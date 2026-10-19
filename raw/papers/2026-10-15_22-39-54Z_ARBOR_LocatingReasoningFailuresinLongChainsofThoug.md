---
title: ARBOR: Locating Reasoning Failures in Long Chains of Thought through Reasoning State Tracking
published: 2026-10-15T22:39:54Z
authors: Huihan Li, Siyuan Wang, Naga Vamsi Ramana Dinavahi, Xiaohui Liu, Xiang Ren
url: http://arxiv.org/abs/2610.22717v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# ARBOR: Locating Reasoning Failures in Long Chains of Thought through Reasoning State Tracking

## Abstract
Large reasoning models solve complex problems through long chains of thought, in which prior work has documented failure modes such as overthinking, underthinking, and unsupported deductions. Existing methods detect these failures from local signals: textual similarity to nearby steps, switch tokens, or an LLM's judgment of a step's correctness. However, what a step contributes to the solution depends on the state that earlier steps have established, so identifying failures requires a global view that tracks that state across the trajectory. Therefore, we propose ARBOR, a reasoning-failure attribution framework that represents each trajectory as a tree of reasoning states, built as each step creates, verifies, prunes, or revisits a state, and attributes each failure to a relation between a step and the state preceding it. Using ARBOR, we refine the three failure modes into distinct subtypes that harm reasoning through different mechanisms and at different costs. We find that the tree state ARBOR maintains before a step separates failure steps from the at-risk steps at which the failure did not occur. We discuss how ARBOR integrates with existing mitigations at inference time and in training data. Code, data and interactive examples are available at https://inklab.usc.edu/ARBOR.

## Metadata
- **Published**: 2026-10-15T22:39:54Z
- **Authors**: Huihan Li, Siyuan Wang, Naga Vamsi Ramana Dinavahi, Xiaohui Liu, Xiang Ren
- **Source**: [ArXiv Link](http://arxiv.org/abs/2610.22717v1)