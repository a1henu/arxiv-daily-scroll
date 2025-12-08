---
layout: default
title: The Seeds of Scheming: Weakness of Will in the Building Blocks of Agentic Systems
---

# The Seeds of Scheming: Weakness of Will in the Building Blocks of Agentic Systems
**arXiv**：[2512.05449v1](https://arxiv.org/abs/2512.05449) · [PDF](https://arxiv.org/pdf/2512.05449.pdf)  
**作者**：Robert Yang  

**一句话要点**：提出意志薄弱概念以分析智能体系统不一致性，并引入基准进行量化评估。

**关键词**：意志薄弱, 智能体系统, 不一致性评估, 基准测试, 多智能体稳定性

## 3 点简述
- 核心问题：大语言模型存在认知与行动不一致，类似人类意志薄弱现象。
- 方法要点：引入意志薄弱概念，设计基准包括基线、同义、时序和诱惑条件。
- 实验或效果：基准支持跨模型、解码策略和诱惑类型的自我控制量化比较。

## 摘要（原文）

> Large language models display a peculiar form of inconsistency: they "know" the correct answer but fail to act on it. In human philosophy, this tension between global judgment and local impulse is called akrasia, or weakness of will. We propose akrasia as a foundational concept for analyzing inconsistency and goal drift in agentic AI systems. To operationalize it, we introduce a preliminary version of the Akrasia Benchmark, currently a structured set of prompting conditions (Baseline [B], Synonym [S], Temporal [T], and Temptation [X]) that measures when a model's local response contradicts its own prior commitments. The benchmark enables quantitative comparison of "self-control" across model families, decoding strategies, and temptation types. Beyond single-model evaluation, we outline how micro-level akrasia may compound into macro-level instability in multi-agent systems that may be interpreted as "scheming" or deliberate misalignment. By reframing inconsistency as weakness of will, this work connects agentic behavior to classical theories of agency and provides an empirical bridge between philosophy, psychology, and the emerging science of agentic AI.

