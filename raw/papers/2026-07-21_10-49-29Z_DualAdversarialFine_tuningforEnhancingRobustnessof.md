---
title: Dual Adversarial Fine-tuning for Enhancing Robustness of Large Vision Language Model
published: 2026-07-21T10:49:29Z
authors: Sibo Wang, Jie Zhang, Shiguang Shan, Xilin Chen, Wen Gao
url: http://arxiv.org/abs/2607.18958v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# Dual Adversarial Fine-tuning for Enhancing Robustness of Large Vision Language Model

## Abstract
While Large Vision-Language Models (LVLMs), represented by LLaVA and GPT-4V, have demonstrated remarkable capabilities, their visual inputs remain vulnerable to adversarial attacks, posing significant security risks. Existing defense methods predominantly target single-task scenarios (e.g., zero-shot classification) and consequently lack generalizability across various multimodal tasks. To address this limitation, we propose a dual adversarial fine-tuning framework that jointly optimizes visual and semantic supervision signals from two modalities, enhancing model robustness while generalizing across multiple downstream tasks. The proposed framework comprises two core components, i.e., $\textbf{Visual}$ supervision branch and $\textbf{Semantic}$ supervision branch. The former branch leverages features from clean images, extracted via a frozen original vision encoder, to guide adversarial robustness while the latter incorporates caption-image alignment as a contextual signal to preserve semantic coherence under attack. Moreover, our method achieves cross-task robustness by simply replacing the CLIP vision encoder in the original model, with no need of separate task-specific retraining or architecture modifications.Extensive experiments demonstrate that our approach outperforms the state-of-the-art method in adversarial robustness evaluation across zero-shot classification, image captioning, and visual question answering (VQA) tasks.

## Metadata
- **Published**: 2026-07-21T10:49:29Z
- **Authors**: Sibo Wang, Jie Zhang, Shiguang Shan, Xilin Chen, Wen Gao
- **Source**: [ArXiv Link](http://arxiv.org/abs/2607.18958v1)