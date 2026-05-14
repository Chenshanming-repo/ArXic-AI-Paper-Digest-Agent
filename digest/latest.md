---
## 2026-05-14

### 1. AlphaGRPO: Unlocking Self-Reflective Multimodal Generation in UMMs via Decompositional Verifiable Reward
**Authors:** Runhui Huang, Jie Wu, Rui Yang, Zhe Liu, Hengshuang Zhao
**Link:** https://arxiv.org/abs/2605.12495v1
**Summary:** The paper presents AlphaGRPO, a new framework that enhances the capabilities of Unified Multimodal Models (UMMs) for complex tasks like text-to-image generation and output refinement, without requiring an initial training phase. By introducing a Decompositional Verifiable Reward system that breaks down user requests into manageable components for evaluation, the framework achieves significant performance improvements in multimodal generation benchmarks and editing tasks. This self-reflective approach effectively leverages the model's inherent understanding to produce higher-quality outputs.

### 2. LongMemEval-V2: Evaluating Long-Term Agent Memory Toward Experienced Colleagues
**Authors:** Di Wu, Zixiang Ji, Asmi Kawatkar, Bryan Kwan, Jia-Chen Gu, Nanyun Peng, Kai-Wei Chang
**Link:** https://arxiv.org/abs/2605.12493v1
**Summary:** The paper introduces LongMemEval-V2, a benchmark designed to assess how well memory systems in agents can retain and utilize experience in specialized web environments. It evaluates five key memory abilities through 451 curated questions and compares two memory methods: AgentRunbook-R and AgentRunbook-C, where the latter significantly outperformed existing baselines with an average accuracy of 72.5%, despite facing high latency issues. This work establishes LME-V2 as a valuable tool for advancing long-term memory systems in agents.

### 3. Pion: A Spectrum-Preserving Optimizer via Orthogonal Equivalence Transformation
**Authors:** Kexuan Shi, Hanxuan Li, Zeju Qiu, Yandong Wen, Simon Buchholz, Weiyang Liu
**Link:** https://arxiv.org/abs/2605.12492v1
**Summary:** The paper presents Pion, a new optimizer designed for training large language models that maintains the singular values of weight matrices by using orthogonal transformations, as opposed to traditional additive methods. This approach helps preserve the spectral properties of the model while still allowing for effective updates during training. The authors demonstrate that Pion provides stable and competitive performance compared to standard optimizers in both the pretraining and finetuning phases.

### 4. Elastic Attention Cores for Scalable Vision Transformers
**Authors:** Alan Z. Song, Yinjie Chen, Mu Nan, Rui Zhang, Jiahang Cao, Weijian Mai, Muquan Yu, Hossein Adeli, Deva Ramanan, Michael J. Tarr, Andrew F. Luo
**Link:** https://arxiv.org/abs/2605.12491v1
**Summary:** The paper addresses the computational inefficiency of Vision Transformers (ViTs), which struggle with high-resolution images due to their quadratic scaling with the number of image patches. The authors introduce VECA (Visual Elastic Core Attention), an architecture that uses a small set of learned core tokens to facilitate communication among patches, reducing attention complexity to linear time while maintaining high accuracy. The key contribution is that VECA can achieve competitive performance with existing models while substantially lowering computational costs, making it a scalable option for ViTs.

### 5. Task-Adaptive Embedding Refinement via Test-time LLM Guidance
**Authors:** Ariel Gera, Shir Ashury-Tahan, Gal Bloch, Ohad Eytan, Assaf Toledo
**Link:** https://arxiv.org/abs/2605.12487v1
**Summary:** The paper addresses the challenge of improving the performance of embedding models in zero-shot search and classification tasks by refining user queries with guidance from a generative language model (LLM). The authors propose an LLM-guided query refinement method that adapts embedding representations in real-time, leading to significant performance improvements in various benchmarks. Key findings show that this approach enhances ranking quality and better aligns embeddings with the specific requirements of user queries, making it a valuable alternative for practical applications where large LLMs are impractical.

