---
title: "Daily signal: Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses"
description: "A draft SciencesLoop Daily Signal selected from public technical sources for human review."
date: "2026-10-05"
lang: "en"
status: "draft"
featured: false
tags:
  - AI for Science
  - SciencesLoop
  - daily signal
  - technical writing
---

**Daily signal: Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses**

This is an automated SciencesLoop draft. I have not yet reviewed the primary
source in detail, reproduced any result, or checked the claim against a real
scientific workflow.

The signal selected today is [Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses](https://arxiv.org/abs/2610.02267) from arXiv cs.AI.
The source summary available to the scanner is:

> arXiv:2610.02267v1 Announce Type: new Abstract: Agent harnesses make many small, typed decisions per task: which model to call, which tool to use, whether retrieved text is relevant, whether an input carries an injection. System-1 decision models answer such questions in a single forward pass with class probabilities, promising large cost and latency savings over LLM calls. We present a paired evaluation of an open-weight (Laya) and a hosted (Jev) System-1 model on 11 agent decision points built from 18 public sources: 7,283 base cases plus 6,640 robustness variants, with byte-identical inputs, paired tests, and cross-hardware and cross-day reproducibility checks. Jev is significantly more accurate on 9 of 11 decision points (+10.8 to +46.0 pp). Neither model beats chance on zero-shot model routing, and they tie on RAG relevance gating. Laya changes 30% of its answers when the option order is reversed and degrades sharply with many or similar candidates (31% at 50 nearest-neighbour tools, vs. 98% for Jev on items with a unique correct tool). We also audit our own pipeline. Three analysis errors and one design confound distorted headline deployment claims: an omitted pre-screen cost (reported 23.9% saving, actual 4.3%), gate accuracy reported as end-to-end quality (58% vs. 98%), in-sample thresholds (5% target, up to 17% held-out misses), and a "channel effect" on injection false positives that vanishes with channel-native content. Two other suspected confounds did not change the conclusions. All cases, raw outputs and analysis code are available at https://github.com/David-DL-Space/sys1-eval.

## SciencesLoop Signal Card

<section class="signal-card signal-card--compact signal-card--visual" aria-label="SciencesLoop Signal Card">
  <div class="signal-card__top">
    <div>
      <p class="signal-card__eyebrow">Draft workflow assessment</p>
      <h3 class="signal-card__title">Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses</h3>
      <p class="signal-card__summary">
        Automated candidate selected from arXiv cs.AI. Treat this as a
        research lead until the source, claims, and failure modes are reviewed.
      </p>
    </div>
    <span class="signal-card__pill">Daily Signal Draft</span>
  </div>

  <p class="signal-card__stage">
    <span>Workflow stage</span>
    <strong>tool/model -&gt; reproducibility</strong>
  </p>

  <dl class="signal-card__details">
    <div class="signal-card__detail">
      <dt>Signal</dt>
      <dd>Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses</dd>
    </div>
    <div class="signal-card__detail">
      <dt>Run status</dt>
      <dd>Not reviewed or run locally</dd>
    </div>
    <div class="signal-card__detail">
      <dt>Practical test</dt>
      <dd>Run one narrow task with logged tool calls, expected artifacts, failure injection, and a human review gate.</dd>
    </div>
  </dl>

  <ul class="signal-card__metrics" aria-label="Assessment dimensions">
    <li class="signal-metric" data-level="medium">
      <div class="signal-metric__head"><span>Evidence quality</span><span class="signal-metric__level">Needs review</span></div>
    </li>
    <li class="signal-metric" data-level="medium">
      <div class="signal-metric__head"><span>Workflow utility</span><span class="signal-metric__level">Candidate</span></div>
    </li>
    <li class="signal-metric" data-level="low">
      <div class="signal-metric__head"><span>Run status</span><span class="signal-metric__level">Not tested</span></div>
    </li>
    <li class="signal-metric" data-level="risk-medium">
      <div class="signal-metric__head"><span>Hype risk</span><span class="signal-metric__level">Unknown</span></div>
    </li>
  </ul>

  <p class="signal-card__test">
    Early pattern: Turn a model response into a traceable workflow artifact.. Likely failure mode: The workflow may look agentic while hiding state, tool errors, or handoff decisions.
  </p>
</section>

## Why I Would Look At This

The reusable pattern I would inspect first is:

> Turn a model response into a traceable workflow artifact.

That does not make the source a recommendation. It gives the next review step a
shape. For SciencesLoop, the useful question is whether the signal changes one
part of scientific work in a way that can be checked later: the evidence used,
the tool action taken, the artifact produced, or the review gate before a human
acts on it.

## Workflow Stage

My initial classification is **tool/model -> reproducibility**.

This classification may change after reading the source. The point of the draft
is to force an early workflow hypothesis before writing commentary. If the
source only describes a model or product without a testable workflow change, the
right decision is to keep it in the sidecar queue and not publish it.

## Failure Mode To Check

The workflow may look agentic while hiding state, tool errors, or handoff decisions.

This is the first place I would be cautious. Popularity, benchmark language, or
a polished demo can identify a signal worth reading, but they do not prove that
the pattern is useful for scientific work. The review should look for what was
measured, what was omitted, what can be reproduced, and what artifact a
scientist or engineer could inspect afterward.

## Practical Test

Run one narrow task with logged tool calls, expected artifacts, failure injection, and a human review gate.

The smallest useful next step is to turn the source into one checkable task. A
good test should name the input, expected artifact, success criteria, and one
failure case. If that cannot be specified, this signal is probably too vague for
a public Daily Signal.

## What To Review Before Publishing

- Open the primary source and replace this scanner summary with source-checked
  facts.
- Decide whether the post should remain a Daily Signal or become a Technical
  Note.
- Add one concrete scenario, preferably from literature review, materials
  screening, agent evaluation, or scientific MLOps.
- Keep any LinkedIn draft, rejected candidates, and claim checks in the matching
  sidecar note.

Source: [Fast Models, Slow Evidence: A Paired and Self-Audited Evaluation of System-1 Decision Models for LLM Agent Harnesses](https://arxiv.org/abs/2610.02267)
