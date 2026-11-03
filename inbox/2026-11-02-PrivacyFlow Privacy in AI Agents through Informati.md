---
interest: medium
link: https://arxiv.org/abs/2610.40714
next_step: skim
priority: low
slack_ts: '1793686640.530379'
source: cs.CR - Cryptography and Security
status: unread
title: 'PrivacyFlow: Privacy in AI Agents through Information Flow Analysis and Consequence-Aware
  Risk Management'
---
# PrivacyFlow: Privacy in AI Agents through Information Flow Analysis and Consequence-Aware Risk Management
> 原文: [https://arxiv.org/abs/2610.40714](https://arxiv.org/abs/2610.40714)

arXiv:2610.40714v1 Announce Type: new
Abstract: Autonomous LLM agents executing multi-step workflows over personal data often misalign with user privacy expectations and leak sensitive, out-of-context information. Although Contextual Integrity (CI) formalizes this problem, existing benchmarks and defenses rarely operationalize CI for realistic multi-step task sequences in evolving environments. In this work, we first introduce agentic PrivacyBench, a benchmark of 5873 tasks in 986 task sequences with dynamic environment updates and CI-grounded allow-sets for sensitive information. We also introduce PrivacyFlow, a defense that separates deliberative privacy planning (System 2) from task execution (System 1), treating each sharing decision as a structured risk-management problem. Before execution, PrivacyFlow traces the provenance and purpose of each planned data flow, models recipient background knowledge, and simulates what external actors could infer. This allows us to model the downstream consequences of disclosure, including inference attacks and context-dependent harms. It then weighs the remaining disclosure risk against task utility and executes a minimized plan, blocks it, or consults the user. Across six models, PrivacyFlow significantly reduces step-level privacy failures and raises the share of completed task sequences without a detected privacy violation by 22--55 percentage points. We further highlight a new privacy--utility--autonomy tradeoff: allowing PrivacyFlow to proactively prompt the user in case of uncertainty can increase authorized task completion at the cost of shifting decision effort back to the user. Our results suggest that proactive CI reasoning can substantially improve agentic privacy and motivate further study of this tradeoff.
