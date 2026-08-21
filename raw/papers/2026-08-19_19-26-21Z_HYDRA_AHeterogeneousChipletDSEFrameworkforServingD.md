---
title: HYDRA: A Heterogeneous Chiplet DSE Framework for Serving Dynamic Hybrid LLM Workloads
published: 2026-08-19T19:26:21Z
authors: Jiahao Lin, Alish Kanani, Sangwan Lee, Jaehyun Park, Umit Ogras
url: http://arxiv.org/abs/2608.19395v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# HYDRA: A Heterogeneous Chiplet DSE Framework for Serving Dynamic Hybrid LLM Workloads

## Abstract
Hybrid Transformer-Mamba large language models (LLMs) enhance long-context efficiency, but their heterogeneous computation and communication patterns complicate efficient hardware acceleration. Chiplet-based architectures offer a scalable solution by integrating specialized compute and memory units. However, the design space spanning static architectural configurations and dynamic runtime policies is prohibitively large to explore exhaustively. To address this challenge, we present HYDRA, a comprehensive design space exploration framework for hybrid LLM serving on heterogeneous chiplet systems. HYDRA jointly explores chiplet composition, placement, inter-chiplet bandwidth provisioning, dynamic batching, and runtime scheduling. It integrates communication-aware placement, dynamic batching, elastic task scheduling, and a fast Markov-based performance estimator that captures multi-tenant runtime dynamics for efficient and accurate exploration. Across all workloads, HYDRA delivers 1.55x the throughput and 43.7 percent lower time-to-first-token on average, with throughput gains reaching up to 2.3x compared to state-of-the-art baselines. These results highlight that co-designing architecture and runtime policies is critical for efficient large-scale LLM serving on heterogeneous chiplet systems.

## Metadata
- **Published**: 2026-08-19T19:26:21Z
- **Authors**: Jiahao Lin, Alish Kanani, Sangwan Lee, Jaehyun Park, Umit Ogras
- **Source**: [ArXiv Link](http://arxiv.org/abs/2608.19395v1)