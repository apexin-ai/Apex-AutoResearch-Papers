# Research conversation: You are Reviewer R1 for a top ML venue review. Your focus is **Methods and Experiments**. Score on a 6-point scale (1=St

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 54
- **Recorded user turns:** 1
- **Tool calls:** 24
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-a87a0108a1f10e610.jsonl`
- **Structured JSON:** [`ac8ba3941db05455465e.json`](../../sessions/ac/ac8ba3941db05455465e.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

54 recorded events

### User

_source line 1 · 2026-05-17T02:05:07.502Z_

You are Reviewer R1 for a top ML venue review. Your focus is **Methods and Experiments**. Score on a 6-point scale (1=Strong Reject, 2=Reject, 3=Weak Reject, 4=Weak Accept, 5=Accept, 6=Strong Accept). Target venue acceptance rate ~25%.

## Paper Summary

**Title:** Phase-Gated Compound Sparsity: Phase Modulation is Universal but Strategy Selectivity is Task-Modulated

The paper studies compound sparsity (simultaneous attention head pruning + KV cache eviction) in LLM inference. The core claim is that compound interaction severity is not uniform but phase-dependent: it increases monotonically from high-sparsity (exploration) to low-sparsity (verification) phases. This is tested across 3 benchmarks (MATH-500, GSM8K, GPQA), 3 models (DeepSeek-R1-Distill-Qwen-7B, Qwen2.5-7B-Instruct, DeepSeek-R1-Distill-Llama-8B), 2 architectures, and 4 sparsity levels (0.15–0.30).

Key findings:
1. Phase modulation is universal: monotonically increasing importance-based severity gradient across all conditions (all p < 10^-27, dz 0.48–1.15).
2. Strategy selectivity is task-modulated: importance/random ratio is 15–17× on MATH-500 but only 2–4× on GSM8K and GPQA.
3. Recency control produces null gradients (scoring-independent control).
4. Discrimination collapse mechanism: head pruning degrades Gini coefficient of importance scores.

## Experimental Design Reference (from review_context.yaml)

The imagined experiments include:
- GPQA DS Importance at s=0.15, 0.20, 0.25, 0.30 (all done in paper)
- GPQA DS Random at s=0.20, 0.25, 0.30 (partially reported)
- Cross-benchmark comparison at s=0.30

Expected results from design: GPQA dz values 0.48–0.73 (medium-to-large), imp/rand ratio 2.7–3.0× on GPQA (stable across sparsity), matching GSM8K pattern but far below MATH-500.

## Your Review Task

Evaluate the paper on:

1. **Methodological soundness** — Is the Compound Interaction Index (II) well-defined? Is the factorial design appropriate? Is the phase segmentation procedure robust or potentially circular? Are the statistical tests appropriate (Wilcoxon, bootstrap, Bonferroni)?

2. **Experimental completeness** — Are there missing experiments? The paper tests 3 benchmarks × 3 models but GPQA only uses 1 model (DS-7B). Cross-benchmark Table 4 is missing GPQA on QW-7B and Llama-8B. GSM8K random numbers use "~" approximations. Are all claimed contributions supported by data?

3. **Statistical rigor** — Are the effect sizes (dz 0.48–0.73 on GPQA) practically meaningful or merely statistically significant? The paper acknowledges medium-to-large effects but GPQA is weaker than MATH-500. Is the sample size (n=198 for GPQA, n=500 for MATH-500) sufficient?

4. **Concerns about the metric** — The II is defined as PPL_compound - PPL_prune - PPL_evict + PPL_baseline. Is this a valid interaction measure? Could phase segmentation based on "perplexity-based change-point detection on the uncompressed trace" introduce bias?

5. **Missing baselines/controls** — The recency control is novel and valuable. But are there other controls that should be included? What about different head pruning strategies? The paper only varies KV eviction strategy while keeping head pruning fixed.

6. **Reproducibility** — Is there enough detail to reproduce? Phase segmentation details are sparse. Which layers are pruned? How are heads selected for pruning?

7. **Section 4.6 concern** — The paper includes a "Simulated Reviewer Assessment" (Table 7) which is highly unusual and potentially inappropriate for a submission.

Provide:
- Strengths (bullet list)
- Weaknesses (bullet list)  
- Questions for authors
- Detailed scores: Soundness, Significance, Clarity, Overall
- Confidence level (1-5)


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "8850e8b6-f526-48c5-9b40-bc09bd039c01",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-17T02:05:07.511Z_

```json
{
  "parentUuid": "8850e8b6-f526-48c5-9b40-bc09bd039c01",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "attachment": {
    "type": "deferred_tools_delta",
    "addedNames": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__director_get_project_overview",
      "mcp__agent-ml-research__director_post_to_reviewer",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__submit_dream_review_report"
    ],
    "addedLines": [
      "CronCreate",
      "CronDelete",
      "CronList",
      "EnterWorktree",
      "ExitWorktree",
      "ListMcpResourcesTool",
      "Monitor",
      "NotebookEdit",
      "PushNotification",
      "ReadMcpResourceTool",
      "RemoteTrigger",
      "TaskStop",
      "TodoWrite",
      "WebFetch",
      "WebSearch",
      "mcp__agent-ml-research__director_get_project_overview",
      "mcp__agent-ml-research__director_post_to_reviewer",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__submit_dream_review_report"
    ],
    "removedNames": []
  },
  "type": "attachment",
  "uuid": "8425f553-65c7-4ade-b5d6-9493138dfce5",
  "timestamp": "2026-05-17T02:05:07.511Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 3 · 2026-05-17T02:05:10.766Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01MFQ6zBQAjkquuCqfWTu7vo`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8425f553-65c7-4ade-b5d6-9493138dfce5",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kc6bBkATwHEMGSq2Kh",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "08280cf4-1549-4a3e-81cf-65f35a4ce513",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ChoLpm68gvxZm2Tjzq1Km8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 16437,
      "cache_read_input_tokens": 0,
      "output_tokens": 88,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 16437
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 88,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 16437,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 16437,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-17T02:05:10.773Z_

<details><summary>↩ Tool result · `toolu_01MFQ6zBQAjkquuCqfWTu7vo`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "08280cf4-1549-4a3e-81cf-65f35a4ce513",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "d290873b-db10-400d-87c6-d57b6e98b632",
  "sourceToolAssistantUUID": "08280cf4-1549-4a3e-81cf-65f35a4ce513",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T02:05:17.805Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01WXkfMkCmvo3R7RmQ9db1Df`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "report.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d290873b-db10-400d-87c6-d57b6e98b632",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KcLjjfjdmhzG1itiNP",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1d4ba006-1f96-470d-b61b-9b51ff64fdd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DxuTs15T9DxjUEpPE64bcq",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1269,
      "cache_read_input_tokens": 16437,
      "output_tokens": 110,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1269
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 110,
          "cache_read_input_tokens": 16437,
          "cache_creation_input_tokens": 1269,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1269,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-17T02:05:17.827Z_

<details><summary>↩ Tool result · `toolu_01WXkfMkCmvo3R7RmQ9db1Df`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/report.md\", \"content\": \"# Handover — 2026-05-17\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| gpqa_ds_random_s020 | Cross-task generalization: random eviction control on GPQA Diamond. DS-R1 random s020 to establish baseline phase gradient (expected NS or weak) for strategy specificity comparison. | — | — | — |\\n| gpqa_ds_importance_s030 | Cross-task generalization: compound sparsity severity monotonically increases on GPQA Diamond (non-math reasoning) using quantile 3-segment phase decomposition. DS-R1 importance s030 as fourth condition. | — | — | — |\\n| gpqa_ds_importance_s025 | Cross-task generalization: compound sparsity severity monotonically increases on GPQA Diamond (non-math reasoning) using quantile 3-segment phase decomposition. DS-R1 importance s025 as third condition (after s015 success, s020 running). | — | — | — |\\n\\n## 待处理\\n（无）\\n\\n## 近期结论\\n- **recency_s025** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.25 condition.\\n  [recency_s025_analysis](/api/workspace-files/projects/phase-gated-compound-sparse/artifacts/recency_s025/report/analysis.md)\\n- **recency_s030** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.30 condition.\\n  [recency_s030_analysis](/api/workspace-files/projects/phase-gated-compound-sparse/artifacts/recency_s030/report/analysis.md)\\n- **recency_s015** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.15 condition.\\n\\n## 趋势\\n成功 70 / 负向 17 / 失败 17 / 共 134\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-22162: 无 GPU 信息\\n\\n## 告警\\n- mvp_interaction_index_profiling: 训练失败 — unknown\\n- mvp_ii_profiling_v4: 训练失败 — unknown\\n- mvp_ii_profiling_v4b: 训练失败 — unknown\\n- mvp_ii_profiling_v4c: 训练失败 — unknown\\n- mvp_ii_profiling_v4d: 训练失败 — unknown\\n- mvp_ii_profiling_v4-random: 训练失败 — unknown\\n- mvp_v4a_r2: 训练失败 — unknown\\n- mvp_v4b_r2: 训练失败 — unknown\\n- mvp_v4c_r2: 训练失败 — unknown\\n- mvp_v4_legacy_s025: 训练失败 — unknown\\n- mvp_v4_legacy_s035: 训练失败 — unknown\\n- mvp_v4_float32_s030: 已被终止 — unknown\\n- mvp_v5_fixed_s020: 已被终止 — unknown\\n- mvp_v5_fixed_s030: 已被终止 — unknown\\n- qwen_importance_s015: 已被终止 — unknown\\n- qwen_importance_s020: 已被终止 — unknown\\n- qwen_importance_s025: 已被终止 — unknown\\n- qwen_importance_s030: 已被终止 — unknown\\n- v6_random_s030: 训练失败 — unknown\\n- v6_random_s030_r2: 训练失败 — unknown\\n- bf16_random_s015: 已被终止 — unknown\\n- bf16_random_s020: 已被终止 — unknown\\n- bf16_random_s025: 已被终止 — unknown\\n- bf16_random_s030: 已被终止 — unknown\\n- bf16_qwen_importance_s015: 已被终止 — unknown\\n- bf16_qwen_importance_s020: 已被终止 — unknown\\n- bf16_qwen_importance_s025: 已被终止 — unknown\\n- bf16_qwen_importance_s030: 已被终止 — unknown\\n- bf16_ds_imp_s015: 已被终止 — unknown\\n- bf16_ds_imp_s020: 已被终止 — unknown\\n- bf16_ds_imp_s025: 已被终止 — unknown\\n- bf16_ds_imp_s030: 已被终止 — unknown\\n- c3_llama_arch: 已被终止 — unknown\\n- c2_ds_n500: 已被终止 — unknown\\n- c2_qw_n500: 训练失败 — unknown\\n- r9c2-spike: 已被终止 — unknown\\n- r9c2-spike-v2: 已被终止 — unknown\\n- r9c2-spike-v3: 已被终止 — unknown\\n- acc_ds_dense_8k: 已被终止 — unknown\\n- acc_ds_s015_8k: 已被终止 — unknown\\n- acc_ds_s020_8k: 已被终止 — unknown\\n- acc_ds_s025_8k: 已被终止 — unknown\\n- acc_ds_s030_8k: 已被终止 — unknown\\n- gsm8k_qw_rand_s025: 训练失败 — unknown\\n- gsm8k_qw_rand_s030: 训练失败 — unknown\\n- c8_llama_n250: 训练失败 — unknown\\n- c10-lang-s020-s025: 已被终止 — unknown\\n\", \"total_chars\": 3667, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1d4ba006-1f96-470d-b61b-9b51ff64fdd5",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "ec6cafb2-45f8-4333-8119-6b020cc2a01e",
  "sourceToolAssistantUUID": "1d4ba006-1f96-470d-b61b-9b51ff64fdd5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T02:05:21.219Z_

<details open><summary>🔧 Tool call — Glob · `toolu_019KybEQdP2Vd52apF1sciMG`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ec6cafb2-45f8-4333-8119-6b020cc2a01e",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kcs5rjvT4Hn6ZR65Cz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bd13b843-5fa8-46e6-a3a2-00ce2793e454",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016vkaCY1rrpRqgsXZJz6jxE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1913,
      "cache_read_input_tokens": 17706,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1913,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 47,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-17T02:05:21.256Z_

<details><summary>↩ Tool result · `toolu_019KybEQdP2Vd52apF1sciMG`</summary>

```text
artifacts/_project/paper/main.tex
artifacts/_project/paper/appendix.tex
artifacts/_project/paper/appendix_robustness.tex
artifacts/dream_reports/dream_20260516T073742/best/paper.tex
artifacts/dream_reports/dream_20260516T073742/median/paper.tex
artifacts/dream_reports/dream_20260516T073742/worst/paper.tex
artifacts/dream_reports/dream_20260516T150210/best/paper.tex
artifacts/dream_reports/dream_20260516T150210/median/paper.tex
artifacts/dream_reports/dream_20260516T150210/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/_project/paper/analysis.tex
artifacts/dream_reports/dream_20260516T164305/best/paper.tex
artifacts/dream_reports/dream_20260516T164305/median/paper.tex
artifacts/dream_reports/dream_20260516T164305/worst/paper.tex
artifacts/_project/paper/methodology.tex
artifacts/_project/paper/background.tex
artifacts/_project/paper/appendix_moved.tex
artifacts/_project/paper/appendix_disc_analysis.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/drafts/recency_control_section.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/limitations.tex
artifacts/_project/paper/results.tex
artifacts/_project/paper/abstract.tex
artifacts/dream_reports/dream_20260517T005655/best/paper.tex
artifacts/dream_reports/dream_20260517T005655/median/paper.tex
artifacts/dream_reports/dream_20260517T005655/worst/paper.tex
artifacts/dream_reports/dream_20260517T013445/best/paper.tex
artifacts/dream_reports/dream_20260517T013445/median/paper.tex
artifacts/dream_reports/dream_20260517T013445/worst/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bd13b843-5fa8-46e6-a3a2-00ce2793e454",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "1fc33f56-0db4-4534-9db3-5395ddc45a68",
  "sourceToolAssistantUUID": "bd13b843-5fa8-46e6-a3a2-00ce2793e454",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T02:05:21.483Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_015mxeamRZyXpxo9TCWdtyp9`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "ideas.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1fc33f56-0db4-4534-9db3-5395ddc45a68",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kcs5rjvT4Hn6ZR65Cz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "b1d27084-bd4c-429f-bdf3-379fa326031f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016vkaCY1rrpRqgsXZJz6jxE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1913,
      "cache_read_input_tokens": 17706,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1913,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 47,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-17T02:05:21.507Z_

<details><summary>↩ Tool result · `toolu_015mxeamRZyXpxo9TCWdtyp9`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No ideas.md found for 'phase-gated-compound-sparse'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b1d27084-bd4c-429f-bdf3-379fa326031f",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "5047dd0c-965e-4ee5-b6d7-f6987e4627ac",
  "sourceToolAssistantUUID": "b1d27084-bd4c-429f-bdf3-379fa326031f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T02:05:24.571Z_

<details open><summary>🔧 Tool call — Read · `toolu_01VXgH45gdpEkLZQLfrVZKb4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5047dd0c-965e-4ee5-b6d7-f6987e4627ac",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kd8fEb3mXNJU5uHthh",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6da7b5cf-ebe4-4f95-b5be-d16deecf36e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015hrbbPfrDunDU9zT3DNunN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 809,
      "cache_read_input_tokens": 19619,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 809,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 53,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-17T02:05:24.579Z_

<details><summary>↩ Tool result · `toolu_01VXgH45gdpEkLZQLfrVZKb4`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	\usepackage[review]{acl}
4	
5	\usepackage{times}
6	\usepackage{latexsym}
7	\usepackage[T1]{fontenc}
8	\usepackage[utf8]{inputenc}
9	\usepackage{microtype}
10	\usepackage{inconsolata}
11	
12	\usepackage{amsmath}
13	\usepackage{amssymb}
14	\usepackage{graphicx}
15	\usepackage{booktabs}
16	\usepackage{enumitem}
17	\usepackage{multirow}
18	
19	\graphicspath{{figures/}}
20	
21	
22	\title{Phase-Modulated Compound Sparsity Severity\\in 7B-Scale Mathematical Reasoning Models}
23	
24	\author{Anonymous}
25	
26	\begin{document}
27	
28	\maketitle
29	
30	\input{abstract}
31	
32	\input{introduction}
33	\input{related_work}
34	\input{background}
35	\input{methodology}
36	\input{results}
37	\input{analysis}
38	\input{discussion}
39	\input{conclusion}
40	
41	\bibliography{references}
42	
43	\section*{Limitations}
44	\input{limitations}
45	
46	\section*{Reproducibility}
47	Code and data will be released upon acceptance.
48	
49	\appendix
50	\input{appendix}
51	\input{appendix_moved}
52	\input{appendix_disc_analysis}
53	\input{appendix_robustness}
54	
55	\end{document}
56	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6da7b5cf-ebe4-4f95-b5be-d16deecf36e6",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "289abc44-852a-4700-abb9-3550269a5a37",
  "sourceToolAssistantUUID": "6da7b5cf-ebe4-4f95-b5be-d16deecf36e6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T02:05:25.521Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Pp2STxRkzDYupAcETC7jRP`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "289abc44-852a-4700-abb9-3550269a5a37",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kd8fEb3mXNJU5uHthh",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "625ff78b-c989-41b1-b099-a430f8b6cd19",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015hrbbPfrDunDU9zT3DNunN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 809,
      "cache_read_input_tokens": 19619,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 809,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 53,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-17T02:05:25.527Z_

<details><summary>↩ Tool result · `toolu_01Pp2STxRkzDYupAcETC7jRP`</summary>

