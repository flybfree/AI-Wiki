---
title: Rubrics as Privileged Information for Open-Ended Generation
published: 2026-08-03T23:25:50Z
authors: Deepika Bablani, Ajay Gupta, Wanming Chen
url: http://arxiv.org/abs/2608.02948v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# Rubrics as Privileged Information for Open-Ended Generation

## Abstract
On-policy self-distillation (OPSD), where a single model acts as both student and teacher with different contexts, has shown promise in verifiable domains like math, where hard privileged information (PI) in the form of ground-truth answers structurally constrains valid continuations. We extend OPSD to open-ended generation using soft PI in the form of rubrics that guide preferences but admit many valid responses. Rubrics have served as scalar rewards for reinforcement learning (RL); we show that they provide substantially richer signal as dense PI for distillation, and contrary to intuition, soft rubric PI provides a larger and more effective training signal on student roll-outs than hard reference completion PI in this regime. A reference completion is one point in a set of valid responses, so distilling towards it over-constrains the student, while rubrics specify the preference structure shared across the set of valid responses. We show the effectiveness of using rubrics as PI for open-ended generation across Qwen and Llama model families and show that it outperforms rubric-as-reward (RaR) RL using HealthBench, a benchmark that grades open-ended health responses against physician-created rubrics, providing dense token-level supervision for open-ended tasks; RuPI beats RaR RL by up to +0.10 absolute score and, under matched recipe and KL direction, beats reference-PI by +0.034 to +0.079 absolute score across three models. We further show that these findings generalize to training on the RubricHub Science corpus and evaluating on ResearchQA: soft rubric PI outperforms both reference-PI distillation and RaR RL (66.6% vs. 64.2% and 57.6%).

## Metadata
- **Published**: 2026-08-03T23:25:50Z
- **Authors**: Deepika Bablani, Ajay Gupta, Wanming Chen
- **Source**: [ArXiv Link](http://arxiv.org/abs/2608.02948v1)