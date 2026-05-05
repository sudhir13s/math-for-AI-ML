[Back to Curriculum](../../README.md) | [Previous: Full Dataset Assembly](../04-Full-Dataset-Assembly/notes.md) | [Next: Documentation and Governance](../06-Documentation-and-Governance/notes.md)

---

# Contamination and Dedup Audits

> _"A benchmark score is only evidence if the benchmark was not in the training data."_

## Overview

Deduplication and contamination audits reduce wasted compute, memorization, privacy
risk, and evaluation leakage. In an LLM training run, data is not an inert pile of text;
it is the empirical distribution that defines the examples, losses, risks, and
capabilities the model will see.

This section is written as LaTeX Markdown. Inline mathematics uses `$...$`, and display
equations use `$$...$$`. The goal is to connect data engineering decisions to
mathematical objects such as records $r_i$, token sequences $x_{1:T}$, filters $f(x)$,
hashes $h(x)$, mixture weights $\boldsymbol{\alpha}$, and empirical expectations.

The scope is deliberately narrow: this chapter owns the training-data pipeline.
Tokenizer design, GPU training systems, benchmark methodology, alignment objectives, and
production MLOps each have their own canonical chapters. Here we study the data objects
that those later systems consume.

## Prerequisites

- [Sampling Methods](../../13-ML-Specific-Math/04-Sampling-Methods/notes.md)
- [Scaling Laws](../../15-Math-for-LLMs/08-Scaling-Laws/notes.md)

## Companion Notebooks

| Notebook | Description |
| --- | --- |
| [theory.ipynb](theory.ipynb) | Executable demonstrations for contamination and dedup audits |
| [exercises.ipynb](exercises.ipynb) | Graded practice for contamination and dedup audits |

## Learning Objectives

After completing this section, you will be able to:

- Define exact duplicates, near duplicates, shingles, Jaccard similarity, and contamination
- Implement canonicalization and hash-based exact deduplication
- Implement shingling, MinHash, and LSH-style candidate retrieval
- Audit train/eval overlap through exact and approximate matching
- Explain prompt-only, answer-only, and full-example contamination
- Connect duplicates to memorization and extractable training data
- Design redaction logs for PII and benchmark-removal decisions
- Interpret dedup reports without destroying useful diversity

---

## Table of Contents

