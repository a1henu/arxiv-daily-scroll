---
layout: default
title: Adam Simplified: Bias Correction Simplified
---

# Adam Simplified: Bias Correction Simplified
**arXiv**：[2511.20516v1](https://arxiv.org/abs/2511.20516) · [PDF](https://arxiv.org/pdf/2511.20516.pdf)  
**作者**：Sam Laing, Antonio Orvieto  

**一句话要点**：质疑Adam优化器中偏置校正的必要性，通过实验揭示其无益或有害

**关键词**：Adam优化器, 偏置校正, 深度学习优化, 超参数调优, 学习率调度

## 3 点简述
- 核心问题：Adam优化器中偏置校正组件的实际贡献未被充分理解，常被盲目采用。
- 方法要点：通过系统消融实验，分析偏置校正在视觉和语言建模任务中的影响。
- 实验或效果：在最优超参数下，偏置校正无性能提升；无适当学习率调度时可能有害。

## 摘要（原文）

> The Adam optimizer is a cornerstone of modern deep learning, yet the empirical necessity of each of its individual components is often taken for granted. This paper presents a focused investigation into the role of bias-correction, a feature whose contribution remains poorly understood. Through a series of systematic ablations on vision and language modelling tasks, we demonstrate that the conventional wisdom surrounding bias correction is misleading. In particular, we demonstrate that in the optimal hyper-parameter configuration, the inclusion of bias correction leads to no improvement in final test performance. Moreover, unless appropriate learning rate scheduling is implemented, the inclusion of bias correction can sometimes be detrimental to performance. We further reinterpret bias correction as a form of implicit learning rate scheduling whose behaviour is strongly dependent on the choice of smoothing hyper-parameters $β_1, β_2 \in [0,1)$. Our findings challenge the universal inclusion of this component.

