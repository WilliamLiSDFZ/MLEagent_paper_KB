---
title: "Robustly overfitting latents for flexible neural image compression"
source: "https://papers.nips.cc/paper_files/paper/2024/hash/c1233cb30ef11a3fe6ab10aa96beabaf-Abstract-Conference.html"
pdf_url: "https://papers.nips.cc/paper_files/paper/2024/file/c1233cb30ef11a3fe6ab10aa96beabaf-Paper-Conference.pdf"
categories: ['learned-compression-entropy-coding-methods', 'diffusion-based-generative-modeling-and-inference']
tags: ['neural-image-compression', 'variational-autoencoder', 'latent-overfitting', 'entropy-coding', 'learned-compression']
venue: "NeurIPS 2024"
tldr: "Proposes robust latent overfitting for flexible neural image compression using variational autoencoders."
---

# Robustly overfitting latents for flexible neural image compression

**Source**: [https://papers.nips.cc/paper_files/paper/2024/hash/c1233cb30ef11a3fe6ab10aa96beabaf-Abstract-Conference.html](https://papers.nips.cc/paper_files/paper/2024/hash/c1233cb30ef11a3fe6ab10aa96beabaf-Abstract-Conference.html)

**TLDR**: Proposes robust latent overfitting for flexible neural image compression using variational autoencoders.

## Abstract

Neural image compression has made a great deal of progress. State-of-the-art models are based on variational autoencoders and are outperforming classical models. Neural compression models learn to encode an image into a quantized latent representation that can be efficiently sent to the decoder, which decodes the quantized latent into a reconstructed image. While these models have proven successful in practice, they lead to sub-optimal results due to imperfect optimization and limitations in the encoder and decoder capacity. Recent work shows how to use stochastic Gumbel annealing (SGA) to refine the latents of pre-trained neural image compression models. We extend this idea by introducing SGA+, which contains three different methods that build upon SGA.We show how our method improves the overall compression performance in terms of the R-D trade-off, compared to its predecessors. Additionally, we show how refinement of the latents with our best-performing method improves the compression performance on both the Tecnick and CLIC dataset. Our method is deployed for a pre-trained hyperprior and for a more flexible model.Further, we give a detailed analysis of our proposed methods and show that they are less sensitive to hyperparameter choices. Finally, we show how each method can be extended to three- instead of two-class rounding.