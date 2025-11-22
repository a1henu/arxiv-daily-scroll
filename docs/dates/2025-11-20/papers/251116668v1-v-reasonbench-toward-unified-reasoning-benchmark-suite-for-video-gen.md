---
layout: default
title: V-ReasonBench: Toward Unified Reasoning Benchmark Suite for Video Generation Models
---

# V-ReasonBench: Toward Unified Reasoning Benchmark Suite for Video Generation Models
**arXiv**：[2511.16668v1](https://arxiv.org/abs/2511.16668) · [PDF](https://arxiv.org/pdf/2511.16668.pdf)  
**作者**：Yang Luo, Xuanlei Zhao, Baijiong Lin, Lingting Zhu, Liyao Tang, Yuqi Liu, Ying-Cong Chen, Shengju Qian, Xin Wang, Yang You  

**一句话要点**：提出V-ReasonBench基准以评估视频生成模型的推理能力

**关键词**：视频推理基准, 多维度评估, 生成模型, 零样本推理, 幻觉分析

## 3 点简述
- 核心问题：视频生成模型缺乏系统推理评估，需可靠基准。
- 方法要点：构建多维度基准，涵盖结构化、空间、模式和物理推理。
- 实验或效果：评估六种模型，揭示推理维度差异和常见幻觉行为。

## 摘要（原文）

> Recent progress in generative video models, such as Veo-3, has shown surprising zero-shot reasoning abilities, creating a growing need for systematic and reliable evaluation. We introduce V-ReasonBench, a benchmark designed to assess video reasoning across four key dimensions: structured problem-solving, spatial cognition, pattern-based inference, and physical dynamics. The benchmark is built from both synthetic and real-world image sequences and provides a diverse set of answer-verifiable tasks that are reproducible, scalable, and unambiguous. Evaluations of six state-of-the-art video models reveal clear dimension-wise differences, with strong variation in structured, spatial, pattern-based, and physical reasoning. We further compare video models with strong image models, analyze common hallucination behaviors, and study how video duration affects Chain-of-Frames reasoning. Overall, V-ReasonBench offers a unified and reproducible framework for measuring video reasoning and aims to support the development of models with more reliable, human-aligned reasoning skills.

