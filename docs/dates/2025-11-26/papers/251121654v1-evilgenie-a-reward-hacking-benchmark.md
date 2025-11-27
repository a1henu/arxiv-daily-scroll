---
layout: default
title: EvilGenie: A Reward Hacking Benchmark
---

# EvilGenie: A Reward Hacking Benchmark
**arXiv**：[2511.21654v1](https://arxiv.org/abs/2511.21654) · [PDF](https://arxiv.org/pdf/2511.21654.pdf)  
**作者**：Jonathan Gabor, Jayson Lynch, Jonathan Rosenfeld  

**一句话要点**：提出EvilGenie基准以评估编程环境中的奖励破解问题

**关键词**：奖励破解基准, 编程代理评估, LLM评判, 测试文件编辑检测, 代码生成安全

## 3 点简述
- 核心问题：编程代理可能通过硬编码测试用例等方式进行奖励破解
- 方法要点：使用保留单元测试、LLM评判和测试文件编辑检测三种方法
- 实验或效果：验证LLM评判在明确案例中高效，并观察到多个流行代理的奖励破解行为

## 摘要（原文）

> We introduce EvilGenie, a benchmark for reward hacking in programming settings. We source problems from LiveCodeBench and create an environment in which agents can easily reward hack, such as by hardcoding test cases or editing the testing files. We measure reward hacking in three ways: held out unit tests, LLM judges, and test file edit detection. We verify these methods against human review and each other. We find the LLM judge to be highly effective at detecting reward hacking in unambiguous cases, and observe only minimal improvement from the use of held out test cases. In addition to testing many models using Inspect's basic_agent scaffold, we also measure reward hacking rates for three popular proprietary coding agents: OpenAI's Codex, Anthropic's Claude Code, and Google's Gemini CLI Using GPT-5, Claude Sonnet 4, and Gemini 2.5 Pro, respectively. We observe explicit reward hacking by both Codex and Claude Code, and misaligned behavior by all three agents. Our codebase can be found at https://github.com/JonathanGabor/EvilGenie.

