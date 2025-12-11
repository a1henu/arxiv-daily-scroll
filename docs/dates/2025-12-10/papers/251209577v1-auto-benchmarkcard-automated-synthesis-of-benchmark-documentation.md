---
layout: default
title: Auto-BenchmarkCard: Automated Synthesis of Benchmark Documentation
---

# Auto-BenchmarkCard: Automated Synthesis of Benchmark Documentation
**arXiv**：[2512.09577v1](https://arxiv.org/abs/2512.09577) · [PDF](https://arxiv.org/pdf/2512.09577.pdf)  
**作者**：Aris Hofmann, Inge Vejsbjerg, Dhaval Salwala, Elizabeth M. Daly  

**一句话要点**：提出Auto-BenchmarkCard工作流，通过自动化生成验证的AI基准文档以解决文档不完整或不一致问题。

**关键词**：基准文档生成, 多智能体提取, LLM合成, 事实验证, AI基准比较, 自动化工作流

## 3 点简述
- 核心问题：AI基准文档常不完整或不一致，影响跨任务或领域的解释与比较。
- 方法要点：结合多智能体数据提取与LLM驱动合成，从异构源自动生成基准描述。
- 实验或效果：通过FactReasoner工具进行原子蕴含评分验证事实准确性，提升透明度、可比性和可重用性。

## 摘要（原文）

> We present Auto-BenchmarkCard, a workflow for generating validated descriptions of AI benchmarks. Benchmark documentation is often incomplete or inconsistent, making it difficult to interpret and compare benchmarks across tasks or domains. Auto-BenchmarkCard addresses this gap by combining multi-agent data extraction from heterogeneous sources (e.g., Hugging Face, Unitxt, academic papers) with LLM-driven synthesis. A validation phase evaluates factual accuracy through atomic entailment scoring using the FactReasoner tool. This workflow has the potential to promote transparency, comparability, and reusability in AI benchmark reporting, enabling researchers and practitioners to better navigate and evaluate benchmark choices.