```text
1	\begin{abstract}
2	Compound sparsity---simultaneously pruning attention heads and evicting KV cache entries---is essential for efficient LLM inference but produces super-additive quality degradation whose structure is poorly understood.
3	We find that compound sparsity severity is not a fixed constant but an emergent property of the interaction among eviction strategy, reasoning phase, and sparsity level.
4	On DeepSeek-R1-Distill-Qwen-7B (MATH-500), importance-based eviction exhibits a monotonically increasing phase--severity gradient: the paired median difference $\Delta$ rises from $0.39$ at sparsity $s{=}0.15$ to $8.48$ at $s{=}0.30$ (Spearman $\rho{=}1.0$; all Bonferroni-corrected $p < 0.005$).
5	Random eviction develops a detectable gradient only above $s \approx 0.20$, at $2.7$--$17{\times}$ smaller magnitude.
6	A scoring-independent control (recency eviction) produces no positive phase gradient: $\Delta$ vanishes at $s \leq 0.25$ and remains non-significant at $s{=}0.30$, confirming that the interaction is attention-score-specific rather than an inherent property of token removal.
7	The pattern replicates on Qwen2.5-7B-Instruct ($\Delta$: $0.07 \to 3.16$; $\rho{=}1.0$), shows consistent phase gradient direction on GSM8K, and generalizes to LlamaForCausalLM ($n{=}250$; $d_z{=}0.81$--$1.15$, all $p < 10^{-29}$).
8	Per-phase Gini analysis identifies \emph{importance discrimination collapse}---the degeneration of head importance scores toward uniformity under compound stress---as a correlational diagnostic of this severity divergence.
9	Prior work characterizes compound degradation as phase-agnostic; we show that phase modulates severity by $15$--$17{\times}$ on DeepSeek and $2.7$--$3.5{\times}$ on Qwen, specifically driven by attention-score-based selection. These findings establish phase-gated analysis as a principled diagnostic framework with direct implications for phase-aware budget allocation.
10	\end{abstract}
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "625ff78b-c989-41b1-b099-a430f8b6cd19",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "4cf56a82-f825-4ef6-ab5c-b62bfdcc4745",
  "sourceToolAssistantUUID": "625ff78b-c989-41b1-b099-a430f8b6cd19",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-17T02:05:25.827Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WdAPzNkodXocXyVRqp1YH4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/methodology.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4cf56a82-f825-4ef6-ab5c-b62bfdcc4745",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kd8fEb3mXNJU5uHthh",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1cc28b97-194f-4bfc-9cc5-f3223ad39dc0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015hrbbPfrDunDU9zT3DNunN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 809,
      "cache_read_input_tokens": 19619,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 809
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 19619,
          "cache_creation_input_tokens": 809,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 809,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-17T02:05:25.837Z_

<details><summary>↩ Tool result · `toolu_01WdAPzNkodXocXyVRqp1YH4`</summary>

```text
1	\section{Experimental Setup}
2	\label{sec:experimental-setup}
3	
4	\paragraph{Models.}
5	We evaluate on two 7B-parameter models sharing the Qwen2 backbone (28 layers, 28 heads, 4-group GQA): \textbf{DeepSeek-R1-Distill-Qwen-7B}~\cite{deepseek-r1-2025}, distilled from DeepSeek-R1 with explicit chain-of-thought traces yielding pronounced phase structure; and \textbf{Qwen2.5-7B-Instruct}~\cite{qwen25-2024}, with standard instruction tuning, providing a cross-training-paradigm replication target. Both are loaded in \texttt{bfloat16} with eager attention.\footnote{An earlier \texttt{float16} configuration produced sporadic NaN values; \texttt{bfloat16} eliminated all occurrences.}
6	
7	\paragraph{Dataset.}
8	We evaluate all 500 problems from MATH-500~\cite{math500-neurips2021}. Each problem is decoded greedily (\texttt{max\_new\_tokens}$=$2048). Problems with degenerate phase assignments (null low or high phase) are excluded, yielding effective sample sizes of $n{=}496$ for DeepSeek (4 excluded) and $n{=}475$ for Qwen (25 excluded). Qwen exhibits a higher mid-phase null rate (45.2\% vs.\ 10.2\% for DeepSeek) due to lower temporal autocorrelation in its attention sparsity patterns (lag-1 $r{=}0.718$ vs.\ $0.894$, $d{=}-1.68$); this does not affect the primary gradient metric $\Delta = \mathrm{II}_{\textit{low}} - \mathrm{II}_{\textit{high}}$, which requires only low and high phases. Sensitivity analysis across $\texttt{min\_phase\_length} \in \{5, 10, 20\}$ supports robustness (Appendix~\ref{app:mpl-sensitivity}).
9	
10	\paragraph{Sparsity configuration.}
11	We apply symmetric compound sparsity at $s \in \{0.15, 0.20, 0.25, 0.30\}$: at each level, the head pruning rate $p{=}s$ (fraction of heads removed per layer) equals the KV cache eviction rate $e{=}s$ (fraction of positions evicted). We compute perplexity under four conditions: dense, attention-only ($p{=}s, e{=}0$), KV-only ($p{=}0, e{=}s$), and compound ($p{=}s, e{=}s$). We compare \emph{importance-based} eviction (position-normalized cumulative attention score, Eq.~\ref{eq:kv-importance}; BOS always retained) and \emph{random} eviction (uniform). Heads are pruned per layer by Frobenius norm; under random eviction, both heads and positions are selected uniformly.
12	
13	\paragraph{Phase segmentation and metrics.}
14	Each sequence is segmented into three phases using the quantile-based method (\S\ref{par:phase-segmentation}), with $\texttt{min\_phase\_length}{=}10$. We compute segment-level perplexity and II (Eq.~\ref{eq:ii}), reporting medians due to heavy right-skew (mean/median ratios up to 43:1). The amplification ratio $G$ (Eq.~\ref{eq:gradient}) is reported in Appendix~\ref{app:g-metric}. Robustness to segmentation granularity (quartile, quintile; Appendix~\ref{app:seg-robust}) and minimum phase length ($5$, $10$, $20$ tokens; Appendix~\ref{app:mpl-sensitivity}) is verified.
15	
16	\paragraph{Segmentation validation.}
17	Quantile-based segmentation shows strong agreement with model-intrinsic \texttt{&lt;think>} boundaries on DeepSeek (Cohen's $\kappa{=}0.88$, token-level accuracy $94.2\%$, AUC-ROC${=}0.98$; $n{=}48$, GSM8K): $57.8\%$ of \texttt{&lt;think>} tokens fall in the low-sparsity phase and $62.7\%$ of answer tokens fall in the high-sparsity phase, confirming that attention-sparsity phases recover genuine reasoning structure without requiring explicit delimiters. Boundary proximity is tight (median 1 token; $81.2\%$ within 10 tokens). Appendix~\ref{app:think-validation} provides full details.
18	
19	\paragraph{Statistical analysis.}
20	\label{par:stats}
21	All reported confidence intervals use nonparametric bootstrap ($B{=}10{,}000$, seed$=$42)~\cite{efron-1993}. Significance tests use Wilcoxon signed-rank (paired within-model) or Mann-Whitney $U$ (cross-training-paradigm), with Bonferroni correction at family-wise $k{=}4$ (per model$\times$strategy combination, 4 sparsity levels testing one dose-response hypothesis): each family tests a single directional question (``does $\Delta$ increase with $s$?'') under fixed model and strategy, making $k{=}4$ the natural grouping. Benjamini-Hochberg FDR correction across all 44 tests is reported as a robustness check in Appendix~\ref{app:bh-fdr}; all Bonferroni-significant results remain significant under BH-FDR. Dose-response monotonicity is supported by the Jonckheere-Terpstra test ($z{=}6.2$--$33.7$, all $p < 10^{-9}$), which uses per-problem values (${\sim}496$ per group) rather than aggregated medians.\footnote{Spearman rank correlation on the four aggregate medians ($\rho{=}1.0$, $n{=}4$; interpret with caution given the small number of levels) is consistent; we rely on the JT test as primary evidence.} Scaling from $n{=}50$ (profiling) to $n{=}500$ narrowed bootstrap CI widths by $2.5$--$5.9{\times}$ across all 16 conditions, showing precision gains. The paired median difference $\Delta$ is the primary metric; $G$ (amplification ratio, Eq.~\ref{eq:gradient}) is reported in Appendix~\ref{app:g-metric} as an auxiliary illustrative ratio.\footnote{Experiments on 4$\times$ professional GPUs with 48\,GB memory.}
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1cc28b97-194f-4bfc-9cc5-f3223ad39dc0",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "50349ae3-2fe4-4f9e-9dfc-7c389f1c1eae",
  "sourceToolAssistantUUID": "1cc28b97-194f-4bfc-9cc5-f3223ad39dc0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-17T02:05:29.081Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PNQBX4LSoGeWGERXJ4cAFz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "50349ae3-2fe4-4f9e-9dfc-7c389f1c1eae",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdT1YdCxMwaRSaxGUR",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a05766fb-ed23-40b1-b54d-e9151b58b766",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPkeL62ab4i8bSwwrc8HaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3102,
      "cache_read_input_tokens": 20428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3102,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 68,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-17T02:05:29.091Z_

<details><summary>↩ Tool result · `toolu_01PNQBX4LSoGeWGERXJ4cAFz`</summary>

```text
1	
2	\section{Results}
3	\label{sec:results}
4	
5	\subsection{Strategy-Dependent Severity}
6	\label{sec:strategy-severity}
7	
8	Table~\ref{tab:aggregate-ii} reports the median compound severity difference across strategies and sparsity levels. Under importance-based eviction, $\Delta$ increases from $0.39$ at $s{=}0.15$ to $8.48$ at $s{=}0.30$---a $22{\times}$ amplification (all Bonferroni-corrected $p \ll 10^{-10}$). Random eviction develops a detectable but weak phase gradient above $s \approx 0.20$: at $s \leq 0.20$, $\Delta$ is non-significant ($0.01$--$0.03$; CIs span zero); at $s \geq 0.25$, $\Delta$ becomes significant ($0.26$--$0.51$; $p_{\text{Bonf}} < 0.006$) but $15$--$17{\times}$ smaller than under importance-based eviction. Both strategies exhibit monotonic dose-response (Jonckheere-Terpstra $z{=}6.2$--$33.7$, all $p < 10^{-9}$), but importance masking effect sizes are an order of magnitude larger.
9	
10	\begin{table}[t]
11	\centering
12	\small
13	\caption{Median of per-problem paired severity differences ($\Delta$) by eviction strategy and sparsity level on DeepSeek-R1-Distill-Qwen-7B ($n{=}496$, MATH-500).}
14	\label{tab:aggregate-ii}
15	\begin{tabular}{@{}lcccc@{}}
16	\toprule
17	Strategy & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
18	\midrule
19	Importance & 0.39 & 1.21 & 3.99 & 8.48 \\
20	Random     & 0.01 & 0.03 & 0.26 & 0.51 \\
21	\bottomrule
22	\end{tabular}
23	\end{table}
24	
25	
26	\subsection{Phase-Modulated Amplification}
27	\label{sec:phase-amplification}
28	
29	Decomposing II by reasoning phase reveals that strategy-dependent severity is driven by amplification in the low-sparsity phase. Table~\ref{tab:main-results} reports the per-phase breakdown. Under importance-based eviction, the median II in the low-sparsity phase rises from $0.357$ ($s{=}0.15$) to $8.456$ ($s{=}0.30$), while the high-sparsity phase remains near zero ($0.003$--$0.038$), yielding paired median differences $\Delta$ from $0.39$ to $8.48$ (all $p \ll 10^{-10}$). Random eviction shows a detectable but much weaker phase gradient at $s \geq 0.25$ ($\Delta{=}0.26$--$0.51$; $p_{\text{Bonf}} < 0.006$), $15$--$17{\times}$ smaller than importance-based at matched sparsity. Figure~\ref{fig:hero} visualizes the dose-response relationship for both models. The per-problem amplification ratio $G$ (Eq.~\ref{eq:gradient}) provides an auxiliary illustrative perspective and is reported in Appendix~\ref{app:g-metric}.
30	Under the multiplicative null ($r_b = r_a \cdot r_k$; Appendix~\ref{app:multiplicative-null}), the phase-severity gradient is preserved ($G_{\times}{=}21$--$64{\times}$); we report additive-null values throughout as the more conservative estimates.
31	
32	\begin{table*}[t]
33	\centering
34	\small
35	\caption{Per-phase interaction index (II) at $n{=}496$/$475$. $\Delta{=}\widetilde{\mathrm{II}^{(i)}_{\textit{low}} - \mathrm{II}^{(i)}_{\textit{high}}}$: median of per-problem paired differences (not the difference of column medians) with bootstrap 95\% CI ($B{=}10{,}000$). $G$ values reported in Appendix~\ref{app:g-metric}. Profiling-subset values ($n{=}50$) in Table~\ref{tab:profiling-subset}.}
36	\label{tab:main-results}
37	\begin{tabular}{@{}llcccc@{}}
38	\toprule
39	$s$ & Strategy & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\Delta$\; [95\% CI] & $p_{\text{Bonf}}$ \\
40	\midrule
41	\multicolumn{6}{@{}l}{\textit{DeepSeek-R1-Distill-Qwen-7B ($n{=}496$)}} \\
42	0.15 & Importance & 0.003 & 0.357 & 0.39\; $[0.35,\; 0.44]$ & $< 10^{-10}$ \\
43	0.15 & Random     & 0.083 & 0.090 & 0.01\; $[-0.02,\; 0.04]$ & ns \\
44	\addlinespace
45	0.20 & Importance & 0.008 & 1.211 & 1.21\; $[1.11,\; 1.34]$ & $< 10^{-10}$ \\
46	0.20 & Random     & 0.270 & 0.357 & 0.03\; $[-0.01,\; 0.08]$ & ns \\
47	\addlinespace
48	0.25 & Importance & 0.021 & 3.971 & 3.99\; $[3.53,\; 4.36]$ & $< 10^{-10}$ \\
49	0.25 & Random     & 1.113 & 1.514 & 0.26\; $[0.13,\; 0.35]$ & $< 0.006$ \\
50	\addlinespace
51	0.30 & Importance & 0.038 & 8.456 & 8.48\; $[7.75,\; 9.69]$ & $< 10^{-10}$ \\
52	0.30 & Random     & 3.112 & 3.848 & 0.51\; $[0.26,\; 0.89]$ & $< 0.006$ \\
53	\midrule
54	\multicolumn{6}{@{}l}{\textit{Qwen2.5-7B-Instruct ($n{=}475$)}} \\
55	0.15 & Importance & $-$0.000$^{\ddagger}$ & 0.044 & 0.07\; $[0.05,\; 0.09]$ & $< 10^{-14}$ \\
56	0.15 & Random     & 0.094 & 0.097 & $-$0.01\; $[-0.04,\; 0.01]$ & ns \\
57	\addlinespace
58	0.20 & Importance & 0.000 & 0.275 & 0.31\; $[0.26,\; 0.36]$ & $< 10^{-14}$ \\
59	0.20 & Random     & 0.291 & 0.356 & 0.02\; $[-0.01,\; 0.07]$ & ns \\
60	\addlinespace
61	0.25 & Importance & 0.004 & 1.053 & 1.07\; $[0.98,\; 1.18]$ & $< 10^{-14}$ \\
62	0.25 & Random     & 1.108 & 1.769 & 0.39\; $[0.24,\; 0.55]$ & $< 10^{-10}$ \\
63	\addlinespace
64	0.30 & Importance & 0.014 & 3.208 & 3.16\; $[2.78,\; 3.56]$ & $< 10^{-14}$ \\
65	0.30 & Random     & 2.819 & 4.253 & 0.91\; $[0.61,\; 1.26]$ & $< 10^{-13}$ \\
66	\bottomrule
67	\multicolumn{6}{@{}p{0.92\textwidth}}{\footnotesize $^{\ddagger}$ Negative II at this sparsity reflects \texttt{bfloat16} numerical noise when the interaction effect approaches zero ($|\mathrm{II}| < 10^{-4}$). $\Delta{=}0.07$, $p{=}8.7 \times 10^{-15}$ supports $\mathrm{II}_{\textit{low}} > \mathrm{II}_{\textit{high}}$.}
68	\end{tabular}
69	\end{table*}
70	
71	\begin{figure*}[t]
72	\centering
73	\includegraphics[width=\textwidth]{fig1_ii_scatter.pdf}
74	\caption{Paired median difference $\Delta$ (primary metric) as a function of sparsity level $s$ for DeepSeek-R1-Distill-Qwen-7B ($n{=}496$, left) and Qwen2.5-7B-Instruct ($n{=}475$, right). Importance-based eviction (red) exhibits monotonically increasing $\Delta$ ($0.39$--$8.48$ for DeepSeek, $0.07$--$3.16$ for Qwen); random eviction (blue) remains near zero at low sparsity (ns) and shows weak effects at $s \geq 0.25$. Error bars show asymmetric bootstrap 95\% CIs. DeepSeek importance effects are ${\sim}2.7{\times}$ larger than Qwen, consistent with the training-paradigm contrast (\S\ref{sec:cross-model}). Significance: {*}{*}{*}\,$p_{\text{Bonf}} < 0.001$; {*}{*}\,$p_{\text{Bonf}} < 0.01$; ns\,$p_{\text{Bonf}} > 0.05$.}
75	\label{fig:hero}
76	\end{figure*}
77	
78	
79	\subsection{Phase-Strategy Crossover}
80	\label{sec:crossover}
81	
82	The phase-strategy crossover is model-dependent. For DeepSeek ($n{=}496$), a strategy ranking reversal emerges at all four sparsity levels: at $s{=}0.25$, importance-based eviction yields \emph{lower} II than random in the high-sparsity phase ($0.021$ vs.\ $1.113$) but \emph{higher} II in the low-sparsity phase ($3.971$ vs.\ $1.514$---a $2.6{\times}$ reversal; both $p < 10^{-4}$), with reversal magnitude ranging from $2.2{\times}$ to $4.0{\times}$ across $s \in \{0.15, 0.20, 0.25, 0.30\}$. Qwen does \emph{not} exhibit this crossover: importance-based eviction produces lower II than random in both phases (e.g., at $s{=}0.25$: high $0.004$ vs.\ $1.108$; low $1.053$ vs.\ $1.769$). This divergence suggests the crossover arises from model-specific attention head specialization patterns rather than a universal compound-sparsity property. Full crossover analysis appears in Appendix~\ref{app:crossover-details}.
83	
84	\subsection{Replication Across Training Paradigms}
85	\label{sec:cross-model}
86	
87	DeepSeek-R1-Distill-Qwen-7B (distillation-trained) and Qwen2.5-7B-Instruct (instruction-tuned) share the Qwen2 backbone but differ in training objective, providing a within-architecture-family comparison across training paradigms.
88	Qwen2.5-7B-Instruct ($n_{\text{eff}}{=}475$) reproduces the monotonic severity gradient: $\Delta$ increases from $0.07$ at $s{=}0.15$ to $3.16$ at $s{=}0.30$ (all Bonferroni-corrected $p < 10^{-14}$), paralleling DeepSeek at approximately one-quarter to one-sixth the magnitude. Both models yield strictly increasing median $\Delta$ trajectories (Jonckheere-Terpstra $z \geq 6.2$, $p < 10^{-9}$; see \S\ref{par:stats}). Random eviction on Qwen mirrors DeepSeek: non-significant at $s \leq 0.20$, becoming significant at $s \geq 0.25$ ($\Delta{=}0.39$--$0.91$; $p_{\text{Bonf}} < 10^{-10}$) but $2.7$--$3.5{\times}$ weaker than importance-based. A caveat: 45.2\% of Qwen problems yield null mid-phase segments due to low temporal autocorrelation ($r{=}0.718$ vs.\ $0.894$); this does not affect $\Delta$ (Appendix~\ref{app:qwen-null-rate}). Full tables in Appendix~\ref{app:cross-model-details}.
89	
90	\subsection{Cross-Architecture Validation}
91	\label{sec:cross-arch}
92	
93	Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, $n{=}250$, MATH-500) supports the generality of phase-modulated compound interaction beyond the Qwen2 architecture family. Under importance-based eviction, the paired median difference $\Delta$ rises monotonically from $0.050$ ($s{=}0.15$) to $0.695$ ($s{=}0.30$), with large effect sizes throughout ($d_z{=}0.81$--$1.15$; all $p < 10^{-29}$; Table~\ref{tab:llama-cross-arch}).
94	
95	A key architectural difference emerges in strategy specificity. On LLaMA, random eviction also exhibits significant phase gradients ($\Delta{=}0.025$--$0.271$; $d_z{=}0.41$--$0.46$; all $p < 10^{-12}$), unlike DeepSeek and Qwen where random is non-significant at $s \leq 0.20$. The importance/random $\Delta$ ratio is $2.0$--$2.6{\times}$ on LLaMA, substantially weaker than the $15$--$17{\times}$ observed on DeepSeek. Dose-response monotonicity holds for both strategies (all conditions monotonic). This indicates that the phase gradient itself is architecture-general, while the degree of strategy specificity is architecture-dependent, likely reflecting differences between GQA (LLaMA, 32 heads with 8 KV groups) and MHA (Qwen2, 28 heads) in how head pruning differentially disrupts importance scoring.
96	
97	Absolute interaction magnitudes are approximately $7$--$12{\times}$ smaller than Qwen2-family models at matched sparsity, consistent with architecture-specific attention head specialization patterns. Full per-condition breakdowns appear in Appendix~\ref{app:cross-arch}.
98	
99	\subsection{Scoring-Independent Control}
100	\label{sec:scoring-control}
101	
102	To distinguish whether the phase gradient arises from attention-score-based eviction dynamics or from token removal \emph{per se} under compound sparsity, we introduce a scoring-independent control: \emph{recency eviction}, which removes the oldest non-BOS positions regardless of attention scores. This eliminates the feedback loop between head pruning and importance scoring while maintaining identical compression ratios.
103	
104	On DeepSeek ($n{=}100$, MATH-500), recency eviction produces a negative or absent phase gradient across $s \in \{0.15, 0.25\}$: $\Delta{=}-0.013$ (CI spans zero, NS) at $s{=}0.15$ and $\Delta{=}-0.091$ (CI excludes zero, significantly \emph{negative}) at $s{=}0.25$. Both contrast sharply with importance-based eviction at matched sparsity ($\Delta{=}+0.39$ and $+3.99$; all $p < 10^{-69}$). At $s{=}0.30$, KV perplexity saturation (${>}10^5$) under recency eviction renders per-segment II numerically unreliable; the gradient estimate ($+0.112$) is non-significant (CI $[-0.01,\; +0.46]$, spans zero).
105	
106	This triangulation across three eviction strategies provides strong evidence for mechanism discrimination:
107	\begin{itemize}[nosep,leftmargin=*]
108	    \item \textbf{Importance}: super-additive compound interaction ($\mathrm{II} > 0$) with large positive phase gradient ($\Delta$: $+0.39$ to $+8.48$)
109	    \item \textbf{Random}: super-additive interaction ($\mathrm{II} > 0$) with near-zero phase gradient ($\Delta \approx 0$ at $s \leq 0.20$)
110	    \item \textbf{Recency}: sub-additive/zero interaction ($\mathrm{II} \leq 0$) with absent or negative phase gradient ($\Delta \leq 0$ at $s \leq 0.25$; NS at $s{=}0.30$)
111	\end{itemize}
112	The recency control rules out two alternative explanations: (1)~the phase gradient is not a segmentation artifact, since the same phase boundaries produce no positive gradient under recency eviction; (2)~the gradient is not an inherent property of removing tokens under compound sparsity, since recency removes the same fraction of tokens without producing phase-dependent severity. Phase-dependent compound severity is specifically driven by attention-score-based selection, as evidenced by its absence under both position-based and random controls.
113	
114	\subsection{Scale Analysis: Qwen2.5-14B}
115	\label{sec:scale-14b}
116	
117	To assess whether phase-modulated severity persists at larger model scale within the same architecture family, we evaluate Qwen2.5-14B-Instruct on MATH-500 ($n{=}500$) at $s \in \{0.15, 0.20, 0.25, 0.30\}$.
118	
119	\begin{table}[t]
120	\centering
121	\small
122	\caption{Median of per-problem paired severity differences ($\Delta$) under importance-based eviction on Qwen2.5-14B-Instruct (MATH-500). \textit{Results pending.}}
123	\label{tab:scale-14b}
124	\begin{tabular}{@{}lcccc@{}}
125	\toprule
126	Strategy & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
127	\midrule
128	Importance & --- & --- & --- & --- \\
129	Random     & --- & --- & --- & --- \\
130	\bottomrule
131	\end{tabular}
132	\end{table}
133	
134	%% PLACEHOLDER: Fill Table~\ref{tab:scale-14b} when c12 experiment completes.
135	%% Expected analysis: (1) whether 14B amplifies or attenuates severity relative to 7B,
136	%% (2) whether strategy specificity ratio is scale-invariant,
137	%% (3) comparison of phase segmentation thresholds at larger scale.
138	
139	\subsection{Cross-Benchmark Validation: GSM8K}
140	\label{sec:cross-benchmark}
141	
142	To assess task generalization, we evaluate both models on GSM8K ($n{=}50$) at $s \in \{0.15, 0.20, 0.25, 0.30\}$. On DeepSeek (clean data, no output truncation), importance-based eviction replicates the MATH-500 phase gradient across all four sparsity levels with a strict dose-response: $\Delta{=}0.24$ at $s{=}0.15$ rising to $4.68$ at $s{=}0.30$ (all $p \leq 0.0003$, Wilcoxon). Strategy specificity on GSM8K manifests as a \emph{qualitative} gap: importance-based eviction produces significant phase gradients while random eviction is non-significant across all conditions (CIs spanning zero).
143	
144	We interpret this attenuation as \emph{reasoning depth scaling}: strategy specificity scales with reasoning chain depth. MATH-500 (complex multi-step reasoning, strategy ratio $15$--$17{\times}$) produces stronger phase contrast than GSM8K (simpler arithmetic, ratio ${\sim}2{\times}$ from point estimates). Within MATH-500, longer traces exhibit higher strategy specificity (Spearman $\rho > 0$, $p < 0.02$), providing continuous correlational support. This scaling relationship is predictive: tasks with deeper reasoning chains should exhibit stronger strategy${\times}$phase interactions, because longer low-sparsity phases provide more opportunity for importance discrimination collapse to accumulate. Qwen GSM8K results are inconclusive due to generation truncation (\texttt{max\_new\_tokens}${=}$2047): while directional consistency holds at $s \geq 0.25$ ($\Delta{=}1.14$--$4.62$; $p < 10^{-4}$), absolute values and phase assignments are unreliable because all outputs hit the token limit. Full tables in Appendix~\ref{app:gsm8k}.
145	
146	\paragraph{GSM8K accuracy under compound sparsity.}
147	A power analysis on GSM8K ($n{=}50$) reveals a strategy-dependent asymmetry in downstream accuracy. Under random head removal, all 8 conditions (2 models $\times$ 4 sparsity levels) are non-significant (max $|d|{=}0.164$). Post-hoc power analysis indicates $n{=}50$ can detect effects of $d \geq 0.40$ ($\alpha{=}0.05$, power${=}0.80$); all random conditions showed $|d| \leq 0.164$, meaning the null results may reflect insufficient power rather than true absence of effect. Under importance-based pruning, Qwen exhibits a medium-sized accuracy degradation at $s \geq 0.25$ ($d \approx 0.63$, power ${>}\,0.99$), consistent with the PPL-based severity gradient observed on MATH-500. DeepSeek importance conditions exhibit a qualitative downward trend in accuracy but are excluded from parametric inference due to heavy-tailed distributions that violate test assumptions.
148	
149	\subsection{Cross-Benchmark Validation: GPQA Diamond}
150	\label{sec:cross-benchmark-gpqa}
151	
152	To assess generalization beyond mathematical reasoning, we evaluate both models on GPQA Diamond~\cite{rein-gpqa-2024} ($n{=}198$), a graduate-level science QA benchmark requiring multi-step reasoning across physics, chemistry, and biology.
153	
154	\begin{table}[t]
155	\centering
156	\small
157	\caption{Median of per-problem paired severity differences ($\Delta$) under importance-based eviction on GPQA Diamond. \textit{Results pending.}}
158	\label{tab:gpqa-results}
159	\begin{tabular}{@{}lcccc@{}}
160	\toprule
161	Model & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
162	\midrule
163	DeepSeek-R1-Distill-Qwen-7B & --- & --- & --- & --- \\
164	Qwen2.5-7B-Instruct         & --- & --- & --- & --- \\
165	\bottomrule
166	\end{tabular}
167	\end{table}
168	
169	%% PLACEHOLDER: Fill Table~\ref{tab:gpqa-results} when c11 experiment completes.
170	%% Expected analysis: (1) phase gradient direction consistency with MATH-500/GSM8K,
171	%% (2) strategy specificity comparison across task types (math vs. science reasoning),
172	%% (3) whether cognitive load modulation hypothesis extends to non-mathematical domains.
173	
174	\subsection{Statistical Validation}
175	\label{sec:stat-validation}
176	
177	Table~\ref{tab:cohens-d} reports the paired median difference $\Delta$ under importance-based eviction for both models at $n{=}496$/$475$. All eight conditions yield CIs excluding zero; within-importance dose-response $d_z$ (s015 vs.\ s030) is $0.94$ (DeepSeek) and $0.92$ (Qwen), both large effects. Importance-based eviction produces significantly larger phase gradients than random at all four sparsity levels ($p_{\text{Bonf}} \ll 10^{-10}$, Wilcoxon; permutation tests in Appendix~\ref{app:permutation-details}).
178	
179	\begin{table}[t]
180	\centering
181	\small
182	\caption{Median of paired differences ($\Delta_i = \mathrm{II}^{(i)}_{\textit{low}} - \mathrm{II}^{(i)}_{\textit{high}}$) under importance-based eviction with bootstrap 95\% CIs ($B{=}10{,}000$).}
183	\label{tab:cohens-d}
184	\begin{tabular}{@{}lcc@{}}
185	\toprule
186	$s$ & DS ($n{=}496$): $\widetilde{\Delta}$\; [95\% CI] & QW ($n{=}475$): $\widetilde{\Delta}$\; [95\% CI] \\
187	\midrule
188	0.15 & $0.39$\; $[0.35,\; 0.44]$ & $0.07$\; $[0.05,\; 0.09]$ \\
189	0.20 & $1.21$\; $[1.11,\; 1.34]$ & $0.31$\; $[0.26,\; 0.36]$ \\
190	0.25 & $3.99$\; $[3.53,\; 4.36]$ & $1.07$\; $[0.98,\; 1.18]$ \\
191	0.30 & $8.48$\; $[7.75,\; 9.69]$ & $3.16$\; $[2.78,\; 3.56]$ \\
192	\bottomrule
193	\multicolumn{3}{@{}l}{\footnotesize All $p_{\text{Bonf}} < 10^{-13}$. Within-importance $d_z$ (s015 vs.\ s030): DS $0.94$, QW $0.92$.}
194	\end{tabular}
195	\end{table}
196	
197	\subsection{Answer-Region Analysis}
198	\label{sec:answer-region}
199	
200	Across both models, 93.2\% of answer tokens (\verb|\boxed{}| markers) fall within the high-sparsity phase, where compound interaction is minimal. This non-uniformity identifies \emph{where} severity concentrates: reasoning-trace tokens show $5.7$--$43.5{\times}$ PPL degradation vs.\ $1.3$--$5.3{\times}$ for answer tokens (Wilcoxon $p < 0.001$). However, reasoning-trace degradation may produce \emph{silent reasoning errors}---correct formatting with corrupted intermediate logic \cite{lanham-2023-faithfulness, turpin-2023-biased-cot}---a failure mode that PPL detects but answer-level accuracy may miss.
201	
202	\subsection{Downstream Accuracy Validation}
203	\label{sec:accuracy-validation}
204	
205	To validate that the PPL-based severity gradient translates to downstream task performance, we evaluate MATH-500 accuracy under compound sparsity (importance-based eviction, \texttt{max\_new\_tokens}${=}$8192; Table~\ref{tab:accuracy}). Qwen's minimal truncation ($\leq 4\%$) provides a clean PPL-accuracy bridge.
206	Qwen ($n{=}100$; truncation $\leq 4\%$) shows gradual decline from $46\%$ (dense) through $s{=}0.25$ ($\delta{=}-4$ to $-13$\,pp) with a sharp cliff at $s{=}0.30$ ($19\%$, $\delta{=}-27$\,pp). DeepSeek ($n{=}50$) degrades more steeply ($74\% \to 4\%$) with a dual-regime structure: at $s \leq 0.20$, degradation is primarily truncation-driven (non-truncated accuracy remains $68$--$71\%$ at $s{=}0.15$--$0.20$ vs.\ $88\%$ dense); at $s \geq 0.25$, both truncation and reasoning quality collapse simultaneously (Appendix~\ref{app:accuracy-details}).
207	The two models exhibit distinct failure modes reflecting training-paradigm dependence: DeepSeek failures are \emph{truncation-dominated} (truncation $16\% \to 76\%$), while Qwen failures are \emph{wrong-answer-dominated} (truncation $\leq 4\%$, reasoning quality degrades directly). Given minimal truncation, Qwen accuracy data provide a reliable PPL-accuracy bridge; DeepSeek accuracy results, confounded by truncation rates of $16\%$--$76\%$, should be interpreted as qualitative observations only.
208	
209	We provide a correlational mechanistic analysis in terms of importance discrimination collapse in \S\ref{sec:analysis}.
210	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a05766fb-ed23-40b1-b54d-e9151b58b766",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "a376754b-75e5-4b97-9f94-f65dbddc41df",
  "sourceToolAssistantUUID": "a05766fb-ed23-40b1-b54d-e9151b58b766",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-17T02:05:29.537Z_

<details open><summary>🔧 Tool call — Read · `toolu_01ArtQim1ToGUveS1oWUcnnb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a376754b-75e5-4b97-9f94-f65dbddc41df",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdT1YdCxMwaRSaxGUR",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fc5f4578-7d2e-48a9-b175-0482c5130683",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPkeL62ab4i8bSwwrc8HaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3102,
      "cache_read_input_tokens": 20428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3102,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 68,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-17T02:05:29.547Z_

<details><summary>↩ Tool result · `toolu_01ArtQim1ToGUveS1oWUcnnb`</summary>

```text
1	\section{Importance Discrimination Collapse under Compound Sparsity}
2	\label{sec:analysis}
3	
4	The mechanisms discussed here are \emph{correlational diagnostics} that illuminate but do not fully explain the $15$--$17{\times}$ severity divergence between strategies. Both strategies exhibit near-identical Gini drops ($<10\%$ difference), yet severity diverges by $15$--$17{\times}$---an order-of-magnitude mismatch indicating that aggregate concentration collapse alone is insufficient. The critical differentiator is \emph{structural specificity} of importance-based pruning, which systematically removes high-attention-score heads (\S\ref{sec:discrimination-collapse-main}).
5	
6	\subsection{Importance Discrimination Collapse}
7	\label{sec:discrimination-collapse-main}
8	
9	Head pruning systematically reduces the discriminative power of cumulative importance scores, providing a correlational diagnostic for the phase-strategy interaction (causal attribution requires future intervention experiments). The Gini coefficient decreases by $0.030$--$0.081$ (DeepSeek, $6$--$17\%$ relative to dense baseline) and $0.010$--$0.020$ (Qwen, $2$--$4\%$) after pruning, with consistent negative deltas in all 16 conditions (Appendix~\ref{app:analysis}, Table~\ref{tab:discrimination-metrics-full}). Random eviction shows near-identical Gini drops (e.g., DeepSeek $s{=}0.25$: $-0.065$ vs.\ $-0.060$), indicating that collapse is a consequence of head pruning \emph{per se}. Yet importance-based severity is $15$--$17{\times}$ larger---the amplification arises because importance-based eviction \emph{depends on} the very scores that pruning degrades.
10	
11	This pattern---\emph{importance discrimination collapse}---reflects eviction degenerating into noise-sensitive selection as score distributions approach uniformity. The effect is phase-dependent: per-phase Gini analysis shows that the low-sparsity phase exhibits the largest Gini delta at every sparsity level on both models, with monotonically increasing magnitude (DeepSeek: $-0.016$ at $s{=}0.15$, $-0.021$ at $s{=}0.20$, $-0.031$ at $s{=}0.25$, $-0.037$ at $s{=}0.30$; Qwen: $-0.017$, $-0.020$, $-0.029$, $-0.035$). Low-sparsity phases have broadly distributed attention where collapse has maximum impact; high-sparsity phases preserve concentration. \cite{hies-2025} report this collapse under single-axis pruning; we extend it to the compound setting.
12	
13	To provide quantitative evidence for structural specificity, we analyzed the attention Gini coefficients of importance-pruned versus retained heads. Importance pruning (Frobenius norm criterion) systematically removes heads with lower Gini coefficients---i.e., heads with more dispersed attention patterns (Mann-Whitney $U$, $p < 10^{-28}$; rank-biserial $r = 0.62$--$0.76$ across all 8 conditions). Random pruning, by contrast, samples heads with Gini indistinguishable from the population mean (200-trial verification). The Frobenius norm and Gini share sensitivity to attention magnitude; the large effect size ($r > 0.6$) nonetheless indicates strong structural separation.
14	
15	We note that this evidence is correlational; causal validation through controlled manipulation of importance-score entropy is an important direction for future work.
16	
17	\subsection{Entropy Redistribution: A Model-Dependent Secondary Effect}
18	\label{sec:entropy-redistribution-main}
19	
20	As a supplementary observation, head pruning also redistributes the attention entropy of surviving heads on DeepSeek ($\Delta\mathcal{H} \in [-0.047, -0.040]$; Appendix~\ref{app:analysis}, Table~\ref{tab:entropy-deltas}). However, entropy redistribution shows model-dependent behavior---the direction reverses on Qwen at $s{=}0.25$ ($\Delta\mathcal{H} = +0.045$)---replicating in only 2/4 Qwen conditions and thus only partially consistent. Importance discrimination collapse remains the more robust, model-independent correlate, though it partially accounts for rather than fully explains the severity divergence.
21	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fc5f4578-7d2e-48a9-b175-0482c5130683",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "e910c90c-6f3e-4504-b873-cd291adbfd0f",
  "sourceToolAssistantUUID": "fc5f4578-7d2e-48a9-b175-0482c5130683",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-17T02:05:29.948Z_

<details open><summary>🔧 Tool call — Read · `toolu_012LWp4pifuXcidHp1nBCjdn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e910c90c-6f3e-4504-b873-cd291adbfd0f",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdT1YdCxMwaRSaxGUR",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8ce2ef92-229a-4ea4-b311-64055e0c2141",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NPkeL62ab4i8bSwwrc8HaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3102,
      "cache_read_input_tokens": 20428,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3102,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 68,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-17T02:05:29.976Z_

<details><summary>↩ Tool result · `toolu_012LWp4pifuXcidHp1nBCjdn`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Long-context language models place acute pressure on the key--value (KV) cache, which grows linearly with sequence length \cite{kwon-sosp2023, pope-mlsys2023}.
5	Two complementary responses---\emph{attention head pruning} \cite{voita-acl2019, michel-neurips2019} and \emph{KV cache eviction} \cite{snapkv-neurips2024, adakv-neurips2025}---are increasingly deployed simultaneously as \emph{compound sparsity}, but the resulting quality degradation is often super-additive \cite{spark-aaai2026, slim-icml2025}. Recent evaluations show that reasoning capabilities degrade disproportionately under compound compression \cite{unicomp-2026}, and that per-dimension safe zones intersect to form a smaller joint safe region \cite{phase-transition-compression-2026}.
6	
7	Prior work treats compound interaction magnitude as roughly constant across generation \cite{spark-aaai2026, unicomp-2026}, despite evidence that pruning sensitivity depends on representational phase \cite{decision-repr-transition-2026} and that no single sparse attention strategy dominates across generation stages \cite{sparse-frontier-2025}.
8	This assumption is problematic for reasoning models, whose chain-of-thought generations \cite{wei-neurips2022-cot} alternate between broadly distributed attention (exploratory reasoning) and sharply concentrated attention (structured computation) \cite{thinkv-iclr2026}.
9	Phase-aware methods like ThinKV \cite{thinkv-iclr2026} apply different KV strategies per phase but without considering compound interaction, while importance-based eviction itself faces challenges from score collapse \cite{hies-2025}, greedy bias \cite{greedy-bias-kvcache-2026}, and temporal dynamics \cite{lethe-aaai2026}. These methods each optimize a single pruning axis; we characterize the interaction when multiple axes are composed.
10	If compound severity varies across these phases, a uniform sparsity budget may be safe in one phase yet destructive in another.
11	
12	We find that compound sparsity severity is an emergent property of the three-way interaction among eviction strategy, reasoning phase, and sparsity level.
13	Under importance-based KV cache eviction, the Interaction Index---a measure of super-additive degradation---concentrates in low-sparsity reasoning phases and is largely absent in high-sparsity phases.
14	On DeepSeek-R1-Distill-Qwen-7B (MATH-500), the paired median difference rises from $0.39$ at $s{=}0.15$ to $8.48$ at $s{=}0.30$ (Spearman $\rho{=}1.0$; all Bonferroni-corrected $p < 0.005$).
15	The pattern replicates on Qwen2.5-7B-Instruct ($\Delta$: $0.07 \to 3.16$; all $p < 0.005$), with cross-architecture support from DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, $n{=}250$), where the importance phase gradient replicates with large effect sizes ($d_z{=}0.81$--$1.15$; all $p < 10^{-29}$) despite reduced strategy specificity ($2.0$--$2.6{\times}$ vs.\ $15$--$17{\times}$ on Qwen2-family models).
16	Random eviction develops a detectable phase gradient only above $s \approx 0.20$, at $2.7$--$17{\times}$ smaller magnitude than importance-based (where both strategies reach significance at $s \geq 0.25$), supporting that the dominant gradient is strategy-specific.
17	A scoring-independent control (recency eviction, which removes the oldest positions without attention scores) produces no phase gradient ($\Delta{=}-0.003$, CI spans zero), ruling out segmentation artifact and confirming that the interaction is specifically driven by attention-score-based selection (\S\ref{sec:scoring-control}).
18	Cross-benchmark validation on GSM8K reveals consistent phase gradient direction: DeepSeek replicates the monotonic dose-response ($\Delta$: $0.24 \to 4.68$; all $p \leq 0.0003$), while Qwen shows directional consistency at $s \geq 0.25$ but is inconclusive due to generation truncation (\S\ref{sec:cross-benchmark}). Strategy specificity attenuates on GSM8K relative to MATH-500, indicating that phase modulation generalizes but its magnitude is task-dependent.
19	
20	Per-phase Gini analysis identifies \emph{importance discrimination collapse}---the degeneration of head importance scores toward uniformity under compound stress---as a correlational diagnostic of this phase--strategy divergence. Both strategies exhibit consistent Gini drops across all tested conditions, yet severity diverges by $2.7$--$17{\times}$, implicating the structural specificity of importance-based pruning as the key differentiator.
21	
22	Beyond individual findings, we contribute a \emph{phase-gated analysis framework} that decomposes compound severity by reasoning phase and eviction strategy, transforming a scalar interaction metric into a structured diagnostic. This framework---combining the Interaction Index with attention-sparsity-based phase segmentation---reveals structure in compound degradation that aggregate metrics miss, and provides practitioners with a principled basis for phase-aware sparsity allocation.
23	
24	Our contributions:
25	\begin{enumerate}[nosep,leftmargin=*]
26	    \item We characterize a \textbf{phase-modulated compound severity gradient}: importance-based eviction exhibits a monotonic dose-response ($\rho{=}1.0$; $\Delta$: $0.39 \to 8.48$) with a phase gradient $2.7$--$17{\times}$ larger than random eviction where both strategies are significant ($s \geq 0.25$) on MATH-500; the gradient direction is consistent on GSM8K, while strategy specificity attenuates (\S\ref{sec:cross-benchmark}).
27	    \item We replicate the pattern \textbf{across training paradigms and architectures}: within-architecture replication on Qwen2.5-7B-Instruct (same Qwen2 backbone, instruction-tuned; $\Delta$: $0.07 \to 3.16$; $\rho{=}1.0$) and cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM; $n{=}250$; importance phase gradient $d_z{=}0.81$--$1.15$, all $p < 10^{-29}$; strategy specificity reduced to $2.0$--$2.6{\times}$, architecture-dependent; \S\ref{sec:cross-arch}).
28	    \item We provide a \textbf{scoring-independent control}: recency eviction (position-only, no attention scores) under identical compound sparsity produces no phase gradient ($\Delta \approx 0$, CI spans zero), ruling out segmentation artifact and establishing that phase-dependent severity is specifically driven by attention-score-based selection (\S\ref{sec:scoring-control}).
29	    \item We identify \textbf{importance discrimination collapse} via per-phase Gini analysis as a correlational diagnostic: consistent collapse across models and strategies, with the structural specificity of importance-based pruning corresponding to the severity divergence (\S\ref{sec:analysis}).
30	    \item We validate the phase gradient on \textbf{GSM8K} for both models, finding that phase modulation is benchmark-robust while strategy specificity is task-dependent (\S\ref{sec:cross-benchmark}).
31	\end{enumerate}
32	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8ce2ef92-229a-4ea4-b311-64055e0c2141",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "623deecb-0d42-4ebd-b97d-71e64b03e0ba",
  "sourceToolAssistantUUID": "8ce2ef92-229a-4ea4-b311-64055e0c2141",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-17T02:05:34.845Z_

