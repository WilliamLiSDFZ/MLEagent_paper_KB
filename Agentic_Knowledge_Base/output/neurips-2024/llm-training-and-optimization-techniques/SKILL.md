---
name: llm-training-and-optimization-techniques
description: >-
  This skill covers methods for improving the efficiency, accuracy, and capabilities of large language models and related architectures through techniques spanning memory-efficient optimizers (e.g., MicroAdam, KV cache quantization), inference acceleration (attention compression, adaptive token allocation), and training data/objective improvements (preference optimization, adversarial training, instruction dataset construction). It also addresses specialized applications including
---

# Llm Training And Optimization Techniques

This skill covers methods for improving the efficiency, accuracy, and capabilities of large language models and related architectures through techniques spanning memory-efficient optimizers (e.g., MicroAdam, KV cache quantization), inference acceleration (attention compression, adaptive token allocation), and training data/objective improvements (preference optimization, adversarial training, instruction dataset construction). It also addresses specialized applications including

## Entry Index

| # | Title | Tags | File |
|---|-------|------|------|
| 1 | MicroAdam: Accurate Adaptive Optimization with Low Space Ove | adam-optimizer, memory-compression, convergence-guarantees | 000f947dcaff8fbffcc3f53a1314f358.md |
| 2 | Mixtures of Experts for Audio-Visual Learning | mixture-of-experts, audio-visual-learning, parameter-efficient-transfer | 009729d26288b9a8826023692a876107.md |
| 3 | Training-Free Adaptive Diffusion with Bounded Difference App | diffusion-models, training-free-acceleration, bounded-difference-approximation | 00d1f03b87a401b1c7957e0cc785d0bc.md |
| 4 | Chain of Preference Optimization: Improving Chain-of-Thought | chain-of-thought, preference-optimization, LLM-reasoning | 00d80722b756de0166523a87805dd00f.md |
| 5 | Decompose, Analyze and Rethink: Solving Intricate Problems w | reasoning-tree, question-decomposition, LLM-problem-solving | 01025a4e79355bb37a10ba39605944b5.md |
| 6 | Improving Sparse Decomposition of Language Model Activations | sparse-autoencoders, mechanistic-interpretability, language-model-features | 01772a8b0420baec00c4d59fe2fbace6.md |
| 7 | Towards Understanding How Transformers Learn In-context Thro | in-context-learning, transformers, representation-learning | 01a8d63f9cb6dcbaa3092ccddd2075ac.md |
| 8 | DiTFastAttn: Attention Compression for Diffusion Transformer | diffusion-transformer, attention-compression, inference-efficiency | 0267925e3c276e79189251585b4100bf.md |
| 9 | KVQuant: Towards 10 Million Context Length LLM Inference wit | KV-cache, quantization, long-context-inference | 028fcbcf85435d39a40c4d61b42c99a4.md |
| 10 | SciInstruct: a Self-Reflective Instruction Annotated Dataset | scientific-llm, self-reflective-annotation, instruction-tuning | 02ee6b7295f720407b56c457b34c54d5-abstract-datasetsandbenchmarkstrackhtml.md |
| 11 | HelpSteer 2: Open-source dataset for training top-performing | preference-dataset, reward-model, human-alignment | 02fd91a387a6a5a5751e81b58a75af90-abstract-datasetsandbenchmarkstrackhtml.md |
| 12 | Efficient Adversarial Training in LLMs with Continuous Attac | adversarial-training, llm-robustness, continuous-attacks | 0302fb83c62991efbccf0a003e4f5a92.md |
| 13 | D-LLM: A Token Adaptive Computing Resource Allocation Strate | token-adaptive-computation, llm-efficiency, resource-allocation | 03469b1a66e351b18272be23baf3b809.md |
| 14 | AdaNovo: Towards Robust \emph{De Novo} Peptide Sequencing in | de-novo-peptide-sequencing, proteomics, data-bias-robustness | 034b4a2860d4d170ce663584bc78cb32.md |
| 15 | JiuZhang3.0: Efficiently Improving Mathematical Reasoning by | mathematical-reasoning, data-synthesis, small-model-training | 0356216f73660e15670510f5e42b5fa6.md |
| 16 | einspace: Searching for Neural Architectures from Fundamenta | neural-architecture-search, search-space-diversity, fundamental-operations | 0382cb76309820f71c6eacd47b36ce71.md |
| 17 | AlchemistCoder: Harmonizing and Eliciting Code Capability by | code-llm, hindsight-tuning, multi-source-data | 040c816286b3844fd78f2124eec75f2e.md |
| 18 | BERTs are Generative In-Context Learners | in-context-learning, masked-language-models, generative-inference | 04ea184dfb5f1babb78c093e850a83f9.md |
| 19 | Autonomous Agents for Collaborative Task under Information A | LLM-multi-agent, information-asymmetry, collaborative-tasks | 0534abc9e6db91683d82186ef0d68202.md |
| 20 | BoNBoN Alignment for Large Language Models and the Sweetness | best-of-n-sampling, LLM-alignment, RLHF | 056521a35eacd9d2127b66a7d3c499c5.md |
| 21 | Analyzing & Reducing the Need for Learning Rate Warmup in GP | learning-rate-warmup, GPT-training, optimization | 059445c2d5b3ef918079851628fef1d6.md |
| 22 | QBB: Quantization with Binary Bases for LLMs | post-training-quantization, binary-bases, llm-compression | 05b69cc4c8ff6e24c5de1ecd27223d37.md |
| 23 | KV Cache is 1 Bit Per Channel: Efficient Large Language Mode | kv-cache-quantization, llm-inference, coupled-quantization | 05d6b5b6901fb57d2c287e1d3ce6d63c.md |
| 24 | Concentrate Attention: Towards Domain-Generalizable Prompt O | prompt-optimization, domain-generalization, language-models | 061d5d1b7d97117764f205d4e038f9eb.md |
| 25 | LT-Defense: Searching-free Backdoor Defense via Exploiting t | backdoor-defense, long-tailed-effect, language-models | 064f6bcd7d3c72fb187bfca35ba2bfd4.md |
| 26 | CAT: Coordinating Anatomical-Textual Prompts for Multi-Organ | medical-image-segmentation, anatomical-textual-prompts, multi-organ-tumor | 06a52a54c8ee03cd86771136bc91eb1f.md |
| 27 | Searching for Efficient Linear Layers over a Continuous Spac | structured-matrices, linear-layers, efficiency | 0729c38b421cd66f2313ab397d099e37.md |
| 28 | Star-Agents: Automatic Data Optimization with LLM Agents for | instruction-tuning, data-optimization, llm-agents | 0852b88e96d973bd4e21b673f51621d0.md |
| 29 | Building on Efficient Foundations: Effective Training of LLM | llm-efficiency, structured-feedforward, parameter-reduction | 0877af85978e9e630b77f6221db47876.md |
| 30 | Weak-to-Strong Search: Align Large Language Models via Searc | llm-alignment, weak-to-strong, test-time-search | 088d99765bc121c6df215da7d45bc4e9.md |
| 31 | IRCAN: Mitigating Knowledge Conflicts in LLM Generation via  | knowledge-conflicts, context-aware-neurons, LLM-generation | 08a9e28c96d016dd63903ab51cd085b0.md |
| 32 | PV-Tuning: Beyond Straight-Through Estimation for Extreme LL | extreme-quantization, LLM-compression, straight-through-estimation | 091166620a04a289c555f411d8899049.md |
| 33 | SLED: Self Logits Evolution Decoding for Improving Factualit | factuality, decoding-strategy, self-logits | 0939f13ffce3ff487509d902ddba4571.md |
| 34 | BackdoorAlign: Mitigating Fine-tuning based Jailbreak Attack | backdoor-alignment, jailbreak-attack, fine-tuning-safety | 094324f386c836c75d4a26f3499d2ede.md |
| 35 | TOPA: Extending Large Language Models for Video Understandin | video-understanding, large-language-models, text-only-pretraining | 0ae94013da7cd459402fd77874e09ee3.md |
| 36 | Towards Scalable and Stable Parallelization of Nonlinear RNN | nonlinear-RNNs, parallel-evaluation, fixed-point-iteration | 0b2b199fdd52089b31d3a0120e400b2a.md |
| 37 | LLMs as Zero-shot Graph Learners: Alignment of GNN Represent | zero-shot-learning, graph-neural-networks, LLM-alignment | 0b77d3a82b59e9d9899370b378087faf.md |
| 38 | KnowGPT: Knowledge Graph based Prompting for Large Language  | knowledge-graphs, prompting, hallucination-reduction | 0b8705a611ed1ce19cdb759031078705.md |
| 39 | A Prompt-Based Knowledge Graph Foundation Model for Universa | knowledge-graphs, in-context-reasoning, foundation-model | 0d70af566e69f1dfb687791ecf955e28.md |
| 40 | You Only Cache Once: Decoder-Decoder Architectures for Langu | kv-cache, decoder-decoder, efficient-inference | 0df38cd13520747e1e64e5b123a78ef8.md |
| 41 | Understanding Information Storage and Transfer in Multi-Moda | mechanistic-interpretability, information-storage, multimodal-llm | 0dfe31d6e703e138d46a7d2fced38b7c.md |
| 42 | Make Continual Learning Stronger via C-Flat | continual-learning, catastrophic-forgetting, loss-landscape | 0e705ac30e573d1526f81a0fd071a151.md |
| 43 | Limits of Transformer Language Models on Learning to Compose | transformers, compositional-reasoning, algorithmic-tasks | 0e797d5139ad94fc2dc2080c09119f29.md |
| 44 | MaskLLM: Learnable Semi-Structured Sparsity for Large Langua | model-pruning, semi-structured-sparsity, LLM-compression | 0e9a05f5ce62284c91e4a33498899124.md |
| 45 | In-Context Learning State Vector with Inner and Momentum Opt | in-context-learning, state-vectors, momentum-optimization | 0ed52d7f6f641f228405d48a611e0684.md |
| 46 | DART-Math: Difficulty-Aware Rejection Tuning for Mathematica | mathematical-reasoning, rejection-tuning, difficulty-aware | 0ef1afa0daa888d695dcd5e9513bafa3.md |
| 47 | Visual Prompt Tuning in Null Space for Continual Learning | continual-learning, prompt-tuning, null-space | 0f06be0008bc568c88d76206aa17954f.md |
| 48 | Kraken: Inherently Parallel Transformers For Efficient Multi | transformer-inference, parallelism, multi-device | 0f4d1fc085b7504c140e66bb26ed8842.md |
| 49 | SDP4Bit: Toward 4-bit Communication Quantization in Sharded  | quantization, sharded-data-parallelism, llm-training | 10826a1a80f816ea98d559d7c7a97973.md |
| 50 | AlphaPruning: Using Heavy-Tailed Self Regularization Theory  | LLM-pruning, heavy-tailed-self-regularization, layer-wise-pruning | 10fc83943b4540a9524af6fc67a23fef.md |
| 51 | LoFiT: Localized Fine-tuning on LLM Representations | representation-intervention, attention-heads, parameter-efficient | 122ea6470232ee5e79a2649243348005.md |
| 52 | HydraLoRA: An Asymmetric LoRA Architecture for Efficient Fin | lora, asymmetric-architecture, parameter-efficient-fine-tuning | 123fd8a56501194823c8e0dca00733df.md |
| 53 | Spiking Transformer with Experts Mixture | spiking-neural-networks, mixture-of-experts, energy-efficient-deep-learning | 137101016144540ed3191dc2b02f09a5.md |
| 54 | TSDS: Data Selection for Task-Specific Model Finetuning | data-selection, fine-tuning, foundation-models | 13848b5893119ff772b69812c95914fa.md |
| 55 | Masked Hard-Attention Transformers Recognize Exactly the Sta | transformers, formal-languages, expressive-power | 13d7f172259b11b230cc5da8768abc5f.md |
| 56 | Exploring Context Window of Large Language Models via Decomp | large-language-models, context-window, positional-encoding | 1403ab1a427050538ec59c7f570aec8b.md |
| 57 | Stacking Your Transformers: A Closer Look at Model Growth fo | model-growth, llm-pretraining, efficient-training | 143ea4a156ef64f32d4d905206cf32e1.md |
| 58 | Layer-Adaptive State Pruning for Deep State Space Models | state-space-models, structured-pruning, state-dimension-optimization | 14730e0dd6ac1c4a5765310909fd51b1.md |
| 59 | I Don't Know: Explicit Modeling of Uncertainty with an [IDK] | hallucination, uncertainty-modeling, idk-token | 14c018d2e72c521605b0567029ef0efb.md |
| 60 | Selective Attention: Enhancing Transformer through Principle | selective-attention, transformer, context-control | 14fc4a68da97a3d31eb11c642b0b10fc.md |
| 61 | EffiBench: Benchmarking the Efficiency of Automatically Gene | code-generation, efficiency-benchmarking, green-computing | 15807b6e09d691fe5e96cdecde6d7b80-abstract-datasetsandbenchmarkstrackhtml.md |
| 62 | A Gradient Accumulation Method for Dense Retriever under Mem | dense-retrieval, InfoNCE-loss, gradient-accumulation | 15ba84c1e19b0eb75f96922f5da0a021.md |
| 63 | Kangaroo: Lossless Self-Speculative Decoding for Acceleratin | speculative-decoding, early-exit, inference-acceleration | 16336d94a5ffca8de019087ab7fe403f.md |
| 64 | MoE Jetpack: From Dense Checkpoints to Adaptive Mixture of E | mixture-of-experts, dense-to-MoE, vision-tasks | 167bcf2af2cd08fcf75b932022db0311.md |
| 65 | The Importance of Online Data: Understanding Preference Fine | preference-fine-tuning, online-RL, data-coverage | 16c628ab12dc4caca8e7712affa6c767.md |
| 66 | Scaling the Codebook Size of VQ-GAN to 100,000 with a Utiliz | codebook-scaling, vector-quantization, image-tokenization | 1716d022edeac750e57a2986a7135e13.md |
| 67 | Representation Noising: A Defence Mechanism Against Harmful  | harmful-finetuning, representation-noising, llm-safety | 172be8b0b88fc2b4aee74237d43f8c04.md |
| 68 | CV-VAE: A Compatible Video VAE for Latent Generative Video M | video-vae, latent-generative-models, spatio-temporal-compression | 1787533e171dcc8549cc2eb5a4840eec.md |
| 69 | Learning to grok: Emergence of in-context learning and skill | in-context-learning, modular-arithmetic, skill-composition | 17d60fef592086d1a5cb136f1946df59.md |
| 70 | On improved Conditioning Mechanisms and Pre-training Strateg | latent-diffusion, conditioning-mechanisms, pretraining | 18023809c155d6bbed27e443043cdebf.md |
| 71 | $\texttt{Model-GLUE}$: Democratized LLM Scaling for A Large  | llm-scaling, model-merging, model-zoo | 180a476f22a52b8ef14f42b2b927afcc-abstract-datasetsandbenchmarkstrackhtml.md |
| 72 | BitDelta: Your Fine-Tune May Only Be Worth One Bit | model-compression, fine-tuning, one-bit-quantization | 187d94b3c93343f0e925b5cf729eadd5.md |
| 73 | Fast and Memory-Efficient Video Diffusion Using Streamlined  | video-diffusion, memory-efficient-inference, streamlined-generation | 18b0b4c788c8f2cf6c2943b989ad18c8.md |
| 74 | Sparse High Rank Adapters | LoRA, sparse-adapters, high-rank-adaptation | 18c0102cb7f1a02c14f0929089b2e576.md |
| 75 | Alignment at Pre-training! Towards Native Alignment for Arab | arabic-llm, pre-training-alignment, native-alignment | 195c4e2910bedabd813f9fe4e70c642c.md |
| 76 | DataComp-LM: In search of the next generation of training se | language-model-pretraining, dataset-curation, benchmark | 19e4ea30dded58259665db375885e412-abstract-datasetsandbenchmarkstrackhtml.md |
| 77 | Leveraging Visual Tokens for Extended Text Contexts in Multi | multimodal-learning, visual-tokens, extended-context | 19f10adb6749b0c9f1ff7610bd01d44d.md |
| 78 | Federated Fine-tuning of Large Language Models under Heterog | federated-learning, lora, llm-finetuning | 1a134b50202088aa8c595cc99b310e5a.md |
| 79 | Catastrophic Goodhart: regularizing RLHF with KL divergence  | rlhf, reward-misspecification, kl-regularization | 1a8189929f3d7bd6183718f42c3f4309.md |
| 80 | Language Models as Hierarchy Encoders | hierarchy-encoding, language-models, hyperbolic-embeddings | 1a970a3e62ac31c76ec3cea3a9f68fdf.md |
| 81 | BLAST: Block-Level Adaptive Structured Matrices for Efficien | structured-matrices, efficient-inference, block-level-adaptation | 1b2df10d5bc3ca563339c801fa2e14db.md |
| 82 | CLIPLoss and Norm-Based Data Selection Methods for Multimoda | data-selection, clip, multimodal-contrastive-learning | 1b33deb9e1e7c31f05300b1c2d4a4f7d.md |
| 83 | Entity Alignment with Noisy Annotations from Large Language  | entity-alignment, knowledge-graphs, noisy-labels | 1b57aaddf85ab01a2445a79c9edc1f4b.md |
| 84 | How do Large Language Models Handle Multilingualism? | multilingualism, large-language-models, layer-analysis | 1bd359b32ab8b2a6bbafa1ed2856cf40.md |
| 85 | Benchmarking LLMs via Uncertainty Quantification | LLM-evaluation, uncertainty-quantification, benchmarking | 1bdcb065d40203a00bd39831153338bb-abstract-datasetsandbenchmarkstrackhtml.md |
| 86 | ChatQA: Surpassing GPT-4 on Conversational QA and RAG | retrieval-augmented-generation, conversational-QA, instruction-tuning | 1c0d54ebd0a6e58c4eca7d591e374b9d.md |
| 87 | HYSYNTH: Context-Free LLM Approximation for Guiding Program  | program-synthesis, LLM-approximation, domain-specific-language | 1c9c85bae6161d52182d0fe2f3640512.md |
| 88 | Enhancing Multiple Dimensions of Trustworthiness in LLMs via | sparse-activation, trustworthiness, llm-alignment | 1cb5b3d64bdf3c6642c8d9a8fbecd019.md |
| 89 | Stress-Testing Long-Context Language Models with Lifelong IC | long-context-llm, in-context-learning, evaluation-suite | 1cc8db5884a7474b4771762b6f0c8ee1-abstract-datasetsandbenchmarkstrackhtml.md |
| 90 | Embedding-Aligned Language Models | reinforcement-learning, embedding-alignment, language-model-training | 1ce12df021f8fb43cf531c556efcebdc.md |
| 91 | SpecExec: Massively Parallel Speculative Decoding For Intera | speculative-decoding, llm-inference, consumer-hardware | 1d91d5689e251d27993a3c2182dddcf7.md |
| 92 | From Unstructured Data to In-Context Learning: Exploring Wha | in-context-learning, transformers, unstructured-data | 1da38b872e19f1f4a3c2846720e8f64a.md |
| 93 | Are Large-scale Soft Labels Necessary for Large-scale Datase | dataset-distillation, soft-labels, knowledge-distillation | 1da9ca7e9cef4b1af63913f05d1630a4.md |
| 94 | On the Noise Robustness of In-Context Learning for Text Gene | in-context-learning, noise-robustness, demonstrations | 1dd8ea647d80e38b3702cf01a0855bed.md |
| 95 | Mercury: A Code Efficiency Benchmark for Code Large Language | code-efficiency, benchmark, code-llm | 1df1df43b58845650b8dada00fca9772-abstract-datasetsandbenchmarkstrackhtml.md |
| 96 | Loki: Low-rank Keys for Efficient Sparse Attention | sparse-attention, low-rank, kv-cache | 1e027da6bec9ceb2ec37951ceeccae93.md |
| 97 | VB-LoRA: Extreme Parameter Efficient Fine-Tuning with Vector | parameter-efficient-fine-tuning, lora, vector-bank | 1e0d38c676d5855bcfab7f6d29d20ad9.md |
| 98 | GlotCC: An Open Broad-Coverage CommonCrawl Corpus and Pipeli | minority-languages, CommonCrawl, multilingual-corpus | 1e6057620ed314b0020b3a30284b0f83-abstract-datasetsandbenchmarkstrackhtml.md |
| 99 | Automating Dataset Updates Towards Reliable and Timely Evalu | llm-evaluation, benchmark-automation, dataset-updating | 1e89c12621c0315373f20f0aeabe5dbe-abstract-datasetsandbenchmarkstrackhtml.md |
| 100 | ESPACE: Dimensionality Reduction of Activations for Model Co | llm-compression, activation-dimensionality-reduction, principal-components | 1f6591cc41be737e9ba4cc487ac8082d.md |
| 101 | Shopping MMLU: A Massive Multi-Task Online Shopping Benchmar | benchmark, online-shopping, multi-task | 2049d75dd13db049897562bcf7d59da8-abstract-datasetsandbenchmarkstrackhtml.md |
| 102 | The Representation Landscape of Few-Shot Learning and Fine-T | in-context-learning, fine-tuning, representation-analysis | 206018a258033def63607fbdf364bd2d.md |
| 103 | In-Context Learning of a Linear Transformer Block: Benefits  | in-context-learning, linear-transformer, MLP-component | 20b6b87ca17792337f414d948af7b0e8.md |
| 104 | Finding Transformer Circuits With Edge Pruning | circuit-discovery, edge-pruning, mechanistic-interpretability | 20fdaf67581e6d7157376d1ed584040a.md |
| 105 | WaterMax: breaking the LLM watermark detectability-robustnes | LLM-watermarking, detectability, robustness | 21b5883bc8fec922fdbbb06675388164.md |
| 106 | SOI: Scaling Down Computational Complexity by Estimating Par | model-compression, MCU, partial-state-estimation | 2277e2c5d7d20f847c2b7d5f9075ce30.md |
| 107 | Metacognitive Capabilities of LLMs: An Exploration in Mathem | metacognition, llm-reasoning, mathematical-problem-solving | 2318d75a06437eaa257737a5cf3ab83c.md |
| 108 | DropBP: Accelerating Fine-Tuning of Large Language Models by | fine-tuning, backward-propagation, llm-efficiency | 240225294cdd2c9b692c2519d3278a08.md |
| 109 | MemoryFormer : Minimize Transformer Computation by Removing  | transformer-efficiency, memory-lookup, removing-ffn | 24143e25a82f856aeed58b2f497d623b.md |
| 110 | Learning and Transferring Sparse Contextual Bigrams with Lin | linear-transformers, in-context-learning, sparse-bigram | 2428ff361a08bc6864fb240bc83fba42.md |
| 111 | Edit Distance Robust Watermarks via Indexing Pseudorandom Co | watermarking, llm-output, edit-distance | 24c53bfa5b53fc2cf05644f5a7a26bb0.md |
| 112 | Active Learning with LLMs for Partially Observed and Cost-Aw | active-learning, llm, cost-aware | 24f3041067ab24157912330344dc3bbd.md |
| 113 | Watermarking Makes Language Models Radioactive | watermarking, radioactivity, synthetic-data-detection | 2567c95fd41459a98a73ba893775d22a.md |
| 114 | Nimbus: Secure and Efficient Two-Party Inference for Transfo | secure-two-party-computation, transformers, privacy-preserving-inference | 264a9b3ce46abdf572dcfe0401141989.md |
| 115 | Multimodal Task Vectors Enable Many-Shot Multimodal In-Conte | multimodal-in-context-learning, task-vectors, large-multimodal-models | 27571b74d6cd650b8eb6cf1837953ae8.md |
| 116 | SnapKV: LLM Knows What You are Looking for Before Generation | kv-cache-compression, long-context-llm, memory-efficiency | 28ab418242603e0f7323e54185d19bde.md |
| 117 | Boosting the Potential of Large Language Models with an Inte | retrieval-augmented-generation, hallucination-mitigation, information-assistant | 28d38c036365420f61ce03300418e44a.md |
| 118 | Unified Generative and Discriminative Training for Multi-mod | vision-language-models, generative-discriminative-training, multimodal-llm | 29416b66c2149872b9d1415a3fd2c5e0.md |
| 119 | Why Do We Need Weight Decay in Modern Deep Learning? | weight-decay, regularization, deep-learning-optimization | 29496c942ed6e08ecc469f4521ebfff0.md |
| 120 | Efficient LLM Jailbreak via Adaptive Dense-to-sparse Constra | jailbreak-attack, adversarial-optimization, llm-safety | 29571f8fda54fe93631c41aad4215abc.md |
| 121 | DeepStack: Deeply Stacking Visual Tokens is Surprisingly Sim | visual-token-compression, large-multimodal-models, deep-stacking | 29cd7f8331d13ede6dc6d6ef3dfacb70.md |
| 122 | Neuro-Symbolic Data Generation for Math Reasoning | math-reasoning, neuro-symbolic, data-generation | 29d319f7c1513c9ecd81d3a6e9632a6e.md |
| 123 | Vision Model Pre-training on Interleaved Image-Text Data via | vision-pretraining, interleaved-image-text, latent-compression | 2a952768bb85041f95ed06a5b60cf4d5.md |
| 124 | The Implicit Bias of Adam on Separable Data | Adam-optimizer, implicit-bias, logistic-regression | 2ac79356a03fe5e9250e5e77ebc76e6e.md |
| 125 | Be like a Goldfish, Don't Memorize! Mitigating Memorization  | memorization-mitigation, goldfish-loss, LLM-privacy | 2ad2dffba5079687651226ac8752df97.md |
| 126 | SIRIUS : Contexual Sparisty with Correction for Efficient LL | contextual-sparsity, LLM-inference, efficiency | 2ae6b2bdf3a179e3e24129e2c54bd871.md |
| 127 | Transcoders find interpretable LLM feature circuits | mechanistic-interpretability, circuit-analysis, transcoders | 2b8f4db0464cc5b6e9d5e6bea4b9f308.md |
| 128 | ShiftAddLLM: Accelerating Pretrained LLMs via Post-Training  | llm-compression, shift-add-reparameterization, post-training-quantization | 2c30a37c75f062e0bf79297c73db8c6c.md |
| 129 | BAdam: A Memory Efficient Full Parameter Optimization Method | block-coordinate-descent, memory-efficient-optimization, llm-finetuning | 2c570b0f9938c7a58a612e5b00af9cc0.md |
| 130 | Pre-trained Large Language Models Use Fourier Features to Co | fourier-features, arithmetic-reasoning, mechanistic-interpretability | 2cc8dc30e52798b27d37b795cc153310.md |
| 131 | DETAIL: Task DEmonsTration Attribution for Interpretable In- | in-context-learning, demonstration-attribution, interpretability | 2ceda49041816da6d5a34eb3b612607f.md |
| 132 | MathPile: A Billion-Token-Scale Pretraining Corpus for Math | math-pretraining, corpus-curation, foundation-models | 2d0be3cd5173c10b6ec075d1c393a13d-abstract-datasetsandbenchmarkstrackhtml.md |
| 133 | Automated Multi-level Preference for MLLMs | multimodal-LLMs, hallucination, RLHF | 2e3073cb65608aa887bb945c382e687f.md |
| 134 | LINGOLY: A Benchmark of Olympiad-Level Linguistic Reasoning  | benchmark, linguistic-reasoning, low-resource-languages | 2e43584b7d7b32fb6b2aa83b32dbbb20-abstract-datasetsandbenchmarkstrackhtml.md |
| 135 | Cluster-Learngene: Inheriting Adaptive Clusters for Vision T | knowledge-inheritance, vision-transformers, adaptive-clustering | 2e53c02ea028cbf603f4b6b47fef3d97.md |
| 136 | DAPE: Data-Adaptive Positional Encoding for Length Extrapola | positional-encoding, length-extrapolation, transformers | 2f050fa9f0d898e3f265d515f50ae8f9.md |
| 137 | LLM-ESR: Large Language Models Enhancement for Long-tailed S | sequential-recommendation, long-tail, large-language-models | 2f0728449cb3150189d765fc87afc913.md |
| 138 | On Softmax Direct Preference Optimization for Recommendation | recommendation, direct-preference-optimization, language-model | 30732ddb12d9faf7180f5d0e8b5b5da7.md |
| 139 | Quantifying and Optimizing Global Faithfulness in Persona-dr | persona-driven-roleplay, faithfulness, LLM-evaluation | 309cadc33589efca4018a490c07db263.md |
| 140 | AlphaMath Almost Zero: Process Supervision without Process | LLM, mathematical-reasoning, process-supervision | 30dfe47a3ccbee68cffa0c19ccb1bc00.md |
| 141 | Don't Look Twice: Faster Video Transformers with Run-Length  | video-transformers, token-compression, run-length-encoding | 3181db351fd3ced43cd589b0b572675d.md |
| 142 | Value-Based Deep Multi-Agent Reinforcement Learning with Dyn | multi-agent-reinforcement-learning, sparse-training, model-compression | 31888563b194f9bb33ce1aebc7e1551c.md |
| 143 | Rethinking Memory and Communication Costs for Efficient Data | distributed-training, large-language-models, data-parallelism | 318f3ae8be3c97cb7555e1c932f472a1.md |
| 144 | Perplexity-aware Correction for Robust Alignment with Noisy  | llm-alignment, noisy-preferences, perplexity | 31a57804448363bcab777f818f75f5b4.md |
| 145 | MoEUT: Mixture-of-Experts Universal Transformers | universal-transformers, mixture-of-experts, parameter-sharing | 321387ba926b8e58d3591c0aeb52ffc2.md |
| 146 | Visual Perception by Large Language Model’s Weights | multimodal-llm, visual-perception, weight-encoding | 322e4a595afd9442a89f0bfaa441871e.md |
| 147 | Enhancing LLM Reasoning via Vision-Augmented Prompting | visual-augmented-prompting, chain-of-thought, multimodal-reasoning | 328c922d068dd4ccb23cec5c64e6c7fc.md |
| 148 | MomentumSMoE: Integrating Momentum into Sparse Mixture of Ex | mixture-of-experts, momentum-optimization, sparse-routing | 32eb183794ef5ef9a3ab1d40a3d2b303.md |
| 149 | Not All Tokens Are What You Need for Pretraining | selective-pretraining, token-importance, next-token-prediction | 3322a9a72a1707de14badd5e552ff466.md |
| 150 | Chain of Thoughtlessness? An Analysis of CoT in Planning | chain-of-thought, planning, out-of-distribution-generalization | 3365d974ce309623bd8151082d78206c.md |
| 151 | A Critical Evaluation of AI Feedback for Aligning Large Lang | LAIF, RLHF, alignment-evaluation | 33870b3e099880cd8e705cd07173ac27.md |
| 152 | Global Convergence in Training Large-Scale Transformers | transformer-optimization, gradient-flow, weight-decay | 33b47b3d2441a17b95344cd635f3dd01.md |
| 153 | Self-Taught Recognizer: Toward Unsupervised Adaptation for S | automatic-speech-recognition, unsupervised-adaptation, self-training | 347110fb894281e5e937f6ccd998a6eb.md |
| 154 | Protecting Your LLMs with Information Bottleneck | LLM-safety, information-bottleneck, jailbreaking | 34a1fc7890141f1ada3d8bc6199cce07.md |
| 155 | Time-Reversal Provides Unsupervised Feedback to LLMs | LLM-feedback, time-reversal, unsupervised-critique | 34aec5ab2f99a8f592e0cca4974013f2.md |
| 156 | Model Fusion through Bayesian Optimization in Language Model | model-fusion, bayesian-optimization, fine-tuning | 34d3cf97696022b179171e5abda42c0b.md |
| 157 | On Giant's Shoulders: Effortless Weak to Strong by Dynamic L | weak-to-strong, logits-fusion, parameter-efficient-fine-tuning | 34ec1286b2ccd4794c5ca4ad078b7150.md |
| 158 | Heavy-Tailed Class Imbalance and Why Adam Outperforms Gradie | adam-optimizer, heavy-tailed, class-imbalance | 350e718ff74062b4bac2c6ffd9e1ac66.md |
| 159 | Binarized Diffusion Model for Image Super-Resolution | diffusion-models, image-super-resolution, binarization | 3685de48976169ca9fd68cb4c8e48b76.md |
| 160 | Accelerating Transformers with Spectrum-Preserving Token Mer | token-merging, transformer-efficiency, spectrum-preserving | 37094fdc81632915a5738293cf9b7ad4.md |
| 161 | The FineWeb Datasets: Decanting the Web for the Finest Text  | pretraining-data, web-text-curation, data-quality | 370df50ccfdf8bde18f8f9c2d9151bda-abstract-datasetsandbenchmarkstrackhtml.md |
| 162 | Should We Really Edit Language Models? On the Evaluation of  | model-editing, language-models, evaluation | 370fa2e691f57eb319bc263a07dad4a5.md |
| 163 | Seeing the Image: Prioritizing Visual Correlation by Contras | vision-language-models, contrastive-alignment, cross-modal | 37294f033582ac0064bf90fa557c2573.md |
| 164 | Delta-CoMe: Training-Free Delta-Compression with Mixed-Preci | delta-compression, mixed-precision, fine-tuned-LLMs | 37664246a1e07e212ddacea6e5a523f2.md |
| 165 | EPIC: Effective Prompting for Imbalanced-Class Data Synthesi | llm, synthetic-data, imbalanced-classification | 37f2f382b1e1f1e887d610e7ea047086.md |
| 166 | Transformers to SSMs: Distilling Quadratic Knowledge to Subq | knowledge-distillation, state-space-models, transformers | 3848fef259495bfd04d60cdc5c1b4db7.md |
| 167 | Wings: Learning Multimodal LLMs without Text-only Forgetting | multimodal-llm, catastrophic-forgetting, text-image-alignment | 3852f6d247ba7deb46e4e4be9e702601.md |
| 168 | Dual Prototype Evolving for Test-Time Generalization of Visi | test-time-adaptation, vision-language-models, prototype-learning | 38b787fc530d0b31825827e2cc306656.md |
| 169 | Fast Best-of-N Decoding via Speculative Rejection | best-of-n, speculative-decoding, llm-alignment | 3950f6bf5c2eb7435ecf58eaa85cc8c2.md |
| 170 | Where does In-context Learning Happen in Large Language Mode | in-context-learning, llm-interpretability, task-localization | 3979818cdc7bc8dbeec87170c11ee340.md |
| 171 | Improved Few-Shot Jailbreaking Can Circumvent Aligned Langua | jailbreaking, few-shot, llm-safety | 39a3aa9dfd0280ff8fbad1d330662cac.md |
| 172 | DiMSUM: Diffusion Mamba - A Scalable and Unified Spatial-Fre | diffusion-models, mamba, spatial-frequency | 39bc6e3cbf5a1991d33dc10ebff9a9cf.md |
| 173 | Graph-based Uncertainty Metrics for Long-form Language Model | hallucination, uncertainty-estimation, graph-based-methods | 39c5871aa13be86ab978cba7069cbcec.md |
| 174 | S-STE: Continuous Pruning Function for Efficient 2:4 Sparse  | sparse-training, 2:4-sparsity, straight-through-estimator | 3b576711b12ab036b45130fc8eb78504.md |
| 175 | Sparse maximal update parameterization: A holistic approach  | sparse-training, maximal-update-parameterization, training-dynamics | 3b6aaffec941f98930753fa6d6de7263.md |
| 176 | Efficient Sign-Based Optimization: Accelerating Convergence  | signSGD, variance-reduction, convergence-acceleration | 3b7db05c0e383518d789b6e93131f1f0.md |
| 177 | Vector Quantization Prompting for Continual Learning | continual-learning, vector-quantization, prompt-tuning | 3baf4eeffad860ca9c54aeab632716b4.md |
| 178 | MindMerger: Efficiently Boosting LLM Reasoning in non-Englis | multilingual-LLM, reasoning, non-English | 3bf80b34f731313b8292f4578e820c90.md |
| 179 | Accelerating Blockwise Parallel Language Models with Draft R | speculative-decoding, blockwise-parallel-decoding, inference-acceleration | 3c9629e718d931e8d4d240378aa1d3bf.md |
| 180 | SpeedLoader: An I/O efficient scheme for heterogeneous and d | llm-inference, heterogeneous-systems, i/o-efficiency | 3d3a9e085540c65dd3e5731361f9320e.md |
| 181 | OpenMathInstruct-1: A 1.8 Million Math Instruction Tuning Da | math-instruction-tuning, synthetic-dataset, llm-training | 3d5aa9a7ce28cdc710fbd044fd3610f3-abstract-datasetsandbenchmarkstrackhtml.md |
| 182 | Rule Extrapolation in Language Modeling: A Study of Composit | compositional-generalization, in-context-learning, transformer-architecture | 3d9ef68629089da055334c2d41dfcf93.md |
| 183 | 3-in-1: 2D Rotary Adaptation for Efficient Finetuning, Effic | parameter-efficient-finetuning, rotary-adaptation, lora | 3dbcadb7beedc2afe32bb23f75dd30ec.md |
| 184 | LeDex: Training LLMs to Better Self-Debug and Explain Code | code-generation, self-debugging, llm-code-explanation | 3ea832724870c700f0a03c665572e2a9.md |
| 185 | OccamLLM: Fast and Exact Language Model Arithmetic in a Sing | LLM-arithmetic, exact-computation, tool-augmented-reasoning | 3eceb70f47690051d6769739fbf6294b.md |
| 186 | NewTerm: Benchmarking Real-Time New Terms for Large Language | LLM-benchmarking, real-time-knowledge, knowledge-cutoff | 3eec719ab86712d32b065c5977f94ad0-abstract-datasetsandbenchmarkstrackhtml.md |
| 187 | Infinite Limits of Multi-head Transformer Dynamics | transformer-dynamics, infinite-width, feature-learning | 3eff068e195daace49955348de9f8398.md |
| 188 | Dataset Decomposition: Faster LLM Training with Variable Seq | LLM-training, variable-sequence-length, curriculum-learning | 3f9bf45ea04c98ad7cb857f951f499e2.md |
| 189 | Mobility-LLM: Learning Visiting Intentions and Travel Prefer | mobility-data, large-language-models, location-based-services | 3fb6c52aeb11e09053c16eabee74dd7b.md |
| 190 | Learning to Reason via Program Generation, Emulation, and Se | program-synthesis, language-models, reasoning | 401ece9f5d1cfa8600c22049ef43930e.md |
| 191 | Interpreting Learned Feedback Patterns in Large Language Mod | RLHF, learned-feedback-patterns, LLM-interpretability | 403bf224290de69c7d5dc856f5a99d9e.md |
| 192 | Unpacking DPO and PPO: Disentangling Best Practices for Lear | DPO, PPO, preference-learning | 404df2480b6eef0486a1679e371894b0.md |
| 193 | MINT-1T: Scaling Open-Source Multimodal Data by 10x: A Multi | multimodal-dataset, interleaved-image-text, large-scale-pretraining | 40b9196c25fe1d64d87ca3a80a91d0ce-abstract-datasetsandbenchmarkstrackhtml.md |
| 194 | StackEval: Benchmarking LLMs in Coding Assistance | llm-benchmarking, coding-assistance, software-engineering | 4126a607bbe2836cb6ca0eb45b75618b-abstract-datasetsandbenchmarkstrackhtml.md |
| 195 | Towards Exact Gradient-based Training on Analog In-memory Co | analog-computing, in-memory-computing, gradient-based-training | 419f72cbd568ad62183f8132a3605a2a.md |
| 196 | Aligning Large Language Models with Representation Editing:  | llm-alignment, representation-editing, control-theory | 41bba7b0f5c81e789a20bb16a370aeeb.md |
| 197 | ALPS: Improved Optimization for Highly Sparse One-Shot Pruni | LLM-pruning, sparse-optimization, one-shot | 4241c27d3161c7a7064bfc1a6e539563.md |
| 198 | Reinforcement Learning Gradients as Vitamin for Online Finet | decision-transformer, online-finetuning, RL-gradients | 43f5f6c5cb333115914c8448b8506411.md |
| 199 | Enhancing In-Context Learning Performance with just SVD-Base | in-context-learning, weight-pruning, SVD | 448444518637da106d978ae7409d9789.md |
| 200 | $\boldsymbol{\mu}\mathbf{P^2}$: Effective Sharpness Aware Mi | sharpness-aware-minimization, infinite-width, layerwise-scaling | 449a016a6ce6fba3fe50d05482abf836.md |
| 201 | BiDM: Pushing the Limit of Quantization for Diffusion Models | quantization, diffusion-models, compression | 44b61c5c0ba06d55ab5a1cfb9cfff763.md |
| 202 | EEGPT: Pretrained Transformer for Universal and Reliable Rep | EEG, pretrained-transformer, brain-computer-interface | 4540d267eeec4e5dbd9dae9448f0b739.md |
| 203 | L-TTA: Lightweight Test-Time Adaptation Using a Versatile St | test-time-adaptation, entropy-minimization, stem-layer | 458d9f2dd5c7565af60143630dc62f10.md |
| 204 | SlimSAM: 0.1% Data Makes Segment Anything Slim | model-compression, pruning, segment-anything | 45a7ca247462d9e465ee88c8a302ca70.md |
| 205 | Robust Prompt Optimization for Defending Language Models Aga | jailbreaking, prompt-optimization, adversarial-robustness | 46ed503889ab232c21c1162340ee17b2.md |
| 206 | HydraViT: Stacking Heads for a Scalable ViT | vision-transformers, multi-head-attention, scalability | 47387bb0aeb97785f608c11f2f4bb091.md |
| 207 | Meteor: Mamba-based Traversal of Rationale for Large Languag | mamba, vision-language-model, rationale-traversal | 473a9a75edc46eff5ff224d53d5f7294.md |
| 208 | The Scandinavian Embedding Benchmarks: Comprehensive Assessm | text-embeddings, multilingual-benchmark, Scandinavian-languages | 4746bb91bd073ec7eef930d5775122ba-abstract-datasetsandbenchmarkstrackhtml.md |
| 209 | LLM Circuit Analyses Are Consistent Across Training and Scal | mechanistic-interpretability, circuit-analysis, LLM-training-dynamics | 47c7edadfee365b394b2a3bd416048da.md |
| 210 | Yo'LLaVA: Your Personalized Language and Vision Assistant | personalized-LMM, visual-question-answering, subject-recognition | 48088756ec0ce6ba362bddc7ebeb3915.md |
| 211 | Compact Language Models via Pruning and Knowledge Distillati | LLM-pruning, knowledge-distillation, model-compression | 4822991365c962105b1b95b1107d30e5.md |
| 212 | Verified Code Transpilation with LLMs | code-transpilation, LLMs, domain-specific-languages | 48bb60a0c0aebb4142bf314bd1a5c6a0.md |
| 213 | SVFT: Parameter-Efficient Fine-Tuning with Singular Vectors | parameter-efficient-fine-tuning, singular-vectors, LoRA | 48c368f105e8145b945227b73255635a.md |
| 214 | Exploiting LLM Quantization | LLM-quantization, adversarial-attacks, security | 496720b3c860111b95ac8634349dcc88.md |
| 215 | MoME: Mixture of Multimodal Experts for Generalist Multimoda | multimodal-LLMs, mixture-of-experts, vision-language | 4a3a14b9536806a0522930007c5512f7.md |
| 216 | Understanding Scaling Laws with Statistical and Approximatio | scaling-laws, transformers, approximation-theory | 4a68bb0e075a3215d4ff37382ea598dc.md |
| 217 | VeLoRA: Memory Efficient Training using Rank-1 Sub-Token Pro | memory-efficient-training, LoRA, rank-1-projections | 4a9eaf6dff3fdac9ab1aaf4c0fe2d563.md |
| 218 | Slicing Vision Transformer for Flexible Inference | vision-transformer, slimmable-network, dynamic-inference | 4b296975eaa172a94e03538094da6a66.md |
| 219 | Revisiting the Integration of Convolution and Attention for  | vision-backbone, convolution-attention-integration, multi-scale | 4b70484ebef62484e0c8cdd269e482fd.md |
| 220 | RL on Incorrect Synthetic Data Scales the Efficiency of LLM  | synthetic-data, math-reasoning, reinforcement-learning | 4b77d5b896c321a29277524a98a50215.md |
| 221 | Exploiting Activation Sparsity with Dense to Dynamic-k Mixtu | mixture-of-experts, activation-sparsity, inference-efficiency | 4c2092ec0b1370cce3fb5965ab255fae.md |
| 222 | Sketchy Moment Matching: Toward Fast and Provable Data Selec | data-selection, finetuning, moment-matching | 4c79c359b3c5f077c0b955f93cb0f53e.md |
| 223 | ReEvo: Large Language Models as Hyper-Heuristics with Reflec | hyper-heuristics, combinatorial-optimization, llm-code-generation | 4ced59d480e07d290b6f29fc8798f195.md |
| 224 | Policy Improvement using Language Feedback Models | language-feedback, imitation-learning, instruction-following | 4d4f7cf206bb00f9a38a5b6ae92cf79a.md |
| 225 | Is Programming by Example Solved by LLMs? | programming-by-example, inductive-synthesis, few-shot-learning | 4eff61b79274124bc71efe2ee9772f95.md |
| 226 | Be Confident in What You Know: Bayesian Parameter Efficient  | bayesian-inference, parameter-efficient-fine-tuning, uncertainty-estimation | 4f1fbd5ab8d58d0ecf33c95fd46b900e.md |
| 227 | Large Scale Transfer Learning for Tabular Data  via Language | tabular-data, language-modeling, transfer-learning | 4fd5cfd2e31bebbccfa5ffa354c04bdc.md |
| 228 | ControlMLLM: Training-Free Visual Prompt Learning for Multim | visual-prompting, multimodal-LLMs, training-free | 4fd96b997454b5b02698595df70fccaf.md |
| 229 | Can Language Models Learn to Skip Steps? | chain-of-thought, step-skipping, reasoning | 504fa7e518da9d1b53a233ed20a38b46.md |
| 230 | Enhancing Domain Adaptation through Prompt Gradient Alignmen | domain-adaptation, prompt-learning, gradient-alignment | 50ea4cf434c84a50203d7145afc7b853.md |
| 231 | From Instance Training to Instruction Learning: Task Adapter | instruction-finetuning, task-adapters, LLM | 50ea4dbd1cff6bd3daef939eff10c092.md |
| 232 | Federated Transformer: Multi-Party Vertical Federated Learni | vertical-federated-learning, fuzzy-entity-linking, transformer | 5141f6bc105d30edbae48f1d2e0b1e66.md |
| 233 | DHA: Learning Decoupled-Head Attention from Transformer Chec | multi-head-attention, head-fusion, LLM-inference | 518a75257f37b32f711082dff33c2ffc.md |
| 234 | SparseLLM: Towards Global Pruning of Pre-trained Language Mo | llm-pruning, global-sparsity, compression | 522134ee1c52c7a2b929bc87cfe1781c.md |
| 235 | Pipeline Parallelism with Controllable Memory | pipeline-parallelism, memory-control, distributed-training | 527dad0b9159805289906d5740a0bdd3.md |
| 236 | Gradient-based Discrete Sampling with Automatic Cyclical Sch | discrete-sampling, gradient-based-mcmc, cyclical-scheduling | 5301c49207917c5c870131959971851c.md |
| 237 | Zero-Shot Tokenizer Transfer | tokenizer-transfer, zero-shot, language-models | 532ce4fcf853023c4cf2ac38cbc5d002.md |
| 238 | Exploring Molecular Pretraining Model at Scale | molecular-pretraining, scaling-laws, self-supervised-learning | 53923bb44655a7defb31c7744c01b62b.md |
| 239 | Metric Transforms and Low Rank Representations of Kernels fo | fast-attention, group-representation-theory, kernel-approximation | 53f2c82c6b165a963b353194113ee71e.md |
| 240 | DisCEdit: Model Editing by Identifying Discriminative Compon | model-editing, discriminative-components, neurons | 54801e196796134a2b0ae5e8adef502f.md |
| 241 | Prompt Tuning Strikes Back: Customizing Foundation Models wi | prompt-tuning, parameter-efficient-fine-tuning, low-rank-adaptation | 548551c07a68c8f0a87d67c6167cedb1.md |
| 242 | HLM-Cite: Hybrid Language Model Workflow for Text-based Scie | citation-prediction, hybrid-language-models, scientific-literature | 5635925cf9d2274f338eb0dd5971e845.md |
| 243 | Learning Better Representations From Less Data For Propositi | propositional-satisfiability, neuro-symbolic, SAT-solving | 56a225639da77e8f7c0409f6d5ba996b.md |
| 244 | Block Transformer: Global-to-Local Language Modeling for Fas | inference-efficiency, kv-cache, hierarchical-modeling | 579b5b84311e122584dedab1d3b7613f.md |
| 245 | Linear Transformers are Versatile In-Context Learners | linear-attention, in-context-learning, gradient-descent | 57a3c602f0a1c8980cc5ed07e49d9490.md |
| 246 | SS1: Accelerating Inference with Fast and Expressive Sketch  | structured-matrices, efficient-inference, sparse-transforms | 57ef0373c890b30407eadfe6e06c8c84.md |
| 247 | On Mesa-Optimization in Autoregressively Trained Transformer | mesa-optimization, in-context-learning, autoregressive-pretraining | 581e1a06fa20f2c079dc5fb2db236335.md |
| 248 | Personalized Steering of Large Language Models: Versatile St | steering-vectors, personalized-llm, bi-directional-preference-optimization | 58cbe393b4254da8966780a40d023c0b.md |
| 249 | LLMs Can Evolve Continually on Modality for $\mathbb{X}$-Mod | multimodal-llm, continual-learning, modality-expansion | 5942d10ae51b6bd07648e54df07ef9cd.md |
| 250 | SpeechAlign: Aligning Speech Generation to Human Preferences | speech-language-models, preference-optimization, alignment | 5a016da670821af25f151f523a2e563f.md |
| 251 | SWE-agent: Agent-Computer Interfaces Enable Automated Softwa | llm-agents, software-engineering, agent-computer-interface | 5a7c947568c1b1328ccc5230172e1e7c.md |
| 252 | ARC: A Generalist Graph Anomaly Detector with In-Context Lea | graph-anomaly-detection, in-context-learning, generalist-model | 5acb720a361eecb34ee62d356859d246.md |
| 253 | Exploring Token Pruning in Vision State Space Models | token-pruning, state-space-models, vision-efficiency | 5af741d487c5f0b08bfe56e11d1883e4.md |
| 254 | HEPrune: Fast Private Training of Deep Neural Networks With  | homomorphic-encryption, private-training, data-pruning | 5b26b9e634ba10f6c51c6db7365c4c28.md |
| 255 | KOALA: Empirical Lessons Toward Memory-Efficient and Fast Di | text-to-image, diffusion-models, memory-efficiency | 5c4e0e38691e2aa08bba4cefc4c6e852.md |
| 256 | Stealth edits to large language models | model-editing, intrinsic-dimension, stealth-attacks | 5c8168a8eca2eb23f6b1f5019371043e.md |
| 257 | MAGIS: LLM-Based Multi-Agent Framework for GitHub Issue Reso | multi-agent, github-issue-resolution, code-generation | 5d1f02132ef51602adf07000ca5b6138.md |
| 258 | REBEL: Reinforcement Learning via Regressing Relative Reward | reinforcement-learning, RLHF, relative-rewards | 5df1d92b478716877f774b82943477b3.md |
| 259 | MInference 1.0: Accelerating Pre-filling for Long-Context LL | sparse-attention, long-context-inference, llm-efficiency | 5dfbe6f5671e82c76841ba687a8a9ecb.md |
| 260 | Unveiling Encoder-Free Vision-Language Models | encoder-free, vision-language-models, visual-representation | 5e2217482fa75556f1970be809acd3f8.md |
| 261 | Toward Self-Improvement of LLMs via Imagination, Searching,  | self-improvement, llm-reasoning, monte-carlo-tree-search | 5e5853f35164e434015716a8c2a66543.md |
| 262 | Multilinear Mixture of Experts: Scalable Expert Specializati | mixture-of-experts, factorization, scalable-specialization | 5eeb693f46d753e5fe24c97212c22bd2.md |
| 263 | Understanding Emergent Abilities of Language Models from the | emergent-abilities, language-models, loss-perspective | 5f1eee2509599faeeb3570a887016a64.md |
| 264 | Autoformalize Mathematical Statements by Symbolic Equivalenc | autoformalization, formal-verification, symbolic-equivalence | 6034a661584af6c28fd97a6f23e56c0a.md |
| 265 | Accelerating Greedy Coordinate Gradient and General Prompt O | adversarial-prompts, gcg-optimization, probe-sampling | 608fe7e32f7b773545cc1d656a0fdc98.md |
| 266 | WISE: Rethinking the Knowledge Memory for Lifelong Model Edi | lifelong-model-editing, large-language-models, knowledge-memory | 60960ad78868fce5c165295fbd895060.md |
| 267 | StepbaQ: Stepping backward as Correction for Quantized Diffu | diffusion-model-quantization, quantization-error, stepping-backward-correction | 615675cc6e94ddb1a783904fb178b5f6.md |
| 268 | Learning to Merge Tokens via Decoupled Embedding for Efficie | token-merging, vision-transformers, efficient-inference | 6158e152498f8d8b83d14388a7ec1963.md |
| 269 | LSH-MoE: Communication-efficient MoE Training via Locality-S | mixture-of-experts, locality-sensitive-hashing, communication-efficiency | 61674667d642ae52f6bb281bea90ee29.md |
| 270 | Can LLMs Implicitly Learn Numeric Parameter Constraints in D | LLM-code-generation, API-constraints, numeric-parameter | 617ffb01ea5b57769b0d63d5e9fefd3f.md |
| 271 | APIGen: Automated PIpeline for Generating Verifiable and Div | function-calling, dataset-generation, llm-agents | 61cce86d180b1184949e58939c4f983d-abstract-datasetsandbenchmarkstrackhtml.md |
| 272 | What Rotary Position Embedding Can Tell Us: Identifying Quer | rotary-position-embedding, transformer-interpretability, syntactic-semantic-attention | 61f425da6e0a201b8fe1454601abfba5.md |
| 273 | Instruction Tuning Large Language Models to Understand Elect | electronic-health-records, instruction-tuning, clinical-llm | 62986e0a78780fe5f17b495aeded5bab-abstract-datasetsandbenchmarkstrackhtml.md |
| 274 | Unlocking the Capabilities of Thought: A Reasoning Boundary  | chain-of-thought, reasoning-boundary, llm-optimization | 62ab1c2cb4b03e717005479efb211841.md |
| 275 | LoRA-GA: Low-Rank Adaptation with Gradient Approximation | lora, gradient-approximation, parameter-efficient-fine-tuning | 62c4718cc334f6a0a62fb81c4a2095a1.md |
| 276 | Recursive Introspection: Teaching Language Model Agents How  | LLM-agents, self-improvement, recursive-introspection | 639d992f819c2b40387d4d5170b8ffd7.md |
| 277 | WAGLE: Strategic Weight Attribution for Effective and Modula | machine-unlearning, large-language-models, weight-attribution | 649ad92e7067b3553a0f15acac68806d.md |
| 278 | FasterDiT: Towards Faster Diffusion Transformers Training wi | diffusion-transformers, training-acceleration, convergence | 661de50100d3115cf4317bb8b5219e56.md |
| 279 | Large Pre-trained time series models for cross-domain Time s | large-pretrained-models, time-series, cross-domain | 662dcc5c2b9aca77b2a0ec8a98aefae9.md |
| 280 | BAM! Just Like That: Simple and Efficient Parameter Upcyclin | mixture-of-experts, parameter-upcycling, llm-training | 665bb142d4b9f55660cb89bb56a66fe1.md |
| 281 | An Efficient Recipe for Long Context Extension via Middle-Fo | long-context-extension, positional-encoding, llm-fine-tuning | 66944d3a3e77ebe366793f6a6126f3a4.md |
| 282 | Causal language modeling can elicit search and reasoning cap | causal-language-modeling, reasoning, search | 67b31ca159553d5593e62d7b998d63ea.md |
| 283 | UniAudio 1.5: Large Language Model-Driven Audio Codec is A F | audio-codec, large-language-models, in-context-learning | 6801fa3fd290229efc490ee0cf1c5687.md |
| 284 | Spectral Editing of Activations for Large Language Model Ali | llm-alignment, activation-editing, spectral-methods | 684c59d614fe6ae74a3be8c3ef07e061.md |
| 285 | LISA: Layerwise Importance Sampling for Memory-Efficient Lar | llm-fine-tuning, memory-efficiency, importance-sampling | 687163285b8affc8ee933bdca8e75747.md |
| 286 | MSA Generation with Seqs2Seqs Pretraining: Advancing Protein | protein-structure-prediction, multiple-sequence-alignment, sequence-generation | 694be3548697e9cc8999d45e8d16fe1e.md |
| 287 | DeltaDEQ: Exploiting Heterogeneous Convergence for Accelerat | deep-equilibrium-models, implicit-networks, heterogeneous-convergence | 69f5b860d6dc469ac6e52f03866b73c4.md |
| 288 | EvoCodeBench: An Evolving Code Generation Benchmark with Dom | code-generation, LLM-evaluation, domain-specific-benchmark | 6a059625a6027aca18302803743abaa2-abstract-datasetsandbenchmarkstrackhtml.md |
| 289 | To Believe or Not to Believe Your LLM: Iterative Prompting f | uncertainty-quantification, epistemic-uncertainty, iterative-prompting | 6aebba00fff5b6de7b488e496f80edd7.md |
| 290 | Teach Better or Show Smarter? On Instructions and Exemplars  | prompt-optimization, instruction-tuning, exemplar-selection | 6b031defd145b02bed031093d8797bb3.md |
| 291 | Algorithmic progress in language models | algorithmic-progress, language-model-pretraining, compute-efficiency | 6b066da6a23bc55f9b887e7298102884.md |
| 292 | Train-Attention: Meta-Learning Where to Focus in Continual K | continual-knowledge-learning, meta-learning, catastrophic-forgetting | 6b111780a4a1c3beecb43b708ad7415e.md |
| 293 | Where Do Large Learning Rates Lead Us? | learning-rate-schedules, generalization, neural-network-training | 6b7375226d4742ff910618a56ae72b7d.md |
| 294 | Mixture of Nested Experts: Adaptive Processing of Visual Tok | mixture-of-experts, vision-transformers, token-efficiency | 6b768359d0e8925164f61f381a748441.md |
| 295 | Efficient LLM Scheduling by Learning to Rank | llm-inference, scheduling, learning-to-rank | 6c8985579293e0209bdaa4f21bb1d237.md |
| 296 | QTIP: Quantization with Trellises and Incoherence Processing | post-training-quantization, trellis-coding, incoherence-processing | 6de2e84b8da47bb2eb5e2ac96c63d2b0.md |
| 297 | S$^{2}$FT: Efficient, Scalable and Generalizable LLM Fine-tu | parameter-efficient-fine-tuning, structured-sparsity, llm-fine-tuning | 6e3b9fb0c0c56cf6e1ee61e6a068fca4.md |
| 298 | SemCoder: Training Code Language Models with Comprehensive S | code-llm, semantic-reasoning, execution-understanding | 6efcc7fd8efeee29a050a79c843c90e0.md |
| 299 | Cherry on Top: Parameter Heterogeneity and Quantization in L | parameter-heterogeneity, quantization, llm-compression | 6fcc2190f456464160921e98393bf50e.md |
| 300 | How Do Large Language Models Acquire Factual Knowledge Durin | factual-knowledge, llm-pretraining, knowledge-acquisition | 6fdf57c71bc1f1ee29014b8dc52e723f.md |
| 301 | Found in the Middle: How Language Models Use Long Contexts B | lost-in-the-middle, positional-encoding, long-context-llm | 6ffdbbe354893979367f93e2121e37dd.md |
| 302 | HW-GPT-Bench: Hardware-Aware Architecture Benchmark for Lang | hardware-aware-nas, language-model-benchmarking, latency-energy-tradeoffs | 6ffdbf064df51857eb802a904aaaba63-abstract-datasetsandbenchmarkstrackhtml.md |
| 303 | Tree of Attacks: Jailbreaking Black-Box LLMs Automatically | jailbreaking, llm-safety, automated-red-teaming | 70702e8cbb4890b4a467b984ae59828a.md |
| 304 | Repurposing Language Models into Embedding Models: Finding t | text-embeddings, contrastive-training, compute-optimal | 707a2d58641b2192203b4bf4c532cfe1.md |
| 305 | $\textit{Trans-LoRA}$: towards data-free Transferable Parame | lora-transfer, parameter-efficient-finetuning, data-free | 708fdc7911f11585ee7161518e509ae6.md |
| 306 | PACE: Marrying generalization in PArameter-efficient fine-tu | parameter-efficient-finetuning, consistency-regularization, generalization | 70a06501001e1820fd1eb9ee821302d2.md |
| 307 | Talking Heads: Understanding Inter-Layer Communication in Tr | transformer-interpretability, inter-layer-communication, attention-heads | 70e5444e5f331f7f5431f302110b97af.md |
| 308 | The Fine-Grained Complexity of Gradient Computation for Trai | gradient-computation, attention-complexity, fine-grained-complexity | 70fa5df8e3300dc30bf19bee44a56155.md |
| 309 | BOLD: Boolean Logic Deep Learning | boolean-logic, binarized-neural-networks, low-precision-training | 718a3c5cf135894db6e718725f52ef9a.md |
| 310 | Make Your LLM Fully Utilize the Context | long-context-LLM, lost-in-the-middle, context-utilization | 71c3451f6cd6a4f82bb822db25cea4fd.md |
| 311 | Regularizing Hidden States Enables Learning Generalizable Re | reward-model, RLHF, hidden-state-regularization | 71f7154547c748c8041505521ca433ab.md |
| 312 | The Feature Speed Formula: a flexible approach to scale hype | hyperparameter-scaling, feature-learning, deep-networks | 720e7ebc49c84252abc0754dddf80976.md |
| 313 | On the Power of Decision Trees in Auto-Regressive Language M | decision-trees, autoregressive, language-modeling | 72176f95680c3fb27a0966f36d5d0c53.md |
| 314 | The Mamba in the Llama: Distilling and Accelerating Hybrid M | Mamba, hybrid-models, knowledge-distillation | 723933067ad315269b620bc0d2c05cba.md |
| 315 | An Analysis of Tokenization: Transformers under Markov Data | tokenization, transformers, Markov-data | 724afcaae4ae92a9220a077ffe80088d.md |
| 316 | SGLang: Efficient Execution of Structured Language Model Pro | LLM-inference, structured-generation, KV-cache | 724be4472168f31ba1c9ac630f15dec8.md |
| 317 | The ALCHEmist: Automated Labeling 500x CHEaper than LLM Data | data-annotation, llm-distillation, cost-reduction | 72802bef5cf1a3449e909b20c2ae18d5.md |
| 318 | PTQ4DiT: Post-training Quantization for Diffusion Transforme | post-training-quantization, diffusion-transformers, model-compression | 72d32f4fe0b7af03732bd227bf1c4a5f.md |
| 319 | SelfCodeAlign: Self-Alignment for Code Generation | instruction-tuning, code-generation, self-alignment | 72da102da91a8042a0b2aa968429a9f9.md |
| 320 | Language Models as Zero-shot Lossless Gradient Compressors:  | gradient-compression, language-model-priors, lossless-compression | 744e09d3213ee53de88f04164a9b06ab.md |
| 321 | Efficient Multi-task LLM Quantization and Serving for Multip | LLM-quantization, LoRA, multi-task-serving | 747dc7c6566c74eb9a663bcd8d057c78.md |
| 322 | ReFT: Representation Finetuning for Language Models | parameter-efficient-finetuning, representation-editing, language-models | 75008a0fba53bf13b0bb3b7bff986e0e.md |
| 323 | BMRS: Bayesian Model Reduction for Structured Pruning | structured-pruning, bayesian-model-reduction, neural-network-compression | 7538e7a7a589a267f49527fe6fbc640e.md |
| 324 | Fight Back Against Jailbreaking via Prompt Adversarial Tunin | jailbreaking, LLM-safety, adversarial-tuning | 759ca99a82e2a9137c6bef4811c8d378.md |
| 325 | The Evolution of Statistical Induction Heads: In-Context Lea | in-context-learning, Markov-chains, induction-heads | 75b0edb869e2cd509d64d0e8ff446bc1.md |
| 326 | Memory-Efficient LLM Training with Online Subspace Descent | memory-efficient-training, LLM, subspace-descent | 760d09bcc06b949f5ac4b6a918739aa8.md |
| 327 | Faster Neighborhood Attention: Reducing the O(n^2) Cost of S | attention-mechanism, neighborhood-attention, efficiency | 76e952a4e83d97186d3f55eef6a3a367.md |
| 328 | ReST-MCTS*: LLM Self-Training via Process Reward Guided Tree | llm-self-training, process-reward, tree-search | 76ec4dc30e9faaf0e4b6093eaa377218.md |
| 329 | Co-occurrence is not Factual Association in Language Models | language-models, factual-knowledge, co-occurrence | 775226eaa2a36c543e2bd6cc9eae1b6a.md |
| 330 | Learning Versatile Skills with Curriculum Masking | masked-prediction, offline-reinforcement-learning, curriculum-learning | 788f9787ec93e3e1f34658fb003a1f44.md |
| 331 | Model Decides How to Tokenize: Adaptive DNA Sequence Tokeniz | DNA-tokenization, genomic-language-models, adaptive-tokenization | 79af547fa22cdcb0facd0b31dcd4bdb0.md |
| 332 | RouterDC: Query-Based Router by Dual Contrastive Learning fo | LLM-routing, dual-contrastive-learning, model-assembly | 7a641b8ec86162fc875fb9f6456a542f.md |
| 333 | OneBit: Towards Extremely Low-bit Large Language Models | quantization, 1-bit, weight-representation | 7a7a3f53faafc0161be0fcb57e5fa078.md |
| 334 | Chain-of-Thought Reasoning Without Prompting | chain-of-thought, reasoning, decoding | 7a8e7fd295aa04eac4b470ae27f8785c.md |
| 335 | FM-Delta: Lossless Compression for Storing Massive Fine-tune | model-compression, lossless-compression, fine-tuned-models | 7b75a7339dfb256ee4b4bec028a6890b.md |
| 336 | Divide-and-Conquer Meets Consensus: Unleashing the Power of  | code-generation, divide-and-conquer, consensus | 7bc4f74e35bcfe8cfe43b0a860786d6a.md |
| 337 | Knowledge Composition using Task Vectors with Learned Anisot | task-vectors, model-merging, anisotropic-scaling | 7c7baa87e763a7e2fa2527e7bf105508.md |
| 338 | SpikedAttention: Training-Free and Fully Spike-Driven Transf | spiking-neural-networks, transformer-conversion, energy-efficiency | 7c9341ad0263428b5057d92f4d88dfa0.md |
| 339 | Subwords as Skills: Tokenization for Sparse-Reward Reinforce | tokenization, sparse-reward, skill-learning | 7d0c7a899224cd178b2e0cbecf39b5a5.md |
| 340 | BLoB: Bayesian Low-Rank Adaptation by Backpropagation for La | bayesian-low-rank-adaptation, uncertainty-quantification, fine-tuning | 7d53575463291ea6b5a23cf6e571f59b.md |
| 341 | ZipCache: Accurate and Efficient KV Cache Quantization with  | KV-cache, quantization, salient-token-identification | 7e57131fdeb815764434b65162c88895.md |
| 342 | FlashAttention-3: Fast and Accurate Attention with Asynchron | attention-mechanism, flashattention, asynchrony | 7ede97c3e082c6df10a8d6103a2eebd2.md |
| 343 | Group and Shuffle: Efficient Structured Orthogonal Parametri | orthogonal-finetuning, structured-matrices, parameter-efficient | 7f0f24deb34c21ee590d8cece365710b.md |
| 344 | Reasons and Solutions for the Decline in Model Performance a | knowledge-editing, model-degradation, llm | 7f588e59e9ae6138d3ea9e4fdaa7e040.md |
| 345 | Changing the Training Data Distribution to Reduce Simplicity | simplicity-bias, training-distribution, generalization | 7f5f9a88c6516469c83d074c6f2976fb.md |
| 346 | Instruction Tuning With Loss Over Instructions | instruction-tuning, loss-over-instructions, language-model-training | 7ffb43adf37b3eeaba559098bc084cc6.md |
| 347 | VisionLLM v2: An End-to-End Generalist Multimodal Large Lang | multimodal-LLM, visual-perception, generalist-model | 81a60d18e010b27b36cd465c6604b915.md |
| 348 | Pin-Tuning: Parameter-Efficient In-Context Tuning for Few-Sh | molecular-property-prediction, few-shot-learning, parameter-efficient-tuning | 82a9fb94035dad3ec007de4ad13c6748.md |
| 349 | Improving Context-Aware Preference Modeling for Language Mod | preference-learning, context-aware, reward-modeling | 82acbbc04435f6c1e7f656b1cbe4ad82.md |
| 350 | MetaLA: Unified Optimal Linear Approximation to Softmax Atte | linear-attention, state-space-models, softmax-approximation | 8329a45669017898bb0cc09d27f8d2bb.md |
| 351 | 2DQuant: Low-bit Post-Training Quantization for Image Super- | post-training-quantization, image-super-resolution, low-bit | 832b20b65f655587e9c0447860406a82.md |
| 352 | Can LLMs Learn by Teaching for Better Reasoning? A Prelimina | learning-by-teaching, LLM-reasoning, knowledge-distillation | 8340b085045cf13f1f0b6c2c4cc0a89c.md |
| 353 | On the Inductive Bias of Stacking Towards Improving Reasonin | gradual-stacking, reasoning-improvement, training-efficiency | 837bc5db12f3d394d220815a7687340c.md |
| 354 | Trace is the Next AutoDiff: Generative Optimization with Ric | LLM-optimization, execution-traces, generative-feedback | 83ba7056bce2c3c3c27e17397cf3e1f0.md |
| 355 | CorDA: Context-Oriented Decomposition Adaptation of Large La | parameter-efficient-fine-tuning, context-oriented-decomposition, task-aware-adaptation | 83f95bb0ac5046338ea2afe3390e9f4b.md |
| 356 | Megalodon: Efficient LLM Pretraining and Inference with Unli | long-context-LLM, linear-complexity, efficient-pretraining | 840abfadd04c967feaa2a49aba94a32d.md |
| 357 | Universal In-Context Approximation By Prompting Fully Recurr | in-context-learning, recurrent-models, universal-approximation | 848784373188ddf641079524e89e0ac9.md |
| 358 | DISP-LLM: Dimension-Independent Structural Pruning for Large | structured-pruning, large-language-models, model-compression | 84a7fc24ed52e8eff514c33e8ac76ea3.md |
| 359 | Decision Mamba: Reinforcement Learning via Hybrid Selective  | reinforcement-learning, mamba, sequential-decision-making | 850e8063d902e0825d3c5504d183bafe.md |
| 360 | Order-Independence Without Fine Tuning | order-independence, autoregressive-language-models, positional-bias | 85529bc995777a74072ef63c05bedd30.md |
| 361 | Scalable Optimization in the Modular Norm | modular-norm, optimizer-scaling, deep-learning-training | 8629b0fff229b8a27efb1422e990605f.md |
| 362 | Aligning to Thousands of Preferences via System Message Gene | LLM-alignment, personalized-preferences, system-message | 86c9df30129f7663ad4d429b6f80d461.md |
| 363 | Efficient Large Multi-modal Models via Visual Context Compre | multimodal-LLMs, visual-token-compression, visual-context | 871ed095b734818cfba48db6aeb25a62.md |
| 364 | Vaccine: Perturbation-aware Alignment for Large Language Mod | LLM-alignment, harmful-fine-tuning, perturbation-aware | 873c86d9a979ab80d8e2919510d4446b.md |
| 365 | Tiny Time Mixers (TTMs): Fast Pre-trained Models for Enhance | time-series-forecasting, pre-trained-models, zero-shot | 874a4d89f2d04b4bcf9a2c19545cf040.md |
| 366 | SwitchHead: Accelerating Transformers with Mixture-of-Expert | mixture-of-experts, transformer-attention, efficient-language-models | 87be61bf9338389702712f5e9754a986.md |
| 367 | Transformers Represent Belief State Geometry in their Residu | transformers, belief-state-geometry, residual-stream | 8936fa1691764912d9519e1b5673ea66.md |
| 368 | MambaTree: Tree Topology is All You Need in State Space Mode | state-space-models, tree-topology, long-range-dependencies | 89b89c04f55ea7c7ca989992bb6a98c0.md |
| 369 | Panacea: Pareto Alignment via Preference Adaptation for LLMs | llm-alignment, multi-dimensional-preferences, pareto-optimality | 89f39d0b3d49a47606a165eefba2778c.md |
| 370 | Accelerating Pre-training of Multimodal LLMs via Chain-of-Si | multimodal-llm, vision-language-pretraining, visual-resampling | 8a54a80ffc2834689ffdd0920202018e.md |
| 371 | Scaling Laws and Compute-Optimal Training Beyond Fixed Train | scaling-laws, compute-optimal, training-duration | 8b970e15a89bf5d12542810df8eae8fc.md |
| 372 | Expanding Sparse Tuning for Low Memory Usage | parameter-efficient-fine-tuning, sparse-tuning, memory-efficiency | 8c420176b45e923cf99dee1d7356a763.md |
| 373 | BitsFusion: 1.99 bits Weight Quantization of Diffusion Model | weight-quantization, diffusion-models, model-compression | 8c64bc3f7796d31caa7c3e6b969bf7da.md |
| 374 | Many-Shot In-Context Learning | in-context-learning, many-shot, large-language-models | 8cb564df771e9eacbfe9d72bd46a24a9.md |
| 375 | Orchid: Flexible and Data-Dependent Convolution for Sequence | sequence-modeling, data-dependent-convolution, attention-alternatives | 8ccc5ec30a8d46793d790e2216efd40d.md |
| 376 | CoMERA: Computing- and Memory-Efficient Training via Rank-Ad | tensor-decomposition, rank-adaptive-optimization, memory-efficient-training | 8d35d225230a9d77b29c1dd300e48ad9.md |
| 377 | Pretrained Transformer Efficiently Learns Low-Dimensional Ta | in-context-learning, transformers, low-dimensional-target-functions | 8d6c356c82252032a20c749dda36f2d8.md |
| 378 | kGym: A Platform and Dataset to Benchmark Large Language Mod | llm-benchmarking, linux-kernel, software-engineering | 8e9ed2a28af7d9085180e3817b2c9a57-abstract-datasetsandbenchmarkstrackhtml.md |
| 379 | Structured Unrestricted-Rank Matrices for Parameter Efficien | parameter-efficient-finetuning, low-rank-adaptation, transformer-finetuning | 8eec8d7bcecf034304174e6b57dbc19a.md |
| 380 | AmoebaLLM: Constructing Any-Shape Large Language Models for  | llm-deployment, model-compression, any-shape-networks | 8f11e548311c7fd3f33596a4d1dd41f0.md |
| 381 | Twin-Merging: Dynamic Integration of Modular Expertise in Mo | model-merging, modular-expertise, large-language-models | 8fcd17eb91bae20d9826786d7d6be799.md |
| 382 | Humanoid Locomotion as Next Token Prediction | humanoid-locomotion, autoregressive-prediction, sensorimotor-control | 90afd20dc776bc8849c31d61a0763a0b.md |
| 383 | Compact Proofs of Model Performance via Mechanistic Interpre | mechanistic-interpretability, formal-verification, transformer-proofs | 90e73f3cf1a6c84c723a2e8b7fb2b2c1.md |
| 384 | Mixture of In-Context Experts Enhance LLMs' Long Context Awa | long-context-awareness, mixture-of-experts, positional-awareness | 91315fbb83ce353ae5538cba395f70d1.md |
| 385 | MutaPLM: Protein Language Modeling for Mutation Explanation  | protein-language-model, mutation-engineering, sequence-modeling | 91a5bb5e5939cb075f5f2464d7b8bbf0.md |
| 386 | Meta-Diffu$B$: A Contextualized Sequence-to-Sequence Text Di | text-diffusion, sequence-to-sequence, meta-exploration | 91d193b65d0b120d29503590827de1ea.md |
| 387 | AutoPSV: Automated Process-Supervised Verifier | process-supervised-verification, llm-reasoning, automatic-annotation | 9246aa822579d9b29a140ecdac36ad60.md |
| 388 | Reference Trustable Decoding: A Training-Free Augmentation P | large-language-models, in-context-learning, training-free | 925869234d3aa2a3aad5f05b643974aa.md |
| 389 | Nearest Neighbor Speculative Decoding for LLM Generation and | speculative-decoding, kNN-LM, hallucination | 93c099bb4cde51b724eaa6d6d4a4b5e4.md |
| 390 | Aggregate-and-Adapt Natural Language Prompts for Downstream  | CLIP, prompt-learning, vision-language | 93e67adb632d636bb2bcedf4eef1a6fe.md |
| 391 | UPS: Unified Projection Sharing for Lightweight Single-Image | super-resolution, transformers, lightweight | 93f250215e4889119807b6fac3a57aec.md |
| 392 | Transforming Vision Transformer: Towards Efficient Multi-Tas | multi-task-learning, vision-transformer, asynchronous-learning | 93fab021315170101c92e8330a56fbdb.md |
| 393 | Mesa-Extrapolation: A Weave Position Encoding Method for Enh | length-extrapolation, position-encoding, large-language-models | 9446c291a8744a125a0bda5b18f4d5a1.md |
| 394 | Mitigating Reward Overoptimization via Lightweight Uncertain | RLHF, reward-overoptimization, uncertainty-estimation | 94bbcb744bbada8808fda05b9d9290d6.md |
| 395 | Online Iterative Reinforcement Learning from Human Feedback  | RLHF, general-preference, online-learning | 94d13c2401fe119e57ba325b6fe526e0.md |
| 396 | Probabilistic Federated Prompt-Tuning with Non-IID and Imbal | federated-learning, prompt-tuning, non-IID-data | 951877b24b376c5f4612e850251ee85b.md |
| 397 | Reawakening knowledge: Anticipatory recovery from catastroph | catastrophic-interference, continual-learning, structured-training | 9628b97f74cd8f83ad12b631378b81e2.md |
| 398 | CE-NAS: An End-to-End Carbon-Efficient Neural Architecture S | neural-architecture-search, carbon-efficiency, energy-aware | 96b42e02294543f0b226f862be75472e.md |
| 399 | Proving Olympiad Algebraic Inequalities without Human Demons | olympiad-inequalities, automated-theorem-proving, algebraic-reasoning | 96f8c5e879c339dae55e6c2188b02a33-abstract-datasetsandbenchmarkstrackhtml.md |
| 400 | GACL: Exemplar-Free Generalized Analytic Continual Learning | continual-learning, class-incremental, analytic-learning | 9713d53ee4f31781304b1ca43266f8d1.md |
| 401 | Measuring Progress in Dictionary Learning for Language Model | sparse-autoencoders, dictionary-learning, mechanistic-interpretability | 9736acf007760cc2b47948ae3cf06274.md |
| 402 | Improving Alignment and Robustness with Circuit Breakers | ai-alignment, adversarial-robustness, representation-engineering | 97ca7168c2c333df5ea61ece3b3276e1.md |
| 403 | TuneTables: Context Optimization for Scalable Prior-Data Fit | prior-data-fitted-networks, in-context-learning, tabular-classification | 97dc07f1253ab33ee514f395a82fa7cc.md |
| 404 | SmallToLarge (S2L): Scalable Data Selection for Fine-tuning  | data-selection, fine-tuning, training-trajectories | 97fe251c25b6f99a2a23b330a75b11d4.md |
| 405 | Multi-language Diversity Benefits Autoformalization | autoformalization, multilingual, formal-verification | 984de836e696ba653bbfbbbfce31d3bc.md |
| 406 | Cross-model Control: Improving Multiple Large Language Model | cross-model-control, llm-training, knowledge-transfer | 9856b5d30ac61ab744fdab6f67d874e4.md |
| 407 | Understanding and Minimising Outlier Features in Transformer | outlier-features, transformer-training, quantization | 986292a930c3692168b177a770025ab3.md |
| 408 | Toward Efficient Inference for Mixture of Experts | mixture-of-experts, inference-efficiency, LLM-serving | 98bf3b8505c611ac21055dd9d355c66e.md |
| 409 | EffiLearner: Enhancing Efficiency of Generated Code via Self | code-generation, self-optimization, llm-efficiency | 99c66755871ae101a4cef87c67fb29e8.md |
| 410 | Parameter Competition Balancing for Model Merging | model-merging, parameter-competition, multi-task-learning | 99fc8bc48b917c301a80cb74d91c0c06.md |
| 411 | MagR: Weight Magnitude Reduction for Enhancing Post-Training | post-training-quantization, weight-regularization, l-infinity-optimization | 9a987c98a7f36cc83f9065df3ca4f9e0.md |
| 412 | Faster Diffusion: Rethinking the Role of the Encoder for Dif | diffusion-models, inference-acceleration, encoder-skipping | 9ad996b5c45130de2bc00b60d8607904.md |
| 413 | DoFIT: Domain-aware Federated Instruction Tuning with Allevi | federated-learning, instruction-tuning, catastrophic-forgetting | 9be9407431b7ff8cc04cae5460fcb7ab.md |
| 414 | In-Context Learning with Representations: Contextual General | in-context-learning, transformers, generalization-theory | 9bfa0c155653e24120760a5ead819376.md |
| 415 | Large Language Models Must Be Taught to Know What They Don’t | uncertainty-quantification, calibration, LLM | 9c20f16b05f5e5e70fa07e2a4364b80e.md |
| 416 | StreamingDialogue: Prolonged Dialogue Learning via Long Cont | long-context, dialogue, context-compression | 9c43057f39d49b8b5c989cc1aac70ab7.md |
| 417 | Cascade Speculative Drafting for Even Faster LLM Inference | speculative-decoding, LLM-inference, cascade-drafting | 9cb5b083ba4f5ca6bd05dd307a2fb354.md |
| 418 | Local to Global: Learning Dynamics and Effect of Initializat | transformers, learning-dynamics, Markov-chains | 9cdb4f8c4dfa13284d2d5a6e7853e5a2.md |
| 419 | Localized Zeroth-Order Prompt Optimization | prompt-optimization, black-box-LLM, zeroth-order-optimization | 9cef1316eaef9bd99da46f63334dc031.md |
| 420 | Discovering Preference Optimization Algorithms with and for  | preference-optimization, LLM, loss-function-discovery | 9d88b87b31986f8293bb0067a841579e.md |
| 421 | Reducing Transformer Key-Value Cache Size with Cross-Layer A | KV-cache, cross-layer-attention, transformer-efficiency | 9e23d020c18e4c40d81c6a0fc7a46f68.md |
| 422 | End-to-End Ontology Learning with Large Language Models | ontology-learning, LLMs, knowledge-graph | 9e89f068a62f6858c661a8abecf5bb0a.md |
| 423 | Base of RoPE Bounds Context Length | RoPE, context-length, position-embedding | 9f12dd32d552f3ad9eaa0e9dfec291be.md |
| 424 | How does Architecture Influence the Base Capabilities of Pre | pre-trained-LLMs, FFN-wider, mixture-of-experts | 9f2b171fd3f4ca8dd71d1998f65c356a.md |
| 425 | AMAGO-2: Breaking the Multi-Task Barrier in Meta-Reinforceme | meta-reinforcement-learning, transformers, multi-task | 9f40d2612d0b3b6f6c2a77da21b1067f.md |
| 426 | LLMCBench: Benchmarking Large Language Model Compression for | LLM-compression, benchmarking, efficient-deployment | 9f4cc62d0632911c63163ea3d9ec19bd-abstract-datasetsandbenchmarkstrackhtml.md |
| 427 | Instruction Embedding: Latent Representations of Instruction | instruction-tuning, latent-representations, task-identification | 9f9e2982759f384495f4b75a33f3dd72-abstract-datasetsandbenchmarkstrackhtml.md |
| 428 | DuQuant: Distributing Outliers via Dual Transformation Makes | llm-quantization, outlier-activation, low-bit-representation | 9febda1c8344cc5f2d51713964864e93.md |
| 429 | Mixture of Demonstrations for In-Context Learning | in-context-learning, demonstration-selection, mixture-of-examples | a0da098e0031f58269efdcba40eedf47.md |
| 430 | IDGen: Item Discrimination Induced Prompt Generation for LLM | llm-evaluation, item-discrimination, prompt-generation | a14ac7911df7d369919a687909a14a8b.md |
| 431 | Speculative Monte-Carlo Tree Search | Monte-Carlo-tree-search, speculative-execution, AlphaZero | a19940b01b77b6acd41ff8b32b334e7c.md |
| 432 | Perception of Knowledge Boundary for Large Language Models t | knowledge-boundary, hallucination, semi-open-ended-QA | a1e0d6fa0c30b7d4f75dd9c7ed6189f2.md |
| 433 | Once Read is Enough: Domain-specific Pretraining-free Langua | sparse-mixture-of-experts, domain-adaptation, long-tail-knowledge | a1f12d8d3cc1b4789ff4ebec46e27609.md |
| 434 | Compressing Large Language Models using Low Rank and Low Pre | model-compression, low-rank-decomposition, quantization | a20e8451ffb07ad25282c21945ad4f19.md |
| 435 | A Theoretical Understanding of Self-Correction through In-co | self-correction, in-context-learning, large-language-models | a399456a191ca36c7c78dff367887f0a.md |
| 436 | Octopus: A Multi-modal LLM with Parallel Recognition and Seq | multimodal-LLM, visual-recognition, parallel-sequential-understanding | a3eadeebbc9eecd621086f6978865a85.md |
| 437 | Low Precision Local Training is Enough for Federated Learnin | federated-learning, low-precision-training, quantization | a421e88bb7db67cd0401475a0ed4a17d.md |
| 438 | D-CPT Law: Domain-specific Continual Pre-Training Scaling La | continual-pretraining, scaling-laws, domain-adaptation | a4628e9fbd3002a554923642f74d5d6b.md |
| 439 | Towards a Theoretical Understanding of the 'Reversal Curse'  | reversal-curse, large-language-models, training-dynamics | a4b95476f673e6e538f80862f622ba2f.md |
| 440 | MAmmoTH2: Scaling Instructions from the Web | instruction-tuning, web-scale-data, reasoning | a4ca07aa108036f80cbb5b82285fd4b1.md |
| 441 | Imitating Language via Scalable Inverse Reinforcement Learni | inverse-reinforcement-learning, language-model-training, imitation-learning | a5036c166e44b731f214f41813364d01.md |
| 442 | Aligner: Efficient Alignment by Learning to Correct | llm-alignment, reinforcement-learning-from-human-feedback, correction-learning | a51a74b2d71387dc71cc29181b5519bb.md |
| 443 | Memory-Efficient Gradient Unrolling for Large-Scale Bi-level | bi-level-optimization, gradient-unrolling, memory-efficiency | a5321f64005b0d4a94d0b18e84e19f48.md |
| 444 | Scaling Retrieval-Based Language Models with a Trillion-Toke | retrieval-augmented-language-models, datastore-scaling, inference-time-retrieval | a5d8aba27dfef4e849e8cb03fb87a954.md |
| 445 | Efficient Contextual LLM Cascades through Budget-Constrained | LLM-cascades, budget-constrained, policy-learning | a6deba3b2408af45b3f9994c2152b862.md |
| 446 | Speculative Decoding with CTC-based Draft Model for LLM Infe | speculative-decoding, CTC-draft-model, LLM-inference-acceleration | a79054a9da91d73ed3cb1a9e87d7cd2d.md |
| 447 | QuanTA: Efficient High-Rank Fine-Tuning of LLMs with Quantum | quantum-inspired, tensor-adaptation, LLM-fine-tuning | a7c17115db36193f6b83b71b0fe1d416.md |
| 448 | Optimized Feature Generation for Tabular Data via LLMs with  | feature-engineering, tabular-data, LLM-reasoning | a7ebe2e8d8cfd2fcec6cd77f9e6fd34d.md |
| 449 | DiP-GO: A Diffusion Pruner via Few-step Gradient Optimizatio | diffusion-model-pruning, few-step-optimization, inference-efficiency | a845fdc3f87751710218718adb634fe7.md |
| 450 | Rethinking the Membrane Dynamics and Optimization Objectives | spiking-neural-networks, membrane-dynamics, firing-patterns | a867a94a427bacbe3f4de16c7ac10ba8.md |
| 451 | Normalization Layer Per-Example Gradients are Sufficient to  | gradient-noise-scale, per-example-gradients, normalization-layers | a9d419ef12fb34105424fa3166716139.md |
| 452 | Multi-Head Mixture-of-Experts | mixture-of-experts, sparse-MoE, expert-activation | ab05dc8bf36a9f66edbff6992ec86f56.md |
| 453 | Perceiving Longer Sequences With Bi-Directional Cross-Attent | efficient-transformer, bi-directional-attention, linear-scaling | ab1ee157f7804a13f980414b644a9460.md |
| 454 | Optimal and Approximate Adaptive Stochastic Quantization | quantization, adaptive-quantization, stochastic-optimization | ab6a2c6ee757afe43882121281f6065c.md |
| 455 | Towards Next-Level Post-Training Quantization of Hyper-Scale | post-training-quantization, transformers, edge-deployment | ab6eba9a853087993addff937c8cec87.md |
| 456 | Hypothesis Testing the Circuit Hypothesis in LLMs | circuit-hypothesis, LLMs, hypothesis-testing | abccb8a90b30d45b948360ba41f5a20f.md |
| 457 | Accelerating Augmentation Invariance Pretraining | contrastive-learning, vision-transformers, pretraining-efficiency | abf731c2993f9b1ee417cc3734787d7a.md |
| 458 | Pre-training Differentially Private Models with Limited Publ | differential-privacy, foundation-models, limited-public-data | ac04e54e0a2d1927d60709019e4e7870.md |
| 459 | Fundamental Limits of Prompt Compression: A Rate-Distortion  | prompt-compression, rate-distortion, black-box-LLMs | ac8fbba029dadca99d6b8c3f913d3ed6.md |
| 460 | Would I Lie To You? Inference Time Alignment of Language Mod | preference-learning, alignment, inference-time | ad3d0ac42b4b5cc3b5f0ca10107d5c84.md |
| 461 | Navigating the Safety Landscape: Measuring Risks in Finetuni | llm-safety, finetuning, alignment | ada93fa6643735f294be51dc31eebbd4.md |
| 462 | Real-time Core-Periphery Guided ViT with Smart Data Layout S | vision-transformer, mobile-deployment, real-time-inference | adb77ecc8ba1c2d3135c86a46b8f2496.md |
| 463 | Improved Generation of Adversarial Examples Against Safety-a | adversarial-examples, jailbreak-attacks, gradient-based-optimization | aeae9df8e6bfe7350160bb42965dbd44.md |
| 464 | Classification Done Right for Vision-Language Pre-Training | vision-language-pretraining, classification, tokenized-text-labels | aee5298251a418aad89618cf6b5e7ccc.md |
| 465 | The Power of Hard Attention Transformers on Data Sequences:  | transformers, formal-language-theory, hard-attention | af58a33861ac45472ea1cc5860d2b13e.md |
| 466 | StrategyLLM: Large Language Models as Strategy Generators, E | prompting, strategy-generation, LLM-problem-solving | af7cc9e2366b8f8837a6ef339810277a.md |
| 467 | Mini-Sequence Transformers: Optimizing Intermediate Memory f | long-sequence-training, memory-efficiency, llm-training | b063829b922fdeb4fa3472dd3471ff43.md |
| 468 | Learn more, but bother less: parameter efficient continual l | continual-learning, catastrophic-forgetting, parameter-efficient | b0bc711f48724237b38823c4d9cee10b.md |
| 469 | CoLoR-Filter: Conditional Loss Reduction Filtering for Targe | data-selection, pre-training, language-models | b0f25f0a63cc544d506e4c1374a3c807.md |
| 470 | SelectIT: Selective Instruction Tuning for LLMs via Uncertai | instruction-tuning, data-selection, uncertainty-quantification | b130a5691815f550977e331f8bec08ae.md |
| 471 | Do LLMs Build World Representations? Probing Through the Len | world-models, state-abstraction, probing | b1b16c4b875eb84d3585cb70d23970ca.md |
| 472 | DDK: Distilling Domain Knowledge for Efficient Large Languag | knowledge-distillation, domain-knowledge, model-compression | b206d54ffbb803b5c51d85f405d422e4.md |
| 473 | Transformers Learn to Achieve Second-Order Convergence Rates | transformers, in-context-learning, second-order-optimization | b2d4051f03a7038a2771dfbbe5c7b54e.md |
| 474 | PaCE: Parsimonious Concept Engineering for Large Language Mo | concept-engineering, llm-alignment, harmful-content-reduction | b3cca813dcd78fe75e4d4df2e6a0b1a7.md |
| 475 | SHED: Shapley-Based Automated Dataset Refinement for Instruc | shapley-values, dataset-refinement, instruction-fine-tuning | b3cff9947cde08b4fa70652cb8ac9209.md |
| 476 | Efficient Prompt Optimization Through the Lens of Best Arm I | prompt-optimization, best-arm-identification, large-language-models | b46bc1449205888e1883f692aff1a252.md |
| 477 | Why Go Full? Elevating Federated Learning Through Partial Ne | federated-learning, partial-network-updates, privacy | b4baac5d3f7508a4eb2b65376470a5a2.md |
| 478 | QuaRot: Outlier-Free 4-Bit Inference in Rotated LLMs | quantization, LLM, rotation-based-outlier-removal | b5b939436789f76f08b9d0da5e81af7c.md |
| 479 | Resolving Discrepancies in Compute-Optimal Scaling of Langua | scaling-laws, compute-optimal, language-models | b6341525cd84f3be0ef203e4d7cd8556.md |
| 480 | HYDRA: Model Factorization Framework for Black-Box LLM Perso | personalization, black-box-LLM, model-factorization | b6b4906c1334656e97cc9968ccfca073.md |
| 481 | CodeRosetta: Pushing the Boundaries of Unsupervised Code Tra | code-translation, unsupervised-learning, parallel-programming | b6edb87876bec4ac2260bffa083cb992.md |
| 482 | Transfer Q-star : Principled Decoding for LLM Alignment | LLM-alignment, decoding, Q-star-transfer | b8700a8a005032fe869c741b0a75274b.md |
| 483 | LM-HT SNN: Enhancing the Performance of SNN to ANN Counterpa | spiking-neural-networks, learnable-threshold, ANN-SNN-conversion | b8bf2c0dd0b48511889b7d3b2c5fc8f5.md |
| 484 | Preference Learning Algorithms Do Not Learn Preference Ranki | RLHF, DPO, preference-learning | b8ce770a6b25e603fbff4a37f9e31edc.md |
| 485 | Learn To be Efficient: Build Structured Sparsity in Large La | LLM-pruning, structured-sparsity, efficient-inference | b8f10193cab43d45df9bb810637333fd.md |
| 486 | MaVEn: An Effective Multi-granularity Hybrid Visual Encoding | multi-image-reasoning, visual-encoding, multimodal-LLM | b8f21f324ff277ba26aed2e944b7576b.md |
| 487 | Efficient Adaptation of Pre-trained Vision Transformer via H | parameter-efficient-fine-tuning, vision-transformer, Householder-transformation | b91cebea9292bfc45a2e674f0b9d4a51.md |
| 488 | UniBias: Unveiling and Mitigating LLM Bias through Internal  | llm-bias, in-context-learning, attention-manipulation | b956d55b4d15eb3f024c67f8415822e4.md |
| 489 | Can Models Learn Skill Composition from Examples? | compositional-generalization, skill-composition, llm-evaluation | b99fd30559b520cc97447ba905040677.md |
| 490 | Mixture of Tokens: Continuous MoE through Cross-Example Aggr | mixture-of-experts, cross-example-aggregation, continuous-moe | bc427eb348789b190e3ea050cceff8a3.md |
| 491 | TrAct: Making First-layer Pre-Activations Trainable | first-layer-training, gradient-updates, pixel-values | bc52716d13d2d72ea0f335667d86c0f8.md |
| 492 | Algorithmic Capabilities of Random Transformers | random-transformers, circuit-emergence, algorithmic-tasks | bccdd196d798a51a4961989984a9ed4a.md |
| 493 | Lisa: Lazy Safety Alignment for Large Language Models agains | safety-alignment, harmful-fine-tuning, lazy-alignment | bcfdaf04b54a69f47623c973c864ee8d.md |
| 494 | Synthetic Programming Elicitation for Text-to-Code in Very L | LLM-for-code, low-resource, synthetic-data-elicitation | bde1c75d7d89e64d6d93dce1c68dc3d8.md |
| 495 | TAIA: Large Language Models are Out-of-Distribution Data Lea | fine-tuning, out-of-distribution, LLM-adaptation | be0a8ecf8b2743a4117557c5eca0fb79.md |
| 496 | Diffusion of Thought: Chain-of-Thought Reasoning in Diffusio | diffusion-language-models, chain-of-thought, reasoning | be30024e7fa2c29cac7a6dafcbb8571f.md |
| 497 | A Polar coordinate system represents syntax in large languag | syntactic-representation, polar-coordinates, structural-probing | be36e50757bf9cd280aa74f89a7d1c23.md |
| 498 | Large Language Model Unlearning | machine-unlearning, llm-alignment, harmful-content-removal | be52acf6bccf4a8c0a90fe2f5cfcead3.md |
| 499 | Lean Workbook: A large-scale Lean problem set formalized fro | lean, formal-theorem-proving, math-problem-formalization | bf236666a2cc5f3ae05d2e08485efc4c-abstract-datasetsandbenchmarkstrackhtml.md |
| 500 | BABILong: Testing the Limits of LLMs with Long Context Reaso | long-context, llm-benchmark, reasoning-in-a-haystack | c0d62e70dbc659cc9bd44cbcf1cb652f-abstract-datasetsandbenchmarkstrackhtml.md |
| 501 | Advancing Tool-Augmented Large Language Models: Integrating  | tool-augmented-llm, api-calling, inference-tree | c0f7ee1901fef1da4dae2b88dfd43195.md |
| 502 | DEPrune: Depth-wise Separable Convolution Pruning for Maximi | structured-pruning, depthwise-separable-convolution, GPU-parallelism | c16a99558b0b4f6b10966ca9bdb98ade.md |
| 503 | SlimGPT: Layer-wise Structured Pruning for Large Language Mo | LLM-pruning, structured-pruning, layer-wise | c1c44e46358e0fb94dc94ec495a7fb1a.md |
| 504 | Identifying Functionally Important Features with End-to-End  | sparse-autoencoders, mechanistic-interpretability, feature-learning | c212c1b88395ab68d5e1671c17883ec6.md |
| 505 | Improving Gloss-free Sign Language Translation by Reducing R | sign-language-translation, gloss-free, representation-density | c225136cfe52a8fd66658bbcf9d894ab.md |
| 506 | GFT: Graph Foundation Model with Transferable Tree Vocabular | graph-foundation-model, tree-vocabulary, transferable-pretraining | c23ccf9eedf87e4380e92b75b24955bb.md |
| 507 | Remix-DiT: Mixing Diffusion Transformers for Multi-Expert De | diffusion-transformers, mixture-of-experts, denoising | c2ae6a5b08e85fb96e31ff7dba83d6c1.md |
| 508 | xLSTM: Extended Long Short-Term Memory | LSTM, extended-memory, large-language-models | c2ce2f2701c10a2b2f2ea0bfa43cfaa3.md |
| 509 | Transformers Can Do Arithmetic with the Right Embeddings | transformers, arithmetic-reasoning, positional-embeddings | c35986bc1ee29b31c1011481b77fe540.md |
| 510 | Retrieval & Fine-Tuning for In-Context Tabular Models | tabular-data, in-context-learning, retrieval-augmented | c40daf14d7a6469e65116507c21faeb7.md |
| 511 | MATES: Model-Aware Data Selection for Efficient Pretraining  | data-selection, LLM-pretraining, data-influence | c4bec0d2fd217e6c2c3eafeced432582.md |
| 512 | Iteration Head: A Mechanistic Study of Chain-of-Thought | chain-of-thought, mechanistic-interpretability, transformer-circuits | c50f8180ef34060ec59b75d6e1220f7a.md |
| 513 | Adaptive Layer Sparsity for Large Language Models via Activa | llm-pruning, layer-sparsity, activation-correlation | c573258c38d0a3919d8c1364053c45df.md |
| 514 | xRAG: Extreme Context Compression for Retrieval-augmented Ge | context-compression, retrieval-augmented-generation, modality-fusion | c5cf13bfd3762821ef7607e63ee90075.md |
| 515 | LLM Processes: Numerical Predictive Distributions Conditione | llm-priors, probabilistic-forecasting, natural-language-conditioning | c5ec22711f3a4a2f4a0a8ffd92167190.md |
| 516 | IQA-EVAL: Automatic Evaluation of Human-Model Interactive Qu | llm-evaluation, interactive-qa, human-model-interaction | c6a23b26eaaefd187973658f5001f4fe.md |
| 517 | VideoLLM-MoD: Efficient Video-Language Streaming with Mixtur | video-language-models, mixture-of-depths, efficient-inference | c6a79e139ec4f371701ea8cc9e06018e.md |
| 518 | Towards Unified Multimodal Editing with Enhanced Knowledge C | multimodal-llm, knowledge-editing, knowledge-collaboration | c705ba25f183b875c9359ef83fa262e8.md |
| 519 | Reranking Laws for Language Generation: A Communication-Theo | reranking, language-generation, communication-theory | c8b2f897e45770595656a79a9ad91e89.md |
| 520 | FedLLM-Bench: Realistic Benchmarks for Federated Learning of | federated-learning, large-language-models, benchmarking | c8cdab0e890c59255c27977072fdb0f0-abstract-datasetsandbenchmarkstrackhtml.md |
| 521 | WizardArena: Post-training Large Language Models via Simulat | post-training, instruction-following, chatbot-arena-simulation | ca4aa9acc097e0f606af55bf986cb031.md |
| 522 | Adversarial Moment-Matching Distillation of Large Language M | knowledge-distillation, moment-matching, language-model-compression | cbae8efcc23a0cb6d15a20f245514020.md |
| 523 | The Factorization Curse: Which Tokens You Predict Underlie t | reversal-curse, hallucination, token-factorization | cbcce87f745072c819204529be843d16.md |
| 524 | Source Code Foundation Models are Transferable Binary Analys | binary-analysis, source-code-models, reverse-engineering | cc83e97320000f4e08cb9e293b12cf7e.md |
| 525 | NoMAD-Attention: Efficient LLM Inference on CPUs Through Mul | llm-inference, cpu-optimization, attention-efficiency | ccda3c632cc8590ee60ca5ba226a4c30.md |
| 526 | Fractal Patterns May Illuminate the Success of Next-Token Pr | language-modeling, fractal-structure, self-similarity | cd004fa45fc1fe5c0218b7801d98d036.md |
| 527 | Customizing Language Models with Instance-wise LoRA for Sequ | sequential-recommendation, LoRA, instance-wise | cd476d01692c508ddf1cb43c6279a704.md |
| 528 | ArkVale: Efficient Generative LLM Inference with Recallable  | LLM-inference, KV-cache, eviction | cd4b49379efac6e84186a3ffce108c37.md |
| 529 | Bridging The Gap between Low-rank and Orthogonal Adaptation  | parameter-efficient-fine-tuning, Householder-reflection, low-rank-adaptation | cdd0640218a27e9e2c0e52e324e25db0.md |
| 530 | Buffer of Thoughts: Thought-Augmented Reasoning with Large L | chain-of-thought, LLM-reasoning, thought-augmentation | cde328b7bf6358f5ebb91fe9c539745e.md |
| 531 | Enhancing Large Language Models through Adaptive Tokenizers | tokenization, adaptive-tokenizers, LLM-efficiency | cdf00c97c0cb2cc35179f03363da6c4f.md |
| 532 | SAFE: Slow and Fast Parameter-Efficient Tuning for Continual | continual-learning, parameter-efficient-tuning, pre-trained-models | ce406fcba6401cd90cbded79567e2cf5.md |
| 533 | On the Surprising Effectiveness of Attention Transfer for Vi | attention-transfer, vision-transformers, pre-training | ceb45c48e29e7f49b0b47edb98e43691.md |
| 534 | Scaling Laws with Vocabulary: Larger Models Deserve Larger V | scaling-laws, vocabulary-size, large-language-models | cf5a019ae9c11b4be88213ce3f85d85c.md |
| 535 | Cal-DPO: Calibrated Direct Preference Optimization for Langu | direct-preference-optimization, LLM-alignment, contrastive-learning | cf8b2205e39f81726a8d828ecbe00ad0.md |
| 536 | Dynamic Tuning Towards Parameter and Inference Efficiency fo | parameter-efficient-fine-tuning, vision-transformers, inference-efficiency | d0241a0fb1fc9be477bdfde5e0da276a.md |
| 537 | Calibrating Reasoning in Language Models with Internal Consi | chain-of-thought, reasoning-calibration, internal-consistency | d037fd021c9aace128b8ce25001cdb6c.md |
| 538 | Amortized Fourier Neural Operators | fourier-neural-operators, partial-differential-equations, parameter-efficiency | d06a797c436cd5136a6f45b063316278.md |
| 539 | AutoSurvey: Large Language Models Can Automatically Write Su | automated-survey-generation, large-language-models, literature-review | d07a9fc7da2e2ec0574c38d5f504d105.md |
| 540 | Mixture of Adversarial LoRAs: Boosting Robust Generalization | adversarial-meta-tuning, lora, few-shot-learning | d085b2d2d6dee1dd596bc3b8ecd5aaa6.md |
| 541 | PowerPM: Foundation Model for Power Systems | foundation-model, electricity-time-series, power-systems | d0a2279c9f7ded859bcbf878c3c3d1ed.md |
| 542 | Cost-efficient Knowledge-based Question Answering with Large | knowledge-based-qa, large-language-models, cost-efficiency | d0aafec03d59db29a92fa683bd783374.md |
| 543 | LoQT: Low-Rank Adapters for Quantized Pretraining | low-rank-adapters, quantized-training, pretraining | d0c6bc641a56bebee9d985b937307367.md |
| 544 | Parallelizing Linear Transformers with the Delta Rule over S | linear-transformers, delta-rule, parallel-training | d13a3eae72366e61dfdc7eea82eeb685.md |
| 545 | Adaptable Logical Control for Large Language Models | constrained-decoding, neuro-symbolic, large-language-models | d15c16cf5619a2b1606da5fc88e3f1a9.md |
| 546 | FLAME : Factuality-Aware Alignment for Large Language Models | factuality, alignment, RLHF | d16152d53088ad779ffa634e7bf66166.md |
| 547 | $\textit{Read-ME}$: Refactorizing LLMs as Router-Decoupled M | mixture-of-experts, llm-inference, router-decoupling | d298cf34e4539f9134db7f38b42f69fe.md |
| 548 | RedPajama: an Open Dataset for Training Large Language Model | open-dataset, llm-pretraining, data-composition | d34497330b1fd6530f7afd86d0df9f76-abstract-datasetsandbenchmarkstrackhtml.md |
| 549 | Iterative Reasoning Preference Optimization | chain-of-thought, preference-optimization, iterative-training | d37c9ad425fe5b65304d500c6edcba00.md |
| 550 | Gated Slot Attention for Efficient Linear-Time Sequence Mode | linear-attention, gated-slot-attention, sequence-modeling | d3f39e51f5f634fb16cc3e658f8512b9.md |
| 551 | The Impact of Initialization on LoRA Finetuning Dynamics | LoRA, fine-tuning, initialization | d4387c37b3b06e55f86eccdb8cd1f829.md |
| 552 | Learning Goal-Conditioned Representations for Language Rewar | RLHF, representation-learning, goal-conditioned | d46f127a80dc58cbc0732a717285c43a.md |
| 553 | Navigating Extremes: Dynamic Sparsity in Large Output Spaces | dynamic-sparse-training, large-output-spaces, model-pruning | d4bdeed749a437de2cbe2e2c7e5a6a8a.md |
| 554 | Adaptive Sampling for Efficient Softmax Approximation | softmax-approximation, adaptive-sampling, efficient-computation | d52dbd66219dc4e432e0bd4f9c25c4c3.md |
| 555 | Noise Contrastive Alignment of Language Models with Explicit | language-model-alignment, noise-contrastive-estimation, explicit-rewards | d5a58d198afa370a3dff0e1ca4fe1802.md |
| 556 | PaDeLLM-NER: Parallel Decoding in Large Language Models for  | named-entity-recognition, parallel-decoding, latency-reduction | d5aed68fde8e934d0ae4aadb57acc6c0.md |
| 557 | Code Repair with LLMs gives an Exploration-Exploitation Trad | code-repair, exploration-exploitation, LLM-refinement | d5c56ec4f69c9a473089b16000d3f8cd.md |
| 558 | Deep Bayesian Active Learning for Preference Modeling in Lar | active-learning, preference-modeling, Bayesian-deep-learning | d5e256c988bdee59a0f4d7a9bc1dd6d9.md |
| 559 | Large Language Model Unlearning via Embedding-Corrupted Prom | LLM-unlearning, embedding-corruption, alignment | d6359156e0e30b1caa116a4306b12688.md |
| 560 | SLTrain: a sparse plus low rank approach for parameter and m | sparse-low-rank, pretraining-efficiency, memory-efficient | d63cf0622eed012a17fe88fced64dcb8.md |
| 561 | Sigmoid Gating is More Sample Efficient than Softmax Gating  | mixture-of-experts, sigmoid-gating, sample-efficiency | d65befe6b80ecf7f180b4def503d7776.md |
| 562 | MambaLRP: Explaining Selective State Space Sequence Models | explainability, mamba, state-space-models | d6d0e41e0b1ed38c76d13c9e417a8f1f.md |
| 563 | Knowledge Circuits in Pretrained Transformers | knowledge-circuits, transformers, mechanistic-interpretability | d6df31b1be98e04be48af8bedb95b499.md |
| 564 | Superposed Decoding: Multiple Generations from a Single Auto | autoregressive-decoding, multiple-drafts, inference-efficiency | d74f9efa1d8ca30b31d65cef8de7c2bf.md |
| 565 | Mixture of Experts Meets Prompt-Based Continual Learning | mixture-of-experts, continual-learning, prompt-tuning | d78d68cae595fabadd187b583ee8708e.md |
| 566 | ElasTST: Towards Robust Varied-Horizon Forecasting with Elas | time-series-forecasting, elastic-transformer, multi-horizon | d7aa002885ccbe68cf6880da583761b2.md |
| 567 | Multiple Physics Pretraining for Spatiotemporal Surrogate Mo | physics-pretraining, spatiotemporal-surrogate, transformer-autoregressive | d7cb9db5ade2db7814fbd01ee59f4c7b.md |
| 568 | Streaming Long Video Understanding with Large Language Model | streaming-video-understanding, vision-language-model, long-video | d7ce06e9293c3d8e6cb3f80b4157f875.md |
| 569 | InfLLM: Training-Free Long-Context Extrapolation for LLMs wi | long-context-LLM, context-memory, training-free-extrapolation | d842425e4bf79ba039352da0f658a906.md |
| 570 | ALPINE: Unveiling The Planning Capability of Autoregressive  | planning, transformer, autoregressive | d848cb2c84f0bba7f1f73cf232734c40.md |
| 571 | Latent Paraphrasing: Perturbation on Layers Improves Knowled | knowledge-injection, fine-tuning, paraphrasing | d85030334fadbd55043c911076caf0ae.md |
| 572 | Ensemble Learning for Heterogeneous Large Language Models wi | llm-ensemble, heterogeneous-models, deep-parallel-collaboration | d8a6eb79f8ccaacbe7198a5caf3a0323.md |
| 573 | Meaningful Learning: Enhancing Abstract Reasoning in Large L | abstract-reasoning, llm-enhancement, generic-facts | da5498f88193ff61f0daea1940b819da.md |
| 574 | Unleashing Region Understanding in Intermediate Layers for M | multimodal-llm, referring-expression-generation, region-understanding | da76884a4e003ad0de97804ec4578e5b.md |
| 575 | PiSSA: Principal Singular Values and Singular Vectors Adapta | parameter-efficient-fine-tuning, low-rank-adaptation, singular-value-decomposition | db36f4d603cc9e3a2a5e10b93e6428f2.md |
| 576 | Suitable is the Best: Task-Oriented Knowledge Fusion in Vuln | vulnerability-detection, knowledge-fusion, task-oriented-learning | db7a81128155d6f14970c12d0b5e7a4c.md |
| 577 | RankRAG: Unifying Context Ranking with Retrieval-Augmented G | retrieval-augmented-generation, context-ranking, instruction-tuning | db93ccb6cf392f352570dd5af0a223d3.md |
| 578 | Extending Video Masked Autoencoders to 128 frames | video-understanding, masked-autoencoders, self-supervised-pretraining | dbe2cfe4767f3255160b73a36ae3162e.md |
| 579 | CogVLM: Visual Expert for Pretrained Language Models | visual-language-model, visual-expert, multimodal-alignment | dc06d4d2792265fb5454a6092bfd5c6a.md |
| 580 | The Group Robustness is in the Details: Revisiting Finetunin | spurious-correlations, worst-group-accuracy, finetuning | dc4db2ff2c1aefce3b594f821ea82fe6.md |
| 581 | AutoTimes: Autoregressive Time Series Forecasters via Large  | time-series-forecasting, large-language-models, autoregressive-pretraining | dcf88cbc8d01ce7309b83d0ebaeb9d29.md |
| 582 | Prompt Optimization with EASE? Efficient Ordering-aware Auto | prompt-optimization, in-context-learning, exemplar-selection | dd8e7dae18cecd7c9137840161e1bf62.md |
| 583 | EMR-Merging: Tuning-Free High-Performance Model Merging | model-merging, multi-task-learning, tuning-free | dda5cac5272a9bcd4bc73d90bc725ef1.md |
| 584 | Can Language Models Perform Robust Reasoning in Chain-of-tho | chain-of-thought, noisy-rationales, llm-robustness | dfaa29ed28dfa175bcc5e2a54aa199f8.md |
| 585 | LLM Dataset Inference: Did you train on my dataset? | dataset-inference, llm-copyright, membership-inference | e01519b47118e2f51aa643151350c905.md |
| 586 | SimPO: Simple Preference Optimization with a Reference-Free  | preference-optimization, dpo, rlhf | e099c1c9699814af0be873a175361713.md |
| 587 | Getting More Juice Out of the SFT Data: Reward Learning from | sft, reward-learning, rlhf | e0c9b65fb3e41aaa86576df3ec33ad2e.md |
| 588 | Accuracy is Not All You Need | llm-compression, quantization, benchmarking | e0e956681b04ac126679e8c7dd706b2e.md |
| 589 | SpaceByte: Towards Deleting Tokenization from Large Language | tokenization-free, byte-level-modeling, large-language-models | e1f418450107c4a0ddc16d008d131573.md |
| 590 | Open-Vocabulary Object Detection via Language Hierarchy | open-vocabulary-detection, language-hierarchy, weak-supervision | e1fcd183ab33714a8464e4e9a20ac710.md |
| 591 | Confidence Regulation Neurons in Language Models | uncertainty-representation, entropy-neurons, language-models | e21955c93dede886af1d0d362c756757.md |
| 592 | Invariant Tokenization of Crystalline Materials for Language | crystal-generation, SE3-invariance, language-model-tokenization | e23133d34964a0a09f6d076fc4b922a4.md |
| 593 | fMRI predictors based on language models of increasing compl | fMRI-encoding, language-models, brain-lateralization | e28e19d00b23fe0265f433fa05a96b06.md |
| 594 | Instance-adaptive Zero-shot Chain-of-Thought Prompting | chain-of-thought, zero-shot-prompting, instance-adaptive | e304e04a6f455dd82f8a85a0a3679493.md |
| 595 | SELF-DISCOVER: Large Language Models Self-Compose Reasoning  | reasoning-structures, self-discovery, chain-of-thought | e41efb03e20ca3c231940a3c6917ef6f.md |
| 596 | AMOR: A Recipe for Building Adaptable Modular Knowledge Agen | llm-agents, modular-knowledge, process-feedback | e4595e77b045971a654edc5e3cd31989.md |
| 597 | Scaling Laws for Reward Model Overoptimization in Direct Ali | reward-overoptimization, RLHF, scaling-laws | e45caa3d5273d105b8d045e748636957.md |
| 598 | HuRef: HUman-REadable Fingerprint for Large Language Models | LLM-fingerprinting, copyright-protection, model-identification | e46fc33e80e9fa2febcdb058fba4beca.md |
| 599 | Quantifying the Gain in Weak-to-Strong Generalization | weak-to-strong-generalization, knowledge-distillation, superhuman-models | e4a0d8aef3567f742b0794844d9b5847.md |
| 600 | Self-playing Adversarial Language Game Enhances LLM Reasonin | self-play, adversarial-language-game, LLM-reasoning | e4be7e9867ef163563f4a5e90cec478f.md |
| 601 | Gorilla: Large Language Model Connected with Massive APIs | API-calling, tool-use, LLM-agents | e4c61f578ff07830f5c37378dd3ecb0d.md |
| 602 | IPO: Interpretable Prompt Optimization for Vision-Language M | vision-language-models, prompt-optimization, CLIP | e52e4de8689a9955b6d3ff421d019387.md |
| 603 | 4-bit Shampoo for Memory-Efficient Network Training | second-order-optimization, 4-bit-quantization, memory-efficient-training | e5b4633454cb2174779d294ccda02318.md |
| 604 | Demystify Mamba in Vision: A Linear Attention Perspective | Mamba, state-space-models, linear-attention | e618724ac897c6cf3fbfb273f8695d67.md |
| 605 | Smoothie: Label Free Language Model Routing | LLM-routing, label-free, model-selection | e6b57a990462df5afa58d64ce2709db9.md |
| 606 | A Theoretical Perspective for Speculative Decoding Algorithm | speculative-decoding, inference-acceleration, theoretical-analysis | e7349e785900b93d8b4971a3f2c1cefe.md |
| 607 | InfiBench: Evaluating the Question-Answering Capabilities of | code-llm, question-answering, benchmark-evaluation | e888eb9400fe14bb70e057aa1d719188-abstract-datasetsandbenchmarkstrackhtml.md |
| 608 | Sequoia: Scalable and Robust Speculative Decoding | speculative-decoding, LLM-inference, scalable-decoding | ea1f5f0878d43ff4fb8bf64ef4a2326c.md |
| 609 | SaulLM-54B & SaulLM-141B: Scaling Up Domain Adaptation for t | legal-LLM, domain-adaptation, large-language-models | ea3f85a33f9ba072058e3df233cf6cca.md |
| 610 | Many-shot Jailbreaking | jailbreaking, many-shot, long-context | ea456e232efb72d261715e33ce25f208.md |
| 611 | $\beta$-DPO: Direct Preference Optimization with Dynamic $\b | direct-preference-optimization, dynamic-beta, llm-alignment | ea888178abdb6fc233226d12321d754f.md |
| 612 | Online Adaptation of Language Models with a Memory of Amorti | online-learning, language-model-adaptation, amortized-contexts | eaf956b52bae51fbf387b8be4cc3ce18.md |
| 613 | Simple and Effective Masked Diffusion Language Models | masked-diffusion, language-modeling, discrete-diffusion | eb0b13cc515724ab8015bc978fdde0ad.md |
| 614 | Information Re-Organization Improves Reasoning in Large Lang | reasoning, information-reorganization, contextual-reasoning | eb1a323fa10d4102ff13422476a744ff.md |
| 615 | Activation Map Compression through Tensor Decomposition for  | tensor-decomposition, edge-ai, backpropagation-compression | eb58e6745340616828a053500220f963.md |
| 616 | Probing the Decision Boundaries of In-context Learning in La | in-context-learning, decision-boundaries, llm-probing | eb5dd4476448c44e55a759a985b3bbec.md |
| 617 | Spectral Adapter: Fine-Tuning in Spectral Space | parameter-efficient-fine-tuning, spectral-adaptation, weight-matrices | ec2b1931cbda8e4c1a601ff5ff81c4a6.md |
| 618 | AutoMix: Automatically Mixing Language Models | llm-routing, cost-optimization, model-mixing | ecda225cb187b40ea8edc1f46b03ffda.md |
| 619 | GREATS: Online Selection of High-Quality Data for LLM Traini | online-batch-selection, llm-training, data-quality | ed165f2ff227cf36c7e3ef88957dadd9.md |
| 620 | CuMo: Scaling Multimodal LLM with Co-Upcycled Mixture-of-Exp | multimodal-llm, mixture-of-experts, upcycling | ed1d3d4c64dc1b95332a8cde3f2a0bdf.md |
| 621 | Parallelizing Model-based Reinforcement Learning Over the Se | model-based-rl, sequence-parallelism, training-efficiency | ed5854c456e136afa3faa5e41b1f3509.md |
| 622 | LLMDFA: Analyzing Dataflow in Code with Large Language Model | dataflow-analysis, large-language-models, program-analysis | ed9dcde1eb9c597f68c1d375bbecf3fc.md |
| 623 | Unveiling LoRA Intrinsic Ranks via Salience Analysis | lora, parameter-efficient-fine-tuning, rank-analysis | ed9f00cb7dd5fbdc2175d55e2fdf1b05.md |
| 624 | Why Transformers Need Adam: A Hessian Perspective | adam-optimizer, hessian, transformers | ee0e45ff4de76cbfdf07015a7839f339.md |
| 625 | Ex Uno Pluria: Insights on Ensembling in Low Precision Numbe | ensemble-methods, low-precision-arithmetic, generalization | f10ceee5c6979988f334058561cac89f.md |
| 626 | Enhancing LLM’s Cognition via Structurization | llm-cognition, text-structurization, long-form-understanding | f169ec4d47933ea4896b994af8ff4f17.md |
| 627 | A Practitioner's Guide to Real-World Continual Multimodal Pr | continual-pretraining, multimodal-foundation-models, vision-language | f1a6a2cdc7e65dbb4579e78f97cd2665-abstract-datasetsandbenchmarkstrackhtml.md |
| 628 | EDT: An Efficient Diffusion Transformer Framework Inspired b | diffusion-transformer, efficient-inference, sketch-inspired-generation | f1f9962f76581ce8bf38d04c6d6c96b1.md |
| 629 | An Improved Empirical Fisher Approximation for Natural Gradi | natural-gradient-descent, fisher-information, empirical-fisher | f23098fa0cfcdef0e743b134d380eeb9.md |
| 630 | InfoRM: Mitigating Reward Hacking in RLHF via Information-Th | reward-hacking, RLHF, information-theoretic | f25d75fc760aec0a6174f9f5d9da59b8.md |
| 631 | Learning Where to Edit Vision Transformers | model-editing, vision-transformers, locality | f269520d5f111719dd82b36667997d49.md |
| 632 | IaC-Eval: A Code Generation Benchmark for Cloud Infrastructu | infrastructure-as-code, code-generation, benchmark | f26b29298ae8acd94bd7e839688e329b-abstract-datasetsandbenchmarkstrackhtml.md |
| 633 | Semantic Density: Uncertainty Quantification for Large Langu | uncertainty-quantification, hallucination, semantic-density | f26d4fbaf7dfa115f1d4b3f104e26bce.md |
| 634 | Understanding the Differences in Foundation Models: Attentio | attention-mechanisms, state-space-models, recurrent-networks | f271a36160097fbdb06a9adeb1605343.md |
| 635 | Membership Inference Attacks against Fine-tuned Large Langua | membership-inference, LLM-fine-tuning, self-prompt-calibration | f36ad694188bb4c4bbbd61e2038e069e.md |
| 636 | DenseFormer: Enhancing Information Flow in Transformers via  | transformer-architecture, depth-weighted-averaging, information-flow | f67449c7ab72f441d3a713b046c6818c.md |
| 637 | Aligning LLM Agents by Learning Latent Preference from User  | llm-alignment, user-feedback, preference-learning | f75744612447126da06767daecce1a84.md |
| 638 | Unchosen Experts Can Contribute Too: Unleashing MoE Models’  | mixture-of-experts, self-contrast, unchosen-experts | f77012b463892a3f2ac56d3a6086fc5b.md |
| 639 | Linguistic Collapse: Neural Collapse in (Large) Language Mod | neural-collapse, language-models, representations | f88cc8930b47a45ec4733123bf3039b9.md |
| 640 | Mixture of Scales: Memory-Efficient Token-Adaptive Binarizat | binarization, large-language-models, quantization | f89221edad5a6a4a54fcf247cb37cd62.md |
| 641 | Benchmarking Complex Instruction-Following with Multiple Con | instruction-following, benchmark, llm-evaluation | f8c24b08b96a08ec7a7a975feea7777e-abstract-datasetsandbenchmarkstrackhtml.md |
| 642 | InversionView: A General-Purpose Method for Reading Informat | mechanistic-interpretability, neural-activations, inversion | f94cfd15db3f16ee7789b6b7e91ec476.md |
| 643 | Divergences between Language Models and Human Brains | language-models, neural-alignment, brain-encoding | f96839fc751b67492e17e70f5c9730e4.md |
| 644 | Fine-grained Analysis of In-context Linear Estimation: Data, | in-context-learning, transformers, linear-attention | f9dc462382fef56d58279e75de2438f3.md |
| 645 | PediatricsGPT: Large Language Models as Chinese Medical Assi | pediatric-medicine, Chinese-LLM, medical-assistant | fa5b423e24b442180bcd4e13ae75a27f.md |
| 646 | Analysing the Generalisation and Reliability of Steering Vec | steering-vectors, activation-intervention, llm-alignment | fb3ad59a84799bfb8d700e56d19c231b.md |
| 647 | Search for Efficient Large Language Models | llm-compression, pruning, quantization | fb64a43508e0cfe53ee6179ff31ea900.md |
| 648 | Boosting Text-to-Video Generative Model with MLLMs Feedback | text-to-video, RLHF, multimodal-feedback | fbe2b2f74a2ece8070d8fb073717bda6.md |
| 649 | The Iterative Optimal Brain Surgeon: Faster Sparse Recovery  | model-pruning, sparsity, optimal-brain-surgeon | fc1dce23e0ba01d3b691789cfd4f65c3.md |
| 650 | Understanding Linear Probing then Fine-tuning Language Model | linear-probing, fine-tuning, neural-tangent-kernel | fcc22e5b7d5d2155d994da22d045f0a6.md |
| 651 | MiniCache: KV Cache Compression in Depth Dimension for Large | kv-cache, compression, large-language-models | fd0705710bf01b88a60a3d479ea341d9.md |
| 652 | MKGL: Mastery of a Three-Word Language | knowledge-graphs, large-language-models, triplet-language | fe03053bd2cf5b5c56de1e463bc53e1a.md |
| 653 | MatFormer: Nested Transformer for Elastic Inference | nested-transformer, elastic-inference, foundation-models | fe066022bab2a6c6a3c57032a1623c70.md |
| 654 | UniTS: A Unified Multi-Task Time Series Model | time-series, multi-task-learning, unified-transformer | fe248e22b241ae5a9adf11493c8c12bc.md |
| 655 | CLUES: Collaborative Private-domain High-quality Data Select | federated-learning, data-selection, training-dynamics | ff80e644be415af4bcd7e4b4efb2152f.md |
| 656 | Discovering Sparsity Allocation for  Layer-wise Pruning of L | llm-pruning, sparsity-allocation, layer-wise-compression | ff997469ac66cf893c4183efeb22212a.md |
