# Resolution-Failure-Directed Extraction: Demand-Driven Grounding for Neuro-Symbolic Text Reasoning

<div align="center">

<a href="https://cdn.jsdelivr.net/gh/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d@main/workflow.svg">
<picture>
  <source media="(prefers-color-scheme: dark)" srcset="workflow-dark.svg">
  <img alt="Artifact workflow — how every artifact in this repo was built" src="workflow.svg">
</picture>
</a>

<sub>🖱️ <b><a href="https://cdn.jsdelivr.net/gh/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d@main/workflow.svg">Open the interactive diagram</a></b> — every card links to its artifact folder.</sub>

</div>

> **TL;DR** — RFDE inverts neuro-symbolic control flow: a backward-chaining proof engine drives LLM-based fact extraction on demand, triggering single-predicate grounding queries only when resolution fails. This demand-driven architecture prevents over-generation of unsupported facts endemic to eager FOL translation. On 18 tasks (synthetic kinship, CLUTRR-style multi-hop, RuleTaker-style deduction), RFDE achieves 61.1% multi-hop accuracy and 0% hallucination rate on asserted predicates—a structural property of the architecture. Accuracy is lower than CoT (83.3%), but this reflects an intentional tradeoff: single-predicate binary questions are inherently harder than holistic document reasoning for implicit inference. RFDE is preferable for risk-sensitive applications (legal, medical) where interpretability and reduced hallucination justify the accuracy cost. The paper honestly addresses measurement asymmetries in the original evaluation and identifies key limitations: reliance on hand-authored tasks rather than established benchmarks, unimplemented Eager FOL baseline correction, and lack of unified hallucination classification with inter-annotator agreement. Future work must scale evaluation to benchmark datasets and implement rigorous measurement methodology.

<details>
<summary>Full hypothesis</summary>