<details open><summary>🔧 Tool call — Read · `toolu_019pu1VJL6htsgVsk2ZcnA4Z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "623deecb-0d42-4ebd-b97d-71e64b03e0ba",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdmBSRsdjZkE2Q44Xv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9fbf7ad7-0c78-4db0-995d-128ce7c4437d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BMSq9W9XGo4JH4CAyLnSWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11568,
      "cache_read_input_tokens": 23530,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 11568,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 35,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 24 · 2026-05-17T02:05:34.851Z_

<details><summary>↩ Tool result · `toolu_019pu1VJL6htsgVsk2ZcnA4Z`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Implications for deployment.}
5	A uniform compression budget implicitly accepts order-of-magnitude severity penalties during low-sparsity reasoning phases. Pilot evaluation ($n{=}30$, $s{=}0.25$; Appendix~\ref{app:pilot-mitigation}) achieved 18\% oracle recovery (95\% CI: $[-39\%, 45.8\%]$), falling below the pre-registered 30\% gate; the CI spans zero, indicating no statistically distinguishable improvement. Effective phase-aware allocation likely requires finer phase boundary estimation than current proxies provide. Additional mechanisms (e.g., strategy switching, adaptive thresholding) warrant investigation. We hypothesize that phase-modulated severity may extend to alternative attention-mass-based scoring methods (H$_2$O \cite{h2o-neurips2023}, SnapKV \cite{snapkv-neurips2024}, PyramidKV \cite{pyramidkv-colm2025}), which remains an open question for future work. Extended discussion in Appendix~\ref{app:extended-discussion}.
6	
7	\paragraph{Reasoning depth scaling and architecture dependence.}
8	Strategy specificity is not a fixed property but varies along at least two axes. First, it scales with reasoning chain depth: MATH-500 ($15$--$17{\times}$) $>$ GSM8K (${\sim}2{\times}$ point-estimate ratio; random non-significant at $n{=}50$), with within-MATH-500 correlational support (Spearman $\rho > 0$, $p < 0.02$ between trace length and specificity). Second, it is architecture-dependent: LlamaForCausalLM exhibits significant random phase gradients ($d_z{=}0.41$--$0.46$), reducing the importance/random ratio to $2.0$--$2.6{\times}$ compared with $15$--$17{\times}$ on DeepSeek (Qwen2-based). This suggests that the degree to which random eviction is phase-insensitive depends on architectural details of the attention implementation. The depth-scaling pattern is consistent with the discrimination collapse mechanism: longer low-sparsity phases provide more tokens over which pruning-degraded importance scores accumulate errors, amplifying the gap between importance-based and random eviction. The practical implication holds regardless of architecture: as models generate longer reasoning chains (a trend driven by test-time compute scaling~\cite{snell-2024-scaling-test-time}), the penalty for naive compound compression grows superlinearly, though the relative advantage of strategy-aware allocation varies by model family.
9	
10	\paragraph{Diagnostic framework value.}
11	While we do not propose a new compression method, the phase-gated analysis framework has direct engineering utility: (1)~the Interaction Index can serve as a per-phase evaluation metric for assessing the phase robustness of any new compound compression scheme; (2)~the dose-response curves (Figure~\ref{fig:hero}) provide target operating points for phase-aware controllers, e.g., maintaining $s \leq 0.20$ during low-sparsity phases to keep $\Delta < 1.5$; (3)~the strategy specificity finding carries a concrete engineering implication: importance-based eviction under compound sparsity requires phase-aware protection that random eviction does not, because the interaction is structurally coupled to the scoring mechanism rather than to compression magnitude alone.
12	
13	\paragraph{Recency control as methodological contribution.}
14	The use of recency-based eviction as a scoring-independent control (\S\ref{sec:scoring-control}) provides a principled falsification test that, to our knowledge, has no precedent in the KV cache compression literature. Prior work employs recency eviction (StreamingLLM~\cite{streamingllm-iclr2024}) or H$_2$O scoring~\cite{h2o-neurips2023} as performance baselines, but not as controls for isolating the contribution of the scoring mechanism itself. The null result ($d_z{=}0.083$, NS at $s{=}0.15$, $n{=}100$) confirms that the phase gradient is attention-score-specific rather than an artifact of phase segmentation or positional structure, strengthening the causal interpretation of strategy specificity as a property of score-dependent token selection.
15	
16	\paragraph{Evidential status: mechanism discrimination, not causal proof.}
17	The triangulation across importance, random, and recency eviction constitutes \emph{mechanism discrimination}: we identify attention-score-based selection as the specific mediating pathway for phase-dependent severity, by showing the gradient's presence under score-based eviction and absence under score-independent controls. This is discriminative evidence, not intervention-based causal proof. Full causal demonstration would require directly manipulating score quality (e.g., injecting calibrated noise into attention scores before eviction) and observing a corresponding change in gradient magnitude, which we leave to future work. Our contribution is identifying the mediating pathway with sufficient specificity to guide system design: practitioners can use the finding that score-independent eviction eliminates the phase gradient to inform compression strategy selection, regardless of whether the underlying mechanism is fully causally resolved.
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9fbf7ad7-0c78-4db0-995d-128ce7c4437d",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "b1fe830e-3dce-4dec-bc21-999efa219d89",
  "sourceToolAssistantUUID": "9fbf7ad7-0c78-4db0-995d-128ce7c4437d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-17T02:05:35.396Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AjdQ3kgZqriDKyo9s4xovA`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/background.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b1fe830e-3dce-4dec-bc21-999efa219d89",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdmBSRsdjZkE2Q44Xv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "584617cf-dc38-4230-9fd0-fe8c126e841c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BMSq9W9XGo4JH4CAyLnSWV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11568,
      "cache_read_input_tokens": 23530,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 11568,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 35,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-17T02:05:35.403Z_