### 6. Learning, Fast and Slow: Towards LLMs That Adapt Continually
**Authors:** Rishabh Tiwari, Kusha Sareen, Lakshya A Agrawal, Joseph E. Gonzalez, Matei Zaharia, Kurt Keutzer, Inderjit S Dhillon, Rishabh Agarwal, Devvrit Khatri
**Link:** https://arxiv.org/abs/2605.12484v1
**Summary:** The paper addresses the issue of catastrophic forgetting in large language models (LLMs) when updating parameters for specific tasks, which limits their flexibility and adaptability. To overcome this, the authors propose a fast-slow learning framework that uses "fast" weights for task-specific adjustments while keeping the "slow" weights close to the base model. The key finding is that this Fast-Slow Training method is significantly more sample-efficient and minimizes forgetting, allowing for better adaptability in continual learning scenarios compared to traditional parameter-only updates.

### 7. Beyond GRPO and On-Policy Distillation: An Empirical Sparse-to-Dense Reward Principle for Language-Model Post-Training
**Authors:** Yuanda Xu, Hejian Sang, Zhengze Zhou, Ran He, Zhipeng Wang, Alborz Geramifard
**Link:** https://arxiv.org/abs/2605.12483v1
**Summary:** The paper addresses the inefficiency in allocating scarce labeled training data when fine-tuning language models by proposing a reward-density principle. It suggests using sparse rewards for exploration with a strong model (teacher) and then transferring that learned behavior as dense supervision to a smaller model (student). The key findings demonstrate that this strategy improves performance on verifiable tasks, significantly outperforming traditional methods like direct GRPO in specific benchmarks.

### 8. ToolCUA: Towards Optimal GUI-Tool Path Orchestration for Computer Use Agents
**Authors:** Xuhao Hu, Xi Zhang, Haiyang Xu, Kyle Qiao, Jingyi Yang, Xuanjing Huang, Jing Shao, Ming Yan, Jieping Ye
**Link:** https://arxiv.org/abs/2605.12481v1
**Summary:** The paper presents ToolCUA, an innovative approach for optimizing the decision-making process of Computer Use Agents (CUAs) when choosing between GUI actions and tool calls, a challenge stemming from the lack of quality training data. To address this, the authors developed a method that synthesizes diverse GUI-Tool interactions from existing data and employs a tailored reinforcement learning strategy to enhance decision-making at critical junctures. The results indicate that ToolCUA achieves a 46.85% accuracy, outperforming previous models by a significant margin and demonstrating the effectiveness of training in a hybrid action framework.

### 9. OmniNFT: Modality-wise Omni Diffusion Reinforcement for Joint Audio-Video Generation
**Authors:** Guohui Zhang, XiaoXiao Ma, Jie Huang, Hang Xu, Hu Yu, Siming Fu, Yuming Li, Zeyue Xue, Lin Song, Haoyang Huang, Nan Duan, Feng Zhao
**Link:** https://arxiv.org/abs/2605.12480v1
**Summary:** The paper addresses the challenges of generating high-quality audio and video simultaneously, particularly focusing on maintaining fidelity, alignment, and synchronization across modalities. The authors present OmniNFT, a novel reinforcement learning framework that incorporates three main strategies to improve the generation process, including routing rewards per modality, managing gradient flow, and adjusting optimization efforts based on critical alignment areas. Extensive experiments show that OmniNFT significantly enhances the quality and synchronization of generated audio and video compared to existing methods.

### 10. MEME: Multi-entity & Evolving Memory Evaluation
**Authors:** Seokwon Jung, Alexander Rubinstein, Arnas Uselis, Sangdoo Yun, Seong Joon Oh
**Link:** https://arxiv.org/abs/2605.12477v1
**Summary:** The paper addresses the challenge of evaluating memory systems in language model-based agents that operate in environments requiring management of multiple entities and evolving information over time. The authors introduce the MEME benchmark, which includes six diverse tasks that assess memory performance, revealing that existing systems struggle with dependency reasoning despite performing well in static retrieval scenarios. A notable finding is that only a specific configuration of a file-based agent with a powerful LLM shows improved performance, although this method is significantly more costly, highlighting a gap in practical scalability.
