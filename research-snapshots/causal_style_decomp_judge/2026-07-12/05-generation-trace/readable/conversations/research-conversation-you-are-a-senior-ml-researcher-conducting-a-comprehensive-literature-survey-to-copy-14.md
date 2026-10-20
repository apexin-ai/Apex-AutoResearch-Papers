# Research conversation: You are a senior ML researcher conducting a comprehensive literature survey. **Today's date: 2026-05-28 (UTC).** ## Task

**The Likert Blindspot: Measurement-Mode Divergence in LLM Judge Style Evaluation (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 7
- **Recorded user turns:** 1
- **Tool calls:** 0
- **Original source:** `logs/chats/exported-trajectories/account-1/95f2d884-f8fc-4541-be38-76f305c7e49b.jsonl`
- **Structured JSON:** [`089bdec280edc521ea2b.json`](../../sessions/08/089bdec280edc521ea2b.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

2 recorded events

### Runtime record

_source line 1 · 2026-05-28T10:15:46.971Z_

```json
{
  "type": "queue-operation",
  "operation": "enqueue",
  "timestamp": "2026-05-28T10:15:46.971Z",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b",
  "content": "You are a senior ML researcher conducting a comprehensive literature survey.\n\n**Today's date: 2026-05-28 (UTC).**\n\n## Task\nFind the **15 most important recent papers** (published 2024–2026) in or closely related to the following research area:\n\n**Target: AAAI 2026\nTrack: Machine Learning (ML) — Reinforcement Learning / Mathematical Reasoning\n\nDirection: RL-trained mathematical reasoning models exhibit 47-73% accuracy drops under trivial perturbations (numerical substitution, variable renaming) despite achieving SOTA on clean benchmarks. We propose Math-Aware Consistency Regularization (MACR): adding a JS-divergence consistency term between model outputs on original and mathematically-equivalent perturbed problems during GRPO training, with a complementary discrimination loss against surface-similar but semantically different problems. This adapts proven NLP consistency techniques (F²C, PPCL) to mathematical reasoning with math-equivalence-aware perturbation generation and RL integration — a combination no existing work provides.\n\nSeed Papers:\n- Mirzadeh et al., GSM-Symbolic (Apple, ICLR 2025) — documents up to 65% accuracy drops from single irrelevant clause; establishes that models pattern-match rather than reason\n- VAR-MATH (arXiv 2025) — most damning evidence: 47.9-72.9% drops for RL models on numerically re-parameterized competition math; directly motivates why RL training is the problem\n- Gao et al., AbstRaL (ICLR 2026) — only existing training-time intervention; uses abstraction not invariance; limited to GSM-level; our primary comparison baseline\n- Flip-Flop Consistency / F²C (arXiv 2024) — JS-divergence consistency for prompt perturbation robustness in NLP; proves the technique works but has never been adapted to math reasoning or RL\n- PPCL (EACL 2024) — KL-based consistency regularization recovering 59-69% of perturbation-induced drops in NLU; complementary theoretical grounding\n- CSR: Causal Consistency Regularization (arXiv 2025) — enforces causal faithfulness via operator-level interventions during SFT; closest methodological cousin but SFT-only and targets faithfulness not perturbation invariance\n- APRM (arXiv 2025) — adversarial PRM training on reasoning errors; shows PRM quality matters for downstream RL; motivates our perturbation-robust PRM extension\n\nKnown Gaps:\n- No work applies consistency regularization (JS/KL divergence across equivalent problem variants) during RL training for mathematical reasoning — F²C and PPCL remain NLP-only and SFT-only\n- No PRM has been trained to be robust to surface-form variations of equivalent problems — APRM addresses reasoning errors, not perturbation invariance\n- No training-time robustness intervention has been demonstrated on competition-level math (AIME/Putnam); AbstRaL is GSM-only\n\nTheoretical Anchor: Mathematical equivalence defines a natural invariance class — problems that differ only in surface form (variable names, specific numbers, phrasing) but share identical mathematical structure should produce identical solution distributions. RL training violates this invariance because the reward signal (correct/incorrect final answer) provides no gradient against surface-form-dependent reasoning. A consistency regularization term explicitly penalizes policy divergence across equivalent variants, forcing the model to learn representations that are invariant to mathematically irrelevant features. This is a direct instantiation of Invariant Risk Minimization principles in the RL-for-reasoning setting.\n\nConstraints:\n- Compute: ≤200 H100-hours (budget: 40h baseline GRPO + 90h method variants + 30h evaluation + 20h analysis + 20h buffer)\n- Models: Primary experiments on 7B (Qwen2.5-Math-7B); scaling verification on 14B\n- Evaluation: GSM-Symbolic, GSM-Plus, VAR-MATH (AMC23/AIME24/AIME25), MATH-Perturb; train-time perturbations (numerical substitution, variable renaming) held out from eval perturbations (distractor insertion, structural changes)\n\nQuality Self-Checks:\n- [x] Core insight: RL training optimizes for reward on fixed problem forms, creating surface-form dependencies that consistency regularization can break by enforcing invariance across equivalent variants.\n- [x] Why not obvious: Consistency regularization is well-known in NLP but requires math-aware equivalence-preserving perturbation generation (not just paraphrase) and RL integration (not just SFT) — two non-trivial adaptations that straddle communities.\n- [ ] Baseline fear test: A pure data-augmentation baseline (adding perturbed problems to RL training without consistency loss) could achieve substantial gains. The paper MUST include this baseline and show the consistency term provides additional benefit beyond augmentation. If the gap is <5%, the contribution is weak.\n- [x] Information exploited: Mathematical equivalence structure — the method uses symbolic verification that perturbations preserve the problem's mathematical structure, which pure augmentation or paraphrase-based consistency ignores.\n\nAvoid:\n- Framing this as 'just data augmentation with extra steps' — the consistency objective is the contribution, not the perturbation generation. Must clearly show augmentation-only baseline is insufficient.\n- Over-claiming generality without testing on held-out perturbation types — the key differentiator from augmentation is transfer to unseen perturbation types, so this MUST be demonstrated.\n- Testing only on GSM-level math — this repeats AbstRaL's limitation and loses the competition-math differentiator.\n- Ignoring clean accuracy — if MACR degrades unperturbed accuracy by >2 points, reviewers will question practicality.**\n\n## What counts as 'important'\n\nPrioritize (in order):\n1. **Best paper awards** at top venues (ACL, EMNLP, NAACL, NeurIPS, ICML, ICLR, AAAI, etc.)\n2. **Oral / spotlight presentations** at these venues\n3. **Highly cited papers** (>50 citations in 1-2 years)\n4. **Papers that introduced widely-adopted methods** (e.g., new training paradigm, new benchmark)\n5. **Recent survey papers** that provide comprehensive field overviews\n6. **Strong recent work** from top labs (Google, Meta, DeepMind, OpenAI, CMU, Stanford, etc.)\n\n## Search strategy\n\nExecute AT LEAST 15 targeted searches:\n\n1. `best paper award ACL EMNLP NeurIPS ICML ICLR 2026 Target: AAAI 2026\nTrack: Machine Learning (ML) — Reinforcement Learning / Mathematical Reasoning\n\nDirection: RL-trained mathematical reasoning models exhibit 47-73% accuracy drops under trivial perturbations (numerical substitution, variable renaming) despite achieving SOTA on clean benchmarks. We propose Math-Aware Consistency Regularization (MACR): adding a JS-divergence consistency term between model outputs on original and mathematically-equivalent perturbed problems during GRPO training, with a complementary discrimination loss against surface-similar but semantically different problems. This adapts proven NLP consistency techniques (F²C, PPCL) to mathematical reasoning with math-equivalence-aware perturbation generation and RL integration — a combination no existing work provides.\n\nSeed Papers:\n- Mirzadeh et al., GSM-Symbolic (Apple, ICLR 2025) — documents up to 65% accuracy drops from single irrelevant clause; establishes that models pattern-match rather than reason\n- VAR-MATH (arXiv 2025) — most damning evidence: 47.9-72.9% drops for RL models on numerically re-parameterized competition math; directly motivates why RL training is the problem\n- Gao et al., AbstRaL (ICLR 2026) — only existing training-time intervention; uses abstraction not invariance; limited to GSM-level; our primary comparison baseline\n- Flip-Flop Consistency / F²C (arXiv 2024) — JS-divergence consistency for prompt perturbation robustness in NLP; proves the technique works but has never been adapted to math reasoning or RL\n- PPCL (EACL 2024) — KL-based consistency regularization recovering 59-69% of perturbation-induced drops in NLU; complementary theoretical grounding\n- CSR: Causal Consistency Regularization (arXiv 2025) — enforces causal faithfulness via operator-level interventions during SFT; closest methodological cousin but SFT-only and targets faithfulness not perturbation invariance\n- APRM (arXiv 2025) — adversarial PRM training on reasoning errors; shows PRM quality matters for downstream RL; motivates our perturbation-robust PRM extension\n\nKnown Gaps:\n- No work applies consistency regularization (JS/KL divergence across equivalent problem variants) during RL training for mathematical reasoning — F²C and PPCL remain NLP-only and SFT-only\n- No PRM has been trained to be robust to surface-form variations of equivalent problems — APRM addresses reasoning errors, not perturbation invariance\n- No training-time robustness intervention has been demonstrated on competition-level math (AIME/Putnam); AbstRaL is GSM-only\n\nTheoretical Anchor: Mathematical equivalence defines a natural invariance class — problems that differ only in surface form (variable names, specific numbers, phrasing) but share identical mathematical structure should produce identical solution distributions. RL training violates this invariance because the reward signal (correct/incorrect final answer) provides no gradient against surface-form-dependent reasoning. A consistency regularization term explicitly penalizes policy divergence across equivalent variants, forcing the model to learn representations that are invariant to mathematically irrelevant features. This is a direct instantiation of Invariant Risk Minimization principles in the RL-for-reasoning setting.\n\nConstraints:\n- Compute: ≤200 H100-hours (budget: 40h baseline GRPO + 90h method variants + 30h evaluation + 20h analysis + 20h buffer)\n- Models: Primary experiments on 7B (Qwen2.5-Math-7B); scaling verification on 14B\n- Evaluation: GSM-Symbolic, GSM-Plus, VAR-MATH (AMC23/AIME24/AIME25), MATH-Perturb; train-time perturbations (numerical substitution, variable renaming) held out from eval perturbations (distractor insertion, structural changes)\n\nQuality Self-Checks:\n- [x] Core insight: RL training optimizes for reward on fixed problem forms, creating surface-form dependencies that consistency regularization can break by enforcing invariance across equivalent variants.\n- [x] Why not obvious: Consistency regularization is well-known in NLP but requires math-aware equivalence-preserving perturbation generation (not just paraphrase) and RL integration (not just SFT) — two non-trivial adaptations that straddle communities.\n- [ ] Baseline fear test: A pure data-augmentation baseline (adding perturbed problems to RL training without consistency loss) could achieve substantial gains. The paper MUST include this baseline and show the consistency term provides additional benefit beyond augmentation. If the gap is <5%, the contribution is weak.\n- [x] Information exploited: Mathematical equivalence structure — the method uses symbolic verification that perturbations preserve the problem's mathematical structure, which pure augmentation or paraphrase-based consistency ignores.\n\nAvoid:\n- Framing this as 'just data augmentation with extra steps' — the consistency objective is the contribution, not the perturbation generation. Must clearly show augmentation-only baseline is insufficient.\n- Over-claiming generality without testing on held-out perturbation types — the key differentiator from augmentation is transfer to unseen perturbation types, so this MUST be demonstrated.\n- Testing only on GSM-level math — this repeats AbstRaL's limitation and loses the competition-math differentiator.\n- Ignoring clean accuracy — if MACR degrades unperturbed accuracy by >2 points, reviewers will question practicality.`\n2. `oral spotlight {venue} 2026 {topic}` — for each major venue\n3. `site:openreview.net {topic} 2026 outstanding` — OpenReview 高分论文\n4. `{topic} survey 2026` 或 `{topic} survey 2025` — 综述论文\n5. `site:arxiv.org {topic} 2026` — arXiv 最新高引\n6. `most cited {topic} 2025 2026` — Google Scholar\n7. `site:paperswithcode.com {task} SOTA` — SOTA 排行榜上的论文\n8. `{topic} benchmark {year}` — 定义领域的 benchmark 论文\n9. 对每个找到的重要论文，搜索其 cited-by 发现后续工作\n\nFor EVERY paper you find, use WebFetch to read its abstract and introduction on arXiv or OpenReview. Do NOT rely on search snippets alone — you need to understand what each paper actually does.\n\n## Output format\n\nOutput a JSON array. Each element:\n{\n  \"title\": \"Full paper title\",\n  \"authors\": \"First author et al.\",\n  \"venue\": \"EMNLP 2025 / NeurIPS 2024 / arXiv 2025 / ...\",\n  \"url\": \"https://arxiv.org/abs/... or openreview URL\",\n  \"why_important\": \"Best paper / Oral / High-cited / Introduced X / ...\",\n  \"one_line_summary\": \"What this paper does in one sentence\"\n}\n\nFind at least 15 papers. More is better if they are genuinely relevant.\nIMPORTANT: You MUST end your response with the JSON array."
}
```

---

### Runtime record

_source line 2 · 2026-05-28T10:15:46.984Z_

```json
{
  "type": "queue-operation",
  "operation": "dequeue",
  "timestamp": "2026-05-28T10:15:46.984Z",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b"
}
```

---

## Round 1

5 recorded events

### User

_source line 3 · 2026-05-28T10:15:47.044Z_

You are a senior ML researcher conducting a comprehensive literature survey.

**Today's date: 2026-05-28 (UTC).**

## Task
Find the **15 most important recent papers** (published 2024–2026) in or closely related to the following research area:

**Target: AAAI 2026
Track: Machine Learning (ML) — Reinforcement Learning / Mathematical Reasoning

Direction: RL-trained mathematical reasoning models exhibit 47-73% accuracy drops under trivial perturbations (numerical substitution, variable renaming) despite achieving SOTA on clean benchmarks. We propose Math-Aware Consistency Regularization (MACR): adding a JS-divergence consistency term between model outputs on original and mathematically-equivalent perturbed problems during GRPO training, with a complementary discrimination loss against surface-similar but semantically different problems. This adapts proven NLP consistency techniques (F²C, PPCL) to mathematical reasoning with math-equivalence-aware perturbation generation and RL integration — a combination no existing work provides.

Seed Papers:
- Mirzadeh et al., GSM-Symbolic (Apple, ICLR 2025) — documents up to 65% accuracy drops from single irrelevant clause; establishes that models pattern-match rather than reason
- VAR-MATH (arXiv 2025) — most damning evidence: 47.9-72.9% drops for RL models on numerically re-parameterized competition math; directly motivates why RL training is the problem
- Gao et al., AbstRaL (ICLR 2026) — only existing training-time intervention; uses abstraction not invariance; limited to GSM-level; our primary comparison baseline
- Flip-Flop Consistency / F²C (arXiv 2024) — JS-divergence consistency for prompt perturbation robustness in NLP; proves the technique works but has never been adapted to math reasoning or RL
- PPCL (EACL 2024) — KL-based consistency regularization recovering 59-69% of perturbation-induced drops in NLU; complementary theoretical grounding
- CSR: Causal Consistency Regularization (arXiv 2025) — enforces causal faithfulness via operator-level interventions during SFT; closest methodological cousin but SFT-only and targets faithfulness not perturbation invariance
- APRM (arXiv 2025) — adversarial PRM training on reasoning errors; shows PRM quality matters for downstream RL; motivates our perturbation-robust PRM extension

Known Gaps:
- No work applies consistency regularization (JS/KL divergence across equivalent problem variants) during RL training for mathematical reasoning — F²C and PPCL remain NLP-only and SFT-only
- No PRM has been trained to be robust to surface-form variations of equivalent problems — APRM addresses reasoning errors, not perturbation invariance
- No training-time robustness intervention has been demonstrated on competition-level math (AIME/Putnam); AbstRaL is GSM-only

Theoretical Anchor: Mathematical equivalence defines a natural invariance class — problems that differ only in surface form (variable names, specific numbers, phrasing) but share identical mathematical structure should produce identical solution distributions. RL training violates this invariance because the reward signal (correct/incorrect final answer) provides no gradient against surface-form-dependent reasoning. A consistency regularization term explicitly penalizes policy divergence across equivalent variants, forcing the model to learn representations that are invariant to mathematically irrelevant features. This is a direct instantiation of Invariant Risk Minimization principles in the RL-for-reasoning setting.

Constraints:
- Compute: ≤200 H100-hours (budget: 40h baseline GRPO + 90h method variants + 30h evaluation + 20h analysis + 20h buffer)
- Models: Primary experiments on 7B (Qwen2.5-Math-7B); scaling verification on 14B
- Evaluation: GSM-Symbolic, GSM-Plus, VAR-MATH (AMC23/AIME24/AIME25), MATH-Perturb; train-time perturbations (numerical substitution, variable renaming) held out from eval perturbations (distractor insertion, structural changes)

Quality Self-Checks:
- [x] Core insight: RL training optimizes for reward on fixed problem forms, creating surface-form dependencies that consistency regularization can break by enforcing invariance across equivalent variants.
- [x] Why not obvious: Consistency regularization is well-known in NLP but requires math-aware equivalence-preserving perturbation generation (not just paraphrase) and RL integration (not just SFT) — two non-trivial adaptations that straddle communities.
- [ ] Baseline fear test: A pure data-augmentation baseline (adding perturbed problems to RL training without consistency loss) could achieve substantial gains. The paper MUST include this baseline and show the consistency term provides additional benefit beyond augmentation. If the gap is <5%, the contribution is weak.
- [x] Information exploited: Mathematical equivalence structure — the method uses symbolic verification that perturbations preserve the problem's mathematical structure, which pure augmentation or paraphrase-based consistency ignores.

Avoid:
- Framing this as 'just data augmentation with extra steps' — the consistency objective is the contribution, not the perturbation generation. Must clearly show augmentation-only baseline is insufficient.
- Over-claiming generality without testing on held-out perturbation types — the key differentiator from augmentation is transfer to unseen perturbation types, so this MUST be demonstrated.
- Testing only on GSM-level math — this repeats AbstRaL's limitation and loses the competition-math differentiator.
- Ignoring clean accuracy — if MACR degrades unperturbed accuracy by >2 points, reviewers will question practicality.**

## What counts as 'important'

Prioritize (in order):
1. **Best paper awards** at top venues (ACL, EMNLP, NAACL, NeurIPS, ICML, ICLR, AAAI, etc.)
2. **Oral / spotlight presentations** at these venues
3. **Highly cited papers** (>50 citations in 1-2 years)
4. **Papers that introduced widely-adopted methods** (e.g., new training paradigm, new benchmark)
5. **Recent survey papers** that provide comprehensive field overviews
6. **Strong recent work** from top labs (Google, Meta, DeepMind, OpenAI, CMU, Stanford, etc.)

## Search strategy

Execute AT LEAST 15 targeted searches:

1. `best paper award ACL EMNLP NeurIPS ICML ICLR 2026 Target: AAAI 2026
Track: Machine Learning (ML) — Reinforcement Learning / Mathematical Reasoning

Direction: RL-trained mathematical reasoning models exhibit 47-73% accuracy drops under trivial perturbations (numerical substitution, variable renaming) despite achieving SOTA on clean benchmarks. We propose Math-Aware Consistency Regularization (MACR): adding a JS-divergence consistency term between model outputs on original and mathematically-equivalent perturbed problems during GRPO training, with a complementary discrimination loss against surface-similar but semantically different problems. This adapts proven NLP consistency techniques (F²C, PPCL) to mathematical reasoning with math-equivalence-aware perturbation generation and RL integration — a combination no existing work provides.

Seed Papers:
- Mirzadeh et al., GSM-Symbolic (Apple, ICLR 2025) — documents up to 65% accuracy drops from single irrelevant clause; establishes that models pattern-match rather than reason
- VAR-MATH (arXiv 2025) — most damning evidence: 47.9-72.9% drops for RL models on numerically re-parameterized competition math; directly motivates why RL training is the problem
- Gao et al., AbstRaL (ICLR 2026) — only existing training-time intervention; uses abstraction not invariance; limited to GSM-level; our primary comparison baseline
- Flip-Flop Consistency / F²C (arXiv 2024) — JS-divergence consistency for prompt perturbation robustness in NLP; proves the technique works but has never been adapted to math reasoning or RL
- PPCL (EACL 2024) — KL-based consistency regularization recovering 59-69% of perturbation-induced drops in NLU; complementary theoretical grounding
- CSR: Causal Consistency Regularization (arXiv 2025) — enforces causal faithfulness via operator-level interventions during SFT; closest methodological cousin but SFT-only and targets faithfulness not perturbation invariance
- APRM (arXiv 2025) — adversarial PRM training on reasoning errors; shows PRM quality matters for downstream RL; motivates our perturbation-robust PRM extension

Known Gaps:
- No work applies consistency regularization (JS/KL divergence across equivalent problem variants) during RL training for mathematical reasoning — F²C and PPCL remain NLP-only and SFT-only
- No PRM has been trained to be robust to surface-form variations of equivalent problems — APRM addresses reasoning errors, not perturbation invariance
- No training-time robustness intervention has been demonstrated on competition-level math (AIME/Putnam); AbstRaL is GSM-only

Theoretical Anchor: Mathematical equivalence defines a natural invariance class — problems that differ only in surface form (variable names, specific numbers, phrasing) but share identical mathematical structure should produce identical solution distributions. RL training violates this invariance because the reward signal (correct/incorrect final answer) provides no gradient against surface-form-dependent reasoning. A consistency regularization term explicitly penalizes policy divergence across equivalent variants, forcing the model to learn representations that are invariant to mathematically irrelevant features. This is a direct instantiation of Invariant Risk Minimization principles in the RL-for-reasoning setting.

Constraints:
- Compute: ≤200 H100-hours (budget: 40h baseline GRPO + 90h method variants + 30h evaluation + 20h analysis + 20h buffer)
- Models: Primary experiments on 7B (Qwen2.5-Math-7B); scaling verification on 14B
- Evaluation: GSM-Symbolic, GSM-Plus, VAR-MATH (AMC23/AIME24/AIME25), MATH-Perturb; train-time perturbations (numerical substitution, variable renaming) held out from eval perturbations (distractor insertion, structural changes)

Quality Self-Checks:
- [x] Core insight: RL training optimizes for reward on fixed problem forms, creating surface-form dependencies that consistency regularization can break by enforcing invariance across equivalent variants.
- [x] Why not obvious: Consistency regularization is well-known in NLP but requires math-aware equivalence-preserving perturbation generation (not just paraphrase) and RL integration (not just SFT) — two non-trivial adaptations that straddle communities.
- [ ] Baseline fear test: A pure data-augmentation baseline (adding perturbed problems to RL training without consistency loss) could achieve substantial gains. The paper MUST include this baseline and show the consistency term provides additional benefit beyond augmentation. If the gap is <5%, the contribution is weak.
- [x] Information exploited: Mathematical equivalence structure — the method uses symbolic verification that perturbations preserve the problem's mathematical structure, which pure augmentation or paraphrase-based consistency ignores.

Avoid:
- Framing this as 'just data augmentation with extra steps' — the consistency objective is the contribution, not the perturbation generation. Must clearly show augmentation-only baseline is insufficient.
- Over-claiming generality without testing on held-out perturbation types — the key differentiator from augmentation is transfer to unseen perturbation types, so this MUST be demonstrated.
- Testing only on GSM-level math — this repeats AbstRaL's limitation and loses the competition-math differentiator.
- Ignoring clean accuracy — if MACR degrades unperturbed accuracy by >2 points, reviewers will question practicality.`
2. `oral spotlight {venue} 2026 {topic}` — for each major venue
3. `site:openreview.net {topic} 2026 outstanding` — OpenReview 高分论文
4. `{topic} survey 2026` 或 `{topic} survey 2025` — 综述论文
5. `site:arxiv.org {topic} 2026` — arXiv 最新高引
6. `most cited {topic} 2025 2026` — Google Scholar
7. `site:paperswithcode.com {task} SOTA` — SOTA 排行榜上的论文
8. `{topic} benchmark {year}` — 定义领域的 benchmark 论文
9. 对每个找到的重要论文，搜索其 cited-by 发现后续工作

For EVERY paper you find, use WebFetch to read its abstract and introduction on arXiv or OpenReview. Do NOT rely on search snippets alone — you need to understand what each paper actually does.

## Output format

Output a JSON array. Each element:
{
  "title": "Full paper title",
  "authors": "First author et al.",
  "venue": "EMNLP 2025 / NeurIPS 2024 / arXiv 2025 / ...",
  "url": "https://arxiv.org/abs/... or openreview URL",
  "why_important": "Best paper / Oral / High-cited / Introduced X / ...",
  "one_line_summary": "What this paper does in one sentence"
}

Find at least 15 papers. More is better if they are genuinely relevant.
IMPORTANT: You MUST end your response with the JSON array.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": false,
  "promptId": "cb5cc4e3-bd56-445f-9645-e83796f2417f",
  "type": "user",
  "uuid": "06763b89-964f-4ca2-95b4-4ef4baadbf79",
  "permissionMode": "default",
  "userType": "external",
  "entrypoint": "sdk-py",
  "cwd": "/home/ubuntu",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b",
  "version": "2.1.142",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 4 · 2026-05-28T10:15:47.040Z_

```json
{
  "parentUuid": "06763b89-964f-4ca2-95b4-4ef4baadbf79",
  "isSidechain": false,
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "NotebookEdit",
      "ScheduleWakeup",
      "TaskCreate",
      "TaskGet",
      "TaskList",
      "TaskOutput",
      "TaskStop",
      "TaskUpdate",
      "WebFetch",
      "WebSearch"
    ],
    "addedLines": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterPlanMode",
      "EnterWorktree",
      "ExitPlanMode",
      "ExitWorktree",
      "NotebookEdit",
      "ScheduleWakeup",
      "TaskCreate",
      "TaskGet",
      "TaskList",
      "TaskOutput",
      "TaskStop",
      "TaskUpdate",
      "WebFetch",
      "WebSearch"
    ],
    "removedNames": [],
    "readdedNames": [],
    "pendingMcpServers": []
  },
  "type": "attachment",
  "uuid": "7460dc68-09a9-461e-acb7-0a37dc68be99",
  "timestamp": "2026-05-28T10:15:47.040Z",
  "userType": "external",
  "entrypoint": "sdk-py",
  "cwd": "/home/ubuntu",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b",
  "version": "2.1.142",
  "gitBranch": "HEAD"
}
```

---

### Runtime record

_source line 5 · 2026-05-28T10:15:47.040Z_

```json
{
  "parentUuid": "7460dc68-09a9-461e-acb7-0a37dc68be99",
  "isSidechain": false,
  "attachment": {
    "type": "skill_listing",
    "content": "- update-config: Use this skill to configure the Claude Code harness via settings.json. Automated behaviors (\"from now on when X\", \"each time X\", \"whenever X\", \"before/after X\") require hooks configured in settings.json - the harness executes these, not Claude, so memory/preferences cannot fulfill them. Also use for: permissions (\"allow X\", \"add permission\", \"move permission to\"), env vars (\"set X=Y\"), hook troubleshooting, or any changes to settings.json/settings.local.json files. Examples: \"allow npm commands\", \"add bq permission to global settings\", \"move permission to user settings\", \"set DEBUG=true\", \"when claude stops show X\". For simple settings like theme/model, suggest the /config command.\n- keybindings-help: Use when the user wants to customize keyboard shortcuts, rebind keys, add chord bindings, or modify ~/.claude/keybindings.json. Examples: \"rebind ctrl+s\", \"add a chord shortcut\", \"change the submit key\", \"customize keybindings\".\n- simplify: Review changed code for reuse, quality, and efficiency, then fix any issues found.\n- fewer-permission-prompts: Scan your transcripts for common read-only Bash and MCP tool calls, then add a prioritized allowlist to project .claude/settings.json to reduce permission prompts.\n- loop: Run a prompt or slash command on a recurring interval (e.g. /loop 5m /foo, defaults to 10m) - When the user wants to set up a recurring task, poll for status, or run something repeatedly on an interval (e.g. \"check the deploy every 5 minutes\", \"keep running /babysit-prs\"). Do NOT invoke for one-off tasks.\n- claude-api: Build, debug, and optimize Claude API / Anthropic SDK apps. Apps built with this skill should include prompt caching. Also handles migrating existing Claude API code between Claude model versions (4.5 → 4.6, 4.6 → 4.7, retired-model replacements).\nTRIGGER when: code imports `anthropic`/`@anthropic-ai/sdk`; user asks for the Claude API, Anthropic SDK, or Managed Agents; user adds/modifies/tunes a Claude feature (caching, thinking, compaction, tool use, batch, files, citations, memory) or model (Opus/Sonnet/Haiku) in a file; questions about prompt caching / cache hit rate in an Anthropic SDK project.\nSKIP: file imports `openai`/other-provider SDK, filename like `*-openai.py`/`*-generic.py`, provider-neutral code, general programming/ML.\n- init: Initialize a new CLAUDE.md file with codebase documentation\n- review: Review a pull request\n- security-review: Complete a security review of the pending changes on the current branch",
    "skillCount": 9,
    "isInitial": true
  },
  "type": "attachment",
  "uuid": "bbe672fd-5d2b-446a-9c27-52a81444d029",
  "timestamp": "2026-05-28T10:15:47.040Z",
  "userType": "external",
  "entrypoint": "sdk-py",
  "cwd": "/home/ubuntu",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b",
  "version": "2.1.142",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 6 · 2026-05-28T10:15:47.221Z_

Not logged in · Please run /login

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bbe672fd-5d2b-446a-9c27-52a81444d029",
  "isSidechain": false,
  "type": "assistant",
  "uuid": "574760f3-3873-4c9e-bcda-aa8d49890791",
  "error": "authentication_failed",
  "isApiErrorMessage": true,
  "userType": "external",
  "entrypoint": "sdk-py",
  "cwd": "/home/ubuntu",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b",
  "version": "2.1.142",
  "gitBranch": "HEAD",
  "message": {
    "id": "ca941482-6893-4e80-a926-319f0c48248b",
    "container": null,
    "model": "&lt;synthetic>",
    "stop_details": null,
    "stop_reason": "stop_sequence",
    "stop_sequence": "",
    "type": "message",
    "usage": {
      "input_tokens": 0,
      "output_tokens": 0,
      "cache_creation_input_tokens": 0,
      "cache_read_input_tokens": 0,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": null,
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 0
      },
      "inference_geo": null,
      "iterations": null,
      "speed": null
    },
    "context_management": null
  }
}
```

</details>

---

### Runtime record

_source line 7_

```json
{
  "type": "last-prompt",
  "lastPrompt": "You are a senior ML researcher conducting a comprehensive literature survey.  **Today's date: 2026-05-28 (UTC).**  ## Task Find the **15 most important recent papers** (published 2024–2026) in or clos…",
  "leafUuid": "574760f3-3873-4c9e-bcda-aa8d49890791",
  "sessionId": "95f2d884-f8fc-4541-be38-76f305c7e49b"
}
```

---
