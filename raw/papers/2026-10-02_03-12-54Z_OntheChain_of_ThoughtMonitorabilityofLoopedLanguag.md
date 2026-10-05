---
title: On the Chain-of-Thought Monitorability of Looped Language Models
published: 2026-10-02T03:12:54Z
authors: Han Wang, Ishwar B Balappanawar, Huan Zhang
url: http://arxiv.org/abs/2610.02741v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# On the Chain-of-Thought Monitorability of Looped Language Models

## Abstract
Chain-of-thought (CoT) monitoring provides a promising approach for detecting undesirable model behavior. Looped language models (LoopLMs) repeatedly apply shared transformer layers, increasing effective computational depth and enabling additional latent computation without increasing model size. However, the effect of looped architectures on CoT monitorability remains largely unexplored. In this work, we provide the first systematic evaluation of CoT monitorability in LoopLMs. We study two complementary settings: (1) varying the loop depth within the same LoopLM family to isolate the effect of additional recurrent computation, and (2) comparing LoopLMs with non-looped language models matched by parameter size, transformer-layer count, or effective depth to study whether LoopLMs are less monitorable. Across eight tasks from MonitorBench and both standard and stress-test settings, we observe task-dependent reductions in CoT monitorability under stress tests on specific Logic/Science/Engineering \texttt{Cue Answer} tasks, while other tasks exhibit weaker or qualitatively different trends. Our diagnosis suggests that these declines are not fully explained by task difficulty, verification pass rate, or generated token length; qualitative examples further suggest changes in how deeper-loop models explicitly use or attribute provided cues. Our cross-model comparison finds no evidence that LoopLMs are systematically less monitorable than non-looped language models matched on size or depth. Overall, our results suggest that deeper loop depth can reduce CoT monitorability in some tasks under stress tests, but looped transformer architecture alone does not necessarily imply lower monitorability.

## Metadata
- **Published**: 2026-10-02T03:12:54Z
- **Authors**: Han Wang, Ishwar B Balappanawar, Huan Zhang
- **Source**: [ArXiv Link](http://arxiv.org/abs/2610.02741v1)