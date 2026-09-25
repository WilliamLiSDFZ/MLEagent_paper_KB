---
name: deep-learning-optimization-and-generalization-theory
description: >-
  This skill covers theoretical analysis and practical optimization of deep learning training dynamics, architectures, and generalization, spanning convergence guarantees for methods like PINNs, policy gradient algorithms, and transformer in-context learning, alongside efficiency techniques including quantization (QBB), neural architecture search, adaptive compute allocation for LLMs, and structured matrix linear layers. It also addresses training stability (
---

# Deep Learning Optimization And Generalization Theory

This skill covers theoretical analysis and practical optimization of deep learning training dynamics, architectures, and generalization, spanning convergence guarantees for methods like PINNs, policy gradient algorithms, and transformer in-context learning, alongside efficiency techniques including quantization (QBB), neural architecture search, adaptive compute allocation for LLMs, and structured matrix linear layers. It also addresses training stability (

## Entry Index

| # | Title | Tags | File |
|---|-------|------|------|
| 1 | How does PDE order affect the convergence of PINNs? | physics-informed-neural-networks, PDE-order, gradient-descent-convergence | 00532321a253959cedc4f971b5524131.md |
| 2 | Occupancy-based Policy Gradient: Estimation, Convergence, an | occupancy-functions, policy-gradient, convergence-optimality | 010c855df402b443e0c16e5b7434e74c.md |
| 3 | Deep Policy Gradient Methods Without Batch Updates, Target N | policy-gradient, online-learning, resource-constrained | 019ef89617d539b15ed610ce8d1b76e1.md |
| 4 | Towards Understanding How Transformers Learn In-context Thro | in-context-learning, transformers, representation-learning | 01a8d63f9cb6dcbaa3092ccddd2075ac.md |
| 5 | Learning from Teaching Regularization: Generalizable Correla | regularization, generalization, knowledge-distillation | 01ce1ae7f94d139e4917f9e4425a4f38.md |
| 6 | D-LLM: A Token Adaptive Computing Resource Allocation Strate | token-adaptive-computation, llm-efficiency, resource-allocation | 03469b1a66e351b18272be23baf3b809.md |
| 7 | einspace: Searching for Neural Architectures from Fundamenta | neural-architecture-search, search-space-diversity, fundamental-operations | 0382cb76309820f71c6eacd47b36ce71.md |
| 8 | Connecting Joint-Embedding Predictive Architecture with Cont | self-supervised-learning, jepa, contrastive-learning | 04a80267ad46fc730011f8760f265054.md |
| 9 | Analyzing & Reducing the Need for Learning Rate Warmup in GP | learning-rate-warmup, GPT-training, optimization | 059445c2d5b3ef918079851628fef1d6.md |
| 10 | QBB: Quantization with Binary Bases for LLMs | post-training-quantization, binary-bases, llm-compression | 05b69cc4c8ff6e24c5de1ecd27223d37.md |
| 11 | Disentangling and mitigating the impact of task similarity f | continual-learning, catastrophic-forgetting, task-similarity | 05cdc7feee41e3572a9a3f4acb773891.md |
| 12 | Training for Stable Explanation for Free | stable-explanations, adversarial-training, explainability | 0626822954674a06ccd9c234e3f0d572.md |
| 13 | HyperLogic: Enhancing Diversity and Accuracy in Rule Learnin | rule-learning, hypernetworks, neural-logic | 067437c6d5d0369b6d09200bef89715b.md |
| 14 | Optimizing Automatic Differentiation with Deep Reinforcement | automatic-differentiation, jacobian-computation, deep-reinforcement-learning | 06cbd2e81dfbd3bb4cb0abce95b32584.md |
| 15 | Searching for Efficient Linear Layers over a Continuous Spac | structured-matrices, linear-layers, efficiency | 0729c38b421cd66f2313ab397d099e37.md |
| 16 | CLIPCEIL: Domain Generalization through CLIP via Channel rEf | domain-generalization, CLIP, channel-refinement | 080be5eb7e887319ff30c792c2cbc28c.md |
| 17 | Explicit Eigenvalue Regularization Improves Sharpness-Aware  | sharpness-aware-minimization, hessian-eigenvalue, generalization | 0845e3f7447ff9e36a26033bb7334674.md |
| 18 | Weight decay induces low-rank attention layers | weight-decay, low-rank, attention-layers | 084a67fb91826028f555e288f3adc9a4.md |
| 19 | Topological Generalization Bounds for Discrete-Time Stochast | topological-generalization, stochastic-optimization, complexity-measures | 0886e50806c3faf55e557bd63ba3e70c.md |
| 20 | PV-Tuning: Beyond Straight-Through Estimation for Extreme LL | extreme-quantization, LLM-compression, straight-through-estimation | 091166620a04a289c555f411d8899049.md |
| 21 | Feedback control guides credit assignment in recurrent neura | credit-assignment, recurrent-neural-networks, feedback-control | 09236f27bad623511341362f26ffcabb.md |
| 22 | Can Learned Optimization Make Reinforcement Learning Less Di | reinforcement-learning, learned-optimization, plasticity | 09e1944b7f2372f9f81866470c59b663.md |
| 23 | Visual Fourier Prompt Tuning | visual-prompt-tuning, Fourier-features, parameter-efficient-finetuning | 0a0eba34ab2ff40ca2d2843324dcc4ab.md |
| 24 | Hardness of Learning Neural Networks under the Manifold Hypo | manifold-hypothesis, learnability, computational-hardness | 0ad6ebd11593822b8a6d5873ca9c5b0b.md |
| 25 | Trade-Offs of Diagonal Fisher Information Matrix Estimators | fisher-information-matrix, diagonal-estimators, neural-network-optimization | 0b43289db08ed60edc6451cb2132e203.md |
| 26 | Rethinking Imbalance in Image Super-Resolution for Efficient | super-resolution, imbalanced-learning, efficient-inference | 0d0dac08f4199f0c348dd2feace0305a.md |
| 27 | On the Saturation Effects of Spectral Algorithms in Large Di | spectral-algorithms, kernel-ridge-regression, saturation-effects | 0d3496dd0cec77a999c98d35003203ca.md |
| 28 | You Only Cache Once: Decoder-Decoder Architectures for Langu | kv-cache, decoder-decoder, efficient-inference | 0df38cd13520747e1e64e5b123a78ef8.md |
| 29 | Breaking Long-Tailed Learning Bottlenecks: A Controllable Pa | long-tailed-learning, hypernetwork, diverse-experts | 0e21697f3b9385f6c4100aad94c26bed.md |
| 30 | Make Continual Learning Stronger via C-Flat | continual-learning, catastrophic-forgetting, loss-landscape | 0e705ac30e573d1526f81a0fd071a151.md |
| 31 | Stability and Generalization of Asynchronous SGD: Sharper Bo | asynchronous-SGD, generalization-bounds, distributed-learning | 0e7e2af2e5ba822c9ad35a37b31b5dd4.md |
| 32 | Understanding the Gains from Repeated Self-Distillation | self-distillation, knowledge-distillation, generalization | 0eb1ac7551ddbae575415aa5183a88be.md |
| 33 | Visual Prompt Tuning in Null Space for Continual Learning | continual-learning, prompt-tuning, null-space | 0f06be0008bc568c88d76206aa17954f.md |
| 34 | Kraken: Inherently Parallel Transformers For Efficient Multi | transformer-inference, parallelism, multi-device | 0f4d1fc085b7504c140e66bb26ed8842.md |
| 35 | Reparameterization invariance in approximate Bayesian infere | bayesian-neural-networks, reparameterization-invariance, approximate-inference | 0f934dd2030f5740cde0aa2697a105a9.md |
| 36 | Improving Deep Learning Optimization through Constrained Par | regularization, weight-decay, constrained-optimization | 10e9204f14c4daa08041343455435308.md |
| 37 | Understanding Representation of Deep Equilibrium Models from | deep-equilibrium-models, neural-collapse, implicit-networks | 128911cc894d57bcae78074a9551c132.md |
| 38 | ECLipsE: Efficient Compositional Lipschitz Constant Estimati | lipschitz-constant, neural-network-robustness, certified-bounds | 1419d8554191a65ea4f2d8e1057973e4.md |
| 39 | Toward Global Convergence of Gradient EM for Over-Paramteriz | expectation-maximization, gaussian-mixture-models, over-parameterization | 14a1f12a530a934dc034f4c1e2d97aa8.md |
| 40 | On Convergence of Adam for Stochastic Optimization under Rel | adam-optimizer, non-convex-optimization, affine-variance-noise | 14bb27f680bee45d83bc769738e7f9b5.md |
| 41 | Selective Attention: Enhancing Transformer through Principle | selective-attention, transformer, context-control | 14fc4a68da97a3d31eb11c642b0b10fc.md |
| 42 | Typicalness-Aware Learning for Failure Detection | failure-detection, overconfidence, typicalness | 155ace40b55215479b6ad4665d1f6c06.md |
| 43 | Incorporating Test-Time Optimization into Training with Dual | human-mesh-recovery, test-time-optimization, dual-networks | 158f036baa5b80a4fe2af094de8f7539.md |
| 44 | Generalization Bound and Learning Methods for Data-Driven Pr | linear-programming, data-driven-projections, generalization-bounds | 1780db9272f81961459f4906036ebc6f.md |
| 45 | Non-asymptotic Analysis of Biased Adaptive Stochastic Approx | biased-gradients, adaptive-sgd, non-asymptotic-analysis | 178b306c7ee66a66db2171646e17da36.md |
| 46 | Navigating the Effect of Parametrization for Dimensionality  | dimensionality-reduction, parametric-methods, parametrization-effects | 178de34a090423c359a0ca2d51a25706.md |
| 47 | DapperFL: Domain Adaptive Federated Learning with Model Fusi | federated-learning, domain-adaptation, model-pruning | 17a1a1439421f1837e10cd612bf92861.md |
| 48 | Policy-shaped prediction: avoiding distractions in model-bas | model-based-rl, distraction-avoidance, policy-shaped-prediction | 17af43527227c5c96db0f8d4c6aadc4e.md |
| 49 | Fundamental Convergence Analysis of Sharpness-Aware Minimiza | sharpness-aware-minimization, convergence-analysis, generalization | 17b08a9de93e2accf13429643e7eafdc.md |
| 50 | Learning to grok: Emergence of in-context learning and skill | in-context-learning, modular-arithmetic, skill-composition | 17d60fef592086d1a5cb136f1946df59.md |
| 51 | Pretraining with Random Noise for Fast and Robust Learning w | pretraining, random-noise, weight-transport-free-learning | 18d3a2f3068d6c669dcae19ceca1bc24.md |
| 52 | FSP-Laplace: Function-Space Priors for the Laplace Approxima | laplace-approximation, bayesian-deep-learning, function-space-priors | 19774ce2d4b0d17a3a8aea26ad99fe8a.md |
| 53 | Functional Bilevel Optimization for Machine Learning | bilevel-optimization, functional-optimization, machine-learning | 19ae2b95d3831c14373271112f189a22.md |
| 54 | Emergence of heavy tails in homogenized stochastic gradient  | stochastic-gradient-descent, heavy-tails, homogenization | 19ba2b9448d5de25826f6eb408dab194.md |
| 55 | Initialization is Critical to Whether Transformers Fit Compo | transformers, compositional-generalization, initialization | 19c145aaad40927c51f4d10eaa339c20.md |
| 56 | On the Role of Attention Masks and LayerNorm in Transformers | transformers, self-attention, rank-collapse | 1ac3030fc57850b0fb11dfe9d4880ad7.md |
| 57 | Directional Smoothness and Gradient Methods: Convergence and | gradient-descent, directional-smoothness, convergence | 1ac83203e88eb6cf6b30642f0239b932.md |
| 58 | Lower Bounds of Uniform Stability in Gradient-Based Bilevel  | bilevel-optimization, hyperparameter-optimization, uniform-stability | 1b96f01343ff10150e6719eb163e1536.md |
| 59 | Improving self-training under distribution shifts via anchor | self-training, distribution-shift, confidence-calibration | 1b99db17b54735d22dbed15c24f2dbdc.md |
| 60 | Improving Deep Reinforcement Learning by Reducing the Chain  | deep-reinforcement-learning, value-churn, policy-churn | 1bd8a2967508c5cf068ac204151b6ecd.md |
| 61 | No Train, all Gain: Self-Supervised Gradients Improve Deep F | self-supervised-learning, gradient-features, frozen-representations | 1bf4cad47f5a54c98fbe7d10516ebf77.md |
| 62 | Stability and Generalization of Adversarial Training for Sha | adversarial-training, generalization, shallow-neural-networks | 1d35a777e932235b115645d5141e0342.md |
| 63 | From Unstructured Data to In-Context Learning: Exploring Wha | in-context-learning, transformers, unstructured-data | 1da38b872e19f1f4a3c2846720e8f64a.md |
| 64 | 4+3 Phases of Compute-Optimal Neural Scaling Laws | neural-scaling-laws, compute-optimal, phase-transitions | 1dccfc3ee01871d05e33457c61037d59.md |
| 65 | Implicit Regularization of Decentralized Gradient Descent fo | implicit-regularization, decentralized-optimization, sparse-regression | 1df5c96e327ea0cbd32e0d8bae835994.md |
| 66 | ST$_k$: A Scalable Module for Solving Top-k Problems | top-k, differentiable-ranking, scalable | 1e0ebde5c2152b03420d9258f7139a58.md |
| 67 | Non-asymptotic Global Convergence Analysis of BFGS with the  | BFGS, quasi-newton, global-convergence | 1e269abc604816c35f600ae14b354efd.md |
| 68 | FedAvP: Augment Local Data via Shared Policy in Federated Le | federated-learning, data-augmentation, shared-policy | 20563b8508ba42e1b688d922e926ee26.md |
| 69 | The Representation Landscape of Few-Shot Learning and Fine-T | in-context-learning, fine-tuning, representation-analysis | 206018a258033def63607fbdf364bd2d.md |
| 70 | Interpret Your Decision: Logical Reasoning Regularization fo | logical-reasoning, regularization, generalization | 2063a00c435aafbcc58c16ce1e522139.md |
| 71 | In-Context Learning of a Linear Transformer Block: Benefits  | in-context-learning, linear-transformer, MLP-component | 20b6b87ca17792337f414d948af7b0e8.md |
| 72 | Efficient Reinforcement Learning by Discovering Neural Pathw | reinforcement-learning, neural-pathways, sparse-networks | 216f4cd12cfd69d46770bb2b491ae24b.md |
| 73 | Suppress Content Shift: Better Diffusion Features via Off-th | diffusion-features, content-shift, discriminative-tasks | 21c86d5b10cdc28664ccdadf0a29065a.md |
| 74 | Curvature Clues: Decoding Deep Learning Privacy with Input L | privacy, loss-curvature, membership-inference | 238e6167319ad5da33c7b38594a1edb1.md |
| 75 | Learning and Transferring Sparse Contextual Bigrams with Lin | linear-transformers, in-context-learning, sparse-bigram | 2428ff361a08bc6864fb240bc83fba42.md |
| 76 | Predictor-Corrector Enhanced Transformers with Exponential M | residual-networks, ode-approximation, predictor-corrector | 2432eb0ddcf3bb630b5bcf96ca7e592d.md |
| 77 | Globally Q-linear Gauss-Newton Method for Overparameterized  | gauss-newton, matrix-sensing, overparameterization | 244da015b91e64f2d9362703fa2a902b.md |
| 78 | Nesterov acceleration despite very noisy gradients | nesterov-acceleration, noisy-gradients, convex-optimization | 24d2dd6dc9b79116f8ebc852ddb9dc94.md |
| 79 | DiffAug: A Diffuse-and-Denoise Augmentation for Training Rob | data-augmentation, diffusion-models, classifier-robustness | 24e8b46430df965674221665816a4964.md |
| 80 | Derivative-enhanced Deep Operator Network | deep-operator-networks, pde-surrogate, derivative-information | 25297252dcd3f4b11eec7ec7ab06bc80.md |
| 81 | What If the Input is Expanded in OOD Detection? | out-of-distribution-detection, input-expansion, scoring-functions | 25cc3adf8c85f7c70989cb8a97a691a7.md |
| 82 | Adaptive Variance Reduction for Stochastic Optimization unde | variance-reduction, adaptive-optimization, STORM | 272efd3a6091ceefcbc79f1f3a6fdba4.md |
| 83 | Rethinking Weight Decay for Robust Fine-Tuning of Foundation | weight-decay, fine-tuning, foundation-models | 281a6b49c66b94f81f3b1ae8f1a0dea4.md |
| 84 | Implicit Optimization Bias of Next-token Prediction in Linea | next-token-prediction, implicit-bias, linear-models | 2858e880333b3cd64f8192f13ddcca2f.md |
| 85 | A two-scale Complexity Measure for Deep Learning Models | generalization-bounds, effective-dimension, capacity-measure | 290141d6bfd7ea4d3f4483d126609bf6.md |
| 86 | Sketched Lanczos uncertainty score: a low-memory summary of  | uncertainty-quantification, fisher-information, lanczos-sketching | 29219efdb96e8164c589b4a0124451b7.md |
| 87 | Why Do We Need Weight Decay in Modern Deep Learning? | weight-decay, regularization, deep-learning-optimization | 29496c942ed6e08ecc469f4521ebfff0.md |
| 88 | Detecting Brittle Decisions for Free: Leveraging Margin Cons | adversarial-robustness, margin-consistency, brittle-decisions | 29753d93c5fc11167567e5df800308ae.md |
| 89 | Identifying Equivalent Training Dynamics | training-dynamics, neural-network-regimes, parameter-evolution | 2a07348a6a7b2c208ab5cb1ee0e78ab5.md |
| 90 | The Implicit Bias of Adam on Separable Data | Adam-optimizer, implicit-bias, logistic-regression | 2ac79356a03fe5e9250e5e77ebc76e6e.md |
| 91 | SIRIUS : Contexual Sparisty with Correction for Efficient LL | contextual-sparsity, LLM-inference, efficiency | 2ae6b2bdf3a179e3e24129e2c54bd871.md |
| 92 | ShiftAddLLM: Accelerating Pretrained LLMs via Post-Training  | llm-compression, shift-add-reparameterization, post-training-quantization | 2c30a37c75f062e0bf79297c73db8c6c.md |
| 93 | Take A Shortcut Back: Mitigating the Gradient Vanishing for  | spiking-neural-networks, gradient-vanishing, shortcut-connections | 2c37c5bcef24b9541550261dcd63261b.md |
| 94 | Shaving Weights with Occam's Razor: Bayesian Sparsification  | bayesian-sparsification, marginal-likelihood, neural-network-pruning | 2c572cad9ae98c5cb6f3fca040b2bc54.md |
| 95 | Cross-video Identity Correlating for Person Re-identificatio | person-re-identification, cross-video-pretraining, identity-correlation | 2ce10f144bb93449767f355c01f24cc1.md |
| 96 | Least Squares Regression Can Exhibit Under-Parameterized Dou | double-descent, least-squares, bias-variance-tradeoff | 2d43f7a61b57f83619f82c971e4bddc0.md |
| 97 | Unified Gradient-Based Machine Unlearning with Remain Geomet | machine-unlearning, gradient-based, KL-divergence | 2e622ac74f66df03b686a12e2e0e4424.md |
| 98 | Generalization of Hamiltonian algorithms | generalization, Hamiltonian-algorithms, stochastic-learning | 2e9d5bcfa9c32d360bae3d4e3d9cc032.md |
| 99 | Better by default: Strong pre-tuned MLPs and boosted trees o | tabular-data, MLP, gradient-boosted-trees | 2ee1c87245956e3eaa71aaba5f5753eb.md |
| 100 | Optimal deep learning of holomorphic operators between Banac | operator-learning, neural-networks, Banach-spaces | 3100d29d662360bb1a40a5ded8e100ae.md |
| 101 | How Far Can Transformers Reason? The Globality Barrier and I | transformers, reasoning, compositionality | 3107e4bdb658c79053d7ef59cbc804dd.md |
| 102 | The Empirical Impact of Neural Parameter Symmetries, or Lack | parameter-symmetries, neural-networks, mode-connectivity | 31d1946b6bccf54bdd4a811bedd9626b.md |
| 103 | A Layer-Wise Natural Gradient Optimizer for Training Deep Ne | natural-gradient, second-order-optimization, layer-wise | 31fb284a0aaaad837d2930a610cd5e50.md |
| 104 | Not All Tokens Are What You Need for Pretraining | selective-pretraining, token-importance, next-token-prediction | 3322a9a72a1707de14badd5e552ff466.md |
| 105 | A2PO: Towards Effective Offline Reinforcement Learning from  | offline-reinforcement-learning, advantage-aware, out-of-distribution | 333a7697dbb67f09249337f81c27d749.md |
| 106 | MSPE: Multi-Scale Patch Embedding Prompts Vision Transformer | vision-transformers, multi-scale-patch-embedding, variable-resolution | 3396657fe1a3c9a43ac7cd809c51a41e.md |
| 107 | Global Convergence in Training Large-Scale Transformers | transformer-optimization, gradient-flow, weight-decay | 33b47b3d2441a17b95344cd635f3dd01.md |
| 108 | Heavy-Tailed Class Imbalance and Why Adam Outperforms Gradie | adam-optimizer, heavy-tailed, class-imbalance | 350e718ff74062b4bac2c6ffd9e1ac66.md |
| 109 | Implicit Regularization Paths of Weighted Neural Representat | implicit-regularization, weighted-representations, pretrained-features | 359ddb9caccb4c54cc915dceeacf4892.md |
| 110 | Accelerating Transformers with Spectrum-Preserving Token Mer | token-merging, transformer-efficiency, spectrum-preserving | 37094fdc81632915a5738293cf9b7ad4.md |
| 111 | Toward a Well-Calibrated Discrimination via Survival Outcome | survival-analysis, contrastive-learning, calibration | 375fca131243755f9e268d1a37ffcd85.md |
| 112 | Towards Combating Frequency Simplicity-biased Learning for D | domain-generalization, frequency-bias, simplicity-bias | 377235d5cee7b104501407c0e5066c92.md |
| 113 | Frequency Adaptive Normalization For Non-stationary Time Ser | non-stationary, frequency-normalization, time-series-forecasting | 37c6d0bc4d2917dcbea693b18504bd87.md |
| 114 | On Statistical Rates and  Provably Efficient Criteria of Lat | diffusion-transformers, statistical-rates, latent-space | 37f6bed18b9b404f53dcaec4607c4fb7.md |
| 115 | High-dimensional (Group) Adversarial Training in Linear Regr | adversarial-training, high-dimensional-regression, robustness | 382a8606a85ca6ec7c06185a1a95ce8b.md |
| 116 | Interpretable Mesomorphic Networks for Tabular Data | interpretable-networks, tabular-data, deep-linear-models | 3848856978da28639d2057094a1287a5.md |
| 117 | $\epsilon$-Softmax: Approximating One-Hot Vectors for Mitiga | label-noise, symmetric-loss, softmax-approximation | 387936a8cd02bf2ad745b751047b9d49.md |
| 118 | Separation and Bias of Deep Equilibrium Models on Expressivi | deep-equilibrium-models, expressivity, learning-dynamics | 38e491559eb9e4cf31b8cd3a4e222436.md |
| 119 | Adaptive Depth Networks with Skippable Sub-Paths | adaptive-depth, inference-efficiency, layer-skipping | 3a2d96d2eb2902043c2db705ca03e9a2.md |
| 120 | Provable Acceleration of Nesterov's Accelerated Gradient for | matrix-factorization, Nesterov-acceleration, convergence-rate | 3b4e1336f775c3dba16ebbb8d2afd258.md |
| 121 | S-STE: Continuous Pruning Function for Efficient 2:4 Sparse  | sparse-training, 2:4-sparsity, straight-through-estimator | 3b576711b12ab036b45130fc8eb78504.md |
| 122 | Sparse maximal update parameterization: A holistic approach  | sparse-training, maximal-update-parameterization, training-dynamics | 3b6aaffec941f98930753fa6d6de7263.md |
| 123 | Quantum Algorithms for Non-smooth Non-convex Optimization | quantum-optimization, non-convex-optimization, zeroth-order-estimation | 3e2c12c1a41af7c19c5b38e0837a52d1.md |
| 124 | Topological obstruction to the training of shallow ReLU neur | loss-landscape, topological-obstruction, relu-networks | 3e356b84727460df86c8d0eeff1ff85d.md |
| 125 | Improving robustness to corruptions with multiplicative weig | corruption-robustness, multiplicative-weight-perturbations, data-augmentation | 3e9412a9c1d93810ef3ef7825115016b.md |
| 126 | Guiding Neural Collapse: Optimising Towards the Nearest Simp | neural-collapse, simplex-ETF, classifier-geometry | 3eb660055cdcdc9a545a0b16c1eff80d.md |
| 127 | Infinite Limits of Multi-head Transformer Dynamics | transformer-dynamics, infinite-width, feature-learning | 3eff068e195daace49955348de9f8398.md |
| 128 | WeiPer: OOD Detection using Weight Perturbations of Class Pr | OOD-detection, weight-perturbation, class-projections | 3effb91593c4fb42b1da1528328eff49.md |
| 129 | On the Impacts of the Random Initialization in the Neural Ta | neural-tangent-kernel, random-initialization, infinite-width | 3f0c8c5dc6b16e601b78e164a70d68a2.md |
| 130 | Separations in the Representational Capabilities of Transfor | transformers, recurrent-architectures, representational-capacity | 3f630b20b7b3ac76d3a0016fe29b6dc0.md |
| 131 | Dataset Decomposition: Faster LLM Training with Variable Seq | LLM-training, variable-sequence-length, curriculum-learning | 3f9bf45ea04c98ad7cb857f951f499e2.md |
| 132 | A Phase Transition between Positional and Semantic Learning  | attention-mechanism, phase-transition, theoretical-analysis | 3fefebc2d4e3c1c6ee9b892bd293117d.md |
| 133 | What Makes CLIP More Robust to Long-Tailed Pre-Training Data | CLIP, long-tailed-distribution, transfer-learning | 403d7aae69d2f2926dadb35499e1a105.md |
| 134 | Benign overfitting in leaky ReLU networks with moderate inpu | benign-overfitting, leaky-ReLU, neural-network-generalization | 4054556fcaa934b0bf76da52cf4f92cb.md |
| 135 | Scaling White-Box Transformers for Vision | white-box-transformers, vision-transformers, scaling | 412f33b7bfecf8d0318113a325339c96.md |
| 136 | Towards Exact Gradient-based Training on Analog In-memory Co | analog-computing, in-memory-computing, gradient-based-training | 419f72cbd568ad62183f8132a3605a2a.md |
| 137 | Efficient Sketches for Training Data Attribution and Studyin | gradient-sketching, training-data-attribution, loss-landscape | 4268cf6ba253744befa41ffee5083fa0.md |
| 138 | Soft ascent-descent as a stable and flexible alternative to  | flooding, loss-landscape, gradient-ascent | 430894999584d0bd358611e2ecf00b15.md |
| 139 | RanDumb: Random Representations Outperform Online Continuall | continual-learning, random-representations, catastrophic-forgetting | 4309616aaed8e848009bc4a7ef73b493.md |
| 140 | A Bayesian Approach to Data Point Selection | data-selection, bayesian-optimization, bi-level-optimization | 437587c32b781fbb94026ac5905b439b.md |
| 141 | Enhancing In-Context Learning Performance with just SVD-Base | in-context-learning, weight-pruning, SVD | 448444518637da106d978ae7409d9789.md |
| 142 | $\boldsymbol{\mu}\mathbf{P^2}$: Effective Sharpness Aware Mi | sharpness-aware-minimization, infinite-width, layerwise-scaling | 449a016a6ce6fba3fe50d05482abf836.md |
| 143 | An exactly solvable model for emergence and scaling laws in  | emergence, scaling-laws, sparse-parity | 45f7ad60c01f17711ccd8ac2f2fb77e3.md |
| 144 | Harnessing small projectors and multiple views for efficient | self-supervised-learning, visual-pretraining, multi-view | 464d8334dfca732d538ac050e45c6dc7.md |
| 145 | Long-tailed Object Detection Pretraining: Dynamic Rebalancin | long-tail-detection, contrastive-learning, pretraining | 470629a47e2d65ce0606c40055df5d26.md |
| 146 | HydraViT: Stacking Heads for a Scalable ViT | vision-transformers, multi-head-attention, scalability | 47387bb0aeb97785f608c11f2f4bb091.md |
| 147 | Learning predictable and robust neural representations by st | neural-representations, trajectory-straightening, visual-prediction | 473c578564ed9fe8041abfef772d37db.md |
| 148 | Reshuffling Resampling Splits Can Improve Generalization of  | hyperparameter-optimization, resampling, cross-validation | 47811ee68103bfcde7ca2223fccefb3a.md |
| 149 | On the Sparsity of the Strong Lottery Ticket Hypothesis | lottery-ticket-hypothesis, sparse-subnetworks, random-networks | 47908cab4e5b696d7af5c7de69f3b7d2.md |
| 150 | Improved Sample Complexity Bounds for Diffusion Model Traini | diffusion-models, sample-complexity, score-matching | 480e563034dbb6d1dd622d8eab7d129b.md |
| 151 | Inexact Augmented Lagrangian Methods for Conic Optimization: | augmented-Lagrangian, conic-optimization, linear-convergence | 480eb35745feb11c9120b666f640893e.md |
| 152 | SVFT: Parameter-Efficient Fine-Tuning with Singular Vectors | parameter-efficient-fine-tuning, singular-vectors, LoRA | 48c368f105e8145b945227b73255635a.md |
| 153 | A Universal Growth Rate for Learning with Smooth Surrogate L | surrogate-losses, H-consistency-bounds, classification | 4964cd3f89ee5b57f07f4bc1824d2beb.md |
| 154 | The Challenges of the Nonlinear Regime for Physics-Informed  | physics-informed-neural-networks, neural-tangent-kernel, nonlinear-PDEs | 49f07f600ca532a89ef4fa0618bb78c1.md |
| 155 | Transferability Bound Theory: Exploring Relationship between | adversarial-transferability, flatness, sharpness-aware-minimization | 49f80e4d2471ad4f2edf4f5f1ab62339.md |
| 156 | Understanding Scaling Laws with Statistical and Approximatio | scaling-laws, transformers, approximation-theory | 4a68bb0e075a3215d4ff37382ea598dc.md |
| 157 | Learning Transferable Features for Implicit Neural Represent | implicit-neural-representations, transfer-learning, neural-features | 4a8bc86ca475c229dc1fd0f4d5cf8f63.md |
| 158 | Learning symmetries via weight-sharing with doubly stochasti | group-equivariance, weight-sharing, doubly-stochastic-tensors | 4b34143d8a1e651f00002e31b3b72e95.md |
| 159 | Mean-Field Analysis for Learning Subspace-Sparse Polynomials | mean-field-theory, subspace-learning, two-layer-networks | 4c11f5dc728d29460f2eb7c096536726.md |
| 160 | DASH: Warm-Starting Neural Network Training in Stationary Se | warm-starting, plasticity-loss, continual-learning | 4c5ce1fc8895076f49935951a630be5c.md |
| 161 | RAMP: Boosting Adversarial Robustness Against Multiple $l_p$ | adversarial-robustness, multiple-lp-norms, adversarial-training | 4d5ce4a7ebf588834db127965cdb5ccb.md |
| 162 | Self-Supervised Adversarial Training via Diverse Augmented Q | self-supervised-adversarial-training, contrastive-learning, robustness | 4d65fc9de1051c382fd258dbafd8cde9.md |
| 163 | When are dynamical systems learned from time series data sta | dynamical-systems, time-series, statistical-accuracy | 4dc57702c987e1e72f0dd2921edb5ded.md |
| 164 | A Single-Step, Sharpness-Aware Minimization is All You Need  | sparse-training, sharpness-aware-minimization, generalization | 4e5a47c427ec16ec863e547bc1aeb70c.md |
| 165 | Implicit Regularization of Sharpness-Aware Minimization for  | sharpness-aware-minimization, scale-invariance, implicit-regularization | 4eb2c0adafbe71269f3a772c130f9e53.md |
| 166 | DOFEN: Deep Oblivious Forest ENsemble | tabular-data, oblivious-decision-trees, deep-ensemble | 4ec160e5bf92ce97ad307500e0db9151.md |
| 167 | Be Confident in What You Know: Bayesian Parameter Efficient  | bayesian-inference, parameter-efficient-fine-tuning, uncertainty-estimation | 4f1fbd5ab8d58d0ecf33c95fd46b900e.md |
| 168 | Biologically Inspired Learning Model for Instructed Vision | biologically-plausible-learning, predictive-coding, instructed-vision | 5039a14b703c4fda9c304a193dfd6d1e.md |
| 169 | Gradient-Free Methods for Nonconvex Nonsmooth Stochastic Com | gradient-free, nonconvex-nonsmooth, stochastic-compositional-optimization | 50be7e77b9c883144940be925b608acc.md |
| 170 | DHA: Learning Decoupled-Head Attention from Transformer Chec | multi-head-attention, head-fusion, LLM-inference | 518a75257f37b32f711082dff33c2ffc.md |
| 171 | Connectivity Shapes Implicit Regularization in Matrix Factor | matrix-factorization, implicit-regularization, nuclear-norm | 5195825ee60d7efc1e42b7f3f3137040.md |
| 172 | Training Dynamics of Transformers to Recognize Word Co-occur | transformer-training-dynamics, gradient-flow, word-co-occurrence | 520416e27d3b0cef3cd70a083e2991c7.md |
| 173 | How does Gradient Descent Learn Features --- A Local Analysi | feature-learning, gradient-descent, two-layer-neural-networks | 527d9d8f89aec80d634e366a97f49ba8.md |
| 174 | Loss Landscape Characterization of Neural Networks without   | loss-landscape, optimization-convergence, non-overparameterized-networks | 52f050499cf82fa8efb588e263f6f3a7.md |
| 175 | Theoretical Analysis of Weak-to-Strong Generalization | weak-to-strong-generalization, knowledge-distillation, theoretical-analysis | 5358d1e6138dff5718c5e9790f5fa593.md |
| 176 | Model Collapse Demystified: The Case of Regression | model-collapse, synthetic-data, regression | 53dbd7e34fab703a639964e2d3ee9e84.md |
| 177 | Generalizable Person Re-identification via Balancing Alignme | person-re-identification, domain-generalization, alignment | 53fba4404ebecf9730dc8919b71d4d22.md |
| 178 | Controlling Continuous Relaxation for Combinatorial Optimiza | combinatorial-optimization, continuous-relaxation, unsupervised-learning | 54191f424e9013fc1d7b923f6e45dff4.md |
| 179 | DisCEdit: Model Editing by Identifying Discriminative Compon | model-editing, discriminative-components, neurons | 54801e196796134a2b0ae5e8adef502f.md |
| 180 | Task Confusion and Catastrophic Forgetting in Class-Incremen | class-incremental-learning, catastrophic-forgetting, task-confusion | 5503a7c69d48a2f86fc00b3dc09de686.md |
| 181 | Graph Neural Networks Do Not Always Oversmooth | graph-neural-networks, oversmoothing, node-classification | 5623c35f3ab5e2c72aeb3abce27dc28f.md |
| 182 | Estimating Generalization Performance Along the Trajectory o | generalization-estimation, proximal-SGD, robust-regression | 56a033d57583623b4034d0ba80119601.md |
| 183 | Monomial Matrix Group Equivariant Neural Functional Networks | neural-functional-networks, monomial-matrix-groups, equivariance | 577cd5863ec73be4e6871340be0936ae.md |
| 184 | Linear Transformers are Versatile In-Context Learners | linear-attention, in-context-learning, gradient-descent | 57a3c602f0a1c8980cc5ed07e49d9490.md |
| 185 | SS1: Accelerating Inference with Fast and Expressive Sketch  | structured-matrices, efficient-inference, sparse-transforms | 57ef0373c890b30407eadfe6e06c8c84.md |
| 186 | On Mesa-Optimization in Autoregressively Trained Transformer | mesa-optimization, in-context-learning, autoregressive-pretraining | 581e1a06fa20f2c079dc5fb2db236335.md |
| 187 | Learning to Shape In-distribution Feature Space for Out-of-d | ood-detection, feature-space-shaping, discriminative-models | 58692a1701314e09cbd7a5f5f3871cc9.md |
| 188 | GS-Hider: Hiding Messages into 3D Gaussian Splatting | 3d-gaussian-splatting, steganography, watermarking | 59091e8226128dfad5f1d75a58f18906.md |
| 189 | Towards the Dynamics of a DNN Learning Symbolic Interactions | symbolic-interactions, neural-network-dynamics, two-phase-learning | 5aa96d1caa0d0b99d534b67df06be2ff.md |
| 190 | Happy: A Debiased Learning Framework for Continual Generaliz | continual-learning, category-discovery, debiased-learning | 5ae0f7cfd65d8e2b39da4177fef82015.md |
| 191 | SAMPa: Sharpness-aware Minimization Parallelized | sharpness-aware-minimization, parallelization, generalization | 5bf2b802e24106064dc547ae9283bb0c.md |
| 192 | Continuous Contrastive Learning for Long-Tailed Semi-Supervi | long-tailed-learning, semi-supervised, contrastive-learning | 5c1170c249cd8e1bde5848a4fc10cb9a.md |
| 193 | Doubly Mild Generalization for Offline Reinforcement Learnin | offline-reinforcement-learning, generalization, out-of-distribution | 5c14b3ee78d09e8b3240ffb1fb6cc819.md |
| 194 | EnOF-SNN: Training Accurate Spiking Neural Networks via Enha | spiking-neural-networks, output-feature-enhancement, energy-efficiency | 5c6f928e3fc5f32ee29a1d916b68e6f5.md |
| 195 | The Many Faces of Optimal Weak-to-Strong Learning | boosting, weak-to-strong-learning, sample-complexity | 5cc19d8570ebe171ffad101fef1e4dde.md |
| 196 | Generalization Bounds via Conditional $f$-Information | generalization-bounds, f-information, conditional-mutual-information | 5d632bbfde3f580d8183dc48ed87b418.md |
| 197 | Overfitting Behaviour of Gaussian Kernel Ridgeless Regressio | kernel-ridgeless-regression, overfitting, benign-overfitting | 5e460d0374fea1e9f83febeb45a1d287.md |
| 198 | Understanding Emergent Abilities of Language Models from the | emergent-abilities, language-models, loss-perspective | 5f1eee2509599faeeb3570a887016a64.md |
| 199 | Color-Oriented Redundancy Reduction in Dataset Distillation | dataset-distillation, color-redundancy, training-efficiency | 5f5f7b6080dcadced61cf5d96f7c6dde.md |
| 200 | Learning via Surrogate PAC-Bayes | pac-bayes, surrogate-bounds, generalization | 5fba70900a84a8fb755c48ba99420c95.md |
| 201 | Provable Tempered Overfitting of Minimal Nets and Typical Ne | overfitting, binary-weights, interpolation | 5fff164c04811174e1836dc3e66c0aba.md |
| 202 | Only Strict Saddles in the Energy Landscape of Predictive Co | predictive-coding, energy-landscape, saddle-points | 6075fc6540b9a3cb951752099efd86ef.md |
| 203 | Transformer Doctor: Diagnosing and Treating Vision Transform | vision-transformers, diagnostic-framework, error-mechanisms | 614f8eba720cfc7ff00274bd64fb0a3f.md |
| 204 | Learning to Merge Tokens via Decoupled Embedding for Efficie | token-merging, vision-transformers, efficient-inference | 6158e152498f8d8b83d14388a7ec1963.md |
| 205 | NeuralFuse: Learning to Recover the Accuracy of Access-Limit | low-voltage-inference, memory-bit-errors, neural-network-robustness | 62133b95efaa6f10a5395eb10ca087cd.md |
| 206 | LoRA-GA: Low-Rank Adaptation with Gradient Approximation | lora, gradient-approximation, parameter-efficient-fine-tuning | 62c4718cc334f6a0a62fb81c4a2095a1.md |
| 207 | Abrupt Learning in Transformers: A Case Study on Matrix Comp | transformer-training-dynamics, loss-plateaus, matrix-completion | 630d293833e09e1ecd892a898a20b074.md |
| 208 | Revisiting Differentially Private ReLU Regression | differential-privacy, relu-regression, high-dimensional-learning | 6454dcd80b5373daaa97e53ce32c78a1.md |
| 209 | Near-Optimal Dynamic Regret for Adversarial Linear Mixture M | linear-mixture-mdp, dynamic-regret, adversarial-rewards | 656678aa961a99a6a3d59bfbf88daf77.md |
| 210 | What Variables Affect Out-of-Distribution Generalization in  | out-of-distribution-generalization, pretrained-models, tunnel-effect | 6701e9c94bc7c7d6b5fc47c0fc13ab5b.md |
| 211 | LISA: Layerwise Importance Sampling for Memory-Efficient Lar | llm-fine-tuning, memory-efficiency, importance-sampling | 687163285b8affc8ee933bdca8e75747.md |
| 212 | Learning on Large Graphs using Intersecting Communities | message-passing, community-structure, scalable-graph-learning | 6953cb03692e187e3acd5c3aada984e3.md |
| 213 | Understanding Generalizability of Diffusion Models Requires  | diffusion-models, generalization, Gaussian-structure | 69e68611ec4d8c0ae4a4b2bece165f5f.md |
| 214 | DeltaDEQ: Exploiting Heterogeneous Convergence for Accelerat | deep-equilibrium-models, implicit-networks, heterogeneous-convergence | 69f5b860d6dc469ac6e52f03866b73c4.md |
| 215 | Functionally Constrained Algorithm Solves Convex Simple Bile | bilevel-optimization, convex-optimization, first-order-methods | 69f98acf161316ed896047e45da3bc0c.md |
| 216 | The Price of Implicit Bias in Adversarially Robust Generaliz | implicit-bias, adversarial-robustness, robust-generalization | 6ad7e3de1776ba5ed1a6aadc9c1724a5.md |
| 217 | Where Do Large Learning Rates Lead Us? | learning-rate-schedules, generalization, neural-network-training | 6b7375226d4742ff910618a56ae72b7d.md |
| 218 | Neural network learns low-dimensional polynomials with SGD n | SGD, single-index-model, information-theoretic-limits | 6bd5fca2074dcd9ede9de50f71f7ec28.md |
| 219 | Self-Guided Masked Autoencoder | masked-autoencoder, self-supervised-learning, representation-learning | 6c4a1a3cbe70ef36d7d6332166bba77d.md |
| 220 | Swift Sampler: Efficient Learning of Sampler by 10 Parameter | data-sampling, meta-learning, training-efficiency | 6c9dcffe0b9cc3b05d83bcdddb250690.md |
| 221 | Wide Two-Layer Networks can Learn from Adversarial Perturbat | adversarial-examples, class-specific-features, two-layer-networks | 6e0274fdb05f21654421db43cd8de042.md |
| 222 | Unveiling The Matthew Effect Across Channels: Assessing Laye | layer-width, weight-norm-variance, matthew-effect | 6e60a9023d2c63f7f0856910129ae753.md |
| 223 | SGD vs GD: Rank Deficiency in Linear Networks | stochastic-gradient-descent, linear-networks, rank-deficiency | 6ec81faa568317949b0ff3be4d87cced.md |
| 224 | On the Limitations of Fractal Dimension as a Measure of Gene | fractal-dimension, generalization-bounds, neural-network-theory | 6f098c5618e4289f5a6b642c94199f34.md |
| 225 | Scaling Laws in Linear Regression: Compute, Parameters, and  | scaling-laws, linear-regression, bias-variance-tradeoff | 6fcb1afcc1e9c2c82c8ddddf03bcf0f6.md |
| 226 | How Do Large Language Models Acquire Factual Knowledge Durin | factual-knowledge, llm-pretraining, knowledge-acquisition | 6fdf57c71bc1f1ee29014b8dc52e723f.md |
| 227 | A Canonicalization Perspective on Invariant and Equivariant  | canonicalization, invariance, equivariance | 702b67152ec4435795f681865b67999c.md |
| 228 | Repurposing Language Models into Embedding Models: Finding t | text-embeddings, contrastive-training, compute-optimal | 707a2d58641b2192203b4bf4c532cfe1.md |
| 229 | PACE: Marrying generalization in PArameter-efficient fine-tu | parameter-efficient-finetuning, consistency-regularization, generalization | 70a06501001e1820fd1eb9ee821302d2.md |
| 230 | The Fine-Grained Complexity of Gradient Computation for Trai | gradient-computation, attention-complexity, fine-grained-complexity | 70fa5df8e3300dc30bf19bee44a56155.md |
| 231 | Understanding Bias in Large-Scale Visual Datasets | dataset-bias, visual-attributes, large-scale-datasets | 7172e147d916eef4cb1eb30016ce725f.md |
| 232 | BOLD: Boolean Logic Deep Learning | boolean-logic, binarized-neural-networks, low-precision-training | 718a3c5cf135894db6e718725f52ef9a.md |
| 233 | Nature-Inspired Local Propagation | local-propagation, biologically-inspired, online-learning | 71d9a840a7f04339ca271c10a0f4fbd4.md |
| 234 | The Feature Speed Formula: a flexible approach to scale hype | hyperparameter-scaling, feature-learning, deep-networks | 720e7ebc49c84252abc0754dddf80976.md |
| 235 | The Closeness of In-Context Learning and Weight Shifting for | in-context-learning, weight-shifting, softmax-regression | 726ab29b61a749b36d2593648716ae3c.md |
| 236 | B-cosification: Transforming Deep Neural Networks to be Inhe | interpretability, b-cos-networks, explainability | 72d50a87b218d84c175d16f4557f7e12.md |
| 237 | Task-recency bias strikes back: Adapting covariances in Exem | class-incremental-learning, covariance-adaptation, exemplar-free | 73ba81c7b25134a559c8a9c39ec1a4c3.md |
| 238 | Provably Transformers Harness Multi-Concept Word Semantics f | transformers, in-context-learning, multi-concept-semantics | 73efab19ebde03ff0958f4f155483f57.md |
| 239 | Training Binary Neural Networks via Gaussian Variational Inf | binary-neural-networks, variational-inference, semidefinite-programming | 750a56383caf20b92fe070732f969300.md |
| 240 | BMRS: Bayesian Model Reduction for Structured Pruning | structured-pruning, bayesian-model-reduction, neural-network-compression | 7538e7a7a589a267f49527fe6fbc640e.md |
| 241 | The Sample Complexity of Gradient Descent in Stochastic Conv | gradient-descent, sample-complexity, stochastic-convex-optimization | 7571c9d44179c7988178593c5b62a9b6.md |
| 242 | Dynamic Neural Regeneration: Enhancing Deep Learning General | deep-learning, generalization, small-datasets | 779cb405b8b916f7db70e73d51650ed2.md |
| 243 | Neural Collapse To Multiple Centers For Imbalanced Data | neural-collapse, imbalanced-data, geometric-structure | 78a2ed8e7da1829d64fb3561adbd706b.md |
| 244 | Nonparametric Classification on Low Dimensional Manifolds us | convolutional-resnets, overparameterization, manifold-learning | 78ed45281dd746a265fff16ff75a02e5.md |
| 245 | Dual Risk Minimization: Towards Next-Level Robustness in Fin | fine-tuning, distribution-shift, zero-shot | 7972f3735e104a54715922aa416fde1b.md |
| 246 | Provably and Practically Efficient Adversarial Imitation Lea | adversarial-imitation-learning, function-approximation, neural-networks | 79b90b4c2ee23cc35fdd8de2969dc4e8.md |
| 247 | Learning Neural Contracting Dynamics: Extended Linearization | contracting-dynamics, neural-networks, global-stability | 79cafa874121a3435d8a54f454b646b4.md |
| 248 | Unveiling Induction Heads: Provable Training Dynamics and Fe | induction-heads, in-context-learning, training-dynamics | 7aae9e3ec211249e05bd07271a6b1441.md |
| 249 | The Impact of Geometric Complexity on Neural Collapse in Tra | neural-collapse, transfer-learning, geometric-complexity | 7b24015f3af598e1d9179f6e06353780.md |
| 250 | Cross-modal Representation Flattening for Multi-modal Domain | multimodal, domain-generalization, representation-flattening | 7b5d3047939b63ed97fcbbee23f8eb77.md |
| 251 | Learning a Single Neuron Robustly to Distributional Shifts a | single-neuron, distributional-shift, adversarial-label-noise | 7c8c0db90a14c7a2db9475e52dc343a9.md |
| 252 | Optimization Algorithm Design via Electric Circuits | convex-optimization, RLC-circuits, algorithm-design | 7db2ffcbfd0bd361d47b7fa612bd2ba2.md |
| 253 | Few-Shot Diffusion Models Escape the Curse of Dimensionality | few-shot, diffusion-models, curse-of-dimensionality | 7eb6233e02f7d9efbb84acd839a996fb.md |
| 254 | FlashAttention-3: Fast and Accurate Attention with Asynchron | attention-mechanism, flashattention, asynchrony | 7ede97c3e082c6df10a8d6103a2eebd2.md |
| 255 | Group and Shuffle: Efficient Structured Orthogonal Parametri | orthogonal-finetuning, structured-matrices, parameter-efficient | 7f0f24deb34c21ee590d8cece365710b.md |
| 256 | Changing the Training Data Distribution to Reduce Simplicity | simplicity-bias, training-distribution, generalization | 7f5f9a88c6516469c83d074c6f2976fb.md |
| 257 | No Representation, No Trust: Connecting Representation, Coll | PPO, representation-collapse, trust-region | 81166fbd9cc5adf14031cdb69d3fd6a8.md |
| 258 | Exploring the Precise Dynamics of Single-Layer GAN Models: L | GAN-training-dynamics, subspace-learning, discriminator | 8198901c33d24a391b4c6b3f30f253ce.md |
| 259 | Understanding Visual Feature Reliance through the Lens of Co | shortcut-learning, feature-complexity, inductive-bias | 819977c0a95458911bbfd9e5b5115018.md |
| 260 | Continual Learning with Global Alignment | continual-learning, catastrophic-forgetting, gradient-alignment | 81b00efcbc755bd0b8dc6c0d15e9d0b1.md |
| 261 | Improving Generalization of Dynamic Graph Learning via Envir | dynamic-graphs, OOD-generalization, environment-prompt | 81c565e605161fcf25d08aa230431eba.md |
| 262 | Dual-Perspective Activation: Efficient Channel Denoising via | activation-function, channel-denoising, sparse-representation | 825341ab91db01bf063add41ac022702.md |
| 263 | Provably Faster Algorithms for Bilevel Optimization via With | bilevel-optimization, without-replacement-sampling, stochastic-gradient | 8258e815fa93aa59441ad526cc828c53.md |
| 264 | Offline Multitask Representation Learning for Reinforcement  | offline-RL, multitask-learning, representation-learning | 82764461a05e933cc2fd9d312e107d12.md |
| 265 | Counter-Current Learning: A Biologically Plausible Dual Netw | biologically-plausible, backpropagation-alternative, dual-network | 82f05a105c928c10706213952bf0c8b7.md |
| 266 | The Ladder in Chaos: Improving Policy Learning by Harnessing | policy-learning, low-dimensional-dynamics, reinforcement-learning | 831406cfe7e4a0aed5ac5c8a8389d1f5.md |
| 267 | The Star Geometry of Critic-Based Regularizer Learning | variational-regularization, critic-based, star-geometry | 834d4d24d223e5dc05f9971eaf30d4a6.md |
| 268 | Large Stepsize Gradient Descent for Non-Homogeneous Two-Laye | large-stepsize, gradient-descent, margin-maximization | 835a0185f61867a1ea0f86155489839a.md |
| 269 | Taming "data-hungry" reinforcement learning? Stability in co | reinforcement-learning, continuous-spaces, convergence-rates | 8364ad56291e22ec6041794355a46802.md |
| 270 | Great Minds Think Alike: The Universal Convergence Trend of  | input-salience, DNN-convergence, neural-network-geometry | 83e77607638c4fb17fba4a9b7844800c.md |
| 271 | DISP-LLM: Dimension-Independent Structural Pruning for Large | structured-pruning, large-language-models, model-compression | 84a7fc24ed52e8eff514c33e8ac76ea3.md |
| 272 | ADOPT: Modified Adam Can Converge with Any $\beta_2$ with th | adam-optimizer, convergence-theory, adaptive-gradient-methods | 84d286e32bbee8fa3a86ee9c50e00081.md |
| 273 | Tighter Convergence Bounds for Shuffled SGD via Primal-Dual  | shuffled-sgd, primal-dual-analysis, convergence-bounds | 84d395725a9b40cb4a49d84478ac24c7.md |
| 274 | Dissecting the Interplay of Attention Paths in a Statistical | transformers, statistical-mechanics, attention-mechanisms | 8523a98265ceae12afd34113aa6c5cca.md |
| 275 | Symmetries in Overparametrized Neural Networks: A Mean Field | mean-field-theory, overparameterized-networks, symmetry-equivariance | 85dbd2fb8b355e4231b51e454c08ec1c.md |
| 276 | SequentialAttention++ for Block Sparsification: Differentiab | neural-network-pruning, block-sparsification, differentiable-pruning | 8735e0793cfd43327eceaacf39466a01.md |
| 277 | SwitchHead: Accelerating Transformers with Mixture-of-Expert | mixture-of-experts, transformer-attention, efficient-language-models | 87be61bf9338389702712f5e9754a986.md |
| 278 | Decoupled Kullback-Leibler Divergence Loss | KL-divergence, knowledge-distillation, loss-decomposition | 87ee1bbac4635e7c948f3eea83c1f262.md |
| 279 | Stochastic Kernel Regularisation Improves Generalisation in  | deep-kernel-machines, stochastic-regularization, generalization | 883f66687a521536c505f9b2fbdcbf1e.md |
| 280 | The Implicit Bias of Gradient Descent toward Collaboration b | implicit-bias, gradient-descent, multilayer-perceptron | 88c2fb9ae705e143c99156ba37926837.md |
| 281 | Exploration by Learning Diverse Skills through Successor Sta | diverse-skills, exploration, successor-state-representations | 8997f9fff71e14a2c01bae9c6e226f44.md |
| 282 | Local Linearity: the Key for No-regret Reinforcement Learnin | no-regret-rl, continuous-mdps, local-linearity | 8ac80f6cdd1fffc43a4ba4ba49f40186.md |
| 283 | Confident Natural Policy Gradient for Local Planning in  $q_ | constrained-mdp, natural-policy-gradient, reinforcement-learning | 8b4e529225152b2fa6749c10c1d616dd.md |
| 284 | Scaling Laws and Compute-Optimal Training Beyond Fixed Train | scaling-laws, compute-optimal, training-duration | 8b970e15a89bf5d12542810df8eae8fc.md |
| 285 | Expanding Sparse Tuning for Low Memory Usage | parameter-efficient-fine-tuning, sparse-tuning, memory-efficiency | 8c420176b45e923cf99dee1d7356a763.md |
| 286 | Randomized Exploration for Reinforcement Learning with Multi | reinforcement-learning, function-approximation, multinomial-logistic | 8c54e9bfed4119c873f575d1d1e2f0a0.md |
| 287 | Deep linear networks for regression are implicitly regulariz | sharpness, deep-linear-networks, implicit-regularization | 8c976a95df6a229551cd28c76627edc9.md |
| 288 | Robust Fine-tuning of Zero-shot Models via Variance Reductio | zero-shot-models, fine-tuning-robustness, variance-reduction | 8cc7e1509fbfee9cabaacd3ab0bfe2b1.md |
| 289 | CoMERA: Computing- and Memory-Efficient Training via Rank-Ad | tensor-decomposition, rank-adaptive-optimization, memory-efficient-training | 8d35d225230a9d77b29c1dd300e48ad9.md |
| 290 | Pretrained Transformer Efficiently Learns Low-Dimensional Ta | in-context-learning, transformers, low-dimensional-target-functions | 8d6c356c82252032a20c749dda36f2d8.md |
| 291 | BPQP: A Differentiable Convex Optimization Framework for Eff | differentiable-optimization, end-to-end-learning, convex-programming | 8db12f7214d3a1a0c450ba751163e0fd.md |
| 292 | Structured Unrestricted-Rank Matrices for Parameter Efficien | parameter-efficient-finetuning, low-rank-adaptation, transformer-finetuning | 8eec8d7bcecf034304174e6b57dbc19a.md |
| 293 | AmoebaLLM: Constructing Any-Shape Large Language Models for  | llm-deployment, model-compression, any-shape-networks | 8f11e548311c7fd3f33596a4d1dd41f0.md |
| 294 | Learning from higher-order correlations, efficiently: hypoth | higher-order-cumulants, statistical-learning, neural-network-efficiency | 8f8af4eebc4e50994e0490898d891c96.md |
| 295 | PeRFlow: Piecewise Rectified Flow as Universal Plug-and-Play | rectified-flow, diffusion-acceleration, sampling-efficiency | 8f9d1362a386e80a723e98451a8c7564.md |
| 296 | Replicability in Learning: Geometric Partitions and KKM-Sper | replicability, geometric-partitions, sperner-lemma | 8ff87c96935244b63503f542472462b3.md |
| 297 | Learnability of high-dimensional targets by two-parameter mo | gradient-flow, learnability, high-dimensional-targets | 9062b7d6e522dadf4f7d85d49b60d81e.md |
| 298 | Bridging the Divide: Reconsidering Softmax and Linear Attent | linear-attention, softmax-attention, vision-transformers | 90800f46f84381b7891e1378ee850013.md |
| 299 | A Boosting-Type Convergence Result for AdaBoost.MH with Fact | adaboost, multi-class-classification, convergence-theory | 91a5742235f70ae846436d9780e9f1d4.md |
| 300 | Graph Neural Networks Need Cluster-Normalize-Activate Module | graph-neural-networks, oversmoothing, cluster-normalize-activate | 91b1966914203338495a76d13b23599c.md |
| 301 | Revive Re-weighting in Imbalanced Learning by Density Ratio  | imbalanced-learning, density-ratio-estimation, re-weighting | 92440ec643f4e9f17409557b6516566e.md |
| 302 | Non-asymptotic Convergence of Training Transformers for Next | transformers, next-token-prediction, convergence-theory | 9370fa016d6a14af78f5048bfcb0582b.md |
| 303 | Towards Dynamic Message Passing on Graphs | graph-neural-networks, message-passing, dynamic-topology | 93b7e2780c4f6599837fdd3718c51fad.md |
| 304 | Decomposing and Interpreting Image Representations via Text  | vision-transformers, interpretability, text-decomposition | 93e45db754dd0f82339763055c6cda56.md |
| 305 | Get rich quick: exact solutions reveal how unbalanced initia | feature-learning, neural-networks, unbalanced-initialization | 94074dd5a072d28ff75a76dabed43767.md |
| 306 | The Implicit Bias of Gradient Descent on Separable Multiclas | implicit-bias, gradient-descent, multiclass-classification | 942d5e890e4e0ab0e7a5f8cbcef5b9ff.md |
| 307 | On the Comparison between Multi-modal and Single-modal Contr | contrastive-learning, multimodal, representation-learning | 94840c41497ead6a84f493f029eba7fa.md |
| 308 | Bayes-optimal learning of an extensive-width neural network  | Bayes-optimal-learning, neural-network, statistical-mechanics | 953e742190ca02fc8f9f710052f2fead.md |
| 309 | One-Layer Transformer Provably Learns One-Nearest Neighbor I | transformer, in-context-learning, nearest-neighbor | 95827e011b9e899f189a01fe2f4ef316.md |
| 310 | Preventing Model Collapse in Deep Canonical Correlation Anal | deep-CCA, multi-view-learning, noise-regularization | 9626a58529367967b71c17c9b2db72f1.md |
| 311 | Error Correction Output Codes for Robust Neural Networks aga | error-correcting-output-codes, neural-tangent-kernel, weight-errors | 964ce727dccdc18aa9bad54604699bbe.md |
| 312 | Optimal Rates for Vector-Valued Spectral Regularization Lear | spectral-regularization, vector-valued-output, kernel-ridge-regression | 966bf8492dbaa8376f5e3756c09d7edb.md |
| 313 | QT-ViT: Improving Linear Attention in ViT with Quadratic Tay | linear-attention, vision-transformer, taylor-expansion | 971f1e59cd956cc094da4e2f78c6ea7c.md |
| 314 | Towards a theory of how the structure of language is acquire | probabilistic-context-free-grammar, next-token-prediction, sample-complexity | 9740da1c07c7b451af14e11523f95271.md |
| 315 | Non-Stationary Learning of Neural Networks with Automatic So | non-stationary-learning, parameter-reset, continual-learning | 978cc34c539fd26f0e8afb7e3905f34a.md |
| 316 | Scaling Law for Time Series Forecasting | scaling-laws, time-series-forecasting, deep-learning | 97c2f0fac182353062d304d0322ae285.md |
| 317 | Improving Equivariant Model Training via Constraint Relaxati | equivariant-networks, constraint-relaxation, symmetry | 98082e6b4b97ab7d3af1134a5013304e.md |
| 318 | On the Stability and Generalization of Meta-Learning | meta-learning, stability, generalization-bounds | 984fa4634385c48ab3722d825c57ede0.md |
| 319 | Understanding and Minimising Outlier Features in Transformer | outlier-features, transformer-training, quantization | 986292a930c3692168b177a770025ab3.md |
| 320 | Towards training digitally-tied analog blocks via hybrid gra | analog-computing, equilibrium-propagation, hybrid-gradient | 989463e7e34dc152bef08156dac95569.md |
| 321 | Vision Transformer Neural Architecture Search for Out-of-Dis | vision-transformer, neural-architecture-search, out-of-distribution-generalization | 9952369f49ecc064d169fe6612cbf204.md |
| 322 | MagR: Weight Magnitude Reduction for Enhancing Post-Training | post-training-quantization, weight-regularization, l-infinity-optimization | 9a987c98a7f36cc83f9065df3ca4f9e0.md |
| 323 | Federated Learning over Connected Modes | federated-learning, linear-mode-connectivity, personalization | 9abc1d4bcdb4e61e7c0e01a11ab7c375.md |
| 324 | A provable control of sensitivity of neural networks through | bi-lipschitz-networks, sensitivity-control, direct-parameterization | 9adc8ada9183f4b9a007a02773fd8114.md |
| 325 | Continual Learning in the Frequency Domain | continual-learning, frequency-domain, catastrophic-forgetting | 9b224ace8963c9385ad5e2b5c9039b97.md |
| 326 | A Closer Look at the CLS Token for Cross-Domain Few-Shot Lea | vision-transformer, cross-domain-few-shot-learning, CLS-token | 9b77f07301b1ef1fe810aae96c12cb7b.md |
| 327 | In-Context Learning with Representations: Contextual General | in-context-learning, transformers, generalization-theory | 9bfa0c155653e24120760a5ead819376.md |
| 328 | Enhancing Robustness in Deep Reinforcement Learning: A Lyapu | deep-reinforcement-learning, robustness, Lyapunov-exponents | 9c4bbdad95f6ffed1a15c06b491e0a3e.md |
| 329 | On Feature Learning in Structured State Space Models | state-space-models, Mamba, feature-learning | 9c7eeda2dc98e61baa9a5884afd231bc.md |
| 330 | Local to Global: Learning Dynamics and Effect of Initializat | transformers, learning-dynamics, Markov-chains | 9cdb4f8c4dfa13284d2d5a6e7853e5a2.md |
| 331 | How many classifiers do we need? | ensembling, classifier-disagreement, accuracy-analysis | 9d4e58d9c6abac29374bedbc5b6f4758.md |
| 332 | Base of RoPE Bounds Context Length | RoPE, context-length, position-embedding | 9f12dd32d552f3ad9eaa0e9dfec291be.md |
| 333 | Provable and Efficient Dataset Distillation for Kernel Ridge | dataset-distillation, kernel-ridge-regression, provable-efficiency | a1c716638d9b618a1a40a96f473c8250.md |
| 334 | Infusing Self-Consistency into Density Functional Theory Ham | density-functional-theory, deep-equilibrium-models, Hamiltonian-prediction | a31d1942f4f4f52a73bfd1d67856bed7.md |
| 335 | Untrained Neural Nets for Snapshot Compressive Imaging: Theo | snapshot-compressive-imaging, untrained-neural-networks, compressed-sensing | a344cef5eceea9c55baad6fdc49bcaed.md |
| 336 | Reinforcement Learning with Euclidean Data Augmentation for  | reinforcement-learning, data-augmentation, euclidean-symmetry | a439259e78294c38d157a51a2c40486b.md |
| 337 | Towards a Theoretical Understanding of the 'Reversal Curse'  | reversal-curse, large-language-models, training-dynamics | a4b95476f673e6e538f80862f622ba2f.md |
| 338 | GRANOLA: Adaptive Normalization for Graph Neural Networks | graph-neural-networks, normalization, adaptive-normalization | a4c17d9b88eaefc9bdf7c656ffc8ce55.md |
| 339 | Gradient Guidance for Diffusion Models: An Optimization Pers | diffusion-models, gradient-guidance, optimization | a5059a9a389ccc76da85760ea79490d8.md |
| 340 | Stochastic Newton Proximal Extragradient Method | stochastic-optimization, newton-method, superlinear-convergence | a51a0d42d794c8adf416196aae9f0974.md |
| 341 | How JEPA Avoids Noisy Features: The Implicit Bias of Deep Li | JEPA, self-distillation, implicit-bias | a600f0f740605205133553cb74a1c107.md |
| 342 | How Sparse Can We Prune A Deep Network: A Fundamental Limit  | network-pruning, sparsity, fundamental-limits | a627810151be4d13f907ac898ff7e948.md |
| 343 | Second-order forward-mode optimization of recurrent neural n | recurrent-neural-networks, second-order-optimization, computational-neuroscience | a791a086d7643ecf53608e57cd5889f0.md |
| 344 | Unraveling the Gradient Descent Dynamics of Transformers | transformer-optimization, gradient-descent-dynamics, theoretical-analysis | a7d36e5cb41a1f21c46db25cb1aafab9.md |
| 345 | Infinite-Dimensional Feature Interaction | feature-interaction, multiplicative-networks, neural-architecture | a7efd7734bb2e79997f8d1137ece3f09.md |
| 346 | In-Context Learning with Transformers: Softmax Attention Ada | in-context-learning, transformers, softmax-attention | a8633d27d782f66fe660c2fb4bae446e.md |
| 347 | Batched Energy-Entropy acquisition for Bayesian Optimization | Bayesian-optimization, acquisition-functions, batch-selection | a96d4fda3017f1773b261a52a3efc8dd.md |
| 348 | Neural Collapse Inspired Feature Alignment for Out-of-Distri | neural-collapse, spurious-correlation, out-of-distribution-generalization | aa56c74513a5e35768a11f4e82dd7ffb.md |
| 349 | Parameter Symmetry and Noise Equilibrium of Stochastic Gradi | parameter-symmetry, stochastic-gradient-descent, noise-equilibrium | aa933b5abc1be30baece1d230ec575a7.md |
| 350 | Multi-Head Mixture-of-Experts | mixture-of-experts, sparse-MoE, expert-activation | ab05dc8bf36a9f66edbff6992ec86f56.md |
| 351 | Stable Minima Cannot Overfit in Univariate ReLU Networks: Ge | generalization, ReLU-networks, large-step-sizes | ab54dd3cd5e273dbb1e75a5e6203fb42.md |
| 352 | Towards Next-Level Post-Training Quantization of Hyper-Scale | post-training-quantization, transformers, edge-deployment | ab6eba9a853087993addff937c8cec87.md |
| 353 | Accelerating Augmentation Invariance Pretraining | contrastive-learning, vision-transformers, pretraining-efficiency | abf731c2993f9b1ee417cc3734787d7a.md |
| 354 | On the Use of Anchoring for Training Vision Models | anchoring, uncertainty-estimation, calibration | ad405c243d2940db5b24057ed26b2b2f.md |
| 355 | Preventing Dimensional Collapse in Self-Supervised Learning  | self-supervised-learning, dimensional-collapse, orthogonality | ad7922fd4650f8aba5d8b067e622ca84.md |
| 356 | Improving Neural ODE Training with Temporal Adaptive Batch N | neural-ode, batch-normalization, temporal-adaptation | adf7fa39d65e2983d724ff7da57f00ac.md |
| 357 | A distributional simplicity bias in the learning dynamics of | simplicity-bias, transformer-learning-dynamics, generalization | ae6c81a39079ddeb88b034b6ef18c7fe.md |
| 358 | Convolutions and More as Einsum: A Tensor Network Perspectiv | einsum, tensor-networks, second-order-optimization | af45937b353f539d0a518b3bb890a01d.md |
| 359 | Rethinking Deep Thinking: Stable Learning of Algorithms usin | deep-thinking, recurrent-networks, Lipschitz-constraints | afbe068bd0469f4cd778c0f8106181b6.md |
| 360 | Mini-Sequence Transformers: Optimizing Intermediate Memory f | long-sequence-training, memory-efficiency, llm-training | b063829b922fdeb4fa3472dd3471ff43.md |
| 361 | Neural Characteristic Activation Analysis and Geometric Para | relu-networks, training-dynamics, activation-boundaries | b0e40256fe5d90b78525312564a2de64.md |
| 362 | Understanding Transformers via N-Gram Statistics | transformers, n-gram-statistics, interpretability | b1c446eebd9a317dd0e96b16908c821a.md |
| 363 | Transformers need glasses! Information over-squashing in lan | transformers, information-propagation, over-squashing | b1d35561c4a4a0e0b6012b2af531e149.md |
| 364 | SuperDeepFool: a new fast and accurate minimal adversarial a | adversarial-attacks, robustness, minimal-perturbation | b2b3e1d9840eba17ad9bbf073e009afe.md |
| 365 | Dual Cone Gradient Descent for Training Physics-Informed Neu | PINNs, PDE, dual-cone | b2b781badeeb49896c4b324c466ec442.md |
| 366 | On the Efficiency of ERM in Feature Learning | ERM, feature-learning, regression | b2c39fe6ce838440faf03a0f780e7a63.md |
| 367 | Transformers Learn to Achieve Second-Order Convergence Rates | transformers, in-context-learning, second-order-optimization | b2d4051f03a7038a2771dfbbe5c7b54e.md |
| 368 | Elucidating the Design Space of Dataset Condensation | dataset-condensation, data-centric-learning, synthetic-data | b3ac2a18635fb355100c85f0f2044b89.md |
| 369 | DeNetDM: Debiasing by Network Depth Modulation | debiasing, spurious-correlations, network-depth | b40d5797756800c97f3d525c2e4c8357.md |
| 370 | A theoretical design of concept sets: improving the predicta | concept-bottleneck-models, interpretability, concept-sets | b5a412531110b92961fa13c90938806a.md |
| 371 | Resolving Discrepancies in Compute-Optimal Scaling of Langua | scaling-laws, compute-optimal, language-models | b6341525cd84f3be0ef203e4d7cd8556.md |
| 372 | Sample-Efficient Agnostic Boosting | boosting, agnostic-learning, sample-efficiency | b63a24a1832bd14fa945c71f535c0095.md |
| 373 | Adaptive Proximal Gradient Method for Convex Optimization | proximal-gradient, adaptive-methods, convex-optimization | b676cbd80be73a4a7af178f12035a801.md |
| 374 | MOTE-NAS: Multi-Objective Training-based Estimate for Effici | neural-architecture-search, multi-objective, NTK | b6e118c759c16f2424997bbb6a1ffd61.md |
| 375 | Fast Rates in Stochastic Online Convex Optimization by Explo | online-convex-optimization, fast-rates, feasible-set-curvature | b84cbefc3bebbb88811e2ead03c9ef0c.md |
| 376 | Learn To be Efficient: Build Structured Sparsity in Large La | LLM-pruning, structured-sparsity, efficient-inference | b8f10193cab43d45df9bb810637333fd.md |
| 377 | Efficient Adaptation of Pre-trained Vision Transformer via H | parameter-efficient-fine-tuning, vision-transformer, Householder-transformation | b91cebea9292bfc45a2e674f0b9d4a51.md |
| 378 | Super Consistency of Neural Network Landscapes and Learning  | learning-rate-transfer, neural-scaling, feature-learning | ba1d33849b963efc6b5d3082ad68f480.md |
| 379 | CIFD: Controlled Information Flow to Enhance Knowledge Disti | knowledge-distillation, information-flow, teacher-student | ba63f9aaba08f39c70ffe19693ef470f.md |
| 380 | CRONOS: Enhancing Deep Learning with Scalable GPU Accelerate | convex-neural-networks, GPU-acceleration, two-layer-networks | ba9e3d60610f3525717665966d86e0cd.md |
| 381 | On the Complexity of Learning Sparse Functions with Statisti | statistical-queries, gradient-queries, sparse-functions | baf0fab890edc9dce805d7c518058712.md |
| 382 | Saliency-driven Experience Replay for Continual Learning | continual-learning, experience-replay, visual-saliency | bb1e9f32181a8d6a834670d5b3e1c48d.md |
| 383 | TrAct: Making First-layer Pre-Activations Trainable | first-layer-training, gradient-updates, pixel-values | bc52716d13d2d72ea0f335667d86c0f8.md |
| 384 | In-Context Symmetries: Self-Supervised Learning through Cont | self-supervised-learning, contextual-world-models, equivariance | bcad07d4bfab51243efaa08b8ed475b3.md |
| 385 | Algorithmic Capabilities of Random Transformers | random-transformers, circuit-emergence, algorithmic-tasks | bccdd196d798a51a4961989984a9ed4a.md |
| 386 | Dimension-free deterministic equivalents and scaling laws fo | random-features, ridge-regression, generalization-bounds | bd18189308a4c45c7d71ca83acf3deaa.md |
| 387 | Diffusion Models With Learned Adaptive Noise | diffusion-models, adaptive-noise, learned-noise-schedules | bee43378b65ec195a67f24709469dcaf.md |
| 388 | Fair Bilevel Neural Network (FairBiNN): On Balancing fairnes | fairness, bilevel-optimization, stackelberg-equilibrium | bef7a072148e646fcb62641cc351e599.md |
| 389 | Asynchronous Perception Machine for Efficient  Test Time Tra | test-time-training, efficient-inference, patch-processing | bfa629625fd35bf5b880df464b584a57.md |
| 390 | Mixed Dynamics In Linear Networks: Unifying the Lazy and Act | linear-networks, training-dynamics, lazy-active-regimes | bfa7d650ddfd7bd55866ee92f7a3393b.md |
| 391 | Visual Data Diagnosis and Debiasing with Concept Graphs | dataset-bias, concept-graphs, debiasing | c01dfe01b97aadc10fc16a201faa80d8.md |
| 392 | Normalization and effective learning rates in reinforcement  | normalization-layers, reinforcement-learning, effective-learning-rate | c04d37be05ba74419d2d5705972a9d64.md |
| 393 | DEPrune: Depth-wise Separable Convolution Pruning for Maximi | structured-pruning, depthwise-separable-convolution, GPU-parallelism | c16a99558b0b4f6b10966ca9bdb98ade.md |
| 394 | Learning from Uncertain Data: From Possible Worlds to Possib | uncertain-data, linear-models, zonotopes | c17fab1bcef325d0d30989c9bf506c0b.md |
| 395 | SlimGPT: Layer-wise Structured Pruning for Large Language Mo | LLM-pruning, structured-pruning, layer-wise | c1c44e46358e0fb94dc94ec495a7fb1a.md |
| 396 | Leveraging Drift to Improve Sample Complexity of Variance Ex | variance-exploding-diffusion, score-matching, sample-complexity | c2f63bec652c85bb335a5ee135f244c9.md |
| 397 | Compositional PAC-Bayes: Generalization of GNNs with persist | PAC-Bayes, graph-neural-networks, persistent-homology | c3266c14d7eb9715d9fad4306133aa4e.md |
| 398 | Adaptive Layer Sparsity for Large Language Models via Activa | llm-pruning, layer-sparsity, activation-correlation | c573258c38d0a3919d8c1364053c45df.md |
| 399 | Robust Graph Neural Networks via Unbiased Aggregation | graph-neural-networks, adversarial-robustness, unbiased-aggregation | c6e31f86c1eb8dfc05190cf15ed52064.md |
| 400 | Semantics and Spatiality of Emergent Communication | emergent-communication, multi-agent, semantic-grounding | c6f83c27a2223d817f9f1ade48d281a2.md |
| 401 | Scaling laws for learning with real and surrogate data | scaling-laws, data-augmentation, surrogate-data | c7038ec7eee8dc5a99d74d594f70aa3f.md |
| 402 | Random Function Descent | stochastic-optimization, random-function, step-size-selection | c980ad0fb46f0cfb0faabcd42b30a67a.md |
| 403 | Why Warmup the Learning Rate? Underlying Mechanisms and Impr | learning-rate-warmup, sgd, adam-optimizer | ca98452d4e9ecbc18c40da2aa0da8b98.md |
| 404 | Meta-Learning Universal Priors Using Non-Injective Change of | meta-learning, non-injective-change-of-variables, universal-priors | cae31fa913f140b3126036cc474fd461.md |
| 405 | Learning Segmentation from Point Trajectories | video-segmentation, motion-segmentation, point-trajectories | cc57fac10eacadb3b72a907ac48f9a98.md |
| 406 | Matching the Statistical Query Lower Bound for $k$-Sparse Pa | sparse-parity, stochastic-gradient-descent, statistical-query | cd38340309ed34d886b9cd6e35059606.md |
| 407 | Bigger, Regularized, Optimistic: scaling for compute and sam | reinforcement-learning, scaling, model-capacity | cd3b5d2ed967e906af24b33d6a356cac.md |
| 408 | Unsupervised Discovery of Formulas for Mathematical Constant | mathematical-constants, formula-discovery, unsupervised-learning | cd8b5de90ebfd6df2b703d2346370cba.md |
| 409 | Generalizablity of Memorization Neural Network | memorization, neural-networks, generalization | cd9b4a28fb9eebe0430c3312a4898a41.md |
| 410 | Improved Particle Approximation Error for Mean Field Neural  | mean-field-Langevin-dynamics, particle-approximation, neural-network-optimization | ce5f18eba5e5e9c7c166062300c677c3.md |
| 411 | Provable Editing of Deep Neural Networks using Parametric Li | DNN-verification, neural-network-editing, parametric-linear-relaxation | ce6326ac4794bb04d5eb16f597446baf.md |
| 412 | A Study of Plasticity Loss in On-Policy Deep Reinforcement L | plasticity-loss, on-policy-RL, continual-learning | ce7984e36d58659211a8dc7d5457cd6f.md |
| 413 | Implicit Bias of Mirror Flow on Separable Data | mirror-descent, implicit-bias, separable-data | cf10920ac985275845247f865b452529.md |
| 414 | Addressing Spectral Bias of Deep Neural Networks by Multi-Gr | spectral-bias, deep-neural-networks, high-frequency-learning | cf1129594f603fde9e1913d10b7dbf77.md |
| 415 | Provable Benefit of Cutout and CutMix for Feature Learning | data-augmentation, Cutout, CutMix | d01db5cd2555ba11f75da0454d57b903.md |
| 416 | A PID Controller Approach for Adaptive Probability-dependent | model-calibration, pid-controller, gradient-decay | d022216357816e483433914204aa80ee.md |
| 417 | Graph Coarsening with Message-Passing Guarantees | graph-coarsening, message-passing, graph-neural-networks | d041d6bb47c01a4ce327a1773703e9a0.md |
| 418 | Theoretical Characterisation of the Gauss Newton Conditionin | gauss-newton-matrix, neural-network-conditioning, preconditioning | d067d16e3e5fe8fa8a3e62909907659a.md |
| 419 | LoQT: Low-Rank Adapters for Quantized Pretraining | low-rank-adapters, quantized-training, pretraining | d0c6bc641a56bebee9d985b937307367.md |
| 420 | Advancing Training Efficiency of Deep Spiking Neural Network | spiking-neural-networks, rate-coding, backpropagation | d1bdc488ec18f64177b2275a03984683.md |
| 421 | You Don’t Need Domain-Specific Data Augmentations When Scali | self-supervised-learning, joint-embedding, data-augmentation-free | d2964af7bd4e891297a39dc9085fa754.md |
| 422 | Exploring and Exploiting the Asymmetric Valley of Deep Neura | loss-landscape, asymmetric-valley, deep-neural-networks | d2bdcd4f51eea138365af22b50f3bf0a.md |
| 423 | Nuclear Norm Regularization for Deep Learning | nuclear-norm, jacobian-regularization, deep-learning | d2cc447db9e56c13b993c11b45956281.md |
| 424 | An In-depth Investigation of Sparse Rate Reduction in Transf | sparse-rate-reduction, transformer-interpretability, information-theory | d3d1947ba438c758790b18d5fcf69e8f.md |
| 425 | The Impact of Initialization on LoRA Finetuning Dynamics | LoRA, fine-tuning, initialization | d4387c37b3b06e55f86eccdb8cd1f829.md |
| 426 | Navigating Extremes: Dynamic Sparsity in Large Output Spaces | dynamic-sparse-training, large-output-spaces, model-pruning | d4bdeed749a437de2cbe2e2c7e5a6a8a.md |
| 427 | Hyper-SD: Trajectory Segmented Consistency Model for Efficie | diffusion-distillation, consistency-models, trajectory-segmentation | d4e1c24ac41ff0b82ca1b171731f0b23.md |
| 428 | Neural Residual Diffusion Models for Deep Scalable Vision Ge | diffusion-models, residual-networks, scalable-generation | d51ceadaf09a4699f18986702df24987.md |
| 429 | Deep Support Vectors | support-vectors, deep-learning, decision-criteria | d60e14c19cd6e0fc38556ad29ac8fbc9.md |
| 430 | SLTrain: a sparse plus low rank approach for parameter and m | sparse-low-rank, pretraining-efficiency, memory-efficient | d63cf0622eed012a17fe88fced64dcb8.md |
| 431 | Sigmoid Gating is More Sample Efficient than Softmax Gating  | mixture-of-experts, sigmoid-gating, sample-efficiency | d65befe6b80ecf7f180b4def503d7776.md |
| 432 | Improving Generalization and Convergence by Enhancing Implic | implicit-regularization, flat-minima, generalization | d712c8625fd97424c9744019b28dca21.md |
| 433 | Inductive biases of multi-task learning and finetuning: mult | multi-task-learning, fine-tuning, feature-reuse | d7346ff79699b5bba26f8af89e700a95.md |
| 434 | Fetch and Forge: Efficient Dataset Condensation for Object D | dataset-condensation, object-detection, synthetic-datasets | d7b351608d824a4680344a02b180a947.md |
| 435 | Diversity-Driven Synthesis: Enhancing Dataset Distillation t | dataset-distillation, weight-adjustment, diversity-synthesis | d80f533473c2dc8dd6984ceffc3ed3fd.md |
| 436 | How Transformers Utilize Multi-Head Attention in In-Context  | transformer-mechanisms, multi-head-attention, in-context-learning | d83d04f40961442fa31dd2552debd0e9.md |
| 437 | Learning from Offline Foundation Features with Tensor Augmen | foundation-models, offline-features, tensor-augmentation | d94e778e4cfabddec0cb6d38ab57accd.md |
| 438 | NoiseGPT: Label Noise Detection and Rectification through Pr | label-noise, noise-detection, probability-curvature | d95cb79a3421e6d9b6c9a9008c4d07c5.md |
| 439 | Test-Time Adaptation Induces Stronger Accuracy and Agreement | test-time-adaptation, accuracy-on-the-line, agreement-on-the-line | d96fcc07d623a9eba68616629911143a.md |
| 440 | PSL: Rethinking and Improving Softmax Loss from Pairwise Per | softmax-loss, recommender-systems, pairwise-ranking | db1d5c63576587fc1d40d33a75190c71.md |
| 441 | PiSSA: Principal Singular Values and Singular Vectors Adapta | parameter-efficient-fine-tuning, low-rank-adaptation, singular-value-decomposition | db36f4d603cc9e3a2a5e10b93e6428f2.md |
| 442 | Convolutional Differentiable Logic Gate Networks | logic-gate-networks, differentiable-relaxation, efficient-inference | db988b089d8d97d0f159c15ed0be6a71.md |
| 443 | No Free Lunch Theorem and Black-Box Complexity Analysis for  | no-free-lunch, black-box-optimization, adversarial-complexity | dc3a0fd5ef0f78ee5934919230d6664f.md |
| 444 | Accelerating Non-Maximum Suppression: A Graph Theory Perspec | non-maximum-suppression, graph-theory, object-detection | dcc0ac74ac8b95dc1939804acce0317d.md |
| 445 | Stochastic Taylor Derivative Estimator: Efficient amortizati | derivative-estimation, differential-operators, physics-informed-neural-networks | dd2eb5250696753ea37141bbd89bb569.md |
| 446 | Applying Guidance in a Limited Interval Improves Sample and  | diffusion-models, guidance, sampling | dd540e1c8d26687d56d296e64d35949f.md |
| 447 | Persistent Test-time Adaptation in Recurring Testing Scenari | test-time-adaptation, distribution-shift, continual-learning | df29d63af05cb91d705cf06ba5945b9d.md |
| 448 | Deep Learning Through A Telescoping Lens: A Simple Model Pro | grokking, gradient-boosting, telescoping-approximation | df334022279996b07e0870a629c18857.md |
| 449 | SpaceByte: Towards Deleting Tokenization from Large Language | tokenization-free, byte-level-modeling, large-language-models | e1f418450107c4a0ddc16d008d131573.md |
| 450 | Confidence Regulation Neurons in Language Models | uncertainty-representation, entropy-neurons, language-models | e21955c93dede886af1d0d362c756757.md |
| 451 | ResAD: A Simple Framework for Class Generalizable Anomaly De | anomaly-detection, class-generalization, residual-features | e2ba11d128034f0c544693374c59e49a.md |
| 452 | Dynamic Rescaling for Training GNNs | graph-neural-networks, rescale-invariance, training-dynamics | e2d89f6d3d7707709afa2e01f5952f95.md |
| 453 | Reconstruct and Match: Out-of-Distribution Robustness via To | out-of-distribution-robustness, topological-homogeneity, representation-regularization | e34d214dfb5b80212ac1b565aa41af55.md |
| 454 | Universality in Transfer Learning for Linear Models | transfer-learning, linear-models, universality | e379877d7880bb1f80c82a9f1c58e6e8.md |
| 455 | Slight Corruption in Pre-training Data Makes Better Diffusio | diffusion-models, pre-training-corruption, data-augmentation | e45c8d054739d31676619e7e11327f68.md |
| 456 | Gradient Cuff: Detecting Jailbreak Attacks on Large Language | jailbreak-detection, refusal-loss, loss-landscape | e46984e056185b21ddb1e7973c365f14.md |
| 457 | The Prevalence of Neural Collapse in Neural Multivariate  Re | neural-collapse, multivariate-regression, imitation-learning | e4748b6b6ca49f04b6a8cfce1d5f9a70.md |
| 458 | Towards Principled Graph Transformers | graph-transformers, weisfeiler-leman, expressive-power | e5419147e53eba322cf12aff266a66f2.md |
| 459 | Theoretical Foundations of Deep Selective State-Space Models | selective-state-space-models, Mamba, theoretical-analysis | e6231c5f46598cfd09ff1970524e0436.md |
| 460 | Understanding the Role of Equivariance in Self-supervised Le | equivariance, contrastive-learning, self-supervised-learning | e6825a8d9ff48e0cfe013608fec3ddec.md |
| 461 | Model LEGO: Creating Models Like Disassembling and Assemblin | model-assembly, knowledge-transfer, CNN | e6c185ba1ac2880d6f53aae3cfa80469.md |
| 462 | Sequoia: Scalable and Robust Speculative Decoding | speculative-decoding, LLM-inference, scalable-decoding | ea1f5f0878d43ff4fb8bf64ef4a2326c.md |
| 463 | Geometry-aware training of factorized layers in tensor Tucke | tucker-decomposition, tensor-factorization, riemannian-optimization | ea48cb23a02ec3b895b0b0124307b0ec.md |
| 464 | Fast yet Safe: Early-Exiting with Risk Control | early-exit-networks, risk-control, conformal-prediction | ea5a63f7ddb82e58623693fd1f4933f7.md |
| 465 | Regularized Q-Learning | q-learning, regularization, linear-function-approximation | ea6d17af54f827336fc8fed27ca0319d.md |
| 466 | Average gradient outer product as a mechanism for deep neura | neural-collapse, gradient-outer-product, representation-geometry | ec045a5ca2d8cfc528591b4c34296370.md |
| 467 | Energy-based Hopfield Boosting for Out-of-Distribution Detec | out-of-distribution-detection, hopfield-networks, energy-based-models | ee20461718669c6c9c5da478d46d60d9.md |
| 468 | Neglected Hessian component explains mysteries in sharpness  | sharpness-aware-minimization, hessian, generalization | ee3ce0121939f42098cdefd3ea025bf1.md |
| 469 | A Label is Worth A Thousand Images in Dataset Distillation | dataset-distillation, data-compression, label-information | ee45939f4403e8abd63a15a29a9c055b.md |
| 470 | Long-Tailed Out-of-Distribution Detection via Normalized Out | out-of-distribution-detection, long-tail, outlier-distribution | ee657707107aa886da19ef6c4b311975.md |
| 471 | Model Sensitivity Aware Continual Learning | continual-learning, model-sensitivity, catastrophic-forgetting | ef62614753535977071395fb1f1435be.md |
| 472 | Exact, Tractable Gauss-Newton Optimization in Deep Reversibl | gauss-newton-optimization, second-order-methods, reversible-architectures | f144ab9985c739a5091ec188a2688644.md |
| 473 | FedNE: Surrogate-Assisted Federated Neighbor Embedding for D | federated-learning, neighbor-embedding, dimensionality-reduction | f1c131d41c3d5119a8de329140b3384e.md |
| 474 | Hamiltonian Monte Carlo on ReLU Neural Networks is Inefficie | hamiltonian-monte-carlo, relu-networks, bayesian-inference | f20cc4ba33ee8ed8734a0456ba00127d.md |
| 475 | An Improved Empirical Fisher Approximation for Natural Gradi | natural-gradient-descent, fisher-information, empirical-fisher | f23098fa0cfcdef0e743b134d380eeb9.md |
| 476 | Kernel PCA for Out-of-Distribution Detection | out-of-distribution-detection, kernel-pca, deep-neural-networks | f2543511e5f4d4764857f9ad833a977d.md |
| 477 | Understanding Hallucinations in Diffusion Models through Mod | diffusion-models, hallucinations, mode-interpolation | f29369d192b13184b65c6d2515474d78.md |
| 478 | Unrolled denoising networks provably learn to perform optima | algorithm-unrolling, Bayesian-inference, denoising-networks | f40b522ef32bbc050d37a2a1ab7ffc2b.md |
| 479 | Unveil Benign Overfitting for Transformer in Vision: Trainin | vision-transformer, benign-overfitting, generalization-theory | f49287371916715b9209fa41a275851e.md |
| 480 | Dynamics of Supervised and Reinforcement Learning in the Non | learning-dynamics, perceptron, reinforcement-learning | f65d490e9f6b26894919d111306dbbb8.md |
| 481 | Sharpness-diversity tradeoff: improving flat ensembles with  | deep-ensembles, sharpness, diversity | f72d4fdfd5eb425cd81df9fe6272a533.md |
| 482 | Mixture of Scales: Memory-Efficient Token-Adaptive Binarizat | binarization, large-language-models, quantization | f89221edad5a6a4a54fcf247cb37cd62.md |
| 483 | Transformers on Markov data: Constant depth suffices | transformers, markov-processes, attention | f8a2070082ad05b4deeff4ffb4312a6f.md |
| 484 | ProTransformer: Robustify Transformers via Plug-and-Play Par | robust-attention, transformers, plug-and-play | f8b1ea224de27a460488db5b854f6c53.md |
| 485 | Bounds for the smallest eigenvalue of the NTK for arbitrary  | neural-tangent-kernel, smallest-eigenvalue, spherical-data | f9af936fc42039578ace655a82d928aa.md |
| 486 | Neural collapse vs. low-rank bias: Is deep neural collapse r | neural-collapse, deep-neural-collapse, low-rank-bias | f9c2ab8d429044e0c35bcece2ff6d123.md |
| 487 | Enhancing Diversity in Bayesian Deep Learning via Hyperspher | Bayesian-deep-learning, CKA, hyperspherical-energy | f9e72ee379bb781f3005775c870a3871.md |
| 488 | Adversarially Robust Multi-task Representation Learning | adversarial-robustness, multi-task-learning, transfer-learning | fb42bb10564271d0cf3cc8244ff3e5bb.md |
| 489 | Recurrent neural networks: vanishing and exploding gradients | recurrent-neural-networks, vanishing-gradients, state-space-models | fbb07254ef01868967dc891ea3fa6c13.md |
| 490 | The Iterative Optimal Brain Surgeon: Faster Sparse Recovery  | model-pruning, sparsity, optimal-brain-surgeon | fc1dce23e0ba01d3b691789cfd4f65c3.md |
| 491 | Understanding Linear Probing then Fine-tuning Language Model | linear-probing, fine-tuning, neural-tangent-kernel | fcc22e5b7d5d2155d994da22d045f0a6.md |
| 492 | On Tractable $\Phi$-Equilibria in Non-Concave Games | phi-equilibria, non-concave-games, online-learning | fdf14882bd645b5a37c912bbc16928c6.md |
| 493 | Penalty-based Methods for Simple Bilevel Optimization under  | bilevel-optimization, penalty-methods, Holderian-error-bounds | fe61e76998bbe3db53a6a48fa58207e9.md |
| 494 | High-probability complexity bounds for stochastic non-convex | minimax-optimization, high-probability-bounds, stochastic-gradient | fec946957ce1af51a61e8f2d851ac98f.md |
| 495 | First-Order Methods for Linearly Constrained Bilevel Optimiz | bilevel-optimization, first-order-methods, linear-constraints | ffd86e56e6403d63dd6face033060e5a.md |
