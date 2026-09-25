---
title: "BeanCounter: A low-toxicity, large-scale, and open dataset of business-oriented text"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/a6b99249d04f982fd2f7d5b2506bf541-Abstract-Datasets_and_Benchmarks_Track.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/a6b99249d04f982fd2f7d5b2506bf541-Paper-Datasets_and_Benchmarks_Track.pdf"
categories: ['toxicity-detection-and-classification-datasets']
tags: ['low-toxicity', 'business-text', 'pretraining-dataset', 'open-dataset']
venue: "NeurIPS 2024"
tldr: "BeanCounter is a large-scale, low-toxicity open dataset of business-oriented text for language model pretraining."
---

# BeanCounter: A low-toxicity, large-scale, and open dataset of business-oriented text

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/a6b99249d04f982fd2f7d5b2506bf541-Abstract-Datasets_and_Benchmarks_Track.html](https://papers.nips.cc/paper_files/paper/2024/hash/a6b99249d04f982fd2f7d5b2506bf541-Abstract-Datasets_and_Benchmarks_Track.html)

**TLDR**: BeanCounter is a large-scale, low-toxicity open dataset of business-oriented text for language model pretraining.

## Abstract

Many of the recent breakthroughs in language modeling have resulted from scaling effectively the same model architecture to larger datasets. In this vein, recent work has highlighted performance gains from increasing training dataset size and quality, suggesting a need for novel sources of large-scale datasets. In this work, we introduce BeanCounter, a public dataset consisting of more than 159B tokens extracted from businesses' disclosures. We show that this data is indeed novel: less than 0.1% of BeanCounter appears in Common Crawl-based datasets and it is an order of magnitude larger than datasets relying on similar sources. Given the data's provenance, we hypothesize that BeanCounter is comparatively more factual and less toxic than web-based datasets. Exploring this hypothesis, we find that many demographic identities occur with similar prevalence in BeanCounter but with significantly less toxic context relative to other datasets. To demonstrate the utility of BeanCounter, we evaluate and compare two LLMs continually pre-trained on BeanCounter with their base models. We find an 18-33% reduction in toxic generation and improved performance within the finance domain for the continually pretrained models. Collectively, our work suggests that BeanCounter is a novel source of low-toxicity and high-quality domain-specific data with sufficient scale to train multi-billion parameter LLMs.