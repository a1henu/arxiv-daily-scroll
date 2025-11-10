---
layout: default
title: A benchmark multimodal oro-dental dataset for large vision-language models
---

# A benchmark multimodal oro-dental dataset for large vision-language models
**arXiv**：[2511.04948v1](https://arxiv.org/abs/2511.04948) · [PDF](https://arxiv.org/pdf/2511.04948.pdf)  
**作者**：Haoxin Lv, Ijazul Haq, Jin Du, Jiaxin Ma, Binnian Zhu, Xiaobing Dang, Chaoan Liang, Ruxu Du, Yingjie Zhang, Muhammad Saqib  

**一句话要点**：提出多模态口腔数据集以促进AI口腔医疗发展

**关键词**：多模态数据集, 口腔医疗AI, 视觉语言模型, 异常分类, 诊断报告生成

## 3 点简述
- 核心问题：口腔医疗AI缺乏大规模多模态数据集，难以模拟临床复杂性。
- 方法要点：构建包含图像、文本的多模态数据集，用于微调视觉语言模型。
- 实验或效果：微调模型在异常分类和诊断报告生成任务上优于基线和GPT-4o。

## 摘要（原文）

> The advancement of artificial intelligence in oral healthcare relies on the
> availability of large-scale multimodal datasets that capture the complexity of
> clinical practice. In this paper, we present a comprehensive multimodal
> dataset, comprising 8775 dental checkups from 4800 patients collected over
> eight years (2018-2025), with patients ranging from 10 to 90 years of age. The
> dataset includes 50000 intraoral images, 8056 radiographs, and detailed textual
> records, including diagnoses, treatment plans, and follow-up notes. The data
> were collected under standard ethical guidelines and annotated for
> benchmarking. To demonstrate its utility, we fine-tuned state-of-the-art large
> vision-language models, Qwen-VL 3B and 7B, and evaluated them on two tasks:
> classification of six oro-dental anomalies and generation of complete
> diagnostic reports from multimodal inputs. We compared the fine-tuned models
> with their base counterparts and GPT-4o. The fine-tuned models achieved
> substantial gains over these baselines, validating the dataset and underscoring
> its effectiveness in advancing AI-driven oro-dental healthcare solutions. The
> dataset is publicly available, providing an essential resource for future
> research in AI dentistry.

