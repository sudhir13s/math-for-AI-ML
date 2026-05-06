[Back to Curriculum](../../README.md) | [Previous: Data Versioning and Lineage](../01-Data-Versioning-and-Lineage/notes.md) | [Next: Feature Stores and Data Contracts](../03-Feature-Stores-and-Data-Contracts/notes.md)

---

# Experiment Tracking and Reproducibility

> _"An experiment that cannot be replayed is a story, not evidence."_

## Overview

Experiment tracking records the complete evidence trail from configuration to metrics, artifacts, and deployment decisions.

Production ML and MLOps are the mathematical discipline of keeping a learned system useful after it leaves the notebook. The model is only one artifact in a larger graph of data, code, configuration, evaluation, deployment, monitoring, and response actions.

This chapter uses LaTeX Markdown throughout. Inline mathematics uses `$...$`, and display equations use `$$...$$`. The central habit is to turn production behavior into explicit objects: versions, hashes, traces, thresholds, queues, contracts, and release decisions.

## Prerequisites

- [Hyperparameter Optimization](../../08-Optimization/09-Hyperparameter-Optimization/notes.md)
- [Learning Rate Schedules](../../08-Optimization/10-Learning-Rate-Schedules/notes.md)
- [Capability Benchmarks](../../17-Evaluation-and-Reliability/01-Capability-Benchmarks/notes.md)
- [Online Experimentation and AB Testing](../../17-Evaluation-and-Reliability/05-Online-Experimentation-and-AB-Testing/notes.md)

## Companion Notebooks

| Notebook | Description |
| --- | --- |
| [theory.ipynb](theory.ipynb) | Executable demonstrations for experiment tracking and reproducibility |
| [exercises.ipynb](exercises.ipynb) | Graded practice for experiment tracking and reproducibility |

## Learning Objectives

After completing this section, you will be able to:

- Define production ML artifacts using mathematical notation
- Represent dependencies as auditable graphs and contracts
- Compute simple production statistics with synthetic data
- Separate offline evaluation from online monitoring
- Design release gates that combine quality, safety, latency, and cost
- Explain how versioning enables rollback and reproducibility
- Diagnose drift, skew, and production regressions
- Connect LLM traces to evaluations, guardrails, and retraining data
- Identify operational failure modes before they become incidents
- Build lightweight notebook simulations of production ML behavior

---

## Table of Contents

