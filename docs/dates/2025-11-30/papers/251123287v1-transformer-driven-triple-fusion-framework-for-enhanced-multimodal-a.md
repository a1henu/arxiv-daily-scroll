---
layout: default
title: Transformer-Driven Triple Fusion Framework for Enhanced Multimodal Author Intent Classification in Low-Resource Bangla
---

# Transformer-Driven Triple Fusion Framework for Enhanced Multimodal Author Intent Classification in Low-Resource Bangla
**arXiv**：[2511.23287v1](https://arxiv.org/abs/2511.23287) · [PDF](https://arxiv.org/pdf/2511.23287.pdf)  
**作者**：Ariful Islam, Tanvir Mahmud, Md Rifat Hossen  

**一句话要点**：提出基于Transformer的三重融合框架BangACMM，以增强低资源孟加拉语社交媒体作者意图分类。

**关键词**：作者意图分类, 多模态融合, Transformer模型, 低资源语言, 孟加拉语社交媒体, 中间融合策略

## 3 点简述
- 针对孟加拉语社交媒体作者意图分类，融合文本和视觉模态以克服单模态方法局限。
- 引入中间融合策略，优于早期和晚期融合，结合mBERT和Swin Transformer实现最优性能。
- 在Uddessho数据集上达到84.11%宏F1分数，比先前方法提升8.4个百分点，建立新基准。

## 摘要（原文）

> The expansion of the Internet and social networks has led to an explosion of user-generated content. Author intent understanding plays a crucial role in interpreting social media content. This paper addresses author intent classification in Bangla social media posts by leveraging both textual and visual data. Recognizing limitations in previous unimodal approaches, we systematically benchmark transformer-based language models (mBERT, DistilBERT, XLM-RoBERTa) and vision architectures (ViT, Swin, SwiftFormer, ResNet, DenseNet, MobileNet), utilizing the Uddessho dataset of 3,048 posts spanning six practical intent categories. We introduce a novel intermediate fusion strategy that significantly outperforms early and late fusion on this task. Experimental results show that intermediate fusion, particularly with mBERT and Swin Transformer, achieves 84.11% macro-F1 score, establishing a new state-of-the-art with an 8.4 percentage-point improvement over prior Bangla multimodal approaches. Our analysis demonstrates that integrating visual context substantially enhances intent classification. Cross-modal feature integration at intermediate levels provides optimal balance between modality-specific representation and cross-modal learning. This research establishes new benchmarks and methodological standards for Bangla and other low-resource languages. We call our proposed framework BangACMM (Bangla Author Content MultiModal).