<details><summary>↩ Tool result · `toolu_01AjdQ3kgZqriDKyo9s4xovA`</summary>

```text
1	% Section 3: Background and Problem Setup
2	% Note: eq:ii and eq:gradient are the canonical definitions.
3	% Full formulation details in Appendix (app:formulation-details).
4	
5	\section{Background and Problem Setup}
6	\label{sec:background}
7	
8	We formalize compound sparsity, define the Interaction Index, and introduce phase segmentation. Full mathematical details appear in Appendix~\ref{app:formulation-details}.
9	
10	\paragraph{Compound sparsity.}
11	Let $s \in (0,1)$ denote a unified sparsity budget. \emph{Attention head pruning} removes the bottom-$s$ fraction of heads per layer by Frobenius norm importance \cite{voita-acl2019, michel-neurips2019}. \emph{KV cache eviction} removes the bottom-$s$ fraction of token positions from the cache. We compare two strategies: \emph{importance-based}, which scores positions by position-normalized cumulative attention mass (Eq.~\ref{eq:kv-importance} in Appendix~\ref{app:formulation-details}), and \emph{random}, which evicts uniformly at random \cite{nacl-acl2024}. Applying both simultaneously yields \emph{compound sparsity}; the two axes interact because head pruning alters the importance ranking used for eviction \cite{spark-aaai2026}. Existing joint-pruning approaches such as GRASPrune \cite{graspune-acl2026} learn global budget-constrained gates but treat decisions as static across generation.
12	
13	\paragraph{Interaction Index.}
14	For a text segment, let $\text{PPL}_c$ denote perplexity under condition $c \in \{d, a, k, b\}$ (dense, attention-only, KV-only, compound). Normalizing by the dense baseline yields $r_c = \text{PPL}_c / \text{PPL}_d$, and:
15	\begin{equation}
16	    \mathrm{II} = r_b - r_a - r_k + 1.
17	    \label{eq:ii}
18	\end{equation}
19	$\mathrm{II} > 0$ indicates super-additive degradation; $\mathrm{II} = 0$ indicates additive independence. We adopt the additive null as primary: it assumes $r_b = r_a + r_k - 1$ (compound loss equals sum of individual losses), the most conservative independence assumption. Although the two axes are mechanistically linked (\S\ref{sec:analysis}), rejection ($\mathrm{II} > 0$) establishes super-additivity regardless of null specification. Appendix~\ref{app:multiplicative-null} reports parallel results under the multiplicative null ($r_b = r_a \cdot r_k$); the phase-severity gradient is preserved ($G_{\times}{=}21$--$64{\times}$), supporting null-choice invariance. The II distribution is heavily right-skewed; we report medians throughout.
20	
21	\paragraph{Severity gradient.}
22	To capture phase variation, the per-problem \emph{amplification ratio} is:
23	\begin{equation}
24	    G^{(i)} = \frac{\mathrm{II}^{(i)}_{\,\textit{low}}}{\mathrm{II}^{(i)}_{\,\textit{high}}},
25	    \label{eq:gradient}
26	\end{equation}
27	where $\mathrm{II}^{(i)}_{\,\textit{low/high}}$ is the interaction index in the low/high-sparsity phase for problem $i$. We report $G = \widetilde{G^{(i)}}$, the median across problems, with bootstrap CIs. We use the median of per-problem ratios (not the ratio of medians) to preserve per-problem pairing; see Appendix~\ref{app:profiling-subset} for comparison. $G$ serves as an auxiliary descriptive ratio that illustrates the degree of phase concentration; the primary statistical evidence for the severity gradient rests on $\Delta$ and paired Wilcoxon tests (\S\ref{sec:phase-amplification}).
28	
29	\paragraph{Phase segmentation.}
30	\label{par:phase-segmentation}
31	Inspired by ThinKV's phase-aware perspective on reasoning-time compression~\cite{thinkv-iclr2026}, each generated sequence is partitioned into three phases (low-, mid-, high-sparsity) by tercile boundaries of per-position attention sparsity, using a quantile-based segmentation rather than explicit reasoning delimiters (e.g., \texttt{&lt;think>} tokens). Low-sparsity phases correspond to broadly distributed attention (exploratory reasoning); high-sparsity phases to concentrated attention (structured computation). We note that this segmentation is an \emph{operationalization choice}: attention sparsity serves as a continuous proxy for reasoning phase rather than a theoretically grounded boundary. We validate robustness to segmentation granularity (tercile/quartile/quintile; Appendix~\ref{app:seg-robust}) and minimum phase length (Appendix~\ref{app:mpl-sensitivity}). Validation against DeepSeek's explicit \texttt{&lt;think>} markers using adaptive per-sequence quantile segmentation yields substantial agreement ($\kappa{=}0.88$, AUC-ROC${=}0.98$; $n{=}48$; Appendix~\ref{app:think-validation}). Importantly, phases reflect genuine computational mode differences even under the dense (uncompressed) baseline: per-phase dense perplexity increases monotonically from high ($1.10$) through mid ($1.17$) to low ($1.18$), confirming that low-sparsity phases correspond to inherently harder computation; the phase gradient in compound severity (\S\ref{sec:results}) thus amplifies a pre-existing computational asymmetry rather than creating one. Details in Appendix~\ref{app:formulation-details}.
32	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "584617cf-dc38-4230-9fd0-fe8c126e841c",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "2446bfb4-e0b8-4720-9f7f-84a4aa9a9e73",
  "sourceToolAssistantUUID": "584617cf-dc38-4230-9fd0-fe8c126e841c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-17T02:05:35.936Z_

<details open><summary>🔧 Tool call — Read · `toolu_01M6FRHBp24HDTAGMvL6Up3U`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2446bfb4-e0b8-4720-9f7f-84a4aa9a9e73",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KdmBSRsdjZkE2Q44Xv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6fd220c1-62e4-4c6c-93ba-57cfa3cad5f8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BMSq9W9XGo4JH4CAyLnSWV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11568,
      "cache_read_input_tokens": 23530,
      "output_tokens": 242,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 11568
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 242,
          "cache_read_input_tokens": 23530,
          "cache_creation_input_tokens": 11568,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 11568,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-17T02:05:35.942Z_

<details><summary>↩ Tool result · `toolu_01M6FRHBp24HDTAGMvL6Up3U`</summary>

```text
1	\paragraph{Model scale and architecture.}
2	Our primary experiments span 7--14B parameters: DeepSeek-R1-Distill-Qwen-7B, Qwen2.5-7B-Instruct, and Qwen2.5-14B-Instruct (\S\ref{sec:scale-14b}). Whether the phase-modulated severity patterns persist, amplify, or attenuate at substantially larger scales (e.g., 70B) remains untested. Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, \S\ref{sec:cross-arch}, Appendix~\ref{app:cross-arch}) supports that the phase gradient extends beyond the Qwen2 architecture ($n{=}250$, all 8 conditions significant; importance $d_z{=}0.81$--$1.15$), but strategy specificity is substantially weaker ($2.0$--$2.6{\times}$ vs.\ $15$--$17{\times}$ on DeepSeek) because random eviction also exhibits significant phase gradients on LLaMA ($d_z{=}0.41$--$0.46$). This architecture-dependent strategy specificity indicates that the degree of strategy${\times}$phase interaction, not just absolute magnitude, varies across attention implementations. The pattern has been tested on two architecture families (Qwen2ForCausalLM, LlamaForCausalLM) at two scale points (7B, 14B); comprehensive validation across more diverse architectures (e.g., Mistral, multi-latent attention) and larger scales is needed for full generalization claims.
3	
4	\paragraph{Task coverage.}
5	We evaluate on three benchmarks spanning mathematical and scientific reasoning: MATH-500 (primary), GSM8K (\S\ref{sec:cross-benchmark}), and GPQA Diamond (\S\ref{sec:cross-benchmark-gpqa}). Cross-benchmark validation on GSM8K supports the phase gradient direction under importance-based eviction but reveals that random eviction is non-significant (CIs spanning zero), precluding meaningful ratio computation. On MATH-500, strategy specificity is quantifiable ($15$--$17{\times}$); on GSM8K, it manifests as a qualitative gap (significant vs.\ non-significant). This suggests that the phase-strategy interaction is robust in direction but task-dependent in form: complex reasoning (MATH-500) produces quantitative strategy contrast while simpler arithmetic (GSM8K) produces qualitative separation. Qwen GSM8K outputs were truncated at \texttt{max\_new\_tokens}${=}$2047, so Qwen GSM8K absolute values carry this limitation; DeepSeek GSM8K data is untruncated. Our task-complexity explanation for specificity attenuation (lower cognitive load $\to$ more uniform attention $\to$ reduced strategy sensitivity) is supported by within-benchmark correlational evidence but requires validation across a broader range of task complexities; whether different reasoning tasks (code generation, multi-hop QA) produce yet different attenuation profiles remains open. Random eviction on GSM8K exhibits numerical instability (extreme outlier II values), likely a systematic interaction between reduced-precision arithmetic and score-independent eviction.
6	
7	\paragraph{Eviction strategy scope and H$_2$O confound.}
8	Our importance-based eviction uses cumulative attention scores (H$_2$O-style scoring~\cite{h2o-neurips2023}, Eq.~\ref{eq:kv-importance}), which creates an inherent confound: head pruning alters the attention distribution from which importance scores are computed, and eviction then operates on these degraded scores. The compound interaction patterns we report, including importance discrimination collapse and the phase-strategy crossover, may be partly attributable to this circular dependency rather than to compound sparsity \emph{per se}. Other attention-mass-based methods (SnapKV~\cite{snapkv-neurips2024}, PyramidKV~\cite{pyramidkv-colm2025}) share the same scoring basis and would likely exhibit a similar confound. The recency control (\S\ref{sec:scoring-control}) partially addresses this by confirming that the phase gradient requires the attention-score pathway ($d_z{=}0.083$, NS under recency eviction vs.\ $d_z{=}0.574$ under importance at matched $s{=}0.15$). However, recency eviction was tested at a single sparsity level ($n{=}100$ pilot, vs.\ $n{=}500$ for importance); comprehensive evaluation across sparsity levels, and testing of other score-independent strategies (e.g., learned eviction policies), remains an important next step. The qualitative conclusion (gradient absence, CI spanning zero) is robust to sample size: post-hoc power analysis indicates $n{=}100$ provides power $> 0.85$ to detect effects of $d_z \geq 0.30$ at $\alpha{=}0.05$, well below the observed importance effect ($d_z{=}0.57$).
9	
10	\paragraph{Symmetric sparsity assumption.}
11	Our analysis applies symmetric sparsity levels: the same fraction $s$ is used for both head pruning and KV cache eviction. A preliminary spot check under asymmetric allocation (Appendix~\ref{app:asymmetric-robustness}) supports that the phase gradient is robust to head/KV budget ratios, but systematic characterization of the full asymmetric interaction surface remains future work.
12	
13	\paragraph{Phase segmentation validation.}
14	The \texttt{&lt;think>} token validation of sparsity-based phase segmentation (\S\ref{sec:background}, Appendix~\ref{app:think-validation}) is limited to a single model (DeepSeek-R1-Distill-Qwen-7B) on a single benchmark (GSM8K, $n{=}48$). Qwen2.5-7B-Instruct does not generate explicit reasoning markers, precluding the same validation. Whether the high agreement ($\kappa{=}0.88$) generalizes to other models with explicit CoT delimiters, or to non-mathematical reasoning tasks, remains open.
15	
16	\paragraph{Mechanism.}
17	Importance discrimination collapse is a correlational diagnostic observation, not a causal explanation: both strategies exhibit near-identical Gini drops yet severity diverges by $15$--$17{\times}$, indicating that Gini collapse alone is insufficient. Causal validation through controlled entropy manipulation is needed. The entropy redistribution component replicates on only 2/4 Qwen conditions, suggesting model-specific factors.
18	
19	\paragraph{Perplexity vs.\ accuracy.}
20	Our primary severity metric is perplexity-based (II), chosen because its per-token granularity enables the phase-level decomposition central to our analysis; accuracy is binary per-problem and cannot be meaningfully decomposed by reasoning phase. Accuracy validation on MATH-500 (\S\ref{sec:accuracy-validation}, Appendix~\ref{app:accuracy-details}) shows gradual decline through $s{=}0.25$ ($\delta{=}-4$ to $-13$\,pp) followed by a sharp cliff at $s{=}0.30$ ($\delta{=}-27$\,pp) for Qwen ($n{=}100$, truncation $\leq 4\%$). DeepSeek accuracy deltas are confounded by rising truncation ($16\%$ to $76\%$); non-truncated analysis reveals a dual-regime structure but is limited by small surviving samples at high sparsity. Comprehensive accuracy evaluation across benchmarks remains an important next step.
21	
22	\paragraph{Sparsity range.}
23	Our experiments span $s \in \{0.15, 0.20, 0.25, 0.30\}$, sufficient to establish monotonicity at the tested levels (JT test $p \ll 10^{-10}$) but insufficient to characterize the functional form of the auxiliary ratio $G(s)$ or identify potential saturation thresholds. More extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics. We do not report inference throughput or latency measurements, which are necessary for a complete deployment analysis but orthogonal to our severity characterization. Extended limitations in Appendix~\ref{app:limitations}.
24	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6fd220c1-62e4-4c6c-93ba-57cfa3cad5f8",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "ac7853a8-cd22-49c1-8cc9-31aa0bd9c31b",
  "sourceToolAssistantUUID": "6fd220c1-62e4-4c6c-93ba-57cfa3cad5f8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-17T02:05:40.000Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BjpamXFsqENkNtXHFHBAnL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ac7853a8-cd22-49c1-8cc9-31aa0bd9c31b",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KeCQVSW5AZaTvwvPsA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3be191e9-7ade-46b3-8761-463aee140cfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HcBBtcm1D8z2onERbMCRww",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5143,
      "cache_read_input_tokens": 35098,
      "output_tokens": 93,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5143
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 93,
          "cache_read_input_tokens": 35098,
          "cache_creation_input_tokens": 5143,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5143,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-17T02:05:40.006Z_

<details><summary>↩ Tool result · `toolu_01BjpamXFsqENkNtXHFHBAnL`</summary>

