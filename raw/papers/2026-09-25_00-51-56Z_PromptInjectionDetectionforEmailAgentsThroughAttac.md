---
title: Prompt Injection Detection for Email Agents Through Attack Chain Modeling
published: 2026-09-25T00:51:56Z
authors: Ahmad Hashmi, Dhyey Patel, Yunting Yin
url: http://arxiv.org/abs/2609.30657v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# Prompt Injection Detection for Email Agents Through Attack Chain Modeling

## Abstract
Large language model email assistants are particularly vulnerable to indirect prompt injection because untrusted email content can be retrieved into the model context and influence subsequent tool use. Existing prompt injection detectors mainly formulate this problem as binary malicious text classification, which overlooks the important factor that harmful agent behavior often arises through a sequence of stages. We propose a detection framework that models this attack chain by combining a text detector, verifiers specific to each stage, explicit rule-based risk signals, user intent and action consistency analysis, and a logistic decision policy. To support this framework, we derive attack chain labels from prompt injection datasets, evaluate the proposed framework under random splits, temporal phase transfer, conditional stage transfer, cross-dataset transfer, and conduct ablation studies on multiple benchmarks. Results show that random train test splits substantially overestimate robustness under distribution shift, while later tool argument stages are more predictable than earlier stages in the framework. We also show that training on harmless emails that resemble attacks helps reduce false alarms while preserving the ability to detect real attacks. Across five binary benchmarks, our framework achieves a mean F1 score of 0.406 under the strict threshold setting policy, compared with 0.216 for the strongest of five pretrained detectors evaluated without additional training. These results highlight the value of combining attack stage predictions with checks for conflicts between the user's request and instructions in retrieved emails. Our experiments also demonstrate the importance of training with challenging benign examples to balance attack detection and false alarms.

## Metadata
- **Published**: 2026-09-25T00:51:56Z
- **Authors**: Ahmad Hashmi, Dhyey Patel, Yunting Yin
- **Source**: [ArXiv Link](http://arxiv.org/abs/2609.30657v1)