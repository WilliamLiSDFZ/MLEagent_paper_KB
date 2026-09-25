---
title: "Non-Asymptotic Uncertainty Quantification in High-Dimensional Learning"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/dd65d612d2ddafd54ef5eceb92f1a754-Abstract-Conference.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/dd65d612d2ddafd54ef5eceb92f1a754-Paper-Conference.pdf"
categories: ['statistical-computational-tradeoffs-high-dimensional-learning', 'statistical-learning-theory-and-matrix-methods']
tags: ['uncertainty-quantification', 'high-dimensional-learning', 'LASSO', 'non-asymptotic-statistics']
venue: "NeurIPS 2024"
tldr: "A data-driven non-asymptotic framework for uncertainty quantification in high-dimensional regression applicable to both classical and modern learning methods."
---

# Non-Asymptotic Uncertainty Quantification in High-Dimensional Learning

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/dd65d612d2ddafd54ef5eceb92f1a754-Abstract-Conference.html](https://papers.nips.cc/paper_files/paper/2024/hash/dd65d612d2ddafd54ef5eceb92f1a754-Abstract-Conference.html)

**TLDR**: A data-driven non-asymptotic framework for uncertainty quantification in high-dimensional regression applicable to both classical and modern learning methods.

## Abstract

Uncertainty quantification (UQ) is a crucial but challenging task in many high-dimensional learning problems to increase the confidence of a given predictor. We develop a new data-driven approach for UQ in regression that applies both to classical optimization approaches such as the LASSO as well as to neural networks. One of the most notable UQ techniques is the debiased LASSO, which modifies the LASSO to allow for the construction of asymptotic confidence intervals by decomposing the estimation error into a Gaussian and an asymptotically vanishing bias component. However, in real-world problems with finite-dimensional data, the bias term is often too significant to disregard, resulting in overly narrow confidence intervals. Our work rigorously addresses this issue and derives a data-driven adjustment that corrects the confidence intervals for a large class of predictors by estimating the means and variances of the bias terms from training data, exploiting high-dimensional concentration phenomena. This gives rise to non-asymptotic confidence intervals, which can help avoid overestimating certainty in critical applications such as MRI diagnosis. Importantly, our analysis extends beyond sparse regression to data-driven predictors like neural networks, enhancing the reliability of model-based deep learning. Our findings bridge the gap between established theory and the practical applicability of such methods.