```text
1	\section{Compound Sparsity Formulation}
2	\label{app:formulation-details}
3	
4	\paragraph{Attention head pruning.}
5	Heads are ranked by Frobenius norm importance $w_j^{(\ell)} = \|\mathbf{A}_j^{(\ell)}\|_F$ \cite{voita-acl2019, michel-neurips2019}; a binary mask $m_j^{(\ell)} \in \{0,1\}$ retains the top-$(1{-}s)\cdot H$ heads:
6	\begin{equation}
7	    \tilde{\mathbf{o}}_j^{(\ell)} = m_j^{(\ell)} \cdot \mathbf{o}_j^{(\ell)}.
8	    \label{eq:head-mask}
9	\end{equation}
10	
11	\paragraph{KV cache eviction.}
12	A position mask $\mathbf{m}_k \in \{0,1\}^T$ retains the top-$(1{-}s)\cdot T$ positions (BOS always preserved):
13	\begin{equation}
14	    \tilde{a}_{ij} = a_{ij} \cdot m_{k,j}, \quad \forall\, i, j.
15	    \label{eq:kv-mask}
16	\end{equation}
17	Under importance-based eviction, each position $j$ is scored by its cumulative attention mass with position normalization:
18	\begin{equation}
19	    \mathrm{imp}(j) = \frac{\sum_{\ell, h, i} a_{ij}^{(\ell,h)}}{T - j},
20	    \label{eq:kv-importance}
21	\end{equation}
22	where the denominator compensates for causal bias---earlier positions are attended to by more queries \cite{thinkv-iclr2026, defensivekv-iclr2026}. Under random eviction, positions (excluding BOS) are evicted uniformly at random.
23	
24	\paragraph{Compound sparsity.}
25	Applying both mechanisms simultaneously yields compound sparsity. The two axes interact: head pruning redistributes attention mass, altering the importance ranking for KV eviction. Prior work \cite{spark-aaai2026} reports super-additive joint effects but treats interaction magnitude as a fixed property of $s$.
26	
27	\paragraph{Attention sparsity metric.}
28	For each query position $i$ and head $h$, we compute the fraction of key positions receiving negligible attention:
29	\begin{equation}
30	    \sigma_i^{(h)} = \frac{1}{T} \sum_{j=1}^{T} \mathbf{1}\!\left[a_{ij}^{(h)} < 0.01 \cdot \max_k a_{ik}^{(h)}\right].
31	    \label{eq:attn-sparsity}
32	\end{equation}
33	The per-position sparsity $\sigma_i = \frac{1}{H}\sum_h \sigma_i^{(h)}$ averages across all heads. Tokens are partitioned into high-, mid-, and low-sparsity phases by the tercile boundaries of $\{\sigma_i\}$; segments shorter than 10 tokens are merged into adjacent phases.
34	
35	\section{Multiplicative Null Verification}
36	\label{app:multiplicative-null}
37	
38	We verified that replacing the additive null $r_b = r_a + r_k - 1$ (Eq.~\ref{eq:ii}) with the multiplicative null $r_b = r_a \cdot r_k$ does not change qualitative conclusions. Under the multiplicative formulation, the interaction index becomes $\mathrm{II}_{\times} = r_b - r_a \cdot r_k$. Notably, $\mathrm{II}_{\times} < 0$ across all phases and sparsity levels: the compound interaction is \emph{sub-multiplicative} everywhere---actual compound degradation is less severe than the multiplicative prediction. $G_{\times}$ therefore quantifies the ratio of sub-multiplicative deviations between phases, not super-multiplicative amplification: a value of $G_{\times}{=}30$ means the low-sparsity phase deviates from the multiplicative null by $30{\times}$ more than the high-sparsity phase. Under importance-based eviction, $G_{\times}{=}21.1$--$36.2{\times}$ (DeepSeek) and $43.9$--$64.0{\times}$ (Qwen) across $s \in \{0.15, 0.20, 0.25, 0.30\}$, yielding a combined range of $21$--$64{\times}$. Although compound effects do not exceed the multiplicative prediction in any phase, the low-sparsity phase's deviation from the multiplicative null is $21$--$64{\times}$ larger than the high-sparsity phase's, indicating that the phase-gated severity gradient is preserved under the multiplicative null. These $n{=}500$ exact values are more conservative than the preliminary $n{=}50$ calibrated estimates ($\approx$51--183${\times}$), reflecting reduced variance at full sample size. Values are computed using aggregate per-phase PPL ratios; per-problem exact computation is left for future work. Random eviction remains flat ($G_{\times} \approx 1$). The crossover at $s{=}0.25$ is preserved. We adopt the additive formulation in the main text as the more conservative baseline: it assumes zero interaction (compound loss equals the sum of individual losses), so rejection ($\mathrm{II} > 0$) establishes super-additivity regardless of null specification. The qualitative conclusions---phase-modulated severity, strategy asymmetry, and crossover---are preserved under the multiplicative null.
39	
40	% Bootstrap and permutation details moved to main text \S\ref{sec:stat-validation}
41	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3be191e9-7ade-46b3-8761-463aee140cfd",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "ce0a710d-0f4f-4538-bd95-e94d686c5694",
  "sourceToolAssistantUUID": "3be191e9-7ade-46b3-8761-463aee140cfd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-17T02:05:43.059Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Ujf1Q9d1Pf7LxW3R657jJ3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_robustness.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ce0a710d-0f4f-4538-bd95-e94d686c5694",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KeVg4SX4ZTAheF62ms",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e26740ca-fd12-4fc4-bf0e-df9309741d08",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017FRE4voZNBgT4beq1Pe9t5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1628,
      "cache_read_input_tokens": 40241,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1628,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 70,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-17T02:05:43.088Z_

<details><summary>↩ Tool result · `toolu_01Ujf1Q9d1Pf7LxW3R657jJ3`</summary>

```text
1	\section{Benjamini-Hochberg FDR Correction}
2	\label{app:bh-fdr}
3	
4	Table~\ref{tab:bh-fdr} compares Bonferroni ($k{=}4$, per model$\times$strategy family) and Benjamini-Hochberg FDR correction across all 44 statistical tests. BH-FDR recovers 5 additional significant results beyond Bonferroni, all in low-effect-size conditions (random eviction or cross-training-paradigm random comparisons). All 32 Bonferroni-significant results remain significant under BH-FDR.
5	
6	\begin{table}[t]
7	\centering
8	\small
9	\caption{Bonferroni vs.\ BH-FDR correction summary ($\alpha{=}0.05$, 44 tests). ``BH only'' denotes tests significant under BH-FDR but not Bonferroni.}
10	\label{tab:bh-fdr}
11	\begin{tabular}{@{}lcc@{}}
12	\toprule
13	Category & Bonf.\ sig. & BH-only sig. \\
14	\midrule
15	Per-condition Wilcoxon ($k{=}16$) & 10 & 2 \\
16	Imp vs.\ rand ($k{=}8$) & 8 & 0 \\
17	Adjacent sparsity ($k{=}12$) & 10 & 1 \\
18	Cross-paradigm Mann-Whitney ($k{=}8$) & 4 & 2 \\
19	\midrule
20	Total ($k{=}44$) & 32 & 5 \\
21	\bottomrule
22	\end{tabular}
23	\end{table}
24	
25	The 5 BH-only results are: DeepSeek random $s{=}0.25$ and $s{=}0.30$ per-condition Wilcoxon ($p_{\text{Bonf}}{=}0.064$/$0.065$, BH $q{=}0.002$), DeepSeek random $s{=}0.25 \to 0.30$ adjacent-sparsity step ($p_{\text{Bonf}}{=}0.078$, BH $q{=}0.002$), and cross-training-paradigm random $s{=}0.25$/$s{=}0.30$ Mann-Whitney ($p_{\text{Bonf}}{=}0.66$/$0.17$, BH $q{=}0.018$/$0.005$). All involve random eviction---the weakest effects---indicating that Bonferroni is conservative but does not miss any importance-based findings.
26	
27	
28	\section{Minimum Phase Length Sensitivity}
29	\label{app:mpl-sensitivity}
30	
31	Table~\ref{tab:mpl-sensitivity} reports the paired median difference $\Delta$ under three \texttt{min\_phase\_length} (mpl) settings across all 16 conditions (2 models $\times$ 2 strategies $\times$ 4 sparsity levels). Conclusions are robust: all importance-based conditions remain significant at $p_{\text{Bonf}} < 10^{-10}$ across mpl $\in \{5, 10, 20\}$; random conditions maintain the same significance pattern (non-significant at $s \leq 0.20$, significant at $s \geq 0.25$). Median $\Delta$ values vary by $<5\%$ between mpl settings for DeepSeek importance, supporting that the severity gradient is not an artifact of the merging threshold.
32	
33	\begin{table*}[t]
34	\centering
35	\small
36	\caption{Sensitivity of median $\Delta$ to \texttt{min\_phase\_length} (mpl). $n_{\text{eff}}$: effective sample size after exclusions. All importance-based $p_{\text{Bonf}} < 10^{-10}$; ``ns'' denotes $p_{\text{Bonf}} > 0.05$.}
37	\label{tab:mpl-sensitivity}
38	\begin{tabular}{@{}llrrrrrr@{}}
39	\toprule
40	Model & Strategy & $s$ & \multicolumn{1}{c}{mpl$=$5} & \multicolumn{1}{c}{mpl$=$10} & \multicolumn{1}{c}{mpl$=$20} & $n_{\text{eff}}$(10) & $n_{\text{eff}}$(20) \\
41	\midrule
42	DS & Imp & 0.15 & 0.391 & 0.391 & 0.393 & 496 & 433 \\
43	DS & Imp & 0.20 & 1.215 & 1.215 & 1.235 & 496 & 433 \\
44	DS & Imp & 0.25 & 3.986 & 3.986 & 4.017 & 496 & 433 \\
45	DS & Imp & 0.30 & 8.481 & 8.481 & 8.420 & 496 & 433 \\
46	\addlinespace
47	DS & Rand & 0.15 & 0.014 & 0.014\textsuperscript{ns} & 0.012\textsuperscript{ns} & 496 & 433 \\
48	DS & Rand & 0.20 & 0.031\textsuperscript{ns} & 0.031\textsuperscript{ns} & 0.023\textsuperscript{ns} & 496 & 433 \\
49	DS & Rand & 0.25 & 0.257 & 0.257 & 0.190 & 496 & 433 \\
50	DS & Rand & 0.30 & 0.510 & 0.510 & 0.410 & 496 & 433 \\
51	\addlinespace
52	QW & Imp & 0.15 & 0.066 & 0.066 & 0.066 & 475 & 289 \\
53	QW & Imp & 0.20 & 0.307 & 0.307 & 0.325 & 475 & 289 \\
54	QW & Imp & 0.25 & 1.074 & 1.074 & 1.106 & 475 & 289 \\
55	QW & Imp & 0.30 & 3.155 & 3.155 & 3.581 & 475 & 289 \\
56	\addlinespace
57	QW & Rand & 0.15 & $-$0.011\textsuperscript{ns} & $-$0.011\textsuperscript{ns} & $-$0.011\textsuperscript{ns} & 475 & 289 \\
58	QW & Rand & 0.20 & 0.015\textsuperscript{ns} & 0.015\textsuperscript{ns} & 0.015\textsuperscript{ns} & 475 & 289 \\
59	QW & Rand & 0.25 & 0.393 & 0.393 & 0.266 & 475 & 289 \\
60	QW & Rand & 0.30 & 0.913 & 0.913 & 0.788 & 475 & 289 \\
61	\bottomrule
62	\end{tabular}
63	\end{table*}
64	
65	The main effect of increasing mpl is reduced $n_{\text{eff}}$: at mpl$=$20, DeepSeek retains 433/500 problems and Qwen retains 289/500 (mid-null rate rises to 71.2\% and 84.6\%, respectively). Despite this sample reduction, all significance conclusions hold.
66	
67	
68	\section{Segmentation Robustness}
69	\label{app:seg-robust}
70	
71	Table~\ref{tab:seg-robust} reports the paired median difference $\Delta$ under tercile, quartile, and quintile segmentation for both models under importance-based eviction. Phase gradient direction and statistical significance are preserved under quartile and quintile segmentation ($n{=}50$ spot check), indicating that the tercile-based findings are not an artifact of the segmentation choice.
72	
73	\begin{table*}[t]
74	\centering
75	\small
76	\caption{Segmentation robustness: median $\Delta$ under tercile ($n{=}496$/$475$), quartile ($n{=}50$ spot check), and quintile ($n{=}50$ spot check) segmentation. Importance-based eviction; all $p_{\text{Bonf}} < 10^{-7}$.}
77	\label{tab:seg-robust}
78	\begin{tabular}{@{}llccc@{}}
79	\toprule
80	Model & $s$ & Tercile & Quartile\; [95\% CI] & Quintile\; [95\% CI] \\
81	\midrule
82	\multirow{4}{*}{DeepSeek} & 0.15 & 0.391 & 0.491\; $[0.44,\; 0.70]$ & 0.505\; $[0.33,\; 0.71]$ \\
83	& 0.20 & 1.215 & 1.388\; $[1.05,\; 1.79]$ & 1.197\; $[1.02,\; 1.76]$ \\
84	& 0.25 & 3.986 & 4.322\; $[3.62,\; 8.06]$ & 4.960\; $[3.80,\; 9.02]$ \\
85	& 0.30 & 8.481 & 12.930\; $[9.83,\; 19.10]$ & 11.548\; $[10.06,\; 18.51]$ \\
86	\addlinespace
87	\multirow{4}{*}{Qwen} & 0.15 & 0.066 & 0.226\; $[0.14,\; 0.27]$ & 0.203\; $[0.13,\; 0.26]$ \\
88	& 0.20 & 0.307 & 0.561\; $[0.35,\; 0.77]$ & 0.517\; $[0.29,\; 0.75]$ \\
89	& 0.25 & 1.074 & 1.870\; $[1.05,\; 2.44]$ & 1.801\; $[1.13,\; 2.38]$ \\
90	& 0.30 & 3.155 & 4.097\; $[2.91,\; 4.94]$ & 4.009\; $[3.28,\; 5.34]$ \\
91	\bottomrule
92	\end{tabular}
93	\end{table*}
94	
95	The quartile and quintile $\Delta$ values are comparable to or slightly larger than tercile values because finer-grained segmentation isolates more extreme phases (the ``lowest'' quintile captures a more concentrated low-sparsity segment than the lowest tercile). The monotonic dose-response ($\Delta$ increasing with $s$) is preserved across all three segmentation schemes for both models, supporting that the severity gradient is not an artifact of the tercile segmentation choice.
96	
97	
98	\section{Robustness to Asymmetric Sparsity Allocation}
99	\label{app:asymmetric-robustness}
100	
101	Our main experiments use symmetric sparsity ($s_{\text{head}} = s_{\text{KV}} = s$). To verify that the phase-gated severity gradient does not depend on this symmetric assumption, we evaluate two asymmetric configurations at a fixed total sparsity budget equivalent to $s{=}0.25$, using importance-based eviction on DeepSeek-R1-Distill-Qwen-7B.
102	
103	\begin{table}[h]
104	\centering
105	\small
106	\caption{Asymmetric sparsity robustness: per-phase II under two head/KV allocations (DeepSeek, importance-based eviction, $n{=}50$ spot check).}
107	\label{tab:asymmetric-robust}
108	\begin{tabular}{@{}lcccccc@{}}
109	\toprule
110	Config & $s_{\text{head}}$ & $s_{\text{KV}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\widetilde{\mathrm{II}}_{\textit{mid}}$ & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\Delta$ \\
111	\midrule
112	A (KV-heavy) & 0.20 & 0.30 & 19.51 & 6.05 & 0.38 & $+$19.13 \\
113	B (head-heavy) & 0.30 & 0.20 & 18.77 & 3.97 & 0.52 & $+$18.25 \\
114	\addlinespace
115	Symmetric & 0.25 & 0.25 & 3.97 & --- & 0.02 & $+$3.99 \\
116	\bottomrule
117	\end{tabular}
118	\end{table}
119	
120	Both asymmetric configurations produce large positive $\Delta$ ($+19.13$ and $+18.25$), supporting that the phase-gated severity gradient is robust to the head/KV allocation ratio. The KV-heavy configuration (A) exhibits higher mid-phase II ($6.05$ vs.\ $3.97$), suggesting that the KV eviction axis has a stronger impact on intermediate reasoning phases. Both asymmetric $\Delta$ values exceed the symmetric baseline ($3.99$), consistent with one axis operating at $s{=}0.30$---above the symmetric maximum tested---which amplifies overall severity. A systematic investigation of the full asymmetric interaction surface is left for future work.
121	
122	
123	\section{Outlier Robustness Analysis}
124	\label{app:outlier-robustness}
125	
126	The extreme mean/median ratio (up to $97{,}640{:}1$ in individual conditions) reflects heavy-tailed II distributions driven by near-zero denominators in specific problems. We verify robustness via symmetric winsorization at $5\%$ and $10\%$ levels. All median-based statistics---paired median difference $\Delta$, Wilcoxon signed-rank $p$-values, and amplification ratio $G$---are strictly invariant under winsorization, as expected for rank-based estimators. The five core claims---compound exceeds individual, importance exceeds random, monotonic dose-response, $G \gg 1$ for importance (auxiliary illustration of phase concentration), $G \approx 1$ for random---are fully robust. The extreme outlier severity further validates our choice of median-based inference over mean-based alternatives. $G$ values in this robustness analysis follow the ratio-of-medians convention (Table~\ref{tab:profiling-subset}); the primary $G$ definition (Eq.~\ref{eq:gradient}) is similarly invariant as a median of per-problem ratios.
127	
128	
129	\section{\texttt{&lt;think>} Token Phase Validation}
130	\label{app:think-validation}
131	
132	DeepSeek-R1-Distill-Qwen-7B generates explicit \texttt{&lt;think>}...\texttt{&lt;/think>} delimiters that demarcate chain-of-thought reasoning from final answers, providing a model-generated ground truth for reasoning phase boundaries. We evaluate whether our attention-sparsity-based phase segmentation (\S\ref{par:phase-segmentation}) recovers these boundaries on GSM8K ($n{=}48$ problems with valid phase assignments), using adaptive per-sequence quantile segmentation rather than a fixed global threshold.
133	
134	\paragraph{Naming convention.}
135	A note on terminology: DeepSeek's \texttt{&lt;think>} phase (active reasoning) exhibits \emph{low} attention sparsity---attention is broadly distributed across many positions during exploratory computation. Conversely, the answer phase exhibits \emph{high} attention sparsity---attention concentrates on a few positions during structured output. Thus PACS ``low-sparsity phase'' corresponds to the model's thinking phase, and ``high-sparsity phase'' to the answer phase. The physical phenomenon is consistent: broadly distributed attention characterizes reasoning in both frameworks.
136	
137	\paragraph{Token-level agreement.}
138	We binarize each token as ``thinking'' (inside \texttt{&lt;think>}) or ``answer'' (outside) and compare against the sparsity-based phase assignment. The adaptive segmentation achieves substantial agreement: $\kappa{=}0.88$ (per-problem mean $0.85$, median $0.88$), with token-level accuracy of $94.2\%$. Per-problem AUC-ROC is $0.98$ (median $0.99$), indicating near-perfect discriminability between thinking and answer phases based on attention sparsity alone. Of problems, $75\%$ achieve $\kappa \geq 0.80$ and $100\%$ achieve $\kappa \geq 0.60$. The \texttt{&lt;think>} phase exhibits significantly lower attention sparsity than the answer phase ($0.656$ vs.\ $0.763$; Cohen's $d{=}-0.80$), indicating that attention distribution breadth reliably distinguishes reasoning from structured computation.
139	
140	\paragraph{Boundary proximity.}
141	The median distance between the sparsity-based phase boundary and the nearest \texttt{&lt;think>}/\texttt{&lt;/think>} delimiter is 1 token, with $81.2\%$ of boundaries falling within 10 tokens. This tight alignment indicates that the attention sparsity transition closely tracks the model's self-identified shift from exploratory reasoning to structured answer generation.
142	
143	\paragraph{Phase composition and II correlation.}
144	We examine whether the fraction of thinking tokens within each phase correlates with compound severity (II). At the mid-phase level, the thinking-token fraction correlates with II (Spearman $\rho{=}0.49$, $p < 0.001$), consistent with mid-phase segments that contain more reasoning content being more vulnerable to compound sparsity. Low- and high-phase correlations are non-significant, as expected: these phases are compositionally dominated by thinking or answer tokens, respectively, leaving insufficient variance for correlation.
145	
146	\paragraph{MATH-500 indirect validation.}
147	Direct $\kappa$ validation requires explicit \texttt{&lt;think>} delimiters, available only on GSM8K. On MATH-500 ($n{=}500$), we instead assess \emph{temporal ordering consistency}: the fraction of problems where the low-sparsity phase precedes the high-sparsity phase, consistent with a thinking-then-answering generation structure. DeepSeek achieves a temporal ordering score of $0.576$ with $100\%$ of problems exhibiting the expected direction (low-sparsity before high-sparsity). Qwen, which lacks \texttt{&lt;think>} delimiters, shows weaker but directionally consistent temporal ordering ($0.479$). This indirect evidence supports the validity of sparsity-based phase segmentation on MATH-500 but does not constitute direct $\kappa$ validation.
148	
149	\paragraph{Scope.}
150	The direct $\kappa$ validation ($\kappa{=}0.88$, $n{=}48$) is limited to DeepSeek-R1-Distill-Qwen-7B on GSM8K; MATH-500 has only indirect (temporal ordering) validation. Qwen2.5-7B-Instruct does not produce explicit reasoning delimiters, precluding direct $\kappa$ validation on either benchmark. Phase segmentation is computed on the dense model's attention patterns and is independent of sparsity level, so the agreement statistics are reported once rather than per-$s$.
151	
152	
153	\subsection{Non-Think Token Quality Under Compound Sparsity}
154	\label{app:nt-samples}
155	
156	Tokens generated outside \texttt{&lt;think>}...\texttt{&lt;/think>} delimiters---i.e., the final answer tokens---fall predominantly in the high-sparsity attention phase, where compound interaction is minimal (\S\ref{sec:answer-region}: 93.2\% of \verb|\boxed{}| markers reside in the high-sparsity phase). We illustrate the differential impact of compound sparsity on non-think (answer) versus think (reasoning) tokens with two representative examples from the GSM8K validation set (DeepSeek-R1-Distill-Qwen-7B, $s{=}0.25$, importance-based eviction).
157	
158	\paragraph{Example 1: Preserved answer, degraded reasoning.}
159	Under compound sparsity, the non-think answer tokens (\texttt{The answer is 42}) are generated with near-baseline perplexity (PPL ratio $1.2{\times}$), while the preceding think-phase tokens exhibit $4.8{\times}$ PPL inflation. The final answer remains correct despite substantial reasoning-trace degradation---a ``silent reasoning error'' scenario where intermediate logic is corrupted but the output format masks the damage.
160	
161	\paragraph{Example 2: Cascading failure at high sparsity.}
162	At $s{=}0.30$, reasoning-phase PPL inflation ($11.3{\times}$) propagates into the answer phase: the model produces a syntactically valid but numerically incorrect \verb|\boxed{}| output (PPL ratio $3.1{\times}$ on answer tokens vs.\ $1.1{\times}$ at $s{=}0.15$). This illustrates the sparsity threshold beyond which compound severity breaches the phase boundary, consistent with the accuracy cliff observed for Qwen at $s{=}0.30$ ($\delta{=}-27$\,pp; Table~\ref{tab:accuracy}).
163	
164	\paragraph{Implication.}
165	These examples illustrate that pruning-induced compound severity is phase-selective: non-think tokens are relatively protected at moderate sparsity ($s \leq 0.25$) because they coincide with the high-sparsity attention phase where importance scores retain discriminative power. At higher sparsity ($s{=}0.30$), discrimination collapse (\S\ref{sec:discrimination-collapse-main}) erodes this protection, and compound severity spills into the answer phase.
166	
167	
168	\section{Amplification Ratio ($G$) Details}
169	\label{app:g-metric}
170	
171	The per-problem amplification ratio $G^{(i)} = \mathrm{II}^{(i)}_{\textit{low}} / \mathrm{II}^{(i)}_{\textit{high}}$ (Eq.~\ref{eq:gradient}) provides an auxiliary illustrative perspective on the primary metric $\Delta$. Table~\ref{tab:g-metric} reports $G$ with bootstrap 95\% CIs for all conditions. $G$ serves as a visualization aid; primary statistical evidence for the phase-modulated severity gradient is provided by $\Delta$ and the associated Wilcoxon tests (\S\ref{sec:phase-amplification}).
172	
173	\begin{table*}[t]
174	\centering
175	\small
176	\caption{Per-problem amplification ratio $G$ (median of $G^{(i)}$) with bootstrap 95\% CIs ($B{=}10{,}000$). $G$ serves as an auxiliary visualization of phase concentration; primary statistical evidence for the severity gradient is provided by the Interaction Index $\Delta$ (\S\ref{sec:phase-amplification}). $G \gg 1$ suggests phase-concentrated severity; $G \approx 1$ suggests uniform severity across phases.}
177	\label{tab:g-metric}
178	\begin{tabular}{@{}llcc@{}}
179	\toprule
180	$s$ & Strategy & $G$\; [95\% CI] (DeepSeek) & $G$\; [95\% CI] (Qwen) \\
181	\midrule
182	0.15 & Importance & $\mathbf{7.5}$\; $[4.1,\; 11.4]$ & n.d.$^{\dagger}$ \\
183	0.15 & Random     & 0.5\; $[0.4,\; 0.6]$ & 0.7\; $[0.4,\; 0.8]$ \\
184	\addlinespace
185	0.20 & Importance & $\mathbf{17.9}$\; $[12.7,\; 26.3]$ & $\mathbf{2.6}$\; $[0.5,\; 5.1]$ \\
186	0.20 & Random     & 0.8\; $[0.6,\; 0.9]$ & 0.9\; $[0.7,\; 1.0]$ \\
187	\addlinespace
188	0.25 & Importance & $\mathbf{49.1}$\; $[40.1,\; 57.8]$ & $\mathbf{9.5}$\; $[5.2,\; 14.8]$ \\
189	0.25 & Random     & 1.1\; $[1.0,\; 1.2]$ & 1.3\; $[1.2,\; 1.4]$ \\
190	\addlinespace
191	0.30 & Importance & $\mathbf{79.8}$\; $[63.3,\; 96.5]$ & $\mathbf{36.9}$\; $[25.3,\; 49.1]$ \\
192	0.30 & Random     & 1.1\; $[1.0,\; 1.3]$ & 1.3\; $[1.2,\; 1.4]$ \\
193	\bottomrule
194	\multicolumn{4}{@{}p{0.85\textwidth}}{\footnotesize $^{\dagger}$ $\widetilde{\mathrm{II}}_{\textit{high}} \approx 0$; ratio undefined ($G$ CI: $[-0.2, 0.9]$). $\Delta{=}0.07$, $p{=}8.7 \times 10^{-15}$ supports $\mathrm{II}_{\textit{low}} > \mathrm{II}_{\textit{high}}$.}
195	\end{tabular}
196	\end{table*}
197	
198	The $G$ values illustrate that phase-concentrated severity is associated with importance-based eviction ($G{=}7.5$--$79.8{\times}$ for DeepSeek, $2.6$--$36.9{\times}$ for Qwen), while random eviction suggests weak modulation at $s \geq 0.25$ ($G \approx 1.1$--$1.3$; CIs exclude 1) and near-uniform severity at $s \leq 0.20$ (CIs span or touch 1). The monotonic increase in $G$ with sparsity is consistent with the $\Delta$ dose-response in Table~\ref{tab:main-results}, but $G$ should be interpreted as a descriptive ratio rather than an independent statistical test---the formal evidence rests on the paired $\Delta$ and associated Wilcoxon tests.
199	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e26740ca-fd12-4fc4-bf0e-df9309741d08",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "673804a3-ea16-41d0-a45f-19abdef71800",
  "sourceToolAssistantUUID": "e26740ca-fd12-4fc4-bf0e-df9309741d08",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-17T02:05:43.739Z_

<details open><summary>🔧 Tool call — Read · `toolu_0199HDud1ZkFAUALeYYYnpdm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_moved.tex",
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "673804a3-ea16-41d0-a45f-19abdef71800",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KeVg4SX4ZTAheF62ms",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e0054c96-d4d8-47cc-a05c-c0d378ecf3fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017FRE4voZNBgT4beq1Pe9t5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1628,
      "cache_read_input_tokens": 40241,
      "output_tokens": 192,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1628
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 192,
          "cache_read_input_tokens": 40241,
          "cache_creation_input_tokens": 1628,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1628,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-17T02:05:43.748Z_

<details><summary>↩ Tool result · `toolu_0199HDud1ZkFAUALeYYYnpdm`</summary>

```text
1	
2	\section{Phase-Strategy Crossover Details}
3	\label{app:crossover-details}
4	
5	On DeepSeek ($n{=}496$), a strategy ranking reversal emerges at $s{=}0.25$ (Figure~\ref{fig:crossover}): importance-based eviction yields \emph{lower} II than random in the high-sparsity phase ($0.021$ vs.\ $1.113$) but \emph{higher} II in the low-sparsity phase ($3.971$ vs.\ $1.514$---a $2.6{\times}$ reversal; both $p < 10^{-4}$). This crossover is observed at all four sparsity levels, with reversal magnitude of $4.0{\times}$ at $s{=}0.15$, $3.4{\times}$ at $s{=}0.20$, $2.6{\times}$ at $s{=}0.25$, and $2.2{\times}$ at $s{=}0.30$ (decreasing as random eviction severity rises). The reversal arises because head pruning redistributes attention mass, altering importance rankings in a way that couples the two sparsity mechanisms in low-sparsity phases (\S\ref{sec:discrimination-collapse-main}). Qwen does not exhibit a crossover: importance-based eviction produces lower II than random in both phases across all sparsity levels (e.g., at $s{=}0.25$: high $0.004$ vs.\ $1.108$; low $1.053$ vs.\ $1.769$).
6	
7	\begin{figure}[t]
8	\centering
9	\includegraphics[width=\columnwidth]{fig3_crossover.pdf}
10	\caption{Strategy-dependent crossover at $s{=}0.25$ on DeepSeek ($n{=}496$). Grouped bar chart of median II by eviction strategy and reasoning phase. Importance-based eviction outperforms random in the high-sparsity phase but produces $2.6{\times}$ higher II in the low-sparsity phase, reversing the strategy ranking.}
11	\label{fig:crossover}
12	\end{figure}
13	
14	
15	\section{Profiling Subset Per-Phase Breakdown}
16	\label{app:profiling-subset}
17	
18	\begin{table*}[t]
19	\centering
20	\small
21	\caption{Per-phase interaction index (II) from the $n{=}50$ profiling subset (DeepSeek-R1-Distill-Qwen-7B). This preliminary table does not include per-condition bootstrap CIs; full-scale values with bootstrap 95\% CIs ($B{=}10{,}000$) at $n{=}496$ appear in Table~\ref{tab:main-results}, and strategy-contrast CIs for this subset appear in the permutation test (Table~\ref{tab:permutation}). $G$ values use the ratio-of-medians definition ($\widetilde{\mathrm{II}}_{\textit{low}} / \widetilde{\mathrm{II}}_{\textit{high}}$) and serve as an auxiliary illustration of phase concentration; the primary evidence is $\Delta$ (see Appendix~\ref{app:g-metric}). At low sparsity ($s{=}0.15$), the ratio-of-medians and per-problem definitions diverge ($7.5{\times}$ vs.\ $69{\times}$) because per-problem ratios are sensitive to near-zero $\mathrm{II}_{\textit{high}}$ values.}
22	\label{tab:profiling-subset}
23	\begin{tabular}{@{}llccccr@{}}
24	\toprule
25	$s$ & Strategy & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\widetilde{\mathrm{II}}_{\textit{mid}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\Delta$ & $G$ \\
26	\midrule
27	0.15 & Importance & 0.006 & 0.081 & 0.398 & 0.39 & $\mathbf{69}$ \\
28	0.15 & Random     & 0.093 & 0.097 & 0.103 & 0.01 & 1.1 \\
29	\addlinespace
30	0.20 & Importance & 0.015 & 0.203 & 1.496 & 1.48 & $\mathbf{103}$ \\
31	0.20 & Random     & 0.292 & 0.350 & 0.276 & $-$0.02 & 0.9 \\
32	\addlinespace
33	0.25 & Importance & 0.032 & 1.118 & 7.196 & 7.16 & $\mathbf{222}$ \\
34	0.25 & Random     & 0.818 & 0.932 & 1.363 & 0.54 & 1.7 \\
35	\addlinespace
36	0.30 & Importance & 0.053 & 2.283 & 14.639 & 14.59 & $\mathbf{274}$ \\
37	0.30 & Random     & 2.503 & 2.592 & 4.041 & 1.54 & 1.6 \\
38	\bottomrule
39	\end{tabular}
40	\end{table*}
41	
42	The $n{=}50$ profiling subset served as a preliminary calibration; all importance-based $\Delta$ values were subsequently replicated at $n{=}496$ with bootstrap 95\% CIs excluding zero (Table~\ref{tab:main-results}: $\Delta{=}0.39$\;$[0.35,\;0.44]$ to $8.48$\;$[7.75,\;9.69]$). The paired permutation test on this subset ($n{=}49$; Table~\ref{tab:permutation}) provides bootstrap 95\% CIs for the strategy contrast ($\widetilde{\Delta}_{\text{imp}} - \widetilde{\Delta}_{\text{rand}}$), all excluding zero after Bonferroni correction.
43	
44	
45	\section{Cross-Training-Paradigm Replication Details}
46	\label{app:cross-model-details}
47	
48	Both models share the Qwen2ForCausalLM backbone (28 layers, 28 heads, 4-group GQA) but differ in training: DeepSeek uses reasoning distillation from DeepSeek-R1, while Qwen2.5 uses standard instruction tuning without explicit reasoning delimiters. This within-architecture-family comparison enables assessment of training methodology effects on the compound sparsity interaction, though causal attribution is limited by the observational design.
49	
50	Despite lacking explicit \texttt{&lt;think>} delimiters, Qwen2.5-7B-Instruct exhibits sufficient variation in attention sparsity to permit phase segmentation via the same quantile-based method (\S\ref{par:phase-segmentation}). Twenty-five of the 500 problems are excluded due to degenerate phase assignments, yielding $n{=}475$ valid problems for Qwen (vs.\ $n{=}496$ for DeepSeek).
51	
52	\paragraph{Per-phase effective sample size.}
53	\label{app:qwen-null-rate}
54	Table~\ref{tab:qwen-effective-n} reports the per-phase effective sample size for Qwen2.5-7B-Instruct, defined as the number of problems with non-null phase segments (segment length $\geq$ \texttt{min\_phase\_length}). The mid-phase null rate (45.2\%) reflects problems where mid-sparsity tokens do not form contiguous runs above the merging threshold; this does not affect the low--high contrast ($\Delta$) used in the primary analysis.
55	
56	\begin{table}[t]
57	\centering
58	\small
59	\caption{Per-phase effective sample size for Qwen2.5-7B-Instruct ($n_{\text{eff}} = 475$). Phase segmentation is performed once on dense-model attention patterns and is independent of sparsity level.}
60	\label{tab:qwen-effective-n}
61	\begin{tabular}{@{}lcccc@{}}
62	\toprule
63	Phase & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
64	\midrule
65	High & 475 & 475 & 475 & 475 \\
66	Mid  & 274 & 274 & 274 & 274 \\
67	Low  & 475 & 475 & 475 & 475 \\
68	\bottomrule
69	\end{tabular}
70	\end{table}
71	
72	Table~\ref{tab:cross-model} reports the cross-training-paradigm comparison. Qwen reproduces the monotonic severity gradient at ${\sim}1/5$ of DeepSeek's magnitude. Figure~\ref{fig:cross-model} visualizes this comparison.
73	
74	\begin{table}[t]
75	\centering
76	\small
77	\caption{Cross-training-paradigm comparison of median compound severity difference ($\Delta$) under importance-based eviction.}
78	\label{tab:cross-model}
79	\begin{tabular}{@{}lcccc@{}}
80	\toprule
81	Model & $s{=}0.15$ & $s{=}0.20$ & $s{=}0.25$ & $s{=}0.30$ \\
82	\midrule
83	DeepSeek-R1-Distill-Qwen-7B ($n{=}496$) & 0.39 & 1.21 & 3.99 & 8.48 \\
84	Qwen2.5-7B-Instruct ($n{=}475$)         & 0.07 & 0.31 & 1.07 & 3.16 \\
85	\bottomrule
86	\end{tabular}
87	\end{table}
88	
89	\begin{figure}[t]
90	\centering
91	\includegraphics[width=\columnwidth]{fig5_crossmodel.pdf}
92	\caption{Cross-training-paradigm comparison of the median severity difference under importance-based eviction ($n{=}496$/$475$). Both DeepSeek (solid) and Qwen (dashed) exhibit monotonically increasing $\Delta$ with sparsity; Qwen's magnitude is approximately one-quarter to one-sixth of DeepSeek's.}
93	\label{fig:cross-model}
94	\end{figure}
95	
96	\paragraph{Per-problem concordance.}
97	The per-problem concordance across models is not significant (mean $\rho = -0.107$, $p = 0.926$), indicating that while the aggregate gradient direction replicates, the specific problems driving severity differ between models---consistent with model-specific attention patterns rather than a universal per-problem vulnerability ranking.
98	
99	\paragraph{Random eviction control.}
100	As a control, random eviction on Qwen mirrors DeepSeek: non-significant at $s \leq 0.20$ ($\Delta$: $-0.01$, $0.02$; CIs span zero) but significant at $s \geq 0.25$ ($\Delta{=}0.39$, $p_{\text{Bonf}} < 10^{-10}$; $\Delta{=}0.91$, $p_{\text{Bonf}} < 10^{-13}$). Where significant, the random phase gradient is $2.7$--$3.5{\times}$ weaker than importance-based ($0.39$ vs.\ $1.07$ at $s{=}0.25$; $0.91$ vs.\ $3.16$ at $s{=}0.30$), supporting strategy-specific amplification.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e0054c96-d4d8-47cc-a05c-c0d378ecf3fa",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "4e426a0e-ebb1-43ba-a83f-460894bc1f26",
  "sourceToolAssistantUUID": "e0054c96-d4d8-47cc-a05c-c0d378ecf3fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-17T02:05:48.508Z_

<details open><summary>🔧 Tool call — Read · `toolu_01T24FkKv5AUG63M7QqAsfrq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/appendix_disc_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4e426a0e-ebb1-43ba-a83f-460894bc1f26",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KemkwYNx3LWBFKG9qY",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "437a7327-e2d7-42cf-bff8-a99eb0bf8b7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PuUc4yKytNpdbVvkW7AYVR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10560,
      "cache_read_input_tokens": 41869,
      "output_tokens": 97,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 10560
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 97,
          "cache_read_input_tokens": 41869,
          "cache_creation_input_tokens": 10560,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 10560,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-17T02:05:48.514Z_

<details><summary>↩ Tool result · `toolu_01T24FkKv5AUG63M7QqAsfrq`</summary>

```text
1	\section{Importance Discrimination Collapse Details}
2	\label{app:discrimination-collapse-details}
3	
4	This cross-model consistency (Table~\ref{tab:discrimination-metrics-full}) supports importance discrimination collapse as a robust consequence of compound sparsity. When importance scores lose discriminative power, thresholding the bottom-$s$ fraction becomes noise-sensitive: small perturbations change which positions cross the eviction boundary. In the limit of perfectly uniform scores, importance-based eviction degenerates into an arbitrary selection functionally equivalent to biased random eviction. The same pattern holds under random eviction (DeepSeek: $-0.031$ to $-0.071$; Qwen: $-0.019$ to $-0.046$), indicating that importance discrimination collapse is a consequence of head pruning \emph{per se}, not of the eviction strategy.
5	
6	
7	\section{Extended Discussion}
8	\label{app:extended-discussion}
9	
10	\paragraph{On the predictability of phase-modulated severity.}
11	The compound interaction is not uniformly fragile---it is selectively fragile in a phase-dependent manner ($\widetilde{\mathrm{II}}_{\text{high}} < 0.06$ at $s \leq 0.30$).
12	
13	\paragraph{Random masking as falsification control.}
14	At $n{=}500$, random eviction develops a detectable but weak phase gradient above $s \approx 0.20$: non-significant at $s \leq 0.20$ for both models, but significant at $s \geq 0.25$ (DS: $\Delta{=}0.26$--$0.51$, $p_{\text{Bonf}} < 0.006$; QW: $\Delta{=}0.39$--$0.91$, $p_{\text{Bonf}} < 10^{-10}$). Where significant, the random phase gradient is $2.7$--$17{\times}$ weaker than importance-based (restricted to conditions where both strategies are significant, $s \geq 0.25$), supporting that the dominant amplification is strategy-specific.
15	
16	\paragraph{Entropy mechanism boundary conditions.}
17	Directly measuring per-head entropy shifts across architecturally distinct models---and identifying what training-time properties determine whether entropy concentrates or disperses under head pruning---would clarify the boundary conditions of the full mechanism.
18	
19	
20	\section{Pilot Mitigation Experiment}
21	\label{app:pilot-mitigation}
22	
23	We explored oracle phase-aware budget reallocation, shifting sparsity budget from high-severity low-sparsity phases to low-severity high-sparsity phases ($n{=}30$ problems at $s{=}0.25$). Oracle recovery---the fraction of compound interaction eliminated by phase-aware allocation---reached 18\% (95\% CI: $[-39\%, 45.8\%]$; Wilcoxon $p = 0.002$), below the pre-registered 30\% gate for claiming practical mitigation. A heuristic variant achieved 32\% recovery (95\% CI: $[-22.8\%, 66\%]$; $p = 0.024$). \textbf{Critically, 95\% bootstrap CIs for both conditions span zero}, meaning neither recovery estimate is statistically distinguishable from no improvement. \textbf{Gate status: FAIL}---neither oracle nor heuristic recovery meets the pre-registered threshold, and neither is statistically distinguishable from zero improvement. These results indicate that phase-aware budget reallocation alone is insufficient to neutralize the severity gradient; effective mitigation likely requires joint optimization of budget allocation and eviction strategy selection across phases.
24	
25	
26	\section{Extended Limitations}
27	\label{app:limitations}
28	
29	\paragraph{Model scale.}
30	All experiments are conducted at the 7B parameter scale.
31	Whether the phase-modulated severity patterns persist, amplify, or attenuate at larger scales (e.g., 70B) remains untested.
32	Larger models may exhibit different attention redundancy structures that alter the importance discrimination collapse dynamics (and the model-dependent entropy component may behave differently at scale).
33	
34	
35	\paragraph{Architectural scope.}
36	Our two models---DeepSeek-R1-Distill-Qwen-7B and Qwen2.5-7B-Instruct---share the Qwen2ForCausalLM architecture.
37	The cross-training-paradigm replication (\S\ref{sec:cross-model}) suggests that the findings are not artifacts of a single model's weights, though both models share the same Qwen2ForCausalLM architecture.
38	Cross-architecture validation on DeepSeek-R1-Distill-Llama-8B (LlamaForCausalLM, $n{=}250$, \S\ref{sec:cross-arch}, Appendix~\ref{app:cross-arch}) confirms qualitatively consistent within-importance phase gradients ($d_z{=}0.81$--$1.15$; all $p < 10^{-29}$) but a substantially weaker strategy${\times}$phase interaction than in Qwen2-based architectures: random eviction also exhibits significant phase gradients on LLaMA ($d_z{=}0.41$--$0.46$; all $p < 10^{-12}$), reducing the importance/random ratio to $2.0$--$2.6{\times}$ (vs.\ $15$--$17{\times}$ on DeepSeek). The phase gradient direction and dose-response monotonicity are architecture-general; quantitative strategy specificity is architecture-dependent. Comprehensive cross-architecture validation across more diverse designs (e.g., Mistral, multi-latent attention architectures) and scales remains an important next step.
39	
40	
41	\paragraph{Task coverage.}
42	We evaluate exclusively on MATH-500, a mathematical reasoning benchmark.
43	Different reasoning tasks---code generation, commonsense reasoning, multi-hop question answering---may induce different phase structures with different sparsity distributions, potentially altering the severity gradient profile.
44	Generalizing the phase-strategy interaction to broader reasoning domains is an important next step.
45	
46	
47	\paragraph{Statistical scope.}
48	Bootstrap confidence intervals use $B{=}10{,}000$ resamples (seed$=$42). The primary analysis uses $n{=}496$ paired problems for DeepSeek (4 excluded) and $n{=}475$ for Qwen (25 excluded); the permutation test (Table~\ref{tab:permutation}) uses $n{=}49$ from an initial profiling subset.
49	The severity difference distribution is right-skewed (mean/median ratios up to $43{:}1$), motivating our use of medians and nonparametric tests rather than parametric alternatives.
50	All four profiling-subset permutation tests reject $H_0$ after Bonferroni correction ($p_{\text{Bonf}} < 0.005$; Table~\ref{tab:permutation}), with CI lower bounds increasing from $0.19$ to $6.70$---supporting the effect direction at every sparsity level. At $n{=}496$, Wilcoxon signed-rank tests support all conditions with $p_{\text{Bonf}} < 10^{-13}$ (Table~\ref{tab:cohens-d}). The permutation CIs at higher sparsity are wider (e.g., $[6.70,\; 16.29]$ at $s{=}0.30$), reflecting genuine variance in per-problem severity amplification.
51	
52	At $n{=}500$, random eviction on both models becomes significant at $s \geq 0.25$ (Qwen: $\Delta{=}0.39$, $p_{\text{Bonf}} < 10^{-10}$ at $s{=}0.25$; $\Delta{=}0.91$, $p_{\text{Bonf}} < 10^{-13}$ at $s{=}0.30$; bootstrap CIs exclude zero).
53	These effects are genuine but $2.7$--$17{\times}$ weaker than importance-based eviction at the same sparsity levels, consistent with a weak phase gradient that is detectable at sufficient sample size but not the primary driver of compound severity.
54	
55	\paragraph{Sparsity range.}
56	Our primary analysis spans $s \in \{0.15, 0.20, 0.25, 0.30\}$; pilot data at $s{=}0.10$ and $s{=}0.35$ exist (6 total sparsity levels) but are not included in the main analysis due to limited sample size at these boundary conditions. Monotonicity is established at the tested sparsity levels (JT test $p \ll 10^{-10}$); the functional form of $G(s)$ between and beyond these levels is not characterized.
57	More extreme sparsity ($s > 0.50$) may exhibit qualitatively different interaction dynamics---the sub-exponential growth pattern suggests the severity gradient may plateau, but this remains unverified.
58	
59	
60	\paragraph{No throughput evaluation.}
61	We do not report inference throughput or latency, which are necessary for deployment analysis but orthogonal to our severity characterization.
62	
63	
64	
65	\section{Cross-Benchmark Validation: GSM8K}
66	\label{app:gsm8k}
67	
68	Tables~\ref{tab:gsm8k-ds} and \ref{tab:gsm8k-qw} report the per-phase II breakdown on GSM8K ($n{=}50$) for DeepSeek and Qwen, respectively. All statistics use medians, Wilcoxon signed-rank tests, and bootstrap median CIs ($B{=}10{,}000$), matching the MATH-500 methodology. DeepSeek importance-based eviction replicates the MATH-500 phase gradient across all four sparsity levels (all $p \leq 0.0003$) with a strict dose-response ($\Delta$: $0.24 \to 4.68$). Qwen importance-based eviction is significant at $s \geq 0.25$ ($p < 10^{-4}$). Random eviction is non-significant across all conditions for both models; Qwen random $s{=}0.30$ is excluded due to data quality concerns (output truncation producing extreme II values).
69	
70	\paragraph{Power analysis for random conditions.}
71	Post-hoc power analysis indicates that at $n{=}50$, the minimum detectable effect size is $d \geq 0.40$ ($\alpha{=}0.05$, power${=}0.80$). All 8 random conditions (2 models $\times$ 4 sparsity levels) show $|d| \leq 0.164$, well below the detectability threshold; their non-significance should therefore be interpreted as absence of evidence rather than evidence of absence. By contrast, Qwen importance-based eviction at $s \geq 0.25$ is adequately powered ($d \approx 0.63$, power ${>}\,0.99$), indicating that the observed significance reflects a genuine effect.
72	
73	\begin{table*}[t]
74	\centering
75	\small
76	\caption{Per-phase interaction index on GSM8K: DeepSeek-R1-Distill-Qwen-7B ($n{=}50$). $\Delta$: paired median difference ($\widetilde{\mathrm{II}}_{\textit{low}} - \widetilde{\mathrm{II}}_{\textit{high}}$) with bootstrap 95\% CI ($B{=}10{,}000$, median statistic). $p$: Wilcoxon signed-rank, Bonferroni-corrected ($k{=}4$).}
77	\label{tab:gsm8k-ds}
78	\begin{tabular}{@{}llcccc@{}}
79	\toprule
80	$s$ & Strategy & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\Delta$\; [95\% CI] & $p_{\text{Bonf}}$ \\
81	\midrule
82	0.15 & Importance & $-$0.001 & 0.241 & 0.24\; $[0.08,\; 0.48]$ & 0.0003 \\
83	0.15 & Random     & 0.036 & 0.105 & $-$0.04\textsuperscript{ns} & 0.90 \\
84	\addlinespace
85	0.20 & Importance & $-$0.002 & 0.740 & 0.74\; $[0.31,\; 1.12]$ & ${<}\,10^{-4}$ \\
86	0.20 & Random     & 0.143 & 0.423 & 0.28\textsuperscript{ns} & 0.96 \\
87	\addlinespace
88	0.25 & Importance & 0.009 & 1.992 & 1.99\; $[0.93,\; 2.82]$ & ${<}\,10^{-4}$ \\
89	0.25 & Random     & 0.619 & 1.603 & 0.98\textsuperscript{ns} & 0.83 \\
90	\addlinespace
91	0.30 & Importance & 0.024 & 4.682 & 4.68\; $[2.12,\; 10.56]$ & ${<}\,10^{-4}$ \\
92	0.30 & Random     & 1.837 & 4.683 & 2.85\textsuperscript{ns} & 0.54 \\
93	\bottomrule
94	\end{tabular}
95	\end{table*}
96	
97	\begin{table*}[t]
98	\centering
99	\small
100	\caption{Per-phase interaction index on GSM8K: Qwen2.5-7B-Instruct ($n{=}50$). Outputs truncated at \texttt{max\_new\_tokens}${=}$2047; absolute values should be interpreted with this limitation. $^{\ddagger}$Excluded: extreme II values from truncation artifacts render this condition invalid.}
101	\label{tab:gsm8k-qw}
102	\begin{tabular}{@{}llcccc@{}}
103	\toprule
104	$s$ & Strategy & $\widetilde{\mathrm{II}}_{\textit{high}}$ & $\widetilde{\mathrm{II}}_{\textit{low}}$ & $\Delta$\; [95\% CI] & $p_{\text{Bonf}}$ \\
105	\midrule
106	0.15 & Importance & 0.000 & 0.029 & 0.03\textsuperscript{ns} & 0.39 \\
107	0.15 & Random     & 0.089 & 0.033 & $-$1.58\textsuperscript{ns} & 0.69 \\
108	\addlinespace
109	0.20 & Importance & 0.004 & 0.180 & 0.09\textsuperscript{ns} & 0.62 \\
110	0.20 & Random     & 0.201 & 0.356 & 4.88\textsuperscript{ns} & 0.57 \\
111	\addlinespace
112	0.25 & Importance & 0.009 & 1.064 & 1.14\; $[0.62,\; 1.66]$ & ${<}\,10^{-4}$ \\
113	0.25 & Random     & 0.802 & 1.213 & 11.1\textsuperscript{ns} & 0.39 \\
114	\addlinespace
115	0.30 & Importance & 0.023 & 2.140 & 4.62\; $[2.88,\; 6.92]$ & ${<}\,10^{-4}$ \\
116	0.30 & Random$^{\ddagger}$     & \multicolumn{4}{c}{\textit{excluded (data quality)}} \\
117	\bottomrule
118	\end{tabular}
119	\end{table*}
120	
121	
122	\section{Downstream Accuracy Validation Details}
123	\label{app:accuracy-details}
124	
125	Table~\ref{tab:accuracy} reports MATH-500 accuracy under compound sparsity (importance-based eviction) at $s \in \{0.15, 0.20, 0.25, 0.30\}$ with \texttt{max\_new\_tokens}${=}$8192, complementing the PPL-based analysis in \S\ref{sec:accuracy-validation}. Qwen ($n{=}100$; truncation $\leq 4\%$ across all conditions) provides the cleanest dose-response evidence: accuracy declines gradually from $46\%$ (dense) through $s{=}0.25$ ($\delta{=}-4$ to $-13$\,pp) before a sharp cliff at $s{=}0.30$ ($19\%$, $\delta{=}-27$\,pp). DeepSeek ($n{=}50$) shows steeper overall degradation ($74\% \to 4\%$), confounded by rising truncation ($16\% \to 76\%$); non-truncated analysis (\S\ref{app:accuracy-nt}) reveals a dual-regime structure.
126	
127	\begin{table}[h]
128	\centering
129	\small
130	\caption{MATH-500 accuracy under compound sparsity (importance-based eviction, \texttt{max\_new\_tokens}${=}$8192). $\delta$: accuracy change vs.\ dense. Trunc: truncation rate under sparse condition. DS: $n{=}50$ (dense truncation $16\%$); QW: $n{=}100$ (truncation $\leq 4\%$ all conditions).}
131	\label{tab:accuracy}
132	\begin{tabular}{@{}lccccc@{}}
133	\toprule
134	Model & $s$ & Dense & Sparse & $\delta$ & Trunc \\
135	\midrule
136	DS & 0.15 & 74\% & 48\% & $-$26\,pp & 32\% \\
137	DS & 0.20 & 74\% & 30\% & $-$44\,pp & 56\% \\
138	DS & 0.25 & 74\% & 8\% & $-$66\,pp & 76\% \\
139	DS & 0.30 & 74\% & 4\% & $-$70\,pp & 76\% \\
140	\addlinespace
141	QW & 0.15 & 46\% & 42\% & $-$4\,pp & $\leq$4\% \\
142	QW & 0.20 & 46\% & 36\% & $-$10\,pp & $\leq$4\% \\
143	QW & 0.25 & 46\% & 33\% & $-$13\,pp & $\leq$4\% \\
144	QW & 0.30 & 46\% & 19\% & $-$27\,pp & $\leq$4\% \\
145	\bottomrule
146	\end{tabular}
147	\end{table}
148	
149	\paragraph{Failure mode divergence.}
150	DeepSeek and Qwen exhibit qualitatively distinct failure modes under compound sparsity. DeepSeek failures are \emph{truncation-dominated}: compound sparsity is associated with verbose, repetitive chain-of-thought that exceeds the token limit (truncation rises from $16\%$ at dense to $32\%$ at $s{=}0.15$ and $76\%$ at $s{=}0.30$, even with \texttt{max\_new\_tokens}${=}$8192). Qwen failures are \emph{wrong-answer-dominated}: outputs complete within the token limit (truncation $\leq 4\%$) but produce incorrect answers, indicating that compound sparsity disrupts reasoning quality directly. This divergence likely reflects training-paradigm differences: DeepSeek's distillation from DeepSeek-R1 produces extended CoT traces susceptible to truncation under degraded conditions.
151	
152	\paragraph{Language switching under high sparsity.}
153	DeepSeek problems exhibit language switching to Chinese mid-generation at the following observed rates: 0\% at dense, 4\% at $s{=}0.15$, and 40\% at $s{=}0.30$ (intermediate sparsity levels not yet measured).\footnote{Language switching rates were detected from \texttt{gen\_snippet} fields in 2048-token evaluations, not from the independent 8192-token generations used in Table~\ref{tab:accuracy}. Rates under the 8192-token budget were not re-measured.} This qualitative pathology---absent in Qwen---is a \emph{symptom} of compound-sparsity-induced degradation rather than a cause of accuracy loss: at $s{=}0.30$, Chinese-language and English-language outputs achieve comparable accuracy ($\sim$10\%), indicating that the accuracy decline reflects pruning-induced reasoning corruption regardless of output language. The switching pattern is consistent with the model's Chinese-language pretraining corpus surfacing under degraded attention in distillation-trained models.
154	
155	
156	\section{Non-Truncated Sensitivity Analysis}
157	\label{app:accuracy-nt}
158	
159	With \texttt{max\_new\_tokens}${=}$8192, Qwen truncation remains $\leq 4\%$ across all sparsity levels, so the full-sample accuracy decline ($\delta{=}-4$ to $-27$\,pp; Table~\ref{tab:accuracy}) reflects pure reasoning quality degradation without truncation confound.
160	
161	DeepSeek exhibits substantial truncation ($16\%$ at dense to $76\%$ at $s{=}0.25$--$0.30$). Restricting to non-truncated outputs reveals a \emph{dual-regime} structure. At $s \leq 0.20$, non-truncated accuracy remains $68$--$71\%$ (vs.\ $88\%$ dense; $n_{\text{NT}}{=}34$ at $s{=}0.15$, $n_{\text{NT}}{=}22$ at $s{=}0.20$), while full-sample accuracy drops to $30$--$48\%$---indicating that degradation at low sparsity is primarily truncation-driven rather than reflecting reasoning quality loss. At $s \geq 0.25$, non-truncated accuracy itself collapses: $33\%$ at $s{=}0.25$ and $17\%$ at $s{=}0.30$ ($n_{\text{NT}}{=}12$ for both; reported as reference values given small samples), showing that high-dose compound sparsity degrades both generation length \emph{and} reasoning quality simultaneously. The NT accuracy cliff from $68\%$ ($s{=}0.20$) to $33\%$ ($s{=}0.25$) localizes the transition between truncation-driven and dual-collapse regimes.
162	
163	This dual-regime structure complements the importance discrimination collapse analysis (\S\ref{sec:analysis}): at low sparsity, compound interaction primarily manifests as increased verbosity (degraded attention produces repetitive CoT); at high sparsity, the interaction additionally corrupts reasoning-critical computations.
164	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "437a7327-e2d7-42cf-bff8-a99eb0bf8b7f",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "c7d28433-78fe-47d5-9c15-f8b94e65344c",
  "sourceToolAssistantUUID": "437a7327-e2d7-42cf-bff8-a99eb0bf8b7f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 37 · 2026-05-17T02:05:51.896Z_

Now let me check for the "Simulated Reviewer Assessment" mentioned in the review task.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c7d28433-78fe-47d5-9c15-f8b94e65344c",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kf84a3hb3fdfrXj9HT",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f4118788-7749-4dd3-8eba-c763ad256cea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nmq9rbzWb2eNMc8JjFBtHG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6211,
      "cache_read_input_tokens": 52429,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6211,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-17T02:05:54.840Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01GEHgbdtorQdCWUbTgsdRPF`</summary>

```json
{
  "pattern": "Simulated Reviewer|Table 7|simulated.*review",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper",
  "output_mode": "content",
  "-i": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f4118788-7749-4dd3-8eba-c763ad256cea",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kf84a3hb3fdfrXj9HT",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "034c87f8-577b-4684-9ff3-00bde15a0fe5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nmq9rbzWb2eNMc8JjFBtHG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6211,
      "cache_read_input_tokens": 52429,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6211,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 39 · 2026-05-17T02:05:54.869Z_

<details><summary>↩ Tool result · `toolu_01GEHgbdtorQdCWUbTgsdRPF`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "034c87f8-577b-4684-9ff3-00bde15a0fe5",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "dcacbdf3-5b02-4a93-a2b3-5d7eacb8e0d6",
  "sourceToolAssistantUUID": "034c87f8-577b-4684-9ff3-00bde15a0fe5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-17T02:05:55.690Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01KyBVDWK6XM8eU7SqiWFCNe`</summary>

```json
{
  "pattern": "GPQA|gpqa",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dcacbdf3-5b02-4a93-a2b3-5d7eacb8e0d6",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kf84a3hb3fdfrXj9HT",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f53a4b74-18e6-48b5-b316-58daa51b2ecb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nmq9rbzWb2eNMc8JjFBtHG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6211,
      "cache_read_input_tokens": 52429,
      "output_tokens": 286,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6211
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 286,
          "cache_read_input_tokens": 52429,
          "cache_creation_input_tokens": 6211,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6211,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 41 · 2026-05-17T02:05:55.716Z_

<details><summary>↩ Tool result · `toolu_01KyBVDWK6XM8eU7SqiWFCNe`</summary>

```text
artifacts/_project/paper/main.bbl:238:  and Bowman}]{rein-gpqa-2024}
artifacts/_project/paper/main.bbl:241:\newblock \href {https://arxiv.org/abs/2311.12022} {{GPQA}: A graduate-level
artifacts/_project/paper/limitations.tex:5:[Omitted long matching line]
artifacts/_project/paper/references.bib:343:@article{rein-gpqa-2024,
artifacts/_project/paper/references.bib:344:    title   = {{GPQA}: A Graduate-Level Google-Proof Q\&A Benchmark},
artifacts/_project/paper/results.tex:149:\subsection{Cross-Benchmark Validation: GPQA Diamond}
artifacts/_project/paper/results.tex:150:\label{sec:cross-benchmark-gpqa}
artifacts/_project/paper/results.tex:152:To assess generalization beyond mathematical reasoning, we evaluate both models on GPQA Diamond~\cite{rein-gpqa-2024} ($n{=}198$), a graduate-level science QA benchmark requiring multi-step reasoning across physics, chemistry, and biology.
artifacts/_project/paper/results.tex:157:\caption{Median of per-problem paired severity differences ($\Delta$) under importance-based eviction on GPQA Diamond. \textit{Results pending.}}
artifacts/_project/paper/results.tex:158:\label{tab:gpqa-results}
artifacts/_project/paper/results.tex:169:%% PLACEHOLDER: Fill Table~\ref{tab:gpqa-results} when c11 experiment completes.
artifacts/_project/paper/main.aux:804:\citation{rein-gpqa-2024}
artifacts/_project/paper/main.aux:807:\@writefile{lot}{\contentsline {table}{\numberline {4}{\ignorespaces Median of per-problem paired severity differences ($\Delta $) under importance-based eviction on GPQA Diamond. \textit  {Results pending.}}}{9}{table.caption.22}\protected@file@percent }
artifacts/_project/paper/main.aux:808:\newlabel{tab:gpqa-results}{{4}{9}{Median of per-problem paired severity differences ($\Delta $) under importance-based eviction on GPQA Diamond. \textit {Results pending.}}{table.caption.22}{}}
artifacts/_project/paper/main.aux:846:\@writefile{toc}{\contentsline {subsection}{\numberline {5.9}Cross-Benchmark Validation: GPQA Diamond}{9}{subsection.5.9}\protected@file@percent }
artifacts/_project/paper/main.aux:847:\newlabel{sec:cross-benchmark-gpqa}{{5.9}{9}{Cross-Benchmark Validation: GPQA Diamond}{subsection.5.9}{}}
artifacts/_project/paper/main.aux:1266:\bibcite{rein-gpqa-2024}{{32}{2024}{{Rein et~al.}}{{Rein, Hou, Stickland, Petty, Pang, Dirani, Michael, and Bowman}}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f53a4b74-18e6-48b5-b316-58daa51b2ecb",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "a3414c1c-c093-4329-b78b-bceb6d13e667",
  "sourceToolAssistantUUID": "f53a4b74-18e6-48b5-b316-58daa51b2ecb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 42 · 2026-05-17T02:05:59.521Z_

<details open><summary>🔧 Tool call — Glob · `toolu_019MQgSneSQa9ETZN3sMUzcc`</summary>

```json
{
  "pattern": "**/dream_reports/dream_20260517T013445/best/paper.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a3414c1c-c093-4329-b78b-bceb6d13e667",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kfety15oc6ra72kXja",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "54bb83df-21e8-4be4-91d3-9b9ff809279f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019M7JdrArhMQvzGALYDYZCv",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 58640,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1215,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 34,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 43 · 2026-05-17T02:05:59.546Z_

<details><summary>↩ Tool result · `toolu_019MQgSneSQa9ETZN3sMUzcc`</summary>

```text
artifacts/dream_reports/dream_20260517T013445/best/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "54bb83df-21e8-4be4-91d3-9b9ff809279f",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "e1f85888-d681-4969-af9d-61eb4d001bdf",
  "sourceToolAssistantUUID": "54bb83df-21e8-4be4-91d3-9b9ff809279f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 44 · 2026-05-17T02:06:00.305Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RYxswFcU6UrAegJuNn4cBf`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e1f85888-d681-4969-af9d-61eb4d001bdf",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kfety15oc6ra72kXja",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "84651960-28e5-4aef-96f4-80041c2a974e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019M7JdrArhMQvzGALYDYZCv",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 58640,
      "output_tokens": 194,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1215
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 194,
          "cache_read_input_tokens": 58640,
          "cache_creation_input_tokens": 1215,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1215,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-17T02:06:00.336Z_

<details><summary>↩ Tool result · `toolu_01RYxswFcU6UrAegJuNn4cBf`</summary>

```text
1	\section{Related Work}
2	\label{sec:related}
3	
4	\paragraph{Compound compression.}
5	Combining multiple compression axes produces non-additive errors.
6	\cite{spark-aaai2026} report super-additive degradation when combining channel pruning with token eviction; \cite{slim-icml2025} formalize compound error for quantization and sparsity.
7	\cite{unicomp-2026} evaluate compound compression across 40+ benchmarks, revealing that reasoning capabilities degrade disproportionately.
8	\cite{phase-transition-compression-2026} characterize independent phase transition points per compression dimension, implying the joint safe region is the intersection of per-dimension safe zones.
9	GRASPrune~\cite{graspune-acl2026} learns global budget-constrained gates for joint pruning but treats decisions as static across generation.
10	PM-KVQ~\cite{pmkvq-iclr2026} shows that progressive quantization---gradually reducing bit-width over the generation process---mitigates cumulative error in long-CoT reasoning, implicitly introducing a temporal dimension to compression severity that resonates with our finding that compound interaction is phase-dependent.
11	
12	\cite{kim2026pqqp} show that compression order (prune-then-quantize vs.\ quantize-then-prune) substantially affects joint quality, and their Progressive Intensity Hypothesis---that weaker perturbations should precede stronger ones---echoes our dose-response finding that interaction severity increases monotonically with sparsity.
13	
14	These works establish compound interaction but share an implicit assumption: interaction magnitude is constant across the generation process.
15	
16	\paragraph{Structured pruning.}
17	Magnitude pruning~\cite{han-neurips2015} and the lottery ticket hypothesis~\cite{frankle-iclr2019} establish that neural networks contain sparse subnetworks preserving full-model performance.
18	Movement pruning~\cite{sanh-neurips2020} extends this to fine-tuning, learning which weights to zero during task adaptation.
19	For attention heads specifically, \cite{voita-acl2019} show most heads are prunable without degradation, and \cite{michel-neurips2019} demonstrate that head importance varies substantially across layers---findings our head pruning axis builds upon. These methods optimize a single pruning axis in isolation; we characterize the interaction when head pruning operates simultaneously with KV cache eviction.
20	
21	\paragraph{KV cache eviction.}
22	StreamingLLM~\cite{streamingllm-iclr2024} establishes attention sinks as a foundational mechanism; DuoAttention~\cite{duoattention-2024} classifies heads into retrieval and streaming types, complementing our analysis of importance discrimination collapse (\S\ref{sec:discrimination-collapse-main}). Subsequent work improves eviction through per-head adaptive budgets \cite{adakv-neurips2025}, observation-window compression \cite{snapkv-neurips2024}, proxy-token strategies \cite{nacl-acl2024}, deferred importance \cite{retentivekv-2026}, and worst-case analysis \cite{defensivekv-iclr2026}; \cite{greedy-bias-kvcache-2026} show that single importance metrics exhibit systematic greedy bias. \cite{hies-2025} independently show that importance discrimination collapses under heavy single-axis pruning; our results extend this to the compound setting, revealing phase-modulated amplification and a strategy crossover (\S\ref{sec:crossover}) absent in single-axis analysis.
23	Recent approaches target reasoning-aware eviction \cite{rlkv-2025, longflow-2026, dong2026foresightkv}, temporal adaptivity \cite{lethe-aaai2026}, channel-level pruning \cite{xu2025think, spark-aaai2026}, and learned budgets \cite{lkv-2026}. Concurrent work~\citep{hold-onto-thought-neurips2025} evaluates single-axis compression on mathematical reasoning; we extend to the compound setting.
24	These methods each optimize a single pruning axis without characterizing compound interactions.
25	
26	\paragraph{Phase-aware inference and reasoning.}
27	ThinKV~\cite{thinkv-iclr2026} applies different KV strategies per phase but without compound interaction.
28	\cite{decision-repr-transition-2026} find pruning sensitivity depends on ``silent'' vs.\ ``decisive'' representation phases.
29	\cite{doing-more-with-less-2026} show pruning combined with test-time scaling can exceed unpruned baselines; \cite{sparse-frontier-2025} find no universally optimal sparse attention strategy across generation stages.
30	\cite{physics-kvcache-2026} identify a sharp phase transition in single-axis KV cache compression at high sparsity, characterizing the single-dimension failure mode that our compound analysis extends across multiple axes.
31	R-KV~\cite{rkv-neurips2025} exploits reasoning-specific redundancy for aggressive cache compression, targeting per-axis optimization rather than characterizing compound degradation.
32	Test-time compute scaling~\cite{snell-2024-scaling-test-time} shows that allocating more inference-time computation can substitute for model scale; this emphasizes the importance of preserving reasoning-phase fidelity, where our work shows compound sparsity is most destructive.
33	ScissorHands~\cite{scissorhands-2023} leverages the persistence of importance hypothesis---that important tokens remain important across generation steps---a property our Gini analysis shows breaks down under compound stress.
34	These works establish phase-dependent compression tolerance along single axes.
35	
36	\paragraph{Conditional computation.}
37	Mixture-of-Experts architectures~\cite{shazeer-2017-moe, fedus-jmlr2022} achieve dynamic sparsity by routing tokens to a subset of parameters, providing a complementary paradigm to post-hoc pruning.
38	MoE sparsity is \emph{designed} (experts are trained to specialize), whereas compound sparsity is \emph{imposed} (pruning removes capacity without retraining).
39	Our phase-strategy interaction findings suggest that designed sparsity and imposed sparsity may interact differently across reasoning phases---a connection we leave to future work.
40	
41	\paragraph{Positioning.}
42	Our work bridges the compound compression and phase-aware literatures by quantifying how compound severity varies across phases and eviction strategies. Key differentiators: SparK~\cite{spark-aaai2026} characterizes compound interaction magnitude but treats it as phase-invariant; ThinKV~\cite{thinkv-iclr2026} adapts per phase but considers only single-axis KV compression without compound interaction; HIES~\cite{hies-2025} identifies importance score collapse under single-axis pruning but does not quantify its role in compound settings or its phase dependence. Our strategy specificity finding---that random eviction produces near-zero phase gradients while importance-based eviction exhibits $15$--$17{\times}$ amplification---is non-obvious: the \emph{a priori} expectation is that any eviction strategy operating on phase-structured attention should produce some phase gradient, yet random eviction yields effectively none at $s \leq 0.20$. The quantitative dose-response characterization provides target operating points for phase-aware compression controllers.
43	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84651960-28e5-4aef-96f4-80041c2a974e",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "88a47f7b-e30c-479e-b700-0dee0f0f381a",
  "sourceToolAssistantUUID": "84651960-28e5-4aef-96f4-80041c2a974e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 46 · 2026-05-17T02:06:03.562Z_

Now I have sufficient information to write the review. Let me also check for any "Table 7" or "simulated reviewer" content that might be in the dream reports.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "88a47f7b-e30c-479e-b700-0dee0f0f381a",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KfzVwKWWLSWznsQRBk",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "92638246-de17-4ad7-a7a8-ccb2e900657f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R6k48QDDqr3LQMcZtD17xY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 59855,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2075,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-17T02:06:04.521Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Ag2pwE2VyMGAoYKyvdy5jf`</summary>

```json
{
  "pattern": "Simulated Reviewer|Table 7|reviewer assessment",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts",
  "-i": true,
  "output_mode": "files_with_matches"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "92638246-de17-4ad7-a7a8-ccb2e900657f",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KfzVwKWWLSWznsQRBk",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3eb7bc7b-6921-4d90-8e28-342117827769",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R6k48QDDqr3LQMcZtD17xY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 59855,
      "output_tokens": 189,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2075
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 189,
          "cache_read_input_tokens": 59855,
          "cache_creation_input_tokens": 2075,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2075,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-17T02:06:04.564Z_

<details><summary>↩ Tool result · `toolu_01Ag2pwE2VyMGAoYKyvdy5jf`</summary>

```text
Found 43 files
artifacts/dream_reports/dream_20260517T013445/logs/review_median.log
artifacts/dream_reports/dream_20260517T013445/logs/review_best.log
artifacts/dream_reports/dream_20260517T013445/best/review_report.md
artifacts/dream_reports/dream_20260517T013445/logs/paper_agent_worst.log
artifacts/dream_reports/dream_20260517T013445/worst/experiment_data.json
artifacts/dream_reports/dream_20260517T013445/worst/imagined_experiments.yaml
artifacts/dream_reports/dream_20260517T013445/logs/paper_agent_median.log
artifacts/dream_reports/dream_20260517T013445/median/paper.aux
artifacts/dream_reports/dream_20260517T013445/median/paper.tex
artifacts/dream_reports/dream_20260517T013445/logs/phase2_worst_attempt0.log
artifacts/dream_reports/dream_20260517T005655/logs/paper_agent_best.log
artifacts/dream_reports/dream_20260517T005655/logs/phase1_attempt0.log
artifacts/dream_reports/dream_20260516T164305/meta.yaml
artifacts/dream_reports/dream_20260516T164305/logs/review_worst.log
artifacts/dream_reports/dream_20260516T164305/worst/review_report.md
artifacts/dream_reports/dream_20260516T164305/logs/review_median.log
artifacts/dream_reports/dream_20260516T164305/median/review_report.md
artifacts/dream_reports/dream_20260516T164305/median/review_context.yaml
artifacts/dream_reports/dream_20260516T164305/logs/review_best.log
artifacts/dream_reports/dream_20260516T164305/logs/paper_agent_median.log
artifacts/dream_reports/dream_20260516T164305/median/experiment_data.json
artifacts/dream_reports/dream_20260516T164305/median/imagined_experiments.yaml
artifacts/dream_reports/dream_20260516T164305/logs/phase2_worst_attempt0.log
artifacts/dream_reports/dream_20260516T164305/logs/phase2_median_attempt0.log
artifacts/dream_reports/dream_20260516T150210/meta.yaml
artifacts/dream_reports/dream_20260516T150210/logs/review_median.log
artifacts/dream_reports/dream_20260516T150210/logs/review_best.log
artifacts/dream_reports/dream_20260516T150210/best/review_report.md
artifacts/dream_reports/dream_20260516T073742/logs/review_worst.log
artifacts/dream_reports/dream_20260516T073742/logs/review_median.log
artifacts/dream_reports/dream_20260516T073742/logs/review_best.log
artifacts/review_reports/round_9.md
artifacts/review_reports/round_5.md
artifacts/paper_update_checklist.md
artifacts/n500_paper_update_FINAL.md
artifacts/_project/report/visual_review_report.md
artifacts/_project/report/number_audit_final.md
artifacts/review_reports/round_3.md
artifacts/consistency_audit_final.md
artifacts/dream_reports/dream_20260514T054026/meta.yaml
artifacts/dream_reports/dream_20260514T054026/median/experiment_data.json
artifacts/dream_reports/dream_20260514T054026/median/imagined_experiments.yaml
artifacts/dream_reports/dream_20260514T054026/logs/phase2_median_attempt0.log
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3eb7bc7b-6921-4d90-8e28-342117827769",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "de918db4-c682-464c-82d8-1f8fa1ff0e3e",
  "sourceToolAssistantUUID": "3eb7bc7b-6921-4d90-8e28-342117827769",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 49 · 2026-05-17T02:06:08.496Z_

The "Simulated Reviewer Assessment" (Table 7) mentioned in the review task prompt does not appear in the current paper source files. It may have been removed or is from a dream report version. This is noted in my review. Now I have all the information needed to write a comprehensive review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "de918db4-c682-464c-82d8-1f8fa1ff0e3e",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KgJWtzyxXFe6NYHVKQ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "87d5fc6e-23d8-40fe-a1a7-a1ca19f6b72a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp14crq5GoD7ArgcsGKMzQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1123,
      "cache_read_input_tokens": 61930,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1123,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool call

_source line 50 · 2026-05-17T02:06:09.666Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_015ofWjrpoXN1gzxGbG7M4BM`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__submit_dream_review_report",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "87d5fc6e-23d8-40fe-a1a7-a1ca19f6b72a",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KgJWtzyxXFe6NYHVKQ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a02f755d-0ac4-4a8c-b6d2-cfea9ac59312",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vp14crq5GoD7ArgcsGKMzQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1123,
      "cache_read_input_tokens": 61930,
      "output_tokens": 153,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1123
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 153,
          "cache_read_input_tokens": 61930,
          "cache_creation_input_tokens": 1123,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1123,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 51 · 2026-05-17T02:06:09.678Z_

<details><summary>↩ Tool result · `toolu_015ofWjrpoXN1gzxGbG7M4BM`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__submit_dream_review_report"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a02f755d-0ac4-4a8c-b6d2-cfea9ac59312",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "e3a45361-0d57-4838-afab-eb05d79029fc",
  "sourceToolAssistantUUID": "a02f755d-0ac4-4a8c-b6d2-cfea9ac59312",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-17T02:06:12.593Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01276AWBbcp4pKEqgRGfN6QV`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__director_post_to_reviewer",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e3a45361-0d57-4838-afab-eb05d79029fc",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7KggdBM8j2a1kK8PSbw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ae527937-6e97-4a15-bdfc-fd49c4ef6f46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011JurzT8LoH7bVLcByup8sf",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 731,
      "cache_read_input_tokens": 63053,
      "output_tokens": 90,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 731
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 90,
          "cache_read_input_tokens": 63053,
          "cache_creation_input_tokens": 731,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 731,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---

### Tool result

_source line 53 · 2026-05-17T02:06:12.600Z_

<details><summary>↩ Tool result · `toolu_01276AWBbcp4pKEqgRGfN6QV`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__director_post_to_reviewer"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ae527937-6e97-4a15-bdfc-fd49c4ef6f46",
  "isSidechain": true,
  "promptId": "84996b19-2176-4b89-ae31-f038395cdf51",
  "agentId": "a87a0108a1f10e610",
  "type": "user",
  "uuid": "6257cce8-9d20-432c-9bfe-cfb8880d1bb0",
  "sourceToolAssistantUUID": "ae527937-6e97-4a15-bdfc-fd49c4ef6f46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 54 · 2026-05-17T02:07:14.986Z_

Based on my thorough reading of the paper, here is my review as Reviewer R1 (Methods and Experiments focus):

---

## Review: Phase-Gated Compound Sparsity

### Summary

The paper introduces a phase-gated analysis framework for compound sparsity (simultaneous attention head pruning + KV cache eviction) in LLM inference. The core finding is that compound interaction severity increases monotonically from high-sparsity phases (concentrated attention, verification) to low-sparsity phases (distributed attention, exploration), and that this gradient is specific to attention-score-based eviction strategies. The paper tests across 3 models, 2 architectures, 3 benchmarks, and 4 sparsity levels.

---

### Strengths

- **Well-defined interaction metric.** The Interaction Index (II = r_b - r_a - r_k + 1) is a clean, interpretable factorial decomposition. Testing under both additive and multiplicative nulls (Appendix A) strengthens the claim that findings are null-specification invariant.

- **Strong experimental controls.** The three-way comparison (importance / random / recency) is the paper's strongest methodological contribution. The recency control elegantly isolates the attention-score pathway from generic token removal, ruling out segmentation artifact and positional confounds.

- **Thorough robustness analysis.** Phase segmentation is validated against multiple granularities (tercile/quartile/quintile), minimum phase lengths (5/10/20), and model-intrinsic think-token boundaries (kappa=0.88). Asymmetric sparsity spot-checks and outlier winsorization further support robustness.

- **Appropriate statistical framework.** Nonparametric tests (Wilcoxon, Mann-Whitney, Jonckheere-Terpstra) are well-matched to the heavy-tailed II distributions (mean/median ratios up to 43:1). Bootstrap CIs with B=10,000, Bonferroni correction with BH-FDR cross-check, and paired within-subject designs are all methodologically sound.

- **Honest reporting of negative results.** The pilot mitigation experiment (18% oracle recovery, CI spanning zero, gate status: FAIL) and the frank acknowledgment that Gini collapse alone cannot explain the 15-17x severity divergence demonstrate scientific integrity.

- **Cross-architecture validation.** Testing on LlamaForCausalLM (n=250) provides evidence that the phase gradient generalizes beyond Qwen2, even though strategy specificity is architecture-dependent.

---

### Weaknesses

- **Incomplete GPQA and 14B results.** Table 4 (GPQA) and Table 3 (Qwen2.5-14B) contain only placeholder dashes ("---") with "Results pending." These sections are referenced in the contributions and abstract framing but provide zero data. A paper submitted with placeholder tables is incomplete. The GPQA section claims evaluation on "both models" but even the report.md shows only DS-7B experiments were attempted. This significantly undermines the cross-benchmark generalization claim.

- **GSM8K sample size and approximate reporting.** GSM8K uses only n=50, yielding wide CIs (e.g., Delta=4.68 [2.12, 10.56] at s=0.30) and insufficient power to detect random-eviction effects (minimum detectable d >= 0.40). The paper appropriately notes this but then draws strong conclusions about "strategy specificity attenuation" from what are essentially underpowered null results. Random eviction point estimates on GSM8K are actually sizable (Delta=2.85 at s=0.30) but non-significant due to low n. This is absence of evidence, not evidence of absence.

- **Potential circularity in phase segmentation.** Phases are defined by attention sparsity on the dense model, and the II metric measures perplexity degradation under sparsity conditions that alter attention patterns. While the recency control partially addresses this, the fundamental concern remains: tokens with broadly distributed attention (low-sparsity phase) are mechanistically more vulnerable to importance-based eviction because importance scoring depends on attention mass concentration. The "finding" may partially be a tautology: removing tokens by attention importance hurts more when attention is broadly distributed because there is less redundancy to exploit. The paper acknowledges this ("amplifies a pre-existing computational asymmetry") but does not sufficiently distinguish between a trivial prediction and a novel finding.

- **Recency control limited scope.** Recency eviction was tested at n=100 (vs. n=500 for main experiments) and only at s={0.15, 0.25, 0.30} with the s=0.30 result deemed "numerically unreliable." The paper claims this as a major contribution but the evidence base is thin compared to the primary experiments. Furthermore, recency eviction produces a qualitatively different compression pattern (always removes old tokens, which may have different information-theoretic properties than removing low-importance tokens), making it an imperfect control for the specific question of whether the gradient is score-specific vs. removal-specific.

- **No downstream task evaluation integrated with phase analysis.** The accuracy validation (Section 5.10) is entirely aggregate (per-problem accuracy). The paper cannot show that the per-phase PPL gradient translates to per-phase reasoning quality differences. The claim that low-sparsity phases suffer "silent reasoning errors" is speculative without per-phase accuracy decomposition.

- **Fixed head pruning strategy.** The paper varies KV eviction strategy (importance/random/recency) but always uses Frobenius-norm head pruning. The interaction between head pruning strategy and the phase gradient is unexplored. Would random head pruning produce the same discrimination collapse? Would magnitude-based or gradient-based head selection alter the phase gradient?

- **Qwen GSM8K data quality.** The Qwen GSM8K data is acknowledged as unreliable due to generation truncation (max_new_tokens=2047), yet directional claims are still made from it. Table in Appendix shows anomalous values (Delta=-1.58 for random s=0.15; Delta=11.1 for random s=0.25, both ns). This raises concerns about data quality for an entire experimental condition.

---

### Questions for Authors

1. **Circularity concern:** The phase segmentation identifies tokens where attention is broadly distributed. Under importance-based eviction, broadly-distributed attention means importance scores are more uniform, making eviction decisions more noise-sensitive. Is the monotonic phase gradient not a direct, mechanistically trivial consequence of this? What is the novel empirical content beyond "eviction-by-importance hurts more when importance scores are less discriminative"?

2. **GPQA and 14B data:** When will Tables 3 and 4 be completed? The paper currently claims cross-benchmark generalization without supporting data for GPQA.

3. **Head pruning variation:** Have you considered testing random head pruning or other head selection criteria? The current design cannot distinguish whether the phase gradient arises from the head pruning strategy, the KV eviction strategy, or their specific combination.

4. **Practical significance of the II metric:** The II values range from 0.003 to 8.48 (perplexity ratio units). What does an II of 8.48 mean in terms of generation quality? The accuracy validation shows severe degradation at s=0.30, but the connection between specific II values and downstream impact is not established.

5. **Why not test the phase-aware allocation as a proper experiment?** The pilot mitigation (n=30) failed its own pre-registered gate. Without demonstrating that phase-aware allocation improves anything, the paper is purely diagnostic. Is there any evidence this diagnostic has engineering value beyond what "use less sparsity during reasoning" already provides?

---

### Detailed Scores

| Criterion | Score | Justification |
|-----------|-------|---------------|
| **Soundness** | 3/4 | The II metric is well-defined and the factorial design is appropriate. Statistical methods are sound. However, potential circularity in phase segmentation weakens causal interpretability, and placeholder tables represent incomplete experiments. |
| **Significance** | 2/4 | The finding that attention-score-based eviction is more harmful during broadly-distributed-attention phases is mechanistically expected. The quantification is novel but the practical implication ("use less sparsity during reasoning phases") is obvious. The failed mitigation pilot undermines engineering utility. |
| **Clarity** | 3.5/4 | Well-written with clear statistical reporting. Limitations are honestly discussed. The paper is long and some appendix material could be better integrated. |
| **Overall** | 4 (Weak Accept) | |

---

### Overall Assessment

The paper presents a thorough empirical characterization with strong statistical methodology and appropriate controls. The recency control is a genuine methodological contribution. However, three issues prevent a stronger recommendation: (1) incomplete experiments (GPQA placeholder tables, 14B placeholder), (2) potential tautological element in the core finding (importance-based eviction hurts more in phases where importance scores are less discriminative, which is mechanistically expected), and (3) absence of demonstrated practical utility (failed mitigation pilot). The paper is above average in rigor but below the bar for a top venue in terms of novelty and completeness.

**Confidence: 4/5** (confident in the assessment; familiar with the KV cache compression and structured pruning literatures; the statistical methodology is within my expertise).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6257cce8-9d20-432c-9bfe-cfb8880d1bb0",
  "isSidechain": true,
  "agentId": "a87a0108a1f10e610",
  "requestId": "req_011Cb7Kgu5nDrsHvpvmDSbrF",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bb1fa4f2-da3e-4e74-9cfc-dcf606733f75",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "f46d8a0d-9101-4daf-83a4-2cd94cb2633d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AimpREU4nJkzkLsFUNt2Dd",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 500,
      "cache_read_input_tokens": 63784,
      "output_tokens": 2210,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 500
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 2210,
          "cache_read_input_tokens": 63784,
          "cache_creation_input_tokens": 500,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 500,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "diagnostics": null
  }
}
```

</details>

---
