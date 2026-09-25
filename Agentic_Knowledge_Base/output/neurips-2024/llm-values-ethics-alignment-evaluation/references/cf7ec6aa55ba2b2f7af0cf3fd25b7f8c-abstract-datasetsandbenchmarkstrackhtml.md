---
title: "Value Imprint: A Technique for Auditing the Human Values Embedded in RLHF Datasets"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/cf7ec6aa55ba2b2f7af0cf3fd25b7f8c-Abstract-Datasets_and_Benchmarks_Track.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/cf7ec6aa55ba2b2f7af0cf3fd25b7f8c-Paper-Datasets_and_Benchmarks_Track.pdf"
categories: ['llm-values-ethics-alignment-evaluation']
tags: ['RLHF', 'human-values', 'auditing', 'preference-datasets', 'alignment']
venue: "NeurIPS 2024"
tldr: "Value Imprint is a framework for auditing which human values are embedded in RLHF datasets used for LLM fine-tuning."
---

# Value Imprint: A Technique for Auditing the Human Values Embedded in RLHF Datasets

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/cf7ec6aa55ba2b2f7af0cf3fd25b7f8c-Abstract-Datasets_and_Benchmarks_Track.html](https://papers.nips.cc/paper_files/paper/2024/hash/cf7ec6aa55ba2b2f7af0cf3fd25b7f8c-Abstract-Datasets_and_Benchmarks_Track.html)

**TLDR**: Value Imprint is a framework for auditing which human values are embedded in RLHF datasets used for LLM fine-tuning.

## Abstract

LLMs are increasingly fine-tuned using RLHF datasets to align them with human preferences and values. However, very limited research has investigated which specific human values are operationalized through these datasets. In this paper, we introduce Value Imprint, a framework for auditing and classifying the human values embedded within RLHF datasets. To investigate the viability of this framework, we conducted three case study experiments by auditing the Anthropic/hh-rlhf, OpenAI WebGPT Comparisons, and Alpaca GPT-4-LLM datasets to examine the human values embedded within them. Our analysis involved a two-phase process. During the first phase, we developed a taxonomy of human values through an integrated review of prior works from philosophy, axiology, and ethics. Then, we applied this taxonomy to annotate 6,501 RLHF preferences. During the second phase, we employed the labels generated from the annotation as ground truth data for training a transformer-based machine learning model to audit and classify the three RLHF datasets. Through this approach, we discovered that information-utility values, including Wisdom/Knowledge and Information Seeking, were the most dominant human values within all three RLHF datasets. In contrast, prosocial and democratic values, including Well-being, Justice, and Human/Animal Rights, were the least represented human values. These findings have significant implications for developing language models that align with societal values and norms. We contribute our datasets to support further research in this area. https://github.com/hv-rsrch/valueimprint