# analysis d072 paper patch inventory

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 0
- **Tool calls:** 24
- **Original source:** `logs/workers/worker_analysis_d072_paper_patch_inventory_20260515T113312.log`
- **Structured JSON:** [`77c9df73ad80264da3a6.json`](../../sessions/77/77c9df73ad80264da3a6.json)

## Before a recorded user message

61 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie",
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__update_registry"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "f12f528e-3eb1-4d3e-ae2a-bf13362b2167",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778854800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "f81a3177-159f-406a-8777-a161b8791cb9",
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced"
}
```

---

### Assistant

_source line 4_

I'll read all the required files in parallel to build the inventory.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "d020edbc-bb08-40a2-a8f2-565d7ab98188",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01HwiLEsdo6QsHDA4JQodGFT`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_results.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "1dcddcc1-6c48-490d-b11b-dc128b9a2467",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-15T11:33:24.098Z_

<details><summary>↩ Tool result · `toolu_01HwiLEsdo6QsHDA4JQodGFT`</summary>

```text
1	# Free-form vs Constrained Decoding Ablation (Qwen SciERC N=8)
2	
3	**Date**: 2026-05-15
4	**Constrained baseline**: exp_012_rerun_1024 (551 instances × 8 samples)
5	**Free-form**: exp_freeform_ablation (551 instances × 8 samples, 4408 total)
6	
7	---
8	
9	## 1. Logprob Distribution Comparison
10	
11	| Metric | Constrained | Free-form | Ratio (F/C) |
12	|--------|------------|-----------|-------------|
13	| Mean LP std | 0.0206 | 0.0199 | 0.97x |
14	| Median LP std | 0.0136 | 0.0137 | 1.01x |
15	| Mean LP range | 0.0623 | 0.0599 | 0.96x |
16	| Median LP range | 0.0413 | 0.0418 | 1.01x |
17	| Tied fraction (ε=0.05) | 59.7% | 57.7% | -2.0pp |
18	| N instances | 551 | 551 | — |
19	
20	## 2. Selection F1
21	
22	### NER
23	
24	| Method | Constrained | Free-form |
25	|--------|------------|-----------|
26	| Greedy F1 | 0.6182 | 0.6204 |
27	| LP-selected F1 | 0.6241 | 0.6222 |
28	| Selection gap | +0.0059 | +0.0018 |
29	
30	### RE
31	
32	| Method | Constrained | Free-form |
33	|--------|------------|-----------|
34	| Greedy F1 | 0.2913 | 0.2880 |
35	| LP-selected F1 | 0.2845 | 0.3050 |
36	| Selection gap | -0.0068 | +0.0169 |
37	
38	## 3. QE Signals: Spearman ρ and AUROC
39	
40	### NER (n=529)
41	
42	| Signal | C_ρ | C_AUROC | F_ρ | F_AUROC | Δρ |
43	|--------|-----|---------|-----|---------|-----|
44	| SJ | 0.3599 | 0.7180 | 0.3774 | 0.7463 | +0.0175 |
45	| FK | 0.2665 | 0.7478 | 0.3197 | 0.7621 | +0.0532 |
46	| LP | 0.2052 | 0.6548 | 0.2129 | 0.6984 | +0.0077 |
47	| EM | 0.2945 | 0.4998 | 0.3171 | 0.5190 | +0.0225 |
48	| VC | 0.3792 | 0.7721 | 0.4089 | 0.7958 | +0.0297 |
49	
50	### RE (n=397)
51	
52	| Signal | C_ρ | C_AUROC | F_ρ | F_AUROC | Δρ |
53	|--------|-----|---------|-----|---------|-----|
54	| SJ | 0.2503 | 0.6099 | 0.2728 | 0.6173 | +0.0225 |
55	| FK | 0.2752 | 0.6638 | 0.3145 | 0.6837 | +0.0393 |
56	| LP | 0.2662 | 0.6780 | 0.3042 | 0.7025 | +0.0379 |
57	| EM | 0.1344 | 0.4886 | 0.1367 | 0.4877 | +0.0024 |
58	| VC | 0.3498 | 0.6820 | 0.3234 | 0.6553 | -0.0263 |
59	
60	## 4. Parse Rate Statistics
61	
62	| Metric | Value |
63	|--------|-------|
64	| Total samples | 4408 |
65	| Successfully parsed | 4406 |
66	| Parse rate | 99.95% |
67	| 8/8 valid instances | 549 (99.6%) |
68	| 7/8 valid instances | 2 (0.4%) |
69	| Total failed samples | 2 |
70	
71	## 5. Key Findings
72	
73	1. **Score compression hypothesis NOT confirmed**: Free-form LP variance is virtually identical to constrained (ratio 0.97x for std, 0.96x for range). Removing constrained decoding did NOT meaningfully increase logprob spread. The tied fraction decreased by only 2.0pp (59.7% → 57.7%). This suggests logprob compression is intrinsic to the model/task, not an artifact of constrained decoding.
74	
75	2. **QE signals uniformly improve under free-form** (except RE voting_conf): All 5 signals show higher ρ in NER (+0.0077 to +0.0532). In RE, 4 of 5 signals improve (+0.0024 to +0.0393), with only VC declining (-0.0263). FK shows the largest consistent gains (NER +0.0532, RE +0.0393).
76	
77	3. **LP selection shows divergent behavior by subtask**: NER selection gain shrinks from +0.0059 (constrained) to +0.0018 (free-form). RE selection flips from negative (-0.0068) to strongly positive (+0.0169). Free-form enables effective LP-based selection for RE where constrained decoding failed.
78	
79	4. **Near-perfect parse rate (99.95%)**: Only 2 of 4408 samples failed parsing, and 549/551 instances (99.6%) have all 8 samples valid. Free-form decoding with Qwen on SciERC is highly reliable — constrained decoding is not needed for format compliance.
80	
81	5. **Greedy F1 is comparable across conditions**: NER greedy F1 differs by only 0.0022 (0.6182 vs 0.6204) and RE by 0.0033 (0.2913 vs 0.2880), confirming the comparison is apples-to-apples on a well-matched task difficulty.
82	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "02742fd4-c239-4697-bffc-0492957d3214",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_results.md",
      "content": "# Free-form vs Constrained Decoding Ablation (Qwen SciERC N=8)\n\n**Date**: 2026-05-15\n**Constrained baseline**: exp_012_rerun_1024 (551 instances × 8 samples)\n**Free-form**: exp_freeform_ablation (551 instances × 8 samples, 4408 total)\n\n---\n\n## 1. Logprob Distribution Comparison\n\n| Metric | Constrained | Free-form | Ratio (F/C) |\n|--------|------------|-----------|-------------|\n| Mean LP std | 0.0206 | 0.0199 | 0.97x |\n| Median LP std | 0.0136 | 0.0137 | 1.01x |\n| Mean LP range | 0.0623 | 0.0599 | 0.96x |\n| Median LP range | 0.0413 | 0.0418 | 1.01x |\n| Tied fraction (ε=0.05) | 59.7% | 57.7% | -2.0pp |\n| N instances | 551 | 551 | — |\n\n## 2. Selection F1\n\n### NER\n\n| Method | Constrained | Free-form |\n|--------|------------|-----------|\n| Greedy F1 | 0.6182 | 0.6204 |\n| LP-selected F1 | 0.6241 | 0.6222 |\n| Selection gap | +0.0059 | +0.0018 |\n\n### RE\n\n| Method | Constrained | Free-form |\n|--------|------------|-----------|\n| Greedy F1 | 0.2913 | 0.2880 |\n| LP-selected F1 | 0.2845 | 0.3050 |\n| Selection gap | -0.0068 | +0.0169 |\n\n## 3. QE Signals: Spearman ρ and AUROC\n\n### NER (n=529)\n\n| Signal | C_ρ | C_AUROC | F_ρ | F_AUROC | Δρ |\n|--------|-----|---------|-----|---------|-----|\n| SJ | 0.3599 | 0.7180 | 0.3774 | 0.7463 | +0.0175 |\n| FK | 0.2665 | 0.7478 | 0.3197 | 0.7621 | +0.0532 |\n| LP | 0.2052 | 0.6548 | 0.2129 | 0.6984 | +0.0077 |\n| EM | 0.2945 | 0.4998 | 0.3171 | 0.5190 | +0.0225 |\n| VC | 0.3792 | 0.7721 | 0.4089 | 0.7958 | +0.0297 |\n\n### RE (n=397)\n\n| Signal | C_ρ | C_AUROC | F_ρ | F_AUROC | Δρ |\n|--------|-----|---------|-----|---------|-----|\n| SJ | 0.2503 | 0.6099 | 0.2728 | 0.6173 | +0.0225 |\n| FK | 0.2752 | 0.6638 | 0.3145 | 0.6837 | +0.0393 |\n| LP | 0.2662 | 0.6780 | 0.3042 | 0.7025 | +0.0379 |\n| EM | 0.1344 | 0.4886 | 0.1367 | 0.4877 | +0.0024 |\n| VC | 0.3498 | 0.6820 | 0.3234 | 0.6553 | -0.0263 |\n\n## 4. Parse Rate Statistics\n\n| Metric | Value |\n|--------|-------|\n| Total samples | 4408 |\n| Successfully parsed | 4406 |\n| Parse rate | 99.95% |\n| 8/8 valid instances | 549 (99.6%) |\n| 7/8 valid instances | 2 (0.4%) |\n| Total failed samples | 2 |\n\n## 5. Key Findings\n\n1. **Score compression hypothesis NOT confirmed**: Free-form LP variance is virtually identical to constrained (ratio 0.97x for std, 0.96x for range). Removing constrained decoding did NOT meaningfully increase logprob spread. The tied fraction decreased by only 2.0pp (59.7% → 57.7%). This suggests logprob compression is intrinsic to the model/task, not an artifact of constrained decoding.\n\n2. **QE signals uniformly improve under free-form** (except RE voting_conf): All 5 signals show higher ρ in NER (+0.0077 to +0.0532). In RE, 4 of 5 signals improve (+0.0024 to +0.0393), with only VC declining (-0.0263). FK shows the largest consistent gains (NER +0.0532, RE +0.0393).\n\n3. **LP selection shows divergent behavior by subtask**: NER selection gain shrinks from +0.0059 (constrained) to +0.0018 (free-form). RE selection flips from negative (-0.0068) to strongly positive (+0.0169). Free-form enables effective LP-based selection for RE where constrained decoding failed.\n\n4. **Near-perfect parse rate (99.95%)**: Only 2 of 4408 samples failed parsing, and 549/551 instances (99.6%) have all 8 samples valid. Free-form decoding with Qwen on SciERC is highly reliable — constrained decoding is not needed for format compliance.\n\n5. **Greedy F1 is comparable across conditions**: NER greedy F1 differs by only 0.0022 (0.6182 vs 0.6204) and RE by 0.0033 (0.2913 vs 0.2880), confirming the comparison is apples-to-apples on a well-matched task difficulty.\n",
      "numLines": 82,
      "startLine": 1,
      "totalLines": 82
    }
  }
}
```

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_01SbAf2hKbTddde7xRV6x7QK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_deep_analysis.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "af3d5bc9-76b5-4025-8b69-d693308a498b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-15T11:33:24.416Z_

<details><summary>↩ Tool result · `toolu_01SbAf2hKbTddde7xRV6x7QK`</summary>

```text
1	# Free-form vs Constrained Decoding: Deep Ablation Analysis
2	
3	**Setup**: 551 instances × 8 samples, Qwen3-8B, SciERC, seed=42, T=1.0, max_tokens=1024.
4	- Constrained: `exp_012_rerun_1024/samples.jsonl`
5	- Free-form: `exp_freeform_ablation/samples.jsonl`
6	
7	---
8	
9	## 1. RE LP Selection Flip
10	
11	**Phenomenon**: LP selection gap for RE flips from -0.68pp (constrained) to +1.69pp (free-form).
12	
13	### 1.1 Per Relation Type Breakdown
14	
15	| Relation Type | N instances | Constrained Gap | Free-form Gap | Δ (flip) |
16	|:---|---:|---:|---:|---:|
17	| USED-FOR | 299 | -1.41% | +2.42% | +3.83% |
18	| CONJUNCTION | 86 | -0.81% | +1.65% | +2.46% |
19	| EVALUATE-FOR | 62 | -1.61% | +0.07% | +1.68% |
20	| FEATURE-OF | 50 | -0.86% | +0.50% | +1.36% |
21	| PART-OF | 44 | -4.51% | +2.01% | **+6.52%** |
22	| HYPONYM-OF | 36 | -3.12% | +1.34% | +4.45% |
23	| COMPARE | 35 | -1.36% | +0.12% | +1.48% |
24	
25	**Interpretation**: The flip is **universal** — all 7 relation types show negative constrained gap and positive (or neutral) free-form gap. This rules out the hypothesis that a single dominant relation type drives the effect. The largest flips occur on PART-OF (+6.52pp) and HYPONYM-OF (+4.45pp), both of which are semantically subtle types requiring precise entity boundary identification. USED-FOR, the most frequent type (54% of instances with relations), contributes the largest absolute mass (+3.83pp × 299 instances).
26	
27	### 1.2 LP–F1 Correlation by Subtask
28	
29	| Condition | NER ρ | NER p | RE ρ | RE p |
30	|:---|---:|---:|---:|---:|
31	| Constrained | 0.171 | 5.24e-05 | 0.318 | 1.88e-14 |
32	| Free-form | 0.189 | 8.09e-06 | 0.301 | 4.83e-13 |
33	
34	**Interpretation**: The Spearman ρ between LP-selected sample's mean logprob and F1 is actually slightly *lower* for RE in free-form (0.301 vs 0.318). This means the flip is **not** due to improved LP–quality correlation overall, but rather to a change in the *distribution* of errors: in constrained mode LP selection is systematically biased toward wrong RE answers, while in free-form this bias disappears.
35	
36	### 1.3 LP Variance Structure
37	
38	| Metric | Constrained | Free-form |
39	|:---|---:|---:|
40	| Mean LP std | 0.0206 | 0.0199 |
41	| Mean LP range | 0.0623 | 0.0599 |
42	| LP_std ↔ NER F1 range (ρ) | +0.329 | +0.337 |
43	| LP_std ↔ RE F1 range (ρ) | **-0.131** | **-0.152** |
44	
45	**Interpretation**: A critical asymmetry: LP variance positively correlates with NER F1 range (when LP varies more, NER quality varies more — so LP can select) but **negatively** correlates with RE F1 range. This means instances where RE quality varies most across samples tend to have *compressed* LP variance, making LP selection near-random for RE. Free-form slightly amplifies this negative correlation (-0.152 vs -0.131), but the key difference lies in *where* the variance is allocated (see §1.5).
46	
47	### 1.4 Instance-Level Flip Analysis
48	
49	31 instances flip from "constrained LP wrong" to "free-form LP right" (5.6% of 551).
50	
51	| Characteristic | Flip Instances (N=31) | Other Instances (N=520) | Baseline (N=551) |
52	|:---|---:|---:|---:|
53	| Mean gold relations | **3.3** | 1.7 | 1.8 |
54	| Mean gold entities | **4.6** | 3.0 | 3.1 |
55	| Mean LP std (constrained) | 0.0162 | 0.0209 | 0.0206 |
56	| Mean LP std (free-form) | 0.0182 | 0.0200 | 0.0199 |
57	| Mean LP range (constrained) | 0.0496 | 0.0631 | 0.0623 |
58	| Mean LP range (free-form) | 0.0564 | 0.0601 | 0.0599 |
59	| NER F1 of LP-sel (constrained) | 0.662 | — | — |
60	| NER F1 of LP-sel (free-form) | **0.763** | — | — |
61	
62	Relation type distribution among flip instances: USED-FOR (25), PART-OF (8), CONJUNCTION (7), FEATURE-OF (6), EVALUATE-FOR (6), COMPARE (4), HYPONYM-OF (4).
63	
64	**Interpretation**: Flip instances are **relation-dense** (3.3 gold rels, nearly 2× baseline) but have **low LP variance** in constrained mode (0.0162 vs 0.0209 for others). The constrained format forces structurally similar outputs on these complex instances, compressing LP spread and making selection near-random. Free-form relaxes this constraint: LP variance increases from 0.0162 to 0.0182 (+12%), and more importantly, the NER F1 of the LP-selected sample jumps from 0.662 to 0.763, suggesting free-form LP preferentially selects samples with better entity boundaries, which cascades into better RE.
65	
66	### 1.5 Hypothesis Test: LP Variance × RE Difficulty
67	
68	Instances split at median greedy RE F1 (0.400).
69	
70	| Group | N | Constrained LP std | Free-form LP std | F/C Ratio |
71	|:---|---:|---:|---:|---:|
72	| RE-difficult (F1 < 0.40) | 194 | 0.0185 | 0.0196 | **1.06** |
73	| RE-easy (F1 ≥ 0.40) | 203 | 0.0159 | 0.0136 | **0.86** |
74	
75	Mann-Whitney U tests (one-sided: difficult > easy):
76	- Free-form: U = 24269, **p < 0.0001**
77	- Constrained: U = 22720, p = 0.0040
78	
79	**Interpretation**: Free-form decoding **selectively amplifies** LP variance on RE-difficult instances (ratio 1.06) while **dampening** it on RE-easy instances (ratio 0.86). Constrained decoding also shows this pattern but less pronounced (both groups have moderately different variance, p = 0.004). The selective amplification in free-form means difficult instances get more LP spread — and thus more discriminative power for LP selection — exactly where it matters most.
80	
81	### 1.6 LP Selection Win/Loss Balance
82	
83	| Condition | Correct (LP > greedy) | Wrong (LP < greedy) | Tied | Net |
84	|:---|---:|---:|---:|---:|
85	| Constrained | 36 (9.1%) | 59 (14.9%) | 302 | **-23** |
86	| Free-form | 45 (11.3%) | 45 (11.3%) | 307 | **0** |
87	
88	(Only instances with ≥1 gold relation, N=397)
89	
90	**Interpretation**: The asymmetry in constrained mode (23 more wrong than correct) is the direct cause of the -0.68pp gap. Free-form brings the win/loss ratio to parity (45:45), which — combined with the fact that correct instances tend to have larger F1 deltas than wrong instances — produces the +1.69pp gap. The mechanism: constrained decoding creates a systematic bias where higher-LP samples tend to be ones that copied more entity tokens verbatim (higher NER logprob) but failed at relation typing; free-form breaks this coupling.
91	
92	---
93	
94	## 2. Non-Tied Subset Overlap
95	
96	**Phenomenon**: Constrained tied fraction = 59.7%, free-form = 57.7% (only -2pp). But does the non-tied set composition change?
97	
98	### 2.1 Set Overlap Statistics
99	
100	| Metric | Value |
101	|:---|---:|
102	| Constrained non-tied | 222 (40.3%) |
103	| Free-form non-tied | 233 (42.3%) |
104	| Intersection (both non-tied) | 146 |
105	| Union (either non-tied) | 309 |
106	| **Jaccard similarity** | **0.472** |
107	| New non-tied in free-form | 87 |
108	| Lost non-tied in free-form | 76 |
109	
110	**Interpretation**: Despite near-identical tied fractions, the Jaccard similarity is only 0.472 — meaning the non-tied sets share less than half their members. 87 instances become non-tied in free-form (were tied in constrained), and 76 go the other way. This is a **substantial reshuffling**: ~38% of the union consists of instances that are non-tied in only one condition.
111	
112	### 2.2 New Non-Tied Instances (Free-form Non-Tied, Constrained Tied)
113	
114	N = 87 instances that gain LP discrimination under free-form.
115	
116	| Characteristic | New Non-Tied (N=87) | Lost Non-Tied (N=76) | Baseline (N=551) |
117	|:---|---:|---:|---:|
118	| Mean gold relations | 1.7 | 1.3 | 1.8 |
119	| Mean gold entities | 2.8 | 2.6 | 3.1 |
120	| % with relations | 71.3% | 64.5% | 72.1% |
121	| Mean LP range (constrained) | 0.0321 | 0.1108 | 0.0623 |
122	| Mean LP range (free-form) | **0.0978** | 0.0314 | 0.0599 |
123	| Mean greedy NER F1 | 0.631 | 0.607 | 0.618 |
124	| Mean greedy RE F1 | 0.417 | 0.406 | — |
125	| Mean output tokens (constrained) | 186 | 164 | — |
126	| Mean output tokens (free-form) | 168 | 175 | — |
127	| Mean input text length | 146 | 137 | — |
128	
129	**Interpretation**: New non-tied instances had very tight LP ranges under constrained decoding (0.0321, barely above the 0.05 threshold — actually below it, hence tied). Free-form triples their LP range to 0.0978. These tend to be moderate-complexity instances (1.7 rels, 2.8 ents) that are slightly longer than lost instances. The constrained format apparently homogenized their outputs, but free-form allows enough structural variation to create LP discrimination.
130	
131	### 2.3 Lost Non-Tied Instances (Constrained Non-Tied, Free-form Tied)
132	
133	N = 76 instances that lose LP discrimination under free-form.
134	
135	These instances had the **highest** LP ranges in constrained mode (0.1108, nearly 2× baseline). In free-form, their LP range collapses to 0.0314. They tend to be simpler instances (1.3 rels, 2.6 ents, shorter text). The constrained format's structural rigidity apparently amplified small differences in these simple cases (e.g., missing/adding a single entity changes token count significantly), but free-form's flexibility allows the model to express the same content with different phrasings that have similar logprobs.
136	
137	### 2.4 LP Range Cross-Condition Correlation
138	
139	| Metric | Value |
140	|:---|---:|
141	| Spearman ρ (per-instance LP range) | 0.488 |
142	| p-value | 2.95e-34 |
143	| Mean LP range (constrained) | 0.0623 |
144	| Mean LP range (free-form) | 0.0599 |
145	
146	**Interpretation**: Moderate positive correlation (ρ = 0.488) — instances with high LP range in one condition tend to have high range in the other, but with substantial scatter. The 0.488 is consistent with roughly 24% shared variance in LP range, meaning ~76% of the variance in which instances are "discriminable" is condition-specific. This confirms the reshuffling finding: the two decoding modes expose different aspects of instance difficulty.
147	
148	---
149	
150	## Summary: Key Takeaways
151	
152	1. **The RE LP selection flip is universal across all 7 SciERC relation types**, with the largest flips on semantically subtle types (PART-OF +6.52pp, HYPONYM-OF +4.45pp). No single type drives the effect.
153	
154	2. **Free-form decoding selectively reallocates LP variance**: it amplifies variance on RE-difficult instances (ratio 1.06, p < 0.0001) and dampens it on RE-easy instances (ratio 0.86). This gives LP selection more discriminative power exactly where RE quality varies most.
155	
156	3. **The constrained format creates a systematic LP selection bias for RE**: in constrained mode, LP selection is wrong more often than right (14.9% vs 9.1%), producing a net -23 instances. Free-form equalizes this to 45:45, flipping the aggregate gap from -0.68pp to +1.69pp. The mechanism is likely that constrained decoding rewards verbatim entity token copying (boosting logprobs) while penalizing relation-type experimentation.
157	
158	4. **Despite near-identical tied fractions (59.7% vs 57.7%), free-form fundamentally reshuffles which instances are discriminable** (Jaccard = 0.472). 87 instances gain LP discrimination (LP range triples from 0.032 to 0.098) while 76 lose it (range collapses from 0.111 to 0.031). Only 24% of LP range variance is shared between conditions.
159	
160	5. **The flip instances are relation-dense** (3.3 gold rels, 2× baseline) with suppressed LP variance in constrained mode. Free-form relaxes structural constraints, allowing these complex instances to produce more varied — and more informatively varied — outputs, enabling LP to select samples with better entity boundaries that cascade into better RE.
161	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "769afa6c-5862-406d-8118-e201f77860a1",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_deep_analysis.md",
      "content": "# Free-form vs Constrained Decoding: Deep Ablation Analysis\n\n**Setup**: 551 instances × 8 samples, Qwen3-8B, SciERC, seed=42, T=1.0, max_tokens=1024.\n- Constrained: `exp_012_rerun_1024/samples.jsonl`\n- Free-form: `exp_freeform_ablation/samples.jsonl`\n\n---\n\n## 1. RE LP Selection Flip\n\n**Phenomenon**: LP selection gap for RE flips from -0.68pp (constrained) to +1.69pp (free-form).\n\n### 1.1 Per Relation Type Breakdown\n\n| Relation Type | N instances | Constrained Gap | Free-form Gap | Δ (flip) |\n|:---|---:|---:|---:|---:|\n| USED-FOR | 299 | -1.41% | +2.42% | +3.83% |\n| CONJUNCTION | 86 | -0.81% | +1.65% | +2.46% |\n| EVALUATE-FOR | 62 | -1.61% | +0.07% | +1.68% |\n| FEATURE-OF | 50 | -0.86% | +0.50% | +1.36% |\n| PART-OF | 44 | -4.51% | +2.01% | **+6.52%** |\n| HYPONYM-OF | 36 | -3.12% | +1.34% | +4.45% |\n| COMPARE | 35 | -1.36% | +0.12% | +1.48% |\n\n**Interpretation**: The flip is **universal** — all 7 relation types show negative constrained gap and positive (or neutral) free-form gap. This rules out the hypothesis that a single dominant relation type drives the effect. The largest flips occur on PART-OF (+6.52pp) and HYPONYM-OF (+4.45pp), both of which are semantically subtle types requiring precise entity boundary identification. USED-FOR, the most frequent type (54% of instances with relations), contributes the largest absolute mass (+3.83pp × 299 instances).\n\n### 1.2 LP–F1 Correlation by Subtask\n\n| Condition | NER ρ | NER p | RE ρ | RE p |\n|:---|---:|---:|---:|---:|\n| Constrained | 0.171 | 5.24e-05 | 0.318 | 1.88e-14 |\n| Free-form | 0.189 | 8.09e-06 | 0.301 | 4.83e-13 |\n\n**Interpretation**: The Spearman ρ between LP-selected sample's mean logprob and F1 is actually slightly *lower* for RE in free-form (0.301 vs 0.318). This means the flip is **not** due to improved LP–quality correlation overall, but rather to a change in the *distribution* of errors: in constrained mode LP selection is systematically biased toward wrong RE answers, while in free-form this bias disappears.\n\n### 1.3 LP Variance Structure\n\n| Metric | Constrained | Free-form |\n|:---|---:|---:|\n| Mean LP std | 0.0206 | 0.0199 |\n| Mean LP range | 0.0623 | 0.0599 |\n| LP_std ↔ NER F1 range (ρ) | +0.329 | +0.337 |\n| LP_std ↔ RE F1 range (ρ) | **-0.131** | **-0.152** |\n\n**Interpretation**: A critical asymmetry: LP variance positively correlates with NER F1 range (when LP varies more, NER quality varies more — so LP can select) but **negatively** correlates with RE F1 range. This means instances where RE quality varies most across samples tend to have *compressed* LP variance, making LP selection near-random for RE. Free-form slightly amplifies this negative correlation (-0.152 vs -0.131), but the key difference lies in *where* the variance is allocated (see §1.5).\n\n### 1.4 Instance-Level Flip Analysis\n\n31 instances flip from \"constrained LP wrong\" to \"free-form LP right\" (5.6% of 551).\n\n| Characteristic | Flip Instances (N=31) | Other Instances (N=520) | Baseline (N=551) |\n|:---|---:|---:|---:|\n| Mean gold relations | **3.3** | 1.7 | 1.8 |\n| Mean gold entities | **4.6** | 3.0 | 3.1 |\n| Mean LP std (constrained) | 0.0162 | 0.0209 | 0.0206 |\n| Mean LP std (free-form) | 0.0182 | 0.0200 | 0.0199 |\n| Mean LP range (constrained) | 0.0496 | 0.0631 | 0.0623 |\n| Mean LP range (free-form) | 0.0564 | 0.0601 | 0.0599 |\n| NER F1 of LP-sel (constrained) | 0.662 | — | — |\n| NER F1 of LP-sel (free-form) | **0.763** | — | — |\n\nRelation type distribution among flip instances: USED-FOR (25), PART-OF (8), CONJUNCTION (7), FEATURE-OF (6), EVALUATE-FOR (6), COMPARE (4), HYPONYM-OF (4).\n\n**Interpretation**: Flip instances are **relation-dense** (3.3 gold rels, nearly 2× baseline) but have **low LP variance** in constrained mode (0.0162 vs 0.0209 for others). The constrained format forces structurally similar outputs on these complex instances, compressing LP spread and making selection near-random. Free-form relaxes this constraint: LP variance increases from 0.0162 to 0.0182 (+12%), and more importantly, the NER F1 of the LP-selected sample jumps from 0.662 to 0.763, suggesting free-form LP preferentially selects samples with better entity boundaries, which cascades into better RE.\n\n### 1.5 Hypothesis Test: LP Variance × RE Difficulty\n\nInstances split at median greedy RE F1 (0.400).\n\n| Group | N | Constrained LP std | Free-form LP std | F/C Ratio |\n|:---|---:|---:|---:|---:|\n| RE-difficult (F1 < 0.40) | 194 | 0.0185 | 0.0196 | **1.06** |\n| RE-easy (F1 ≥ 0.40) | 203 | 0.0159 | 0.0136 | **0.86** |\n\nMann-Whitney U tests (one-sided: difficult > easy):\n- Free-form: U = 24269, **p < 0.0001**\n- Constrained: U = 22720, p = 0.0040\n\n**Interpretation**: Free-form decoding **selectively amplifies** LP variance on RE-difficult instances (ratio 1.06) while **dampening** it on RE-easy instances (ratio 0.86). Constrained decoding also shows this pattern but less pronounced (both groups have moderately different variance, p = 0.004). The selective amplification in free-form means difficult instances get more LP spread — and thus more discriminative power for LP selection — exactly where it matters most.\n\n### 1.6 LP Selection Win/Loss Balance\n\n| Condition | Correct (LP > greedy) | Wrong (LP < greedy) | Tied | Net |\n|:---|---:|---:|---:|---:|\n| Constrained | 36 (9.1%) | 59 (14.9%) | 302 | **-23** |\n| Free-form | 45 (11.3%) | 45 (11.3%) | 307 | **0** |\n\n(Only instances with ≥1 gold relation, N=397)\n\n**Interpretation**: The asymmetry in constrained mode (23 more wrong than correct) is the direct cause of the -0.68pp gap. Free-form brings the win/loss ratio to parity (45:45), which — combined with the fact that correct instances tend to have larger F1 deltas than wrong instances — produces the +1.69pp gap. The mechanism: constrained decoding creates a systematic bias where higher-LP samples tend to be ones that copied more entity tokens verbatim (higher NER logprob) but failed at relation typing; free-form breaks this coupling.\n\n---\n\n## 2. Non-Tied Subset Overlap\n\n**Phenomenon**: Constrained tied fraction = 59.7%, free-form = 57.7% (only -2pp). But does the non-tied set composition change?\n\n### 2.1 Set Overlap Statistics\n\n| Metric | Value |\n|:---|---:|\n| Constrained non-tied | 222 (40.3%) |\n| Free-form non-tied | 233 (42.3%) |\n| Intersection (both non-tied) | 146 |\n| Union (either non-tied) | 309 |\n| **Jaccard similarity** | **0.472** |\n| New non-tied in free-form | 87 |\n| Lost non-tied in free-form | 76 |\n\n**Interpretation**: Despite near-identical tied fractions, the Jaccard similarity is only 0.472 — meaning the non-tied sets share less than half their members. 87 instances become non-tied in free-form (were tied in constrained), and 76 go the other way. This is a **substantial reshuffling**: ~38% of the union consists of instances that are non-tied in only one condition.\n\n### 2.2 New Non-Tied Instances (Free-form Non-Tied, Constrained Tied)\n\nN = 87 instances that gain LP discrimination under free-form.\n\n| Characteristic | New Non-Tied (N=87) | Lost Non-Tied (N=76) | Baseline (N=551) |\n|:---|---:|---:|---:|\n| Mean gold relations | 1.7 | 1.3 | 1.8 |\n| Mean gold entities | 2.8 | 2.6 | 3.1 |\n| % with relations | 71.3% | 64.5% | 72.1% |\n| Mean LP range (constrained) | 0.0321 | 0.1108 | 0.0623 |\n| Mean LP range (free-form) | **0.0978** | 0.0314 | 0.0599 |\n| Mean greedy NER F1 | 0.631 | 0.607 | 0.618 |\n| Mean greedy RE F1 | 0.417 | 0.406 | — |\n| Mean output tokens (constrained) | 186 | 164 | — |\n| Mean output tokens (free-form) | 168 | 175 | — |\n| Mean input text length | 146 | 137 | — |\n\n**Interpretation**: New non-tied instances had very tight LP ranges under constrained decoding (0.0321, barely above the 0.05 threshold — actually below it, hence tied). Free-form triples their LP range to 0.0978. These tend to be moderate-complexity instances (1.7 rels, 2.8 ents) that are slightly longer than lost instances. The constrained format apparently homogenized their outputs, but free-form allows enough structural variation to create LP discrimination.\n\n### 2.3 Lost Non-Tied Instances (Constrained Non-Tied, Free-form Tied)\n\nN = 76 instances that lose LP discrimination under free-form.\n\nThese instances had the **highest** LP ranges in constrained mode (0.1108, nearly 2× baseline). In free-form, their LP range collapses to 0.0314. They tend to be simpler instances (1.3 rels, 2.6 ents, shorter text). The constrained format's structural rigidity apparently amplified small differences in these simple cases (e.g., missing/adding a single entity changes token count significantly), but free-form's flexibility allows the model to express the same content with different phrasings that have similar logprobs.\n\n### 2.4 LP Range Cross-Condition Correlation\n\n| Metric | Value |\n|:---|---:|\n| Spearman ρ (per-instance LP range) | 0.488 |\n| p-value | 2.95e-34 |\n| Mean LP range (constrained) | 0.0623 |\n| Mean LP range (free-form) | 0.0599 |\n\n**Interpretation**: Moderate positive correlation (ρ = 0.488) — instances with high LP range in one condition tend to have high range in the other, but with substantial scatter. The 0.488 is consistent with roughly 24% shared variance in LP range, meaning ~76% of the variance in which instances are \"discriminable\" is condition-specific. This confirms the reshuffling finding: the two decoding modes expose different aspects of instance difficulty.\n\n---\n\n## Summary: Key Takeaways\n\n1. **The RE LP selection flip is universal across all 7 SciERC relation types**, with the largest flips on semantically subtle types (PART-OF +6.52pp, HYPONYM-OF +4.45pp). No single type drives the effect.\n\n2. **Free-form decoding selectively reallocates LP variance**: it amplifies variance on RE-difficult instances (ratio 1.06, p < 0.0001) and dampens it on RE-easy instances (ratio 0.86). This gives LP selection more discriminative power exactly where RE quality varies most.\n\n3. **The constrained format creates a systematic LP selection bias for RE**: in constrained mode, LP selection is wrong more often than right (14.9% vs 9.1%), producing a net -23 instances. Free-form equalizes this to 45:45, flipping the aggregate gap from -0.68pp to +1.69pp. The mechanism is likely that constrained decoding rewards verbatim entity token copying (boosting logprobs) while penalizing relation-type experimentation.\n\n4. **Despite near-identical tied fractions (59.7% vs 57.7%), free-form fundamentally reshuffles which instances are discriminable** (Jaccard = 0.472). 87 instances gain LP discrimination (LP range triples from 0.032 to 0.098) while 76 lose it (range collapses from 0.111 to 0.031). Only 24% of LP range variance is shared between conditions.\n\n5. **The flip instances are relation-dense** (3.3 gold rels, 2× baseline) with suppressed LP variance in constrained mode. Free-form relaxes structural constraints, allowing these complex instances to produce more varied — and more informatively varied — outputs, enabling LP to select samples with better entity boundaries that cascade into better RE.\n",
      "numLines": 161,
      "startLine": 1,
      "totalLines": 161
    }
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_011StBSfiFye3UP6DX3Bzp4a`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_appendix_table.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "284fc490-8fab-4fa1-bc8a-0f815da426fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T11:33:24.695Z_

<details><summary>↩ Tool result · `toolu_011StBSfiFye3UP6DX3Bzp4a`</summary>

```text
1	% Requires: \usepackage{booktabs, multirow}
2	\begin{table*}[t]
3	\centering
4	\caption{Comparison of constrained vs.\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed=42).}
5	\label{tab:freeform-ablation}
6	
7	%% ---- Panel A: Logprob Distribution ----
8	\vspace{2pt}
9	{\small\textsc{Panel A: Logprob Distribution}}
10	\vspace{2pt}
11	
12	\begin{tabular}{lccc}
13	\toprule
14	Metric & Constrained & Free-form & $\Delta$ \\
15	\midrule
16	Mean LP std        & 0.0206 & 0.0199 & $-$0.0007 \\
17	Mean LP range      & 0.0623 & 0.0599 & $-$0.0024 \\
18	Tied fraction ($\varepsilon{=}0.05$) & 59.7\% & 57.7\% & $-$2.0\,pp \\
19	\bottomrule
20	\end{tabular}
21	
22	\vspace{8pt}
23	
24	%% ---- Panel B: Selection F1 ----
25	{\small\textsc{Panel B: Selection F1}}
26	\vspace{2pt}
27	
28	\begin{tabular}{llccc}
29	\toprule
30	Task & Method & Constrained & Free-form & $\Delta$ \\
31	\midrule
32	\multirow{3}{*}{NER}
33	  & Greedy        & 0.6182 & 0.6204 & \textbf{+0.0022} \\
34	  & LP-selected   & 0.6241 & 0.6222 & $-$0.0019 \\
35	  & Selection gap & +0.0059 & +0.0018 & $-$0.0041 \\
36	\midrule
37	\multirow{3}{*}{RE}
38	  & Greedy        & 0.2913 & 0.2880 & $-$0.0033 \\
39	  & LP-selected   & 0.2845 & 0.3050 & \textbf{+0.0205} \\
40	  & Selection gap & $-$0.0068 & +0.0169 & \textbf{+0.0237} \\
41	\bottomrule
42	\end{tabular}
43	
44	\vspace{8pt}
45	
46	%% ---- Panel C: QE Signal Quality (Spearman ρ) ----
47	{\small\textsc{Panel C: QE Signal Quality (Spearman $\rho$)}}
48	\vspace{2pt}
49	
50	\begin{tabular}{l ccc ccc}
51	\toprule
52	 & \multicolumn{3}{c}{NER ($n{=}529$)} & \multicolumn{3}{c}{RE ($n{=}397$)} \\
53	\cmidrule(lr){2-4} \cmidrule(lr){5-7}
54	Signal & Constr. & Free & $\Delta$ & Constr. & Free & $\Delta$ \\
55	\midrule
56	SJ & 0.3599 & 0.3774 & \textbf{+0.0175} & 0.2503 & 0.2728 & \textbf{+0.0225} \\
57	FK & 0.2665 & 0.3197 & \textbf{+0.0532} & 0.2752 & 0.3145 & \textbf{+0.0393} \\
58	LP & 0.2052 & 0.2129 & \textbf{+0.0077} & 0.2662 & 0.3042 & \textbf{+0.0379} \\
59	EM & 0.2945 & 0.3171 & \textbf{+0.0225} & 0.1344 & 0.1367 & \textbf{+0.0024} \\
60	VC & 0.3792 & 0.4089 & \textbf{+0.0297} & 0.3498 & 0.3234 & $-$0.0263 \\
61	\bottomrule
62	\end{tabular}
63	
64	\vspace{8pt}
65	
66	%% ---- Panel D: Parse Rate ----
67	{\small\textsc{Panel D: Parse Rate (Free-form)}}
68	\vspace{2pt}
69	
70	\begin{tabular}{lc}
71	\toprule
72	Metric & Value \\
73	\midrule
74	Total samples          & 4408 \\
75	Parse rate             & 99.95\% \\
76	Instances 8/8 valid    & 549\,/\,551 (99.6\%) \\
77	\bottomrule
78	\end{tabular}
79	
80	\end{table*}
81	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "5935fbf6-fcad-4c7e-ae3f-4fd93bb86c58",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/freeform_ablation_appendix_table.tex",
      "content": "% Requires: \\usepackage{booktabs, multirow}\n\\begin{table*}[t]\n\\centering\n\\caption{Comparison of constrained vs.\\ free-form decoding on SciERC (Qwen3-8B, $N{=}8$, $T{=}1.0$, seed=42).}\n\\label{tab:freeform-ablation}\n\n%% ---- Panel A: Logprob Distribution ----\n\\vspace{2pt}\n{\\small\\textsc{Panel A: Logprob Distribution}}\n\\vspace{2pt}\n\n\\begin{tabular}{lccc}\n\\toprule\nMetric & Constrained & Free-form & $\\Delta$ \\\\\n\\midrule\nMean LP std        & 0.0206 & 0.0199 & $-$0.0007 \\\\\nMean LP range      & 0.0623 & 0.0599 & $-$0.0024 \\\\\nTied fraction ($\\varepsilon{=}0.05$) & 59.7\\% & 57.7\\% & $-$2.0\\,pp \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n%% ---- Panel B: Selection F1 ----\n{\\small\\textsc{Panel B: Selection F1}}\n\\vspace{2pt}\n\n\\begin{tabular}{llccc}\n\\toprule\nTask & Method & Constrained & Free-form & $\\Delta$ \\\\\n\\midrule\n\\multirow{3}{*}{NER}\n  & Greedy        & 0.6182 & 0.6204 & \\textbf{+0.0022} \\\\\n  & LP-selected   & 0.6241 & 0.6222 & $-$0.0019 \\\\\n  & Selection gap & +0.0059 & +0.0018 & $-$0.0041 \\\\\n\\midrule\n\\multirow{3}{*}{RE}\n  & Greedy        & 0.2913 & 0.2880 & $-$0.0033 \\\\\n  & LP-selected   & 0.2845 & 0.3050 & \\textbf{+0.0205} \\\\\n  & Selection gap & $-$0.0068 & +0.0169 & \\textbf{+0.0237} \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n%% ---- Panel C: QE Signal Quality (Spearman ρ) ----\n{\\small\\textsc{Panel C: QE Signal Quality (Spearman $\\rho$)}}\n\\vspace{2pt}\n\n\\begin{tabular}{l ccc ccc}\n\\toprule\n & \\multicolumn{3}{c}{NER ($n{=}529$)} & \\multicolumn{3}{c}{RE ($n{=}397$)} \\\\\n\\cmidrule(lr){2-4} \\cmidrule(lr){5-7}\nSignal & Constr. & Free & $\\Delta$ & Constr. & Free & $\\Delta$ \\\\\n\\midrule\nSJ & 0.3599 & 0.3774 & \\textbf{+0.0175} & 0.2503 & 0.2728 & \\textbf{+0.0225} \\\\\nFK & 0.2665 & 0.3197 & \\textbf{+0.0532} & 0.2752 & 0.3145 & \\textbf{+0.0393} \\\\\nLP & 0.2052 & 0.2129 & \\textbf{+0.0077} & 0.2662 & 0.3042 & \\textbf{+0.0379} \\\\\nEM & 0.2945 & 0.3171 & \\textbf{+0.0225} & 0.1344 & 0.1367 & \\textbf{+0.0024} \\\\\nVC & 0.3792 & 0.4089 & \\textbf{+0.0297} & 0.3498 & 0.3234 & $-$0.0263 \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{8pt}\n\n%% ---- Panel D: Parse Rate ----\n{\\small\\textsc{Panel D: Parse Rate (Free-form)}}\n\\vspace{2pt}\n\n\\begin{tabular}{lc}\n\\toprule\nMetric & Value \\\\\n\\midrule\nTotal samples          & 4408 \\\\\nParse rate             & 99.95\\% \\\\\nInstances 8/8 valid    & 549\\,/\\,551 (99.6\\%) \\\\\n\\bottomrule\n\\end{tabular}\n\n\\end{table*}\n",
      "numLines": 81,
      "startLine": 1,
      "totalLines": 81
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01AxdZAfj6Ugh3X57tFgNT8r`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/tost_breakpoint_delta_star.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "2b1e23c9-5221-420c-96dc-8d8cc0bc8cd4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T11:33:25.520Z_

<details><summary>↩ Tool result · `toolu_01AxdZAfj6Ugh3X57tFgNT8r`</summary>

```text
1	# TOST Breakpoint δ*
2	
3	**Definition**: δ* = max(|CI_lower|, |CI_upper|) of the 90% CI of the paired mean difference (selection F1 − greedy F1). This is the smallest equivalence margin δ at which TOST (α=0.05) would confirm equivalence.
4	
5	**Method**: Paired t-distribution 90% CI = mean_Δ ± t_{0.05, n−1} × SE, where SE = std_Δ / √n.
6	
7	**Data source**: exp_012_rerun_1024 (Qwen2.5-7B-Instruct LoRA, N=8 samples, T=1.0). TOST worker log 2026-05-15.
8	
9	## NER (SciERC, n=529)
10	
11	| Signal | mean_Δ (pp) | 90% CI lower (pp) | 90% CI upper (pp) | δ* (pp) |
12	|--------|-------------|--------------------|--------------------|---------|
13	| LP     | +0.62       | −0.56              | +1.80              | 1.80    |
14	| SJ     | +0.11       | −1.06              | +1.28              | 1.28    |
15	| EM     | −0.79       | −2.07              | +0.49              | 2.07    |
16	| VC     | −1.02       | −2.29              | +0.25              | 2.29    |
17	| FK     | −1.80       | −3.38              | −0.22              | 3.38    |
18	
19	## RE (SciERC, n=397)
20	
21	| Signal | mean_Δ (pp) | 90% CI lower (pp) | 90% CI upper (pp) | δ* (pp) |
22	|--------|-------------|--------------------|--------------------|---------|
23	| LP     | −0.94       | −2.86              | +0.98              | 2.86    |
24	| SJ     | −1.88       | −3.76              | +0.00              | 3.76    |
25	| FK     | −2.18       | −4.22              | −0.14              | 4.22    |
26	| EM     | −3.16       | −5.17              | −1.15              | 5.17    |
27	| VC     | −4.51       | −6.53              | −2.49              | 6.53    |
28	
29	## Summary
30	
31	All δ* ∈ [1.28, 6.53] pp.
32	
33	- **NER**: δ* ∈ [1.28, 3.38] pp. All 5 signals confirm equivalence at δ=5pp (current paper uses δ=2pp). At δ=2pp, only SJ (1.28) and LP (1.80) pass; EM (2.07), VC (2.29), FK (3.38) require larger margins.
34	- **RE**: δ* ∈ [2.86, 6.53] pp. At δ=5pp (current paper), LP (2.86), SJ (3.76), FK (4.22) pass; EM (5.17) and VC (6.53) fail. VC has the largest δ* due to systematic negative bias (−4.5pp).
35	
36	### Implications for paper's TOST parameters
37	
38	| Paper setting       | NER δ=2pp              | RE δ=5pp               |
39	|---------------------|------------------------|------------------------|
40	| Signals that pass   | SJ (1.28), LP (1.80)   | LP (2.86), SJ (3.76), FK (4.22) |
41	| Borderline          | EM (2.07)              | EM (5.17)              |
42	| Signals that fail   | VC (2.29), FK (3.38)   | VC (6.53)              |
43	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "336247a7-1076-4418-8ef9-b5b80611a700",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/tost_breakpoint_delta_star.md",
      "content": "# TOST Breakpoint δ*\n\n**Definition**: δ* = max(|CI_lower|, |CI_upper|) of the 90% CI of the paired mean difference (selection F1 − greedy F1). This is the smallest equivalence margin δ at which TOST (α=0.05) would confirm equivalence.\n\n**Method**: Paired t-distribution 90% CI = mean_Δ ± t_{0.05, n−1} × SE, where SE = std_Δ / √n.\n\n**Data source**: exp_012_rerun_1024 (Qwen2.5-7B-Instruct LoRA, N=8 samples, T=1.0). TOST worker log 2026-05-15.\n\n## NER (SciERC, n=529)\n\n| Signal | mean_Δ (pp) | 90% CI lower (pp) | 90% CI upper (pp) | δ* (pp) |\n|--------|-------------|--------------------|--------------------|---------|\n| LP     | +0.62       | −0.56              | +1.80              | 1.80    |\n| SJ     | +0.11       | −1.06              | +1.28              | 1.28    |\n| EM     | −0.79       | −2.07              | +0.49              | 2.07    |\n| VC     | −1.02       | −2.29              | +0.25              | 2.29    |\n| FK     | −1.80       | −3.38              | −0.22              | 3.38    |\n\n## RE (SciERC, n=397)\n\n| Signal | mean_Δ (pp) | 90% CI lower (pp) | 90% CI upper (pp) | δ* (pp) |\n|--------|-------------|--------------------|--------------------|---------|\n| LP     | −0.94       | −2.86              | +0.98              | 2.86    |\n| SJ     | −1.88       | −3.76              | +0.00              | 3.76    |\n| FK     | −2.18       | −4.22              | −0.14              | 4.22    |\n| EM     | −3.16       | −5.17              | −1.15              | 5.17    |\n| VC     | −4.51       | −6.53              | −2.49              | 6.53    |\n\n## Summary\n\nAll δ* ∈ [1.28, 6.53] pp.\n\n- **NER**: δ* ∈ [1.28, 3.38] pp. All 5 signals confirm equivalence at δ=5pp (current paper uses δ=2pp). At δ=2pp, only SJ (1.28) and LP (1.80) pass; EM (2.07), VC (2.29), FK (3.38) require larger margins.\n- **RE**: δ* ∈ [2.86, 6.53] pp. At δ=5pp (current paper), LP (2.86), SJ (3.76), FK (4.22) pass; EM (5.17) and VC (6.53) fail. VC has the largest δ* due to systematic negative bias (−4.5pp).\n\n### Implications for paper's TOST parameters\n\n| Paper setting       | NER δ=2pp              | RE δ=5pp               |\n|---------------------|------------------------|------------------------|\n| Signals that pass   | SJ (1.28), LP (1.80)   | LP (2.86), SJ (3.76), FK (4.22) |\n| Borderline          | EM (2.07)              | EM (5.17)              |\n| Signals that fail   | VC (2.29), FK (3.38)   | VC (6.53)              |\n",
      "numLines": 43,
      "startLine": 1,
      "totalLines": 43
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Read · `toolu_01TZYzq42Waja4A3eftzsk4M`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/qwen3_thinking_confirmation.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "99a3ceb0-cfba-44a0-942c-01347bc56b47",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-15T11:33:26.016Z_

<details><summary>↩ Tool result · `toolu_01TZYzq42Waja4A3eftzsk4M`</summary>

````text
1	# Qwen3 SciERC Training: Thinking Tokens Confirmation
2	
3	## 1. enable_thinking 配置状态
4	
5	| 训练配置 | 文件 | enable_thinking 设置 | 实际生效值 |
6	|----------|------|---------------------|-----------|
7	| ft_001 (SciERC) | `train_config.yaml` | **未设置** | `True` (默认值) |
8	| ft_002 (SciERC) | `train_config_v2.yaml` | **未设置** | `True` (默认值) |
9	| ft_002_v2 (SciERC) | `train_config_v2.yaml` | **未设置** | `True` (默认值) |
10	| CoNLL-2003 | `train_config_conll2003.yaml` | `false` | `False` |
11	| WNUT-17 | `train_config_wnut17.yaml` | `false` | `False` |
12	
13	**LLaMA Factory 0.9.4 默认值**: `data_args.enable_thinking` 定义在 `llamafactory/hparams/data_args.py:122`，默认 `True`。SciERC 训练配置未覆盖此参数，因此使用默认值 `True`。
14	
15	## 2. 训练日志中的 thinking token 证据
16	
17	所有三次 SciERC 训练日志均包含：
18	
19	```
20	[WARNING] llamafactory.data.template:148 >> You are using reasoning template,
21	please add `_nothink` suffix if the model is not a reasoning model. e.g., qwen3_vl_nothink
22	&lt;think>
23	&lt;/think>
24	&lt;think>
25	&lt;/think>
26	...
27	```
28	
29	| 日志文件 | 时间戳 | 包含 `&lt;think>` |
30	|----------|--------|----------------|
31	| `ft_001_train.log` | 2026-05-14 14:09:15 | Yes |
32	| `ft_002_train.log` | 2026-05-14 15:43:17 | Yes |
33	| `ft_002v2_train.log` | 2026-05-14 16:10:02 | Yes |
34	
35	## 3. LLaMA Factory enable_thinking 机制 (template.py)
36	
37	当 `enable_thinking=True` 且训练数据不含 `&lt;think>`/`&lt;/think>` 时（正是 SciERC 的情况），LLaMA Factory 的行为（`template.py:424-431`）：
38	
39	```python
40	if (
41	    self.thought_words[0].strip() not in messages[-1]["content"]
42	    and self.thought_words[1].strip() not in messages[-1]["content"]
43	):  # add empty cot
44	    if not self.enable_thinking:  # do not compute loss
45	        prompt_ids += self.get_thought_word_ids(tokenizer)
46	    else:  # do compute loss
47	        response_ids = self.get_thought_word_ids(tokenizer) + response_ids
48	```
49	
50	- **`enable_thinking=True`（SciERC）**: 空 `&lt;think>\n&lt;/think>\n\n` 被 **prepend 到 response_ids**，纳入 loss 计算。模型被训练在每个 JSON 响应前先输出空 thinking block。
51	- **`enable_thinking=False`（CoNLL/WNUT）**: 空 `&lt;think>\n&lt;/think>` 被 append 到 prompt_ids，**不参与 loss 计算**。
52	
53	## 4. 结论
54	
55	**Thinking tokens 在 SciERC 训练时实际被激活。**
56	
57	具体表现：
58	- 每个训练样本的 response 前被自动注入空 thinking block `&lt;think>\n&lt;/think>\n\n`
59	- 这些 token 被纳入 loss 计算，模型学会在输出 JSON 前先产生空 thinking block
60	- 但 thinking block 始终为空（训练数据不含任何推理链），不存在实际的 chain-of-thought 内容
61	
62	**推理时的处理**：
63	- `apply_chat_template(enable_thinking=False)` + XGrammar JSON constrained decoding 确保推理输出不含任何 thinking tokens
64	- 这构成了一个 train-test distribution mismatch：训练时模型预期输出 `&lt;think>\n&lt;/think>` → JSON，推理时直接输出 JSON
65	
66	**影响评估**：
67	- 空 thinking block 仅含 4-5 个 token（`&lt;think>`, `\n`, `&lt;/think>`, `\n\n`），在 2048 cutoff_len 中占比极小
68	- 不存在推理链泄漏（thinking block 始终为空）
69	- 主要影响：模型的 token 分布被轻微偏移（学会先输出 thinking 标记再输出 JSON），推理时跳过这些 token 可能对首 token 概率分布有微弱影响
70	- CoNLL-2003 和 WNUT-17 不受影响（已显式设置 `enable_thinking: false`）
71	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "8eaca1e1-c1a9-4812-86c5-2389b682cf08",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/qwen3_thinking_confirmation.md",
      "content": "# Qwen3 SciERC Training: Thinking Tokens Confirmation\n\n## 1. enable_thinking 配置状态\n\n| 训练配置 | 文件 | enable_thinking 设置 | 实际生效值 |\n|----------|------|---------------------|-----------|\n| ft_001 (SciERC) | `train_config.yaml` | **未设置** | `True` (默认值) |\n| ft_002 (SciERC) | `train_config_v2.yaml` | **未设置** | `True` (默认值) |\n| ft_002_v2 (SciERC) | `train_config_v2.yaml` | **未设置** | `True` (默认值) |\n| CoNLL-2003 | `train_config_conll2003.yaml` | `false` | `False` |\n| WNUT-17 | `train_config_wnut17.yaml` | `false` | `False` |\n\n**LLaMA Factory 0.9.4 默认值**: `data_args.enable_thinking` 定义在 `llamafactory/hparams/data_args.py:122`，默认 `True`。SciERC 训练配置未覆盖此参数，因此使用默认值 `True`。\n\n## 2. 训练日志中的 thinking token 证据\n\n所有三次 SciERC 训练日志均包含：\n\n```\n[WARNING] llamafactory.data.template:148 >> You are using reasoning template,\nplease add `_nothink` suffix if the model is not a reasoning model. e.g., qwen3_vl_nothink\n&lt;think>\n&lt;/think>\n&lt;think>\n&lt;/think>\n...\n```\n\n| 日志文件 | 时间戳 | 包含 `&lt;think>` |\n|----------|--------|----------------|\n| `ft_001_train.log` | 2026-05-14 14:09:15 | Yes |\n| `ft_002_train.log` | 2026-05-14 15:43:17 | Yes |\n| `ft_002v2_train.log` | 2026-05-14 16:10:02 | Yes |\n\n## 3. LLaMA Factory enable_thinking 机制 (template.py)\n\n当 `enable_thinking=True` 且训练数据不含 `&lt;think>`/`&lt;/think>` 时（正是 SciERC 的情况），LLaMA Factory 的行为（`template.py:424-431`）：\n\n```python\nif (\n    self.thought_words[0].strip() not in messages[-1][\"content\"]\n    and self.thought_words[1].strip() not in messages[-1][\"content\"]\n):  # add empty cot\n    if not self.enable_thinking:  # do not compute loss\n        prompt_ids += self.get_thought_word_ids(tokenizer)\n    else:  # do compute loss\n        response_ids = self.get_thought_word_ids(tokenizer) + response_ids\n```\n\n- **`enable_thinking=True`（SciERC）**: 空 `&lt;think>\\n&lt;/think>\\n\\n` 被 **prepend 到 response_ids**，纳入 loss 计算。模型被训练在每个 JSON 响应前先输出空 thinking block。\n- **`enable_thinking=False`（CoNLL/WNUT）**: 空 `&lt;think>\\n&lt;/think>` 被 append 到 prompt_ids，**不参与 loss 计算**。\n\n## 4. 结论\n\n**Thinking tokens 在 SciERC 训练时实际被激活。**\n\n具体表现：\n- 每个训练样本的 response 前被自动注入空 thinking block `&lt;think>\\n&lt;/think>\\n\\n`\n- 这些 token 被纳入 loss 计算，模型学会在输出 JSON 前先产生空 thinking block\n- 但 thinking block 始终为空（训练数据不含任何推理链），不存在实际的 chain-of-thought 内容\n\n**推理时的处理**：\n- `apply_chat_template(enable_thinking=False)` + XGrammar JSON constrained decoding 确保推理输出不含任何 thinking tokens\n- 这构成了一个 train-test distribution mismatch：训练时模型预期输出 `&lt;think>\\n&lt;/think>` → JSON，推理时直接输出 JSON\n\n**影响评估**：\n- 空 thinking block 仅含 4-5 个 token（`&lt;think>`, `\\n`, `&lt;/think>`, `\\n\\n`），在 2048 cutoff_len 中占比极小\n- 不存在推理链泄漏（thinking block 始终为空）\n- 主要影响：模型的 token 分布被轻微偏移（学会先输出 thinking 标记再输出 JSON），推理时跳过这些 token 可能对首 token 概率分布有微弱影响\n- CoNLL-2003 和 WNUT-17 不受影响（已显式设置 `enable_thinking: false`）\n",
      "numLines": 71,
      "startLine": 1,
      "totalLines": 71
    }
  }
}
````

</details>

---

### Tool call

_source line 15_

<details open><summary>🔧 Tool call — Read · `toolu_01XuW4a7xHMYFbokqQXbkvzz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/vc_implementation_rho_diff.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "23eec194-cdd0-4966-a9fd-f7e18c103af6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-15T11:33:26.462Z_

<details><summary>↩ Tool result · `toolu_01XuW4a7xHMYFbokqQXbkvzz`</summary>

```text
1	# VC Implementation ρ Difference: Eq.6 vs Majority Threshold
2	
3	Two Voting Confidence (VC) implementations exist in the codebase:
4	
5	- **Eq.6 (no threshold)**: `mean([v/N for v in counter.values()])` — averages voting rate over all unique items
6	- **Majority threshold**: `mean([v/N for v in counter.values() if v > N/2])` else 0.0 — only items appearing in >50% of samples
7	
8	D068 unified the paper to majority threshold for Table 2.
9	
10	## Spearman ρ (VC vs F1), full split (non-empty gold)
11	
12	| Dataset | Model | Task | N | n | ρ\_eq6 | ρ\_majority | Δρ (eq6 − maj) |
13	|---------|-------|------|---|---|--------|-------------|----------------|
14	| SciERC | Qwen | NER | 8 | 529 | 0.3792 | 0.2524 | **+0.1268** |
15	| SciERC | Qwen | RE | 8 | 397 | 0.3498 | 0.3311 | **+0.0187** |
16	| SciERC | LLaMA | NER | 8 | 529 | 0.4053 | — | — |
17	| SciERC | LLaMA | RE | 8 | 397 | 0.3840 | — | — |
18	| CoNLL | LLaMA | NER | 8 | 2756 | 0.4256 | — | — |
19	| CoNLL | Qwen | NER | 16 | 2756 | 0.4286 | — | — |
20	
21	"—" = samples.jsonl not available locally; majority-threshold ρ requires recomputation from raw samples.
22	
23	## Methodology
24	
25	- **Qwen × SciERC**: Computed from local `exp_012_rerun_1024/samples_with_logprobs.jsonl` (seed=42). NER F1 uses strict span match `(start, end, type)`. RE F1 uses `(head_start, head_end, tail_start, tail_end, type)`. Values validated against worker verification result (exact match).
26	- **Other configurations**: ρ\_eq6 from experiment registry (all registry entries use Eq.6 implementation, confirmed by worker verification of exp\_012).
27	
28	## Key observations
29	
30	1. **NER Δρ is large (+0.127)**: The majority threshold discards all items appearing in ≤4 of 8 samples. For NER, many valid but rare entity mentions get filtered out, collapsing the signal's dynamic range and reducing correlation with F1.
31	
32	2. **RE Δρ is small (+0.019)**: Relations are inherently sparser — most extracted relations either appear consistently (majority) or not at all. The threshold filter removes fewer items proportionally, so the two implementations converge.
33	
34	3. **Direction is consistent**: Eq.6 ≥ majority threshold in both subtasks. The no-threshold version preserves more discriminative signal from low-frequency items.
35	
36	4. **Practical impact on paper claims**: The qualitative ranking VC > SJ > others holds under both implementations for NER. For RE, VC remains the top signal either way. The D068 decision to use majority threshold is conservative — it reports the weaker of the two ρ values.
37	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "22dd7933-f262-4ea6-9927-2fec3df2814e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/vc_implementation_rho_diff.md",
      "content": "# VC Implementation ρ Difference: Eq.6 vs Majority Threshold\n\nTwo Voting Confidence (VC) implementations exist in the codebase:\n\n- **Eq.6 (no threshold)**: `mean([v/N for v in counter.values()])` — averages voting rate over all unique items\n- **Majority threshold**: `mean([v/N for v in counter.values() if v > N/2])` else 0.0 — only items appearing in >50% of samples\n\nD068 unified the paper to majority threshold for Table 2.\n\n## Spearman ρ (VC vs F1), full split (non-empty gold)\n\n| Dataset | Model | Task | N | n | ρ\\_eq6 | ρ\\_majority | Δρ (eq6 − maj) |\n|---------|-------|------|---|---|--------|-------------|----------------|\n| SciERC | Qwen | NER | 8 | 529 | 0.3792 | 0.2524 | **+0.1268** |\n| SciERC | Qwen | RE | 8 | 397 | 0.3498 | 0.3311 | **+0.0187** |\n| SciERC | LLaMA | NER | 8 | 529 | 0.4053 | — | — |\n| SciERC | LLaMA | RE | 8 | 397 | 0.3840 | — | — |\n| CoNLL | LLaMA | NER | 8 | 2756 | 0.4256 | — | — |\n| CoNLL | Qwen | NER | 16 | 2756 | 0.4286 | — | — |\n\n\"—\" = samples.jsonl not available locally; majority-threshold ρ requires recomputation from raw samples.\n\n## Methodology\n\n- **Qwen × SciERC**: Computed from local `exp_012_rerun_1024/samples_with_logprobs.jsonl` (seed=42). NER F1 uses strict span match `(start, end, type)`. RE F1 uses `(head_start, head_end, tail_start, tail_end, type)`. Values validated against worker verification result (exact match).\n- **Other configurations**: ρ\\_eq6 from experiment registry (all registry entries use Eq.6 implementation, confirmed by worker verification of exp\\_012).\n\n## Key observations\n\n1. **NER Δρ is large (+0.127)**: The majority threshold discards all items appearing in ≤4 of 8 samples. For NER, many valid but rare entity mentions get filtered out, collapsing the signal's dynamic range and reducing correlation with F1.\n\n2. **RE Δρ is small (+0.019)**: Relations are inherently sparser — most extracted relations either appear consistently (majority) or not at all. The threshold filter removes fewer items proportionally, so the two implementations converge.\n\n3. **Direction is consistent**: Eq.6 ≥ majority threshold in both subtasks. The no-threshold version preserves more discriminative signal from low-frequency items.\n\n4. **Practical impact on paper claims**: The qualitative ranking VC > SJ > others holds under both implementations for NER. For RE, VC remains the top signal either way. The D068 decision to use majority threshold is conservative — it reports the weaker of the two ρ values.\n",
      "numLines": 37,
      "startLine": 1,
      "totalLines": 37
    }
  }
}
```

</details>

---

### Tool call

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01S31AhibEKK1nkcge4sSmDV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/multi_seed_stability_table.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "fe7475b9-53a6-4c02-a26a-47871eba226d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-15T11:33:27.405Z_

<details><summary>↩ Tool result · `toolu_01S31AhibEKK1nkcge4sSmDV`</summary>

```text
1	# Multi-seed Signal Stability (SciERC NER & RE, N=8, T=1.0, max_tokens=1024)
2	
3	All values from `compute_llama_3seed_summary.py` (fresh rerun data) and `compute_3seed_summary.py` (Qwen). Source: script output, NOT report.json.
4	
5	## Table A: Per-seed Signal Values (Spearman ρ) — NER
6	
7	| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |
8	|-------|--------|---------|----------|----------|------|---|
9	| Qwen  | LP     | 0.2052  | 0.2341   | 0.2107   | 0.2167 | 0.0125 |
10	| Qwen  | FK     | 0.2665  | 0.2628   | 0.2314   | 0.2536 | 0.0157 |
11	| Qwen  | SJ     | 0.3599  | 0.3878   | 0.3445   | 0.3641 | 0.0179 |
12	| Qwen  | VC     | 0.3701  | 0.4123   | 0.3758   | 0.3861 | 0.0187 |
13	| Qwen  | EM     | 0.2990  | 0.3052   | 0.3172   | 0.3071 | 0.0076 |
14	| LLaMA | LP     | 0.1503  | 0.1970   | 0.1391   | 0.1621 | 0.0251 |
15	| LLaMA | FK     | 0.2352  | 0.2897   | 0.2422   | 0.2557 | 0.0242 |
16	| LLaMA | SJ     | 0.3096  | 0.3552   | 0.3099   | 0.3249 | 0.0214 |
17	| LLaMA | VC     | 0.3730  | 0.4032   | 0.3751   | 0.3838 | 0.0138 |
18	| LLaMA | EM     | 0.2703  | 0.2945   | 0.2708   | 0.2785 | 0.0113 |
19	
20	## Table A2: Per-seed Signal Values (Spearman ρ) — RE
21	
22	| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |
23	|-------|--------|---------|----------|----------|------|---|
24	| Qwen  | LP     | 0.2662  | 0.3143   | 0.3105   | 0.2970 | 0.0218 |
25	| Qwen  | FK     | 0.2752  | 0.2908   | 0.3049   | 0.2903 | 0.0121 |
26	| Qwen  | SJ     | 0.2503  | 0.2486   | 0.2466   | 0.2485 | 0.0015 |
27	| Qwen  | VC     | 0.3060  | 0.3399   | 0.2804   | 0.3088 | 0.0244 |
28	| Qwen  | EM     | 0.1369  | 0.1153   | 0.1537   | 0.1353 | 0.0157 |
29	| LLaMA | LP     | 0.3163  | 0.3054   | 0.3009   | 0.3075 | 0.0065 |
30	| LLaMA | FK     | 0.3027  | 0.2555   | 0.2791   | 0.2791 | 0.0193 |
31	| LLaMA | SJ     | 0.2748  | 0.2462   | 0.2828   | 0.2679 | 0.0157 |
32	| LLaMA | VC     | 0.3055  | 0.3129   | 0.3280   | 0.3155 | 0.0094 |
33	| LLaMA | EM     | 0.1653  | 0.1598   | 0.1847   | 0.1699 | 0.0107 |
34	
35	## Table B: Per-seed Signal Values (AUROC) — NER
36	
37	| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |
38	|-------|--------|---------|----------|----------|------|---|
39	| Qwen  | LP     | 0.6116  | 0.6132   | 0.6153   | 0.6134 | 0.0015 |
40	| Qwen  | FK     | 0.6154  | 0.6300   | 0.6078   | 0.6177 | 0.0092 |
41	| Qwen  | SJ     | 0.6715  | 0.6919   | 0.6888   | 0.6841 | 0.0090 |
42	| Qwen  | VC     | 0.6834  | 0.7065   | 0.7004   | 0.6968 | 0.0098 |
43	| Qwen  | EM     | 0.6518  | 0.6549   | 0.6750   | 0.6606 | 0.0103 |
44	| LLaMA | LP     | 0.5808  | 0.5839   | 0.5676   | 0.5774 | 0.0071 |
45	| LLaMA | FK     | 0.6088  | 0.6317   | 0.6086   | 0.6164 | 0.0108 |
46	| LLaMA | SJ     | 0.6518  | 0.6682   | 0.6453   | 0.6551 | 0.0096 |
47	| LLaMA | VC     | 0.6877  | 0.6954   | 0.6827   | 0.6886 | 0.0052 |
48	| LLaMA | EM     | 0.6397  | 0.6412   | 0.6278   | 0.6362 | 0.0060 |
49	
50	## Table B2: Per-seed Signal Values (AUROC) — RE
51	
52	| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |
53	|-------|--------|---------|----------|----------|------|---|
54	| Qwen  | LP     | 0.6205  | 0.6605   | 0.6602   | 0.6471 | 0.0188 |
55	| Qwen  | FK     | 0.6449  | 0.6512   | 0.6518   | 0.6493 | 0.0031 |
56	| Qwen  | SJ     | 0.6346  | 0.6230   | 0.6235   | 0.6270 | 0.0054 |
57	| Qwen  | VC     | 0.6577  | 0.6699   | 0.6466   | 0.6581 | 0.0095 |
58	| Qwen  | EM     | 0.5726  | 0.5444   | 0.5704   | 0.5625 | 0.0128 |
59	| LLaMA | LP     | 0.6682  | 0.6544   | 0.6526   | 0.6584 | 0.0070 |
60	| LLaMA | FK     | 0.6515  | 0.6293   | 0.6380   | 0.6396 | 0.0091 |
61	| LLaMA | SJ     | 0.6599  | 0.6385   | 0.6609   | 0.6531 | 0.0103 |
62	| LLaMA | VC     | 0.6774  | 0.6704   | 0.6862   | 0.6780 | 0.0065 |
63	| LLaMA | EM     | 0.6032  | 0.5959   | 0.6122   | 0.6038 | 0.0067 |
64	
65	## Table C: Signal Ranking Consistency
66	
67	### NER — Spearman ρ ranking per seed
68	
69	| Seed | Qwen ranking | LLaMA ranking |
70	|------|-------------|---------------|
71	| 42   | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |
72	| 123  | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |
73	| 456  | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |
74	
75	**NER ranking is perfectly stable**: VC > SJ > EM > FK > LP across all 6 seed×model combinations.
76	
77	### RE — Spearman ρ ranking per seed
78	
79	| Seed | Qwen ranking | LLaMA ranking |
80	|------|-------------|---------------|
81	| 42   | VC > FK > LP > SJ > EM | LP > VC > FK > SJ > EM |
82	| 123  | VC > LP > FK > SJ > EM | VC > LP > FK > SJ > EM |
83	| 456  | LP > FK > VC > SJ > EM | VC > LP > SJ > FK > EM |
84	
85	RE ranking shows minor instability in the top-3 (VC/LP/FK are close), but EM is consistently last and SJ is consistently 4th.
86	
87	### Cross-model consistency
88	- **NER**: Qwen and LLaMA produce identical signal ranking across all seeds.
89	- **RE**: Top-3 ordering varies, but both models agree on SJ 4th, EM 5th.
90	
91	### LLaMA SJ ρ correction (NER)
92	- **Old (contaminated, exp_007 data)**: seed42 SJ ρ = 0.363, mean ≈ 0.362, σ ≈ 0.004
93	- **New (fresh rerun, exp_018 r1024)**: seed42 SJ ρ = 0.310, mean = 0.325, σ = 0.021
94	- σ increased ~5×. This is real seed variability, not noise: seed123 (ρ=0.355) pulls the mean up while seed42/456 cluster at ~0.310. The old exp_007 data artificially compressed variance.
95	
96	## Key Observations
97	
98	### 1. Core claim "structural > logprob" stability
99	
100	**NER (strong support)**: All structural signals (SJ, FK, EM, VC) beat LP in every seed×model combination (12/12). VC and SJ maintain a large margin over LP (Δρ ≈ 0.12–0.22).
101	
102	**RE (partial support)**: LP competes with or beats SJ and FK in most RE seeds. Only VC consistently outperforms LP in RE. The claim holds at the aggregate level (VC > LP across seeds) but not for SJ/FK individually.
103	
104	### 2. ρ-AUROC separation
105	
106	The ρ-AUROC gap is compressed for weaker signals:
107	- NER LP has the lowest ρ (Qwen 0.217, LLaMA 0.162) but AUROC remains above 0.57–0.61. A ρ ratio of ~2.4× between best (VC) and worst (LP) compresses to ~1.14× in AUROC.
108	- This compression is stable across all seeds and both models, suggesting AUROC is less sensitive to calibration quality differences.
109	
110	### 3. LLaMA vs Qwen absolute values
111	
112	- **NER**: Qwen edges out LLaMA on most signals (SJ mean: 0.364 vs 0.325; LP mean: 0.217 vs 0.162). The gap is consistent across seeds.
113	- **RE**: Qwen and LLaMA are closer, with LLaMA slightly ahead on LP (0.308 vs 0.297) and VC (0.316 vs 0.309).
114	- Cross-seed σ is similar between models (typically 0.01–0.025), indicating comparable stability.
115	
116	### 4. Most/least stable signals
117	
118	| Metric | Most stable (lowest σ) | Least stable (highest σ) |
119	|--------|----------------------|------------------------|
120	| NER ρ  | Qwen EM (σ=0.008)   | LLaMA LP (σ=0.025)    |
121	| RE ρ   | Qwen SJ (σ=0.002)   | Qwen VC (σ=0.024)     |
122	| NER AUROC | Qwen LP (σ=0.002) | LLaMA FK (σ=0.011)  |
123	| RE AUROC | Qwen FK (σ=0.003)  | Qwen LP (σ=0.019)    |
124	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "f1a2e5c6-96b7-4a22-9b96-2e18f8f67b03",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/multi_seed_stability_table.md",
      "content": "# Multi-seed Signal Stability (SciERC NER & RE, N=8, T=1.0, max_tokens=1024)\n\nAll values from `compute_llama_3seed_summary.py` (fresh rerun data) and `compute_3seed_summary.py` (Qwen). Source: script output, NOT report.json.\n\n## Table A: Per-seed Signal Values (Spearman ρ) — NER\n\n| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |\n|-------|--------|---------|----------|----------|------|---|\n| Qwen  | LP     | 0.2052  | 0.2341   | 0.2107   | 0.2167 | 0.0125 |\n| Qwen  | FK     | 0.2665  | 0.2628   | 0.2314   | 0.2536 | 0.0157 |\n| Qwen  | SJ     | 0.3599  | 0.3878   | 0.3445   | 0.3641 | 0.0179 |\n| Qwen  | VC     | 0.3701  | 0.4123   | 0.3758   | 0.3861 | 0.0187 |\n| Qwen  | EM     | 0.2990  | 0.3052   | 0.3172   | 0.3071 | 0.0076 |\n| LLaMA | LP     | 0.1503  | 0.1970   | 0.1391   | 0.1621 | 0.0251 |\n| LLaMA | FK     | 0.2352  | 0.2897   | 0.2422   | 0.2557 | 0.0242 |\n| LLaMA | SJ     | 0.3096  | 0.3552   | 0.3099   | 0.3249 | 0.0214 |\n| LLaMA | VC     | 0.3730  | 0.4032   | 0.3751   | 0.3838 | 0.0138 |\n| LLaMA | EM     | 0.2703  | 0.2945   | 0.2708   | 0.2785 | 0.0113 |\n\n## Table A2: Per-seed Signal Values (Spearman ρ) — RE\n\n| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |\n|-------|--------|---------|----------|----------|------|---|\n| Qwen  | LP     | 0.2662  | 0.3143   | 0.3105   | 0.2970 | 0.0218 |\n| Qwen  | FK     | 0.2752  | 0.2908   | 0.3049   | 0.2903 | 0.0121 |\n| Qwen  | SJ     | 0.2503  | 0.2486   | 0.2466   | 0.2485 | 0.0015 |\n| Qwen  | VC     | 0.3060  | 0.3399   | 0.2804   | 0.3088 | 0.0244 |\n| Qwen  | EM     | 0.1369  | 0.1153   | 0.1537   | 0.1353 | 0.0157 |\n| LLaMA | LP     | 0.3163  | 0.3054   | 0.3009   | 0.3075 | 0.0065 |\n| LLaMA | FK     | 0.3027  | 0.2555   | 0.2791   | 0.2791 | 0.0193 |\n| LLaMA | SJ     | 0.2748  | 0.2462   | 0.2828   | 0.2679 | 0.0157 |\n| LLaMA | VC     | 0.3055  | 0.3129   | 0.3280   | 0.3155 | 0.0094 |\n| LLaMA | EM     | 0.1653  | 0.1598   | 0.1847   | 0.1699 | 0.0107 |\n\n## Table B: Per-seed Signal Values (AUROC) — NER\n\n| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |\n|-------|--------|---------|----------|----------|------|---|\n| Qwen  | LP     | 0.6116  | 0.6132   | 0.6153   | 0.6134 | 0.0015 |\n| Qwen  | FK     | 0.6154  | 0.6300   | 0.6078   | 0.6177 | 0.0092 |\n| Qwen  | SJ     | 0.6715  | 0.6919   | 0.6888   | 0.6841 | 0.0090 |\n| Qwen  | VC     | 0.6834  | 0.7065   | 0.7004   | 0.6968 | 0.0098 |\n| Qwen  | EM     | 0.6518  | 0.6549   | 0.6750   | 0.6606 | 0.0103 |\n| LLaMA | LP     | 0.5808  | 0.5839   | 0.5676   | 0.5774 | 0.0071 |\n| LLaMA | FK     | 0.6088  | 0.6317   | 0.6086   | 0.6164 | 0.0108 |\n| LLaMA | SJ     | 0.6518  | 0.6682   | 0.6453   | 0.6551 | 0.0096 |\n| LLaMA | VC     | 0.6877  | 0.6954   | 0.6827   | 0.6886 | 0.0052 |\n| LLaMA | EM     | 0.6397  | 0.6412   | 0.6278   | 0.6362 | 0.0060 |\n\n## Table B2: Per-seed Signal Values (AUROC) — RE\n\n| Model | Signal | seed=42 | seed=123 | seed=456 | mean | σ |\n|-------|--------|---------|----------|----------|------|---|\n| Qwen  | LP     | 0.6205  | 0.6605   | 0.6602   | 0.6471 | 0.0188 |\n| Qwen  | FK     | 0.6449  | 0.6512   | 0.6518   | 0.6493 | 0.0031 |\n| Qwen  | SJ     | 0.6346  | 0.6230   | 0.6235   | 0.6270 | 0.0054 |\n| Qwen  | VC     | 0.6577  | 0.6699   | 0.6466   | 0.6581 | 0.0095 |\n| Qwen  | EM     | 0.5726  | 0.5444   | 0.5704   | 0.5625 | 0.0128 |\n| LLaMA | LP     | 0.6682  | 0.6544   | 0.6526   | 0.6584 | 0.0070 |\n| LLaMA | FK     | 0.6515  | 0.6293   | 0.6380   | 0.6396 | 0.0091 |\n| LLaMA | SJ     | 0.6599  | 0.6385   | 0.6609   | 0.6531 | 0.0103 |\n| LLaMA | VC     | 0.6774  | 0.6704   | 0.6862   | 0.6780 | 0.0065 |\n| LLaMA | EM     | 0.6032  | 0.5959   | 0.6122   | 0.6038 | 0.0067 |\n\n## Table C: Signal Ranking Consistency\n\n### NER — Spearman ρ ranking per seed\n\n| Seed | Qwen ranking | LLaMA ranking |\n|------|-------------|---------------|\n| 42   | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |\n| 123  | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |\n| 456  | VC > SJ > EM > FK > LP | VC > SJ > EM > FK > LP |\n\n**NER ranking is perfectly stable**: VC > SJ > EM > FK > LP across all 6 seed×model combinations.\n\n### RE — Spearman ρ ranking per seed\n\n| Seed | Qwen ranking | LLaMA ranking |\n|------|-------------|---------------|\n| 42   | VC > FK > LP > SJ > EM | LP > VC > FK > SJ > EM |\n| 123  | VC > LP > FK > SJ > EM | VC > LP > FK > SJ > EM |\n| 456  | LP > FK > VC > SJ > EM | VC > LP > SJ > FK > EM |\n\nRE ranking shows minor instability in the top-3 (VC/LP/FK are close), but EM is consistently last and SJ is consistently 4th.\n\n### Cross-model consistency\n- **NER**: Qwen and LLaMA produce identical signal ranking across all seeds.\n- **RE**: Top-3 ordering varies, but both models agree on SJ 4th, EM 5th.\n\n### LLaMA SJ ρ correction (NER)\n- **Old (contaminated, exp_007 data)**: seed42 SJ ρ = 0.363, mean ≈ 0.362, σ ≈ 0.004\n- **New (fresh rerun, exp_018 r1024)**: seed42 SJ ρ = 0.310, mean = 0.325, σ = 0.021\n- σ increased ~5×. This is real seed variability, not noise: seed123 (ρ=0.355) pulls the mean up while seed42/456 cluster at ~0.310. The old exp_007 data artificially compressed variance.\n\n## Key Observations\n\n### 1. Core claim \"structural > logprob\" stability\n\n**NER (strong support)**: All structural signals (SJ, FK, EM, VC) beat LP in every seed×model combination (12/12). VC and SJ maintain a large margin over LP (Δρ ≈ 0.12–0.22).\n\n**RE (partial support)**: LP competes with or beats SJ and FK in most RE seeds. Only VC consistently outperforms LP in RE. The claim holds at the aggregate level (VC > LP across seeds) but not for SJ/FK individually.\n\n### 2. ρ-AUROC separation\n\nThe ρ-AUROC gap is compressed for weaker signals:\n- NER LP has the lowest ρ (Qwen 0.217, LLaMA 0.162) but AUROC remains above 0.57–0.61. A ρ ratio of ~2.4× between best (VC) and worst (LP) compresses to ~1.14× in AUROC.\n- This compression is stable across all seeds and both models, suggesting AUROC is less sensitive to calibration quality differences.\n\n### 3. LLaMA vs Qwen absolute values\n\n- **NER**: Qwen edges out LLaMA on most signals (SJ mean: 0.364 vs 0.325; LP mean: 0.217 vs 0.162). The gap is consistent across seeds.\n- **RE**: Qwen and LLaMA are closer, with LLaMA slightly ahead on LP (0.308 vs 0.297) and VC (0.316 vs 0.309).\n- Cross-seed σ is similar between models (typically 0.01–0.025), indicating comparable stability.\n\n### 4. Most/least stable signals\n\n| Metric | Most stable (lowest σ) | Least stable (highest σ) |\n|--------|----------------------|------------------------|\n| NER ρ  | Qwen EM (σ=0.008)   | LLaMA LP (σ=0.025)    |\n| RE ρ   | Qwen SJ (σ=0.002)   | Qwen VC (σ=0.024)     |\n| NER AUROC | Qwen LP (σ=0.002) | LLaMA FK (σ=0.011)  |\n| RE AUROC | Qwen FK (σ=0.003)  | Qwen LP (σ=0.019)    |\n",
      "numLines": 124,
      "startLine": 1,
      "totalLines": 124
    }
  }
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Glob · `toolu_017FiM2yVr1WMfxaEyCUdY1t`</summary>

```json
{
  "pattern": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "465e7923-6027-4080-a8b7-056cad7ca377",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nj7hTAsJWegSie9Q1ZrJuv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 11607,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11607
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-15T11:33:27.648Z_

<details><summary>↩ Tool result · `toolu_017FiM2yVr1WMfxaEyCUdY1t`</summary>

```text
docs/paper/sections/related_work.tex
docs/paper/sections/method.tex
docs/paper/sections/experiments.tex
docs/paper/sections/abstract.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/limitations.tex
docs/paper/sections/introduction.tex
docs/paper/sections/discussion.tex
docs/paper/sections/appendix.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "9d326f57-8f53-4c35-9231-318973bbdbf4",
  "tool_use_result": {
    "filenames": [
      "docs/paper/sections/related_work.tex",
      "docs/paper/sections/method.tex",
      "docs/paper/sections/experiments.tex",
      "docs/paper/sections/abstract.tex",
      "docs/paper/sections/conclusion.tex",
      "docs/paper/sections/limitations.tex",
      "docs/paper/sections/introduction.tex",
      "docs/paper/sections/discussion.tex",
      "docs/paper/sections/appendix.tex"
    ],
    "durationMs": 17,
    "numFiles": 9,
    "truncated": false
  }
}
```

</details>

---

### Assistant

_source line 21_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the paper sections (discussion, appendix, limitations) and check the registry for exp_007 metrics.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "670dd6b8-912c-4755-8e42-2c90c7829e98",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 22_

Now reading the paper sections and checking the registry.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "5d5c7fc8-bf24-437b-9a1f-127ea94caaac",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — Read · `toolu_01AuMdQLF7RGRgVRGs4MmuCz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "970018b4-6167-42ec-84ba-d7338cc0ee83",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-15T11:33:33.444Z_

<details><summary>↩ Tool result · `toolu_01AuMdQLF7RGRgVRGs4MmuCz`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	\paragraph{Practical recommendations.}
4	For per-instance quality ranking, VC provides the strongest rank correlation ($\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).
5	Signal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across tested model families, though with model-dependent magnitude.
6	When model capability is insufficient (WNUT-17), all signals converge toward non-significant conditional correlations (Table~\ref{tab:wnut}).
7	
8	\paragraph{Why the gap exists: two layers.}
9	\textit{Layer 1 (definitional):} Four of five signals are instance-level aggregates that assign a single score per input; they cannot rank candidates by construction.
10	Consensus-proximity selection (\S\ref{sec:evaluation}) does not recover per-sample discrimination (Table~\ref{tab:selection}).
11	\textit{Layer 2 (score compression):} Log-probability, the only per-sample signal, also fails to exploit the 13--18~pp oracle headroom.
12	LP scores are severely compressed: 60\% of instances have a within-sample range below 0.05, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$; Appendix~\ref{app:logprob_ties}).
13	In the 40\% of instances where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), LP \textit{significantly} outperforms greedy ($+2.9$~pp, $p{=}0.01$; within-instance $\rho$: 0.08$\to$0.39).
14	This diagnostic confirms that LP carries useful per-sample quality information; score compression is the primary mechanistic bottleneck.
15	A controlled ablation (\S\ref{sec:ablation}) confirms that this compression is intrinsic to the model and task, not an artifact of constrained decoding.
16	Diversity-stratified analysis confirms the gap persists even among high-diversity instances (Appendix~\ref{app:diversity}); RE miscalibration (ECE 0.109--0.339, preliminary; Appendix~\ref{app:calibration}) may compound this.
17	
18	\paragraph{Connection to MBR decoding.}
19	Our selection strategies instantiate minimum Bayes risk (MBR) decoding \cite{eikema2022sampling, muller2021understanding}: each selects $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.
20	Despite MBR's success in machine translation \cite{freitag2022high} and its extension to summarization, code generation, and captioning \cite{jinnai2024mbr}, all variants fail here because the utility functions correlate with F1 at the instance level but not within a single instance---the mathematical essence of the correlation-selection gap.
21	\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs---consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.
22	
23	\paragraph{Score compression is task-inherent.}\label{sec:ablation}
24	A natural hypothesis is that LP compression is an artifact of constrained decoding's restricted token space.
25	We test this via controlled ablation: generating free-form (unconstrained) outputs on the same instances with post-hoc JSON parsing (parse rate 99.95\%, 4406/4408; Table~\ref{tab:freeform_ablation}).
26	LP variance is essentially unchanged (within-instance std ratio $0.97{\times}$, tied fraction 59.7\%$\to$57.7\%).
27	NER selection gains remain negligible ($+0.18$~pp free-form vs.\ $+0.59$~pp constrained).
28	This rules out constrained decoding as the cause of compression and establishes LP compression as inherent to structured output generation.
29	The correlation-selection gap is therefore a fundamental challenge for test-time scaling in structured IE, not an artifact of any particular decoding strategy.
30	Notably, the fine-tuned model achieved 99.95\% parse rate without grammar constraints, suggesting that constrained decoding's format-compliance role may be redundant for sufficiently fine-tuned models.
31	
32	\paragraph{RE task-specific interaction.}
33	RE LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form), suggesting a task-specific interaction between decoding regime and selection efficacy that does not generalize to NER.
34	Free-form decoding also slightly improves quality estimation (NER VC $\rho$: 0.379$\to$0.409), though this does not translate to selection gains.
35	
36	\paragraph{Methodological implications.}
37	The decoupling of quality estimation ($\rho$), binary discrimination (AUROC), and sample selection (best-of-$N$ F1) means evaluating on a single metric risks selecting the wrong signal for the intended use case.
38	Effective selection likely requires per-sample signals such as trained verifiers \cite{cobbe2021verifiers, venktesh2025trust}; $N$-scaling analysis (Appendix~\ref{app:additional}) shows $N{=}8$ captures most quality estimation benefit.
39	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "55550cb1-cb2e-462c-a3eb-fdd65a333c3c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\n\\paragraph{Practical recommendations.}\nFor per-instance quality ranking, VC provides the strongest rank correlation ($\\rho{=}0.38$), though EM leads binary discrimination (AUROC${=}0.749$); under conditional filtering, EM leads on both NER and RE ($\\rho{=}0.360$, $0.417$; RE: preliminary, single benchmark).\nSignal rankings depend on task difficulty---EM dominates easy tasks (CoNLL), VC and SJ dominate hard tasks (SciERC)---directionally consistent across tested model families, though with model-dependent magnitude.\nWhen model capability is insufficient (WNUT-17), all signals converge toward non-significant conditional correlations (Table~\\ref{tab:wnut}).\n\n\\paragraph{Why the gap exists: two layers.}\n\\textit{Layer 1 (definitional):} Four of five signals are instance-level aggregates that assign a single score per input; they cannot rank candidates by construction.\nConsensus-proximity selection (\\S\\ref{sec:evaluation}) does not recover per-sample discrimination (Table~\\ref{tab:selection}).\n\\textit{Layer 2 (score compression):} Log-probability, the only per-sample signal, also fails to exploit the 13--18~pp oracle headroom.\nLP scores are severely compressed: 60\\% of instances have a within-sample range below 0.05, and 75\\% of pairwise comparisons are effective ties ($|\\Delta|{<}0.026$; Appendix~\\ref{app:logprob_ties}).\nIn the 40\\% of instances where compression is mitigated (LP range ${\\geq}0.05$, $n{=}210$), LP \\textit{significantly} outperforms greedy ($+2.9$~pp, $p{=}0.01$; within-instance $\\rho$: 0.08$\\to$0.39).\nThis diagnostic confirms that LP carries useful per-sample quality information; score compression is the primary mechanistic bottleneck.\nA controlled ablation (\\S\\ref{sec:ablation}) confirms that this compression is intrinsic to the model and task, not an artifact of constrained decoding.\nDiversity-stratified analysis confirms the gap persists even among high-diversity instances (Appendix~\\ref{app:diversity}); RE miscalibration (ECE 0.109--0.339, preliminary; Appendix~\\ref{app:calibration}) may compound this.\n\n\\paragraph{Connection to MBR decoding.}\nOur selection strategies instantiate minimum Bayes risk (MBR) decoding \\cite{eikema2022sampling, muller2021understanding}: each selects $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} U(y_i, y_j)$ with utility $U$ defined by SJ, EM, or entity overlap.\nDespite MBR's success in machine translation \\cite{freitag2022high} and its extension to summarization, code generation, and captioning \\cite{jinnai2024mbr}, all variants fail here because the utility functions correlate with F1 at the instance level but not within a single instance---the mathematical essence of the correlation-selection gap.\n\\citet{eikema2025structured} study structure-conditional MBR decoding and find that standard utility functions degrade on structured outputs---consistent with our finding that consensus-proximity selection fails in IE despite its success in machine translation.\n\n\\paragraph{Score compression is task-inherent.}\\label{sec:ablation}\nA natural hypothesis is that LP compression is an artifact of constrained decoding's restricted token space.\nWe test this via controlled ablation: generating free-form (unconstrained) outputs on the same instances with post-hoc JSON parsing (parse rate 99.95\\%, 4406/4408; Table~\\ref{tab:freeform_ablation}).\nLP variance is essentially unchanged (within-instance std ratio $0.97{\\times}$, tied fraction 59.7\\%$\\to$57.7\\%).\nNER selection gains remain negligible ($+0.18$~pp free-form vs.\\ $+0.59$~pp constrained).\nThis rules out constrained decoding as the cause of compression and establishes LP compression as inherent to structured output generation.\nThe correlation-selection gap is therefore a fundamental challenge for test-time scaling in structured IE, not an artifact of any particular decoding strategy.\nNotably, the fine-tuned model achieved 99.95\\% parse rate without grammar constraints, suggesting that constrained decoding's format-compliance role may be redundant for sufficiently fine-tuned models.\n\n\\paragraph{RE task-specific interaction.}\nRE LP selection flips from $-0.68$~pp (constrained) to $+1.69$~pp (free-form), suggesting a task-specific interaction between decoding regime and selection efficacy that does not generalize to NER.\nFree-form decoding also slightly improves quality estimation (NER VC $\\rho$: 0.379$\\to$0.409), though this does not translate to selection gains.\n\n\\paragraph{Methodological implications.}\nThe decoupling of quality estimation ($\\rho$), binary discrimination (AUROC), and sample selection (best-of-$N$ F1) means evaluating on a single metric risks selecting the wrong signal for the intended use case.\nEffective selection likely requires per-sample signals such as trained verifiers \\cite{cobbe2021verifiers, venktesh2025trust}; $N$-scaling analysis (Appendix~\\ref{app:additional}) shows $N{=}8$ captures most quality estimation benefit.\n",
      "numLines": 39,
      "startLine": 1,
      "totalLines": 39
    }
  }
}
```

</details>

---

### Tool call

_source line 25_

<details open><summary>🔧 Tool call — Read · `toolu_016fFvV8hgfwmUZsTAnYqZTw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "0a945af5-faf9-4d3c-adf0-bcb803060520",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-15T11:33:34.043Z_

<details><summary>↩ Tool result · `toolu_016fFvV8hgfwmUZsTAnYqZTw`</summary>

```text
1	\section{Notation}\label{app:notation}
2	
3	Table~\ref{tab:notation} summarizes the notation used throughout the paper.
4	
5	\begin{table}[h]
6	\centering
7	\small
8	\begin{tabular}{cl}
9	\toprule
10	Symbol & Meaning \\
11	\midrule
12	$\mathcal{M}$ & Language model \\
13	$x$ & Input instance \\
14	$y_i$ & $i$-th stochastic sample \\
15	$N$ & Number of samples \\
16	$T$ & Sampling temperature \\
17	$c(\cdot)$ & Confidence signal \\
18	SJ & Soft Jaccard similarity \\
19	FK & Fleiss' $\kappa$ \\
20	EM & Exact-match voting rate \\
21	VC ($c_{\mathrm{vc}}$) & Entity voting confidence \\
22	LP ($c_{\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\
23	\bottomrule
24	\end{tabular}
25	\caption{Notation used throughout the paper.}
26	\label{tab:notation}
27	\end{table}
28	
29	\section{Robustness Analysis}\label{app:robustness}
30	
31	\begin{table}[t]
32	\centering
33	\small
34	\caption{Signal robustness across configurations (Spearman $\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\pm\sigma$). $^\dagger$Mean over 3 seeds ($\sigma{=}0.025$; individual: 0.428, 0.424, 0.384).}
35	\label{tab:robustness}
36	\begin{tabular}{llcc}
37	\toprule
38	& & NER $\rho$ & RE $\rho$ \\
39	\midrule
40	\multicolumn{4}{l}{\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\
41	\quad SJ & $T{=}0.7$ & 0.388 & 0.234 \\
42	\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\
43	\quad FK & $T{=}0.7$ & 0.321 & 0.184 \\
44	\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\
45	\midrule
46	\multicolumn{4}{l}{\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\
47	\quad SJ & $N{=}8$  & 0.360 & 0.250 \\
48	\quad SJ & $N{=}16$ & 0.412$^\dagger$ & 0.281 \\
49	\quad FK & $N{=}8$  & 0.267 & 0.275 \\
50	\quad FK & $N{=}16$ & 0.280 & 0.279 \\
51	\midrule
52	\multicolumn{4}{l}{\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\
53	\quad SJ &  & $0.463{\pm}0.007$ & --- \\
54	\quad FK &  & $0.455{\pm}0.006$ & --- \\
55	\quad EM &  & $0.460{\pm}0.008$ & --- \\
56	\quad VC &  & $0.458{\pm}0.003$ & --- \\
57	\quad LP &  & $0.310{\pm}0.005$ & --- \\
58	\bottomrule
59	\end{tabular}
60	\end{table}
61	
62	\begin{figure}[t]
63	\centering
64	\includegraphics[width=\columnwidth]{fig_temperature_robustness}
65	\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP $T{=}0.7$ data unavailable.}
66	\label{fig:temperature_robustness}
67	\end{figure}
68	
69	\paragraph{Temperature sensitivity.}
70	SJ NER $\rho$ shifts from 0.388 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.028 whose bootstrap confidence interval includes zero.
71	FK shows mixed behavior: NER $\rho$ drops by 0.054, while RE $\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.
72	Across all comparisons, the SJ--FK relative ordering is preserved at both temperatures on NER (0.388 vs.\ 0.321 at $T{=}0.7$; 0.360 vs.\ 0.267 at $T{=}1.0$), indicating a stable signal hierarchy despite numerically small temperature effects.
73	
74	\paragraph{Sample size scaling.}
75	Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\rho$ rises from 0.360 to $0.412{\pm}0.025$ (three seeds: 0.428, 0.424, 0.384), a gain of $+0.052$.
76	The magnitude of $N$-scaling gains is setting-dependent---LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$---though the direction is consistently positive.
77	LLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\Delta\rho{\approx}{+}0.030$ (range: $+0.027$ to $+0.032$) while LP gains only $+0.003$ (Table~\ref{tab:quality_estimation}).
78	FK $N$-scaling is inconsistent: degradation on SciERC ($-0.007$ to $-0.019$) but improvement on CoNLL with LLaMA ($+0.027$), suggesting sensitivity to both model and task characteristics.
79	VC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.062$ on Qwen SciERC), while LP is approximately $N$-invariant ($\Delta{\leq}0.021$).
80	SJ, EM, and VC scale consistently across all tested settings; only FK shows setting-dependent variation, suggesting that structural and binary-agreement signals are the most robust to $N$.
81	
82	\paragraph{Transfer across model families.}
83	LLaMA-3.1-8B-Instruct replicates the structural-over-surface ordering on SciERC NER (SJ $\rho{=}0.363$, FK $\rho{=}0.327$).
84	On CoNLL, the gap across model families is minimal (Table~\ref{tab:quality_estimation}): SJ achieves $\rho{=}0.431$ (LLaMA) vs.\ 0.436 (Qwen), $\Delta{=}0.005$.
85	At $N{=}16$, the structural-over-LP advantage holds across all four tested settings: Qwen SciERC (VC $\rho{=}0.411$ vs.\ LP 0.259, $\Delta{=}{+}0.152$), Qwen CoNLL (EM $\rho{=}0.463$ vs.\ LP 0.328, $\Delta{=}{+}0.135$), LLaMA SciERC (VC $\rho{=}0.452$ vs.\ LP 0.277, $\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\rho{=}0.463{\pm}0.007$ vs.\ LP $0.310{\pm}0.005$, $\Delta{=}{+}0.153$).
86	
87	\section{Calibration Analysis}\label{app:calibration}
88	
89	\begin{figure*}[t]
90	\centering
91	\includegraphics[width=\textwidth]{fig_reliability}
92	\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), reflecting the difficulty of calibrating confidence for compound extraction tasks.}
93	\label{fig:reliability}
94	\end{figure*}
95	
96	Reliability diagrams use 10 equal-width bins.
97	NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), indicating that translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.
98	
99	\section{Additional Analyses}\label{app:additional}
100	
101	\paragraph{Per-relation diagnostic.}
102	RE signal degradation is relation-specific.
103	\textsc{Feature-Of} has near-zero correlation ($\rho{=}0.004$), while \textsc{Hyponym-Of} achieves $\rho{=}0.646$.
104	The primary bottleneck is entity span errors, which account for 55.5\% of RE false negatives---a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.
105	We note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.
106	
107	\paragraph{Capability stratification.}
108	For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\rho{=}0.547$, compared to $\rho{=}0.415$ for 1--2 entities.
109	The SJ advantage over LP remains stable across sentence-length quartiles ($\Delta\rho{\approx}0.08$--$0.20$).
110	For RE, SJ $\rho$ increases monotonically with sentence length (Q1: 0.110 $\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$), indicating that longer, more relation-dense sentences provide richer structure for consistency-based estimation.
111	Both proxies are weakly correlated with F1 ($|r|{<}0.15$), confirming they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.
112	For RE, entity count and relation count are strongly correlated ($\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.
113	On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$---all far above the full-set levels.
114	Richer relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.
115	
116	\paragraph{Length vs.\ log-probability.}
117	Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
118	
119	\begin{figure}[t]
120	\centering
121	\includegraphics[width=\columnwidth]{fig_length_logprob_scatter}
122	\caption{Output length vs.\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\rho{=}0.386$; RE: $\rho{=}0.326$) rule out length-penalty confounding.}
123	\label{fig:length_logprob_scatter}
124	\end{figure}
125	
126	\paragraph{Evaluation circularity and LOO-SJ equivalence.}
127	Consensus-proximity selection chooses $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$.
128	Leave-one-out SJ (LOO-SJ) for sample $y_i$ is $\text{LOO-SJ}_i = \frac{1}{N-1}\sum_{j \neq i} \text{SJ}(y_i, y_j)$.
129	Since the $\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\arg\max_{y_i} \text{LOO-SJ}_i = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$, making the two selection rules equivalent.
130	Standard (non-LOO) SJ adds the self-comparison term $\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.
131	Empirically, LOO-SJ yields $\Delta\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\times}10^{-4}$ (negligible at the individual prediction level).
132	Evaluation circularity is negligible.
133	
134	\paragraph{Conditional filtering details.}
135	On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\rho{=}0.405$ while FK drops to $\rho{=}0.259$, confirming that structural advantage is robust across both models and evaluation conditions.
136	At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
137	EM ranks first across all four tested conditional configurations---SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$)---despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
138	On the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.
139	On the conditional set---where the model demonstrably produces varied outputs---exact agreement becomes the strongest quality signal.
140	The margin over SJ is largest on RE ($\Delta\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\Delta\rho{=}{+}0.002$), where all signals converge near $\rho{\approx}0.46$.
141	
142	\paragraph{WNUT-17 full signal analysis.}
143	Table~\ref{tab:wnut} reports all five signals on WNUT-17.
144	VC achieves $\rho{=}0.724$ (AUROC${=}0.913$) on the full set, but conditional analysis (non-zero F1 instances) reveals this is entirely driven by the zero/non-zero boundary: conditional $\rho{=}0.038$ ($p{=}0.49$).
145	LP shows the reverse pattern: full-set $\rho{=}{-}0.410$ but conditional $\rho{=}0.350$, the highest among all signals on the conditional set.
146	This inversion confirms that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
147	
148	\begin{table}[t]
149	\centering
150	\small
151	\caption{Quality estimation on WNUT-17 (Qwen, $N{=}8$, $T{=}1.0$, $n{=}689$ after filtering gold-empty instances). Cond: non-zero F1 instances ($n{=}334$). LP exhibits strong negative full-set $\rho$; its conditional $\rho$ reverses to the highest among all signals, confirming that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.}
152	\label{tab:wnut}
153	\begin{tabular}{lccccc}
154	\toprule
155	Signal & $\rho$ & $p$ & AUROC & Cond.\ $\rho$ & Cond.\ $p$ \\
156	\midrule
157	VC      & .724 & ${<}$1e-112 & .913 & .038 & .487 \\
158	FK      & .125 & .001 & .555 & .169 & .002 \\
159	SJ      & .089 & .020 & .517 & .288 & ${<}$1e-7 \\
160	EM      & .050 & .194 & .487 & .333 & ${<}$1e-9 \\
161	LP & $-$.410 & ${<}$1e-28 & .219 & .350 & ${<}$1e-10 \\
162	\bottomrule
163	\end{tabular}
164	\end{table}
165	
166	\paragraph{Cross-configuration selection analysis.}
167	Table~\ref{tab:cross_selection} extends the selection analysis to four additional configurations.
168	On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of greedy (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
169	On CoNLL, 57--88\% of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect (greedy F1 ${\approx}$0.91--0.92) rather than signal failure; selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
170	
171	\begin{table*}[t]
172	\centering
173	\small
174	\caption{Best-of-$N$ selection F1 across configurations ($T{=}1.0$). SJ: Soft Jaccard, FK: Fleiss' $\kappa$, EM: Exact Match, LP: Log-prob, VC: Voting Confidence. Best non-oracle signal per row in \textbf{bold}. No signal significantly outperforms greedy in any configuration; CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
175	\label{tab:cross_selection}
176	\begin{tabular}{llccccccc}
177	\toprule
178	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
179	\midrule
180	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
181	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
182	Qwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \textbf{.899} & .893 & .898 & .897 & .895 \\
183	LLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \textbf{.925} & .924 & .924 & .923 \\
184	\bottomrule
185	\end{tabular}
186	\end{table*}
187	
188	\paragraph{Diminishing returns of $N$-scaling.}
189	Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2024scaling}.
190	For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.052$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
191	Structural signals leverage $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, indicating diminishing information per additional comparison.
192	This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\rho{=}0.431$ on LLaMA CoNLL (vs.\ LP $\rho{=}0.307$, $\Delta{=}{+}0.124$), and the gap \textit{widens} at $N{=}16$ ($\Delta{=}{+}0.153$) because structural signals continue to benefit from additional pairwise evidence while LP does not.
193	For sample selection, additional samples increase the oracle upper bound---more draws raise the probability of a high-quality candidate---but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.
194	The practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.
195	
196	\section{Bootstrap CI for Signal Comparisons}\label{app:bootstrap_signal}
197	
198	Table~\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\rho$ and pairwise $\Delta\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).
199	The SJ--LP gap ($\Delta\rho{=}{+}0.155$) is clearly significant, confirming the structural advantage reported in \S\ref{sec:qe_results}.
200	The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant, indicating that these two structural signals perform comparably.
201	The SJ--EM gap ($\Delta\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.
202	
203	\begin{table}[t]
204	\centering
205	\small
206	\caption{Bootstrap 95\% CIs for signal $\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\Delta\rho$; ``Sig.'' indicates whether the 95\% CI excludes zero.}
207	\label{tab:bootstrap_signal_ci}
208	\begin{tabular}{lcc}
209	\toprule
210	Signal & $\rho$ & 95\% CI \\
211	\midrule
212	VC & +0.379 & [+0.299, +0.456] \\
213	SJ & +0.360 & [+0.277, +0.437] \\
214	EM & +0.295 & [+0.212, +0.371] \\
215	FK & +0.267 & [+0.176, +0.354] \\
216	LP & +0.205 & [+0.119, +0.291] \\
217	\bottomrule
218	\end{tabular}
219	
220	\vspace{0.5em}
221	
222	\begin{tabular}{lccc}
223	\toprule
224	Comparison & $\Delta\rho$ & 95\% CI & Sig. \\
225	\midrule
226	SJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\
227	VC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\
228	SJ $-$ EM & +0.065 & [+0.003, +0.130] & Marginal$^\dagger$ \\
229	\bottomrule
230	\end{tabular}
231	
232	\smallskip
233	{\footnotesize $^\dagger$Marginally significant without multiple comparison correction; would not survive Bonferroni correction for 10 pairwise comparisons ($\alpha_{\text{adj}}{=}0.005$).}
234	\end{table}
235	
236	\section{Diversity and Selection Analysis}\label{app:diversity}
237	
238	\paragraph{Output diversity quantification.}
239	Table~\ref{tab:diversity} summarizes output diversity across configurations.
240	On SciERC, output diversity is substantial: Qwen produces 43\% unique outputs per instance (mean 3.5 distinct out of $N{=}8$), with per-sample F1 standard deviation of 0.144 and mean pairwise SJ of 0.703.
241	LLaMA shows similar diversity (39\% unique, F1 std 0.11).
242	On CoNLL, diversity collapses: 57\% (Qwen) to 88\% (LLaMA) of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect where greedy F1 already exceeds 0.90.
243	WNUT-17 shows 55\% identical outputs, driven by the 52\% zero-F1 rate.
244	
245	\begin{table}[t]
246	\centering
247	\small
248	\caption{Output diversity across configurations ($N{=}8$, $T{=}1.0$). ``Identical'' = fraction of instances with all $N$ outputs identical. ``Unique'' = mean fraction of distinct outputs per instance.}
249	\label{tab:diversity}
250	\begin{tabular}{lcc}
251	\toprule
252	Config & Identical & Unique \\
253	\midrule
254	Qwen/SciERC & 11\% & 43\% \\
255	LLaMA/SciERC & 18\% & 39\% \\
256	Qwen/CoNLL & 57\% & --- \\
257	LLaMA/CoNLL & 88\% & --- \\
258	WNUT-17 & 55\% & --- \\
259	\bottomrule
260	\end{tabular}
261	\end{table}
262	
263	\paragraph{Oracle-improvable fraction.}
264	Across SciERC configurations, 39--42\% of instances contain at least one sample with F1 exceeding greedy: Qwen NER 42.0\% (222/529, mean headroom $+$31.9~pp among improvable instances), Qwen RE 41.3\% (164/397, $+$45.3~pp), LLaMA NER 39.3\% (208/529, $+$33.7~pp).
265	On CoNLL, only 4--9\% of instances are improvable, confirming the ceiling effect.
266	
267	\paragraph{Diversity-stratified selection gap.}
268	On the 44\% of Qwen SciERC instances with high diversity (${\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below greedy, and LP---the only per-sample signal---achieves merely $+$0.8~pp.
269	LLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below greedy and LP captures only $+$2.0~pp.
270	This rules out insufficient diversity as an explanation for the correlation-selection gap.
271	
272	\paragraph{TOST equivalence testing.}
273	The primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\% CI [$-$3.0, $+$4.2]~pp spanning zero.
274	Table~\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to greedy within a bound $\delta$.
275	The $\delta$ values are anchored to oracle headroom (13--18~pp): $\delta{=}5$~pp corresponds to forgoing 28--38\% of the available headroom, $\delta{=}3$~pp forgoing 17--23\%, and $\delta{=}2$~pp less than 15\%.
276	The breakpoint $\delta^*$---the minimum equivalence margin at which each signal passes TOST---ranges from approximately 1.3~pp (SJ, ${\sim}$10\% of oracle headroom) to 3.4~pp (FK, ${\sim}$26\%) on NER, and from approximately 2.9~pp (LP, ${\sim}$16\%) to 6.5~pp (VC, ${\sim}$36\%) on RE.
277	On NER ($n{=}529$), at $\delta{=}{\pm}2$~pp, SJ and LP are confirmed equivalent to greedy (TOST $p{<}0.05$); at $\delta{=}{\pm}3$~pp, four of five signals pass; at $\delta{=}{\pm}5$~pp, all five pass.
278	On RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\delta{=}{\pm}5$~pp due to systematic underperformance ($\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).
279	The effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.
280	
281	\begin{table}[t]
282	\centering
283	\small
284	\caption{TOST equivalence testing: signals vs.\ greedy on SciERC ($N{=}8$, $T{=}1.0$). \checkmark: equivalent at $p{<}0.05$; \texttimes: not equivalent. $\Delta$: mean F1 difference (signal $-$ greedy).}
285	\label{tab:tost}
286	\begin{tabular}{l cccc cccc}
287	\toprule
288	& \multicolumn{4}{c}{\textbf{NER}} & \multicolumn{4}{c}{\textbf{RE}} \\
289	\cmidrule(lr){2-5} \cmidrule(lr){6-9}
290	Signal & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 \\
291	\midrule
292	LP & +0.6 & \checkmark & \checkmark & \checkmark & $-$0.9 & \texttimes & \checkmark & \checkmark \\
293	SJ & +0.1 & \checkmark & \checkmark & \checkmark & $-$1.8 & \texttimes & \texttimes & \checkmark \\
294	FK & $-$0.5 & \texttimes & \checkmark & \checkmark & $-$1.6 & \texttimes & \texttimes & \checkmark \\
295	EM & $-$0.8 & \texttimes & \checkmark & \checkmark & $-$3.2 & \texttimes & \texttimes & \texttimes \\
296	VC & $-$1.0 & \texttimes & \texttimes & \checkmark & $-$4.5 & \texttimes & \texttimes & \texttimes \\
297	\bottomrule
298	\end{tabular}
299	\end{table}
300	
301	\section{Multi-Seed Stability}\label{app:multiseed}
302	
303	Table~\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC NER ($N{=}8$, $T{=}1.0$).
304	The signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\sigma{\leq}0.025$ for all signals, confirming that our findings are robust to random seed variation.
305	LLaMA absolute values are systematically lower than Qwen, consistent with the directionally-consistent-but-magnitude-dependent characterization in the main text.
306	
307	\begin{table}[t]
308	\centering
309	\small
310	\caption{Multi-seed quality estimation on SciERC NER ($N{=}8$, $T{=}1.0$, seeds: 42, 123, 456). Top: Spearman $\rho$; bottom: AUROC. Signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations ($\sigma{\leq}0.025$).}
311	\label{tab:multiseed}
312	\begin{tabular}{lccccc}
313	\toprule
314	& LP & FK & SJ & VC & EM \\
315	\midrule
316	\multicolumn{6}{l}{\textit{Spearman $\rho$ (mean $\pm\sigma$)}} \\
317	Qwen & .217${\pm}$.013 & .254${\pm}$.016 & .364${\pm}$.018 & .386${\pm}$.019 & .307${\pm}$.008 \\
318	LLaMA & .162${\pm}$.025 & .256${\pm}$.024 & .325${\pm}$.021 & .384${\pm}$.014 & .279${\pm}$.011 \\
319	\midrule
320	\multicolumn{6}{l}{\textit{AUROC (mean $\pm\sigma$)}} \\
321	Qwen & .613${\pm}$.002 & .618${\pm}$.009 & .684${\pm}$.009 & .697${\pm}$.010 & .661${\pm}$.010 \\
322	LLaMA & .577${\pm}$.007 & .616${\pm}$.011 & .655${\pm}$.010 & .689${\pm}$.005 & .636${\pm}$.006 \\
323	\bottomrule
324	\end{tabular}
325	\end{table}
326	
327	\section{Training Configuration}\label{app:training}
328	
329	Both models are fine-tuned with identical hyperparameters (Table~\ref{tab:training}) to ensure comparisons across model families reflect model differences rather than training confounds.
330	
331	\begin{table}[t]
332	\centering
333	\small
334	\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}
335	\label{tab:training}
336	\begin{tabular}{ll}
337	\toprule
338	Parameter & Value \\
339	\midrule
340	LoRA rank / $\alpha$ & 32 / 64 \\
341	LoRA target & All linear modules \\
342	LoRA dropout & 0 \\
343	Optimizer & AdamW \\
344	Learning rate & 2e-4, cosine schedule \\
345	Warmup ratio & 0.1 \\
346	Effective batch size & 16 (2 $\times$ grad.\ accum.\ 8) \\
347	Epochs & 5 \\
348	Max sequence length & 2048 \\
349	Precision & bf16 \\
350	Gradient checkpointing & Enabled \\
351	Max gradient norm & 1.0 \\
352	Training seed & 42 \\
353	Framework & LLaMA Factory \\
354	\midrule
355	\multicolumn{2}{l}{\textit{Dataset-specific}} \\
356	SciERC split & 1861 / 275 / 551 \\
357	CoNLL / WNUT & +\,load\_best\_model\_at\_end, \\
358	& eval\_steps${=}$200, save\_limit${=}$5 \\
359	\bottomrule
360	\end{tabular}
361	\end{table}
362	
363	\paragraph{Prompt template.}
364	For NER, we use a structured prompt:
365	\begin{quote}
366	\small
367	\texttt{System:} You are an expert in Named Entity Recognition.\\
368	\texttt{User:} Extract all named entities from the following text. Output as JSON.\\
369	Text: \texttt{\{input\_text\}}\\
370	Entity types: \texttt{\{schema\_types\}}
371	\end{quote}
372	RE follows the same structure with ``Relation Extraction'' and relation type lists substituted accordingly.
373	
374	\paragraph{Constrained decoding.}
375	Inference uses vLLM with XGrammar-based JSON schema enforcement \cite{willard2023guided}, which constrains outputs to valid entity/relation structures matching the target schema.
376	This eliminates format errors but may compress per-sample diversity by restricting the output space.\footnote{SciERC training used \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \texttt{enable\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \S\ref{sec:setup} and Limitations for discussion of this confound.}
377	
378	\section{Log-Probability Score Compression}\label{app:logprob_ties}
379	
380	Under constrained decoding, log-probability scores are severely compressed within instances, limiting per-sample discrimination (Table~\ref{tab:logprob_ties}).
381	The median within-instance LP range is only 0.041, and 75\% of pairwise comparisons are effective ties ($|\Delta|{<}0.026$).
382	At $\varepsilon{=}0.05$, 60.3\% of instances have a within-sample range below the threshold, leaving LP unable to meaningfully distinguish candidates.
383	For comparison, SJ has only 12.5\% tied instances at the same threshold---SJ's advantage over LP for selection is one of score resolution, not information content.
384	
385	\begin{table}[t]
386	\centering
387	\small
388	\caption{Log-probability score compression on SciERC NER ($N{=}8$, $n{=}529$). ``Tied'' = fraction of instances where within-instance LP range ${<}\varepsilon$.}
389	\label{tab:logprob_ties}
390	\begin{tabular}{lc}
391	\toprule
392	$\varepsilon$ threshold & Tied instances (\%) \\
393	\midrule
394	0.01 & 1.1\% \\
395	0.05 & 60.3\% \\
396	0.1  & ${\sim}$84\% \\
397	0.5  & ${\sim}$99\% \\
398	\bottomrule
399	\end{tabular}
400	\end{table}
401	
402	\paragraph{Non-tied subset.}
403	Among instances with LP range ${\geq}0.05$ ($n{=}210$, 40\% of total), log-probability selection \textit{significantly} outperforms greedy ($+2.9$~pp F1, $p{=}0.01$), and within-instance $\rho(\text{LP}, \text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).
404	This confirms that LP carries useful per-sample quality information but is resolution-limited---the signal exists but is compressed below the discrimination threshold for most instances.
405	A free-form decoding ablation (Appendix~\ref{app:freeform_ablation}) confirms this compression is intrinsic, not decoding-regime-specific.
406	
407	\section{RE Conditional Selection}\label{app:re_conditional_selection}
408	
409	Table~\ref{tab:re_cond_selection} extends the selection analysis to the RE non-zero F1 subset.
410	Of $n{=}397$ RE instances, 238 (60\%) have non-zero F1 and 159 (40\%) have zero F1.
411	All five signals underperform greedy on both subsets.
412	On the non-zero subset, selection performance is \textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\ $-4.5$~pp on full set), because greedy is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.
413	Oracle headroom exists (0.757 vs.\ 0.674) but no signal exploits it, ruling out the 40\% zero-F1 floor effect as the explanation for RE selection failure.
414	
415	\begin{table}[t]
416	\centering
417	\small
418	\caption{RE selection F1 on SciERC ($N{=}8$, $T{=}1.0$). Full set ($n{=}397$) and non-zero F1 subset ($n{=}238$). No signal outperforms greedy on either subset.}
419	\label{tab:re_cond_selection}
420	\begin{tabular}{lcc}
421	\toprule
422	Method & Full ($n{=}397$) & Non-zero ($n{=}238$) \\
423	\midrule
424	Oracle & 0.585 & 0.757 \\
425	\midrule
426	LP & 0.395 & 0.600 \\
427	SJ & 0.386 & 0.604 \\
428	EM & 0.372 & 0.583 \\
429	VC & 0.359 & 0.574 \\
430	\midrule
431	Greedy & 0.404 & 0.674 \\
432	\bottomrule
433	\end{tabular}
434	\end{table}
435	
436	\section{Free-Form Decoding Ablation}\label{app:freeform_ablation}
437	
438	Table~\ref{tab:freeform_ablation} compares constrained and free-form decoding on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B).
439	Free-form decoding removes grammar constraints entirely; outputs are parsed post-hoc (parse rate 99.95\%, 4406/4408).
440	LP score distributions are nearly identical across regimes (within-instance std ratio $0.97{\times}$), confirming that score compression is intrinsic to the model and task.
441	
442	\begin{table}[t]
443	\centering
444	\small
445	\caption{Constrained vs.\ free-form decoding ablation on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B). LP compression and selection failure persist under free-form decoding.}
446	\label{tab:freeform_ablation}
447	\begin{tabular}{lcc}
448	\toprule
449	Metric & Constrained & Free-form \\
450	\midrule
451	LP within-instance std & 0.0206 & 0.0199 \\
452	Tied fraction ($\varepsilon{=}0.05$) & 59.7\% & 57.7\% \\
453	NER LP selection $\Delta$F1 & $+$0.59~pp & $+$0.18~pp \\
454	RE LP selection $\Delta$F1 & $-$0.68~pp & $+$1.69~pp \\
455	NER VC $\rho$ & 0.379 & 0.409 \\
456	Parse rate & 100\% & 99.95\% \\
457	\bottomrule
458	\end{tabular}
459	\end{table}
460	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "024d38e6-6ae4-4c51-a551-000d3ade5c0c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\section{Notation}\\label{app:notation}\n\nTable~\\ref{tab:notation} summarizes the notation used throughout the paper.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{cl}\n\\toprule\nSymbol & Meaning \\\\\n\\midrule\n$\\mathcal{M}$ & Language model \\\\\n$x$ & Input instance \\\\\n$y_i$ & $i$-th stochastic sample \\\\\n$N$ & Number of samples \\\\\n$T$ & Sampling temperature \\\\\n$c(\\cdot)$ & Confidence signal \\\\\nSJ & Soft Jaccard similarity \\\\\nFK & Fleiss' $\\kappa$ \\\\\nEM & Exact-match voting rate \\\\\nVC ($c_{\\mathrm{vc}}$) & Entity voting confidence \\\\\nLP ($c_{\\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Notation used throughout the paper.}\n\\label{tab:notation}\n\\end{table}\n\n\\section{Robustness Analysis}\\label{app:robustness}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Signal robustness across configurations (Spearman $\\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\\pm\\sigma$). $^\\dagger$Mean over 3 seeds ($\\sigma{=}0.025$; individual: 0.428, 0.424, 0.384).}\n\\label{tab:robustness}\n\\begin{tabular}{llcc}\n\\toprule\n& & NER $\\rho$ & RE $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\\\\n\\quad SJ & $T{=}0.7$ & 0.388 & 0.234 \\\\\n\\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\\\\n\\quad FK & $T{=}0.7$ & 0.321 & 0.184 \\\\\n\\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\\\\n\\quad SJ & $N{=}8$  & 0.360 & 0.250 \\\\\n\\quad SJ & $N{=}16$ & 0.412$^\\dagger$ & 0.281 \\\\\n\\quad FK & $N{=}8$  & 0.267 & 0.275 \\\\\n\\quad FK & $N{=}16$ & 0.280 & 0.279 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\\\\n\\quad SJ &  & $0.463{\\pm}0.007$ & --- \\\\\n\\quad FK &  & $0.455{\\pm}0.006$ & --- \\\\\n\\quad EM &  & $0.460{\\pm}0.008$ & --- \\\\\n\\quad VC &  & $0.458{\\pm}0.003$ & --- \\\\\n\\quad LP &  & $0.310{\\pm}0.005$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_temperature_robustness}\n\\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP $T{=}0.7$ data unavailable.}\n\\label{fig:temperature_robustness}\n\\end{figure}\n\n\\paragraph{Temperature sensitivity.}\nSJ NER $\\rho$ shifts from 0.388 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.028 whose bootstrap confidence interval includes zero.\nFK shows mixed behavior: NER $\\rho$ drops by 0.054, while RE $\\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.\nAcross all comparisons, the SJ--FK relative ordering is preserved at both temperatures on NER (0.388 vs.\\ 0.321 at $T{=}0.7$; 0.360 vs.\\ 0.267 at $T{=}1.0$), indicating a stable signal hierarchy despite numerically small temperature effects.\n\n\\paragraph{Sample size scaling.}\nIncreasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.412{\\pm}0.025$ (three seeds: 0.428, 0.424, 0.384), a gain of $+0.052$.\nThe magnitude of $N$-scaling gains is setting-dependent---LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$---though the direction is consistently positive.\nLLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\\Delta\\rho{\\approx}{+}0.030$ (range: $+0.027$ to $+0.032$) while LP gains only $+0.003$ (Table~\\ref{tab:quality_estimation}).\nFK $N$-scaling is inconsistent: degradation on SciERC ($-0.007$ to $-0.019$) but improvement on CoNLL with LLaMA ($+0.027$), suggesting sensitivity to both model and task characteristics.\nVC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.062$ on Qwen SciERC), while LP is approximately $N$-invariant ($\\Delta{\\leq}0.021$).\nSJ, EM, and VC scale consistently across all tested settings; only FK shows setting-dependent variation, suggesting that structural and binary-agreement signals are the most robust to $N$.\n\n\\paragraph{Transfer across model families.}\nLLaMA-3.1-8B-Instruct replicates the structural-over-surface ordering on SciERC NER (SJ $\\rho{=}0.363$, FK $\\rho{=}0.327$).\nOn CoNLL, the gap across model families is minimal (Table~\\ref{tab:quality_estimation}): SJ achieves $\\rho{=}0.431$ (LLaMA) vs.\\ 0.436 (Qwen), $\\Delta{=}0.005$.\nAt $N{=}16$, the structural-over-LP advantage holds across all four tested settings: Qwen SciERC (VC $\\rho{=}0.411$ vs.\\ LP 0.259, $\\Delta{=}{+}0.152$), Qwen CoNLL (EM $\\rho{=}0.463$ vs.\\ LP 0.328, $\\Delta{=}{+}0.135$), LLaMA SciERC (VC $\\rho{=}0.452$ vs.\\ LP 0.277, $\\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\\rho{=}0.463{\\pm}0.007$ vs.\\ LP $0.310{\\pm}0.005$, $\\Delta{=}{+}0.153$).\n\n\\section{Calibration Analysis}\\label{app:calibration}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_reliability}\n\\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), reflecting the difficulty of calibrating confidence for compound extraction tasks.}\n\\label{fig:reliability}\n\\end{figure*}\n\nReliability diagrams use 10 equal-width bins.\nNER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), indicating that translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.\n\n\\section{Additional Analyses}\\label{app:additional}\n\n\\paragraph{Per-relation diagnostic.}\nRE signal degradation is relation-specific.\n\\textsc{Feature-Of} has near-zero correlation ($\\rho{=}0.004$), while \\textsc{Hyponym-Of} achieves $\\rho{=}0.646$.\nThe primary bottleneck is entity span errors, which account for 55.5\\% of RE false negatives---a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.\nWe note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.\n\n\\paragraph{Capability stratification.}\nFor NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\nThe SJ advantage over LP remains stable across sentence-length quartiles ($\\Delta\\rho{\\approx}0.08$--$0.20$).\nFor RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$), indicating that longer, more relation-dense sentences provide richer structure for consistency-based estimation.\nBoth proxies are weakly correlated with F1 ($|r|{<}0.15$), confirming they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.\nFor RE, entity count and relation count are strongly correlated ($\\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.\nOn the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$---all far above the full-set levels.\nRicher relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.\n\n\\paragraph{Length vs.\\ log-probability.}\nFigure~\\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\\rho{=}0.386$, $n{=}4{,}232$; RE: $\\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \\textit{higher}, not lower, token-averaged log-probability under constrained decoding.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_length_logprob_scatter}\n\\caption{Output length vs.\\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\\rho{=}0.386$; RE: $\\rho{=}0.326$) rule out length-penalty confounding.}\n\\label{fig:length_logprob_scatter}\n\\end{figure}\n\n\\paragraph{Evaluation circularity and LOO-SJ equivalence.}\nConsensus-proximity selection chooses $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nLeave-one-out SJ (LOO-SJ) for sample $y_i$ is $\\text{LOO-SJ}_i = \\frac{1}{N-1}\\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nSince the $\\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\\arg\\max_{y_i} \\text{LOO-SJ}_i = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$, making the two selection rules equivalent.\nStandard (non-LOO) SJ adds the self-comparison term $\\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.\nEmpirically, LOO-SJ yields $\\Delta\\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\\times}10^{-4}$ (negligible at the individual prediction level).\nEvaluation circularity is negligible.\n\n\\paragraph{Conditional filtering details.}\nOn LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, confirming that structural advantage is robust across both models and evaluation conditions.\nAt $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\nEM ranks first across all four tested conditional configurations---SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$)---despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).\nOn the full set, EM is diluted by trivial agreement: instances where all $N$ samples produce identical (possibly incorrect) outputs receive EM${=}1$ regardless of quality, compressing the signal's dynamic range.\nOn the conditional set---where the model demonstrably produces varied outputs---exact agreement becomes the strongest quality signal.\nThe margin over SJ is largest on RE ($\\Delta\\rho{=}{+}0.171$), where compound extraction decisions amplify output variability, and smallest on CoNLL LLaMA ($\\Delta\\rho{=}{+}0.002$), where all signals converge near $\\rho{\\approx}0.46$.\n\n\\paragraph{WNUT-17 full signal analysis.}\nTable~\\ref{tab:wnut} reports all five signals on WNUT-17.\nVC achieves $\\rho{=}0.724$ (AUROC${=}0.913$) on the full set, but conditional analysis (non-zero F1 instances) reveals this is entirely driven by the zero/non-zero boundary: conditional $\\rho{=}0.038$ ($p{=}0.49$).\nLP shows the reverse pattern: full-set $\\rho{=}{-}0.410$ but conditional $\\rho{=}0.350$, the highest among all signals on the conditional set.\nThis inversion confirms that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Quality estimation on WNUT-17 (Qwen, $N{=}8$, $T{=}1.0$, $n{=}689$ after filtering gold-empty instances). Cond: non-zero F1 instances ($n{=}334$). LP exhibits strong negative full-set $\\rho$; its conditional $\\rho$ reverses to the highest among all signals, confirming that full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.}\n\\label{tab:wnut}\n\\begin{tabular}{lccccc}\n\\toprule\nSignal & $\\rho$ & $p$ & AUROC & Cond.\\ $\\rho$ & Cond.\\ $p$ \\\\\n\\midrule\nVC      & .724 & ${<}$1e-112 & .913 & .038 & .487 \\\\\nFK      & .125 & .001 & .555 & .169 & .002 \\\\\nSJ      & .089 & .020 & .517 & .288 & ${<}$1e-7 \\\\\nEM      & .050 & .194 & .487 & .333 & ${<}$1e-9 \\\\\nLP & $-$.410 & ${<}$1e-28 & .219 & .350 & ${<}$1e-10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Cross-configuration selection analysis.}\nTable~\\ref{tab:cross_selection} extends the selection analysis to four additional configurations.\nOn LLaMA SciERC, where output diversity remains substantial (18\\% identical outputs, 39\\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of greedy (0.646), replicating the gap observed on Qwen SciERC (Table~\\ref{tab:selection}).\nOn CoNLL, 57--88\\% of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect (greedy F1 ${\\approx}$0.91--0.92) rather than signal failure; selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 across configurations ($T{=}1.0$). SJ: Soft Jaccard, FK: Fleiss' $\\kappa$, EM: Exact Match, LP: Log-prob, VC: Voting Confidence. Best non-oracle signal per row in \\textbf{bold}. No signal significantly outperforms greedy in any configuration; CoNLL shows especially tight clustering where greedy already exceeds 0.90.}\n\\label{tab:cross_selection}\n\\begin{tabular}{llccccccc}\n\\toprule\nConfig & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\\\\n\\midrule\nLLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \\textbf{.652} & .633 \\\\\nLLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \\textbf{.649} & \\textbf{.649} & .640 & .646 & .640 \\\\\nQwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .948 & \\textbf{.899} & .893 & .898 & .897 & .895 \\\\\nLLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \\textbf{.925} & .924 & .924 & .923 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\paragraph{Diminishing returns of $N$-scaling.}\nOur $N{=}8$ and $N{=}16$ comparisons (Table~\\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \\cite{brown2024monkeys, snell2024scaling}.\nFor quality estimation, structural signals benefit consistently but sublinearly: SJ $\\rho$ improves by $+0.052$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\\Delta\\rho{\\leq}0.021$).\nStructural signals leverage $\\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\\rho$ improvement is far less than proportional, indicating diminishing information per additional comparison.\nThis asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\\rho{=}0.431$ on LLaMA CoNLL (vs.\\ LP $\\rho{=}0.307$, $\\Delta{=}{+}0.124$), and the gap \\textit{widens} at $N{=}16$ ($\\Delta{=}{+}0.153$) because structural signals continue to benefit from additional pairwise evidence while LP does not.\nFor sample selection, additional samples increase the oracle upper bound---more draws raise the probability of a high-quality candidate---but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.\nThe practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.\n\n\\section{Bootstrap CI for Signal Comparisons}\\label{app:bootstrap_signal}\n\nTable~\\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\\rho$ and pairwise $\\Delta\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).\nThe SJ--LP gap ($\\Delta\\rho{=}{+}0.155$) is clearly significant, confirming the structural advantage reported in \\S\\ref{sec:qe_results}.\nThe VC--SJ gap ($\\Delta\\rho{=}{+}0.019$) is not significant, indicating that these two structural signals perform comparably.\nThe SJ--EM gap ($\\Delta\\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Bootstrap 95\\% CIs for signal $\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$). Top: individual signals. Bottom: pairwise $\\Delta\\rho$; ``Sig.'' indicates whether the 95\\% CI excludes zero.}\n\\label{tab:bootstrap_signal_ci}\n\\begin{tabular}{lcc}\n\\toprule\nSignal & $\\rho$ & 95\\% CI \\\\\n\\midrule\nVC & +0.379 & [+0.299, +0.456] \\\\\nSJ & +0.360 & [+0.277, +0.437] \\\\\nEM & +0.295 & [+0.212, +0.371] \\\\\nFK & +0.267 & [+0.176, +0.354] \\\\\nLP & +0.205 & [+0.119, +0.291] \\\\\n\\bottomrule\n\\end{tabular}\n\n\\vspace{0.5em}\n\n\\begin{tabular}{lccc}\n\\toprule\nComparison & $\\Delta\\rho$ & 95\\% CI & Sig. \\\\\n\\midrule\nSJ $-$ LP & +0.155 & [+0.074, +0.234] & Yes \\\\\nVC $-$ SJ & +0.019 & [$-$0.033, +0.073] & No \\\\\nSJ $-$ EM & +0.065 & [+0.003, +0.130] & Marginal$^\\dagger$ \\\\\n\\bottomrule\n\\end{tabular}\n\n\\smallskip\n{\\footnotesize $^\\dagger$Marginally significant without multiple comparison correction; would not survive Bonferroni correction for 10 pairwise comparisons ($\\alpha_{\\text{adj}}{=}0.005$).}\n\\end{table}\n\n\\section{Diversity and Selection Analysis}\\label{app:diversity}\n\n\\paragraph{Output diversity quantification.}\nTable~\\ref{tab:diversity} summarizes output diversity across configurations.\nOn SciERC, output diversity is substantial: Qwen produces 43\\% unique outputs per instance (mean 3.5 distinct out of $N{=}8$), with per-sample F1 standard deviation of 0.144 and mean pairwise SJ of 0.703.\nLLaMA shows similar diversity (39\\% unique, F1 std 0.11).\nOn CoNLL, diversity collapses: 57\\% (Qwen) to 88\\% (LLaMA) of instances produce identical outputs across all $N$ samples, reflecting a ceiling effect where greedy F1 already exceeds 0.90.\nWNUT-17 shows 55\\% identical outputs, driven by the 52\\% zero-F1 rate.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Output diversity across configurations ($N{=}8$, $T{=}1.0$). ``Identical'' = fraction of instances with all $N$ outputs identical. ``Unique'' = mean fraction of distinct outputs per instance.}\n\\label{tab:diversity}\n\\begin{tabular}{lcc}\n\\toprule\nConfig & Identical & Unique \\\\\n\\midrule\nQwen/SciERC & 11\\% & 43\\% \\\\\nLLaMA/SciERC & 18\\% & 39\\% \\\\\nQwen/CoNLL & 57\\% & --- \\\\\nLLaMA/CoNLL & 88\\% & --- \\\\\nWNUT-17 & 55\\% & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Oracle-improvable fraction.}\nAcross SciERC configurations, 39--42\\% of instances contain at least one sample with F1 exceeding greedy: Qwen NER 42.0\\% (222/529, mean headroom $+$31.9~pp among improvable instances), Qwen RE 41.3\\% (164/397, $+$45.3~pp), LLaMA NER 39.3\\% (208/529, $+$33.7~pp).\nOn CoNLL, only 4--9\\% of instances are improvable, confirming the ceiling effect.\n\n\\paragraph{Diversity-stratified selection gap.}\nOn the 44\\% of Qwen SciERC instances with high diversity (${\\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below greedy, and LP---the only per-sample signal---achieves merely $+$0.8~pp.\nLLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below greedy and LP captures only $+$2.0~pp.\nThis rules out insufficient diversity as an explanation for the correlation-selection gap.\n\n\\paragraph{TOST equivalence testing.}\nThe primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\\% CI [$-$3.0, $+$4.2]~pp spanning zero.\nTable~\\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to greedy within a bound $\\delta$.\nThe $\\delta$ values are anchored to oracle headroom (13--18~pp): $\\delta{=}5$~pp corresponds to forgoing 28--38\\% of the available headroom, $\\delta{=}3$~pp forgoing 17--23\\%, and $\\delta{=}2$~pp less than 15\\%.\nThe breakpoint $\\delta^*$---the minimum equivalence margin at which each signal passes TOST---ranges from approximately 1.3~pp (SJ, ${\\sim}$10\\% of oracle headroom) to 3.4~pp (FK, ${\\sim}$26\\%) on NER, and from approximately 2.9~pp (LP, ${\\sim}$16\\%) to 6.5~pp (VC, ${\\sim}$36\\%) on RE.\nOn NER ($n{=}529$), at $\\delta{=}{\\pm}2$~pp, SJ and LP are confirmed equivalent to greedy (TOST $p{<}0.05$); at $\\delta{=}{\\pm}3$~pp, four of five signals pass; at $\\delta{=}{\\pm}5$~pp, all five pass.\nOn RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\\delta{=}{\\pm}5$~pp due to systematic underperformance ($\\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).\nThe effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{TOST equivalence testing: signals vs.\\ greedy on SciERC ($N{=}8$, $T{=}1.0$). \\checkmark: equivalent at $p{<}0.05$; \\texttimes: not equivalent. $\\Delta$: mean F1 difference (signal $-$ greedy).}\n\\label{tab:tost}\n\\begin{tabular}{l cccc cccc}\n\\toprule\n& \\multicolumn{4}{c}{\\textbf{NER}} & \\multicolumn{4}{c}{\\textbf{RE}} \\\\\n\\cmidrule(lr){2-5} \\cmidrule(lr){6-9}\nSignal & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 \\\\\n\\midrule\nLP & +0.6 & \\checkmark & \\checkmark & \\checkmark & $-$0.9 & \\texttimes & \\checkmark & \\checkmark \\\\\nSJ & +0.1 & \\checkmark & \\checkmark & \\checkmark & $-$1.8 & \\texttimes & \\texttimes & \\checkmark \\\\\nFK & $-$0.5 & \\texttimes & \\checkmark & \\checkmark & $-$1.6 & \\texttimes & \\texttimes & \\checkmark \\\\\nEM & $-$0.8 & \\texttimes & \\checkmark & \\checkmark & $-$3.2 & \\texttimes & \\texttimes & \\texttimes \\\\\nVC & $-$1.0 & \\texttimes & \\texttimes & \\checkmark & $-$4.5 & \\texttimes & \\texttimes & \\texttimes \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Multi-Seed Stability}\\label{app:multiseed}\n\nTable~\\ref{tab:multiseed} reports quality estimation metrics across three random seeds for both model families on SciERC NER ($N{=}8$, $T{=}1.0$).\nThe signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations, with $\\sigma{\\leq}0.025$ for all signals, confirming that our findings are robust to random seed variation.\nLLaMA absolute values are systematically lower than Qwen, consistent with the directionally-consistent-but-magnitude-dependent characterization in the main text.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Multi-seed quality estimation on SciERC NER ($N{=}8$, $T{=}1.0$, seeds: 42, 123, 456). Top: Spearman $\\rho$; bottom: AUROC. Signal ranking VC${>}$SJ${>}$EM${>}$FK${>}$LP is identical across all six model-seed combinations ($\\sigma{\\leq}0.025$).}\n\\label{tab:multiseed}\n\\begin{tabular}{lccccc}\n\\toprule\n& LP & FK & SJ & VC & EM \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{Spearman $\\rho$ (mean $\\pm\\sigma$)}} \\\\\nQwen & .217${\\pm}$.013 & .254${\\pm}$.016 & .364${\\pm}$.018 & .386${\\pm}$.019 & .307${\\pm}$.008 \\\\\nLLaMA & .162${\\pm}$.025 & .256${\\pm}$.024 & .325${\\pm}$.021 & .384${\\pm}$.014 & .279${\\pm}$.011 \\\\\n\\midrule\n\\multicolumn{6}{l}{\\textit{AUROC (mean $\\pm\\sigma$)}} \\\\\nQwen & .613${\\pm}$.002 & .618${\\pm}$.009 & .684${\\pm}$.009 & .697${\\pm}$.010 & .661${\\pm}$.010 \\\\\nLLaMA & .577${\\pm}$.007 & .616${\\pm}$.011 & .655${\\pm}$.010 & .689${\\pm}$.005 & .636${\\pm}$.006 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Training Configuration}\\label{app:training}\n\nBoth models are fine-tuned with identical hyperparameters (Table~\\ref{tab:training}) to ensure comparisons across model families reflect model differences rather than training confounds.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Training configuration. Both Qwen3-8B and LLaMA-3.1-8B-Instruct use identical settings unless noted.}\n\\label{tab:training}\n\\begin{tabular}{ll}\n\\toprule\nParameter & Value \\\\\n\\midrule\nLoRA rank / $\\alpha$ & 32 / 64 \\\\\nLoRA target & All linear modules \\\\\nLoRA dropout & 0 \\\\\nOptimizer & AdamW \\\\\nLearning rate & 2e-4, cosine schedule \\\\\nWarmup ratio & 0.1 \\\\\nEffective batch size & 16 (2 $\\times$ grad.\\ accum.\\ 8) \\\\\nEpochs & 5 \\\\\nMax sequence length & 2048 \\\\\nPrecision & bf16 \\\\\nGradient checkpointing & Enabled \\\\\nMax gradient norm & 1.0 \\\\\nTraining seed & 42 \\\\\nFramework & LLaMA Factory \\\\\n\\midrule\n\\multicolumn{2}{l}{\\textit{Dataset-specific}} \\\\\nSciERC split & 1861 / 275 / 551 \\\\\nCoNLL / WNUT & +\\,load\\_best\\_model\\_at\\_end, \\\\\n& eval\\_steps${=}$200, save\\_limit${=}$5 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Prompt template.}\nFor NER, we use a structured prompt:\n\\begin{quote}\n\\small\n\\texttt{System:} You are an expert in Named Entity Recognition.\\\\\n\\texttt{User:} Extract all named entities from the following text. Output as JSON.\\\\\nText: \\texttt{\\{input\\_text\\}}\\\\\nEntity types: \\texttt{\\{schema\\_types\\}}\n\\end{quote}\nRE follows the same structure with ``Relation Extraction'' and relation type lists substituted accordingly.\n\n\\paragraph{Constrained decoding.}\nInference uses vLLM with XGrammar-based JSON schema enforcement \\cite{willard2023guided}, which constrains outputs to valid entity/relation structures matching the target schema.\nThis eliminates format errors but may compress per-sample diversity by restricting the output space.\\footnote{SciERC training used \\texttt{enable\\_thinking=True} (LLaMA Factory 0.9.4 default), injecting empty \\texttt{&lt;think>&lt;/think>} blocks (4--5 tokens) into each training response with loss computation; CoNLL and WNUT explicitly set \\texttt{enable\\_thinking=False}. Constrained decoding at inference time enforces JSON-only output, suppressing thinking tokens. See \\S\\ref{sec:setup} and Limitations for discussion of this confound.}\n\n\\section{Log-Probability Score Compression}\\label{app:logprob_ties}\n\nUnder constrained decoding, log-probability scores are severely compressed within instances, limiting per-sample discrimination (Table~\\ref{tab:logprob_ties}).\nThe median within-instance LP range is only 0.041, and 75\\% of pairwise comparisons are effective ties ($|\\Delta|{<}0.026$).\nAt $\\varepsilon{=}0.05$, 60.3\\% of instances have a within-sample range below the threshold, leaving LP unable to meaningfully distinguish candidates.\nFor comparison, SJ has only 12.5\\% tied instances at the same threshold---SJ's advantage over LP for selection is one of score resolution, not information content.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Log-probability score compression on SciERC NER ($N{=}8$, $n{=}529$). ``Tied'' = fraction of instances where within-instance LP range ${<}\\varepsilon$.}\n\\label{tab:logprob_ties}\n\\begin{tabular}{lc}\n\\toprule\n$\\varepsilon$ threshold & Tied instances (\\%) \\\\\n\\midrule\n0.01 & 1.1\\% \\\\\n0.05 & 60.3\\% \\\\\n0.1  & ${\\sim}$84\\% \\\\\n0.5  & ${\\sim}$99\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Non-tied subset.}\nAmong instances with LP range ${\\geq}0.05$ ($n{=}210$, 40\\% of total), log-probability selection \\textit{significantly} outperforms greedy ($+2.9$~pp F1, $p{=}0.01$), and within-instance $\\rho(\\text{LP}, \\text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).\nThis confirms that LP carries useful per-sample quality information but is resolution-limited---the signal exists but is compressed below the discrimination threshold for most instances.\nA free-form decoding ablation (Appendix~\\ref{app:freeform_ablation}) confirms this compression is intrinsic, not decoding-regime-specific.\n\n\\section{RE Conditional Selection}\\label{app:re_conditional_selection}\n\nTable~\\ref{tab:re_cond_selection} extends the selection analysis to the RE non-zero F1 subset.\nOf $n{=}397$ RE instances, 238 (60\\%) have non-zero F1 and 159 (40\\%) have zero F1.\nAll five signals underperform greedy on both subsets.\nOn the non-zero subset, selection performance is \\textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\\ $-4.5$~pp on full set), because greedy is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.\nOracle headroom exists (0.757 vs.\\ 0.674) but no signal exploits it, ruling out the 40\\% zero-F1 floor effect as the explanation for RE selection failure.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{RE selection F1 on SciERC ($N{=}8$, $T{=}1.0$). Full set ($n{=}397$) and non-zero F1 subset ($n{=}238$). No signal outperforms greedy on either subset.}\n\\label{tab:re_cond_selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Full ($n{=}397$) & Non-zero ($n{=}238$) \\\\\n\\midrule\nOracle & 0.585 & 0.757 \\\\\n\\midrule\nLP & 0.395 & 0.600 \\\\\nSJ & 0.386 & 0.604 \\\\\nEM & 0.372 & 0.583 \\\\\nVC & 0.359 & 0.574 \\\\\n\\midrule\nGreedy & 0.404 & 0.674 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\section{Free-Form Decoding Ablation}\\label{app:freeform_ablation}\n\nTable~\\ref{tab:freeform_ablation} compares constrained and free-form decoding on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B).\nFree-form decoding removes grammar constraints entirely; outputs are parsed post-hoc (parse rate 99.95\\%, 4406/4408).\nLP score distributions are nearly identical across regimes (within-instance std ratio $0.97{\\times}$), confirming that score compression is intrinsic to the model and task.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Constrained vs.\\ free-form decoding ablation on SciERC ($N{=}8$, $T{=}1.0$, Qwen3-8B). LP compression and selection failure persist under free-form decoding.}\n\\label{tab:freeform_ablation}\n\\begin{tabular}{lcc}\n\\toprule\nMetric & Constrained & Free-form \\\\\n\\midrule\nLP within-instance std & 0.0206 & 0.0199 \\\\\nTied fraction ($\\varepsilon{=}0.05$) & 59.7\\% & 57.7\\% \\\\\nNER LP selection $\\Delta$F1 & $+$0.59~pp & $+$0.18~pp \\\\\nRE LP selection $\\Delta$F1 & $-$0.68~pp & $+$1.69~pp \\\\\nNER VC $\\rho$ & 0.379 & 0.409 \\\\\nParse rate & 100\\% & 99.95\\% \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n",
      "numLines": 460,
      "startLine": 1,
      "totalLines": 460
    }
  }
}
```

</details>

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Read · `toolu_01UZ8PkzW14HoeYcyynM3FVh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "13b1cefa-cdb9-45ac-8028-8e9c472cc007",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-15T11:33:34.783Z_

<details><summary>↩ Tool result · `toolu_01UZ8PkzW14HoeYcyynM3FVh`</summary>

```text
1	Our evaluation covers three datasets but only one RE benchmark (SciERC), where 40\% of instances receive zero F1, compressing the discriminable range and limiting signal differentiation for relation extraction.
2	RE selection failure persists even when restricting to non-zero F1 instances (Appendix~\ref{app:re_conditional_selection}), ruling out floor effects as the sole explanation, but generalization to other RE benchmarks remains unvalidated.
3	WNUT-17 confirms the capability boundary of our approach, but our positive results on formal-domain text (CoNLL, SciERC) have not been validated on informal or noisy text where models achieve non-trivial performance.
4	
5	We evaluate two model families (Qwen3-8B and LLaMA-3.1-8B), both at 8B parameters.
6	A 3-seed robustness analysis confirms that signal rankings are stable across seeds ($\sigma{\leq}0.025$; Table~\ref{tab:multiseed}), but whether our findings---particularly the correlation-selection gap and the difficulty-dependent signal ordering---hold for larger models (70B+) or closed-source APIs remains untested.
7	Larger models may produce higher-quality and more diverse samples, potentially altering the signal landscape.
8	
9	Our analysis of selection potential uses only unsupervised signals.
10	We do not train a dedicated verifier or reward model, leaving unknown how much of the oracle headroom a supervised approach could recover.
11	
12	We evaluate at $N{=}8$ and $N{=}16$.
13	The behavior of confidence signals at larger sample sizes (e.g., $N{=}64$ or $N{=}128$) is unknown, and $N$-scaling gains are setting-dependent: SJ improves by $+0.052$ on Qwen SciERC NER but only $+0.016$ on LLaMA SciERC NER when doubling from $N{=}8$ to $N{=}16$.
14	
15	On CoNLL with LLaMA, the SJ--FK gap is only 0.003 ($\rho{=}0.431$ vs.\ $0.428$), so the structural advantage over surface signals may not generalize to all simple-schema datasets.
16	Our free-form ablation (\S\ref{sec:ablation}) confirms that LP score compression persists without constrained decoding, but was conducted on a single dataset (SciERC) with one model (Qwen3-8B); whether the intrinsic compression finding generalizes to other datasets, model families, or model scales remains untested.
17	
18	Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking} active, injecting empty \texttt{&lt;think>&lt;/think>} blocks (4--5 tokens, no reasoning chain) before each response; CoNLL and WNUT checkpoints disabled this feature.
19	At inference time, constrained decoding suppresses thinking tokens in all configurations, so they do not appear in generated samples.
20	The empty blocks may weakly affect first-token probability distributions during training, but the absence of any reasoning content limits their representational impact; we do not expect this inconsistency to alter our quantitative conclusions.
21	
22	Finally, log-probability was excluded from the temperature comparison ($T{=}0.7$ vs.\ $T{=}1.0$) due to missing $T{=}0.7$ LP data, leaving its temperature sensitivity uncharacterized.
23	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "5ee6992f-33bb-439e-a0af-0fbbec780eda",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex",
      "content": "Our evaluation covers three datasets but only one RE benchmark (SciERC), where 40\\% of instances receive zero F1, compressing the discriminable range and limiting signal differentiation for relation extraction.\nRE selection failure persists even when restricting to non-zero F1 instances (Appendix~\\ref{app:re_conditional_selection}), ruling out floor effects as the sole explanation, but generalization to other RE benchmarks remains unvalidated.\nWNUT-17 confirms the capability boundary of our approach, but our positive results on formal-domain text (CoNLL, SciERC) have not been validated on informal or noisy text where models achieve non-trivial performance.\n\nWe evaluate two model families (Qwen3-8B and LLaMA-3.1-8B), both at 8B parameters.\nA 3-seed robustness analysis confirms that signal rankings are stable across seeds ($\\sigma{\\leq}0.025$; Table~\\ref{tab:multiseed}), but whether our findings---particularly the correlation-selection gap and the difficulty-dependent signal ordering---hold for larger models (70B+) or closed-source APIs remains untested.\nLarger models may produce higher-quality and more diverse samples, potentially altering the signal landscape.\n\nOur analysis of selection potential uses only unsupervised signals.\nWe do not train a dedicated verifier or reward model, leaving unknown how much of the oracle headroom a supervised approach could recover.\n\nWe evaluate at $N{=}8$ and $N{=}16$.\nThe behavior of confidence signals at larger sample sizes (e.g., $N{=}64$ or $N{=}128$) is unknown, and $N$-scaling gains are setting-dependent: SJ improves by $+0.052$ on Qwen SciERC NER but only $+0.016$ on LLaMA SciERC NER when doubling from $N{=}8$ to $N{=}16$.\n\nOn CoNLL with LLaMA, the SJ--FK gap is only 0.003 ($\\rho{=}0.431$ vs.\\ $0.428$), so the structural advantage over surface signals may not generalize to all simple-schema datasets.\nOur free-form ablation (\\S\\ref{sec:ablation}) confirms that LP score compression persists without constrained decoding, but was conducted on a single dataset (SciERC) with one model (Qwen3-8B); whether the intrinsic compression finding generalizes to other datasets, model families, or model scales remains untested.\n\nQwen3-8B's SciERC checkpoint was trained with \\texttt{enable\\_thinking} active, injecting empty \\texttt{&lt;think>&lt;/think>} blocks (4--5 tokens, no reasoning chain) before each response; CoNLL and WNUT checkpoints disabled this feature.\nAt inference time, constrained decoding suppresses thinking tokens in all configurations, so they do not appear in generated samples.\nThe empty blocks may weakly affect first-token probability distributions during training, but the absence of any reasoning content limits their representational impact; we do not expect this inconsistency to alter our quantitative conclusions.\n\nFinally, log-probability was excluded from the temperature comparison ($T{=}0.7$ vs.\\ $T{=}1.0$) due to missing $T{=}0.7$ LP data, leaving its temperature sensitivity uncharacterized.\n",
      "numLines": 23,
      "startLine": 1,
      "totalLines": 23
    }
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — Read · `toolu_01FvMpag4aPzUve5CkteiMsF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "ae6a246c-bec0-4fc4-be7b-c372593b141d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-15T11:33:35.252Z_

<details><summary>↩ Tool result · `toolu_01FvMpag4aPzUve5CkteiMsF`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	\paragraph{Datasets.}
8	We evaluate on three English IE benchmarks spanning a difficulty gradient.
9	\textbf{SciERC} \cite{luan2018scierc} contains 551 test instances annotated for joint NER (6 types) and RE (7 types).
10	\textbf{CoNLL-2003} \cite{tjongkimsang2003conll} provides 3{,}453 test sentences with 4 entity types, where models achieve ${\approx}$91\% micro F1.
11	\textbf{WNUT-17} \cite{derczynski2017wnut} consists of 1{,}287 social media instances with emerging entities, used to probe method boundaries (52\% zero F1).
12	
13	\paragraph{Models and sampling.}
14	Both \textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\alpha{=}64$) for 5 epochs using LLaMA Factory \cite{zheng2024llamafactory} under identical training procedures, ensuring comparisons across the two model families (both at 8B scale) reflect model differences rather than training confounds.
15	We note a training confound for SciERC: Qwen3-8B's SciERC checkpoint was trained with \texttt{enable\_thinking=True} (LLaMA Factory 0.9.4 default), which prepends empty \texttt{&lt;think>\textbackslash n&lt;/think>} blocks (4--5 tokens) to each training response and includes them in the loss computation; CoNLL-2003 and WNUT-17 checkpoints explicitly set \texttt{enable\_thinking=False}.
16	No reasoning content is present (the blocks are always empty), and constrained decoding at inference time enforces JSON-only output, so thinking tokens do not appear in generated samples.
17	This constitutes a minor train--test distribution mismatch for SciERC ($<$0.3\% of the 2048-token training window); CoNLL-2003 and WNUT-17 are unaffected.
18	We discuss implications in the Limitations section.
19	We draw $N{=}8$ samples at $T{=}1.0$ (primary; single seed, seed${=}42$), with $N{=}16$ for scaling experiments.\footnote{$N{=}16$ results for CoNLL (Qwen) and SciERC (LLaMA) are in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}). A 3-seed stability analysis ($\sigma{\leq}0.025$; Table~\ref{tab:multiseed}, Appendix~\ref{app:multiseed}) confirms that signal rankings are identical across seeds.}
20	Quality estimation uses Spearman $\rho$ and AUROC; downstream utility uses best-of-$N$ selection F1 with exact span matching (NER) and head-tail-label matching (RE).
21	Inference uses vLLM with constrained decoding \cite{willard2023guided}.
22	
23	%% ============================================================
24	\subsection{Quality Estimation Results}
25	\label{sec:qe_results}
26	
27	\begin{table*}[t]
28	\centering
29	\small
30	\caption{Quality estimation across tasks and models (Spearman $\rho$ and AUROC; $N{=}8$, seed${=}42$). Best value per column in \textbf{bold}. SciERC evaluates joint NER (6 types) and RE (7 types, single benchmark---preliminary); CoNLL evaluates NER (4 types). $N{=}16$ results appear in Table~\ref{tab:robustness} (Appendix~\ref{app:robustness}).}
31	\label{tab:quality_estimation}
32	\begin{tabular}{ll cc cc cc cc}
33	\toprule
34	& & \multicolumn{2}{c}{\textbf{SciERC NER}} & \multicolumn{2}{c}{\textbf{SciERC RE}} & \multicolumn{2}{c}{\textbf{CoNLL (Qwen)}} & \multicolumn{2}{c}{\textbf{CoNLL (LLaMA)}} \\
35	\cmidrule(lr){3-4} \cmidrule(lr){5-6} \cmidrule(lr){7-8} \cmidrule(lr){9-10}
36	Signal & Family & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC \\
37	\midrule
38	VC & Structural & \textbf{.379} & .684 & \textbf{.350} & .693 & .424 & .789 & .426 & .709 \\
39	SJ  & Structural & .360 & .692 & .250 & .670 & .436 & .801 & \textbf{.431} & .704 \\
40	FK & Surface & .267 & .629 & .275 & .609 & .400 & .774 & .428 & .703 \\
41	EM  & Surface    & .295 & \textbf{.749} & .134 & \textbf{.706} & \textbf{.451} & \textbf{.816} & \textbf{.431} & .705 \\
42	LP     & Model      & .205 & .578 & .266 & .600 & .316 & .753 & .307 & \textbf{.761} \\
43	\bottomrule
44	\end{tabular}
45	\end{table*}
46	
47	\begin{figure*}[t]
48	\centering
49	\includegraphics[width=\textwidth]{fig_signal_heatmap}
50	\caption{Quality estimation heatmap (Spearman $\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$), while LP RE collapses to near-zero ($\rho{=}0.011$).}
51	\label{fig:signal_heatmap}
52	\end{figure*}
53	
54	Table~\ref{tab:quality_estimation} presents rank correlation ($\rho$) and AUROC for five confidence signals across tasks and models.
55	
56	\paragraph{Difficulty-dependent signal complementarity.}
57	On SciERC NER (complex schema, 6 types), structural signals lead: VC achieves $\rho{=}0.379$ and SJ $\rho{=}0.360$, both outperforming surface ($\rho{\leq}0.295$) and LP ($\rho{=}0.205$).
58	This advantage persists on RE (VC $\rho{=}0.350$; preliminary, single benchmark), though all signals weaken due to the 40\% zero-F1 floor effect.
59	VC and SJ show moderate instance-level correlation (NER: $\rho{=}0.659$; RE: $\rho{=}0.605$), indicating information overlap but not redundancy; their differential behavior across difficulty levels reflects the complementary granularity of entity-level frequency vs.\ span-level set overlap.
60	While the best $\rho{=}0.38$ (VC) explains approximately 14\% of F1 variance, the best AUROC reaches 0.749 (EM), indicating strong binary discriminative power for the quality/failure classification most relevant to practitioners in quality-aware routing.\footnote{For scale context, semantic entropy \cite{kuhn2023semantic} achieves comparable AUROC on discrete-answer QA, though direct comparison is not meaningful due to fundamentally different output spaces and evaluation protocols.}
61	Pairwise bootstrap CIs confirm the SJ advantage over LP ($\Delta\rho{=}{+}0.155$, CI excludes zero) but not over EM ($\Delta\rho{=}{+}0.065$, marginal under Bonferroni correction; Table~\ref{tab:bootstrap_signal_ci}, Appendix~\ref{app:bootstrap_signal}).
62	
63	\paragraph{$\rho$--AUROC dissociation.}
64	Signal choice depends on the intended use: on NER, EM leads AUROC (0.749) despite ranking third in $\rho$ (0.295), preferred for binary quality triage; structural signals ($\rho{\geq}0.36$) are better for fine-grained ranking.
65	On CoNLL with LLaMA, LP leads AUROC (0.761) yet trails in $\rho$ (0.307), confirming this pattern across datasets.
66	
67	\paragraph{Signal rankings shift with task difficulty.}
68	On CoNLL (greedy F1${\approx}$0.91), EM leads ($\rho{=}0.451$, AUROC${=}0.816$), surpassing SJ and VC.
69	When most samples are near-correct, binary agreement captures remaining variance more efficiently than set-level similarity.
70	This crossover---EM${>}$SJ on easy tasks vs.\ SJ${>}$EM on hard tasks---demonstrates difficulty-dependent complementarity rather than a universal structural advantage, suggesting practitioners should match signal type to expected task difficulty.
71	Stability across the two model families (both 8B) is strong: SJ achieves $\rho{=}0.436$ (Qwen) vs.\ $0.431$ (LLaMA) on CoNLL ($\Delta{=}0.005$, within 3-seed $\sigma{\approx}0.007$).
72	On WNUT-17, where 52\% of instances receive zero F1, full-set correlations are misleading: VC achieves $\rho{=}0.724$ (AUROC${=}0.913$), but this is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, n.s.; Table~\ref{tab:wnut}).
73	LP exhibits strong \textit{negative} correlation ($\rho{=}{-}0.410$, AUROC${=}0.219$).
74	We hypothesize that this reversal reflects overconfidence on out-of-distribution inputs \citep{xiong2024llm}: the model assigns high log-probabilities to fluent but incorrect entity patterns (e.g., common noun phrases that resemble but do not match rare WNUT entity types), while producing lower scores for genuinely uncertain outputs where it correctly hedges.
75	On the conditional set, all signals collapse toward weak or non-significant correlations ($\rho{\leq}0.35$), with SJ achieving only $\rho{=}0.089$ ($p{=}0.020$) on the full set---suggesting a capability boundary beyond which consistency signals capture binary success/failure but not quality gradation.
76	
77	\paragraph{Conditional filtering.}
78	Filtering to non-zero F1 instances reshuffles rankings (Figure~\ref{fig:signal_heatmap}, right).
79	EM emerges as the strongest conditional signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$; preliminary), while VC and FK drop substantially (VC NER: $0.379{\to}0.300$; FK NER: $0.267{\to}0.176$).
80	LP RE collapses to $\rho{=}0.011$, confirming its full-set correlation was driven by zero/non-zero separation.
81	This creates a natural complementarity: VC and SJ are preferred on the full set, while EM provides the most precise ranking within the non-trivial subset (see Appendix~\ref{app:additional} for details).
82	
83	%% ============================================================
84	\subsection{The Correlation-Selection Gap}
85	\label{sec:selection_gap}
86	
87	\begin{figure*}[t]
88	\centering
89	\includegraphics[width=\textwidth]{fig_selection_gap}
90	\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Left: NER; right: RE. Bars show best-of-$N$ selection F1; the line marks quality estimation $\rho$. Despite $\rho$ up to 0.38, no signal significantly outperforms greedy on either task ($p{=}0.39$ for NER LP, the best signal; Table~\ref{tab:selection}). Dashed line indicates oracle upper bound.}
91	\label{fig:selection_gap}
92	\end{figure*}
93	
94	\begin{table}[t]
95	\centering
96	\small
97	\caption{Best-of-$N$ selection F1 on SciERC ($N{=}8$, $T{=}1.0$). RE results are from a single benchmark (preliminary). Best non-oracle result per column in \textbf{bold}. EM selects the plurality output; despite a 42\% pairwise exact-match rate, EM selection underperforms greedy on both tasks.}
98	\label{tab:selection}
99	\begin{tabular}{lcc}
100	\toprule
101	Method & NER F1 & RE F1 \\
102	\midrule
103	Oracle & 0.776 & 0.585 \\
104	\midrule
105	LP           & \textbf{0.650} & 0.395 \\
106	SJ       & 0.645 & 0.386 \\
107	EM        & 0.636 & 0.372 \\
108	VC                 & 0.634 & 0.359 \\
109	\midrule
110	Greedy ($T{=}0$)   & 0.644 & \textbf{0.404} \\
111	Random             & 0.608 & 0.354 \\
112	\bottomrule
113	\end{tabular}
114	\end{table}
115	
116	Despite strong quality estimation, confidence signals yield limited gains when used for best-of-$N$ selection (Table~\ref{tab:selection}, Figure~\ref{fig:selection_gap}).
117	Four of five signals are instance-level aggregates that assign a single score per input regardless of which sample is evaluated; they cannot rank candidates by construction.
118	The non-trivial question is whether log-probability---the only per-sample signal---can exploit the oracle headroom.
119	We anchor this analysis on SciERC, where output diversity is substantial: only 11--18\% of instances produce identical outputs across all $N{=}8$ samples, with 39--43\% unique outputs per instance (mean 3.5 distinct outputs), per-sample F1 standard deviation of 0.11--0.14, and mean pairwise SJ of 0.703.
120	
121	\paragraph{No significant improvement over greedy.}
122	We exclude 22 instances with empty gold annotations ($n{=}529$) and evaluate significance via instance-level paired bootstrap resampling ($B{=}10{,}000$).
123	On NER, the oracle (0.776) reveals 13.2~pp of headroom above greedy (0.644).
124	LP achieves the highest selection F1 (0.650, +0.6~pp), but this is not significant ($p{=}0.39$; 95\% CI: [$-$3.0, +4.2]~pp; Cohen's $d{=}0.038$).
125	On RE, the best signal (LP, 0.395) falls below greedy (0.404, $-0.9$\,pp, $p{=}0.80$), while 18.1~pp of oracle headroom remains.
126	TOST equivalence testing confirms most signals are indistinguishable from greedy at ${\pm}2$--$3$~pp on NER; on RE, EM and VC fail equivalence even at ${\pm}5$~pp (Table~\ref{tab:tost}, Appendix~\ref{app:diversity}).
127	VC ($\rho{=}0.379$, the best quality estimator) selects to only 0.634 on NER---\textit{below} greedy.
128	The gap extends to CoNLL (ceiling effect, 57--88\% identical outputs) and WNUT-17 (capability boundary; Table~\ref{tab:cross_selection}).
129	
130	\paragraph{Quality estimation $\neq$ output selection.}
131	Instance-level confidence signals predict \textit{which inputs} the model handles reliably, not \textit{which output} among $N$ candidates is best.
132	When per-sample variance is low relative to instance-level difficulty, even perfect quality estimation cannot discriminate among near-identical candidates.
133	This gap has direct consequences for test-time scaling in IE \cite{brown2024monkeys, snell2024scaling}: closing it likely requires per-sample signals such as trained verifiers \cite{cobbe2021verifiers}.
134	
135	%% ============================================================
136	\subsection{Robustness}
137	\label{sec:robustness_main}
138	
139	Consistency-based signals show robust performance across $T{\in}\{0.7, 1.0\}$ (SJ NER $\Delta\rho{=}0.028$, bootstrap CI includes zero) and sublinear gains from $N{=}8$ to $N{=}16$, with structural signals maintaining their advantage over LP across all settings ($\Delta\rho{=}{+}0.135$ to ${+}0.175$; Table~\ref{tab:robustness}, Appendix~\ref{app:robustness}).
140	NER signals are reasonably calibrated (ECE 0.069--0.096; Appendix~\ref{app:calibration}), while RE miscalibration (ECE 0.109--0.339) and compound errors impose a ceiling at $\rho{\approx}0.28$ for $N{=}16$.
141	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "96ad6e88-0390-4e4d-ae2d-ae4fe7f86653",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Datasets.}\nWe evaluate on three English IE benchmarks spanning a difficulty gradient.\n\\textbf{SciERC} \\cite{luan2018scierc} contains 551 test instances annotated for joint NER (6 types) and RE (7 types).\n\\textbf{CoNLL-2003} \\cite{tjongkimsang2003conll} provides 3{,}453 test sentences with 4 entity types, where models achieve ${\\approx}$91\\% micro F1.\n\\textbf{WNUT-17} \\cite{derczynski2017wnut} consists of 1{,}287 social media instances with emerging entities, used to probe method boundaries (52\\% zero F1).\n\n\\paragraph{Models and sampling.}\nBoth \\textbf{Qwen3-8B} and \\textbf{LLaMA-3.1-8B-Instruct} are fine-tuned with LoRA (rank$=$32, $\\alpha{=}64$) for 5 epochs using LLaMA Factory \\cite{zheng2024llamafactory} under identical training procedures, ensuring comparisons across the two model families (both at 8B scale) reflect model differences rather than training confounds.\nWe note a training confound for SciERC: Qwen3-8B's SciERC checkpoint was trained with \\texttt{enable\\_thinking=True} (LLaMA Factory 0.9.4 default), which prepends empty \\texttt{&lt;think>\\textbackslash n&lt;/think>} blocks (4--5 tokens) to each training response and includes them in the loss computation; CoNLL-2003 and WNUT-17 checkpoints explicitly set \\texttt{enable\\_thinking=False}.\nNo reasoning content is present (the blocks are always empty), and constrained decoding at inference time enforces JSON-only output, so thinking tokens do not appear in generated samples.\nThis constitutes a minor train--test distribution mismatch for SciERC ($<$0.3\\% of the 2048-token training window); CoNLL-2003 and WNUT-17 are unaffected.\nWe discuss implications in the Limitations section.\nWe draw $N{=}8$ samples at $T{=}1.0$ (primary; single seed, seed${=}42$), with $N{=}16$ for scaling experiments.\\footnote{$N{=}16$ results for CoNLL (Qwen) and SciERC (LLaMA) are in Table~\\ref{tab:robustness} (Appendix~\\ref{app:robustness}). A 3-seed stability analysis ($\\sigma{\\leq}0.025$; Table~\\ref{tab:multiseed}, Appendix~\\ref{app:multiseed}) confirms that signal rankings are identical across seeds.}\nQuality estimation uses Spearman $\\rho$ and AUROC; downstream utility uses best-of-$N$ selection F1 with exact span matching (NER) and head-tail-label matching (RE).\nInference uses vLLM with constrained decoding \\cite{willard2023guided}.\n\n%% ============================================================\n\\subsection{Quality Estimation Results}\n\\label{sec:qe_results}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Quality estimation across tasks and models (Spearman $\\rho$ and AUROC; $N{=}8$, seed${=}42$). Best value per column in \\textbf{bold}. SciERC evaluates joint NER (6 types) and RE (7 types, single benchmark---preliminary); CoNLL evaluates NER (4 types). $N{=}16$ results appear in Table~\\ref{tab:robustness} (Appendix~\\ref{app:robustness}).}\n\\label{tab:quality_estimation}\n\\begin{tabular}{ll cc cc cc cc}\n\\toprule\n& & \\multicolumn{2}{c}{\\textbf{SciERC NER}} & \\multicolumn{2}{c}{\\textbf{SciERC RE}} & \\multicolumn{2}{c}{\\textbf{CoNLL (Qwen)}} & \\multicolumn{2}{c}{\\textbf{CoNLL (LLaMA)}} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6} \\cmidrule(lr){7-8} \\cmidrule(lr){9-10}\nSignal & Family & $\\rho$ & AUC & $\\rho$ & AUC & $\\rho$ & AUC & $\\rho$ & AUC \\\\\n\\midrule\nVC & Structural & \\textbf{.379} & .684 & \\textbf{.350} & .693 & .424 & .789 & .426 & .709 \\\\\nSJ  & Structural & .360 & .692 & .250 & .670 & .436 & .801 & \\textbf{.431} & .704 \\\\\nFK & Surface & .267 & .629 & .275 & .609 & .400 & .774 & .428 & .703 \\\\\nEM  & Surface    & .295 & \\textbf{.749} & .134 & \\textbf{.706} & \\textbf{.451} & \\textbf{.816} & \\textbf{.431} & .705 \\\\\nLP     & Model      & .205 & .578 & .266 & .600 & .316 & .753 & .307 & \\textbf{.761} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_signal_heatmap}\n\\caption{Quality estimation heatmap (Spearman $\\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$), while LP RE collapses to near-zero ($\\rho{=}0.011$).}\n\\label{fig:signal_heatmap}\n\\end{figure*}\n\nTable~\\ref{tab:quality_estimation} presents rank correlation ($\\rho$) and AUROC for five confidence signals across tasks and models.\n\n\\paragraph{Difficulty-dependent signal complementarity.}\nOn SciERC NER (complex schema, 6 types), structural signals lead: VC achieves $\\rho{=}0.379$ and SJ $\\rho{=}0.360$, both outperforming surface ($\\rho{\\leq}0.295$) and LP ($\\rho{=}0.205$).\nThis advantage persists on RE (VC $\\rho{=}0.350$; preliminary, single benchmark), though all signals weaken due to the 40\\% zero-F1 floor effect.\nVC and SJ show moderate instance-level correlation (NER: $\\rho{=}0.659$; RE: $\\rho{=}0.605$), indicating information overlap but not redundancy; their differential behavior across difficulty levels reflects the complementary granularity of entity-level frequency vs.\\ span-level set overlap.\nWhile the best $\\rho{=}0.38$ (VC) explains approximately 14\\% of F1 variance, the best AUROC reaches 0.749 (EM), indicating strong binary discriminative power for the quality/failure classification most relevant to practitioners in quality-aware routing.\\footnote{For scale context, semantic entropy \\cite{kuhn2023semantic} achieves comparable AUROC on discrete-answer QA, though direct comparison is not meaningful due to fundamentally different output spaces and evaluation protocols.}\nPairwise bootstrap CIs confirm the SJ advantage over LP ($\\Delta\\rho{=}{+}0.155$, CI excludes zero) but not over EM ($\\Delta\\rho{=}{+}0.065$, marginal under Bonferroni correction; Table~\\ref{tab:bootstrap_signal_ci}, Appendix~\\ref{app:bootstrap_signal}).\n\n\\paragraph{$\\rho$--AUROC dissociation.}\nSignal choice depends on the intended use: on NER, EM leads AUROC (0.749) despite ranking third in $\\rho$ (0.295), preferred for binary quality triage; structural signals ($\\rho{\\geq}0.36$) are better for fine-grained ranking.\nOn CoNLL with LLaMA, LP leads AUROC (0.761) yet trails in $\\rho$ (0.307), confirming this pattern across datasets.\n\n\\paragraph{Signal rankings shift with task difficulty.}\nOn CoNLL (greedy F1${\\approx}$0.91), EM leads ($\\rho{=}0.451$, AUROC${=}0.816$), surpassing SJ and VC.\nWhen most samples are near-correct, binary agreement captures remaining variance more efficiently than set-level similarity.\nThis crossover---EM${>}$SJ on easy tasks vs.\\ SJ${>}$EM on hard tasks---demonstrates difficulty-dependent complementarity rather than a universal structural advantage, suggesting practitioners should match signal type to expected task difficulty.\nStability across the two model families (both 8B) is strong: SJ achieves $\\rho{=}0.436$ (Qwen) vs.\\ $0.431$ (LLaMA) on CoNLL ($\\Delta{=}0.005$, within 3-seed $\\sigma{\\approx}0.007$).\nOn WNUT-17, where 52\\% of instances receive zero F1, full-set correlations are misleading: VC achieves $\\rho{=}0.724$ (AUROC${=}0.913$), but this is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, n.s.; Table~\\ref{tab:wnut}).\nLP exhibits strong \\textit{negative} correlation ($\\rho{=}{-}0.410$, AUROC${=}0.219$).\nWe hypothesize that this reversal reflects overconfidence on out-of-distribution inputs \\citep{xiong2024llm}: the model assigns high log-probabilities to fluent but incorrect entity patterns (e.g., common noun phrases that resemble but do not match rare WNUT entity types), while producing lower scores for genuinely uncertain outputs where it correctly hedges.\nOn the conditional set, all signals collapse toward weak or non-significant correlations ($\\rho{\\leq}0.35$), with SJ achieving only $\\rho{=}0.089$ ($p{=}0.020$) on the full set---suggesting a capability boundary beyond which consistency signals capture binary success/failure but not quality gradation.\n\n\\paragraph{Conditional filtering.}\nFiltering to non-zero F1 instances reshuffles rankings (Figure~\\ref{fig:signal_heatmap}, right).\nEM emerges as the strongest conditional signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$; preliminary), while VC and FK drop substantially (VC NER: $0.379{\\to}0.300$; FK NER: $0.267{\\to}0.176$).\nLP RE collapses to $\\rho{=}0.011$, confirming its full-set correlation was driven by zero/non-zero separation.\nThis creates a natural complementarity: VC and SJ are preferred on the full set, while EM provides the most precise ranking within the non-trivial subset (see Appendix~\\ref{app:additional} for details).\n\n%% ============================================================\n\\subsection{The Correlation-Selection Gap}\n\\label{sec:selection_gap}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_selection_gap}\n\\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Left: NER; right: RE. Bars show best-of-$N$ selection F1; the line marks quality estimation $\\rho$. Despite $\\rho$ up to 0.38, no signal significantly outperforms greedy on either task ($p{=}0.39$ for NER LP, the best signal; Table~\\ref{tab:selection}). Dashed line indicates oracle upper bound.}\n\\label{fig:selection_gap}\n\\end{figure*}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 on SciERC ($N{=}8$, $T{=}1.0$). RE results are from a single benchmark (preliminary). Best non-oracle result per column in \\textbf{bold}. EM selects the plurality output; despite a 42\\% pairwise exact-match rate, EM selection underperforms greedy on both tasks.}\n\\label{tab:selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & NER F1 & RE F1 \\\\\n\\midrule\nOracle & 0.776 & 0.585 \\\\\n\\midrule\nLP           & \\textbf{0.650} & 0.395 \\\\\nSJ       & 0.645 & 0.386 \\\\\nEM        & 0.636 & 0.372 \\\\\nVC                 & 0.634 & 0.359 \\\\\n\\midrule\nGreedy ($T{=}0$)   & 0.644 & \\textbf{0.404} \\\\\nRandom             & 0.608 & 0.354 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nDespite strong quality estimation, confidence signals yield limited gains when used for best-of-$N$ selection (Table~\\ref{tab:selection}, Figure~\\ref{fig:selection_gap}).\nFour of five signals are instance-level aggregates that assign a single score per input regardless of which sample is evaluated; they cannot rank candidates by construction.\nThe non-trivial question is whether log-probability---the only per-sample signal---can exploit the oracle headroom.\nWe anchor this analysis on SciERC, where output diversity is substantial: only 11--18\\% of instances produce identical outputs across all $N{=}8$ samples, with 39--43\\% unique outputs per instance (mean 3.5 distinct outputs), per-sample F1 standard deviation of 0.11--0.14, and mean pairwise SJ of 0.703.\n\n\\paragraph{No significant improvement over greedy.}\nWe exclude 22 instances with empty gold annotations ($n{=}529$) and evaluate significance via instance-level paired bootstrap resampling ($B{=}10{,}000$).\nOn NER, the oracle (0.776) reveals 13.2~pp of headroom above greedy (0.644).\nLP achieves the highest selection F1 (0.650, +0.6~pp), but this is not significant ($p{=}0.39$; 95\\% CI: [$-$3.0, +4.2]~pp; Cohen's $d{=}0.038$).\nOn RE, the best signal (LP, 0.395) falls below greedy (0.404, $-0.9$\\,pp, $p{=}0.80$), while 18.1~pp of oracle headroom remains.\nTOST equivalence testing confirms most signals are indistinguishable from greedy at ${\\pm}2$--$3$~pp on NER; on RE, EM and VC fail equivalence even at ${\\pm}5$~pp (Table~\\ref{tab:tost}, Appendix~\\ref{app:diversity}).\nVC ($\\rho{=}0.379$, the best quality estimator) selects to only 0.634 on NER---\\textit{below} greedy.\nThe gap extends to CoNLL (ceiling effect, 57--88\\% identical outputs) and WNUT-17 (capability boundary; Table~\\ref{tab:cross_selection}).\n\n\\paragraph{Quality estimation $\\neq$ output selection.}\nInstance-level confidence signals predict \\textit{which inputs} the model handles reliably, not \\textit{which output} among $N$ candidates is best.\nWhen per-sample variance is low relative to instance-level difficulty, even perfect quality estimation cannot discriminate among near-identical candidates.\nThis gap has direct consequences for test-time scaling in IE \\cite{brown2024monkeys, snell2024scaling}: closing it likely requires per-sample signals such as trained verifiers \\cite{cobbe2021verifiers}.\n\n%% ============================================================\n\\subsection{Robustness}\n\\label{sec:robustness_main}\n\nConsistency-based signals show robust performance across $T{\\in}\\{0.7, 1.0\\}$ (SJ NER $\\Delta\\rho{=}0.028$, bootstrap CI includes zero) and sublinear gains from $N{=}8$ to $N{=}16$, with structural signals maintaining their advantage over LP across all settings ($\\Delta\\rho{=}{+}0.135$ to ${+}0.175$; Table~\\ref{tab:robustness}, Appendix~\\ref{app:robustness}).\nNER signals are reasonably calibrated (ECE 0.069--0.096; Appendix~\\ref{app:calibration}), while RE miscalibration (ECE 0.109--0.339) and compound errors impose a ceiling at $\\rho{\\approx}0.28$ for $N{=}16$.\n",
      "numLines": 141,
      "startLine": 1,
      "totalLines": 141
    }
  }
}
```

</details>

---

### Tool call

_source line 31_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01GVex8NuG2xdibMdCXwv3Am`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "bbba1685-827f-47a4-a5d1-a294764b50b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Needxv6C4Fed1pngo8iLt8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 15286,
      "cache_read_input_tokens": 23448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 15286
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-15T11:33:36.164Z_

<details><summary>↩ Tool result · `toolu_01GVex8NuG2xdibMdCXwv3Am`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "ceb49cb9-3fc1-4925-a2ae-b4cd639dc530",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry"
    ],
    "query": "select:mcp__agent-ml-research__read_registry",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Assistant

_source line 33_

<details><summary>Logged reasoning block</summary>

```text
Let me now read the registry for exp_007 series metrics and also check the experiments.tex and conclusion.tex for current paper state.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "f846d6d4-d6ae-4a00-9c21-96c7b24dddb0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xtzhz4iHVECT72BXBvw7bf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 20118,
      "cache_read_input_tokens": 38734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20118
      },
      "output_tokens": 18,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 34_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_018n8kQcmFdE5eAoCiwb1wkF`</summary>

```json
{
  "project": "struct_self_consist_ie",
  "limit": 0,
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "98801ab5-8cd1-4281-b929-47811d1aa871",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xtzhz4iHVECT72BXBvw7bf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 20118,
      "cache_read_input_tokens": 38734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20118
      },
      "output_tokens": 18,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 35 · 2026-05-15T11:33:41.837Z_

<details><summary>↩ Tool result · `toolu_018n8kQcmFdE5eAoCiwb1wkF`</summary>

```text
Error: result (126,839 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "bf167324-cb31-44b6-9445-5a74c34a6083",
  "tool_use_result": {
    "content": "Error: result (126,839 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_017_llama_conll_n16_s456_r1024\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:04.572Z\", \"updated_at\": \"2026-05-15T10:59:06.605Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed456.\", \"parent\": \"exp_017_llama_conll_n16_s456\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s456_r1024\", \"gpu\": \"cuda:2\", \"pid\": \"175870\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_s456_r1024\"}, \"conclusion\": \"killed\"}, \"exp_017_llama_conll_n16_r1024\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:01.036Z\", \"updated_at\": \"2026-05-15T10:59:03.652Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed42.\", \"parent\": \"exp_017_llama_conll_n16\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_r1024\", \"gpu\": \"cuda:1\", \"pid\": \"175734\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_r1024\"}, \"conclusion\": \"killed\"}, \"exp_002_merge_conll2003\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:25:56.211Z\", \"updated_at\": \"2026-05-15T10:57:58.714Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli export export_config_conll2003.yaml > /tmp/merge_conll2003.log 2>&1 && echo 'MERGE_DONE' >> /tmp/merge_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"57524\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_merge_conll2003.log\", \"submitted_at\": \"2026-05-14T12:25:56.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_002_ner_conll2003 (completed on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_002_ner_conll2003 (DONE)\", \"notes\": \"Completed as exp_002_conll_n16 on autodl-5090. Registry status corrected.\"}, \"exp_007_ner_llama\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:21.510Z\", \"updated_at\": \"2026-05-15T10:57:57.717Z\", \"spec\": {\"description\": \"Fine-tune LLaMA-3.1-8B on SciERC + NER pilot (N=8, T=0.7). Model-agnostic validation.\", \"hypothesis\": \"SJ advantage is model-agnostic, not Qwen3-specific\", \"plan_id\": \"exp-007\", \"claim\": 1, \"model_name\": \"llama-3.1-8b-instruct (new fine-tune)\", \"dataset\": \"SciERC\", \"priority\": \"P0\", \"failure_reason\": \"Superseded by exp_007_ner_multi_model + exp_007_llama_inference (completed on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_007_llama_inference (DONE)\", \"notes\": \"Completed as exp_007_llama_n16 on autodl-5090. Registry status corrected.\"}, \"exp008_re_n16\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:50.987Z\", \"updated_at\": \"2026-05-15T10:38:44.272Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp008_re_n16 && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp008_re_n16 --collect_logprobs 2>&1 | tee output/exp008_re_n16/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"53600\", \"log_path\": \"~/runs/struct_self_consist_ie/exp008_re_n16.log\", \"submitted_at\": \"2026-05-14T12:15:14.917Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_008_re_n16_v2 (full 551-instance run on autodl-5090)\"}, \"conclusion\": \"success\"}, \"exp_017_llama_conll_n16_s123_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:02.953Z\", \"updated_at\": \"2026-05-15T10:38:43.623Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed123.\", \"parent\": \"exp_017_llama_conll_n16_s123\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s123_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:20:51.219Z\", \"notes\": \"Output exists on autodl-5090. Registry status corrected from killed to success.\"}, \"exp_001_n16_seed456\": {\"status\": \"RUNNING\", \"retry_count\": 1, \"created_at\": \"2026-05-14T12:10:30.350Z\", \"updated_at\": \"2026-05-15T10:36:56.089Z\", \"completed_at\": \"2026-05-14T12:28:38.721Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.6577, \"oracle_f1\": 0.8129, \"headroom\": 0.1553, \"rho_sj_full\": 0.3297, \"rho_fk_full\": 0.2578, \"rho_logprob_full\": 0.2866, \"rho_sj_cond\": 0.3394, \"rho_fk_cond\": 0.2721, \"rho_logprob_cond\": 0.2567, \"sj_beats_fk\": true, \"rho_advantage\": 0.0719}, \"re\": {\"greedy_f1\": 0.4312, \"oracle_f1\": 0.6737, \"headroom\": 0.2425, \"rho_sj_full\": 0.285, \"rho_fk_full\": 0.2372, \"rho_logprob_full\": 0.2626, \"rho_sj_cond\": 0.3525, \"rho_fk_cond\": 0.2614, \"rho_logprob_cond\": 0.1927, \"sj_beats_fk\": true, \"rho_advantage\": 0.0478}, \"verdict\": \"FAIL\"}}}, \"spec\": {\"hypothesis\": \"N=16 seed456 multi-seed robustness verification for SciERC NER+RE\", \"plan_id\": \"exp-001\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 456, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"174595\", \"log_path\": \"output/exp001_n16_seed456_run.log\", \"tmux_session\": \"exp_001_n16_seed456\"}}, \"exp_019_supervised_verifier\": {\"status\": \"PENDING\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:08:54.395Z\", \"updated_at\": \"2026-05-15T10:28:45.920Z\", \"spec\": {\"hypothesis\": \"Supervised verifier (DeBERTa-v3-large) can close the correlation-selection gap, proving the gap is closable with supervision\", \"plan_id\": \"exp-019\", \"model_name\": \"microsoft/deberta-v3-large\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl\", \"data_count\": 551, \"seed\": 42}, \"conclusion\": \"killed\", \"notes\": \"Cancelled by Director: DDL risk too high (3-4 days for implementation+training+eval+paper), scope creep for analytical paper, free-form ablation already provides sufficient mechanistic evidence\"}, \"exp_freeform_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:22.868Z\", \"updated_at\": \"2026-05-15T10:00:09.238Z\", \"spec\": {\"command\": \"python run_freeform_inference.py --seed 42 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"169042\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_ablation.log\", \"submitted_at\": \"2026-05-15T09:42:30.236Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Free-form decoding recovers logprob variance and selection ability lost under constrained decoding\", \"plan_id\": \"exp-018\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"tmux_session\": \"exp_freeform_ablation\", \"wall_clock_seconds\": 1059.0, \"gpu_hours\": 0.29}, \"conclusion\": \"negative\", \"metrics\": {\"lp_std_ratio_free_vs_constrained\": 0.97, \"lp_range_ratio\": 0.96, \"tied_fraction_constrained\": 0.597, \"tied_fraction_freeform\": 0.577, \"ner_selection_gap_constrained\": 0.0059, \"ner_selection_gap_freeform\": 0.0018, \"re_selection_gap_constrained\": -0.0068, \"re_selection_gap_freeform\": 0.0169, \"parse_rate\": 0.9995, \"ner_vc_rho_constrained\": 0.3792, \"ner_vc_rho_freeform\": 0.4089}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"completed_at\": \"2026-05-15T10:00:09.238Z\"}, \"exp_018_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:15.150Z\", \"updated_at\": \"2026-05-15T06:22:40.868Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=456, max_tokens=1024. Fresh inference (D066 decision: replace exp_007 re-analysis with independent replication).\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T06:08:05.756Z\", \"notes\": \"SUPERSEDED by exp_018_llama_scierc_seed456_r1024 (D066). Original data was re-analysis of exp_007_llama_seed456, not independent inference. Fresh rerun with explicit max_tokens=1024 now canonical.\"}, \"exp_018_llama_scierc_seed42_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:09:57.155Z\", \"updated_at\": \"2026-05-15T06:21:59.257Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=42 with explicit max_tokens=1024. Replaces exp_007_llama_inference for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 42, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed42_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"156809\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"finished_at\": \"2026-05-15T06:15:47.963Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:15:50.613872+00:00\"}]}, \"metrics\": {\"ner\": {\"full\": {\"SJ\": {\"rho\": 0.3096, \"tau\": 0.2288, \"auroc\": 0.6683}, \"FK\": {\"rho\": 0.2352, \"tau\": 0.1759, \"auroc\": 0.6069}, \"logprob\": {\"rho\": 0.1503, \"tau\": 0.1087, \"auroc\": 0.5318}, \"EM\": {\"rho\": 0.2587, \"tau\": 0.1966, \"auroc\": 0.7174}, \"voting_conf\": {\"rho\": 0.4053, \"tau\": 0.3042, \"auroc\": 0.6967}}, \"conditional\": {\"SJ\": {\"rho\": 0.2718, \"tau\": null, \"auroc\": 0.6565}, \"FK\": {\"rho\": 0.1472, \"tau\": null, \"auroc\": 0.5866}, \"logprob\": {\"rho\": 0.081, \"tau\": null, \"auroc\": 0.5129}, \"EM\": {\"rho\": 0.3165, \"tau\": null, \"auroc\": 0.7244}, \"voting_conf\": {\"rho\": 0.3078, \"tau\": null, \"auroc\": 0.6714}}, \"greedy_f1\": 0.6607, \"oracle_f1\": 0.7781, \"n_full\": 529, \"n_cond\": 478}, \"re\": {\"full\": {\"SJ\": {\"rho\": 0.2748, \"tau\": 0.2102, \"auroc\": 0.7244}, \"FK\": {\"rho\": 0.3027, \"tau\": 0.2337, \"auroc\": 0.691}, \"logprob\": {\"rho\": 0.3163, \"tau\": 0.233, \"auroc\": 0.6313}, \"EM\": {\"rho\": 0.1681, \"tau\": 0.1275, \"auroc\": 0.7697}, \"voting_conf\": {\"rho\": 0.384, \"tau\": 0.2965, \"auroc\": 0.7337}}, \"conditional\": {\"SJ\": {\"rho\": 0.3461, \"tau\": null, \"auroc\": 0.7233}, \"FK\": {\"rho\": 0.1969, \"tau\": null, \"auroc\": 0.6684}, \"logprob\": {\"rho\": 0.0888, \"tau\": null, \"auroc\": 0.5556}, \"EM\": {\"rho\": 0.4969, \"tau\": null, \"auroc\": 0.819}, \"voting_conf\": {\"rho\": 0.3433, \"tau\": null, \"auroc\": 0.7003}}, \"greedy_f1\": 0.4319, \"oracle_f1\": 0.5775, \"n_full\": 397, \"n_cond\": 251}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:47.660Z\"}, \"exp_018_llama_scierc_seed456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:12:43.492Z\", \"updated_at\": \"2026-05-15T06:21:49.320Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=456 with explicit max_tokens=1024. Replaces exp_007 re-analysis for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"157584\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"finished_at\": \"2026-05-15T06:18:22.307Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:18:24.880896+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_018_llama_scierc_seed456_r1024\", \"metrics\": {\"ner_greedy_f1\": 0.6597, \"ner_oracle_f1\": 0.7683, \"ner_oracle_headroom\": 0.1086, \"ner_cond_rho_fk\": 0.1472, \"ner_cond_rho_sj\": 0.2718, \"ner_cond_rho_logprob\": 0.083, \"ner_logprob_auroc_cond\": 0.5485, \"re_greedy_f1\": 0.4338, \"re_oracle_f1\": 0.5834, \"re_oracle_headroom\": 0.1496, \"re_cond_rho_fk\": 0.2107, \"re_cond_rho_sj\": 0.3898, \"re_cond_rho_logprob\": 0.1252, \"re_logprob_auroc_cond\": 0.6119, \"ner_structural_beats_logprob\": true, \"re_structural_beats_logprob\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:45.350Z\"}, \"exp_018_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:14.370Z\", \"updated_at\": \"2026-05-15T06:08:04.855Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed123/\", \"log_path\": \"output/exp_018_llama_scierc_seed123.log\", \"samples_md5\": \"072eeca68236d46b4c5c84b945209abc\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:04.855Z\"}, \"exp_018_qwen_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:13.570Z\", \"updated_at\": \"2026-05-15T06:08:03.898Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=456, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 456 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed456\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed456/\", \"log_path\": \"output/exp_018_qwen_scierc_seed456/run.log\", \"samples_md5\": \"46d0de47ad7693c07e7df3a77c90c3be\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:03.898Z\"}, \"exp_018_qwen_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:12.747Z\", \"updated_at\": \"2026-05-15T06:08:02.954Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed123/\", \"log_path\": \"output/exp_018_qwen_scierc_seed123.log\", \"samples_md5\": \"866a59581dea56f4633149f0b18a31ae\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:02.954Z\"}, \"exp_002_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:57.682Z\", \"updated_at\": \"2026-05-15T01:20:53.108Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen CoNLL N=16.\", \"parent\": \"exp_002_conll_n16\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_002_conll_n16_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:53.108Z\"}, \"exp_007_llama_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:59.685Z\", \"updated_at\": \"2026-05-15T01:20:52.194Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA SciERC N=16.\", \"parent\": \"exp_007_llama_n16\", \"model_name\": \"llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_007_llama_n16_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:52.194Z\"}, \"exp_001_seed123_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:54.442Z\", \"updated_at\": \"2026-05-15T01:20:49.812Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed123.\", \"parent\": \"exp_001_seed123_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed123_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:49.812Z\"}, \"exp_001_seed456_v2_ner_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:55.975Z\", \"updated_at\": \"2026-05-15T01:20:48.914Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed456.\", \"parent\": \"exp_001_seed456_v2_ner\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:48.914Z\"}, \"exp_016_rerun_1024_bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:21.577Z\", \"updated_at\": \"2026-05-14T23:44:48.818Z\", \"hypothesis\": \"3-seed bootstrap significance test for NER logprob vs greedy selection gap (+0.6pp). Tests whether the observed advantage is statistically significant.\", \"spec\": {\"command\": \"python code/bootstrap_significance.py\", \"server\": \"local\", \"data_path\": \"output/exp_016_rerun_1024/\", \"data_count\": 529, \"model_name\": \"N/A (statistical analysis)\", \"seed\": \"3-seed bootstrap (1000 iterations)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_016_rerun_1024_bootstrap/\"}, \"conclusion\": \"negative\", \"metrics\": {\"bootstrap_ci_95\": [-0.03, 0.042], \"permutation_p\": 0.39, \"cohen_d\": 0.038, \"sign_test_win_rate\": 0.466, \"ner_logprob_vs_greedy_delta\": 0.006, \"conclusion_summary\": \"NER selection: no signal significantly outperforms greedy; RE: same conclusion\"}, \"completed_at\": \"2026-05-14T23:44:48.818Z\"}, \"exp_015_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:34:23.336Z\", \"updated_at\": \"2026-05-14T23:11:11.790Z\", \"spec\": {\"command\": \"python code/analyze_exp015_v2_metrics.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/ (10 datasets)\", \"data_count\": 9148, \"model_name\": \"Qwen3-8B + LLaMA (multi-model)\", \"seed\": \"42,123,456 (multi-seed)\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp015_v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:34:56.741Z\", \"metrics\": {\"scierc_ner_avg\": {\"sj_auroc\": 0.7394, \"fk_auroc\": 0.6172, \"em_auroc\": 0.7873, \"voting_auroc\": 0.7367, \"logprob_auroc\": 0.5918}, \"scierc_re_avg\": {\"sj_auroc\": 0.6746, \"fk_auroc\": 0.5939, \"em_auroc\": 0.715, \"voting_auroc\": 0.7234, \"logprob_auroc\": 0.5849}}}, \"exp_012_rerun_1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:11:33.777Z\", \"updated_at\": \"2026-05-14T23:10:58.651Z\", \"spec\": {\"hypothesis\": \"Verify if max_tokens=512 truncation inflated Table 1 N=8 SciERC signal values. Rerun with max_tokens=1024 for clean comparison.\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"parent\": \"exp_012_logprob_baseline\", \"data_count\": 551, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_012_rerun_1024\", \"checkpoint_path\": \"output/exp_012_rerun_1024/\", \"log_path\": \"output/exp_012_rerun_1024/run.log\", \"data_path\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"metrics\": {\"ner_full\": {\"n\": 529, \"SJ\": {\"rho\": 0.3599, \"tau\": 0.2646, \"AUROC\": 0.6917, \"ECE\": 0.4531, \"rho_ci95\": [0.2732, 0.4389], \"AUROC_ci95\": [0.6304, 0.7406]}, \"FK\": {\"rho\": 0.2665, \"tau\": 0.1974, \"AUROC\": 0.629, \"ECE\": 0.4512, \"rho_ci95\": [0.1743, 0.3486], \"AUROC_ci95\": [0.5612, 0.6882]}, \"logprob\": {\"rho\": 0.2052, \"tau\": 0.1478, \"AUROC\": 0.5783, \"ECE\": 0.7064, \"rho_ci95\": [0.1171, 0.2904], \"AUROC_ci95\": [0.5179, 0.6387]}, \"EM\": {\"rho\": 0.2945, \"tau\": 0.2208, \"AUROC\": 0.7493, \"ECE\": 0.3526, \"rho_ci95\": [0.2094, 0.37], \"AUROC_ci95\": [0.7002, 0.7928]}, \"voting_conf\": {\"rho\": 0.3792, \"tau\": 0.2805, \"AUROC\": 0.6841, \"ECE\": 0.3807, \"rho_ci95\": [0.2972, 0.4486], \"AUROC_ci95\": [0.6249, 0.7366]}}, \"ner_cond\": {\"n\": 477, \"SJ\": {\"rho\": 0.3113, \"tau\": 0.2257, \"AUROC\": 0.6772, \"ECE\": 0.4416, \"rho_ci95\": [0.2353, 0.3959], \"AUROC_ci95\": [0.621, 0.7337]}, \"FK\": {\"rho\": 0.1761, \"tau\": 0.1284, \"AUROC\": 0.6078, \"ECE\": 0.4389, \"rho_ci95\": [0.0839, 0.2665], \"AUROC_ci95\": [0.5442, 0.6709]}, \"logprob\": {\"rho\": 0.1538, \"tau\": 0.1111, \"AUROC\": 0.5633, \"ECE\": 0.6803, \"rho_ci95\": [0.0637, 0.2424], \"AUROC_ci95\": [0.5032, 0.6232]}, \"EM\": {\"rho\": 0.3596, \"tau\": 0.2735, \"AUROC\": 0.7556, \"ECE\": 0.3257, \"rho_ci95\": [0.2819, 0.4408], \"AUROC_ci95\": [0.7011, 0.8107]}, \"voting_conf\": {\"rho\": 0.3, \"tau\": 0.2189, \"AUROC\": 0.6618, \"ECE\": 0.3746, \"rho_ci95\": [0.2168, 0.3836], \"AUROC_ci95\": [0.6004, 0.7201]}}, \"re_full\": {\"n\": 397, \"SJ\": {\"rho\": 0.2503, \"tau\": 0.1878, \"AUROC\": 0.6702, \"ECE\": 0.3865}, \"FK\": {\"rho\": 0.2752, \"tau\": 0.2117, \"AUROC\": 0.6089, \"ECE\": 0.4405}, \"logprob\": {\"rho\": 0.2662, \"tau\": 0.1951, \"AUROC\": 0.6005, \"ECE\": 0.7694}, \"EM\": {\"rho\": 0.1344, \"tau\": 0.1081, \"AUROC\": 0.7059, \"ECE\": 0.3548}, \"voting_conf\": {\"rho\": 0.3498, \"tau\": 0.2663, \"AUROC\": 0.6935, \"ECE\": 0.2724}}, \"re_cond\": {\"n\": 238, \"SJ\": {\"rho\": 0.2457, \"tau\": 0.1811, \"AUROC\": 0.6463, \"ECE\": 0.2941}, \"FK\": {\"rho\": 0.1139, \"tau\": 0.0876, \"AUROC\": 0.551, \"ECE\": 0.3424}, \"logprob\": {\"rho\": 0.0112, \"tau\": 0.0051, \"AUROC\": 0.5186, \"ECE\": 0.6464}, \"EM\": {\"rho\": 0.4165, \"tau\": 0.3256, \"AUROC\": 0.7515, \"ECE\": 0.2232}, \"voting_conf\": {\"rho\": 0.2409, \"tau\": 0.178, \"AUROC\": 0.642, \"ECE\": 0.207}}, \"delta_vs_512_ner_full_rho\": {\"SJ\": 0.0034, \"FK\": 0.0014, \"EM\": 0.0379, \"voting_conf\": -0.1226, \"logprob\": 0.0656}, \"provenance_note\": \"exp_015_v2 scierc_n8_logprob used exp_012_logprob (max_tokens=512 truncated data). voting_conf was inflated 0.502→0.379, logprob was suppressed 0.140→0.205.\"}, \"completed_at\": \"2026-05-14T23:10:33.075Z\"}, \"exp_001_seed42_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:52.571Z\", \"updated_at\": \"2026-05-14T22:28:53.686Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed42.\", \"parent\": \"exp_001_seed42_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed42_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"metrics\": {\"greedy_f1\": 0.6647, \"oracle_f1\": 0.8106, \"softjaccard_rho_full\": 0.3928, \"fleiss_rho_full\": 0.2489, \"logprob_rho_full\": 0.2136, \"softjaccard_rho_cond\": 0.3455, \"fleiss_rho_cond\": 0.163, \"logprob_rho_cond\": 0.1624, \"verdict\": \"MARGINAL\"}, \"checkpoint_path\": \"output/exp_001_seed42_v2_r1024\", \"log_path\": \"output/exp_001_seed42_v2_r1024/run.log\", \"completed_at\": \"2026-05-14T22:27:43.836Z\"}, \"exp_001_n16_seed123_full\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:43:47.915Z\", \"updated_at\": \"2026-05-14T21:51:16.458Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed123_full/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"61812\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed123_full.log\", \"submitted_at\": \"2026-05-14T12:44:06.059Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\"}, \"exp_001_n16_seed456_full\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:44:31.348Z\", \"updated_at\": \"2026-05-14T21:51:15.963Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed456/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"62170\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed456_full.log\", \"submitted_at\": \"2026-05-14T12:44:31.087Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\"}, \"exp001_seed123\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:45.739Z\", \"updated_at\": \"2026-05-14T21:51:15.007Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed123 && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"48530\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed123.log\", \"submitted_at\": \"2026-05-14T12:09:45.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only, 551 instances on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\"}, \"exp001_seed456\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:48.078Z\", \"updated_at\": \"2026-05-14T21:51:14.103Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed456 && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs 2>&1 | tee output/exp001_n16_seed456/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"50302\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed456.log\", \"submitted_at\": \"2026-05-14T12:12:41.206Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\"}, \"exp_017_llama_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.987Z\", \"updated_at\": \"2026-05-14T20:24:45.875Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s456\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 456}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9488, \"oracle_headroom\": 0.0245, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4552, \"SJ_AUROC\": 0.7288, \"SJ_ECE\": 0.1134, \"FK_rho\": 0.4478, \"FK_AUROC\": 0.7248, \"FK_ECE\": 0.109, \"logprob_rho\": 0.3078, \"logprob_AUROC\": 0.7612, \"logprob_ECE\": 0.1289, \"EM_rho\": 0.452, \"EM_AUROC\": 0.7275, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4571, \"voting_conf_AUROC\": 0.7348, \"voting_conf_ECE\": 0.0863}, \"conditional\": {\"SJ_rho\": 0.4505, \"SJ_AUROC\": 0.7449, \"SJ_ECE\": 0.0826, \"FK_rho\": 0.4422, \"FK_AUROC\": 0.7401, \"FK_ECE\": 0.0835, \"logprob_rho\": 0.3242, \"logprob_AUROC\": 0.8067, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.451, \"EM_AUROC\": 0.745, \"EM_ECE\": 0.0756, \"voting_conf_rho\": 0.3962, \"voting_conf_AUROC\": 0.7202, \"voting_conf_ECE\": 0.0746}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9215, \"sj_best\": 0.9243, \"logprob_best\": 0.9243, \"voting_conf_best\": 0.9243, \"oracle\": 0.9488}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0238, \"full_FK_rho_delta\": 0.0201, \"full_logprob_rho_delta\": 0.0006, \"full_EM_rho_delta\": 0.0214, \"full_voting_conf_rho_delta\": 0.0315, \"cond_SJ_rho_delta\": 0.0149, \"cond_FK_rho_delta\": 0.0112, \"cond_logprob_rho_delta\": -0.004, \"cond_EM_rho_delta\": 0.0107, \"cond_voting_conf_rho_delta\": 0.0219}}, \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s456/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s456/all_signals_report.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:24:45.875Z\"}, \"exp_017_llama_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:19:35.318Z\", \"updated_at\": \"2026-05-14T19:45:16.265Z\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL N=16: complete the 2x2 matrix (model x dataset x N). If SJ N-scaling holds for LLaMA on CoNLL, the finding is fully cross-model cross-dataset.\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll_infer\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"data_count\": 3453, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_017_llama_conll_n16\", \"data_path\": \"data/conll2003\", \"pid\": 106997, \"n_samples\": 16, \"temperature\": 1, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16/all_signals_report.json\"}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9487, \"oracle_headroom\": 0.0244, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4642, \"SJ_AUROC\": 0.7391, \"SJ_ECE\": 0.1131, \"FK_rho\": 0.4566, \"FK_AUROC\": 0.736, \"FK_ECE\": 0.1071, \"logprob_rho\": 0.3058, \"logprob_AUROC\": 0.7594, \"logprob_ECE\": 0.1288, \"EM_rho\": 0.4613, \"EM_AUROC\": 0.7391, \"EM_ECE\": 0.1084, \"voting_conf_rho\": 0.4554, \"voting_conf_AUROC\": 0.7406, \"voting_conf_ECE\": 0.0844}, \"conditional\": {\"SJ_rho\": 0.4597, \"SJ_AUROC\": 0.7565, \"SJ_ECE\": 0.0846, \"FK_rho\": 0.4515, \"FK_AUROC\": 0.753, \"FK_ECE\": 0.0813, \"logprob_rho\": 0.3193, \"logprob_AUROC\": 0.8023, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.4618, \"EM_AUROC\": 0.7589, \"EM_ECE\": 0.0757, \"voting_conf_rho\": 0.3978, \"voting_conf_AUROC\": 0.7287, \"voting_conf_ECE\": 0.0742}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9213, \"sj_best\": 0.9259, \"logprob_best\": 0.925, \"voting_conf_best\": 0.9268, \"oracle\": 0.9487}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0328, \"full_FK_rho_delta\": 0.0289, \"full_logprob_rho_delta\": -0.0014, \"full_EM_rho_delta\": 0.0307, \"full_voting_conf_rho_delta\": 0.0298, \"cond_SJ_rho_delta\": 0.0241, \"cond_FK_rho_delta\": 0.0205, \"cond_logprob_rho_delta\": -0.0089, \"cond_EM_rho_delta\": 0.0215, \"cond_voting_conf_rho_delta\": 0.0235}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:45:16.265Z\"}, \"exp_017_llama_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.084Z\", \"updated_at\": \"2026-05-14T19:43:06.607Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL-2003 NER N=16 seed=123: cross-seed robustness check against N=8 seed=42 baseline (exp_017_llama_conll_infer)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s123\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9497, \"oracle_headroom\": 0.0231, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4698, \"SJ_AUROC\": 0.7402, \"SJ_ECE\": 0.1135, \"FK_rho\": 0.4594, \"FK_AUROC\": 0.7351, \"FK_ECE\": 0.1114, \"logprob_rho\": 0.3161, \"logprob_AUROC\": 0.768, \"logprob_ECE\": 0.129, \"EM_rho\": 0.4676, \"EM_AUROC\": 0.7399, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4612, \"voting_conf_AUROC\": 0.7429, \"voting_conf_ECE\": 0.0832}, \"conditional\": {\"SJ_rho\": 0.4712, \"SJ_AUROC\": 0.7609, \"SJ_ECE\": 0.0828, \"FK_rho\": 0.4595, \"FK_AUROC\": 0.7547, \"FK_ECE\": 0.0858, \"logprob_rho\": 0.3314, \"logprob_AUROC\": 0.8134, \"logprob_ECE\": 0.0922, \"EM_rho\": 0.4732, \"EM_AUROC\": 0.7626, \"EM_ECE\": 0.075, \"voting_conf_rho\": 0.4086, \"voting_conf_AUROC\": 0.7338, \"voting_conf_ECE\": 0.0706}, \"best_of_n\": {\"greedy\": 0.9242, \"random_avg\": 0.9216, \"sj_best\": 0.9247, \"logprob_best\": 0.9253, \"voting_conf_best\": 0.9255, \"oracle\": 0.9486}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0384, \"full_FK_rho_delta\": 0.0317, \"full_logprob_rho_delta\": 0.0089, \"full_SJ_AUROC_delta\": 0.0363, \"full_FK_AUROC_delta\": 0.0325, \"full_logprob_AUROC_delta\": 0.007, \"cond_SJ_rho_delta\": 0.0356, \"cond_FK_rho_delta\": 0.0285, \"cond_logprob_rho_delta\": 0.0032}}, \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:43:06.607Z\"}, \"exp_007_llama_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:31:44.366Z\", \"updated_at\": \"2026-05-14T19:03:50.284Z\", \"spec\": {\"hypothesis\": \"LLaMA SciERC N=16: cross-model N-scaling validation. If SJ rho increases from N=8 (0.363) to N=16, N-scaling is model-agnostic.\", \"plan_id\": \"exp-007\", \"parent\": \"exp_007_llama_inference\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"eval_data\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_007_llama_n16/samples.jsonl\", \"log_path\": \"output/exp_007_llama_n16.log\", \"completed_at\": \"2026-05-14T19:03:39.163Z\", \"metrics\": {\"N\": 16, \"dataset\": \"scierc\", \"subtask\": \"ner\", \"n_instances\": 551, \"n_valid\": 529, \"n_conditional\": 478, \"greedy_f1\": 0.645, \"full\": {\"SJ_rho\": 0.3791, \"FK_rho\": 0.3081, \"logprob_rho\": 0.2041, \"EM_rho\": 0.3159, \"voting_conf_rho\": 0.4515, \"SJ_AUROC\": 0.717, \"FK_AUROC\": 0.6581, \"logprob_AUROC\": 0.5656, \"EM_AUROC\": 0.7686, \"voting_conf_AUROC\": 0.7266, \"SJ_ECE\": 0.1019, \"FK_ECE\": 0.1556, \"logprob_ECE\": 0.084, \"EM_ECE\": 0.1761, \"voting_conf_ECE\": 0.1365}, \"conditional\": {\"SJ_rho\": 0.3222, \"FK_rho\": 0.2182, \"logprob_rho\": 0.1286, \"EM_rho\": 0.3563, \"voting_conf_rho\": 0.3356, \"SJ_AUROC\": 0.7014, \"FK_AUROC\": 0.6392, \"logprob_AUROC\": 0.545, \"EM_AUROC\": 0.7708, \"voting_conf_AUROC\": 0.6988, \"SJ_ECE\": 0.1466, \"FK_ECE\": 0.1853, \"logprob_ECE\": 0.1141, \"EM_ECE\": 0.1887, \"voting_conf_ECE\": 0.2634}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0161, \"FK\": -0.0185, \"logprob\": 0.0214, \"EM\": 0.0007, \"voting_conf\": 0.0184}}}, \"exp_002_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:12:16.041Z\", \"updated_at\": \"2026-05-14T19:03:19.801Z\", \"spec\": {\"hypothesis\": \"Qwen CoNLL-2003 N=16: cross-dataset N-scaling comparison with SciERC N=16\", \"plan_id\": \"exp-002\", \"parent\": \"exp_002_ner_conll2003\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_002_conll_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"N\": 16, \"dataset\": \"conll2003\", \"subtask\": \"ner\", \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2614, \"greedy_f1\": 0.907, \"full\": {\"SJ_rho\": 0.4496, \"FK_rho\": 0.3928, \"logprob_rho\": 0.3146, \"EM_rho\": 0.4627, \"voting_conf_rho\": 0.4286, \"SJ_AUROC\": 0.8264, \"FK_AUROC\": 0.7821, \"logprob_AUROC\": 0.7531, \"EM_AUROC\": 0.8409, \"voting_conf_AUROC\": 0.8071, \"SJ_ECE\": 0.0747, \"FK_ECE\": 0.1786, \"logprob_ECE\": 0.2031, \"EM_ECE\": 0.0786, \"voting_conf_ECE\": 0.529}, \"conditional\": {\"SJ_rho\": 0.4208, \"FK_rho\": 0.3494, \"logprob_rho\": 0.3756, \"EM_rho\": 0.4658, \"voting_conf_rho\": 0.3654, \"SJ_AUROC\": 0.8405, \"FK_AUROC\": 0.7819, \"logprob_AUROC\": 0.8259, \"EM_AUROC\": 0.8781, \"voting_conf_AUROC\": 0.7951, \"SJ_ECE\": 0.0982, \"FK_ECE\": 0.1899, \"logprob_ECE\": 0.2504, \"EM_ECE\": 0.0997, \"voting_conf_ECE\": 0.6096}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0139, \"FK\": -0.007, \"logprob\": -0.0011, \"EM\": 0.012, \"voting_conf\": 0.0049}}, \"checkpoint_path\": \"output/exp_002_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_002_conll_n16.log\", \"completed_at\": \"2026-05-14T18:58:40.473Z\"}, \"exp_009_v2_re_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:56:31.535Z\", \"updated_at\": \"2026-05-14T18:56:58.168Z\", \"spec\": {\"command\": \"python code/exp_009_v2_re_rerun.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_008_re_n16_v2/samples.jsonl\", \"data_count\": 397, \"model_name\": \"cpu_analysis\", \"seed\": 42, \"checkpoint_source\": \"exp_008_re_n16_v2\", \"checkpoint_path\": \"output/exp_009_v2_re_rerun/results.json\", \"log_path\": \"/tmp/re_rerun.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:56:58.168Z\"}, \"exp_001_seed456_v2_ner\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:13:00.414Z\", \"updated_at\": \"2026-05-14T18:55:18.772Z\", \"spec\": {\"hypothesis\": \"NER N=16 seed=456 robustness test (NER-only rerun, fixing subtask mismatch from exp_001_seed456_v2)\", \"plan_id\": \"exp-001\", \"parent\": \"exp_001_seed456_v2\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"data/scierc/processed_data\", \"metrics\": {\"sj_rho\": 0.384, \"structural_gt_surface\": true, \"structural_surface_delta\": 0.16}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2_ner/\"}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"pid\": 96161, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:52:01.372Z\", \"metrics\": {\"full\": {\"SJ\": {\"rho\": 0.384, \"auroc\": 0.711}, \"FK\": {\"rho\": 0.223, \"auroc\": 0.577}, \"logprob\": {\"rho\": 0.232, \"auroc\": 0.594}, \"EM\": {\"rho\": 0.316, \"auroc\": 0.768}, \"voting_conf\": {\"rho\": 0.411, \"auroc\": 0.712}}, \"conditional\": {\"SJ\": {\"rho\": 0.349, \"auroc\": 0.699}, \"FK\": {\"rho\": 0.157, \"auroc\": 0.561}, \"logprob\": {\"rho\": 0.171, \"auroc\": 0.576}, \"EM\": {\"rho\": 0.406, \"auroc\": 0.78}, \"voting_conf\": {\"rho\": 0.346, \"auroc\": 0.694}}, \"3seed_mean_SJ_rho_full\": 0.412, \"3seed_sd_SJ_rho_full\": 0.025, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}}, \"exp_003_wnut17_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:56.415Z\", \"updated_at\": \"2026-05-14T18:11:36.559Z\", \"spec\": {\"description\": \"WNUT-17 retrain: downsample gold-empty instances to ≤25%, fine-tune Qwen3-8B, inference N=16 T=1.0 with log-probs\", \"hypothesis\": \"After removing excess empty instances, structural consistency signals (SJ) will show stronger correlation on social media NER\", \"plan_id\": \"exp-003\", \"claim\": 1, \"model_name\": \"Qwen3-8B\", \"dataset\": \"WNUT-17 (downsampled)\", \"priority\": \"P0\", \"parent\": \"exp_003_ner_wnut17\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_wnut17.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train_downsampled.json\", \"data_count\": 1637, \"seed\": 42, \"pid\": 92215, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_wnut17.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-lora\", \"downsampling\": \"empty instances 63.8% -> 25.0%, total 3394 -> 1637\", \"metrics\": {\"train_loss\": 0.105, \"eval_loss\": 0.0836, \"epochs\": 5, \"train_time_min\": 16.37, \"train_samples_per_sec\": 8.33}, \"note\": \"D045: Training succeeded (train_loss=0.105) but inference FAIL: 54% F1=0, SJ rho=0.062 (p=0.106). WNUT-17 abandoned — model capability insufficient on social media NER. Paper reports as Claim 3 (capability boundary) evidence.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:11:36.559Z\"}, \"exp_017_llama_conll_infer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:33:23.653Z\", \"updated_at\": \"2026-05-14T17:55:35.572Z\", \"spec\": {\"hypothesis\": \"LLaMA-3.1-8B CoNLL-2003 inference: cross-model cross-dataset validation of structural consistency signals\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll\", \"command\": \"python code/run_llama_conll_infer.py\", \"server\": \"autodl-5090\", \"data_path\": \"conll2003 test\", \"data_count\": 3453, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"n_samples\": 8, \"temperature\": 1, \"description\": \"LLaMA CoNLL-2003 NER inference N=8 (cross-model + cross-dataset validation)\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9443, \"oracle_headroom\": 0.0177, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"N\": 8, \"full\": {\"SJ_rho\": 0.4314, \"FK_rho\": 0.4277, \"logprob_rho\": 0.3072, \"EM_rho\": 0.4306, \"voting_conf_rho\": 0.4256, \"SJ_AUROC\": 0.7039, \"FK_AUROC\": 0.7026, \"logprob_AUROC\": 0.761, \"EM_AUROC\": 0.7046, \"voting_conf_AUROC\": 0.7088, \"SJ_ECE\": 0.1137, \"FK_ECE\": 0.1053, \"logprob_ECE\": 0.129, \"EM_ECE\": 0.1094, \"voting_conf_ECE\": 0.0949}, \"conditional\": {\"SJ_rho\": 0.4356, \"FK_rho\": 0.431, \"logprob_rho\": 0.3282, \"EM_rho\": 0.4403, \"voting_conf_rho\": 0.3743, \"SJ_AUROC\": 0.7225, \"FK_AUROC\": 0.7208, \"logprob_AUROC\": 0.8102, \"EM_AUROC\": 0.7257, \"voting_conf_AUROC\": 0.6989, \"SJ_ECE\": 0.0829, \"FK_ECE\": 0.0796, \"logprob_ECE\": 0.0922, \"EM_ECE\": 0.0754, \"voting_conf_ECE\": 0.0784}}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:55:33.476Z\", \"notes\": \"LLaMA CoNLL-2003 NER N=8 (not N=16, cost constraint: 3453 test instances). SJ ρ=0.431 > logprob ρ=0.307 (Δ=+0.124). ρ-AUROC dissociation: logprob AUROC=0.761 > SJ AUROC=0.704. All 4 structural signals ρ>0.42 vs logprob 0.31. Directly comparable to exp_002 (Qwen CoNLL N=8) and exp_007 (LLaMA SciERC N=8).\"}, \"exp_008_re_n16_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:45:10.852Z\", \"updated_at\": \"2026-05-14T17:51:43.957Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --num_test 9999 --output_dir output/exp008_re_n16/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"62585\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_008_re_n16_full.log\", \"submitted_at\": \"2026-05-14T12:45:10.764Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18393.2, \"gpu_hours\": 5.11}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_008_re_n16_t10_full (full 551-instance RE-only run on autodl-5090)\", \"completed_at\": \"2026-05-14T17:51:43.957Z\"}, \"exp_017_llama_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:39:32.014Z\", \"updated_at\": \"2026-05-14T17:30:26.798Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_llama_conll2003.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 14041, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"failure_reason\": null, \"metrics\": {\"train_loss\": 0.039, \"eval_loss\": 0.023, \"epochs\": 5, \"train_time\": \"2h22m\"}, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/exp017_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-conll2003-lora/\", \"note\": \"Training completed successfully. Checkpoint includes adapter_model.safetensors + intermediate checkpoints (200/400/515). Previously misclassified as failed due to narrow log search path.\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:12:15.687Z\"}, \"exp_001_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:38:55.569Z\", \"updated_at\": \"2026-05-14T17:12:14.682Z\", \"spec\": {\"hypothesis\": \"NER/RE N=16 seed=456 robustness test, third seed for 3-seed stability\", \"plan_id\": \"exp-001\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"metrics\": {\"full_rho_kappa_f1\": 0.3383, \"full_rho_sj_f1\": 0.2988, \"cond_rho_kappa_f1\": 0.233, \"cond_rho_sj_f1\": 0.3245, \"logprob_full_rho\": 0.3405, \"logprob_full_auroc\": 0.6694, \"logprob_cond_rho\": 0.0501, \"structural_gt_surface\": false}, \"note\": \"CRITICAL: Ran with --subtask joint instead of --subtask ner. seed42/seed123 v2 used --subtask ner. Results valid for joint-mode analysis but NOT comparable for NER 3-seed protocol. Need NER-only rerun.\", \"log_path\": \"output/exp_001_seed456_v2/run.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:12:14.682Z\"}, \"exp_016_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:39:07.501Z\", \"updated_at\": \"2026-05-14T15:39:39.950Z\", \"spec\": {\"command\": \"python code/exp_016_v2_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis_only\", \"seed\": 42, \"checkpoint_path\": \"output/exp_016_v2/\", \"log_path\": \"/tmp/exp016v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:39:34.478Z\", \"metrics\": {\"ner_conditional\": {\"n\": 529, \"best_single_signal_rho\": {\"soft_jaccard\": 0.4412}, \"best_combo_rho\": {\"sj+vc_a0.55\": 0.4552}, \"ensemble_auroc\": 0.7141, \"best_single_auroc\": {\"soft_jaccard\": 0.7166}, \"selection_f1\": {\"greedy\": 0.6442, \"logprob_best\": 0.6505, \"ensemble_best\": 0.6475, \"sj_best\": 0.6471, \"oracle\": 0.8442}}, \"re_conditional\": {\"n\": 397, \"best_single_signal_rho\": {\"voting_confidence\": 0.3849}, \"best_combo_rho\": {\"logprob+vc_a0.25\": 0.3936}, \"ensemble_auroc\": 0.6916, \"best_single_auroc\": {\"voting_confidence\": 0.7023}, \"selection_f1\": {\"greedy\": 0.403, \"logprob_best\": 0.4097, \"ensemble_best\": 0.4227, \"oracle\": 0.6306}}, \"re_full\": {\"ensemble_auroc\": 0.8608, \"best_single_auroc\": {\"voting_confidence\": 0.8248}}}}, \"exp_009_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:36:47.946Z\", \"updated_at\": \"2026-05-14T15:37:27.960Z\", \"spec\": {\"command\": \"python3 code/exp_009_v2_stratification.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis\", \"seed\": 42}, \"checkpoint_path\": \"output/exp_009_v2/results.json\", \"log_path\": \"output/exp_009_v2_run.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:37:18.311Z\", \"metrics\": {\"ner_seed42_global\": {\"sj_rho\": 0.431, \"fk_rho\": 0.325, \"logprob_rho\": 0.203, \"voting_conf_rho\": 0.475, \"em_rho\": 0.292}, \"ner_seed123_global\": {\"sj_rho\": 0.422, \"fk_rho\": 0.315, \"logprob_rho\": 0.226, \"voting_conf_rho\": 0.438, \"em_rho\": 0.299}, \"re_seed42_global\": {\"sj_rho\": 0.063, \"fk_rho\": 0.226, \"logprob_rho\": 0.4, \"voting_conf_rho\": 0.22, \"em_rho\": -0.132}, \"ner_seed_stability_max_delta\": 0.037, \"independent_proxies\": [\"sent_len\", \"ent_count\", \"type_diversity\"], \"inverted_u_ner\": \"not confirmed (ρ stable across independent proxies)\", \"inverted_u_re\": \"monotonic increase with complexity, not inverted-U\"}}, \"exp_004_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:31:40.554Z\", \"updated_at\": \"2026-05-14T15:32:04.966Z\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/analyze_exp004_v2_re_diagnostic.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"Qwen2.5-7B-Instruct (SFT)\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004v2_re_diagnostic/\"}, \"completed_at\": \"2026-05-14T15:32:04.966Z\"}, \"exp_006_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:30:02.348Z\", \"updated_at\": \"2026-05-14T15:30:41.053Z\", \"spec\": {\"command\": \"python3 code/exp_006_v2_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_{001_seed42,001_seed123,002_conll,008_re}_v2/\", \"data_count\": 4952, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_006_v2/exp_006_v2_results.json\", \"log_path\": \"output/exp_006_v2_run.log\", \"completed_at\": \"2026-05-14T15:30:32.474Z\", \"metrics\": {\"NER_SciERC_s42\": {\"greedy\": 0.618, \"oracle\": 0.787, \"SJ\": 0.62, \"logprob\": 0.621, \"FK\": 0.621, \"EM\": 0.606, \"voting_conf\": 0.585, \"random\": 0.586}, \"NER_SciERC_s123\": {\"greedy\": 0.618, \"oracle\": 0.785, \"SJ\": 0.617, \"logprob\": 0.618, \"FK\": 0.621, \"EM\": 0.613, \"voting_conf\": 0.584, \"random\": 0.583}, \"NER_CoNLL\": {\"greedy\": 0.725, \"oracle\": 0.757, \"SJ\": 0.718, \"logprob\": 0.716, \"FK\": 0.717, \"EM\": 0.716, \"voting_conf\": 0.714, \"random\": 0.692}, \"RE_SciERC\": {\"greedy\": 0.403, \"oracle\": 0.631, \"SJ\": 0.397, \"logprob\": 0.41, \"FK\": 0.396, \"EM\": 0.381, \"voting_conf\": 0.408, \"random\": 0.364}}}, \"exp_005_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:28:14.924Z\", \"updated_at\": \"2026-05-14T15:28:35.949Z\", \"spec\": {\"description\": \"Temperature sensitivity analysis: T=0.7 vs T=1.0 across 5 signals (SJ, FK, logprob, EM, voting_conf)\", \"command\": \"python code/analyze_exp005_v2_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/mvp_pilot_004 + output/mvp_pilot_005 + output/exp_012_logprob\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_005_v2_temperature/temperature_sensitivity_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:28:35.949Z\"}, \"exp_008_re_n16_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:06.296Z\", \"updated_at\": \"2026-05-14T15:23:59.395Z\", \"spec\": {\"description\": \"RE N=16 on SciERC full set confirmation, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1 on SciERC full dataset\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_n16_v2\", \"gpu\": [\"cuda:3\"], \"pid\": \"78737\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_n16_v2/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sj_rho_full\": 0.281, \"sj_rho_cond\": 0.308, \"f1_zero_pct\": 44.3, \"conclusion_note\": \"RE N=16 v2 negative: SJ weak, 44.3% F1=0\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.598Z\", \"log_path\": \"output/exp_008_re_n16_v2/\"}, \"exp_001_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:04.210Z\", \"updated_at\": \"2026-05-14T15:23:56.155Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=123, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC (seed robustness check)\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 123, \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed123_v2\", \"gpu\": [\"cuda:2\"], \"pid\": \"78733\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed123_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.424, \"sj_rho_cond\": 0.376, \"structural_minus_surface\": 0.149, \"conclusion_note\": \"NER seed123 robustness confirmed, structural>surface +0.149\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.076Z\", \"log_path\": \"output/exp_001_seed123_v2/\"}, \"exp_001_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:02.350Z\", \"updated_at\": \"2026-05-14T15:23:52.846Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=42, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed42_v2\", \"gpu\": [\"cuda:1\"], \"pid\": \"78728\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed42_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.428, \"sj_rho_cond\": 0.369, \"structural_minus_surface\": 0.147, \"conclusion_note\": \"NER seed42 robustness confirmed, structural>surface +0.147\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:34.091Z\", \"log_path\": \"output/exp_001_seed42_v2/\"}, \"exp_008_re_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:51.386Z\", \"updated_at\": \"2026-05-14T15:21:39.591Z\", \"spec\": {\"description\": \"RE N=16 on SciERC, seed=123, seed robustness test for relation extraction\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1, robust across seeds\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": [\"cuda:3\"], \"backend\": \"tmux\", \"tmux_session\": \"exp008_rs123\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_seed123/run.log\"}, \"log_path\": \"output/exp_008_re_seed123/run.log\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.4229, \"oracle_f1\": 0.6244, \"oracle_headroom\": 0.2015, \"fleiss_kappa_mean\": 0.3455, \"soft_jaccard_mean\": 0.6126, \"sample_f1_mean\": 0.3594, \"sample_f1_std\": 0.3793, \"sample_f1_zero_pct\": 44.1, \"structural_gt_surface\": false, \"rho_kappa_f1_full\": 0.3174, \"rho_sj_f1_full\": 0.2835, \"rho_kappa_f1_cond\": 0.0766, \"rho_sj_f1_cond\": 0.2877, \"logprob_auroc_full\": 0.6499, \"logprob_auroc_cond\": 0.5265, \"verdict\": \"FAIL\"}, \"checkpoint_path\": \"N/A\", \"completed_at\": \"2026-05-14T15:21:39.591Z\"}, \"exp_007_llama_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.157Z\", \"updated_at\": \"2026-05-14T15:19:47.267Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=123, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 123, \"gpu\": [\"cuda:1\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s123\", \"account\": \"root\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T15:19:43.424Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6605, \"oracle_f1\": 0.7703, \"headroom\": 0.1098, \"fleiss_kappa\": 0.4553, \"soft_jaccard\": 0.7525, \"rho_kappa_f1\": 0.2143, \"rho_sj_f1\": 0.3371, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.433, \"oracle_f1\": 0.5719, \"headroom\": 0.1389, \"fleiss_kappa\": 0.3851, \"soft_jaccard\": 0.6911, \"rho_kappa_f1\": 0.2844, \"rho_sj_f1\": 0.268, \"structural_gt_surface\": false}, \"fail_reasons\": [\"RE rho_sj=0.2680 < 0.40 threshold\", \">30% samples F1=0 (RE: 41.0%)\", \"RE structural not > surface (delta=-0.0165)\"]}}, \"exp_007_llama_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.628Z\", \"updated_at\": \"2026-05-14T15:19:27.040Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=456, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed456\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 456, \"gpu\": [\"cuda:2\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s456\", \"account\": \"root\", \"log_path\": \"output/exp_007_llama_seed456/run.log\"}, \"conclusion\": \"negative\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/\", \"completed_at\": \"2026-05-14T15:19:20.693Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6597, \"oracle_f1\": 0.7575, \"oracle_headroom\": 0.0978, \"fleiss_kappa\": 0.4543, \"soft_jaccard\": 0.7491, \"rho_kappa_f1\": 0.3115, \"rho_sj_f1\": 0.3663, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.4334, \"oracle_f1\": 0.5789, \"oracle_headroom\": 0.1455, \"fleiss_kappa\": 0.3791, \"soft_jaccard\": 0.6782, \"rho_kappa_f1\": 0.3013, \"rho_sj_f1\": 0.287, \"structural_gt_surface\": false}, \"logprob_ner\": {\"rho\": 0.1911, \"auroc\": 0.5989}, \"logprob_re\": {\"rho\": 0.3246, \"auroc\": 0.6678}, \"fail_reason\": \"RE rho_sj=0.2870 < 0.40 threshold; >30% samples F1=0\"}}, \"exp_015_metrics_expansion\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:47:36.569Z\", \"updated_at\": \"2026-05-14T15:16:34.851Z\", \"spec\": {\"hypothesis\": \"Comprehensive evaluation of all 5 confidence signals with extended metrics\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"exp_012_logprob_baseline\", \"method\": \"CPU-only analysis: 6 metrics x 5 signals x 2 subtasks (NER+RE)\", \"command\": \"python code/analyze_exp015_metrics_expansion.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp015_metrics_expansion\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:22:32.661Z\", \"metrics\": {\"data_source\": \"exp_012_logprob/samples_with_logprobs.jsonl\", \"config\": \"N=8, T=1.0, seed=42, model=qwen3-8b-scierc-merged-v2\", \"ner\": {\"n_valid\": 529, \"n_cond\": 501, \"voting_rho_full\": 0.5018, \"voting_rho_cond\": 0.4497, \"voting_auroc\": 0.7279, \"voting_tau\": 0.3766, \"sj_rho_full\": 0.3565, \"sj_rho_cond\": 0.412, \"sj_auroc\": 0.6656, \"sj_tau\": 0.2658, \"em_rho_full\": 0.2566, \"em_rho_cond\": 0.3427, \"em_auroc\": 0.623, \"em_tau\": 0.1924, \"fk_rho_full\": 0.2651, \"fk_rho_cond\": 0.306, \"fk_auroc\": 0.6243, \"fk_tau\": 0.2027, \"logprob_rho_full\": 0.1396, \"logprob_rho_cond\": 0.1627, \"logprob_auroc\": 0.5585, \"logprob_tau\": 0.1006}, \"re\": {\"n_valid\": 397, \"n_cond\": 296, \"voting_rho_full\": 0.4217, \"voting_rho_cond\": 0.463, \"voting_auroc\": 0.7162, \"voting_tau\": 0.327, \"sj_rho_full\": 0.2112, \"sj_rho_cond\": 0.3683, \"sj_auroc\": 0.5816, \"sj_tau\": 0.1619, \"em_rho_full\": 0.1002, \"em_rho_cond\": 0.3607, \"em_auroc\": 0.5036, \"em_tau\": 0.0839, \"fk_rho_full\": 0.2528, \"fk_rho_cond\": 0.3168, \"fk_auroc\": 0.6308, \"fk_tau\": 0.1967, \"logprob_rho_full\": 0.2467, \"logprob_rho_cond\": 0.1457, \"logprob_auroc\": 0.6354, \"logprob_tau\": 0.1808}, \"diagnosis\": \"Unified 5-signal evaluation on single data source. Voting leads NER full (ρ=0.502), SJ retains strength in NER cond (ρ=0.412). All structural signals beat logprob on NER. RE: voting leads both full and cond.\"}}, \"exp_010_selection_curves\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:01:53.585Z\", \"updated_at\": \"2026-05-14T15:02:34.760Z\", \"spec\": {\"command\": \"python3 code/exp010_selection_curves.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2, output/exp_008_re_n16_v2, output/exp002_conll2003\", \"data_count\": \"551+397+3453 instances\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"description\": \"Best-of-N selection curves: F1 vs N for 7 signals across 3 datasets\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp010.log\", \"completed_at\": \"2026-05-14T15:02:22.638Z\", \"metrics\": {\"scierc_ner\": {\"n_instances\": 551, \"greedy_f1\": 0.618, \"N16\": {\"oracle\": 0.787, \"SJ\": 0.62, \"FK\": 0.621, \"logprob\": 0.621, \"voting_conf\": 0.585, \"EM\": 0.606, \"random\": 0.595}, \"N8\": {\"oracle\": 0.752, \"SJ\": 0.614, \"FK\": 0.614, \"logprob\": 0.619, \"voting_conf\": 0.591, \"EM\": 0.603, \"random\": 0.589}, \"N4\": {\"oracle\": 0.714, \"SJ\": 0.607, \"FK\": 0.608, \"logprob\": 0.616, \"voting_conf\": 0.594, \"EM\": 0.6, \"random\": 0.587}}, \"scierc_re\": {\"n_instances\": 397, \"greedy_f1\": 0.403, \"N16\": {\"oracle\": 0.631, \"SJ\": 0.397, \"FK\": 0.396, \"logprob\": 0.41, \"voting_conf\": 0.408, \"EM\": 0.381, \"random\": 0.364}, \"N8\": {\"oracle\": 0.583, \"SJ\": 0.393, \"FK\": 0.394, \"logprob\": 0.413, \"voting_conf\": 0.398, \"EM\": 0.381, \"random\": 0.363}}, \"conll_ner\": {\"n_instances\": 3453, \"greedy_f1\": 0.725, \"N8\": {\"oracle\": 0.757, \"SJ\": 0.718, \"FK\": 0.717, \"logprob\": 0.716, \"voting_conf\": 0.714, \"EM\": 0.716, \"random\": 0.69}, \"N4\": {\"oracle\": 0.746, \"SJ\": 0.714, \"FK\": 0.714, \"logprob\": 0.715, \"voting_conf\": 0.714, \"EM\": 0.712, \"random\": 0.692}}}}, \"exp_009_capability_stratification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:59:24.201Z\", \"updated_at\": \"2026-05-14T14:59:53.951Z\", \"spec\": {\"command\": \"python code/exp009_stratification_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp001_n16_seed42 + output/exp008_re_n16 + output/exp002_conll2003\", \"data_count\": 4555, \"model_name\": \"analysis_only\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp009_stratification_results.json\", \"log_path\": \"/tmp/exp009.log\", \"completed_at\": \"2026-05-14T14:59:46.463Z\", \"metrics\": {\"scierc_ner\": {\"n\": 551, \"sj_rho_overall\": 0.398, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": 0.159, \"med_low_sj_rho\": 0.139, \"med_high_sj_rho\": 0.09, \"easy_sj_rho\": 0.23}, \"by_sent_len\": {\"Q1_sj_rho\": 0.461, \"Q2_sj_rho\": 0.401, \"Q3_sj_rho\": 0.296, \"Q4_sj_rho\": 0.382}, \"by_ent_count\": {\"0_sj_rho\": 0.689, \"1_2_sj_rho\": 0.415, \"3_5_sj_rho\": 0.353, \"6plus_sj_rho\": 0.547}}, \"scierc_re\": {\"n\": 551, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": -0.043, \"easy_sj_rho\": 0.21}, \"by_sent_len\": {\"Q1_sj_rho\": 0.447, \"Q4_sj_rho\": 0.54}, \"by_rel_count\": {\"0_sj_rho\": 0.62, \"1_2_sj_rho\": 0.275, \"6plus_sj_rho\": 0.527}}, \"conll_ner\": {\"n\": 3453, \"by_sent_len\": {\"Q1_sj_rho\": 0.334, \"Q3_sj_rho\": 0.518}}, \"proxy_independence\": {\"scierc_ner_f1_vs_slen\": -0.021, \"scierc_ner_f1_vs_ecnt\": 0.007, \"scierc_re_f1_vs_slen\": -0.147}}}, \"exp_003_wnut17_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:47:34.654Z\", \"updated_at\": \"2026-05-14T14:28:43.864Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_eval --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/wnut17\", \"data_count\": 1287, \"model_name\": \"qwen3-8b-wnut17-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:08:17.429Z\", \"metrics\": {\"greedy_f1\": 0.523, \"oracle_f1\": 0.664, \"headroom\": 0.141, \"rho_fk\": 0.125, \"rho_sj\": 0.089, \"rho_fk_cond\": 0.169, \"rho_sj_cond\": 0.288, \"rho_logprob_full\": -0.409, \"rho_logprob_cond\": 0.35, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 53.7, \"n_instances\": 1287, \"N\": 16, \"T\": 1, \"seed\": 42, \"model\": \"Qwen3-8B\", \"n_gold_empty_filtered\": 598, \"verdict\": \"FAIL\", \"verdict_note\": \"structural_beats_surface=false; >50% samples F1=0\"}}, \"exp_007_llama_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:54:48.055Z\", \"updated_at\": \"2026-05-14T14:28:32.909Z\", \"spec\": {\"command\": \"python run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp007_llama_inference/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"75172\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_llama_inference.log\", \"submitted_at\": \"2026-05-14T13:54:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Meta-Llama-3.1-8B-Instruct (LoRA fine-tuned on SciERC)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"description\": \"LLaMA-3.1-8B SciERC joint inference (NER+RE) with 8 samples, T=1.0, logprobs collected.\", \"wall_clock_seconds\": 1038.5, \"gpu_hours\": 0.29}, \"log_path\": \"output/exp007_llama_inference/\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.66, \"oracle_f1\": 0.781, \"headroom\": 0.121, \"rho_fk\": 0.327, \"rho_sj\": 0.363, \"rho_fk_cond\": 0.226, \"rho_sj_cond\": 0.311, \"rho_logprob\": 0.183, \"rho_logprob_cond\": 0.109, \"structural_beats_surface\": true, \"sample_f1_pct_zero\": 11.6}, \"re\": {\"greedy_f1\": 0.434, \"oracle_f1\": 0.568, \"headroom\": 0.135, \"rho_fk\": 0.305, \"rho_sj\": 0.299, \"rho_fk_cond\": 0.259, \"rho_sj_cond\": 0.405, \"rho_logprob\": 0.288, \"rho_logprob_cond\": 0.092, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 41.2}, \"n_instances\": 551, \"N\": 8, \"T\": 1, \"seed\": 42, \"model\": \"LLaMA-3.1-8B-Instruct\", \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj_full=0.299 < 0.40; >30% RE samples F1=0\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:12:06.442Z\"}, \"exp_008_re_n16_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.867Z\", \"updated_at\": \"2026-05-14T14:05:49.091Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:18.988Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:19.577Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:21.528032+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.444}, \"re\": {\"rho_sj\": 0.248}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 42, \"mode\": \"RE-only\", \"source\": \"director_corrected\"}}, \"exp_001_seed123_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.503Z\", \"updated_at\": \"2026-05-14T14:05:38.817Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:13.823Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:13.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:16.532801+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.417, \"rho_fk\": 0.283}, \"re\": {\"rho_sj\": 0.265, \"rho_fk\": 0.315}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 123, \"source\": \"reviewer_verified_report_json\"}}, \"exp_001_seed456_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:41.067Z\", \"updated_at\": \"2026-05-14T14:05:37.904Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:05.416Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:05.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:10.317185+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.414, \"rho_fk\": 0.298}, \"re\": {\"rho_sj\": 0.268, \"rho_fk\": 0.26}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 456, \"source\": \"reviewer_verified_report_json\"}}, \"exp_003_ner_wnut17\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:17.544Z\", \"updated_at\": \"2026-05-14T13:40:20.979Z\", \"spec\": {\"merged_model_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"pilot_command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_pilot --num_test 9999 --collect_logprobs\", \"pilot_pid\": 71498, \"pilot_server\": \"autodl-5090\", \"pilot_started_at\": \"2026-05-14T21:36:00Z\", \"test_samples\": 1287}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-14T11:43:50.537Z\", \"finished_at\": \"2026-05-14T12:53:13.262Z\", \"training_hours\": 1.16}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:53:14.768981+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.525, \"oracle_f1\": 0.664, \"headroom\": 0.139, \"rho_sj_full\": 0.082, \"rho_fk_full\": 0.124, \"rho_logprob_full\": -0.414, \"rho_sj_cond\": 0.275, \"rho_fk_cond\": 0.164, \"rho_logprob_cond\": 0.352, \"sj_beats_logprob_cond\": false}, \"n_instances\": 1287, \"n_gold_empty\": 598, \"sample_f1_mean\": 0.401, \"sample_f1_pct_zero\": 53.7, \"N\": 16, \"T\": 1, \"seed\": 42, \"verdict\": \"FAIL\", \"verdict_note\": \">30% samples F1=0; structural rho weak; logprob baseline stronger\"}, \"conclusion\": \"negative\", \"log_path\": \"output/exp003_wnut17_pilot/\", \"completed_at\": \"2026-05-14T13:40:20.979Z\"}, \"exp_007_ner_multi_model\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:20.748Z\", \"updated_at\": \"2026-05-14T13:35:43.251Z\", \"spec\": {\"command\": \"bash -c 'source env.sh && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_llama.yaml'\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"60970\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"submitted_at\": \"2026-05-14T12:43:09.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data\", \"data_count\": 1861, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"log_file\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"wall_clock_seconds\": 165.8, \"gpu_hours\": 0.05}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T11:43:50.977Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:45:54.952Z\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-scierc-lora\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0767, \"eval_loss\": 0.1049, \"train_runtime_sec\": 1494.5, \"train_samples_per_second\": 6.226, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"base_model\": \"Meta-Llama-3.1-8B-Instruct\", \"lora_r\": 32, \"lora_alpha\": 64, \"note\": \"EXIT_CODE=129 (SIGHUP) but training completed all 5 epochs before signal. Checkpoint fully intact.\"}, \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\"}, \"exp_001_ner_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:46:06.430Z\", \"updated_at\": \"2026-05-14T13:33:40.719Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"63407\", \"log_path\": \"output/exp001_n16_seed123_run.log\", \"submitted_at\": \"2026-05-14T12:46:06.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 551, \"data_path\": \"data/scierc/processed_data\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"checkpoint_path\": \"output/exp001_n16_seed123/\", \"wall_clock_seconds\": 2748.0, \"gpu_hours\": 0.76}, \"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.809, \"headroom\": 0.146, \"rho_sj\": 0.423, \"rho_fk\": 0.29, \"rho_logprob\": 0.239, \"rho_sj_cond\": 0.423, \"rho_fk_cond\": 0.26}, \"re\": {\"greedy_f1\": 0.419, \"oracle_f1\": 0.625, \"headroom\": 0.206, \"rho_sj\": 0.267, \"rho_fk\": 0.315, \"rho_sj_cond\": 0.364, \"rho_fk_cond\": 0.331}, \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj=0.267 < 0.40; RE >30% samples F1=0\", \"n_instances\": 551, \"seed\": 123, \"N\": 16, \"T\": 1}, \"completed_at\": \"2026-05-14T13:31:54.232Z\"}, \"exp_008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:03:06.876Z\", \"updated_at\": \"2026-05-14T12:43:01.073Z\", \"spec\": {\"hypothesis\": \"RE N=16 confirms negative finding with higher statistical power. If rho still <0.30, task-complexity boundary is robust.\", \"plan_id\": \"exp-008\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"gpu\": \"cuda:2\", \"server\": \"gpu-5090-4x-2\", \"gpu_budget_hours\": 12, \"description\": \"RE N=16 on SciERC to confirm negative finding. Inference with log-prob capture.\", \"priority\": \"P1\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 42, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.6635, \"oracle_f1\": 0.8208, \"headroom\": 0.1572, \"rho_sj_full\": 0.377, \"rho_fk_full\": 0.2508, \"rho_logprob_full\": 0.3153, \"rho_sj_cond\": 0.3598, \"rho_fk_cond\": 0.2251, \"rho_logprob_cond\": 0.2927, \"sj_beats_fk\": true, \"rho_advantage\": 0.1262}, \"re\": {\"greedy_f1\": 0.4339, \"oracle_f1\": 0.6658, \"headroom\": 0.2319, \"rho_sj_full\": 0.2966, \"rho_fk_full\": 0.2871, \"rho_logprob_full\": 0.2986, \"rho_sj_cond\": 0.3975, \"rho_fk_cond\": 0.3774, \"rho_logprob_cond\": 0.2745, \"sj_beats_fk\": true, \"rho_advantage\": 0.0095}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp008_re_n16/\", \"completed_at\": \"2026-05-14T12:28:39.268Z\"}, \"exp_001_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:29.393Z\", \"updated_at\": \"2026-05-14T12:42:58.393Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs\", \"server\": \"gpu-5090-4x-2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.655, \"oracle_f1\": 0.8028, \"headroom\": 0.1478, \"rho_sj_full\": 0.4076, \"rho_fk_full\": 0.2799, \"rho_logprob_full\": 0.3189, \"rho_sj_cond\": 0.4271, \"rho_fk_cond\": 0.2743, \"rho_logprob_cond\": 0.2835, \"sj_beats_fk\": true, \"rho_advantage\": 0.1277}, \"re\": {\"greedy_f1\": 0.4243, \"oracle_f1\": 0.6771, \"headroom\": 0.2528, \"rho_sj_full\": 0.2943, \"rho_fk_full\": 0.2657, \"rho_logprob_full\": 0.3005, \"rho_sj_cond\": 0.4003, \"rho_fk_cond\": 0.313, \"rho_logprob_cond\": 0.2317, \"sj_beats_fk\": true, \"rho_advantage\": 0.0286}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp001_n16_seed123/\", \"completed_at\": \"2026-05-14T12:28:38.104Z\"}, \"exp_016_signal_ensemble\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:15:23.771Z\", \"updated_at\": \"2026-05-14T12:42:55.931Z\", \"spec\": {\"command\": \"python code/analyze_exp016_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"N/A (CPU-only analysis)\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"pilot_004\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp016_signal_ensemble/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:15:53.341Z\", \"metrics\": {\"sj_logprob_pearson_ner\": 0.57, \"sj_logprob_pearson_re\": 0.42, \"best_linear_ner\": {\"combo\": \"SJ+voting_conf\", \"alpha\": 0.3, \"rho\": 0.489}, \"best_linear_re\": {\"combo\": \"voting_conf+logprob\", \"alpha\": 0.6, \"rho\": 0.429}, \"ensemble_ner_auroc\": 0.735, \"ensemble_re_auroc\": 0.719, \"best_single_ner_auroc\": 0.7, \"best_single_re_auroc\": 0.721, \"ensemble_ner_delta\": 0.035, \"selection_f1_ner\": {\"greedy\": 0.609, \"logprob\": 0.609, \"sj\": 0.604, \"ensemble\": 0.604, \"voting\": 0.596, \"random\": 0.58, \"oracle\": 0.769}, \"selection_f1_re\": {\"logprob\": 0.397, \"greedy\": 0.374, \"sj\": 0.368, \"ensemble\": 0.367, \"voting\": 0.338, \"random\": 0.338, \"oracle\": 0.561}, \"diagnosis\": \"SJ+voting_conf linear combo boosts NER ρ to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge.\"}}, \"exp_001_ner_n16_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:10.898Z\", \"updated_at\": \"2026-05-14T12:42:49.592Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp001_n16_seed42 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed42_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"54357\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_ner_n16_scierc.log\", \"submitted_at\": \"2026-05-14T12:15:46.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:43:48.643Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:55:45.664Z\", \"metrics\": {\"n_instances\": 551, \"ner_n\": 529, \"re_n\": 397, \"N\": 16, \"T\": 1, \"seed\": 42, \"full_test_set\": true, \"ner_voting_conf_rho\": 0.399, \"ner_sj_rho\": 0.398, \"ner_em_rho\": 0.339, \"ner_fk_rho\": 0.288, \"ner_logprob_rho\": 0.237, \"ner_voting_conf_auroc\": 0.704, \"ner_sj_auroc\": 0.697, \"ner_cond_em_rho\": 0.414, \"ner_cond_sj_rho\": 0.349, \"ner_cond_vc_rho\": 0.34, \"re_voting_conf_rho\": 0.38, \"re_logprob_rho\": 0.293, \"re_fk_rho\": 0.281, \"re_sj_rho\": 0.277, \"re_em_rho\": 0.148, \"re_voting_conf_auroc\": 0.699, \"re_cond_em_rho\": 0.475, \"re_cond_sj_rho\": 0.318, \"re_cond_vc_rho\": 0.35, \"re_cond_em_auroc\": 0.742, \"diagnosis\": \"551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7.\"}}, \"exp_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:39:53.226Z\", \"updated_at\": \"2026-05-14T12:40:17.202Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --collect_logprobs --num_test 99999\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-lora-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"log_path\": \"/tmp/pilot_conll2003.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:40:08.402Z\", \"metrics\": {\"sj_rho_full\": 0.4357, \"sj_tau_full\": 0.3851, \"sj_auroc_full\": 0.8008, \"sj_rho_cond\": 0.4511, \"fk_rho_full\": 0.3998, \"fk_tau_full\": 0.3568, \"fk_auroc_full\": 0.7741, \"fk_rho_cond\": 0.4064, \"logprob_rho_full\": 0.3157, \"logprob_tau_full\": 0.2469, \"logprob_auroc_full\": 0.7532, \"logprob_rho_cond\": 0.3562, \"em_rho_full\": 0.4507, \"em_tau_full\": 0.4002, \"em_auroc_full\": 0.8156, \"em_rho_cond\": 0.4799, \"ev_rho_full\": 0.4237, \"ev_tau_full\": 0.3777, \"ev_auroc_full\": 0.7889, \"ev_rho_cond\": 0.4127, \"greedy_f1\": 0.9123, \"oracle_f1\": 0.9543, \"voting_f1\": 0.9141, \"oracle_headroom\": 0.042, \"sj_vs_logprob_delta_rho\": 0.12, \"sj_vs_logprob_ci_low\": 0.0881, \"sj_vs_logprob_ci_high\": 0.154, \"sj_vs_logprob_significant\": true, \"n_instances\": 3453, \"n_valid\": 2756, \"n_samples\": 8, \"temperature\": 1}}, \"exp_002_ner_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:15.223Z\", \"updated_at\": \"2026-05-14T12:27:35.413Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp002_conll2003 --num_test 99999 --seed 42 --collect_logprobs 2>&1 | tee /tmp/pilot_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"58208\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"submitted_at\": \"2026-05-14T12:27:35.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T11:43:49.959Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-lora\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"completed_at\": \"2026-05-14T12:18:04.097Z\"}, \"exp_004_re_diagnostic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:49:44.497Z\", \"updated_at\": \"2026-05-14T11:50:24.620Z\", \"spec\": {\"hypothesis\": \"RE diagnostic: per-relation-type breakdown reveals which types drive low RE rho; error propagation and threshold sensitivity clarify the gap between NER and RE consistency signals\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-relation-type SJ/FK/voting rho, error propagation classification, threshold sensitivity, bootstrap CI, Fisher z-test NER vs RE\", \"command\": \"python3 code/analyze_exp004_re_diagnostic.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic/\", \"checkpoint_source\": \"mvp_pilot_004\", \"eval_data\": \"scierc_test_551\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:50:04.662Z\", \"metrics\": {\"per_relation_type\": {\"HYPONYM-OF\": {\"n\": 36, \"rho_sj\": 0.545, \"rho_fk\": 0.646, \"rho_vc\": 0.628, \"mean_f1\": 0.513}, \"CONJUNCTION\": {\"n\": 86, \"rho_sj\": 0.383, \"rho_fk\": 0.35, \"rho_vc\": 0.484, \"mean_f1\": 0.48}, \"USED-FOR\": {\"n\": 299, \"rho_sj\": 0.236, \"rho_fk\": 0.255, \"rho_vc\": 0.286, \"mean_f1\": 0.422}, \"PART-OF\": {\"n\": 44, \"rho_sj\": 0.239, \"rho_fk\": 0.348, \"rho_vc\": 0.283, \"mean_f1\": 0.297}, \"EVALUATE-FOR\": {\"n\": 62, \"rho_sj\": 0.172, \"rho_fk\": 0.255, \"rho_vc\": 0.226, \"mean_f1\": 0.365}, \"COMPARE\": {\"n\": 35, \"rho_sj\": 0.168, \"rho_fk\": 0.184, \"rho_vc\": 0.18, \"mean_f1\": 0.453}, \"FEATURE-OF\": {\"n\": 50, \"rho_sj\": 0.004, \"rho_fk\": 0.052, \"rho_vc\": 0.014, \"mean_f1\": 0.254}}, \"error_propagation\": {\"total_fn\": 553, \"tail_error_pct\": 21.9, \"full_error_pct\": 21.7, \"head_error_pct\": 17.7, \"head_tail_error_pct\": 15.9, \"type_error_pct\": 8.3, \"worst_consistency\": \"head_type_error (sj=0.411)\", \"best_consistency\": \"head_error (sj=0.613)\"}, \"threshold_sensitivity\": {\"thr_0.00_rho_sj\": 0.3161, \"thr_0.00_rho_vc\": 0.3841, \"thr_0.00_n\": 313, \"thr_0.05_rho_sj\": 0.2682, \"thr_0.05_rho_vc\": 0.2364, \"thr_0.05_n\": 239}, \"bootstrap_ci_95\": {\"ner_sj\": [0.2946, 0.4586], \"ner_voting_conf\": [0.3048, 0.4656], \"re_sj\": [0.1422, 0.3391], \"re_voting_conf\": [0.1818, 0.3721], \"re_cond_sj\": [0.2161, 0.4102], \"re_cond_voting_conf\": [0.2825, 0.474]}, \"fisher_z_ner_vs_re\": {\"sj_z\": 2.31, \"sj_p\": 0.0209, \"sj_significant\": true, \"fk_z\": -0.31, \"fk_p\": 0.756, \"fk_significant\": false, \"voting_z\": 1.914, \"voting_p\": 0.0556, \"voting_significant\": false}, \"diagnosis\": \"FEATURE-OF is near-zero rho across all signals (n=50, F1=0.254). HYPONYM-OF strongest (rho_fk=0.646). Entity span errors (head+tail) account for 55.5% of RE FN. NER rho_sj significantly > RE rho_sj (p=0.021). Voting_conf is best RE signal in conditional set (rho=0.384).\"}}, \"exp_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:45:16.360Z\", \"updated_at\": \"2026-05-14T11:45:38.570Z\", \"spec\": {\"hypothesis\": \"Temperature sensitivity: systematic comparison of T=0.7 vs T=1.0 on all 5 confidence signals\", \"method\": \"CPU-only analysis from checkpoint metrics (pilot_004 T=1.0, pilot_005 T=0.7, exp_012/013/014)\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2\", \"data_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"server\": \"local\", \"seed\": 42, \"parent\": \"mvp_pilot_004,mvp_pilot_005\", \"command\": \"python3 analyze_exp005_temperature.py\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"log_path\": \"N/A\", \"checkpoint_source\": \"pilot_004+pilot_005 checkpoint metrics\", \"eval_data\": \"SciERC test set (n=551)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:45:38.570Z\"}, \"exp_014_entity_majority_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:21.203Z\", \"updated_at\": \"2026-05-14T11:33:30.085Z\", \"spec\": {\"hypothesis\": \"Entity-level majority voting confidence beats SJ as correlation signal\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-entity voting across N=8 samples, consensus construction, confidence = mean voting rate\", \"command\": \"python code/analyze_entity_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:18:09.468Z\", \"metrics\": {\"ner_full_rho\": 0.3915, \"ner_full_p\": 8.1e-21, \"ner_full_tau\": 0.2906, \"ner_full_auroc\": 0.7039, \"re_full_rho\": 0.3403, \"re_full_p\": 3.21e-12, \"re_full_tau\": 0.256, \"re_full_auroc\": 0.6668, \"ner_voting_f1\": 0.6246, \"ner_greedy_f1\": 0.6483, \"ner_oracle_f1\": 0.7793, \"re_voting_f1\": 0.3577, \"re_greedy_f1\": 0.4022, \"re_oracle_f1\": 0.5886, \"diagnosis\": \"Voting confidence BEATS SJ on both NER (rho 0.392 vs 0.383) and RE (0.340 vs 0.244). But voting as selection strategy LOSES to greedy.\"}}, \"exp_013_exact_match_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:18.753Z\", \"updated_at\": \"2026-05-14T11:33:22.644Z\", \"spec\": {\"hypothesis\": \"Exact-match voting rate correlates with F1\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Count exact-match duplicates across N=8 samples\", \"command\": \"python code/analyze_exact_match_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp013_exact_match_report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T11:18:09.026Z\", \"metrics\": {\"ner_full_rho\": 0.2941, \"ner_full_p\": 5.12e-12, \"ner_full_tau\": 0.2181, \"ner_full_auroc\": 0.6398, \"re_full_rho\": 0.1562, \"re_full_p\": 0.0018, \"re_full_tau\": 0.1185, \"re_full_auroc\": 0.5863, \"diagnosis\": \"EM between SJ and FK on NER, weakest on RE. Too coarse-grained.\"}}, \"exp_012_logprob_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:16.166Z\", \"updated_at\": \"2026-05-14T11:13:30.240Z\", \"spec\": {\"hypothesis\": \"Log-probability baseline: mean sequence log-prob correlates with F1 as well as or better than SJ\", \"model_name\": \"ft_002_v2 (qwen3-8b-scierc-merged-v2)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"vLLM forward pass for log-probs + Spearman rho + AUROC + Kendall tau\", \"command\": \"python3 code/extract_logprobs.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/logprob_analysis.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:06:42.542Z\", \"metrics\": {\"ner_full_rho_sj\": 0.3565, \"ner_full_rho_fk\": 0.2651, \"ner_full_rho_logprob\": 0.1396, \"ner_full_rho_greedy_logprob\": 0.1615, \"ner_full_tau_sj\": 0.2658, \"ner_full_tau_logprob\": 0.1006, \"ner_full_auroc_sj\": 0.6892, \"ner_full_auroc_fk\": 0.6292, \"ner_full_auroc_logprob\": 0.5907, \"ner_full_n\": 529, \"ner_sj_vs_logprob_delta\": 0.2169, \"re_full_rho_sj\": 0.2112, \"re_full_rho_fk\": 0.2528, \"re_full_rho_logprob\": 0.2467, \"re_full_auroc_sj\": 0.5916, \"re_full_auroc_fk\": 0.6262, \"re_full_auroc_logprob\": 0.6186, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3683, \"re_cond_rho_fk\": 0.3168, \"re_cond_rho_logprob\": 0.1457, \"re_cond_auroc_sj\": 0.6839, \"re_cond_auroc_logprob\": 0.5487, \"re_cond_n\": 296, \"diagnosis\": \"NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED.\"}}, \"mvp_pilot_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:14:09.456Z\", \"updated_at\": \"2026-05-14T09:47:06.597Z\", \"spec\": {\"hypothesis\": \"T=0.7 降低 RE zero rate，恢复 SJ>FK，rho_sj 可能 ≥ 0.30 (MARGINAL threshold)\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=0.7 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.7 --max_tokens 1024 --output_dir output/mvp_pilot_005 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 32456, \"tmux_session\": \"mvp_pilot_005\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005/train.log\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005\", \"metrics\": {\"ner_greedy_f1\": 0.6619, \"ner_oracle_f1\": 0.7585, \"ner_headroom\": 0.0966, \"ner_fleiss_kappa_mean\": 0.4722, \"ner_soft_jaccard_mean\": 0.7757, \"ner_full_rho_sj\": 0.3875, \"ner_full_rho_fk\": 0.3211, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3868, \"ner_cond_rho_fk\": 0.305, \"ner_cond_n\": 504, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0664, \"ner_sample_f1_mean\": 0.6243, \"ner_sample_f1_std\": 0.3131, \"ner_sample_f1_pct_zero\": 11.2, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 25, \"re_greedy_f1\": 0.4219, \"re_oracle_f1\": 0.5532, \"re_headroom\": 0.1313, \"re_fleiss_kappa_mean\": 0.3829, \"re_soft_jaccard_mean\": 0.687, \"re_full_rho_sj\": 0.2343, \"re_full_rho_fk\": 0.1835, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3716, \"re_cond_rho_fk\": 0.2533, \"re_cond_n\": 301, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0508, \"re_sample_f1_mean\": 0.3782, \"re_sample_f1_std\": 0.3845, \"re_sample_f1_pct_zero\": 42.4, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 96, \"parse_failures\": 0, \"verdict\": \"FAIL\", \"verdict_note\": \"RE full rho_sj=0.234 < 0.40; RE cond rho_sj=0.372 passes conditional but not full threshold\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:47:06.597Z\"}, \"e1_component_wise_re_sj\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:15:17.262Z\", \"updated_at\": \"2026-05-14T09:23:38.818Z\", \"spec\": {\"hypothesis\": \"RE SJ 乘性惩罚是 root cause：分解后 head_sj ρ ≈ NER ρ (~0.38)，tail_sj 和乘性组合拖低整体 ρ\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 397, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Component-wise decomposition: head_sj, tail_sj, type_match 分别计算 Spearman ρ vs per-instance RE F1\", \"command\": \"python3 code/analyze_component_wise_re.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/e1_component_analysis.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"full_head_sj_rho\": 0.21, \"full_tail_sj_rho\": 0.201, \"full_type_match_rho\": 0.201, \"full_multiplicative_rho\": 0.244, \"full_additive_rho\": 0.243, \"full_fleiss_kappa_rho\": 0.278, \"cond_head_sj_rho\": 0.27, \"cond_tail_sj_rho\": 0.259, \"cond_type_match_rho\": 0.252, \"cond_multiplicative_rho\": 0.316, \"cond_additive_rho\": 0.306, \"cond_fleiss_kappa_rho\": 0.307, \"n_full\": 397, \"n_conditional\": 313, \"diagnosis\": \"head_sj rho=0.210 FAR from NER rho=0.383. Multiplicative penalty hypothesis REJECTED. Problem is fundamental: span-level SJ lacks discriminative power for RE.\"}, \"completed_at\": \"2026-05-14T09:22:26.155Z\"}, \"mvp_pilot_004\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:51:38.203Z\", \"updated_at\": \"2026-05-14T09:10:40.918Z\", \"spec\": {\"hypothesis\": \"With improved RE quality (F1=41.8%), structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa, reaching rho_sj >= 0.40 on RE\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/mvp_pilot_004 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 31041, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/mvp_pilot_004.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\"}, \"metrics\": {\"ner_greedy_f1\": 0.6671, \"ner_oracle_f1\": 0.7756, \"ner_headroom\": 0.1085, \"ner_fleiss_kappa_mean\": 0.4048, \"ner_soft_jaccard_mean\": 0.7008, \"ner_full_rho_fk\": 0.259, \"ner_full_rho_sj\": 0.3825, \"ner_full_n\": 529, \"ner_cond_rho_fk\": 0.2352, \"ner_cond_rho_sj\": 0.3762, \"ner_cond_n\": 508, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_mean\": 0.6084, \"ner_sample_f1_std\": 0.3174, \"ner_sample_f1_pct_zero\": 12.19, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 21, \"re_greedy_f1\": 0.4208, \"re_oracle_f1\": 0.5882, \"re_headroom\": 0.1674, \"re_fleiss_kappa_mean\": 0.2996, \"re_soft_jaccard_mean\": 0.6114, \"re_full_rho_fk\": 0.2782, \"re_full_rho_sj\": 0.2441, \"re_full_n\": 397, \"re_cond_rho_fk\": 0.3067, \"re_cond_rho_sj\": 0.3161, \"re_cond_n\": 313, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_mean\": 0.3612, \"re_sample_f1_std\": 0.383, \"re_sample_f1_pct_zero\": 44.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 84, \"parse_failures\": 0, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:10:40.918Z\"}, \"ft_002_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:28:40.861Z\", \"updated_at\": \"2026-05-14T08:51:32.405Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) with OOM fix improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:1\", \"pid\": 24947, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002v2_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_v2.yaml\"}, \"conclusion\": \"success\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0806, \"eval_loss\": 0.089, \"train_runtime\": \"28m41s\", \"train_samples_per_second\": 5.407, \"train_steps_per_second\": 0.34, \"total_steps\": 585, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"gate0_final_ner_f1\": 0.6615, \"gate0_final_re_f1\": 0.4177, \"gate0_final_parse_failures\": 0, \"gate0_final_ner_pass\": true, \"gate0_final_re_pass\": true, \"gate0_final_pass\": true, \"gate0_ckpt400_ner_f1\": 0.6475, \"gate0_ckpt400_re_f1\": 0.3793, \"gate0_ckpt400_parse_failures\": 0, \"gate0_ckpt400_verdict\": \"FAIL\", \"gate0_ckpt400_re_sample_f1_pct_zero\": 58.8, \"gate0_ckpt400_warning\": \">30% samples F1=0\"}, \"completed_at\": \"2026-05-14T08:51:32.405Z\"}, \"mvp_pilot_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:02:16.991Z\", \"updated_at\": \"2026-05-14T08:48:14.040Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"Qwen3-8B-SciERC-LoRA (ft_001)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + gold-empty filter + conditional rho\", \"gpu\": \"cuda:0\", \"note\": \"Rerun of mvp_pilot_001 which crashed silently\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-lora --data_dir data/scierc --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 512 --output_dir output/mvp_pilot_001 --num_test 551 --seed 42 --tensor_parallel 1\", \"failure_reason\": \"Worker used LoRA adapter path instead of merged model path; vLLM cannot load LoRA adapter directly\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T08:48:14.040Z\"}, \"ft_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:18.640Z\", \"updated_at\": \"2026-05-14T08:28:00.590Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, relation direction hint\", \"command\": \"llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_v2.yaml\", \"gpu\": \"cuda:1\", \"pid\": 19666, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"total_steps\": 585, \"trainable_params\": \"87.3M\", \"estimated_runtime\": \"29min\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T08:02:30.390Z\", \"metrics\": {\"last_step\": 70, \"total_steps\": 585, \"progress_pct\": 11.97, \"last_loss\": 0.1134, \"last_lr\": 0.00019982, \"elapsed\": \"3m32s\", \"failure_reason\": \"OOM at step 73, batch_size=4 too large for 32GB RTX 5090\"}}, \"ft_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:04:28.030Z\", \"updated_at\": \"2026-05-14T08:27:58.182Z\", \"spec\": {\"hypothesis\": \"Fine-tuned Qwen3-8B on SciERC UIE can achieve NER F1 >= 73 and serve as base model for structural consistency MVP\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"method\": \"LoRA r=16 alpha=32\", \"framework\": \"LLaMA Factory 0.9.4\", \"command\": \"sft training qwen3-8b on scierc with lora\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/ft_001_train.log\", \"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"epoch\": 3, \"train_runtime\": \"0:17:49\", \"note\": \"gate0: NER PASS 60.4% / RE FAIL 33.8%\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:30:32.889Z\", \"metrics\": {\"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"gate0_ner_f1_strict\": 0.1143, \"gate0_re_f1_strict\": 0.0125, \"gate0_ner_f1_text\": 0.606, \"gate0_re_f1_text\": 0.3392, \"gate0_offset_accuracy\": 0.1665, \"gate0_parse_failures\": 43, \"gate0_pass\": false, \"gate0_realigned_ner_f1\": 0.6045, \"gate0_realigned_re_f1\": 0.338, \"gate0_realigned_entity_offset_accuracy\": 1, \"gate0_realigned_relation_offset_accuracy\": 1, \"gate0_realigned_ner_pass\": true, \"gate0_realigned_re_pass\": false, \"gate0_realigned_pass\": false, \"gate0_ner_f1_delta_realign\": 0.4901, \"gate0_re_f1_delta_realign\": 0.3255, \"verdict_note\": \"partial: NER PASS (60.4%) / RE FAIL (33.8% < 40%)\"}}, \"mvp_pilot_003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:21:09.847Z\", \"updated_at\": \"2026-05-14T08:21:44.983Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged --data_dir /root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003 --num_test 551 --seed 42 --tensor_parallel 1\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged\", \"seed\": 42}, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/mvp_pilot_003.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T08:21:30.319Z\", \"metrics\": {\"ner_greedy_f1\": 0.6362, \"ner_oracle_f1\": 0.792, \"ner_headroom\": 0.1559, \"ner_fleiss_kappa_mean\": 0.2488, \"ner_soft_jaccard_mean\": 0.5066, \"ner_full_rho_sj\": 0.3808, \"ner_full_rho_fk\": 0.3362, \"ner_full_p_sj\": 1.07e-19, \"ner_full_p_fk\": 1.93e-15, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3836, \"ner_cond_rho_fk\": 0.3187, \"ner_cond_p_sj\": 1.83e-19, \"ner_cond_p_fk\": 1.33e-13, \"ner_cond_n\": 514, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0446, \"ner_sample_f1_mean\": 0.5153, \"ner_sample_f1_std\": 0.3334, \"ner_sample_f1_pct_zero\": 19.9, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 15, \"re_greedy_f1\": 0.3774, \"re_oracle_f1\": 0.5939, \"re_headroom\": 0.2165, \"re_fleiss_kappa_mean\": 0.0879, \"re_soft_jaccard_mean\": 0.3958, \"re_full_rho_sj\": 0.2367, \"re_full_rho_fk\": 0.2221, \"re_full_p_sj\": 1.85e-06, \"re_full_p_fk\": 7.92e-06, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3004, \"re_cond_rho_fk\": 0.2374, \"re_cond_p_sj\": 2.25e-08, \"re_cond_p_fk\": 1.19e-05, \"re_cond_n\": 333, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0146, \"re_sample_f1_mean\": 0.1977, \"re_sample_f1_std\": 0.3251, \"re_sample_f1_pct_zero\": 67.6, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 64, \"parse_failures_stochastic\": 0, \"parse_failures_greedy\": 0, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2367 < 0.40 threshold; strong signal exists but below PASS bar\"}}, \"mvp_pilot_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:16.313Z\", \"updated_at\": \"2026-05-14T08:05:34.348Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"qwen3-8b-scierc-merged\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/test.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/mvp_pilot.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_001.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T07:52:47.006Z\", \"metrics\": {\"ner_greedy_f1\": 0.611, \"ner_oracle_f1\": 0.78, \"ner_headroom\": 0.169, \"ner_fleiss_kappa_mean\": 0.2449, \"ner_soft_jaccard_mean\": 0.5041, \"ner_full_rho_sj\": 0.3616, \"ner_full_rho_fk\": 0.3515, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3688, \"ner_cond_rho_fk\": 0.3569, \"ner_cond_n\": 510, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_pct_zero\": 20.4, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 19, \"re_greedy_f1\": 0.355, \"re_oracle_f1\": 0.572, \"re_headroom\": 0.217, \"re_fleiss_kappa_mean\": 0.0681, \"re_soft_jaccard_mean\": 0.3635, \"re_full_rho_sj\": 0.2535, \"re_full_rho_fk\": 0.2885, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3515, \"re_cond_rho_fk\": 0.3107, \"re_cond_n\": 320, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_pct_zero\": 58.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 77, \"parse_failures_stochastic\": 164, \"parse_failures_greedy\": 29, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2535 < 0.40; SJ does not beat FK on RE full set\"}}}, \"count\": 81, \"total\": 81, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.328}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 36_

<details open><summary>🔧 Tool call — Read · `toolu_01Xxh7nnwpcW8Zg9pwd9jz49`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "3f341cd1-8e50-4ea7-abd3-f5364b278b37",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Xtzhz4iHVECT72BXBvw7bf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 20118,
      "cache_read_input_tokens": 38734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 20118
      },
      "output_tokens": 18,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 37 · 2026-05-15T11:33:42.425Z_

<details><summary>↩ Tool result · `toolu_01Xxh7nnwpcW8Zg9pwd9jz49`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	We demonstrate that consistency signals are effective quality estimators ($\rho$ up to 0.38, AUROC up to 0.75) for LLM-based structured IE, but fail at sample selection---the \textit{correlation-selection gap}.
4	By construction, four of five signals assign identical scores to all candidates from the same input; log-probability, the only per-sample signal, also fails ($p{>}0.39$) despite 13--18~pp oracle headroom due to score compression.
5	Where compression is mitigated, LP becomes a significant selector ($+2.9$~pp, $p{=}0.01$); consensus-proximity selection (MBR decoding) similarly fails as utility correlates with quality across instances but not within them.
6	A controlled free-form decoding ablation confirms that score compression is intrinsic to the model and task, not an artifact of constrained decoding.
7	Signal rankings depend on task difficulty, with consistent ordering across two model families at 8B scale.
8	RE findings rest on SciERC alone (preliminary, single benchmark) and warrant multi-benchmark validation.
9	Trained verifiers, scaling to 70B+ models, and conformal prediction are promising directions for closing the gap.
10	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "4cf351a7-9bf1-4616-9668-914a78ce9c18",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nWe demonstrate that consistency signals are effective quality estimators ($\\rho$ up to 0.38, AUROC up to 0.75) for LLM-based structured IE, but fail at sample selection---the \\textit{correlation-selection gap}.\nBy construction, four of five signals assign identical scores to all candidates from the same input; log-probability, the only per-sample signal, also fails ($p{>}0.39$) despite 13--18~pp oracle headroom due to score compression.\nWhere compression is mitigated, LP becomes a significant selector ($+2.9$~pp, $p{=}0.01$); consensus-proximity selection (MBR decoding) similarly fails as utility correlates with quality across instances but not within them.\nA controlled free-form decoding ablation confirms that score compression is intrinsic to the model and task, not an artifact of constrained decoding.\nSignal rankings depend on task difficulty, with consistent ordering across two model families at 8B scale.\nRE findings rest on SciERC alone (preliminary, single benchmark) and warrant multi-benchmark validation.\nTrained verifiers, scaling to 70B+ models, and conformal prediction are promising directions for closing the gap.\n",
      "numLines": 10,
      "startLine": 1,
      "totalLines": 10
    }
  }
}
```

</details>

---

### Tool call

_source line 38_

<details open><summary>🔧 Tool call — Bash · `toolu_01Pkz1xYkHbaLcsy2hesnaC4`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nexps = json.loads(data['result'])\nfor exp in exps:\n    eid = exp.get('experiment_id','')\n    if 'exp_007' in eid or 'exp_017' in eid or 'exp_018' in eid or 'freeform' in eid:\n        print(f\\\"=== {eid} ===\\\")\n        print(f\\\"  status: {exp.get('status')}\\\")\n        print(f\\\"  conclusion: {exp.get('conclusion','')[:200]}\\\")\n        metrics = exp.get('metrics', {})\n        if metrics:\n            print(f\\\"  metrics keys: {list(metrics.keys())[:10]}\\\")\n            for k,v in list(metrics.items())[:5]:\n                print(f\\\"    {k}: {v}\\\")\n        print()\n\"\n",
  "description": "Extract exp_007, exp_017, exp_018, freeform experiments from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "f52a0022-08fc-4c05-9218-7f12179ba487",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XPKRUH7d6RbNLbd6s7cWHn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1112,
      "cache_read_input_tokens": 58852,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1112
      },
      "output_tokens": 62,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 39 · 2026-05-15T11:33:50.561Z_

<details><summary>↩ Tool result · reported error · `toolu_01Pkz1xYkHbaLcsy2hesnaC4`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 6, in &lt;module>
    eid = exp.get('experiment_id','')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "d74481a6-3a8c-490e-ac77-86ee53eb30b1",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 6, in &lt;module>\n    eid = exp.get('experiment_id','')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'"
}
```

</details>

---

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Bash · `toolu_017pQaw3Kht9aX8CBCk4WdYJ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nresult = data['result']\n# result might be a JSON string containing a list or dict\nparsed = json.loads(result) if isinstance(result, str) else result\nprint(type(parsed).__name__)\nif isinstance(parsed, list):\n    print(f'Length: {len(parsed)}')\n    if len(parsed) > 0:\n        print(f'First element type: {type(parsed[0]).__name__}')\n        if isinstance(parsed[0], dict):\n            print(f'Keys: {list(parsed[0].keys())[:15]}')\nelif isinstance(parsed, dict):\n    print(f'Keys: {list(parsed.keys())[:15]}')\n\"\n",
  "description": "Probe registry JSON structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "227ec004-fc18-4e79-9bb5-22fbd90fc82d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MZWtUfhwtgiVtRSEU4MkWU",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 497,
      "cache_read_input_tokens": 59964,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 497
      },
      "output_tokens": 73,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 41 · 2026-05-15T11:33:57.562Z_

<details><summary>↩ Tool result · `toolu_017pQaw3Kht9aX8CBCk4WdYJ`</summary>

```text
dict
Keys: ['success', 'data', 'error', 'metadata']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "a84ac7a9-8a2b-4b3a-88bd-e29e0f58c562",
  "tool_use_result": {
    "stdout": "dict\nKeys: ['success', 'data', 'error', 'metadata']",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 42_

<details open><summary>🔧 Tool call — Bash · `toolu_01Q2upimWT2jvYhnNJKAkcaT`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nparsed = json.loads(data['result'])\nexps = parsed['data']\nfor exp in exps:\n    eid = exp.get('experiment_id','')\n    if any(x in eid for x in ['exp_007','exp_017','exp_018','freeform']):\n        print(f'=== {eid} ===')\n        print(f'  status: {exp.get(\\\"status\\\")}')\n        print(f'  conclusion: {str(exp.get(\\\"conclusion\\\",\\\"\\\"))[:200]}')\n        metrics = exp.get('metrics', {})\n        if metrics:\n            for k,v in list(metrics.items())[:8]:\n                print(f'    {k}: {v}')\n        print()\n\"\n",
  "description": "Extract relevant experiments from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "1dd9b36f-f260-4184-9c23-22b0283bc3ae",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ChHQr7oSts5ho8p4tvWTSe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 387,
      "cache_read_input_tokens": 60461,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 387
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 43 · 2026-05-15T11:34:02.560Z_

<details><summary>↩ Tool result · reported error · `toolu_01Q2upimWT2jvYhnNJKAkcaT`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 7, in &lt;module>
    eid = exp.get('experiment_id','')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "2519bba9-eaa0-4cbb-83cf-7d31fd9012e1",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 7, in &lt;module>\n    eid = exp.get('experiment_id','')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'"
}
```

</details>

---

### Tool call

_source line 44_

<details open><summary>🔧 Tool call — Bash · `toolu_01Fq9SoaUAQ6Uw4u2PZqBnGE`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nparsed = json.loads(data['result'])\nd = parsed['data']\nprint(type(d).__name__)\nif isinstance(d, list):\n    print(f'len={len(d)}')\n    print(f'first type: {type(d[0]).__name__}')\n    if isinstance(d[0], str):\n        print(f'first: {d[0][:200]}')\n    elif isinstance(d[0], dict):\n        print(f'keys: {list(d[0].keys())}')\nelif isinstance(d, dict):\n    print(f'keys: {list(d.keys())[:20]}')\n    for k in list(d.keys())[:3]:\n        v = d[k]\n        print(f'  {k}: type={type(v).__name__}, preview={str(v)[:100]}')\n\"\n",
  "description": "Debug registry data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "69c92d44-9a32-4256-a8b7-462494cdedf7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M8c66nMCMX1HNAXdT4Sx4y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 461,
      "cache_read_input_tokens": 60848,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 461
      },
      "output_tokens": 73,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-15T11:34:09.442Z_

<details><summary>↩ Tool result · `toolu_01Fq9SoaUAQ6Uw4u2PZqBnGE`</summary>

```text
dict
keys: ['experiments', 'count', 'total', 'baseline']
  experiments: type=dict, preview={'exp_017_llama_conll_n16_s456_r1024': {'status': 'RUNNING', 'retry_count': 0, 'created_at': '2026-0
  count: type=int, preview=81
  total: type=int, preview=81
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "d7dfaf36-be8e-48b1-9c01-c8fb0cdff318",
  "tool_use_result": {
    "stdout": "dict\nkeys: ['experiments', 'count', 'total', 'baseline']\n  experiments: type=dict, preview={'exp_017_llama_conll_n16_s456_r1024': {'status': 'RUNNING', 'retry_count': 0, 'created_at': '2026-0\n  count: type=int, preview=81\n  total: type=int, preview=81",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Tool call

_source line 46_

<details open><summary>🔧 Tool call — Bash · `toolu_01VpFjoKDVYiufqx1FBd3mRP`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/c03756a4-6b28-4a5f-9a56-f8f8d904dced/tool-results/mcp-agent-ml-research-read_registry-1778844821819.txt | python3 -c \"\nimport json, sys\ndata = json.loads(sys.stdin.read())\nparsed = json.loads(data['result'])\nexps = parsed['data']['experiments']\nfor eid, exp in exps.items():\n    if any(x in eid for x in ['exp_007','exp_017','exp_018','freeform']):\n        print(f'=== {eid} ===')\n        print(f'  status: {exp.get(\\\"status\\\")}')\n        concl = str(exp.get('conclusion',''))[:200]\n        if concl: print(f'  conclusion: {concl}')\n        metrics = exp.get('metrics', {})\n        if metrics:\n            for k,v in list(metrics.items())[:8]:\n                print(f'    {k}: {v}')\n        print()\n\" 2>&1 | head -120\n",
  "description": "Extract exp_007/017/018/freeform from registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "1f0bf4e1-b0df-484d-ac44-2762fee10649",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AuGAQd6FfY5MZCGX1sUFLb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 510,
      "cache_read_input_tokens": 61309,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 510
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 47 · 2026-05-15T11:34:17.621Z_

<details><summary>↩ Tool result · `toolu_01VpFjoKDVYiufqx1FBd3mRP`</summary>

```text
=== exp_017_llama_conll_n16_s456_r1024 ===
  status: RUNNING
  conclusion: killed

=== exp_017_llama_conll_n16_r1024 ===
  status: RUNNING
  conclusion: killed

=== exp_007_ner_llama ===
  status: PREPARING
  conclusion: killed

=== exp_017_llama_conll_n16_s123_r1024 ===
  status: DONE
  conclusion: success

=== exp_freeform_ablation ===
  status: DONE
  conclusion: negative
    lp_std_ratio_free_vs_constrained: 0.97
    lp_range_ratio: 0.96
    tied_fraction_constrained: 0.597
    tied_fraction_freeform: 0.577
    ner_selection_gap_constrained: 0.0059
    ner_selection_gap_freeform: 0.0018
    re_selection_gap_constrained: -0.0068
    re_selection_gap_freeform: 0.0169

=== exp_018_llama_scierc_seed456 ===
  status: DONE
  conclusion: killed

=== exp_018_llama_scierc_seed42_r1024 ===
  status: DONE
  conclusion: success
    ner: {'full': {'SJ': {'rho': 0.3096, 'tau': 0.2288, 'auroc': 0.6683}, 'FK': {'rho': 0.2352, 'tau': 0.1759, 'auroc': 0.6069}, 'logprob': {'rho': 0.1503, 'tau': 0.1087, 'auroc': 0.5318}, 'EM': {'rho': 0.2587, 'tau': 0.1966, 'auroc': 0.7174}, 'voting_conf': {'rho': 0.4053, 'tau': 0.3042, 'auroc': 0.6967}}, 'conditional': {'SJ': {'rho': 0.2718, 'tau': None, 'auroc': 0.6565}, 'FK': {'rho': 0.1472, 'tau': None, 'auroc': 0.5866}, 'logprob': {'rho': 0.081, 'tau': None, 'auroc': 0.5129}, 'EM': {'rho': 0.3165, 'tau': None, 'auroc': 0.7244}, 'voting_conf': {'rho': 0.3078, 'tau': None, 'auroc': 0.6714}}, 'greedy_f1': 0.6607, 'oracle_f1': 0.7781, 'n_full': 529, 'n_cond': 478}
    re: {'full': {'SJ': {'rho': 0.2748, 'tau': 0.2102, 'auroc': 0.7244}, 'FK': {'rho': 0.3027, 'tau': 0.2337, 'auroc': 0.691}, 'logprob': {'rho': 0.3163, 'tau': 0.233, 'auroc': 0.6313}, 'EM': {'rho': 0.1681, 'tau': 0.1275, 'auroc': 0.7697}, 'voting_conf': {'rho': 0.384, 'tau': 0.2965, 'auroc': 0.7337}}, 'conditional': {'SJ': {'rho': 0.3461, 'tau': None, 'auroc': 0.7233}, 'FK': {'rho': 0.1969, 'tau': None, 'auroc': 0.6684}, 'logprob': {'rho': 0.0888, 'tau': None, 'auroc': 0.5556}, 'EM': {'rho': 0.4969, 'tau': None, 'auroc': 0.819}, 'voting_conf': {'rho': 0.3433, 'tau': None, 'auroc': 0.7003}}, 'greedy_f1': 0.4319, 'oracle_f1': 0.5775, 'n_full': 397, 'n_cond': 251}

=== exp_018_llama_scierc_seed456_r1024 ===
  status: DONE
  conclusion: success
    ner_greedy_f1: 0.6597
    ner_oracle_f1: 0.7683
    ner_oracle_headroom: 0.1086
    ner_cond_rho_fk: 0.1472
    ner_cond_rho_sj: 0.2718
    ner_cond_rho_logprob: 0.083
    ner_logprob_auroc_cond: 0.5485
    re_greedy_f1: 0.4338

=== exp_018_llama_scierc_seed123 ===
  status: DONE
  conclusion: success

=== exp_018_qwen_scierc_seed456 ===
  status: DONE
  conclusion: success

=== exp_018_qwen_scierc_seed123 ===
  status: DONE
  conclusion: success

=== exp_007_llama_n16_r1024 ===
  status: DONE
  conclusion: killed

=== exp_017_llama_conll_n16_s456 ===
  status: DONE
  conclusion: success
    greedy_f1: 0.9243
    oracle_f1: 0.9488
    oracle_headroom: 0.0245
    n_instances: 3453
    n_valid: 2756
    n_conditional: 2642
    structural_beats_surface: True
    full: {'SJ_rho': 0.4552, 'SJ_AUROC': 0.7288, 'SJ_ECE': 0.1134, 'FK_rho': 0.4478, 'FK_AUROC': 0.7248, 'FK_ECE': 0.109, 'logprob_rho': 0.3078, 'logprob_AUROC': 0.7612, 'logprob_ECE': 0.1289, 'EM_rho': 0.452, 'EM_AUROC': 0.7275, 'EM_ECE': 0.1082, 'voting_conf_rho': 0.4571, 'voting_conf_AUROC': 0.7348, 'voting_conf_ECE': 0.0863}

=== exp_017_llama_conll_n16 ===
  status: DONE
  conclusion: success
    greedy_f1: 0.9243
    oracle_f1: 0.9487
    oracle_headroom: 0.0244
    n_instances: 3453
    n_valid: 2756
    n_conditional: 2642
    structural_beats_surface: True
    full: {'SJ_rho': 0.4642, 'SJ_AUROC': 0.7391, 'SJ_ECE': 0.1131, 'FK_rho': 0.4566, 'FK_AUROC': 0.736, 'FK_ECE': 0.1071, 'logprob_rho': 0.3058, 'logprob_AUROC': 0.7594, 'logprob_ECE': 0.1288, 'EM_rho': 0.4613, 'EM_AUROC': 0.7391, 'EM_ECE': 0.1084, 'voting_conf_rho': 0.4554, 'voting_conf_AUROC': 0.7406, 'voting_conf_ECE': 0.0844}

=== exp_017_llama_conll_n16_s123 ===
  status: DONE
  conclusion: success
    greedy_f1: 0.9266
    oracle_f1: 0.9497
    oracle_headroom: 0.0231
    n_instances: 3453
    n_valid: 2756
    n_conditional: 2642
    structural_beats_surface: True
    full: {'SJ_rho': 0.4698, 'SJ_AUROC': 0.7402, 'SJ_ECE': 0.1135, 'FK_rho': 0.4594, 'FK_AUROC': 0.7351, 'FK_ECE': 0.1114, 'logprob_rho': 0.3161, 'logprob_AUROC': 0.768, 'logprob_ECE': 0.129, 'EM_rho': 0.4676, 'EM_AUROC': 0.7399, 'EM_ECE': 0.1082, 'voting_conf_rho': 0.4612, 'voting_conf_AUROC': 0.7429, 'voting_conf_ECE': 0.0832}

=== exp_007_llama_n16 ===
  status: DONE
  conclusion: success
    N: 16
    dataset: scierc
    subtask: ner
    n_instances: 551
    n_valid: 529
    n_conditional: 478
    greedy_f1: 0.645
    full: {'SJ_rho': 0.3791, 'FK_rho': 0.3081, 'logprob_rho': 0.2041, 'EM_rho': 0.3159, 'voting_conf_rho': 0.4515, 'SJ_AUROC': 0.717, 'FK_AUROC': 0.6581, 'logprob_AUROC': 0.5656, 'EM_AUROC': 0.7686, 'voting_conf_AUROC': 0.7266, 'SJ_ECE': 0.1019, 'FK_ECE': 0.1556, 'logprob_ECE': 0.084, 'EM_ECE': 0.1761, 'voting_conf_ECE': 0.1365}

=== exp_017_llama_conll_infer ===
  status: DONE
  conclusion: success
    greedy_f1: 0.9266
    oracle_f1: 0.9443
    oracle_headroom: 0.0177
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "b2abb5a7-338c-4835-849b-030d41a3e641",
  "tool_use_result": {
    "stdout": "=== exp_017_llama_conll_n16_s456_r1024 ===\n  status: RUNNING\n  conclusion: killed\n\n=== exp_017_llama_conll_n16_r1024 ===\n  status: RUNNING\n  conclusion: killed\n\n=== exp_007_ner_llama ===\n  status: PREPARING\n  conclusion: killed\n\n=== exp_017_llama_conll_n16_s123_r1024 ===\n  status: DONE\n  conclusion: success\n\n=== exp_freeform_ablation ===\n  status: DONE\n  conclusion: negative\n    lp_std_ratio_free_vs_constrained: 0.97\n    lp_range_ratio: 0.96\n    tied_fraction_constrained: 0.597\n    tied_fraction_freeform: 0.577\n    ner_selection_gap_constrained: 0.0059\n    ner_selection_gap_freeform: 0.0018\n    re_selection_gap_constrained: -0.0068\n    re_selection_gap_freeform: 0.0169\n\n=== exp_018_llama_scierc_seed456 ===\n  status: DONE\n  conclusion: killed\n\n=== exp_018_llama_scierc_seed42_r1024 ===\n  status: DONE\n  conclusion: success\n    ner: {'full': {'SJ': {'rho': 0.3096, 'tau': 0.2288, 'auroc': 0.6683}, 'FK': {'rho': 0.2352, 'tau': 0.1759, 'auroc': 0.6069}, 'logprob': {'rho': 0.1503, 'tau': 0.1087, 'auroc': 0.5318}, 'EM': {'rho': 0.2587, 'tau': 0.1966, 'auroc': 0.7174}, 'voting_conf': {'rho': 0.4053, 'tau': 0.3042, 'auroc': 0.6967}}, 'conditional': {'SJ': {'rho': 0.2718, 'tau': None, 'auroc': 0.6565}, 'FK': {'rho': 0.1472, 'tau': None, 'auroc': 0.5866}, 'logprob': {'rho': 0.081, 'tau': None, 'auroc': 0.5129}, 'EM': {'rho': 0.3165, 'tau': None, 'auroc': 0.7244}, 'voting_conf': {'rho': 0.3078, 'tau': None, 'auroc': 0.6714}}, 'greedy_f1': 0.6607, 'oracle_f1': 0.7781, 'n_full': 529, 'n_cond': 478}\n    re: {'full': {'SJ': {'rho': 0.2748, 'tau': 0.2102, 'auroc': 0.7244}, 'FK': {'rho': 0.3027, 'tau': 0.2337, 'auroc': 0.691}, 'logprob': {'rho': 0.3163, 'tau': 0.233, 'auroc': 0.6313}, 'EM': {'rho': 0.1681, 'tau': 0.1275, 'auroc': 0.7697}, 'voting_conf': {'rho': 0.384, 'tau': 0.2965, 'auroc': 0.7337}}, 'conditional': {'SJ': {'rho': 0.3461, 'tau': None, 'auroc': 0.7233}, 'FK': {'rho': 0.1969, 'tau': None, 'auroc': 0.6684}, 'logprob': {'rho': 0.0888, 'tau': None, 'auroc': 0.5556}, 'EM': {'rho': 0.4969, 'tau': None, 'auroc': 0.819}, 'voting_conf': {'rho': 0.3433, 'tau': None, 'auroc': 0.7003}}, 'greedy_f1': 0.4319, 'oracle_f1': 0.5775, 'n_full': 397, 'n_cond': 251}\n\n=== exp_018_llama_scierc_seed456_r1024 ===\n  status: DONE\n  conclusion: success\n    ner_greedy_f1: 0.6597\n    ner_oracle_f1: 0.7683\n    ner_oracle_headroom: 0.1086\n    ner_cond_rho_fk: 0.1472\n    ner_cond_rho_sj: 0.2718\n    ner_cond_rho_logprob: 0.083\n    ner_logprob_auroc_cond: 0.5485\n    re_greedy_f1: 0.4338\n\n=== exp_018_llama_scierc_seed123 ===\n  status: DONE\n  conclusion: success\n\n=== exp_018_qwen_scierc_seed456 ===\n  status: DONE\n  conclusion: success\n\n=== exp_018_qwen_scierc_seed123 ===\n  status: DONE\n  conclusion: success\n\n=== exp_007_llama_n16_r1024 ===\n  status: DONE\n  conclusion: killed\n\n=== exp_017_llama_conll_n16_s456 ===\n  status: DONE\n  conclusion: success\n    greedy_f1: 0.9243\n    oracle_f1: 0.9488\n    oracle_headroom: 0.0245\n    n_instances: 3453\n    n_valid: 2756\n    n_conditional: 2642\n    structural_beats_surface: True\n    full: {'SJ_rho': 0.4552, 'SJ_AUROC': 0.7288, 'SJ_ECE': 0.1134, 'FK_rho': 0.4478, 'FK_AUROC': 0.7248, 'FK_ECE': 0.109, 'logprob_rho': 0.3078, 'logprob_AUROC': 0.7612, 'logprob_ECE': 0.1289, 'EM_rho': 0.452, 'EM_AUROC': 0.7275, 'EM_ECE': 0.1082, 'voting_conf_rho': 0.4571, 'voting_conf_AUROC': 0.7348, 'voting_conf_ECE': 0.0863}\n\n=== exp_017_llama_conll_n16 ===\n  status: DONE\n  conclusion: success\n    greedy_f1: 0.9243\n    oracle_f1: 0.9487\n    oracle_headroom: 0.0244\n    n_instances: 3453\n    n_valid: 2756\n    n_conditional: 2642\n    structural_beats_surface: True\n    full: {'SJ_rho': 0.4642, 'SJ_AUROC': 0.7391, 'SJ_ECE': 0.1131, 'FK_rho': 0.4566, 'FK_AUROC': 0.736, 'FK_ECE': 0.1071, 'logprob_rho': 0.3058, 'logprob_AUROC': 0.7594, 'logprob_ECE': 0.1288, 'EM_rho': 0.4613, 'EM_AUROC': 0.7391, 'EM_ECE': 0.1084, 'voting_conf_rho': 0.4554, 'voting_conf_AUROC': 0.7406, 'voting_conf_ECE': 0.0844}\n\n=== exp_017_llama_conll_n16_s123 ===\n  status: DONE\n  conclusion: success\n    greedy_f1: 0.9266\n    oracle_f1: 0.9497\n    oracle_headroom: 0.0231\n    n_instances: 3453\n    n_valid: 2756\n    n_conditional: 2642\n    structural_beats_surface: True\n    full: {'SJ_rho': 0.4698, 'SJ_AUROC': 0.7402, 'SJ_ECE': 0.1135, 'FK_rho': 0.4594, 'FK_AUROC': 0.7351, 'FK_ECE': 0.1114, 'logprob_rho': 0.3161, 'logprob_AUROC': 0.768, 'logprob_ECE': 0.129, 'EM_rho': 0.4676, 'EM_AUROC': 0.7399, 'EM_ECE': 0.1082, 'voting_conf_rho': 0.4612, 'voting_conf_AUROC': 0.7429, 'voting_conf_ECE': 0.0832}\n\n=== exp_007_llama_n16 ===\n  status: DONE\n  conclusion: success\n    N: 16\n    dataset: scierc\n    subtask: ner\n    n_instances: 551\n    n_valid: 529\n    n_conditional: 478\n    greedy_f1: 0.645\n    full: {'SJ_rho': 0.3791, 'FK_rho': 0.3081, 'logprob_rho': 0.2041, 'EM_rho': 0.3159, 'voting_conf_rho': 0.4515, 'SJ_AUROC': 0.717, 'FK_AUROC': 0.6581, 'logprob_AUROC': 0.5656, 'EM_AUROC': 0.7686, 'voting_conf_AUROC': 0.7266, 'SJ_ECE': 0.1019, 'FK_ECE': 0.1556, 'logprob_ECE': 0.084, 'EM_ECE': 0.1761, 'voting_conf_ECE': 0.1365}\n\n=== exp_017_llama_conll_infer ===\n  status: DONE\n  conclusion: success\n    greedy_f1: 0.9266\n    oracle_f1: 0.9443\n    oracle_headroom: 0.0177",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---

### Assistant

_source line 48_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need. Let me compile the inventory. Let me also check what the paper currently says about LLaMA CoNLL results and multi-seed stability to understand what's new vs. already written.

Key findings to inventory:

1. **Free-form ablation** (from freeform_ablation_results.md, freeform_ablation_deep_analysis.md, freeform_ablation_appendix_table.tex):
   - Already partially written into discussion.tex §ablation and appendix.tex §app:freeform_ablation
   - The deep analysis (RE LP selection flip mechanism, per-relation breakdown, non-tied subset reshuffling) is NOT in the paper
   - The full 4-panel appendix table is missing—only a simplified 2-column version exists

2. **TOST breakpoint δ*** (from tost_breakpoint_delta_star.md):
   - The paper already has the TOST table with checkmarks at δ=2,3,5pp
   - The δ* values themselves aren't explicitly in the paper, though the approximate ranges are mentioned in the appendix text (1.3~pp to 3.4~pp on NER, 2.9~pp to 6.5~pp on RE)
   - A per-signal δ* table would be needed to show the individual values

3. **Qwen3 thinking tokens confirmation** (from qwen3_thinking_confirmation.md):
   - Already covered in the training configuration footnote and limitations section
   - The detailed mechanism analysis isn't included, but the key facts are there

4. **VC implementation ρ difference**

:
   - There's a 0.127 difference in NER ρ between the eq6 and majority threshold implementations, which the paper doesn't discuss
   - The paper shows VC NER ρ=0.379, which matches the eq6 value (0.3792) rather than majority threshold (0.2524)
   - The artifact claims it unified to majority threshold for Table 2, but the actual numbers suggest the paper is using eq6 instead
   - There's also a discrepancy between the multi-seed table (0.3701) and the VC artifact (0.3792) - likely due to different experimental runs or VC formulation variations within eq6 itself.

The real question for the inventory is whether the eq6 versus majority threshold analysis represents new findings that should be included in the paper. Looking at what's already documented versus what's missing: the multi-seed stability results are in the appendix for NER, but the RE multi-seed data hasn't made it into the paper yet. Same with the LLaMA SJ ρ correction comparing the contaminated versus fresh runs, and the signal ranking consistency tables aren't explicitly shown despite the text mentioning the ranking order. I need to track what's actually in the current draft versus what's sitting in the supporting materials.

For the LLaMA CoNLL N=16 experiments across three seed sets, I'm seeing consistent performance metrics across the different random seeds, with the average SJ score of 0.463 already captured in the robustness table.

Looking at the exp_017 runs, most are completed with seeds 42, 123, and 456 all finished, though there are a couple of failed attempts marked as killed. Now I need to sort through what's already documented in the paper versus what's genuinely new and needs to be added. The free-form ablation results, TOST ranges, Qwen thinking token analysis, and the multi-seed stability results are all accounted for. That leaves me to identify what new findings are actually ready to include.

The mechanistic breakdown of the free-form ablation is substantial—I can trace exactly how the LP selection flips across all seven relation types, show the variance reallocation pattern, and quantify the non-tied subset reshuffling with a Jaccard similarity of 0.472. This goes into the discussion and a new appendix subsection to explain the mechanism. I also need to replace the simplified two-column ablation table with the full four-panel version that shows logprob distributions, selection F1 scores, QE signal quality, and parse rates. Finally, I have the multi-seed RE stability tables computed with Spearman correlations and AUROC values per seed.

The ranking consistency analysis reveals that RE has minor instability in the top-3 while NER remains perfectly stable across seeds, which should go in the appendix. For the VC implementation comparison, the NER improvement of +0.127 Spearman is substantial enough that I need to clarify which version the paper uses and note that equation 6 is strictly superior. I should also add a table with the exact δ* values per signal for the equivalence testing rather than just mentioning ranges, and there's a LLaMA SJ correlation correction that needs attention.

The contaminated experiment showed σ≈0.004 while the fresh run gives σ≈0.021—a fivefold increase that validates the data quality improvement. Looking at the free-form QE signal results, all five signals perform better under NER with gains ranging from +0.008 to +0.053, with FK showing the most consistent improvements across the board. This extends the ablation findings beyond just LP compression effects.

For the pending items, the LLaMA CoNLL registry actually shows the 3-seed data is already complete with all three seeds finished, so those "running/killed" entries are just earlier failed attempts. I still need to work through the N=16 3-seed SCS analysis.

Now I'm drafting the inventory document.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "6a4b90e0-4efd-4522-a34f-bbb4af39bb19",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013SsHRn6yc4BqXSqpqMxuUD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3174,
      "cache_read_input_tokens": 61819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3174
      },
      "output_tokens": 10,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 49_

Now I have all the data. Let me also check what's in the current multi-seed appendix table and VC definition in the method section to compare against new findings.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "9d20bea6-edc7-4230-b519-8e57cc2bd2f1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013SsHRn6yc4BqXSqpqMxuUD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3174,
      "cache_read_input_tokens": 61819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3174
      },
      "output_tokens": 10,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 50_

<details open><summary>🔧 Tool call — Read · `toolu_01RXZRTKdjy6S8EJgaZMBvA7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "66de2d38-645d-4929-9559-0fa268057d34",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013SsHRn6yc4BqXSqpqMxuUD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3174,
      "cache_read_input_tokens": 61819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3174
      },
      "output_tokens": 10,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 51 · 2026-05-15T11:35:14.924Z_

<details><summary>↩ Tool result · `toolu_01RXZRTKdjy6S8EJgaZMBvA7`</summary>

```text
1	\section{Method}\label{sec:method}
2	
3	\subsection{Problem Formulation}\label{sec:formulation}
4	
5	Given a language model $\mathcal{M}$ and input $x$, we sample $N$ structured outputs $\{y_1, \ldots, y_N\}$ at temperature $T > 0$ via constrained decoding \cite{willard2023guided}.
6	Each $y_i$ is an entity set (NER) or relation set (RE).
7	A confidence signal $c$ serves two purposes: (a) \textit{quality estimation}---predicting which instances the model handles reliably, and (b) \textit{sample selection}---identifying the best output among $N$ candidates.
8	
9	A \textbf{per-sample signal} scores each $y_i$ independently, $c_{\text{ps}}: (x, y_i) \to \mathbb{R}$, enabling direct candidate ranking.
10	An \textbf{instance-level signal} aggregates over all $N$ samples, $c_{\text{il}}: (x, \{y_i\}_{i=1}^N) \to \mathbb{R}$, producing a single score per input.
11	This asymmetry---between predicting \textit{which inputs} are easy and selecting \textit{which output} is best---is central to the correlation-selection gap we investigate.
12	Notation is summarized in Appendix~\ref{app:notation}.
13	
14	\subsection{Confidence Signals}\label{sec:signals}
15	
16	We use \textit{confidence signal} as the umbrella term for all five measures.
17	Four are \textit{consistency signals}---computed from inter-sample agreement---spanning two families: \textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \textit{surface} (exact match [EM], Fleiss' $\kappa$ [FK]).
18	The fifth, log-probability, is the sole \textit{model-internal} signal and the only one that scores individual samples rather than the instance as a whole.
19	
20	\paragraph{Log-probability (model-internal, per-sample).}
21	The only per-sample signal.
22	For sample $y_i$ with tokens $t_1, \ldots, t_{|y_i|}$:
23	\begin{equation}\label{eq:logprob}
24	c_{\text{lp}}(y_i) = \frac{1}{|y_i|} \sum_{j=1}^{|y_i|} \log p_{\mathcal{M}}(t_j \mid t_{&lt;j}, x)
25	\end{equation}
26	
27	\paragraph{Exact match voting (surface, instance-level).}
28	The majority fraction---the proportion of samples producing the most common output:
29	\begin{equation}\label{eq:em}
30	c_{\text{em}}(x) = \frac{1}{N} \max_{y} \big|\{i : y_i = y\}\big|
31	\end{equation}
32	
33	\paragraph{Fleiss' $\kappa$ (surface, instance-level).}
34	We adapt \citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\cup| \times 2$ rating matrix:
35	\begin{equation}\label{eq:fk}
36	\kappa = \frac{\bar{P} - \bar{P}_e}{1 - \bar{P}_e}
37	\end{equation}
38	where $\bar{P}$ is mean observed pairwise agreement and $\bar{P}_e$ is expected agreement under random assignment.
39	While FK assumes independent raters, temperature-based sampling provides sufficient response diversity for the statistic to capture inter-sample agreement patterns.
40	Empirically, we measure excess agreement ($\bar{P} - \bar{P}_e$) across all configurations (SciERC NER/RE, CoNLL, WNUT-17; $N{=}8$, $T{=}1.0$) and find values between $-$0.4\% and $-$4.0\%, indicating mild \textit{negative} dependence---samples from the same model tend to err on different items---which confirms that FK is not inflated by inter-sample dependence.
41	(All excess agreement values are negative across 5 configurations; a one-sample $t$-test against zero yields $p{<}0.05$.)
42	Unlike structural signals, FK relies on exact string matching and does not tolerate surface variations.
43	
44	\paragraph{Soft Jaccard (structural, instance-level).}
45	Our primary structural signal extends Jaccard similarity \cite{jaccard1901distribution} to extracted entity/relation sets.
46	For samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching via the Hungarian algorithm (maximizing total token-level IoU; zero-IoU pairs automatically receive zero weight), and define:
47	\begin{equation}\label{eq:sj}
48	\text{SJ}(y_i, y_j) = \frac{\sum_{m \in M} \text{sim}(a_m, b_m)}{\sum_{g} \max(|g_i|, |g_j|)}
49	\end{equation}
50	where $M$ is the matched set from the Hungarian algorithm (without minimum similarity threshold), $\text{sim}(a_m, b_m)$ is the token-level IoU (intersection of tokens divided by union of tokens) between matched entity spans $a_m$ and $b_m$, and $g_i, g_j$ index per-type extraction counts.
51	We use $\max(|g_i|, |g_j|)$ rather than $|g_i \cup g_j|$ as the normalizer to penalize length asymmetry between samples.
52	The instance-level signal averages over all pairs:
53	\begin{equation}\label{eq:sj_instance}
54	c_{\text{sj}}(x) = \frac{1}{\binom{N}{2}} \sum_{i&lt;j} \text{SJ}(y_i, y_j)
55	\end{equation}
56	
57	\paragraph{Entity voting confidence (structural, instance-level).}
58	For each entity $e$ in the union $E_\cup$ of all samples, we compute frequency $\text{freq}(e) = |\{i : e \in y_i\}| / N$.
59	The instance-level confidence is the mean frequency:
60	\begin{equation}\label{eq:voting}
61	c_{\text{vote}}(x) = \frac{1}{|E_\cup|} \sum_{e \in E_\cup} \text{freq}(e)
62	\end{equation}
63	When $E_\cup = \emptyset$ (no entity extracted by any sample), we set $c_{\mathrm{vc}}(x) = 0$.\footnote{This occurs in $<$1\% of instances in our experiments (WNUT-17 only). Equation~\ref{eq:voting} defines the continuous QE signal used throughout Table~\ref{tab:quality_estimation} and all correlation analyses. For voted-output \textit{selection} (Table~\ref{tab:selection}), we include only entities with frequency ${>}N/2$, following standard majority voting. The two computations serve different purposes: Eq.~\ref{eq:voting} assigns a continuous quality score per instance; the majority threshold constructs a discrete output for F1 evaluation. On NER, the threshold variant yields $\rho{=}0.252$ (vs.\ $0.379$ for Eq.~\ref{eq:voting}), reflecting information loss from binarization; on RE, the difference is negligible ($\Delta\rho{=}0.019$).}
64	
65	\subsection{Evaluation Framework}\label{sec:evaluation}
66	
67	\paragraph{Quality estimation.}
68	We measure rank correlation (Spearman $\rho$) between the confidence signal and instance-level F1, and binary discrimination (AUROC) by classifying instances as above or below median F1.
69	
70	\paragraph{Sample selection.}
71	We report best-of-$N$ F1: for each instance, the signal selects one sample.
72	Per-sample signals (LP) directly rank candidates; instance-level signals select the sample closest to the consensus output (the consensus-proximity score for SJ is mathematically equivalent to leave-one-out SJ selection).
73	We compare against an \textit{oracle} (highest-F1 sample) and \textit{greedy} ($T{=}0$, $N{=}1$).
74	
75	\paragraph{Complementarity.}
76	High rank correlation does not guarantee effective sample selection: if per-sample variance is low, even a perfect quality estimator cannot distinguish among near-identical candidates (\S\ref{sec:selection_gap}).
77	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "acf8a2df-49da-4563-b443-271dfed18b15",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex",
      "content": "\\section{Method}\\label{sec:method}\n\n\\subsection{Problem Formulation}\\label{sec:formulation}\n\nGiven a language model $\\mathcal{M}$ and input $x$, we sample $N$ structured outputs $\\{y_1, \\ldots, y_N\\}$ at temperature $T > 0$ via constrained decoding \\cite{willard2023guided}.\nEach $y_i$ is an entity set (NER) or relation set (RE).\nA confidence signal $c$ serves two purposes: (a) \\textit{quality estimation}---predicting which instances the model handles reliably, and (b) \\textit{sample selection}---identifying the best output among $N$ candidates.\n\nA \\textbf{per-sample signal} scores each $y_i$ independently, $c_{\\text{ps}}: (x, y_i) \\to \\mathbb{R}$, enabling direct candidate ranking.\nAn \\textbf{instance-level signal} aggregates over all $N$ samples, $c_{\\text{il}}: (x, \\{y_i\\}_{i=1}^N) \\to \\mathbb{R}$, producing a single score per input.\nThis asymmetry---between predicting \\textit{which inputs} are easy and selecting \\textit{which output} is best---is central to the correlation-selection gap we investigate.\nNotation is summarized in Appendix~\\ref{app:notation}.\n\n\\subsection{Confidence Signals}\\label{sec:signals}\n\nWe use \\textit{confidence signal} as the umbrella term for all five measures.\nFour are \\textit{consistency signals}---computed from inter-sample agreement---spanning two families: \\textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \\textit{surface} (exact match [EM], Fleiss' $\\kappa$ [FK]).\nThe fifth, log-probability, is the sole \\textit{model-internal} signal and the only one that scores individual samples rather than the instance as a whole.\n\n\\paragraph{Log-probability (model-internal, per-sample).}\nThe only per-sample signal.\nFor sample $y_i$ with tokens $t_1, \\ldots, t_{|y_i|}$:\n\\begin{equation}\\label{eq:logprob}\nc_{\\text{lp}}(y_i) = \\frac{1}{|y_i|} \\sum_{j=1}^{|y_i|} \\log p_{\\mathcal{M}}(t_j \\mid t_{&lt;j}, x)\n\\end{equation}\n\n\\paragraph{Exact match voting (surface, instance-level).}\nThe majority fraction---the proportion of samples producing the most common output:\n\\begin{equation}\\label{eq:em}\nc_{\\text{em}}(x) = \\frac{1}{N} \\max_{y} \\big|\\{i : y_i = y\\}\\big|\n\\end{equation}\n\n\\paragraph{Fleiss' $\\kappa$ (surface, instance-level).}\nWe adapt \\citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\\cup| \\times 2$ rating matrix:\n\\begin{equation}\\label{eq:fk}\n\\kappa = \\frac{\\bar{P} - \\bar{P}_e}{1 - \\bar{P}_e}\n\\end{equation}\nwhere $\\bar{P}$ is mean observed pairwise agreement and $\\bar{P}_e$ is expected agreement under random assignment.\nWhile FK assumes independent raters, temperature-based sampling provides sufficient response diversity for the statistic to capture inter-sample agreement patterns.\nEmpirically, we measure excess agreement ($\\bar{P} - \\bar{P}_e$) across all configurations (SciERC NER/RE, CoNLL, WNUT-17; $N{=}8$, $T{=}1.0$) and find values between $-$0.4\\% and $-$4.0\\%, indicating mild \\textit{negative} dependence---samples from the same model tend to err on different items---which confirms that FK is not inflated by inter-sample dependence.\n(All excess agreement values are negative across 5 configurations; a one-sample $t$-test against zero yields $p{<}0.05$.)\nUnlike structural signals, FK relies on exact string matching and does not tolerate surface variations.\n\n\\paragraph{Soft Jaccard (structural, instance-level).}\nOur primary structural signal extends Jaccard similarity \\cite{jaccard1901distribution} to extracted entity/relation sets.\nFor samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching via the Hungarian algorithm (maximizing total token-level IoU; zero-IoU pairs automatically receive zero weight), and define:\n\\begin{equation}\\label{eq:sj}\n\\text{SJ}(y_i, y_j) = \\frac{\\sum_{m \\in M} \\text{sim}(a_m, b_m)}{\\sum_{g} \\max(|g_i|, |g_j|)}\n\\end{equation}\nwhere $M$ is the matched set from the Hungarian algorithm (without minimum similarity threshold), $\\text{sim}(a_m, b_m)$ is the token-level IoU (intersection of tokens divided by union of tokens) between matched entity spans $a_m$ and $b_m$, and $g_i, g_j$ index per-type extraction counts.\nWe use $\\max(|g_i|, |g_j|)$ rather than $|g_i \\cup g_j|$ as the normalizer to penalize length asymmetry between samples.\nThe instance-level signal averages over all pairs:\n\\begin{equation}\\label{eq:sj_instance}\nc_{\\text{sj}}(x) = \\frac{1}{\\binom{N}{2}} \\sum_{i&lt;j} \\text{SJ}(y_i, y_j)\n\\end{equation}\n\n\\paragraph{Entity voting confidence (structural, instance-level).}\nFor each entity $e$ in the union $E_\\cup$ of all samples, we compute frequency $\\text{freq}(e) = |\\{i : e \\in y_i\\}| / N$.\nThe instance-level confidence is the mean frequency:\n\\begin{equation}\\label{eq:voting}\nc_{\\text{vote}}(x) = \\frac{1}{|E_\\cup|} \\sum_{e \\in E_\\cup} \\text{freq}(e)\n\\end{equation}\nWhen $E_\\cup = \\emptyset$ (no entity extracted by any sample), we set $c_{\\mathrm{vc}}(x) = 0$.\\footnote{This occurs in $<$1\\% of instances in our experiments (WNUT-17 only). Equation~\\ref{eq:voting} defines the continuous QE signal used throughout Table~\\ref{tab:quality_estimation} and all correlation analyses. For voted-output \\textit{selection} (Table~\\ref{tab:selection}), we include only entities with frequency ${>}N/2$, following standard majority voting. The two computations serve different purposes: Eq.~\\ref{eq:voting} assigns a continuous quality score per instance; the majority threshold constructs a discrete output for F1 evaluation. On NER, the threshold variant yields $\\rho{=}0.252$ (vs.\\ $0.379$ for Eq.~\\ref{eq:voting}), reflecting information loss from binarization; on RE, the difference is negligible ($\\Delta\\rho{=}0.019$).}\n\n\\subsection{Evaluation Framework}\\label{sec:evaluation}\n\n\\paragraph{Quality estimation.}\nWe measure rank correlation (Spearman $\\rho$) between the confidence signal and instance-level F1, and binary discrimination (AUROC) by classifying instances as above or below median F1.\n\n\\paragraph{Sample selection.}\nWe report best-of-$N$ F1: for each instance, the signal selects one sample.\nPer-sample signals (LP) directly rank candidates; instance-level signals select the sample closest to the consensus output (the consensus-proximity score for SJ is mathematically equivalent to leave-one-out SJ selection).\nWe compare against an \\textit{oracle} (highest-F1 sample) and \\textit{greedy} ($T{=}0$, $N{=}1$).\n\n\\paragraph{Complementarity.}\nHigh rank correlation does not guarantee effective sample selection: if per-sample variance is low, even a perfect quality estimator cannot distinguish among near-identical candidates (\\S\\ref{sec:selection_gap}).\n",
      "numLines": 77,
      "startLine": 1,
      "totalLines": 77
    }
  }
}
```

</details>

---

### Assistant

_source line 52_

<details><summary>Logged reasoning block</summary>

```text
Now I have a complete picture. The method.tex footnote on VC already mentions:
- "On NER, the threshold variant yields ρ=0.252 (vs. 0.379 for Eq. 6), reflecting information loss from binarization; on RE, the difference is negligible (Δρ=0.019)."

So the VC eq6 vs majority comparison is ALREADY in the paper as a footnote. Good.

Now let me also check: the paper's multi-seed appendix table (tab:multiseed) only shows NER data (both ρ and AUROC). The RE multi-seed data is available but not in the paper.


Now I'm checking whether the LLaMA SciERC values in the paper match what I get from a fresh rerun. The paper reports Table 3 results for transfer across model families with LLaMA on CoNLL, and the multi-seed table shows both Qwen and LLaMA NER metrics with their uncertainty ranges.

Comparing the multi-seed table values against the stability artifact data, everything lines up perfectly—the LLaMA results across all five datasets match exactly. However, I'm noticing a discrepancy in the robustness table: the paper shows SJ ρ=0.363 for LLaMA SciERC transfer, but when I rerun the data with fresh seeds, I get SJ values of 0.310, 0.355, and 0.310 with a mean of 0.325. That 0.363 value matches the old contaminated data, which means the paper still contains the outdated result in that particular table.

Actually, wait—I need to look more carefully at what tab:robustness is actually showing. The line I'm looking at is for LLaMA CoNLL with 16 examples across 3 seeds, not SciERC. The SciERC values mentioned in the main text (SJ ρ=0.363, FK ρ=0.327) are single-seed results, not the multi-seed averages.

Looking at the actual data, the multi-seed stability table shows LLaMA SciERC with three different seeds giving SJ values of 0.3096, 0.3552, and 0.3099. But the paper cites SJ ρ=0.363, which doesn't match any of these—it's actually the old contaminated value from exp_007 that shouldn't be in the paper anymore.

Now checking Table 2 in the main text, I see it only shows SciERC results for Qwen, not LLaMA. The LLaMA SciERC data is relegated to the appendix tables on robustness and cross-selection, so there's a mismatch between what the paper claims and where the actual results appear.

Looking at the specific LLaMA-3.1-8B-Instruct numbers for SciERC NER, those correlation values need to be pulled from the fresh exp_018 data rather than what's currently cited.

Let me organize what needs updating versus what's already correct in the paper. Most of the core findings are already there—the free-form ablation numbers, TOST ranges, Qwen thinking token confirmation, LLaMA CoNLL results, and the multi-seed stability table. But I need to flag the LLaMA SciERC values as requiring correction from the new experimental run.

For the new material ready to add, the priority items are the expanded free-form ablation table replacing the simplified version, the detailed analysis of how relation types respond to LP selection flipping and the reshuffling patterns in non-tied instances, the multi-seed RE tables for the appendix, and fixing that contaminated SciERC data point. The per-signal TOST values are also available if needed.

Beyond those, I can add the signal ranking stability findings showing NER's consistency versus RE's minor fluctuations in the top tier, document how free-form improves most signal-task combinations, and correct the LLaMA SJ uncertainty estimate. The LLaMA CoNLL data is actually complete across all three seeds despite what the status showed, so I'm ready to compile the full inventory.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "6f6802d9-51e6-4e12-9908-f5db87ad177e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TMuGXkXg2dHsHrAZtYyPrH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 64993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4675
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 53_

I have all the data. Now writing the inventory.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "78de939b-3001-4de9-b4b1-c40fc46a0ef5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TMuGXkXg2dHsHrAZtYyPrH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 64993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4675
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 54_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01UwkYJFrcu8Z59ZpMTsGcp2`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "3bb12300-7a91-4c6e-b811-71518c28077e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TMuGXkXg2dHsHrAZtYyPrH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 64993,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4675
      },
      "output_tokens": 12,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 55 · 2026-05-15T11:36:01.884Z_

<details><summary>↩ Tool result · `toolu_01UwkYJFrcu8Z59ZpMTsGcp2`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "4f2d7fad-b4ba-4b7f-8de6-17f8e606d92a",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 25
  }
}
```

</details>

---

### Tool call

_source line 56_

<details open><summary>🔧 Tool call — Write · `toolu_01P2Tv6EWNhNqeSxVGBiVCcy`</summary>

````json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/d072_paper_patch_inventory.md",
  "content": "# D072 Paper Patch Inventory\n\n**Date**: 2026-05-15\n\n---\n\n## 已就绪可写入的新发现\n\n### 发现 1: Free-form ablation 扩展表格（4-panel）\n\n- **数据来源**: `freeform_ablation_appendix_table.tex`\n- **关键数字**: Panel A (LP分布), Panel B (Selection F1: NER +0.18pp / RE +1.69pp), Panel C (QE ρ: 9/10 信号×任务组合提升), Panel D (parse rate 99.95%)\n- **写入位置**: `appendix.tex` §app:freeform_ablation — 替换当前简化的 2 列 `tab:freeform_ablation`（6行）为完整 4-panel 版本\n- **修改类型**: 替换表格\n- **优先级**: P0\n- **备注**: 当前 appendix 表格仅有 LP std / tied fraction / selection ΔF1 / VC ρ / parse rate 共 6 行。新表格包含完整 logprob 分布、NER+RE selection F1、全部 5 信号 QE ρ（含 AUROC）、parse rate 四个 panel。信息量提升 4×。\n\n### 发现 2: RE LP Selection Flip 机制分析\n\n- **数据来源**: `freeform_ablation_deep_analysis.md` §1\n- **关键数字**:\n  - 全部 7 种关系类型均从 constrained 负 gap 翻转为 free-form 正/零 gap（universal flip）\n  - PART-OF 翻转最大 +6.52pp，HYPONYM-OF +4.45pp\n  - Win/loss balance: constrained 36:59 (net -23) → free-form 45:45 (net 0)\n  - Free-form 选择性放大 RE-difficult 实例 LP 方差（ratio 1.06, p<0.0001），抑制 RE-easy（ratio 0.86）\n  - Flip 实例（N=31）关系密度 3.3（基线 1.8 的 2×），constrained LP std 仅 0.0162\n- **写入位置**: `discussion.tex` §ablation \"RE task-specific interaction\" 段落扩展 + `appendix.tex` 新增 §app:freeform_re_flip 详细分析\n- **修改类型**: discussion 段落扩展（3-4句 → 8-10句）+ appendix 新增 subsection\n- **优先级**: P0\n- **备注**: 当前 discussion 仅一句\"RE LP selection flips from −0.68pp to +1.69pp\"。深层机制（universal across 7 types、selective variance reallocation、win/loss asymmetry）是论文的新贡献，必须写入。\n\n### 发现 3: Non-tied 子集重洗牌分析\n\n- **数据来源**: `freeform_ablation_deep_analysis.md` §2\n- **关键数字**:\n  - Jaccard(non-tied sets) = 0.472 — 两种 decoding 模式下可区分实例重叠不到一半\n  - 87 个实例在 free-form 下新获 LP 区分力（LP range 从 0.032 → 0.098, 3×）\n  - 76 个实例失去区分力（LP range 从 0.111 → 0.031）\n  - LP range 跨条件 Spearman ρ = 0.488，~76% 方差为条件特异性\n- **写入位置**: `discussion.tex` §ablation 新增段落 或 `appendix.tex` §app:freeform_ablation 扩展\n- **修改类型**: 新增段落\n- **优先级**: P0\n- **备注**: 这个发现揭示了一个关键现象：尽管 tied fraction 几乎相同（59.7% vs 57.7%），free-form 实际上重新分配了哪些实例可被 LP 区分。这补充了\"compression is intrinsic\"的叙事——总体压缩不变，但压缩分布发生了结构性变化。\n\n### 发现 4: 多种子 RE 稳定性数据\n\n- **数据来源**: `multi_seed_stability_table.md` Table A2, B2, C\n- **关键数字**:\n  - RE Spearman ρ: Qwen VC mean=0.309±0.024, LP mean=0.297±0.022; LLaMA VC mean=0.316±0.009, LP mean=0.308±0.007\n  - RE AUROC: Qwen VC mean=0.658±0.010; LLaMA VC mean=0.678±0.007\n  - RE ranking stability: EM 一致排最后，SJ 一致第 4；top-3 (VC/LP/FK) 有轻微波动\n  - NER ranking 完美稳定: VC > SJ > EM > FK > LP 在全部 6 个 seed×model 组合一致\n- **写入位置**: `appendix.tex` §app:multiseed — 扩展 `tab:multiseed` 加入 RE 行，或新增 RE 表\n- **修改类型**: 表格扩展 + 文本新增\n- **优先级**: P0\n- **备注**: 当前 tab:multiseed 仅含 NER 数据。RE 数据已计算完毕且稳定性特征不同（top-3 有波动 vs NER 完美一致），值得单独讨论。RE 结论标注为\"preliminary, single benchmark\"需要这些稳定性数据支撑。\n\n### 发现 5: LLaMA SciERC 数据更正（exp_007 → exp_018）\n\n- **数据来源**: `multi_seed_stability_table.md` §LLaMA SJ ρ correction\n- **关键数字**:\n  - 旧值（contaminated exp_007）: seed42 SJ ρ = 0.363, σ ≈ 0.004\n  - 新值（fresh exp_018 r1024）: seed42 SJ ρ = 0.310, mean = 0.325, σ = 0.021\n  - σ 增大 ~5×，旧数据人为压缩了方差\n- **写入位置**: `appendix.tex` §app:robustness — \"LLaMA-3.1-8B-Instruct replicates the structural-over-surface ordering on SciERC NER (SJ ρ=0.363, FK ρ=0.327)\" → 更正为 fresh values (SJ ρ=0.325±0.021)\n- **修改类型**: 数字更正\n- **优先级**: P0\n- **备注**: 当前论文 appendix robustness 段落引用的 LLaMA SciERC SJ ρ=0.363 是 contaminated exp_007 的值。必须替换为 exp_018 的 fresh 数据。定性结论不变（structural > surface），但具体数字需要更正。FK ρ=0.327 也需核实更正（exp_018 seed42 FK=0.2352, mean=0.256±0.024）。\n\n### 发现 6: Per-signal TOST δ* 精确值\n\n- **数据来源**: `tost_breakpoint_delta_star.md`\n- **关键数字**:\n  - NER: SJ δ*=1.28pp, LP δ*=1.80pp, EM δ*=2.07pp, VC δ*=2.29pp, FK δ*=3.38pp\n  - RE: LP δ*=2.86pp, SJ δ*=3.76pp, FK δ*=4.22pp, EM δ*=5.17pp, VC δ*=6.53pp\n  - NER 所有信号在 δ=5pp 通过，RE 只有 LP/SJ/FK 通过\n- **写入位置**: `appendix.tex` §app:diversity TOST 段落 — 当前文本仅给范围（\"approximately 1.3pp to 3.4pp on NER\"），可加小表格或在文本中列出具体值\n- **修改类型**: 文本扩展或新增迷你表格\n- **优先级**: P1\n- **备注**: 当前文本已包含近似范围，精确值增加透明度但不改变结论。\n\n### 发现 7: Free-form QE 信号全面提升\n\n- **数据来源**: `freeform_ablation_results.md` §3\n- **关键数字**:\n  - NER: 全部 5 信号 ρ 提升（FK +0.053, VC +0.030, EM +0.023, SJ +0.018, LP +0.008）\n  - RE: 4/5 信号提升（FK +0.039, LP +0.038, SJ +0.023, EM +0.002），仅 VC 下降（-0.026）\n  - FK 两个 subtask 一致提升最大\n- **写入位置**: `discussion.tex` §ablation — 当前仅提\"NER VC ρ: 0.379→0.409\"一个数据点，应扩展为完整图景\n- **修改类型**: 段落扩展（1句 → 3-4句）\n- **优先级**: P1\n- **备注**: 加入 4-panel 表格后（发现 1），这些数字自动可见。但 discussion 文本应引用关键趋势。\n\n---\n\n## 已在论文中的内容（无需修改）\n\n| 内容 | 位置 | 状态 |\n|------|------|------|\n| Free-form ablation 基本结论 | discussion.tex §ablation | ✓ 已写入 |\n| TOST δ* 范围 | appendix.tex §app:diversity | ✓ 已写入（近似值） |\n| Qwen3 thinking tokens confound | experiments.tex footnote + limitations.tex | ✓ 已写入 |\n| VC eq6 vs majority threshold (Δρ=+0.127 NER) | method.tex Eq.6 footnote | ✓ 已写入 |\n| Multi-seed NER 稳定性 | appendix.tex tab:multiseed | ✓ 已写入 |\n| LLaMA CoNLL N=16 3-seed | appendix.tex tab:robustness | ✓ 已写入 |\n\n---\n\n## 等待中的结果\n\n| 项目 | 状态 | 预计 |\n|------|------|------|\n| exp_017 LLaMA CoNLL N=16 | 3 seed 全部 DONE (s42/s123/s456) | ✓ 已完成，数据已在 tab:robustness |\n| exp_017 LLaMA CoNLL N=8 r1024 | 2 个 entry RUNNING/killed | 可能需要重跑 |\n| N=16 三种子 SCS 分析 | 分析中 | 待完成 |\n\n---\n\n## 论文修改工作量估算\n\n### 必须改的 section\n\n| Section | 修改项 | 工作量 |\n|---------|--------|--------|\n| `appendix.tex` §app:freeform_ablation | 替换 tab:freeform_ablation 为 4-panel 版本 | 15 min（LaTeX 已就绪） |\n| `appendix.tex` §app:freeform_ablation | 新增 RE flip 机制 + non-tied reshuffling 段落 | 45 min |\n| `appendix.tex` §app:multiseed | 扩展 tab:multiseed 加入 RE 数据 + 讨论 RE ranking stability | 30 min |\n| `appendix.tex` §app:robustness | 更正 LLaMA SciERC 数字 (exp_007→exp_018) | 15 min |\n| `discussion.tex` §ablation | 扩展 RE flip 段落 + QE 全面提升趋势 | 30 min |\n\n### 可选改的 section\n\n| Section | 修改项 | 工作量 |\n|---------|--------|--------|\n| `appendix.tex` §app:diversity TOST | 加入 per-signal δ* 表格 | 15 min |\n| `conclusion.tex` | 提及 free-form RE flip 作为 nuance | 5 min |\n\n### 总预计工时\n\n- **P0 必须项**: ~2.5 小时\n- **P1 可选项**: ~20 分钟\n- **总计**: ~3 小时\n\n### 修改依赖关系\n\n```\n发现1 (4-panel table) ← 独立，可直接替换\n发现2 (RE flip) ← 依赖发现1的 Panel B 数据，但文本独立\n发现3 (non-tied reshuffling) ← 与发现2互补，可合并写\n发现4 (RE multi-seed) ← 独立\n发现5 (数字更正) ← 独立，最高优先\n发现6 (TOST δ*) ← 独立\n发现7 (QE提升) ← 依赖发现1的 Panel C，文本独立\n```\n\n**建议执行顺序**: 5 (数字更正) → 1 (表格替换) → 4 (RE multi-seed) → 2+3 (RE flip + reshuffling) → 7 (QE提升) → 6 (TOST δ*)\n"
}
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "b10de4df-ff11-49ff-8b31-bcf111d2fa22",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CM2kyUvFLNk5JpPuGWXPvr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2828,
      "cache_read_input_tokens": 69668,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2828
      },
      "output_tokens": 33,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 57 · 2026-05-15T11:37:30.249Z_

<details><summary>↩ Tool result · `toolu_01P2Tv6EWNhNqeSxVGBiVCcy`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/d072_paper_patch_inventory.md
```

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "ea0213d1-149b-4c3a-9f6f-af0b900f9d0b",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/d072_paper_patch_inventory.md",
    "content": "# D072 Paper Patch Inventory\n\n**Date**: 2026-05-15\n\n---\n\n## 已就绪可写入的新发现\n\n### 发现 1: Free-form ablation 扩展表格（4-panel）\n\n- **数据来源**: `freeform_ablation_appendix_table.tex`\n- **关键数字**: Panel A (LP分布), Panel B (Selection F1: NER +0.18pp / RE +1.69pp), Panel C (QE ρ: 9/10 信号×任务组合提升), Panel D (parse rate 99.95%)\n- **写入位置**: `appendix.tex` §app:freeform_ablation — 替换当前简化的 2 列 `tab:freeform_ablation`（6行）为完整 4-panel 版本\n- **修改类型**: 替换表格\n- **优先级**: P0\n- **备注**: 当前 appendix 表格仅有 LP std / tied fraction / selection ΔF1 / VC ρ / parse rate 共 6 行。新表格包含完整 logprob 分布、NER+RE selection F1、全部 5 信号 QE ρ（含 AUROC）、parse rate 四个 panel。信息量提升 4×。\n\n### 发现 2: RE LP Selection Flip 机制分析\n\n- **数据来源**: `freeform_ablation_deep_analysis.md` §1\n- **关键数字**:\n  - 全部 7 种关系类型均从 constrained 负 gap 翻转为 free-form 正/零 gap（universal flip）\n  - PART-OF 翻转最大 +6.52pp，HYPONYM-OF +4.45pp\n  - Win/loss balance: constrained 36:59 (net -23) → free-form 45:45 (net 0)\n  - Free-form 选择性放大 RE-difficult 实例 LP 方差（ratio 1.06, p<0.0001），抑制 RE-easy（ratio 0.86）\n  - Flip 实例（N=31）关系密度 3.3（基线 1.8 的 2×），constrained LP std 仅 0.0162\n- **写入位置**: `discussion.tex` §ablation \"RE task-specific interaction\" 段落扩展 + `appendix.tex` 新增 §app:freeform_re_flip 详细分析\n- **修改类型**: discussion 段落扩展（3-4句 → 8-10句）+ appendix 新增 subsection\n- **优先级**: P0\n- **备注**: 当前 discussion 仅一句\"RE LP selection flips from −0.68pp to +1.69pp\"。深层机制（universal across 7 types、selective variance reallocation、win/loss asymmetry）是论文的新贡献，必须写入。\n\n### 发现 3: Non-tied 子集重洗牌分析\n\n- **数据来源**: `freeform_ablation_deep_analysis.md` §2\n- **关键数字**:\n  - Jaccard(non-tied sets) = 0.472 — 两种 decoding 模式下可区分实例重叠不到一半\n  - 87 个实例在 free-form 下新获 LP 区分力（LP range 从 0.032 → 0.098, 3×）\n  - 76 个实例失去区分力（LP range 从 0.111 → 0.031）\n  - LP range 跨条件 Spearman ρ = 0.488，~76% 方差为条件特异性\n- **写入位置**: `discussion.tex` §ablation 新增段落 或 `appendix.tex` §app:freeform_ablation 扩展\n- **修改类型**: 新增段落\n- **优先级**: P0\n- **备注**: 这个发现揭示了一个关键现象：尽管 tied fraction 几乎相同（59.7% vs 57.7%），free-form 实际上重新分配了哪些实例可被 LP 区分。这补充了\"compression is intrinsic\"的叙事——总体压缩不变，但压缩分布发生了结构性变化。\n\n### 发现 4: 多种子 RE 稳定性数据\n\n- **数据来源**: `multi_seed_stability_table.md` Table A2, B2, C\n- **关键数字**:\n  - RE Spearman ρ: Qwen VC mean=0.309±0.024, LP mean=0.297±0.022; LLaMA VC mean=0.316±0.009, LP mean=0.308±0.007\n  - RE AUROC: Qwen VC mean=0.658±0.010; LLaMA VC mean=0.678±0.007\n  - RE ranking stability: EM 一致排最后，SJ 一致第 4；top-3 (VC/LP/FK) 有轻微波动\n  - NER ranking 完美稳定: VC > SJ > EM > FK > LP 在全部 6 个 seed×model 组合一致\n- **写入位置**: `appendix.tex` §app:multiseed — 扩展 `tab:multiseed` 加入 RE 行，或新增 RE 表\n- **修改类型**: 表格扩展 + 文本新增\n- **优先级**: P0\n- **备注**: 当前 tab:multiseed 仅含 NER 数据。RE 数据已计算完毕且稳定性特征不同（top-3 有波动 vs NER 完美一致），值得单独讨论。RE 结论标注为\"preliminary, single benchmark\"需要这些稳定性数据支撑。\n\n### 发现 5: LLaMA SciERC 数据更正（exp_007 → exp_018）\n\n- **数据来源**: `multi_seed_stability_table.md` §LLaMA SJ ρ correction\n- **关键数字**:\n  - 旧值（contaminated exp_007）: seed42 SJ ρ = 0.363, σ ≈ 0.004\n  - 新值（fresh exp_018 r1024）: seed42 SJ ρ = 0.310, mean = 0.325, σ = 0.021\n  - σ 增大 ~5×，旧数据人为压缩了方差\n- **写入位置**: `appendix.tex` §app:robustness — \"LLaMA-3.1-8B-Instruct replicates the structural-over-surface ordering on SciERC NER (SJ ρ=0.363, FK ρ=0.327)\" → 更正为 fresh values (SJ ρ=0.325±0.021)\n- **修改类型**: 数字更正\n- **优先级**: P0\n- **备注**: 当前论文 appendix robustness 段落引用的 LLaMA SciERC SJ ρ=0.363 是 contaminated exp_007 的值。必须替换为 exp_018 的 fresh 数据。定性结论不变（structural > surface），但具体数字需要更正。FK ρ=0.327 也需核实更正（exp_018 seed42 FK=0.2352, mean=0.256±0.024）。\n\n### 发现 6: Per-signal TOST δ* 精确值\n\n- **数据来源**: `tost_breakpoint_delta_star.md`\n- **关键数字**:\n  - NER: SJ δ*=1.28pp, LP δ*=1.80pp, EM δ*=2.07pp, VC δ*=2.29pp, FK δ*=3.38pp\n  - RE: LP δ*=2.86pp, SJ δ*=3.76pp, FK δ*=4.22pp, EM δ*=5.17pp, VC δ*=6.53pp\n  - NER 所有信号在 δ=5pp 通过，RE 只有 LP/SJ/FK 通过\n- **写入位置**: `appendix.tex` §app:diversity TOST 段落 — 当前文本仅给范围（\"approximately 1.3pp to 3.4pp on NER\"），可加小表格或在文本中列出具体值\n- **修改类型**: 文本扩展或新增迷你表格\n- **优先级**: P1\n- **备注**: 当前文本已包含近似范围，精确值增加透明度但不改变结论。\n\n### 发现 7: Free-form QE 信号全面提升\n\n- **数据来源**: `freeform_ablation_results.md` §3\n- **关键数字**:\n  - NER: 全部 5 信号 ρ 提升（FK +0.053, VC +0.030, EM +0.023, SJ +0.018, LP +0.008）\n  - RE: 4/5 信号提升（FK +0.039, LP +0.038, SJ +0.023, EM +0.002），仅 VC 下降（-0.026）\n  - FK 两个 subtask 一致提升最大\n- **写入位置**: `discussion.tex` §ablation — 当前仅提\"NER VC ρ: 0.379→0.409\"一个数据点，应扩展为完整图景\n- **修改类型**: 段落扩展（1句 → 3-4句）\n- **优先级**: P1\n- **备注**: 加入 4-panel 表格后（发现 1），这些数字自动可见。但 discussion 文本应引用关键趋势。\n\n---\n\n## 已在论文中的内容（无需修改）\n\n| 内容 | 位置 | 状态 |\n|------|------|------|\n| Free-form ablation 基本结论 | discussion.tex §ablation | ✓ 已写入 |\n| TOST δ* 范围 | appendix.tex §app:diversity | ✓ 已写入（近似值） |\n| Qwen3 thinking tokens confound | experiments.tex footnote + limitations.tex | ✓ 已写入 |\n| VC eq6 vs majority threshold (Δρ=+0.127 NER) | method.tex Eq.6 footnote | ✓ 已写入 |\n| Multi-seed NER 稳定性 | appendix.tex tab:multiseed | ✓ 已写入 |\n| LLaMA CoNLL N=16 3-seed | appendix.tex tab:robustness | ✓ 已写入 |\n\n---\n\n## 等待中的结果\n\n| 项目 | 状态 | 预计 |\n|------|------|------|\n| exp_017 LLaMA CoNLL N=16 | 3 seed 全部 DONE (s42/s123/s456) | ✓ 已完成，数据已在 tab:robustness |\n| exp_017 LLaMA CoNLL N=8 r1024 | 2 个 entry RUNNING/killed | 可能需要重跑 |\n| N=16 三种子 SCS 分析 | 分析中 | 待完成 |\n\n---\n\n## 论文修改工作量估算\n\n### 必须改的 section\n\n| Section | 修改项 | 工作量 |\n|---------|--------|--------|\n| `appendix.tex` §app:freeform_ablation | 替换 tab:freeform_ablation 为 4-panel 版本 | 15 min（LaTeX 已就绪） |\n| `appendix.tex` §app:freeform_ablation | 新增 RE flip 机制 + non-tied reshuffling 段落 | 45 min |\n| `appendix.tex` §app:multiseed | 扩展 tab:multiseed 加入 RE 数据 + 讨论 RE ranking stability | 30 min |\n| `appendix.tex` §app:robustness | 更正 LLaMA SciERC 数字 (exp_007→exp_018) | 15 min |\n| `discussion.tex` §ablation | 扩展 RE flip 段落 + QE 全面提升趋势 | 30 min |\n\n### 可选改的 section\n\n| Section | 修改项 | 工作量 |\n|---------|--------|--------|\n| `appendix.tex` §app:diversity TOST | 加入 per-signal δ* 表格 | 15 min |\n| `conclusion.tex` | 提及 free-form RE flip 作为 nuance | 5 min |\n\n### 总预计工时\n\n- **P0 必须项**: ~2.5 小时\n- **P1 可选项**: ~20 分钟\n- **总计**: ~3 小时\n\n### 修改依赖关系\n\n```\n发现1 (4-panel table) ← 独立，可直接替换\n发现2 (RE flip) ← 依赖发现1的 Panel B 数据，但文本独立\n发现3 (non-tied reshuffling) ← 与发现2互补，可合并写\n发现4 (RE multi-seed) ← 独立\n发现5 (数字更正) ← 独立，最高优先\n发现6 (TOST δ*) ← 独立\n发现7 (QE提升) ← 依赖发现1的 Panel C，文本独立\n```\n\n**建议执行顺序**: 5 (数字更正) → 1 (表格替换) → 4 (RE multi-seed) → 2+3 (RE flip + reshuffling) → 7 (QE提升) → 6 (TOST δ*)\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
````

</details>

---

### Tool call

_source line 58_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01DQsVE9c2oNJLZvGYGroW5g`</summary>

```json
{
  "name": "D072 Paper Patch Inventory",
  "type": "report",
  "description": "论文可写入新发现的完整清单：7项发现（5×P0 + 2×P1），含数据来源、写入位置、修改类型、优先级。P0包括free-form扩展表格、RE flip机制、non-tied reshuffling、RE multi-seed、LLaMA数据更正。预计总工时~3h。",
  "project": "struct_self_consist_ie",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/d072_paper_patch_inventory.md",
  "tags": [
    "paper",
    "inventory",
    "d072"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "83cdacfa-56ed-4c28-b6ef-e55436ecc025",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B3LXWgTkLRajLbGRxPHByE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3944,
      "cache_read_input_tokens": 72496,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3944
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 59 · 2026-05-15T11:37:36.923Z_

<details><summary>↩ Tool result · `toolu_01DQsVE9c2oNJLZvGYGroW5g`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_b2d959\", \"name\": \"D072 Paper Patch Inventory\", \"type\": \"report\", \"description\": \"论文可写入新发现的完整清单：7项发现（5×P0 + 2×P1），含数据来源、写入位置、修改类型、优先级。P0包括free-form扩展表格、RE flip机制、non-tied reshuffling、RE multi-seed、LLaMA数据更正。预计总工时~3h。\", \"path\": \"projects/struct_self_consist_ie/artifacts/_project/report/d072_paper_patch_inventory.md\", \"url\": null, \"project\": \"struct_self_consist_ie\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-15T11:37:36.704295+00:00\", \"tags\": [\"paper\", \"inventory\", \"d072\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "07be11c0-c9a2-4aa6-bcd6-a31fdbfd2583",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260515_b2d959\\\", \\\"name\\\": \\\"D072 Paper Patch Inventory\\\", \\\"type\\\": \\\"report\\\", \\\"description\\\": \\\"论文可写入新发现的完整清单：7项发现（5×P0 + 2×P1），含数据来源、写入位置、修改类型、优先级。P0包括free-form扩展表格、RE flip机制、non-tied reshuffling、RE multi-seed、LLaMA数据更正。预计总工时~3h。\\\", \\\"path\\\": \\\"projects/struct_self_consist_ie/artifacts/_project/report/d072_paper_patch_inventory.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"struct_self_consist_ie\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-15T11:37:36.704295+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"inventory\\\", \\\"d072\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260515_b2d959\", \"name\": \"D072 Paper Patch Inventory\", \"type\": \"report\", \"description\": \"论文可写入新发现的完整清单：7项发现（5×P0 + 2×P1），含数据来源、写入位置、修改类型、优先级。P0包括free-form扩展表格、RE flip机制、non-tied reshuffling、RE multi-seed、LLaMA数据更正。预计总工时~3h。\", \"path\": \"projects/struct_self_consist_ie/artifacts/_project/report/d072_paper_patch_inventory.md\", \"url\": null, \"project\": \"struct_self_consist_ie\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-15T11:37:36.704295+00:00\", \"tags\": [\"paper\", \"inventory\", \"d072\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 60_

清单已写入并注册。

**汇总**: 7 项可写入发现，5 项 P0 + 2 项 P1。

**P0 关键项**:
1. **Free-form 4-panel 扩展表格** — 替换 appendix 简化表，信息量 4×
2. **RE LP selection flip 机制** — 全部 7 关系类型 universal flip，selective variance reallocation (p<0.0001)，win/loss 从 36:59 翻转到 45:45
3. **Non-tied 子集重洗牌** — Jaccard=0.472，87 个实例新获区分力（LP range 3×），揭示压缩分布的结构性变化
4. **多种子 RE 稳定性** — RE ranking 有轻微 top-3 波动（vs NER 完美稳定），tab:multiseed 需加 RE 行
5. **数据更正** — appendix robustness 中 LLaMA SciERC SJ ρ=0.363 是 contaminated exp_007 值，应更正为 0.325±0.021（exp_018 fresh data）；FK 0.327→0.256±0.024

**预计工时**: P0 ~2.5h，P1 ~20min，总计 ~3h。建议先修数字更正（发现5），再替换表格（发现1）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "uuid": "29b47b60-f290-4a9a-8650-08db03e775b2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HRYxMdPZC3wzN6q5DvUN3z",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 657,
      "cache_read_input_tokens": 76440,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 657
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 61_

清单已写入并注册。

**汇总**: 7 项可写入发现，5 项 P0 + 2 项 P1。

**P0 关键项**:
1. **Free-form 4-panel 扩展表格** — 替换 appendix 简化表，信息量 4×
2. **RE LP selection flip 机制** — 全部 7 关系类型 universal flip，selective variance reallocation (p<0.0001)，win/loss 从 36:59 翻转到 45:45
3. **Non-tied 子集重洗牌** — Jaccard=0.472，87 个实例新获区分力（LP range 3×），揭示压缩分布的结构性变化
4. **多种子 RE 稳定性** — RE ranking 有轻微 top-3 波动（vs NER 完美稳定），tab:multiseed 需加 RE 行
5. **数据更正** — appendix robustness 中 LLaMA SciERC SJ ρ=0.363 是 contaminated exp_007 值，应更正为 0.325±0.021（exp_018 fresh data）；FK 0.327→0.256±0.024

**预计工时**: P0 ~2.5h，P1 ~20min，总计 ~3h。建议先修数字更正（发现5），再替换表格（发现1）。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 276558,
  "duration_api_ms": 276677,
  "num_turns": 25,
  "stop_reason": "end_turn",
  "session_id": "c03756a4-6b28-4a5f-9a56-f8f8d904dced",
  "total_cost_usd": 1.0719105,
  "usage": {
    "input_tokens": 19,
    "cache_creation_input_tokens": 65256,
    "cache_read_input_tokens": 720873,
    "output_tokens": 12081,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 65256,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 392,
        "cache_read_input_tokens": 76440,
        "cache_creation_input_tokens": 657,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 657
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1429,
      "outputTokens": 15,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001504,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 19,
      "outputTokens": 12081,
      "cacheReadInputTokens": 720873,
      "cacheCreationInputTokens": 65256,
      "webSearchRequests": 0,
      "costUSD": 1.0704065,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "eefa5d09-bdd2-454a-a763-75c6b2c3cdc0"
}
```

</details>

---
