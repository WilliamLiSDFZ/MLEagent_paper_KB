---
title: "AlphaMath Almost Zero: Process Supervision without Process"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/30dfe47a3ccbee68cffa0c19ccb1bc00-Abstract-Conference.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/30dfe47a3ccbee68cffa0c19ccb1bc00-Paper-Conference.pdf"
categories: ['llm-training-and-optimization-techniques', 'neural-networks-for-formal-reasoning-and-verification']
tags: ['LLM', 'mathematical-reasoning', 'process-supervision', 'MCTS']
venue: "NeurIPS 2024"
tldr: "AlphaMath uses Monte Carlo Tree Search to automatically generate process supervision signals for LLMs to improve multi-step mathematical reasoning without human-annotated process labels."
---

# AlphaMath Almost Zero: Process Supervision without Process

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/30dfe47a3ccbee68cffa0c19ccb1bc00-Abstract-Conference.html](https://papers.nips.cc/paper_files/paper/2024/hash/30dfe47a3ccbee68cffa0c19ccb1bc00-Abstract-Conference.html)

**TLDR**: AlphaMath uses Monte Carlo Tree Search to automatically generate process supervision signals for LLMs to improve multi-step mathematical reasoning without human-annotated process labels.

## Abstract

Although recent advancements in large language models (LLMs) have significantly improved their performance on various tasks, they still face challenges with complex and symbolic multi-step reasoning, particularly in mathematical reasoning. To bolster the mathematical reasoning capabilities of LLMs, most existing efforts concentrate on seeking assistance from either domain experts or GPT-4 for high-quality process-supervised data, which is not only expensive but also labor-intensive. In our study, we propose an innovative framework, AlphaMath, that bypasses the need for process annotations (from humans or GPTs) by leveraging Monte Carlo Tree Search (MCTS). This framework focuses on unleashing the potential of a well-pretrained LLM to autonomously enhance its mathematical reasoning. Specifically, we integrate a value model with the LLM, automatically generating both process supervision and step-level evaluation signals in MCTS. Furthermore, we propose an efficient inference strategy—step-level beam search, where the value model is crafted to assist the policy model (i.e., LLM) in navigating more effective reasoning paths, rather than solely relying on prior probabilities. The experimental results on both in-domain and out-of-domain datasets demonstrate that even without GPT-4 or human-annotated process supervision, our AlphaMath framework achieves comparable or superior results to previous state-of-the-art methods.