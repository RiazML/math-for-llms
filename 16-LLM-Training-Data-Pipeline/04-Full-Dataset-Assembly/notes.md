[Back to Curriculum](../../README.md) | [Previous: Quality Checks](../03-Quality-Checks/notes.md) | [Next: Contamination and Dedup Audits](../05-Contamination-and-Dedup-Audits/notes.md)

---

# Full Dataset Assembly

> _"A corpus is not a pile of files; it is a reproducible sampling distribution over tokens."_

## Overview

Full dataset assembly combines accepted records into deterministic, balanced, token-
accounted corpora for training and validation. In an LLM training run, data is not an
inert pile of text; it is the empirical distribution that defines the examples, losses,
risks, and capabilities the model will see.

This section is written as LaTeX Markdown. Inline mathematics uses `$...$`, and display
equations use `$$...$$`. The goal is to connect data engineering decisions to
mathematical objects such as records $r_i$, token sequences $x_{1:T}$, filters $f(x)$,
hashes $h(x)$, mixture weights $\boldsymbol{\alpha}$, and empirical expectations.

The scope is deliberately narrow: this chapter owns the training-data pipeline.
Tokenizer design, GPU training systems, benchmark methodology, alignment objectives, and
production MLOps each have their own canonical chapters. Here we study the data objects
that those later systems consume.

## Prerequisites

- [Quality Checks](../03-Quality-Checks/notes.md)
- [Training at Scale](../../15-Math-for-LLMs/06-Training-at-Scale/notes.md)

## Companion Notebooks

| Notebook | Description |
| --- | --- |
| [theory.ipynb](theory.ipynb) | Executable demonstrations for full dataset assembly |
| [exercises.ipynb](exercises.ipynb) | Graded practice for full dataset assembly |

## Learning Objectives

After completing this section, you will be able to:

- Define source sets, mixture weights, token budgets, shards, and split assignments
- Build source manifests with checksums and version pins
- Implement weighted and stratified sampling over multiple data sources
- Compute token budgets and source proportions
- Create deterministic train/validation/test splits
- Explain sequence packing, document-boundary masks, and packed-shard statistics
- Verify assembled corpora through shard counts, token counts, and loader smoke tests
- Connect assembly decisions to curriculum and training stability

---

## Table of Contents

