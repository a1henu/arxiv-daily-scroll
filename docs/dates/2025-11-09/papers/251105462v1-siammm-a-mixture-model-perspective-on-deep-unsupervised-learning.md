---
layout: default
title: SiamMM: A Mixture Model Perspective on Deep Unsupervised Learning
---

# SiamMM: A Mixture Model Perspective on Deep Unsupervised Learning
**arXiv**：[2511.05462v1](https://arxiv.org/abs/2511.05462) · [PDF](https://arxiv.org/pdf/2511.05462.pdf)  
**作者**：Xiaodong Wang, Jing Huang, Kevin J Liang  

**一句话要点**：提出SiamMM模型，通过混合模型视角增强无监督聚类方法，提升自监督学习性能。

**关键词**：无监督学习, 聚类方法, 混合模型, 自监督学习, 性能提升

## 3 点简述
- 核心问题：无监督聚类方法应用启发式，缺乏理论指导。
- 方法要点：将无监督聚类与统计混合模型关联，开发SiamMM模型。
- 实验或效果：在自监督学习基准中达到最优，聚类结果接近真实标签。

## 摘要（原文）

> Recent studies have demonstrated the effectiveness of clustering-based
> approaches for self-supervised and unsupervised learning. However, the
> application of clustering is often heuristic, and the optimal methodology
> remains unclear. In this work, we establish connections between these
> unsupervised clustering methods and classical mixture models from statistics.
> Through this framework, we demonstrate significant enhancements to these
> clustering methods, leading to the development of a novel model named SiamMM.
> Our method attains state-of-the-art performance across various self-supervised
> learning benchmarks. Inspection of the learned clusters reveals a strong
> resemblance to unseen ground truth labels, uncovering potential instances of
> mislabeling.

