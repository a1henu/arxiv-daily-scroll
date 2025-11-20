---
layout: default
title: Octopus: Agentic Multimodal Reasoning with Six-Capability Orchestration
---

# Octopus: Agentic Multimodal Reasoning with Six-Capability Orchestration
**arXiv**：[2511.15351v1](https://arxiv.org/abs/2511.15351) · [PDF](https://arxiv.org/pdf/2511.15351.pdf)  
**作者**：Yifu Guo, Zishan Xu, Zhiyuan Yao, Yuquan Lu, Jiaye Lin, Sen Hu, Zhenheng Tang, Yingchao Li, Huacan Wang, Ronghao Chen  

**一句话要点**：提出Octopus代理多模态推理框架，通过六能力编排解决动态任务适应问题

**关键词**：多模态推理, 代理系统, 能力编排, 自主探索, 动态选择, 基准评估

## 3 点简述
- 现有多模态推理模型缺乏自主探索推理路径的能力，难以适应动态变化的任务需求
- 定义六种核心能力，实现自主探索和动态选择最合适能力进行推理
- 在Octopus-Bench基准测试中，Octopus在多数任务上取得最佳性能

## 摘要（原文）

> Existing multimodal reasoning models and frameworks suffer from fundamental architectural limitations: most lack the human-like ability to autonomously explore diverse reasoning pathways-whether in direct inference, tool-driven visual exploration, programmatic visual manipulation, or intrinsic visual imagination. Consequently, they struggle to adapt to dynamically changing capability requirements in real-world tasks. Meanwhile, humans exhibit a complementary set of thinking abilities when addressing such tasks, whereas existing methods typically cover only a subset of these dimensions. Inspired by this, we propose Octopus: Agentic Multimodal Reasoning with Six-Capability Orchestration, a new paradigm for multimodal agentic reasoning. We define six core capabilities essential for multimodal reasoning and organize a comprehensive evaluation benchmark, Octopus-Bench, accordingly. Octopus is capable of autonomously exploring during reasoning and dynamically selecting the most appropriate capability based on the current state. Experimental results show that Octopus achieves the best performance on the vast majority of tasks in Octopus-Bench, highlighting the crucial role of capability coordination in agentic multimodal reasoning.

