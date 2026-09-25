---
title: "GLBench: A Comprehensive Benchmark for Graph with Large Language Models"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/4ab0bd666d034fcaa5566fc7d176daa6-Abstract-Datasets_and_Benchmarks_Track.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/4ab0bd666d034fcaa5566fc7d176daa6-Paper-Datasets_and_Benchmarks_Track.pdf"
categories: ['graph-neural-networks-and-representation-learning', 'ai-benchmarking-and-evaluation-methodology']
tags: ['graph-LLMs', 'benchmark', 'GraphLLM', 'evaluation']
venue: "NeurIPS 2024"
tldr: "GLBench provides a comprehensive benchmark for evaluating large language model-enhanced graph learning methods across diverse tasks and datasets."
---

# GLBench: A Comprehensive Benchmark for Graph with Large Language Models

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/4ab0bd666d034fcaa5566fc7d176daa6-Abstract-Datasets_and_Benchmarks_Track.html](https://papers.nips.cc/paper_files/paper/2024/hash/4ab0bd666d034fcaa5566fc7d176daa6-Abstract-Datasets_and_Benchmarks_Track.html)

**TLDR**: GLBench provides a comprehensive benchmark for evaluating large language model-enhanced graph learning methods across diverse tasks and datasets.

## Abstract

The emergence of large language models (LLMs) has revolutionized the way we interact with graphs, leading to a new paradigm called GraphLLM. Despite the rapid development of GraphLLM methods in recent years, the progress and understanding of this field remain unclear due to the lack of a benchmark with consistent experimental protocols. To bridge this gap, we introduce GLBench, the first comprehensive benchmark for evaluating GraphLLM methods in both supervised and zero-shot scenarios. GLBench provides a fair and thorough evaluation of different categories of GraphLLM methods, along with traditional baselines such as graph neural networks. Through extensive experiments on a collection of real-world datasets with consistent data processing and splitting strategies, we have uncovered several key findings. Firstly, GraphLLM methods outperform traditional baselines in supervised settings, with LLM-as-enhancers showing the most robust performance. However, using LLMs as predictors is less effective and often leads to uncontrollable output issues. We also notice that no clear scaling laws exist for current GraphLLM methods. In addition, both structures and semantics are crucial for effective zero-shot transfer, and our proposed simple baseline can even outperform several models tailored for zero-shot scenarios. The data and code of the benchmark can be found at https://github.com/NineAbyss/GLBench.