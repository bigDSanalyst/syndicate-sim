---
aliases: ["Multi-head Quantum Neural Networks: Replacing Transformer Blocks with NISQ Modules inside a 30-Billion-Parameter LLM"]
tags: [literature/arxiv, status/triage]
arxiv_id: "2611.15250"
url: "http://arxiv.org/abs/2611.15250v1"
published: "2026-11-11T09:39:14Z"
ingested: "2026-11-13T13:52:45Z"
authors:
  - "Maforikan Amoussou"
  - "Borja Aizpurua"
  - "Sukhbinder Singh"
  - "Román Orús"
  - "Hans-Arno Jacobsen"
---

# Multi-head Quantum Neural Networks: Replacing Transformer Blocks with NISQ Modules inside a 30-Billion-Parameter LLM

## Abstract

> We introduce the multi-head quantum neural network (QNN), a quantum module compatible with noisy
> intermediate-scale quantum (NISQ) devices that can replace transformer blocks inside pre-trained
> large language models (LLMs) with little loss in accuracy and with far fewer parameters than the
> blocks it replaces. Encoding a model's $D$ hidden neurons into a qubit register is the obstacle:
> amplitude encoding scales poorly in circuit depth and angle encoding in qubit count, so neither
> is practical at production-scale width. We instead partition the hidden space into $k$ disjoint
> heads, angle-encode each into an $n_q$-qubit register, process the heads in parallel, and couple
> them through constrained classical linear layers, the mixers. Performing surgery on
> Qwen3-30B-A3B-Instruct-2507, we show that a single multi-head QNN with $145\,281$ trainable
> parameters ($D=2048$, $k=32$, $n_q=8$, $L=4$) can replace a contiguous span of eight transformer
> blocks, displacing $16.33\%$ of the model's parameters. Ablations show that, for a single
> replaced block, the quantum heads (circuits followed by a learned readout), and not the
> classical mixers alone, recover the displaced function, whereas for fused spans the mixers alone
> come within $1$-$3\%$ of the full module in perplexity. Whether this benefit is specific to
> trained, entangling quantum circuits is not established: controls that switch the entangler off
> (two seeds), or freeze the circuit at its initial or at uniformly random angles (one seed), beat
> the full module on held-out perplexity, and a parameter-matched classical multilayer perceptron
> remains a few percent ahead of the full module. We train classically with exact statevector
> simulation, then execute the quantum heads of our fusion checkpoints on a $156$-qubit IBM Heron
> processor, showing that NISQ-scale quantum modules can be installed in a production-scale LLM
> and run on hardware.

---
## Reading Notes
*Annotations below. Update the status tag as you triage; the arxiv_id frontmatter must survive edits - it is the dedup key.*

