---
title: "Daily signal: OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows"
description: "A draft SciencesLoop Daily Signal selected from public technical sources for human review."
date: "2026-09-11"
lang: "en"
status: "draft"
featured: false
tags:
  - AI for Science
  - SciencesLoop
  - daily signal
  - technical writing
---

**Daily signal: OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows**

This is an automated SciencesLoop draft. I have not yet reviewed the primary
source in detail, reproduced any result, or checked the claim against a real
scientific workflow.

The signal selected today is [OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows](https://arxiv.org/abs/2609.09203) from arXiv cs.AI.
The source summary available to the scanner is:

> arXiv:2609.09203v1 Announce Type: new Abstract: Existing benchmarks for autonomous AI scientists evaluate only final outputs---generated code, hypotheses, or papers---yet discard the reasoning process by which those outputs were obtained. This makes it impossible to audit scientific methodology, diagnose failure modes, or distinguish systematic reasoning from fortunate guessing. We present \textbf{OpenDiscoveryTrace}, a public dataset of 558 complete AI scientific agent trajectories that captures how models reason, not just what they produce. Each trajectory records a structured 9-field-per-step trace---including thoughts, tool calls, observations, errors, revision triggers, and self-reported confidence---as models execute 124 scientific tasks spanning drug discovery, materials science, genomics, and scientific literature analysis. The dataset covers seven models: three frontier models (GPT-5.4, Claude Opus 4.6, and Gemini 3.1 Pro; 124 trajectories each, fully balanced across domains and difficulty levels) and four open-weight models (Qwen2.5-7B, Mistral-7B-v0.3, Phi-3.5-mini, and Qwen2.5-1.5B; 30 each), plus 60 live-retrieval variant trajectories. Pilot analysis on 363 LLM-judged trajectories reveals that process traces expose behavioral differences invisible to output-only evaluation: all three frontier models achieve comparable success rates (84--89%), yet Claude Opus 4.6 produces 30$\times$ more errors than GPT-5.4 (2.5 vs. 0.08 per trajectory, $p < 0.0001$, Cliff's $\delta = 0.613$), with qualitatively different error profiles---66.7% tool misuse for Claude versus 83.6% reasoning errors for GPT-5.4. We define five benchmark tasks with baselines from logistic regression, random forests, LSTMs, and Transformer models. The dataset, trace schema, agent harness, and benchmark definitions are publicly available under CC BY 4.0 to support research on process-level evaluation, scientific agent auditing, and AI governance.

## SciencesLoop Signal Card

<section class="signal-card signal-card--compact signal-card--visual" aria-label="SciencesLoop Signal Card">
  <div class="signal-card__top">
    <div>
      <p class="signal-card__eyebrow">Draft workflow assessment</p>
      <h3 class="signal-card__title">OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows</h3>
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
      <dd>OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows</dd>
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

Source: [OpenDiscoveryTrace: Process Traces for Evaluating AI Scientist Workflows](https://arxiv.org/abs/2609.09203)