- [1. Intuition](#1-intuition)
  - [1.1 experiments as scientific records](#11-experiments-as-scientific-records)
  - [1.2 why metrics alone are not enough](#12-why-metrics-alone-are-not-enough)
  - [1.3 reproducibility versus repeatability](#13-reproducibility-versus-repeatability)
  - [1.4 comparison tables](#14-comparison-tables)
  - [1.5 experiment debt](#15-experiment-debt)
- [2. Formal Definitions](#2-formal-definitions)
  - [2.1 run $r$](#21-run)
  - [2.2 parameter vector $\boldsymbol{\lambda}$](#22-parameter-vector)
  - [2.3 metric vector $\mathbf{m}$](#23-metric-vector)
  - [2.4 artifact set $\mathcal{A}_r$](#24-artifact-set)
  - [2.5 reproducibility envelope](#25-reproducibility-envelope)
- [3. Experiment Tracking](#3-experiment-tracking)
  - [3.1 parameters and configs](#31-parameters-and-configs)
  - [3.2 metrics and curves](#32-metrics-and-curves)
  - [3.3 artifacts and model registry](#33-artifacts-and-model-registry)
  - [3.4 tags and run hierarchy](#34-tags-and-run-hierarchy)
  - [3.5 search and comparison](#35-search-and-comparison)
- [4. Reproducibility Controls](#4-reproducibility-controls)
  - [4.1 random seeds](#41-random-seeds)
  - [4.2 environment capture](#42-environment-capture)
  - [4.3 dependency locks](#43-dependency-locks)
  - [4.4 hardware nondeterminism](#44-hardware-nondeterminism)
  - [4.5 deterministic replay limits](#45-deterministic-replay-limits)
- [5. Statistical Comparison](#5-statistical-comparison)
  - [5.1 validation variance](#51-validation-variance)
  - [5.2 confidence intervals](#52-confidence-intervals)
  - [5.3 multiple runs](#53-multiple-runs)
  - [5.4 paired comparisons](#54-paired-comparisons)
  - [5.5 leaderboard traps](#55-leaderboard-traps)
- [6. Production Handoff](#6-production-handoff)
  - [6.1 promotion gates](#61-promotion-gates)
  - [6.2 model registry lifecycle](#62-model-registry-lifecycle)
  - [6.3 model cards](#63-model-cards)
  - [6.4 approval metadata](#64-approval-metadata)
  - [6.5 rollback candidates](#65-rollback-candidates)
- [7. LLM and GenAI Tracking](#7-llm-and-genai-tracking)
  - [7.1 prompt versions](#71-prompt-versions)
  - [7.2 evaluation traces](#72-evaluation-traces)
  - [7.3 dataset model prompt triples](#73-dataset-model-prompt-triples)
  - [7.4 token and cost metrics](#74-token-and-cost-metrics)
  - [7.5 judge-version tracking](#75-judgeversion-tracking)
- [8. Common Mistakes](#8-common-mistakes)
- [9. Exercises](#9-exercises)
- [10. Why This Matters for AI](#10-why-this-matters-for-ai)
- [11. Conceptual Bridge](#11-conceptual-bridge)
- [References](#references)

---

## 1. Intuition

Intuition develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 1.1 experiments as scientific records

Experiments as scientific records is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that experiments as scientific records should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of experiments as scientific records in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Experiments as scientific records is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for experiments as scientific records:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of experiments as scientific records executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for experiments as scientific records should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 1.2 why metrics alone are not enough

Why metrics alone are not enough is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that why metrics alone are not enough should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of why metrics alone are not enough in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Why metrics alone are not enough is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for why metrics alone are not enough:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of why metrics alone are not enough executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for why metrics alone are not enough should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 1.3 reproducibility versus repeatability

Reproducibility versus repeatability is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that reproducibility versus repeatability should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of reproducibility versus repeatability in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Reproducibility versus repeatability is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for reproducibility versus repeatability:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of reproducibility versus repeatability executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for reproducibility versus repeatability should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 1.4 comparison tables

Comparison tables is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that comparison tables should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of comparison tables in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Comparison tables is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for comparison tables:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of comparison tables executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for comparison tables should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 1.5 experiment debt

Experiment debt is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that experiment debt should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of experiment debt in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Experiment debt is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for experiment debt:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of experiment debt executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for experiment debt should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 2. Formal Definitions

Formal Definitions develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 2.1 run $r$

Run $r$ is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that run $r$ should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of run $r$ in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Run $r$ is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for run $r$:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of run $r$ executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for run $r$ should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 2.2 parameter vector $\boldsymbol{\lambda}$

Parameter vector $\boldsymbol{\lambda}$ is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that parameter vector $\boldsymbol{\lambda}$ should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of parameter vector $\boldsymbol{\lambda}$ in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Parameter vector $\boldsymbol{\lambda}$ is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for parameter vector $\boldsymbol{\lambda}$:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of parameter vector $\boldsymbol{\lambda}$ executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for parameter vector $\boldsymbol{\lambda}$ should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 2.3 metric vector $\mathbf{m}$

Metric vector $\mathbf{m}$ is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that metric vector $\mathbf{m}$ should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of metric vector $\mathbf{m}$ in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Metric vector $\mathbf{m}$ is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for metric vector $\mathbf{m}$:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of metric vector $\mathbf{m}$ executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for metric vector $\mathbf{m}$ should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 2.4 artifact set $\mathcal{A}_r$

Artifact set $\mathcal{a}_r$ is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that artifact set $\mathcal{a}_r$ should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of artifact set $\mathcal{a}_r$ in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Artifact set $\mathcal{a}_r$ is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for artifact set $\mathcal{a}_r$:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of artifact set $\mathcal{a}_r$ executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for artifact set $\mathcal{a}_r$ should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 2.5 reproducibility envelope

Reproducibility envelope is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that reproducibility envelope should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of reproducibility envelope in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Reproducibility envelope is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for reproducibility envelope:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of reproducibility envelope executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for reproducibility envelope should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 3. Experiment Tracking

Experiment Tracking develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 3.1 parameters and configs

Parameters and configs is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that parameters and configs should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of parameters and configs in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Parameters and configs is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for parameters and configs:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of parameters and configs executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for parameters and configs should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 3.2 metrics and curves

Metrics and curves is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that metrics and curves should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of metrics and curves in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Metrics and curves is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for metrics and curves:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of metrics and curves executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for metrics and curves should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 3.3 artifacts and model registry

Artifacts and model registry is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that artifacts and model registry should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of artifacts and model registry in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Artifacts and model registry is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for artifacts and model registry:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of artifacts and model registry executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for artifacts and model registry should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 3.4 tags and run hierarchy

Tags and run hierarchy is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that tags and run hierarchy should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of tags and run hierarchy in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Tags and run hierarchy is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for tags and run hierarchy:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of tags and run hierarchy executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for tags and run hierarchy should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 3.5 search and comparison

Search and comparison is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that search and comparison should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of search and comparison in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Search and comparison is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for search and comparison:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of search and comparison executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for search and comparison should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 4. Reproducibility Controls

Reproducibility Controls develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 4.1 random seeds

Random seeds is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that random seeds should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of random seeds in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Random seeds is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for random seeds:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of random seeds executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for random seeds should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 4.2 environment capture

Environment capture is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that environment capture should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of environment capture in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Environment capture is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for environment capture:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of environment capture executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for environment capture should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 4.3 dependency locks

Dependency locks is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that dependency locks should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of dependency locks in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Dependency locks is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for dependency locks:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of dependency locks executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for dependency locks should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 4.4 hardware nondeterminism

Hardware nondeterminism is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that hardware nondeterminism should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of hardware nondeterminism in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Hardware nondeterminism is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for hardware nondeterminism:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of hardware nondeterminism executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for hardware nondeterminism should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 4.5 deterministic replay limits

Deterministic replay limits is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that deterministic replay limits should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of deterministic replay limits in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Deterministic replay limits is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for deterministic replay limits:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of deterministic replay limits executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for deterministic replay limits should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 5. Statistical Comparison

Statistical Comparison develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 5.1 validation variance

Validation variance is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that validation variance should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of validation variance in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Validation variance is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for validation variance:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of validation variance executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for validation variance should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 5.2 confidence intervals

Confidence intervals is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that confidence intervals should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of confidence intervals in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Confidence intervals is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for confidence intervals:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of confidence intervals executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for confidence intervals should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 5.3 multiple runs

Multiple runs is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that multiple runs should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of multiple runs in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Multiple runs is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for multiple runs:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of multiple runs executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for multiple runs should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 5.4 paired comparisons

Paired comparisons is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that paired comparisons should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of paired comparisons in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Paired comparisons is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for paired comparisons:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of paired comparisons executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for paired comparisons should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 5.5 leaderboard traps

Leaderboard traps is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that leaderboard traps should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of leaderboard traps in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Leaderboard traps is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for leaderboard traps:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of leaderboard traps executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for leaderboard traps should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 6. Production Handoff

Production Handoff develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 6.1 promotion gates

Promotion gates is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that promotion gates should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of promotion gates in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Promotion gates is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for promotion gates:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of promotion gates executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for promotion gates should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 6.2 model registry lifecycle

Model registry lifecycle is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that model registry lifecycle should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of model registry lifecycle in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Model registry lifecycle is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for model registry lifecycle:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of model registry lifecycle executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for model registry lifecycle should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 6.3 model cards

Model cards is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that model cards should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of model cards in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Model cards is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for model cards:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of model cards executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for model cards should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 6.4 approval metadata

Approval metadata is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that approval metadata should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of approval metadata in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Approval metadata is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for approval metadata:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of approval metadata executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for approval metadata should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 6.5 rollback candidates

Rollback candidates is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that rollback candidates should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of rollback candidates in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Rollback candidates is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for rollback candidates:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of rollback candidates executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for rollback candidates should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 7. LLM and GenAI Tracking

LLM and GenAI Tracking develops the part of experiment tracking and reproducibility assigned by the approved Chapter 19 table of contents. The treatment is production-focused: every idea is connected to a versioned artifact, measurable signal, release decision, or incident response.

### 7.1 prompt versions

Prompt versions is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that prompt versions should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of prompt versions in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Prompt versions is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for prompt versions:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of prompt versions executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for prompt versions should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 7.2 evaluation traces

Evaluation traces is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\Delta = m(r_a)-m(r_b).$$

The formula is intentionally simple. It says that evaluation traces should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of evaluation traces in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Evaluation traces is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for evaluation traces:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of evaluation traces executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for evaluation traces should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 7.3 dataset model prompt triples

Dataset model prompt triples is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$r = (\boldsymbol{\lambda}, s, e, \mathcal{D}_v, c, \mathbf{m}, \mathcal{A}_r).$$

The formula is intentionally simple. It says that dataset model prompt triples should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of dataset model prompt triples in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Dataset model prompt triples is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for dataset model prompt triples:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of dataset model prompt triples executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for dataset model prompt triples should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 7.4 token and cost metrics

Token and cost metrics is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$\bar{m} = \frac{1}{K}\sum_{k=1}^{K}m_k, \qquad \widehat{\operatorname{SE}}(\bar{m}) = \frac{s_m}{\sqrt{K}}.$$

The formula is intentionally simple. It says that token and cost metrics should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of token and cost metrics in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Token and cost metrics is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for token and cost metrics:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of token and cost metrics executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for token and cost metrics should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

### 7.5 judge-version tracking

Judge-version tracking is part of the canonical scope of Experiment Tracking and Reproducibility. In production ML, the useful question is not only whether the model can be trained, but whether the surrounding artifact, signal, or control can be named, versioned, measured, and recovered after a failure.

For this section, the working object is run metadata, reproducibility envelopes, model registries, statistical comparison, and production promotion gates. The notation below treats production systems as mathematical objects because that is how incidents become diagnosable. A dataset, feature, run, trace, or endpoint that lacks a stable identifier cannot be compared across time.

$$E(r) = \{\mathcal{D}_v, c, e, s, H\}.$$

The formula is intentionally simple. It says that judge-version tracking should be reduced to a measurable object before anyone argues about dashboards or tools. Once the object is measurable, the system can decide whether to accept, warn, rollback, retrain, or escalate.

| Production object | Mathematical role | Operational consequence |
| --- | --- | --- |
| Identifier | A stable key in a set or graph | Lets teams join logs, artifacts, and incidents |
| Version | A time-indexed element such as $v_t$ | Makes old and new behavior comparable |
| Metric | A function $m: \mathcal{X} \to \mathbb{R}$ | Turns behavior into a release or alert signal |
| Contract | A predicate $C(\cdot)$ | Rejects invalid inputs before the model absorbs them |
| Owner | A decision variable outside the model | Prevents silent failure after detection |

Examples of judge-version tracking in a real system:

1. A production pipeline records the input version, transformation code hash, model version, and endpoint version before serving predictions.
2. An LLM application logs prompt version, retrieval index version, tool span, latency, token count, and guardrail action for each trace.
3. A release gate compares the candidate model against the current model on quality, safety, latency, and cost before promotion.

Non-examples that often look similar but fail the production contract:

1. A manually named file like `final_dataset.csv` with no hash, schema, lineage, or owner.
2. A metric screenshot pasted into chat without the run id, evaluation dataset, seed, or model artifact.
3. A dashboard alert with no threshold rationale, no escalation rule, and no rollback candidate.

The AI connection is concrete. Modern ML and LLM systems are compound systems: data pipelines, feature stores, model registries, inference servers, retrievers, tools, evaluators, and safety layers. Judge-version tracking is one place where the compound system either becomes observable or becomes technical debt.

Operational checklist for judge-version tracking:

- State the artifact or signal being controlled.
- Give it a stable id and version.
- Define the metric or predicate that decides whether it is valid.
- Log the dependency chain needed to reproduce it.
- Attach an owner and a response action.
- Test the check in continuous integration or release gating.

A useful mental model is to treat every production ML component as a function with preconditions and postconditions. If $u$ is the upstream artifact and $z$ is the downstream artifact, the production question is whether the relation $u \mapsto z$ can be replayed and audited.

$$z = T(u; c, e),$$

where $T$ is the transformation, $c$ is code or configuration, and $e$ is the execution environment. The hidden technical debt appears when any of $u$, $c$, or $e$ is missing from the record.

In notebooks, this subsection will be represented with small synthetic arrays, graphs, traces, or counters rather than external services. The point is not to mimic a vendor tool. The point is to make the mathematics of judge-version tracking executable enough to test.

Boundary note: this chapter assumes the evaluation methods from Chapter 17, the safety policy ideas from Chapter 18, and the data documentation work from Chapter 16. Here we focus on the production machinery that makes those ideas run repeatedly.

Failure analysis for judge-version tracking should be written before the incident occurs. A good production note asks what can be stale, missing, corrupted, delayed, unaudited, or too expensive. Each answer should correspond to one observable signal and one response action.

| Failure question | Production test | Response |
| --- | --- | --- |
| Is the artifact stale? | Compare event time to freshness limit | Warn, block, or backfill |
| Is the artifact malformed? | Evaluate schema and semantic contract | Reject before serving or training |
| Is the artifact inconsistent? | Compare current statistic with reference statistic | Investigate drift or skew |
| Is the artifact unauditable? | Check for missing version, owner, or lineage edge | Stop promotion until metadata exists |
| Is the artifact too costly? | Track latency, tokens, storage, or compute | Route, cache, batch, or downscale |

The production design pattern is therefore not just to calculate a value. It is to calculate a value, compare it with a declared rule, log the evidence, and make the next action unambiguous. That four-step pattern will reappear across all Chapter 19 notebooks.

## 8. Common Mistakes

| # | Mistake | Why It Is Wrong | Fix |
| --- | --- | --- | --- |
| 1 | Treating production metadata as optional | Without metadata, failures cannot be attributed to a dataset, run, endpoint, prompt, or release. | Make identifiers, hashes, versions, and owners part of the production contract. |
| 2 | Optimizing one metric in isolation | Single metrics hide tail latency, subgroup failure, safety regressions, and cost explosions. | Use metric hierarchies with guardrails and release gates. |
| 3 | Comparing runs without controlling variance | A one-run improvement can be noise, seed luck, or validation leakage. | Use repeated runs, confidence intervals, paired comparisons, and frozen evaluation sets. |
| 4 | Letting dashboards replace decisions | A dashboard can display signals without encoding what action should follow. | Tie every alert to an owner, severity, runbook, and rollback or retraining policy. |
| 5 | Ignoring training-serving skew | The model learns one feature distribution and serves on another. | Use shared transformations, point-in-time joins, contract tests, and skew monitors. |
| 6 | Deploying without rollback evidence | A rollback is impossible if the previous artifacts and dependencies are not recoverable. | Keep model, data, config, endpoint, and environment versions in the registry. |
| 7 | Using raw thresholds without calibration | Bad thresholds create alert floods or missed incidents. | Tune thresholds on historical incidents and measure false positives and false negatives. |
| 8 | Conflating evaluation, monitoring, and alignment | Offline evals, online telemetry, and safety policy answer different questions. | Keep chapter boundaries clear and connect them through release gates. |
| 9 | Forgetting cost as a reliability metric | A system that is accurate but unaffordable fails in production. | Track tokens, GPU time, cache hit rate, and cost per successful task. |
| 10 | Overfitting production fixes to one incident | A narrow patch can pass the incident case while worsening the broader distribution. | Convert incidents into regression tests, then run full capability and safety suites. |

## 9. Exercises

1. (*) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

2. (*) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

3. (*) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

4. (**) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

5. (**) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

6. (**) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

7. (***) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

8. (***) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

9. (***) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

10. (***) Design a production ML check related to experiment tracking and reproducibility.
   - (a) Define the object being checked using mathematical notation.
   - (b) State the metric, predicate, or threshold used to decide pass/fail.
   - (c) Explain which artifact versions must be logged.
   - (d) Give one failure case and one rollback or escalation action.

## 10. Why This Matters for AI

| Concept | AI Impact |
| --- | --- |
| Versioned artifacts | Make model behavior reproducible after a production incident |
| Lineage graphs | Reveal which upstream data, prompt, feature, or code change caused a downstream regression |
| Release gates | Prevent models from shipping on quality alone while safety, latency, or cost fails |
| Drift statistics | Convert changing user behavior into measurable maintenance signals |
| LLM traces | Explain failures across prompts, retrieval, tools, guardrails, and generated responses |
| Contracts | Catch invalid data before it silently corrupts training or serving |
| Registries | Preserve rollback candidates and promotion evidence |
| Observability | Turns production behavior into data for future evaluation and retraining |

## 11. Conceptual Bridge

Experiment Tracking and Reproducibility sits after the chapters on data construction, evaluation, and alignment because production systems combine all three. Chapter 16 explains how reliable datasets are assembled. Chapter 17 explains how models are measured. Chapter 18 explains how desired behavior and safety constraints are specified. Chapter 19 asks whether those ideas survive contact with changing data, users, services, and costs.

The backward bridge is operational memory. If a model fails today, the team must recover the data, code, environment, model, endpoint, prompt, retriever, guardrail, and metric definitions that produced the behavior. That is why the notation in this chapter emphasizes hashes, graphs, traces, thresholds, and predicates.

The forward bridge is broader mathematical maturity. Later chapters return to signal processing, learning theory, causal inference, game theory, measure theory, and geometry. Production ML uses those ideas under constraints: bounded latency, incomplete labels, shifting distributions, and costly human attention.

```text
+--------------------------------------------------------------+
| Chapter 16: data construction and governance                 |
| Chapter 17: evaluation and reliability                       |
| Chapter 18: alignment and safety                             |
| Chapter 19: production ML and MLOps                          |
|   artifact -> endpoint -> telemetry -> alert -> retrain      |
| Chapter 20+: mathematical tools for deeper modeling          |
+--------------------------------------------------------------+
```

## References

- MLflow. Model registry tutorial and experiment tracking documentation. https://www.mlflow.org/docs/latest/ml/model-registry/tutorial
- Kubeflow. Pipelines concepts. https://www.kubeflow.org/docs/components/pipelines/concepts/pipeline/
- Mitchell et al.. Model Cards for Model Reporting. https://arxiv.org/abs/1810.03993
- Google Cloud. MLOps continuous delivery for ML. https://cloud.google.com/solutions/machine-learning/mlops-continuous-delivery-and-automation-pipelines-in-machine-learning
