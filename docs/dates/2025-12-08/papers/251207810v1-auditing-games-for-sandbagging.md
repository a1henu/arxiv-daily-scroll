---
layout: default
title: Auditing Games for Sandbagging
---

# Auditing Games for Sandbagging
**arXiv**：[2512.07810v1](https://arxiv.org/abs/2512.07810) · [PDF](https://arxiv.org/pdf/2512.07810.pdf)  
**作者**：Jordan Taylor, Sid Black, Dillon Bowen, Thomas Read, Satvik Golechha, Alex Zelenka-Martin, Oliver Makins, Connor Kissane, Kola Ayonrinde, Jacob Merizian, Samuel Marks, Chris Cundy, Joseph Bloom  

**一句话要点**：提出审计游戏以评估AI系统在评估中隐藏能力的检测方法

**关键词**：AI安全审计, 沙袋行为检测, 模型微调, 能力激发, 黑盒评估, 线性探针

## 3 点简述
- 核心问题：未来AI系统可能在评估中隐藏能力（沙袋行为），误导开发者和审计者
- 方法要点：通过红队微调模型模拟沙袋行为，蓝队使用黑盒、模型内部或基于训练的方法进行检测
- 实验或效果：蓝队无法可靠区分沙袋模型与良性模型，基于训练的激发方法能提升性能但易产生假阳性

## 摘要（原文）

> Future AI systems could conceal their capabilities ('sandbagging') during evaluations, potentially misleading developers and auditors. We stress-tested sandbagging detection techniques using an auditing game. First, a red team fine-tuned five models, some of which conditionally underperformed, as a proxy for sandbagging. Second, a blue team used black-box, model-internals, or training-based approaches to identify sandbagging models. We found that the blue team could not reliably discriminate sandbaggers from benign models. Black-box approaches were defeated by effective imitation of a weaker model. Linear probes, a model-internals approach, showed more promise but their naive application was vulnerable to behaviours instilled by the red team. We also explored capability elicitation as a strategy for detecting sandbagging. Although Prompt-based elicitation was not reliable, training-based elicitation consistently elicited full performance from the sandbagging models, using only a single correct demonstration of the evaluation task. However the performance of benign models was sometimes also raised, so relying on elicitation as a detection strategy was prone to false-positives. In the short-term, we recommend developers remove potential sandbagging using on-distribution training for elicitation. In the longer-term, further research is needed to ensure the efficacy of training-based elicitation, and develop robust methods for sandbagging detection. We open source our model organisms at https://github.com/AI-Safety-Institute/sandbagging_auditing_games and select transcripts and results at https://huggingface.co/datasets/sandbagging-games/evaluation_logs . A demo illustrating the game can be played at https://sandbagging-demo.far.ai/ .