When a pure-Python SLD resolution engine intercepts empty-clause failures during backward-chaining proof search and issues targeted, single-predicate grounding queries against the source document via LLM, the resulting pipeline achieves structurally lower hallucination rates than architectures that translate the full document to FOL upfront — because demand-driven extraction is bounded by proof obligations and never asserts facts the proof tree never requires. This structural guarantee (zero over-generated predicates by construction) is the core contribution; it must be validated using a unified Explicit/Implicit/Hallucinated annotator classification (Cohen's Kappa ≥0.75) applied identically to all compared methods. The accuracy cost of demand-driven extraction relative to holistic CoT reasoning (empirically ~22 percentage points on hand-authored tasks) is expected, real, and must be reported as a confirmed precision-hallucination tradeoff — not masked. To be publishable, the evaluation must: (a) implement unified hallucination classification replacing the current incommensurable per-method heuristics; (b) fix the Eager FOL baseline by passing Prolog goal terms directly rather than regex-parsing NL queries, and re-run all comparisons with the corrected baseline; (c) sample ≥30 examples from the officially downloaded CLUTRR and RuleTaker benchmarks (already available in art_rc9BIIHKg1h0) rather than author-authored surrogates, and report Wilson 95% confidence intervals; (d) correct the CLUTRR and RuleTaker references (CLUTRR: Sinha et al., EMNLP 2019; RuleTaker: Clark et al., IJCAI 2020). The document-grounding constraint — restricting every LLM-extracted fact to content supportable from the source text, as opposed to ARGOS-style open-ended world-knowledge generation — remains the primary novelty distinguishing RFDE from all prior failure-driven neuro-symbolic systems.

</details>

[![Download PDF](https://img.shields.io/badge/Download-PDF-red)](https://cdn.jsdelivr.net/gh/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d@main/paper.pdf) [![LaTeX Source](https://img.shields.io/badge/LaTeX-Source-orange)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/paper_latex)

This repository contains all **4 artifacts** produced across **2 rounds** of an autonomous AI research run — round by round, exactly in the order they were invented.

## Round 1

| Artifact | Type | Demo | Source | Builds on |
|----------|------|------|--------|-----------|
| **[Neuro-Symbolic Reasoning: State-of-the-Art Methods, Benchmar…](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/research-1)** | [![research](https://img.shields.io/badge/research-3b82f6)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/research-1) | [![View Research](https://img.shields.io/badge/View-Research-green)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/blob/main/round-1/research-1/demo/research_demo.md) | [![Source Code](https://img.shields.io/badge/Source_Code-2962FF)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/research-1/src) | — |
| **[FOL Reasoning Benchmarks: FOLIO, ProofWriter, RuleTaker (11,…](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/dataset-1)** | [![dataset](https://img.shields.io/badge/dataset-f59e0b)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/dataset-1) | [![Open In Colab](https://colab.research.google.com/assets/colab-badge.svg)](https://colab.research.google.com/github/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/blob/main/round-1/dataset-1/demo/data_code_demo.ipynb) | [![Source Code](https://img.shields.io/badge/Source_Code-2962FF)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/dataset-1/src) | — |
| **[Resolution-Failure-Directed Extraction (RFDE): Neuro-Symboli…](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/experiment-1)** | [![experiment](https://img.shields.io/badge/experiment-8b5cf6)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/experiment-1) | [![Open In Colab](https://colab.research.google.com/assets/colab-badge.svg)](https://colab.research.google.com/github/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/blob/main/round-1/experiment-1/demo/method_code_demo.ipynb) | [![Source Code](https://img.shields.io/badge/Source_Code-2962FF)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/experiment-1/src) | — |

## Round 2

| Artifact | Type | Demo | Source | Builds on |
|----------|------|------|--------|-----------|
| **[Document-Grounded Failure-Driven Extraction in Neuro-Symboli…](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-2/research-1)** | [![research](https://img.shields.io/badge/research-3b82f6)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-2/research-1) | [![View Research](https://img.shields.io/badge/View-Research-green)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/blob/main/round-2/research-1/demo/research_demo.md) | [![Source Code](https://img.shields.io/badge/Source_Code-2962FF)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-2/research-1/src) | <sub><i>background:</i><br/>[research‑1&nbsp;(R1)](https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d/tree/main/round-1/research-1)</sub> |

## Repository Structure

Artifacts are grouped by the round of invention that produced them. Each
artifact has its own folder with source code and a self-contained demo:

```
.
├── round-1/                         # One folder per round of invention
│   ├── experiment-1/
│   │   ├── README.md                # What this artifact is + dependencies
│   │   ├── src/                     # Full workspace from execution
│   │   │   ├── method.py            # Main implementation
│   │   │   ├── method_out.json      # Full output data
│   │   │   └── ...                  # All execution artifacts
│   │   └── demo/                    # Self-contained demo
│   │       └── method_code_demo.ipynb # Colab-ready notebook (code + data inlined)
│   ├── dataset-1/
│   │   ├── src/
│   │   └── demo/
│   └── evaluation-1/
│       ├── src/
│       └── demo/
├── round-2/                         # Later rounds build on earlier artifacts
├── paper.pdf                        # Research paper
├── paper_latex/                     # LaTeX source files
├── workflow.svg                     # Artifact dependency diagram (this page's header)
└── README.md
```

## Running Notebooks

### Option 1: Google Colab (Recommended)

Click the "Open in Colab" badges above to run notebooks directly in your browser.
No installation required!

### Option 2: Local Jupyter

```bash
# Clone the repo
git clone https://github.com/AMGrobelnik/ai-invention-14efe0-resolution-failure-directed-extraction-d
cd ai-invention-14efe0-resolution-failure-directed-extraction-d

# Install dependencies
pip install jupyter

# Run any artifact's demo notebook
jupyter notebook <artifact_folder>/demo/
```

## Source Code

The original source files are in each artifact's `src/` folder.
These files may have external dependencies - use the demo notebooks for a self-contained experience.

---
*Generated by AI Inventor Pipeline - Automated Research Generation*