- [1. Intuition](#1-intuition)
  - [1.1 Duplicates waste compute](#11-duplicates-waste-compute)
  - [1.2 Near-duplicates increase memorization](#12-nearduplicates-increase-memorization)
  - [1.3 Benchmark leakage inflates evaluation](#13-benchmark-leakage-inflates-evaluation)
  - [1.4 Dedup vs diversity](#14-dedup-vs-diversity)
  - [1.5 Audit trail as scientific evidence](#15-audit-trail-as-scientific-evidence)
- [2. Formal Definitions](#2-formal-definitions)
  - [2.1 Exact duplicate](#21-exact-duplicate)
  - [2.2 Near duplicate](#22-near-duplicate)
  - [2.3 $n$-gram overlap](#23-ngram-overlap)
  - [2.4 Jaccard similarity](#24-jaccard-similarity)
  - [2.5 Contamination relation between train and eval sets](#25-contamination-relation-between-train-and-eval-sets)
- [3. Exact Deduplication](#3-exact-deduplication)
  - [3.1 Canonicalization](#31-canonicalization)
  - [3.2 Hashing](#32-hashing)
  - [3.3 Document-level dedup](#33-documentlevel-dedup)
  - [3.4 Substring dedup](#34-substring-dedup)
  - [3.5 Dedup reports](#35-dedup-reports)
- [4. Fuzzy Deduplication](#4-fuzzy-deduplication)
  - [4.1 Shingling](#41-shingling)
  - [4.2 MinHash](#42-minhash)
  - [4.3 LSH buckets](#43-lsh-buckets)
  - [4.4 Similarity thresholds](#44-similarity-thresholds)
  - [4.5 False merge risks](#45-false-merge-risks)
- [5. Benchmark Contamination Audits](#5-benchmark-contamination-audits)
  - [5.1 Exact benchmark match](#51-exact-benchmark-match)
  - [5.2 Prompt-only contamination](#52-promptonly-contamination)
  - [5.3 Answer leakage](#53-answer-leakage)
  - [5.4 Paraphrase contamination preview](#54-paraphrase-contamination-preview)
  - [5.5 WIMBD-style count/search audit](#55-wimbdstyle-countsearch-audit)
- [6. Memorization and Privacy](#6-memorization-and-privacy)
  - [6.1 Repetition and memorization](#61-repetition-and-memorization)
  - [6.2 PII leakage risk](#62-pii-leakage-risk)
  - [6.3 Extraction attack motivation](#63-extraction-attack-motivation)
  - [6.4 Dedup impact](#64-dedup-impact)
  - [6.5 Redaction logs](#65-redaction-logs)
- [7. Common Mistakes](#7-common-mistakes)
- [8. Exercises](#8-exercises)
- [9. Why This Matters for AI](#9-why-this-matters-for-ai)
- [10. Conceptual Bridge](#10-conceptual-bridge)
- [References](#references)

---

## 1. Intuition

Intuition gives the conceptual and mathematical layer for contamination and dedup
audits. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 1.1 Duplicates waste compute

Duplicates waste compute is part of the canonical scope of contamination and dedup
audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 1.2 Near-duplicates increase memorization

Near-duplicates increase memorization is part of the canonical scope of contamination
and dedup audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 1.3 Benchmark leakage inflates evaluation

Benchmark leakage inflates evaluation is part of the canonical scope of contamination
and dedup audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 1.4 Dedup vs diversity

Dedup vs diversity is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 1.5 Audit trail as scientific evidence

Audit trail as scientific evidence is part of the canonical scope of contamination and
dedup audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 2. Formal Definitions

Formal Definitions gives the conceptual and mathematical layer for contamination and
dedup audits. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 2.1 Exact duplicate

Exact duplicate is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 2.2 Near duplicate

Near duplicate is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 2.3 $n$-gram overlap

$n$-gram overlap is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 2.4 Jaccard similarity

Jaccard similarity is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 2.5 Contamination relation between train and eval sets

Contamination relation between train and eval sets is part of the canonical scope of
contamination and dedup audits. We model the relevant object as a finite collection
$\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token
content $x_i$. The practical question is whether the transformation preserves the
intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 3. Exact Deduplication

Exact Deduplication gives the conceptual and mathematical layer for contamination and
dedup audits. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 3.1 Canonicalization

Canonicalization is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 3.2 Hashing

Hashing is part of the canonical scope of contamination and dedup audits. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 3.3 Document-level dedup

Document-level dedup is part of the canonical scope of contamination and dedup audits.
We model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 3.4 Substring dedup

Substring dedup is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 3.5 Dedup reports

Dedup reports is part of the canonical scope of contamination and dedup audits. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 4. Fuzzy Deduplication

Fuzzy Deduplication gives the conceptual and mathematical layer for contamination and
dedup audits. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 4.1 Shingling

Shingling is part of the canonical scope of contamination and dedup audits. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 4.2 MinHash

MinHash is part of the canonical scope of contamination and dedup audits. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 4.3 LSH buckets

LSH buckets is part of the canonical scope of contamination and dedup audits. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 4.4 Similarity thresholds

Similarity thresholds is part of the canonical scope of contamination and dedup audits.
We model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 4.5 False merge risks

False merge risks is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 5. Benchmark Contamination Audits

Benchmark Contamination Audits gives the conceptual and mathematical layer for
contamination and dedup audits. The local variables in this section should be read as
pipeline objects: documents, records, tokens, filters, weights, shards, and manifests.

### 5.1 Exact benchmark match

Exact benchmark match is part of the canonical scope of contamination and dedup audits.
We model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 5.2 Prompt-only contamination

Prompt-only contamination is part of the canonical scope of contamination and dedup
audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 5.3 Answer leakage

Answer leakage is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 5.4 Paraphrase contamination preview

Paraphrase contamination preview is part of the canonical scope of contamination and
dedup audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 5.5 WIMBD-style count/search audit

WIMBD-style count/search audit is part of the canonical scope of contamination and dedup
audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 6. Memorization and Privacy

Memorization and Privacy gives the conceptual and mathematical layer for contamination
and dedup audits. The local variables in this section should be read as pipeline
objects: documents, records, tokens, filters, weights, shards, and manifests.

### 6.1 Repetition and memorization

Repetition and memorization is part of the canonical scope of contamination and dedup
audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `duplicate`, the invariant should be explicit enough that a checker can fail fast.
If the invariant is only written in a notebook comment or an engineer's memory, it will
not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 6.2 PII leakage risk

PII leakage risk is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `near duplicate`, the invariant should be explicit enough that a checker can fail
fast. If the invariant is only written in a notebook comment or an engineer's memory, it
will not protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 6.3 Extraction attack motivation

Extraction attack motivation is part of the canonical scope of contamination and dedup
audits. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shingle`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 6.4 Dedup impact

Dedup impact is part of the canonical scope of contamination and dedup audits. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `MinHash`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

### 6.5 Redaction logs

Redaction logs is part of the canonical scope of contamination and dedup audits. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `Jaccard`, the invariant should be explicit enough that a checker can fail fast. If
the invariant is only written in a notebook comment or an engineer's memory, it will not
protect a long-running data build.

Examples:
- A small local experiment can store this object in memory; a frontier-scale run must store it as sharded, versioned, validated records.
- The mathematical object is simple, but the operational contract must survive restarts, parallel workers, schema changes, and audits.
- The notebook for this section uses synthetic data so the same ideas can be executed without external files.

Non-examples:
- A path on disk without a manifest is not a reproducible dataset.
- A metric dashboard without record-level lineage is not a provenance system.
- A filter threshold without an audit sample is not evidence of quality.

Implementation consequence: every transformation should report both a count and a rate.
If $n_{\mathrm{in}}$ records enter the stage and $n_{\mathrm{out}}$ records leave, the
acceptance rate is

$$
a = \frac{n_{\mathrm{out}}}{n_{\mathrm{in}}}.
$$

A sudden change in $a$ is a data-drift signal even when the code still runs. This is why
pipeline math is inseparable from logging, manifests, and audit slices.

For LLM work, the token-weighted view is often more important than the document-weighted
view. A filter that removes 5 percent of documents may remove 30 percent of tokens if it
targets long documents. The corresponding token acceptance rate is

$$
a_{\mathrm{tok}} = \frac{\sum_i f(r_i)\,T_i}{\sum_i T_i},
$$

where $T_i$ is the token count or a deterministic token-count estimate. The distinction
matters for compute budgets, mixture proportions, and scaling-law interpretation.

## 7. Common Mistakes

| # | Mistake | Why It Is Wrong | Fix |
| --- | --- | --- | --- |
| 1 | Trusting a file because it exists | A zero-byte or unparsable artifact can still pass a loose path check | Validate content and parseability |
| 2 | Counting documents but not tokens | Long documents dominate compute | Report both document and token rates |
| 3 | Changing schemas without versioning | Old and new records become indistinguishable | Pin schema versions in every record |
| 4 | Dropping metadata during transforms | Audits and removals become impossible | Preserve source and transform lineage |
| 5 | Using nondeterministic ordering | Rebuilds cannot be compared | Seed and record ordering rules |
| 6 | Ignoring failed records | Silent loss can bias the corpus | Quarantine and summarize failures |
| 7 | Treating filters as neutral | Filters encode preferences and tradeoffs | Ablate and audit every major filter |
| 8 | Mixing train and eval sources | Evaluation becomes contaminated | Run overlap audits before release |
| 9 | Optimizing one aggregate score | Small domains can regress | Track slice metrics |
| 10 | Skipping data cards | Users cannot judge intended use or risk | Publish structured documentation |
| 11 | Assuming licenses are uniform | Source terms can conflict | Track license at source and record level |
| 12 | Forgetting reproducible manifests | The same name can refer to different data | Use hashes and version pins |

## 8. Exercises

1. (*) Build a synthetic `duplicate` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
2. (*) Build a synthetic `near duplicate` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
3. (*) Build a synthetic `shingle` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
4. (**) Build a synthetic `MinHash` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
5. (**) Build a synthetic `Jaccard` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
6. (**) Build a synthetic `contamination` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
7. (**) Build a synthetic `memorization` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
8. (***) Build a synthetic `duplicate` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
9. (***) Build a synthetic `near duplicate` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
10. (***) Build a synthetic `shingle` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.

## 9. Why This Matters for AI

| Concept | AI impact |
| --- | --- |
| duplicate | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| near duplicate | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| shingle | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| MinHash | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| Jaccard | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| contamination | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| memorization | Controls what examples, gradients, risks, or audits the model pipeline can represent |

Data pipeline quality is model quality in delayed form. The model eventually converts these records into gradients; any unresolved ambiguity becomes either wasted compute, misleading evaluation, memorization risk, or irreproducible science.

## 10. Conceptual Bridge

This section connects the previous and next pieces of the curriculum as follows:

```text
raw sources -> records -> validation -> assembly -> audits -> documentation -> mixture
```

The next section is [Documentation and Governance](../06-Documentation-and-
Governance/notes.md). It uses the contracts established here and moves one step further
through the LLM data pipeline.

## References

- [DataComp-LM](https://arxiv.org/abs/2406.11794)
- [FineWeb](https://arxiv.org/abs/2406.17557)
- [Dolma](https://arxiv.org/abs/2402.00159)
- [WIMBD](https://arxiv.org/abs/2310.20707)
- [Deduplicating Training Data Makes Language Models Better](https://arxiv.org/abs/2107.06499)
- [DoReMi](https://arxiv.org/abs/2305.10429)
- [Data Cards](https://arxiv.org/abs/2204.01075)
- [A Pretrainer's Guide to Training Data](https://arxiv.org/abs/2305.13169)
- [Hugging Face Datasets loading docs](https://huggingface.co/docs/datasets/loading)
