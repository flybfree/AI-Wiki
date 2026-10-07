---
title: AdvSim2Real : Training Web Agents Against Adaptive Prompt Injection in a Web World Model
published: 2026-10-06T17:56:43Z
authors: Sarim Hashmi, Mukul Ranjan, Kshitij Mishra, Mikhail Kuznetsov, Praneeth Vepakomma, Nils Lukas
url: http://arxiv.org/abs/2610.08773v1
type: paper-summary
tags: [paper-summary, arxiv]
---

# AdvSim2Real : Training Web Agents Against Adaptive Prompt Injection in a Web World Model

## Abstract
Web agents complete user requests by reading and acting on pages that third parties write, so an instruction planted on a page can redirect the agent away from the user's goal. The agent cannot simply ignore the page, because the page also holds the values and controls the task requires. Current defenses fine-tune the agent on injections fixed before training, and attackers that adapt to the trained model bypass them. Adversarial training lets the attacker adapt but keeps the tasks fixed, so a task stops teaching once the agent solves it. We introduce AdvSim2Real, which co-evolves a task curriculum, an injection adversary, and the agent inside a frozen web world model. The curriculum is rewarded for tasks the agent solves about half of the time, and the adversary only for a success flip, an injection that turns a judged success into a failure. Training in the simulator makes a 4B agent both more capable and more robust: its completion rises with and without attacks, holds against a frontier-model adversary it never trained against, and its capability gain carries over to a real browser. On 150 web tasks, AdvSim2Real raises completion under this unseen adversary by 33.6\% relative to the base agent.

## Metadata
- **Published**: 2026-10-06T17:56:43Z
- **Authors**: Sarim Hashmi, Mukul Ranjan, Kshitij Mishra, Mikhail Kuznetsov, Praneeth Vepakomma, Nils Lukas
- **Source**: [ArXiv Link](http://arxiv.org/abs/2610.08773v1)