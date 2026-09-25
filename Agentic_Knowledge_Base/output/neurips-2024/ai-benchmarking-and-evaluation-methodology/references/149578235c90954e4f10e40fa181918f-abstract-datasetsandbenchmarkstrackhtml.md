---
title: "PertEval: Unveiling Real Knowledge Capacity of LLMs with Knowledge-Invariant Perturbations"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/149578235c90954e4f10e40fa181918f-Abstract-Datasets_and_Benchmarks_Track.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/149578235c90954e4f10e40fa181918f-Paper-Datasets_and_Benchmarks_Track.pdf"
categories: ['ai-benchmarking-and-evaluation-methodology', 'machine-learning-theory-and-evaluation-methods']
tags: ['benchmark-reliability', 'data-contamination', 'knowledge-evaluation']
venue: "NeurIPS 2024"
tldr: "PertEval uses knowledge-invariant perturbations to expose LLMs' true knowledge capacity and reveal reliability issues in existing benchmarks caused by data contamination."
---

# PertEval: Unveiling Real Knowledge Capacity of LLMs with Knowledge-Invariant Perturbations

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/149578235c90954e4f10e40fa181918f-Abstract-Datasets_and_Benchmarks_Track.html](https://papers.nips.cc/paper_files/paper/2024/hash/149578235c90954e4f10e40fa181918f-Abstract-Datasets_and_Benchmarks_Track.html)

**TLDR**: PertEval uses knowledge-invariant perturbations to expose LLMs' true knowledge capacity and reveal reliability issues in existing benchmarks caused by data contamination.

## Abstract

Expert-designed close-ended benchmarks are indispensable in assessing the knowledge capacity of large language models (LLMs). Despite their widespread use, concerns have mounted regarding their reliability due to limited test scenarios and an unavoidable risk of data contamination. To rectify this, we present PertEval, a toolkit devised for in-depth probing of LLMs' knowledge capacity through knowledge-invariant perturbations. These perturbations employ human-like restatement techniques to generate on-the-fly test samples from static benchmarks, meticulously retaining knowledge-critical content while altering irrelevant details. Our toolkit further includes a suite of response consistency analyses that compare performance on raw vs. perturbed test sets to precisely assess LLMs' genuine knowledge capacity. Six representative LLMs are re-evaluated using PertEval. Results reveal significantly inflated performance of the LLMs on raw benchmarks, including an absolute 25.8% overestimation for GPT-4. Additionally, through a nuanced response pattern analysis, we discover that PertEval retains LLMs' uncertainty to specious knowledge, and reveals their potential rote memorization to correct options which leads to overestimated performance. We also find that the detailed response consistency analyses by PertEval could illuminate various weaknesses in existing LLMs' knowledge mastery and guide the development of refinement. Our findings provide insights for advancing more robust and genuinely knowledgeable LLMs. Our code is available at https://github.com/aigc-apps/PertEval.