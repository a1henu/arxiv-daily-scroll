---
layout: default
title: A Study on Inference Latency for Vision Transformers on Mobile Devices
---

# A Study on Inference Latency for Vision Transformers on Mobile Devices
**arXiv**：[2510.25166v1](https://arxiv.org/abs/2510.25166) · [PDF](https://arxiv.org/pdf/2510.25166.pdf)  
**作者**：Zhuojin Li, Marco Paolieri, Leana Golubchik  

**一句话要点**：研究移动设备上视觉变换器的推理延迟，提供预测模型与数据集

**关键词**：视觉变换器, 推理延迟, 移动设备, 性能分析, 数据集构建

## 3 点简述
- 核心问题：移动设备上视觉变换器推理延迟的影响因素与性能特征
- 方法要点：比较190个ViT与102个CNN，构建1000个合成ViT延迟数据集
- 实验或效果：预测新ViT延迟准确，适用于实际应用

## 摘要（原文）

> Given the significant advances in machine learning techniques on mobile
> devices, particularly in the domain of computer vision, in this work we
> quantitatively study the performance characteristics of 190 real-world vision
> transformers (ViTs) on mobile devices. Through a comparison with 102 real-world
> convolutional neural networks (CNNs), we provide insights into the factors that
> influence the latency of ViT architectures on mobile devices. Based on these
> insights, we develop a dataset including measured latencies of 1000 synthetic
> ViTs with representative building blocks and state-of-the-art architectures
> from two machine learning frameworks and six mobile platforms. Using this
> dataset, we show that inference latency of new ViTs can be predicted with
> sufficient accuracy for real-world applications.