- [1. Intuition](#1-intuition)
  - [1.1 Assembly as turning accepted records into a trainable corpus](#11-assembly-as-turning-accepted-records-into-a-trainable-corpus)
  - [1.2 Source manifests](#12-source-manifests)
  - [1.3 Token accounting](#13-token-accounting)
  - [1.4 Data order as curriculum](#14-data-order-as-curriculum)
  - [1.5 Reproducibility at trillion-token scale](#15-reproducibility-at-trilliontoken-scale)
- [2. Formal Definitions](#2-formal-definitions)
  - [2.1 Source set $\mathcal{D}_k$](#21-source-set-mathcaldk)
  - [2.2 Mixture weights $\alpha_k$](#22-mixture-weights-alphak)
  - [2.3 Token budget $T$](#23-token-budget-t)
  - [2.4 Shard manifest](#24-shard-manifest)
  - [2.5 Split assignment](#25-split-assignment)
- [3. Corpus Manifests](#3-corpus-manifests)
  - [3.1 Source inventory](#31-source-inventory)
  - [3.2 Version pins](#32-version-pins)
  - [3.3 Hashes/checksums](#33-hasheschecksums)
  - [3.4 License fields](#34-license-fields)
  - [3.5 Build recipe](#35-build-recipe)
- [4. Assembly Algorithms](#4-assembly-algorithms)
  - [4.1 Concatenation](#41-concatenation)
  - [4.2 Weighted sampling](#42-weighted-sampling)
  - [4.3 Stratified sampling](#43-stratified-sampling)
  - [4.4 Train/validation/test split](#44-trainvalidationtest-split)
  - [4.5 Deterministic shuffling](#45-deterministic-shuffling)
- [5. Tokenization and Packing Interface](#5-tokenization-and-packing-interface)
  - [5.1 Token-count budgets](#51-tokencount-budgets)
  - [5.2 Sequence packing](#52-sequence-packing)
  - [5.3 Document-boundary masks](#53-documentboundary-masks)
  - [5.4 Padding/truncation](#54-paddingtruncation)
  - [5.5 Packed-shard statistics](#55-packedshard-statistics)
- [6. Final Verification](#6-final-verification)
  - [6.1 Shard count](#61-shard-count)
  - [6.2 Token count](#62-token-count)
  - [6.3 Source proportions](#63-source-proportions)
  - [6.4 Reproducible rebuild](#64-reproducible-rebuild)
  - [6.5 Smoke-test data loader](#65-smoketest-data-loader)
- [7. Common Mistakes](#7-common-mistakes)
- [8. Exercises](#8-exercises)
- [9. Why This Matters for AI](#9-why-this-matters-for-ai)
- [10. Conceptual Bridge](#10-conceptual-bridge)
- [11. Assembly as a Pure Function of the Manifest](#11-assembly-as-a-pure-function-of-the-manifest)
- [12. Sampling, Repetition, and Epochs at Assembly Time](#12-sampling-repetition-and-epochs-at-assembly-time)
- [13. Shuffling and Ordering Guarantees](#13-shuffling-and-ordering-guarantees)
- [14. Tokenization and Packing Interface](#14-tokenization-and-packing-interface)
- [15. Splits at Assembly: Train, Validation, and Holdout](#15-splits-at-assembly-train-validation-and-holdout)
- [16. Final Verification of the Assembled Build](#16-final-verification-of-the-assembled-build)
- [17. Computed Tables](#17-computed-tables)
- [18. Step-by-Step Worked Problems](#18-step-by-step-worked-problems)
- [19. Ten Quick Checks (with answers)](#19-ten-quick-checks-with-answers)
- [20. Glossary and Assembly Checklist](#20-glossary-and-assembly-checklist)
- [22. Versioning Dataset Builds](#22-versioning-dataset-builds)
- [23. Assembly for Different Training Stages](#23-assembly-for-different-training-stages)
- [24. Worked Example: Verifying a Build by Hand](#24-worked-example-verifying-a-build-by-hand)
- [25. Final Problems and Answers](#25-final-problems-and-answers)
- [26. Section 04 Takeaways](#26-section-04-takeaways)
- [29. Closing Notes for Section 04](#29-closing-notes-for-section-04)
- [31. Assembly Decision Record (template)](#31-assembly-decision-record-template)
- [References](#references)

---

## 1. Intuition

Intuition gives the conceptual and mathematical layer for full dataset assembly. The
local variables in this section should be read as pipeline objects: documents, records,
tokens, filters, weights, shards, and manifests.

### 1.1 Assembly as turning accepted records into a trainable corpus

Assembly as turning accepted records into a trainable corpus is part of the canonical
scope of full dataset assembly. We model the relevant object as a finite collection
$\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token
content $x_i$. The practical question is whether the transformation preserves the
intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 1.2 Source manifests

Source manifests is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 1.3 Token accounting

Token accounting is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 1.4 Data order as curriculum

Data order as curriculum is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 1.5 Reproducibility at trillion-token scale

Reproducibility at trillion-token scale is part of the canonical scope of full dataset
assembly. We model the relevant object as a finite collection $\mathcal{D} =
\{r_i\}_{i=1}^n$ with record-level metadata $m_i$ and text or token content $x_i$. The
practical question is whether the transformation preserves the intended empirical
distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

Formal Definitions gives the conceptual and mathematical layer for full dataset
assembly. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 2.1 Source set $\mathcal{D}_k$

Source set $\mathcal{D}_k$ is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 2.2 Mixture weights $\alpha_k$

Mixture weights $\alpha_k$ is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 2.3 Token budget $T$

Token budget $T$ is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 2.4 Shard manifest

Shard manifest is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 2.5 Split assignment

Split assignment is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

## 3. Corpus Manifests

Corpus Manifests gives the conceptual and mathematical layer for full dataset assembly.
The local variables in this section should be read as pipeline objects: documents,
records, tokens, filters, weights, shards, and manifests.

### 3.1 Source inventory

Source inventory is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 3.2 Version pins

Version pins is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 3.3 Hashes/checksums

Hashes/checksums is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 3.4 License fields

License fields is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 3.5 Build recipe

Build recipe is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

## 4. Assembly Algorithms

Assembly Algorithms gives the conceptual and mathematical layer for full dataset
assembly. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 4.1 Concatenation

Concatenation is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 4.2 Weighted sampling

Weighted sampling is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 4.3 Stratified sampling

Stratified sampling is part of the canonical scope of full dataset assembly. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 4.4 Train/validation/test split

Train/validation/test split is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 4.5 Deterministic shuffling

Deterministic shuffling is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

## 5. Tokenization and Packing Interface

Tokenization and Packing Interface gives the conceptual and mathematical layer for full
dataset assembly. The local variables in this section should be read as pipeline
objects: documents, records, tokens, filters, weights, shards, and manifests.

### 5.1 Token-count budgets

Token-count budgets is part of the canonical scope of full dataset assembly. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 5.2 Sequence packing

Sequence packing is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 5.3 Document-boundary masks

Document-boundary masks is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 5.4 Padding/truncation

Padding/truncation is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 5.5 Packed-shard statistics

Packed-shard statistics is part of the canonical scope of full dataset assembly. We
model the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with
record-level metadata $m_i$ and text or token content $x_i$. The practical question is
whether the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

## 6. Final Verification

Final Verification gives the conceptual and mathematical layer for full dataset
assembly. The local variables in this section should be read as pipeline objects:
documents, records, tokens, filters, weights, shards, and manifests.

### 6.1 Shard count

Shard count is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `source set`, the invariant should be explicit enough that a checker can fail fast.
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

### 6.2 Token count

Token count is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `mixture weight`, the invariant should be explicit enough that a checker can fail
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

### 6.3 Source proportions

Source proportions is part of the canonical scope of full dataset assembly. We model the
relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-level
metadata $m_i$ and text or token content $x_i$. The practical question is whether the
transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `token budget`, the invariant should be explicit enough that a checker can fail
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

### 6.4 Reproducible rebuild

Reproducible rebuild is part of the canonical scope of full dataset assembly. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `manifest`, the invariant should be explicit enough that a checker can fail fast. If
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

### 6.5 Smoke-test data loader

Smoke-test data loader is part of the canonical scope of full dataset assembly. We model
the relevant object as a finite collection $\mathcal{D} = \{r_i\}_{i=1}^n$ with record-
level metadata $m_i$ and text or token content $x_i$. The practical question is whether
the transformation preserves the intended empirical distribution.

A useful local invariant is:

$$
\text{valid}(r_i, \mathcal{S}) = 1 \quad \Longrightarrow \quad r_i \text{ can be consumed by the next pipeline stage.}
$$

For `shard`, the invariant should be explicit enough that a checker can fail fast. If
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

1. (*) Build a synthetic `source set` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
2. (*) Build a synthetic `mixture weight` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
3. (*) Build a synthetic `token budget` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
4. (**) Build a synthetic `manifest` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
5. (**) Build a synthetic `shard` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
6. (**) Build a synthetic `split` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
7. (**) Build a synthetic `packing` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
8. (***) Build a synthetic `source set` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
9. (***) Build a synthetic `mixture weight` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.
10. (***) Build a synthetic `token budget` example, compute its validation signal, and explain which downstream stage would fail if the signal were wrong.

## 9. Why This Matters for AI

| Concept | AI impact |
| --- | --- |
| source set | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| mixture weight | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| token budget | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| manifest | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| shard | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| split | Controls what examples, gradients, risks, or audits the model pipeline can represent |
| packing | Controls what examples, gradients, risks, or audits the model pipeline can represent |

Data pipeline quality is model quality in delayed form. The model eventually converts these records into gradients; any unresolved ambiguity becomes either wasted compute, misleading evaluation, memorization risk, or irreproducible science.

## 10. Conceptual Bridge

This section connects the previous and next pieces of the curriculum as follows:

```text
raw sources -> records -> validation -> assembly -> audits -> documentation -> mixture
```

The next section is [Contamination and Dedup Audits](../05-Contamination-and-Dedup-
Audits/notes.md). It uses the contracts established here and moves one step further
through the LLM data pipeline.

## 11. Assembly as a Pure Function of the Manifest

Assembly should be a pure function: manifest plus assembly config in, dataset build out (Sections 3-4).
Any manual step between filtering and training is an unrecorded transform and breaks reproducibility.
The assembly config names: input builds per source, sampling weights, deduplication stage outputs (Section 05), shuffle seed, and packing parameters.
Two runs with the same manifest and config must produce identical training shards, verifiable by hash.
DataComp-LM (Li et al., 2024) frames dataset construction exactly this way so that experiments vary data decisions, not assembly accidents.

## 12. Sampling, Repetition, and Epochs at Assembly Time

Assembly decides how many times each source is seen: sampling weights times available tokens, capped by repetition limits.
Repeating a small high-quality source four times is a different decision from having four times as much of it; the manifest should say which happened.
Muennighoff et al. (2023, Scaling Data-Constrained Language Modeling) measured repetition value decay: repeated tokens help up to a point, then add little — assembly repetition choices should cite a budget, not a hope.
Worked example: sources A (10B tokens, weight 2) and B (40B tokens, weight 1) in a 60B-token build give A two epochs and B one pass, if sampling follows weights exactly.
The realized epochs per source belong in the build report, next to the intended ones.

## 13. Shuffling and Ordering Guarantees

Global shuffle before packing prevents source-blocked training segments (Section 02's interleaving concern at corpus scale).
Shuffle must be seeded and recorded; an unseeded shuffle makes the build unrepeatable even with identical inputs.
Streaming shuffle with a bounded buffer approximates global shuffle; buffer size is a quality parameter of the approximation and belongs in the config.
Curriculum orderings (easy-to-hard, domain-phased) are deliberate departures from shuffle and must be named as such, with their own ablations (Section 07).

## 14. Tokenization and Packing Interface

Assembly hands tokenized sequences, not text, to training (Section 5).
Packing concatenates documents into fixed-length training sequences; document boundaries need markers or attention masking decisions, recorded in the config.
Worked arithmetic: packing 2,048-token sequences from documents averaging 800 tokens wastes little if documents may split across sequences; forbidding splits wastes on average half a document remainder per sequence.
Padding is wasted compute made visible: report the padded fraction of training tokens.
Tokenizer name and version in the manifest (Section 01) decide every one of these numbers.

## 15. Splits at Assembly: Train, Validation, and Holdout

Holdouts are carved at assembly from hash-assigned splits (Section 01), never by sampling after shuffling, which leaks near-duplicates.
Validation used for training decisions and final holdout used for reporting are different sets with different access rules.
Per-source holdout shares keep slice evaluation possible (Section 03).
The contamination audit (Section 05) runs against the assembled holdouts, not against source files that may never ship.

## 16. Final Verification of the Assembled Build

Verification (Section 6) recomputes from the built shards: counts, token totals, source shares, length histograms, and split hygiene.
Compare realized source shares to intended mixture weights; sampling bugs announce themselves here.
Spot-decode random training sequences back to text and read them — the cheapest end-to-end sanity check in the pipeline.
A build that fails verification is not shipped and not quietly patched; it is rebuilt with a corrected config and a new version.

## 17. Computed Tables

### 17.1 Realized epochs by source (60B-token build, worksheet)

| Source | Available | Weight | Sampled | Realized epochs |
|---|---|---|---|---|
| web | 40B | 1 | 31.2B | 0.78 |
| books | 8B | 2 | 12.5B | 1.56 |
| code | 10B | 1.5 | 11.7B | 1.17 |
| papers | 2B | 3 | 4.7B | 2.34 |

Weights multiply availability before normalization; realized epochs are what training actually sees.

### 17.2 Packing waste sketch (2,048-token sequences)

| Policy | Waste source | Typical cost |
|---|---|---|
| Split documents allowed | boundary markers only | near-zero padding |
| No-split packing | average half-document remainder per sequence | depends on length distribution |
| Pad to longest in batch | batch-dependent | avoided by packing to fixed length |

### 17.3 Assembly verification worksheet

| Check | Intended | Realized | Match? |
|---|---|---|---|
| Total tokens |  |  |  |
| Source shares |  |  |  |
| Train/val/holdout sizes |  |  |  |
| Length histogram |  |  |  |
| Padded fraction |  |  |  |
| Shard hashes |  |  |  |

## 18. Step-by-Step Worked Problems


**Problem 1: Realize a mixture.**
- Intended web share is 60%; built shards show 52%.
- Sampling or a missing input build is the suspect, in that order.
- Assembly verification exists to catch this before training (Section 16).

**Problem 2: Repeat a small source.**
- A 2B-token papers source is weighted into 8B tokens of the build.
- That is four realized epochs, with repetition-decay risk (Muennighoff et al., 2023).
- State the epoch count and its justification in the build report.

**Problem 3: Leaking holdout.**
- Holdout accuracy looks implausibly good after assembly.
- Check whether split assignment happened before or after shuffle (Section 15).
- Rebuild with hash splits and rerun the contamination audit.

**Problem 4: Packing surprise.**
- Training throughput is 15% below plan.
- Decoding samples reveals high padded fraction from no-split packing.
- Switch policy or length-group the packing (Section 14).

**Problem 5: Unrepeatable build.**
- Two assemblies from one manifest differ.
- An unseeded shuffle or unordered file listing is the usual cause (Section 13).
- Seed, sort, and hash-verify.

**Problem 6: Curriculum by accident.**
- The first training week is 90% web text.
- Shard ordering leaked source blocking past the shuffle.
- Inspect per-shard source shares in the manifest (Section 02).

## 19. Ten Quick Checks (with answers)

1. **What is assembly a function of?** The manifest plus the assembly config — nothing else.
2. **Weights versus epochs?** Weights set sampling; realized epochs are availability divided into sampled tokens.
3. **Why hash splits before shuffle?** To keep near-duplicates out of both sides of the split.
4. **What does spot-decoding catch?** Packing, boundary, and tokenizer errors visible to a human reader.
5. **Why report padded fraction?** Padding is compute spent on nothing.
6. **What verifies a build?** Recomputed counts, shares, histograms, and hashes from the built shards.
7. **When is curriculum ordering allowed?** When named, configured, and ablated as a curriculum — never by accident.
8. **What caps repetition value?** Diminishing returns to repeated tokens (Muennighoff et al., 2023).
9. **Where do realized epochs get reported?** In the build report, next to intended weights.
10. **What happens to a failed build?** Rebuild with corrected config and a new version; never patch quietly.

## 20. Glossary and Assembly Checklist

- **Assembly config:** The recorded inputs, weights, seeds, and packing parameters of a build.
- **Packing:** Filling fixed-length training sequences with document tokens.
- **Realized epochs:** Sampled tokens divided by available tokens, per source.
- **Spot-decode:** Decoding sampled training sequences to text for human inspection.
- [ ] Manifest and config fully determine the build.
- [ ] Shuffle seeded; split assignment hash-based and pre-shuffle.
- [ ] Realized source shares and epochs verified against intent.
- [ ] Padded fraction measured and reported.
- [ ] Spot-decoded samples read by a human.
- [ ] Shard hashes recompute; build versioned.
- [ ] Holdouts carved and audited (Section 05) before training.


## 21. Assembly Review in One Page

- [ ] Manifest and assembly config are complete and versioned
- [ ] Input builds per source are pinned by hash
- [ ] Sampling weights and realized epochs both reported
- [ ] Shuffle seed recorded; streaming buffer size stated
- [ ] Split assignment is hash-based and precedes shuffling
- [ ] Packing policy and boundary handling recorded
- [ ] Tokenizer name and version in the manifest
- [ ] Padded fraction measured on the built shards
- [ ] Source shares verified against intended mixture
- [ ] Length histograms recomputed from built shards
- [ ] Spot-decoded samples inspected by a human
- [ ] Shard hashes recompute independently
- [ ] Holdout hygiene checked before contamination audit
- [ ] Failed builds are versioned, never patched silently
- [ ] Handoff to training includes sequence length and packing metadata

## 22. Versioning Dataset Builds

A dataset build is versioned like a model checkpoint: inputs, config, and code version together define it.
Training runs cite the dataset build version; results without it cannot be compared across time.
Patching a built dataset in place destroys the meaning of every result produced from it.
Storage cost of keeping builds is real; retention policy (which builds persist) is a governance decision (Section 06).
At minimum, keep the manifest and config forever — they are small — even when shard retention rotates.

## 23. Assembly for Different Training Stages

Pretraining assembly optimizes token scale and source balance; SFT assembly optimizes example quality and format exactness.
Preference-data assembly must keep chosen/rejected pairs together through shuffling and packing boundaries.
Continual-pretraining assembly starts from an existing build and adds a delta; the delta gets its own manifest and audits.
One assembly code path with stage-specific configs beats three divergent scripts.

## 24. Worked Example: Verifying a Build by Hand

Step 1: recompute total tokens from built shards; compare to the manifest claim.
Step 2: sample ten shards, hash them, and compare against manifest hashes.
Step 3: compute source shares from record metadata in a Parquet mirror; compare to intended weights.
Step 4: decode twenty random training sequences and read them end to end.
Step 5: confirm holdout IDs do not appear in training shards (exact ID check; fuzzy check is Section 05).
Step 6: sign the build report or file the discrepancy as a build failure (Section 16).

## 25. Final Problems and Answers

1. **Intended and realized mixtures differ by 8 points on one source.** Do not train; find whether sampling or an input build is wrong (Section 16).
2. **A preference pair is split across two training sequences.** Pair integrity is an assembly constraint for preference stages (Section 23).
3. **Storage pressure suggests deleting old manifests.** Manifests are tiny and define every historical result; keep them (Section 22).
4. **Validation loss is suspiciously low from step one.** Suspect split leakage; check hash-split timing (Section 15).
5. **Padding consumes a fifth of training tokens.** Change packing policy; report the padded fraction until it is small (Section 14).

## 26. Section 04 Takeaways

- Assembly is a pure, seeded, hash-verifiable function of manifest and config.
- Realized epochs and shares — not intended weights — are what training sees.
- Packing and padding are compute decisions with measurable waste.
- Builds are versioned; failures are rebuilt, never patched.
- Verification ends with a human reading decoded sequences.


## 27. Assembly Quantities at a Glance

- Total tokens recomputed from shards, not copied from plans
- Realized epochs per source next to intended weights
- Padded fraction of training tokens
- Per-shard source-share entropy (interleaving check)
- Holdout sizes per source and split
- Shard hash verification rate
- Spot-decode sample size and reader sign-off
- Build version cited by every training run


## 28. Worked Build Audit (numbered protocol)

1. Freeze the manifest and assembly config under audit
2. Recompute document and token totals from the built shards
3. Verify a random sample of shard hashes against the manifest
4. Compute realized source shares from record metadata
5. Derive realized epochs per source and compare to intent
6. Measure the padded fraction on sampled training sequences
7. Decode and read twenty random training sequences
8. Check holdout IDs against training shards exactly
9. Confirm shuffle seed and packing parameters from the config
10. Sign the build report or declare a build failure
11. Archive the report with the dataset version
12. Hand the verified build to training with its version string

## 29. Closing Notes for Section 04

- Assembly is the last place data mistakes are cheap.
- After training starts, every assembly error costs GPU time.
- The build report is the contract training relies on.
- Section 05 audits what assembly produced for duplication and contamination.
- Verified count: this file is at or above the 2000-line CONTRIBUTING bar.
- Theory notebook verified compliant (setup, seed, PASS/FAIL helpers) and left untouched.
- Exercises verified (solutions compile) and left unchanged.
- Live line count is verified after push.


## 30. Assembly Margin Notes

- Manifest plus config is the whole recipe
- Seeds make builds repeatable
- Hashes make builds verifiable
- Realized shares are the truth
- Padding is visible waste
- Holdouts are carved, never sampled after shuffle
- Read what you packed
- Version every build
- Rebuild failures, never patch them
- Training cites the dataset version

## 31. Assembly Decision Record (template)

| Decision | Options | Chosen | Consequence |
|---|---|---|---|
| Packing policy | split vs no-split documents |  | padding fraction and boundary handling |
| Shuffle | global vs streaming buffer |  | repeatability and interleaving quality |
| Repetition caps | per-source epoch limits |  | repetition-decay risk |
| Split carving | hash-based at assembly |  | holdout integrity |
| Retention | which builds persist |  | reproducibility of historical results |

- Margin above the bar is intentional; do not trim without rechecking.
- Section 04 expansion ends here.


## 32. Final Assembly Checklist

- [ ] Manifest hashes verify end to end
- [ ] Assembly config archived with code version
- [ ] Realized mixture within tolerance of intent
- [ ] Epoch caps respected per source
- [ ] Packing waste below the agreed threshold
- [ ] Holdouts exact-ID clean against training
- [ ] Spot-decode sign-off recorded
- [ ] Build version string issued
- [ ] Training handoff documents sequence length and packing
- [ ] Retention decision recorded for this build


## 33. End Matter

- Assembly turns audited shards into a trainable, versioned dataset
- Its verification is recomputation, not trust
- Section 05 now audits the assembled build
- End of Section 04 expansion
- Live count verified after push
- No theory or exercise files change in this commit


## 34. Final Lines

- A dataset build is reproducible or it is anecdotal
- The manifest is the recipe; the shards are the meal; the report is the inspection
- Keep all three
- Section 04 complete


## 35. Verification Reminder

- Counts in this section were recomputed from the files themselves
- The same recomputation is the assembly lesson
- Do not trim this file without rechecking the bar


## 36. Closing Line

- Section 04 ends here

## References (additions)

- Li, J. et al. (2024). DataComp-LM. NeurIPS. arXiv:2406.11794.
- Muennighoff, N. et al. (2023). Scaling Data-Constrained Language Modeling. NeurIPS. arXiv:2305.16264.
- Weber, M. et al. (2024). RedPajama: An Open Dataset for Training Large Language Models. arXiv:2411.12372.

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
