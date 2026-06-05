---
interest: medium
link: https://arxiv.org/abs/2606.02630
next_step: skim
priority: low
slack_ts: '1780633549.943899'
source: cs.CR - Cryptography and Security
status: unread
title: 'MultiTurnPSB: Evaluating Multi-Turn Jailbreak Attacks an dClassifier-Based
  Defenses for Medical AI Safety'
---
# MultiTurnPSB: Evaluating Multi-Turn Jailbreak Attacks an dClassifier-Based Defenses for Medical AI Safety
> 原文: [https://arxiv.org/abs/2606.02630](https://arxiv.org/abs/2606.02630)

arXiv:2606.02630v1 Announce Type: new
Abstract: Patient-facing medical chatbots are commonly evaluated on single-turn prompts, yet real users push back after refusals, add urgency, and invoke authority. We introduce MultiTurnPSB, a four-turn adversarial extension of PatientSafetyBench, and evaluate GPT-4.1-mini under fixed template, template-adaptive, and live adversarial attacks. Unsafe responses rise from 35% to nearly 80% by Turn 4 under live attack. Under the same adversary, GPT-4.1-mini and Claude Sonnet 4.5 are statistically indistinguishable at baseline but diverge to a 19x gap by Turn 4, a difference invisible to single-turn evaluation. We characterize four degradation trajectory signatures and identify a two-element attack formula responsible for most catastrophic failures. A lightweight input-side classifier reduces Turn 4 unsafe responses by 52 percentage points despite severe accuracy degradation, but the 45% false alarm rate on benign queries is the primary deployment constraint. A methodological finding also emerges: Claude Sonnet refused to generate adversarial messages in over half of late-turn conversations despite explicit red team framing, suggesting safety training may generalize to the attacker role.
