---
layout: default
title: From Signal to Turn: Interactional Friction in Modular Speech-to-Speech Pipelines
---

# From Signal to Turn: Interactional Friction in Modular Speech-to-Speech Pipelines
**arXiv**：[2512.11724v1](https://arxiv.org/abs/2512.11724) · [PDF](https://arxiv.org/pdf/2512.11724.pdf)  
**作者**：Titaya Mairittha, Tanakon Sawanglok, Panuwit Raden, Jirapast Buntub, Thanapat Warunee, Napat Asawachaisuvikrom, Thanaphum Saiwongin  

**一句话要点**：分析模块化语音到语音检索增强生成管道中的交互摩擦，揭示其结构性根源。

**关键词**：语音到语音检索增强生成, 交互摩擦, 模块化系统设计, 对话断裂分析, 系统级分析

## 3 点简述
- 核心问题：模块化语音AI系统在交互中产生对话断裂，表现为时间错位、表达扁平化和修复僵化。
- 方法要点：通过系统级分析，识别三种常见对话断裂模式，强调摩擦是模块化设计优先控制而非流畅性的结果。
- 实验或效果：基于代表性生产系统分析，提出构建自然语音AI需从优化组件转向协调模块间衔接。

## 摘要（原文）

> While voice-based AI systems have achieved remarkable generative capabilities, their interactions often feel conversationally broken. This paper examines the interactional friction that emerges in modular Speech-to-Speech Retrieval-Augmented Generation (S2S-RAG) pipelines. By analyzing a representative production system, we move beyond simple latency metrics to identify three recurring patterns of conversational breakdown: (1) Temporal Misalignment, where system delays violate user expectations of conversational rhythm; (2) Expressive Flattening, where the loss of paralinguistic cues leads to literal, inappropriate responses; and (3) Repair Rigidity, where architectural gating prevents users from correcting errors in real-time. Through system-level analysis, we demonstrate that these friction points should not be understood as defects or failures, but as structural consequences of a modular design that prioritizes control over fluidity. We conclude that building natural spoken AI is an infrastructure design challenge, requiring a shift from optimizing isolated components to carefully choreographing the seams between them.

