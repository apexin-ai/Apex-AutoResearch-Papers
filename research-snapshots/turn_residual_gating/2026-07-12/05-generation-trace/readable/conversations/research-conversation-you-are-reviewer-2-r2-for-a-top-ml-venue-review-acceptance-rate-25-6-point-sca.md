# Research conversation: You are Reviewer 2 (R2) for a top ML venue review (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 6=Strong Accept

**Exposure Bias Collapses Auxiliary Attention Losses in Multi-Turn Dialogue (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 28
- **Recorded user turns:** 1
- **Tool calls:** 12
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-a0f61c367bd26458b.jsonl`
- **Structured JSON:** [`52eb5424d27c4c1874a3.json`](../../sessions/52/52eb5424d27c4c1874a3.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

28 recorded events

### User

_source line 1 · 2026-05-17T01:19:51.422Z_

You are Reviewer 2 (R2) for a top ML venue review (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 6=Strong Accept). Your focus is **Novelty and Related Work**: significance of contributions, positioning against prior work, related work coverage, and whether the paper advances the field meaningfully.

## Paper Summary

Title: "Phase-Gated Compound Sparsity: Reasoning Phase Modulates the Severity of Pruning-Eviction Interactions in Large Language Models"

The paper studies compound sparsity (simultaneous attention head pruning + KV cache eviction) and claims the interaction severity depends on reasoning phase and eviction strategy. It is explicitly an empirical finding paper, not a method paper.

Key contributions:
1. Discovery that compound sparsity severity is an emergent property of strategy × phase interaction
2. Introduction of recency-based eviction as a scoring-independent control for triple dissociation
3. Proposed "discrimination collapse" mechanism
4. Cross-model, cross-architecture, cross-benchmark validation

## Related Work Section (from paper)

The paper covers:
- **Compound Sparsity**: SparK (2024), SLiM (2024) — joint pruning+compression, uniform interaction assumption. Paper claims phase-modulated interaction.
- **Phase-Aware KV Compression**: ThinKV (2025), R-KV (2025) — single-axis phase-aware methods. Paper claims compound (two-axis) phase-dependent behavior.
- **Importance Score Dynamics**: HIES (2025) — importance score collapse under compression, entropy compensation. Physics-KV (2026) — phase transitions in compression rate. Paper claims independent support for discrimination collapse.
- **Adaptive Eviction**: Lethe (2026), Ada-KV (2024) — method papers. Paper positions itself as empirical finding paper.

Total references: ~10 papers cited (Ada-KV, H2O, HIES, Lethe, Physics-KV, R-KV, SLiM, SparK, StreamingLLM, ThinKV).

## Methods Summary

- Interaction Index: II_i = PPL_both - (PPL_prune + PPL_evict - PPL_base)
- Phase segmentation by per-token perplexity tertiles from uncompressed model
- Triple dissociation: importance (scoring-dependent) vs recency (scoring-independent) vs random (structure-independent)
- 3 models, 2 architectures, 3 benchmarks, sparsity s ∈ {0.15, 0.20, 0.25, 0.30}

## Key Results

- Importance-based eviction: monotonically increasing phase gradients (dz 0.57→1.13)
- Recency: consistently null (dz ≤ 0.15)
- Random: null to small (dz ≤ 0.18)
- Cross-benchmark (GPQA): dose-response confirmed, strategy specificity 4.2×
- Architecture-dependent: Qwen2 specificity 15-17×, Llama 2.0-2.6×
- Discrimination collapse: Gini/CV decline (correlational)

## Discussion/Limitations from paper

- 7B scale only
- Strategy specificity is benchmark-specific (MATH-500 15-17× vs GSM8K 2.3-3.8×)
- Discrimination collapse is correlational, not causal
- Phase detection at inference time not addressed (offline segmentation only)
- Mitigation pilot shows directional but not practically significant results

## Your Task

Write a detailed review covering:
1. **Summary** (2-3 sentences)
2. **Strengths** (bullet points, focus on novelty, significance, positioning)
3. **Weaknesses** (bullet points, focus on novelty, related work gaps, significance concerns)
4. **Questions for Authors** (specific, actionable)
5. **Minor Issues**
6. **Scores**: Overall (1-6), Novelty (1-5), Presentation (1-5), Confidence (1-5)

Be rigorous. Consider: Is the triple dissociation genuinely novel or an obvious control? Is recency control really a "methodological innovation"? How significant is the finding for the field? Is the related work coverage sufficient for a top venue? Are there important missing references (e.g., GQA/MQA work, other KV compression methods, reasoning-phase analysis papers)? Is the paper positioned correctly as an "empirical finding" paper? Does the lack of a method contribution limit venue fit? Is "discrimination collapse" a genuine mechanistic insight or a restatement of known phenomena (HIES already described score collapse)?

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "ece46d50-ef5f-4f8c-a095-f4d5f9a933f5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-17T01:19:51.426Z_

```json
{
  "parentUuid": "ece46d50-ef5f-4f8c-a095-f4d5f9a933f5",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
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
  "uuid": "46ea64ab-c193-4e96-9eb4-f7a802b08fd6",
  "timestamp": "2026-05-17T01:19:51.426Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Tool call

_source line 3 · 2026-05-17T01:19:54.710Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01Szgi3nU2cAQ7N7mM5bxqeT`</summary>

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
  "parentUuid": "46ea64ab-c193-4e96-9eb4-f7a802b08fd6",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7G9tAkMmZdmx7saVhtE",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "51221d69-3ebb-4cb5-9e23-2c1f66cfe821",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01B1tDQeUYJUEr8yYiZZjVEP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 8208,
      "cache_read_input_tokens": 8252,
      "output_tokens": 88,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8208
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 88,
          "cache_read_input_tokens": 8252,
          "cache_creation_input_tokens": 8208,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8208,
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

_source line 4 · 2026-05-17T01:19:54.719Z_

<details><summary>↩ Tool result · `toolu_01Szgi3nU2cAQ7N7mM5bxqeT`</summary>

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
  "parentUuid": "51221d69-3ebb-4cb5-9e23-2c1f66cfe821",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "1230aac3-9c39-4a15-bba7-f5099c9afa28",
  "sourceToolAssistantUUID": "51221d69-3ebb-4cb5-9e23-2c1f66cfe821",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-17T01:19:58.420Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_014zDDo3CGvXhSyaZesRKgHW`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "report.md",
  "max_chars": 12000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1230aac3-9c39-4a15-bba7-f5099c9afa28",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GA8J4GMfVaB4QdE8mP",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "092b030e-6e4c-4e37-8bce-d9a37c8461a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GNd6vLtfYD5kM8TH9PBRkt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1270,
      "cache_read_input_tokens": 16460,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1270,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 50,
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

_source line 6 · 2026-05-17T01:19:58.435Z_

<details><summary>↩ Tool result · `toolu_014zDDo3CGvXhSyaZesRKgHW`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/report.md\", \"content\": \"# Handover — 2026-05-17\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| gpqa_ds_random_s020 | Cross-task generalization: random eviction control on GPQA Diamond. DS-R1 random s020 to establish baseline phase gradient (expected NS or weak) for strategy specificity comparison. | — | — | — |\\n| gpqa_ds_importance_s030 | Cross-task generalization: compound sparsity severity monotonically increases on GPQA Diamond (non-math reasoning) using quantile 3-segment phase decomposition. DS-R1 importance s030 as fourth condition. | — | — | — |\\n| gpqa_ds_importance_s025 | Cross-task generalization: compound sparsity severity monotonically increases on GPQA Diamond (non-math reasoning) using quantile 3-segment phase decomposition. DS-R1 importance s025 as third condition (after s015 success, s020 running). | — | — | — |\\n\\n## 待处理\\n（无）\\n\\n## 近期结论\\n- **recency_s025** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.25 condition.\\n  [recency_s025_analysis](/api/workspace-files/projects/phase-gated-compound-sparse/artifacts/recency_s025/report/analysis.md)\\n- **recency_s030** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.30 condition.\\n  [recency_s030_analysis](/api/workspace-files/projects/phase-gated-compound-sparse/artifacts/recency_s030/report/analysis.md)\\n- **recency_s015** (success): Recency-based (position-only) eviction as scoring-independent control to disentangle phase segmentation circularity and H2O confound from attention-score-specific compound interaction. s=0.15 condition.\\n\\n## 趋势\\n成功 70 / 负向 17 / 失败 17 / 共 134\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-22162: 无 GPU 信息\\n\\n## 告警\\n- mvp_interaction_index_profiling: 训练失败 — unknown\\n- mvp_ii_profiling_v4: 训练失败 — unknown\\n- mvp_ii_profiling_v4b: 训练失败 — unknown\\n- mvp_ii_profiling_v4c: 训练失败 — unknown\\n- mvp_ii_profiling_v4d: 训练失败 — unknown\\n- mvp_ii_profiling_v4-random: 训练失败 — unknown\\n- mvp_v4a_r2: 训练失败 — unknown\\n- mvp_v4b_r2: 训练失败 — unknown\\n- mvp_v4c_r2: 训练失败 — unknown\\n- mvp_v4_legacy_s025: 训练失败 — unknown\\n- mvp_v4_legacy_s035: 训练失败 — unknown\\n- mvp_v4_float32_s030: 已被终止 — unknown\\n- mvp_v5_fixed_s020: 已被终止 — unknown\\n- mvp_v5_fixed_s030: 已被终止 — unknown\\n- qwen_importance_s015: 已被终止 — unknown\\n- qwen_importance_s020: 已被终止 — unknown\\n- qwen_importance_s025: 已被终止 — unknown\\n- qwen_importance_s030: 已被终止 — unknown\\n- v6_random_s030: 训练失败 — unknown\\n- v6_random_s030_r2: 训练失败 — unknown\\n- bf16_random_s015: 已被终止 — unknown\\n- bf16_random_s020: 已被终止 — unknown\\n- bf16_random_s025: 已被终止 — unknown\\n- bf16_random_s030: 已被终止 — unknown\\n- bf16_qwen_importance_s015: 已被终止 — unknown\\n- bf16_qwen_importance_s020: 已被终止 — unknown\\n- bf16_qwen_importance_s025: 已被终止 — unknown\\n- bf16_qwen_importance_s030: 已被终止 — unknown\\n- bf16_ds_imp_s015: 已被终止 — unknown\\n- bf16_ds_imp_s020: 已被终止 — unknown\\n- bf16_ds_imp_s025: 已被终止 — unknown\\n- bf16_ds_imp_s030: 已被终止 — unknown\\n- c3_llama_arch: 已被终止 — unknown\\n- c2_ds_n500: 已被终止 — unknown\\n- c2_qw_n500: 训练失败 — unknown\\n- r9c2-spike: 已被终止 — unknown\\n- r9c2-spike-v2: 已被终止 — unknown\\n- r9c2-spike-v3: 已被终止 — unknown\\n- acc_ds_dense_8k: 已被终止 — unknown\\n- acc_ds_s015_8k: 已被终止 — unknown\\n- acc_ds_s020_8k: 已被终止 — unknown\\n- acc_ds_s025_8k: 已被终止 — unknown\\n- acc_ds_s030_8k: 已被终止 — unknown\\n- gsm8k_qw_rand_s025: 训练失败 — unknown\\n- gsm8k_qw_rand_s030: 训练失败 — unknown\\n- c8_llama_n250: 训练失败 — unknown\\n- c10-lang-s020-s025: 已被终止 — unknown\\n\", \"total_chars\": 3667, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "092b030e-6e4c-4e37-8bce-d9a37c8461a4",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "23f0f86f-4832-4a56-b31d-d9a3e4f9d700",
  "sourceToolAssistantUUID": "092b030e-6e4c-4e37-8bce-d9a37c8461a4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-17T01:19:58.855Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01LpNgERx7fPUL3DzeUcw9jY`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "literature_map.yaml",
  "max_chars": 12000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "23f0f86f-4832-4a56-b31d-d9a3e4f9d700",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GA8J4GMfVaB4QdE8mP",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "31b32f67-a33e-423d-82e1-cfeae1381ec8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GNd6vLtfYD5kM8TH9PBRkt",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1270,
      "cache_read_input_tokens": 16460,
      "output_tokens": 206,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1270
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 206,
          "cache_read_input_tokens": 16460,
          "cache_creation_input_tokens": 1270,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1270,
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

_source line 8 · 2026-05-17T01:19:58.871Z_

<details><summary>↩ Tool result · `toolu_01LpNgERx7fPUL3DzeUcw9jY`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/literature_map.yaml\", \"content\": \"## Literature Map — Phase-Gated Compound Sparsity\\n## 增量扫描: 2026-05-14\\n\\n# ============================================================\\n# 已知文献（baseline）\\n# ============================================================\\n\\n- paper_id: spark-aaai2026\\n  title: \\\"SparK: Query-Aware Unstructured Sparsity with Recoverable KV Cache Channel Pruning\\\"\\n  venue: AAAI 2026\\n  year: 2026\\n  category: direct-competitor\\n  relevance: 首篇报告 compound sparsity 总是 super-additive（ThinK+SnapKV 退化 65%），核心对标\\n  key_finding: compound KV cache sparsity (channel + token) 产生 super-additive degradation\\n\\n- paper_id: thinkv-iclr2026\\n  title: \\\"ThinKV\\\"\\n  venue: ICLR 2026 Oral\\n  year: 2026\\n  category: method-component\\n  relevance: phase 划分思想来源，但只做单一压缩策略\\n  key_finding: KV cache 可按 phase 划分应用不同策略\\n\\n- paper_id: rac-neurips2025\\n  title: \\\"RAC\\\"\\n  venue: NeurIPS 2025\\n  year: 2025\\n  category: background\\n  relevance: reasoning model 对 sparsity 更敏感，支撑评估任务选择\\n  key_finding: reasoning model 对 sparsity 敏感度高于一般 LLM\\n\\n- paper_id: raas-acl2025\\n  title: \\\"RaaS\\\"\\n  venue: ACL 2025\\n  year: 2025\\n  category: method-component\\n  relevance: milestone tokens 先重要后衰减，支撑 phase-dependent importance\\n  key_finding: token importance 随 decoding phase 非单调变化\\n\\n- paper_id: mixeddimkv-2026\\n  title: \\\"MixedDimKV\\\"\\n  year: 2026\\n  category: method-component\\n  relevance: multi-dimension compression budget allocation，与 joint controller 思路平行\\n  key_finding: 多维度压缩 budget allocation 优于均匀分配\\n\\n# ============================================================\\n# 新增 — Compound / Joint Compression Interaction\\n# ============================================================\\n\\n- paper_id: slim-icml2025\\n  title: \\\"SLiM: One-shot Quantization and Sparsity with Low-rank Approximation for LLM Weight Compression\\\"\\n  authors: Mozaffari et al.\\n  venue: ICML 2025\\n  year: 2025\\n  category: method-component\\n  relevance: 首个正式处理 compound compression error 的框架——用 low-rank adapter 补偿 Q+S 聚合误差，证明误差非加性\\n  key_finding: quantization + sparsity 聚合误差非加性；invertible saliency function 精确计算 low-rank 补偿\\n\\n- paper_id: unicomp-2026\\n  title: \\\"UniComp: A Unified Evaluation of Large Language Model Compression via Pruning, Quantization and Distillation\\\"\\n  authors: Wang et al.\\n  venue: arXiv 2602.09130\\n  year: 2026\\n  category: evaluation\\n  relevance: 40+ benchmarks 系统评估 compound compression，发现 compression 有 consistent knowledge bias\\n  key_finding: compression 对 knowledge-intensive tasks 保留好但 reasoning/multilingual 显著退化；quantization 整体 trade-off 最佳\\n\\n- paper_id: compression-ordering-2025\\n  title: \\\"A Systematic Study of Compression Ordering for Large Language Models\\\"\\n  venue: arXiv 2511.19495\\n  year: 2025\\n  category: background\\n  relevance: 证明 compound compression ordering 显著影响结果，early quantization 造成不可逆信息损失\\n  key_finding: P→KD→Q 最优；quantization first 产生不可逆退化；interaction 依赖 ordering\\n\\n- paper_id: phase-transition-compression-2026\\n  title: \\\"Phase Transitions in Large Language Model Compression\\\"\\n  authors: Ma et al.\\n  venue: npj Artificial Intelligence (Nature), 2026\\n  year: 2026\\n  category: background\\n  relevance: 直接支撑 phase-gating 理论动机——不同压缩维度有独立 phase transition point，联合安全区可叠加\\n  key_finding: structured pruning 30-45% 崩溃，unstructured 55-65%；多维度 PTP 正交，联合安全区可实现 10% 压缩\\n\\n- paper_id: graspune-acl2026\\n  title: \\\"GRASPrune: Global Gating for Budgeted Structured Pruning of Large Language Models\\\"\\n  authors: Wang et al.\\n  venue: ACL 2026 Main\\n  year: 2026\\n  category: direct-competitor\\n  relevance: 最直接 competitor——联合 pruning FFN channels + KV head groups with learned gate scores under global budget\\n  key_finding: learned gate + projected STE 全局 budget 下联合 prune FFN+heads，高压缩比下显著优于逐层独立 pruning\\n\\n- paper_id: mustafar-neurips2025\\n  title: \\\"MUSTAFAR: Promoting Unstructured Sparsity for KV Cache Pruning in LLM Inference\\\"\\n  authors: Joo et al.\\n  venue: NeurIPS 2025\\n  year: 2025\\n  category: method-component\\n  relevance: per-token magnitude pruning 70% sparsity 无损，与 token eviction 可组合——potential compound baseline\\n  key_finding: unstructured KV sparsity (per-token magnitude) 70% 无损，bitmap 格式 2.23x throughput\\n\\n# ============================================================\\n# 新增 — Non-monotonic / Sign Reversal / Phase Effects\\n# ============================================================\\n\\n- paper_id: decision-repr-transition-2026\\n  title: \\\"Understanding Performance Collapse in Layer-Pruned LLMs via Decision Representation Transitions\\\"\\n  venue: arXiv 2605.07271\\n  year: 2026\\n  category: background\\n  relevance: layer pruning 存在 Silent/Decisive Phase 二分——pruning 敏感度 phase-dependent，直接支撑 phase-gated 思想\\n  key_finding: Decision Margin 在 Transition Point 发生符号反转（负→正）；pruning Silent Phase 崩溃，Decisive Phase 可安全 prune\\n\\n- paper_id: doing-more-with-less-2026\\n  title: \\\"Doing More With Less: Revisiting the Effectiveness of LLM Pruning for Test-Time Scaling\\\"\\n  venue: arXiv 2604.25098\\n  year: 2026\\n  category: background\\n  relevance: 符号反转直接证据——unstructured pruning + TTS 可超越未剪枝模型\\n  key_finding: unstructured pruning + test-time scaling 可超越 unpruned baseline（Qwen3-8B）；structured pruning 严重退化\\n\\n- paper_id: sparse-frontier-2025\\n  title: \\\"The Sparse Frontier: Sparse Attention Trade-offs in Transformer LLMs\\\"\\n  venue: arXiv 2504.17768\\n  year: 2025\\n  category: evaluation\\n  relevance: 最大规模 sparse attention 评估，无通用最优策略，trade-off 依赖 task 和 phase\\n  key_finding: decoding vs prefilling 可承受 sparsity 不同；大模型+高稀疏可优于小模型+密集\\n\\n# ============================================================\\n# 新增 — Adaptive / Learned Controllers\\n# ============================================================\\n\\n- paper_id: obcache-2025\\n  title: \\\"OBCache: Optimal Brain KV Cache Pruning for Efficient Long-Context LLM Inference\\\"\\n  venue: arXiv 2510.07651\\n  year: 2025\\n  category: method-component\\n  relevance: OBD 理论推导 joint K-V saliency score，可作为 importance-based masking 的理论参照\\n  key_finding: 二阶 Taylor 近似推导 joint K-V pruning score；key-pruning 比 value-pruning 影响更大\\n\\n- paper_id: pagedeviction-eacl2026\\n  title: \\\"PagedEviction: Structured Block-wise KV Cache Pruning\\\"\\n  venue: EACL 2026 Findings\\n  year: 2026\\n  category: method-component\\n  relevance: prefill/decode 两阶段不同 eviction 策略，呼应 phase-gated 思想\\n  key_finding: block-wise eviction prefill/decode 分阶段执行，优于 token-level baselines\\n\\n- paper_id: adakv-neurips2025\\n  title: \\\"Ada-KV: Adaptive Budget Allocation for KV Cache Eviction\\\"\\n  venue: NeurIPS 2025\\n  year: 2025\\n  category: method-component\\n  relevance: per-head adaptive budget 分配，与 per-phase budget allocation 正交互补\\n  key_finding: 自适应 per-head KV cache budget 优于均匀分配\\n\\n- paper_id: sol-2026\\n  title: \\\"SOL: Self-Optimizing Language Models — Compute Where it Counts\\\"\\n  venue: arXiv 2605.10875\\n  year: 2026\\n  category: method-component\\n  relevance: learned policy 按 token difficulty 分配 compute，与 learned joint controller 方法论平行\\n  key_finding: 学习 per-token compute allocation policy，easy tokens 少算 hard tokens 多算\\n\\n# ============================================================\\n# 新增 — Phase-Adaptive Dynamic Compression (2026-05-14 scan)\\n# ============================================================\\n\\n- paper_id: twilight-neurips2025\\n  title: \\\"Twilight: Adaptive Attention Sparsity with Hierarchical Top-p Pruning\\\"\\n  authors: Lin, Tang, Yang, Wang, Tang, Tian, Stoica, Han, Gao\\n  venue: NeurIPS 2025 Spotlight\\n  year: 2025\\n  category: method-component\\n  relevance: 证明 fixed budget 次优，per-step adaptive budget 更优；但单轴无 compound interaction\\n  key_finding: top-p 采样思想做 per-step adaptive attention budget，最多 prune 98% tokens\\n\\n- paper_id: lava-emnlp2025\\n  title: \\\"LAVa: Layer-wise KV Cache Eviction with Dynamic Budget Allocation\\\"\\n  authors: Shen, Yuan, Zhang, Wang, Jiang, Nguyen\\n  venue: EMNLP 2025 Findings\\n  year: 2025\\n  category: method-component\\n  relevance: layer budgets 对 generation 重要、head budgets 对 extraction 重要——支撑 task-conditional budget\\n  key_finding: 基于 Layer Attention Output Loss 的 unified eviction + dynamic budget；budget 需求 task-dependent\\n\\n- paper_id: lkv-2026\\n  title: \\\"LKV: End-to-End Learning of Head-wise Budgets and Token Selection for LLM KV Cache Eviction\\\"\\n  venue: arXiv 2605.06676\\n  year: 2026\\n  category: method-component\\n  relevance: 首个端到端可微 budget+selection 联合学习框架；可作 phase-gated controller backbone\\n  key_finding: LKV-H 学 head budget + LKV-T 学 token selection，全面超越启发式方法\\n\\n- paper_id: defensivekv-iclr2026\\n  title: \\\"DefensiveKV: Taming the Fragility of KV Cache Eviction in LLM Inference\\\"\\n  venue: ICLR 2026\\n  year: 2026\\n  category: direct-competitor\\n  relevance: 独立发现 importance-based eviction 的脆弱性——stability assumption 不成立，importance 高度非稳态\\n  key_finding: mean aggregation 在极端情况下 vulnerable；defensive aggregation 控制 worst-case risk，2.3-4.3x 质量损失降低\\n\\n- paper_id: retentivekv-2026\\n  title: \\\"RetentiveKV: State-Space Memory for Uncertainty-Aware Multimodal KV Cache Eviction\\\"\\n  venue: arXiv 2605.04075\\n  year: 2026\\n  category: background\\n  relevance: \\\"Deferred Importance\\\" 现象——token 初始 salience 低但后期变 pivotal，直接支撑 crossover 机制\\n  key_finding: 视觉 tokens 存在 deferred importance——早期不重要晚期关键；单一时刻 importance 评估不可靠\\n\\n- paper_id: pitfalls-kvcache-2025\\n  title: \\\"The Pitfalls of KV Cache Compression\\\"\\n  venue: arXiv 2510.00231\\n  year: 2025\\n  category: background\\n  relevance: multi-instruction 场景下部分指令被压缩严重忽略——condition-dependent failure\\n  key_finding: 特定 instructions 在压缩下退化极快甚至完全被忽略；compression method + order 产生 bias 交互\\n\\n- paper_id: greedy-bias-kvcache-2026\\n  title: \\\"More Than a Quick Glance: Overcoming the Greedy Bias in KV-Cache Compression\\\"\\n  venue: arXiv 2602.02199\\n  year: 2026\\n  category: background\\n  relevance: 单一 attention-score metric 是 greedy 的——miss structurally relevant tokens\\n  key_finding: 单 metric 有 greedy bias；multi-metric scoring 克服 condition-dependent metric failure\\n\\n- paper_id: thinking-tokens-mi-neurips2025\\n  title: \\\"Demystifying Reasoning Dynamics with Mutual Information: Thinking Tokens are Information Peaks\\\"\\n  venue: NeurIPS 2025\\n  year: 2025\\n  category: background\\n  relevance: reasoning 中 MI 在 thinking tokens 处突然 peak——compression 需避开 info-critical phases\\n  key_finding: thinking tokens (Hmm/Wait/Therefore) 处 MI 突增；这些 tokens 对推理性能不成比例重要\\n\\n- paper_id: lserve-mlsys2025\\n  title: \\\"LServe: Efficient Long-sequence LLM Serving with Unified Sparse Attention\\\"\\n  venue: MLSys 2025\\n  year: 2025\\n  category: background\\n  relevance: sparse attention + KV quantization 工业级联合部署但无 interaction 分析\\n  key_finding: 统一 static/dynamic sparsity + KV quant 到单 GPU kernel；prefilling 2.9x 加速\\n\\n- paper_id: squeezeattention-iclr2025\\n  title: \\\"SqueezeAttention: 2D Management of KV-Cache via Layer-wise Optimal Budget\\\"\\n  venue: ICLR 2025\\n  year: 2025\\n  category: method-component\\n  relevance: layer × sequence 二维 budget 优化；我们增加第三维——temporal phase\\n  key_finding: layer-wise cosine similarity 区分 layer 重要性，30-70% memory reduction\\n\\n- paper_id: nsa-acl2025\\n  title: \\\"NSA: Native Sparse Attention\\\"\\n  authors: DeepSeek\\n  venue: ACL 2025 Best Paper\\n  year: 2025\\n  category: background\\n  relevance: hardware-aligned trainable sparse attention；hierarchical 策略（coarse compression + fine selection）呼应 multi-phase\\n  key_finding: 端到端可训练 sparse attention，64k 解码 11.6x 加速；coarse+fine 分层策略\\n\\n- paper_id: evicpress-2025\\n  title: \\\"EVICPRESS: Joint KV-Cache Compression and Eviction for Efficient LLM Serving\\\"\\n  venue: arXiv 2512.14946\\n  year: 2025\\n  category: method-component\\n  relevance: 联合 eviction + quantization 优化 KV cache——compound 方向但仅 KV 内部\\n  key_finding: joint eviction + quantization 优于独立应用；但无 head pruning compound\\n\\n- paper_id: phase-transition-pruning-thermo-2026\\n  title: \\\"Phase Transitions in Neural Networks Pruning (Thermodynamic Analysis)\\\"\\n  venue: arXiv 2602.15224\\n  year: 2026\\n  category: background\\n  relevance: 自由能分析预测 sharp collapse；transition 前稳定 3-5%，跨越后 30%+ 骤降\\n  key_finding: free-energy phase transition 预测 pruning 崩溃点；importance 方法可能在某 phase 跨越 PTP\\n\\n- paper_id: token-budget-aware-acl2025\\n  title: \\\"Token-Budget-Aware LLM Reasoning\\\"\\n  venue: ACL 2025 Findings\\n  year: 2025\\n  category: background\\n  relevance: reasoning budget 应按 query 难度自适应分配——支撑 phase-adaptive compression\\n  key_finding: self-consistency 作为 thinking necessity proxy 动态调整 reasoning token budget\\n\\n# ============================================\\n\\n... [截断: 省略 1069 字符，传 max_chars=0 获取完整内容]\", \"total_chars\": 13069, \"truncated\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "31b32f67-a33e-423d-82e1-cfeae1381ec8",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "1dd3c216-92cf-4ed0-85f0-f374857e87e3",
  "sourceToolAssistantUUID": "31b32f67-a33e-423d-82e1-cfeae1381ec8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-17T01:20:03.185Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01VafnsgHLUHXYEuHBYv2fXD`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "ideas.md",
  "max_chars": 12000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1dd3c216-92cf-4ed0-85f0-f374857e87e3",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GAS8MxezPhEqJzfvRC",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "74f26388-867c-4324-b0c8-e9f8dee05f70",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LLPqEhJSwaCkcysakgVDP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7156,
      "cache_read_input_tokens": 17730,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7156,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 42,
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

_source line 10 · 2026-05-17T01:20:03.195Z_

<details><summary>↩ Tool result · `toolu_01VafnsgHLUHXYEuHBYv2fXD`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No ideas.md found for 'phase-gated-compound-sparse'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "74f26388-867c-4324-b0c8-e9f8dee05f70",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "930d68bc-8549-4b50-8e97-8175cdcbbe9d",
  "sourceToolAssistantUUID": "74f26388-867c-4324-b0c8-e9f8dee05f70",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-17T01:20:03.550Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01Ub4qTf3KduUftGfJ9QR85o`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "paper_framing.md",
  "max_chars": 12000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "930d68bc-8549-4b50-8e97-8175cdcbbe9d",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GAS8MxezPhEqJzfvRC",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "016399ae-b243-4a8f-ba39-c73b65f76cb0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_016LLPqEhJSwaCkcysakgVDP",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7156,
      "cache_read_input_tokens": 17730,
      "output_tokens": 206,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7156
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 206,
          "cache_read_input_tokens": 17730,
          "cache_creation_input_tokens": 7156,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7156,
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

_source line 12 · 2026-05-17T01:20:03.565Z_

<details><summary>↩ Tool result · `toolu_01Ub4qTf3KduUftGfJ9QR85o`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/paper_framing.md\", \"content\": \"# Paper Framing — Phase-Gated Compound Sparsity\\n\\n> 最后更新: 2026-05-17 (D102: C11 confirmed — recency triple NS across s015/s025/s030; s015+s025 primary, s030 supplementary) | 维护者: Director\\n\\n## Core Insight\\n\\nCompound sparsity（attention head pruning + KV cache eviction）的 severity 不是固定常数——它是 eviction strategy 和 reasoning phase 交互的涌现属性。Importance-based eviction 的 compound interaction severity（paired median difference: median(II_low_i − II_high_i)）随 sparsity 单调递增（DeepSeek: 0.39→1.21→3.99→8.48; Qwen: 0.07→0.31→1.07→3.16），而 random masking 在 s015/s020 NS，在 s025 跨模型显著但效应量远小于 importance（DS: 0.257 vs 3.986; QW: 0.393 vs 1.074, 2.7-17×差异），存在 sparsity threshold ~s020-s025（D063; s030 待定）。Cohen's d（per-problem paired, B=10000）从 medium 到 large（DeepSeek: 0.61→1.13; Qwen: 0.37→1.44，registry cohens_d s015→s030）。LLaMA 跨架构验证（D060, c8_llama_n250_fixed, n=250）：within-importance phase gradient 强（d_z=0.81-1.15, all p<10^-29, all monotonic），且 random 在 LLaMA 上所有条件均显著（d_z=0.41-0.46, all p<10^-12），imp/rand Δ ratio 仅 2.0-2.6×（vs DeepSeek 15-17×），strategy×phase 交互强度 architecture-dependent。GSM8K 跨 benchmark 验证（D075）：importance masking 的 phase gradient 在 GSM8K 上同样单调递增（QW: 0.039→0.158→1.100→2.092; DS: 0.241→0.740→1.992→4.682），但 strategy specificity（importance/random gradient ratio）从 MATH-500 的 15-17× 衰减至 GSM8K 的 2.3-3.8×。注意：\\\"反转\\\"仅在原始 II_low 值上（random > importance），phase gradient 层面 importance ≥ random。Strategy specificity 的 task-dependence 机制是开放问题（见 §6 Discussion）。这一发现挑战了 compound degradation 均匀分布的隐含假设。\\n\\n**数字基准**：所有数字基于 bf16 per-problem paired 统计量（B=10000 bootstrap）。median_diff 定义为 median(II_low_i − II_high_i)（逐 problem 配对差的中位数）。fp16 旧数据已弃用。\\n\\n## Narrative Arc\\n\\nCompound sparsity 是高效 LLM 推理的实用部署需求，但 prior work（SparK, Ada-KV, SLiM）将 compound interaction 视为均匀超可加。我们发现 severity 是 strategy × phase 交互的涌现属性：importance eviction 的 compound interaction 在 low-sparsity phase 远大于 high-sparsity phase（paired median difference 单调递增 0.39→8.48），而 random eviction 在低 sparsity (s015/s020) NS，在 s025+ 跨模型显著但效应量远小于 importance (2.7-17×)——存在 sparsity threshold (~s020-s025)，低于阈值 compound effect importance-specific，高于阈值两者均触发但 importance 主导。Cross-model replication 方向一致（Qwen magnitude ~1/4 of DeepSeek，onset threshold s≥0.20）。LLaMA 跨架构验证已完成（c8_llama_n250_fixed, n=250, D060）：within-importance phase gradient 强（d_z=0.81-1.15, all p<10^-29），random 所有条件显著（d_z=0.41-0.46, all p<10^-12），但 imp/rand ratio 仅 2.0-2.6×（远低于 DS 15-17×），strategy×phase 交互强度 architecture-dependent。Recency-based eviction（scoring-independent control, D100/D102）跨三个 sparsity level 均产生 null phase gradient（s015+s025 为 primary evidence，s030 supplementary due to numerical instability at extreme sparsity），确认 phase-dependent severity 是 attention-score-based eviction 的特有交互效应而非 token removal 的 trivial 副产物。我们通过 discrimination collapse 机制解释这一现象：head pruning → importance score 的判别力崩塌（Gini/CV 下降跨模型一致）→ importance eviction 退化为有偏伪随机。Attention entropy redistribution 作为 model-dependent secondary effect 在 DeepSeek 上观察到，但在 Qwen 上不稳健（D044）。\\n\\n**Framing 硬约束（D015）**：\\n- MUST: \\\\\\\"emergent phase-strategy interaction\\\\\\\"\\n- MUST NOT: \\\\\\\"importance metric limitation / importance is broken\\\\\\\"\\n- MUST NOT: claim \\\\\\\"importance masking produces super-additive interaction\\\\\\\" without qualifier — random masking also produces positive II, and at s025+ random is statistically significant (D063). The distinguishing signal is **magnitude gradient** (importance 2.7-17× larger) and **onset threshold** (random NS below ~s020, importance significant from s015+), not the existence of super-additivity itself (D023)\\n\\n## Core Claims\\n\\n| ID | Claim | Status | Key Evidence |\\n|----|-------|--------|-------------|\\n| C1 | Compound sparsity severity is strategy- and task-modulated | confirmed | MATH-500: importance gradient 15-17× random (DeepSeek s025-s030); GSM8K: ratio 衰减至 2.3-3.8× (D075)。Phase gradient 层面 importance ≥ random 跨 benchmark 成立，但 magnitude ratio task-dependent。Threshold ~s020-s025 (D063) |\\n| C2 | Severity is phase-modulated (amplified in low-sparsity phase) | confirmed | bf16 paired median difference 单调递增: 0.39→1.21→3.99→8.48; Bonferroni p<0.005 全 4 水平 (D032)。预注册：n=500 后若 QW s015 CI 仍跨零，叙事改为 'compound effect emerges above threshold sparsity (~s020)' |\\n| C3 | Phase-strategy crossover exists | confirmed | s=0.25: importance high_phase=0.032 < random=0.818, importance low_phase=7.196 > random=1.363 (bf16) |\\n| C4 | Discrimination collapse as primary mechanism; entropy redistribution model-dependent | partially_confirmed | D044: Gini/CV 下降跨模型一致; entropy collapse DeepSeek 一致但 Qwen s025 反转(+0.045) s030≈0。30/30 problems completed. |\\n| C5 | Phase-modulated compound severity generalizes across models | confirmed | DeepSeek + Qwen cross-model replication: 方向一致, Cohen's d ρ=1.0, gradient permutation p=0.043. Qwen magnitude ~1/4 of DeepSeek, onset threshold s≥0.20 (S3→C). |\\n| C5b | Phase-aware mitigation recovers compound degradation | future_work | D056: pilot 完成 gate_failed。Oracle recovery 18% < 30% gate (Wilcoxon p=0.002)，heuristic 32% 但 CI 跨零。方向正确但效应量不足，需更精细 phase boundary estimation → future work |\\n| C6 | Severity gradient is sub-exponential | confirmed | Growth rate decreasing: Δ增长因子 3.8×→4.8×→2.0×（递减） |\\n| C7 | Statistical power at n=500 confirms dose-response | confirmed | c2_n500_deepseek (success) + c2_qw_n500_r3 (success): 两模型 n=500 全 4 sparsity Bonferroni p<0.005, Spearman ρ=1.0 |\\n| C8 | Cross-architecture validation (LLaMA) | confirmed | c8_llama_n250_fixed (n=250, D060): within-importance phase gradient d_z=0.81-1.15 (all p<10^-29, all monotonic) ✓。Random 所有条件显著 (d_z=0.41-0.46, all p<10^-12)，与 DeepSeek/Qwen random 低 sparsity NS 模式定性不同。Imp/rand Δ ratio 2.0-2.6×（远低于 DS 15-17×）。Strategy specificity architecture-dependent。n=250 功效充分。 |\\n| C9 | Differentiation from Lethe/SparK prior work | planned | Related Work §2 引用区分 + SparK gap analysis |\\n| C10 | Phase gradient cross-benchmark robust; strategy specificity task-modulated | confirmed | GSM8K DS gradient 0.241→4.682 单调递增; QW gradient 0.039→2.092; imp/rand ratio 衰减至 2.3-3.8× (D075)。QW random s025+s030 均 success |\\n| C11 | Phase-dependent severity absent under scoring-independent eviction (recency control) | confirmed | D102: 三个 sparsity level 全部 NS。s015+s025 为 primary evidence (n=100 each, both d_z < 0.1, p > 0.5); s030 supplementary (numerical instability at extreme sparsity)。对比 importance: d_z=0.574-1.15, ratio=119.8×。Triple dissociation confirmed: importance 有 gradient, recency + random 均 NS。排除 (a) phase segmentation circularity (b) H2O scoring pathway confound。文献中无先例将 recency eviction 作为 methodological control (experimental design contribution)。 |\\n| S3→C | Onset threshold is model-dependent (DeepSeek s≥0.15, Qwen s≥0.20) | confirmed | D037/D038: Qwen s015 d_z=0.37 CI含0, s020+ 显著 |\\n| S7→C | Dose-response monotonicity (Spearman ρ=1.0) | confirmed | D047: 6-point dose-response, 单调递增 |\\n\\n## Anticipated Reviewer Concerns\\n\\n### RC1: Generalizability — 7B models only, benchmark scope\\n- **预期质疑**: \\\\\\\"Results on two 7B models and MATH-500 only. How do we know this generalizes to larger models or other reasoning tasks?\\\\\\\"\\n- **应对**: 四层泛化证据：(1) Cross-model: DeepSeek-R1-Distill-Qwen-7B + Qwen2.5-7B-Instruct（同架构不同训练，ρ=1.0）(2) Cross-architecture: c8_llama_n250_fixed (DeepSeek-R1-Distill-Llama-8B, LlamaForCausalLM, n=250)，within-importance phase gradient 强 (d_z=0.81-1.15)，但 strategy specificity 弱于 Qwen2 架构（2.0-2.6× vs 15-17×），strategy×phase 交互强度 architecture-dependent (3) **Cross-benchmark (D075)**: GSM8K（两模型）phase gradient 单调递增复现（DS: 0.241→4.682; QW: 0.039→2.092），但 strategy specificity ratio 从 MATH-500 15-17× 衰减至 2.3-3.8×，表明 phase modulation 跨 benchmark 稳健而 magnitude modulation task-dependent。Limitations 诚实声明：(a) 7B scale only；(b) strategy specificity 强度 task-dependent（GSM8K 衰减，可能因推理链更短）；(c) random phase gradient 行为 architecture-dependent。\\n- **实验支撑**: C5 (cross-model) + C8 (c8_llama_n250_fixed cross-architecture, n=250) + C10 (cross-benchmark GSM8K, D075)\\n\\n### RC2: Methodology — phase segmentation circularity and scoring confound\\n- **预期质疑**: \\\\\\\"Your phase segmentation uses perplexity computed from the same model whose sparsity you're measuring. Isn't this circular? And H2O's attention-score mechanism could itself create the phase gradient artifact.\\\\\\\"\\n- **应对**: Recency-based eviction (scoring-independent control, D102 confirmed) produces null phase gradient across all three sparsity levels (s015+s025 primary, s030 supplementary), confirming the observed severity pattern is specific to attention-score-based methods, not an artifact of (a) phase segmentation itself or (b) the scoring computation pathway. Triple dissociation: importance shows gradient (d_z=0.574+), recency and random both NS. Novel experimental design: repurposing recency eviction as methodological control has no precedent in literature (H2O/StreamingLLM use it only as performance baseline).\\n- **实验支撑**: C11 (recency_s015/s025/s030, D102 confirmed) + c4_entropy (discrimination collapse mechanism, D044)\\n\\n### RC3: Practical impact — 没有 throughput 数据\\n- **预期质疑**: \\\\\\\"No wall-clock or throughput measurements. Is the severity amplification reflected in actual inference speed?\\\\\\\"\\n- **应对**: 本文定位是 empirical finding paper（发现 + 机制解释），不是 method paper。Throughput 不是 claim 的一部分。Discussion 中明确 phase-gated controller 作为 future direction。\\n  - C5b pilot 已完成（D056）：oracle recovery 18%（Wilcoxon p=0.002），heuristic recovery 32%（p=0.024），但两者 95% CI 均跨零。方向正确（Wilcoxon 显著）但效应量不足（未达 30% gate），需更精细的 phase boundary estimation。论文 §6 Discussion 诚实报告 pilot 结果 + future work。\\n  - Heuristic > oracle 悖论值得提及：token position ratio 粗粒度划分可能恰好更适合 mitigation 场景，暗示 phase boundary 的最优粒度是开放问题。\\n- **实验支撑**: c5b_pilot (gate_failed, D056)\\n\\n### RC4: Statistical rigor — bootstrap 是否足够\\n- **预期质疑**: \\\\\\\"Per-problem bootstrap with 50 problems — sufficient sample size?\\\\\\\"\\n- **应对**: bf16 使用 B=10000 per-problem paired bootstrap，有效配对数 n=49 (DeepSeek) / n=46 (Qwen)；n=500 实验进一步验证 (C7 confirmed)。Permutation test 使用 paired median difference 作为 robust statistic（D032），Bonferroni 校正后全 4 水平 p<0.005。Dose-response 主用 Wilcoxon signed-rank p + median_diff（robust to outliers），Cohen's d 作为辅助效应量（DeepSeek 0.61→1.13, Qwen 0.37→1.44, registry cohens_d s015→s030），注释高 sparsity 下 d 受 outlier-driven variance 影响（DS s020→s025: median 3.3× jump 但 d 非单调，因极端 II 值影响分母，D064）。可在 appendix 补充 per-problem 分布图（已生成 fig4_per_problem_dist.pdf）。\\n- **实验支撑**: bf16 permutation test (D032) + Cohen's d per-problem paired (rebootstrap B=10000) + n=500 Wilcoxon (C7 confirmed)\\n\\n### RC5: Novelty — prior work 是否已覆盖 phase-dependent sparsity\\n- **预期质疑**: \\\"ThinKV and phase-aware methods already consider phase. What's new?\\\"\\n- **应对**: Prior work 在单轴上分析 phase（ThinKV: phase-aware eviction）或 compound（SparK: joint compression）。没有工作同时分析 compound × phase × strategy 的三维交互。Crossover 现象（同一 strategy 在不同 phase 方向反转）是全新发现。Related Work 加 Lethe 引用区分 + SparK 对比。具体区分：\\n  - **ThinKV** (arxiv 2510.01290, Oct 2025): 在 KV cache 单轴上做 phase-aware 压缩（按 CoT 阶段差异化 eviction），但不涉及 pruning × eviction 的 compound interaction。我们研究的是双轴（head pruning × KV eviction）compound interaction 如何随 phase 变化，ThinKV 的单轴 phase-aware 策略是我们分析维度的子集。\\n  - **Physics of KV Cache Compression** (arxiv 2603.01426, Mar 2026): 揭示了单轴 KV 压缩的 phase transition 和 representational rigidity，是机制层面最接近的工作。关键区分：他们刻画的是单一压缩轴上压缩率的 critical threshold（phase transition），我们刻画的是两种压缩方法的 compound interaction severity 如何被 reasoning phase 调制（phase-dependent gradient）——维度正交。\\n  - **HIES** (arxiv 2510.13832, Oct 2025): 发现 importance score collapse 并提出 entropy 补偿，为我们的 discrimination collapse 机制提供独立 supporting evidence——他们在单轴上观察到的 score collapse 正是我们在 compound setting 中发现的 Gini/CV 下降的单轴对应。\\n  - **R-KV** (arxiv 2505.24133, May 2025): 针对 reasoning task 做 KV compression 优化，属于 task-specific method。我们不是提出新方法，而是 mechanistic 分析 compound interaction 的 phase-dependent 行为，二者目标不同（optimization vs understanding）。\\n- **实验支撑**: C3 (crossover), Related Work §2 的 gap 分析\\n\\n### RC6: Novelty vs Lethe/SparK\\n- **预期质疑**: \\\"How does this differ from Lethe (AAAI 2026) which also does layer-time-adaptive KV pruning, or SparK which studies compound compression?\\\"\\n- **应对*\\n\\n... [截断: 省略 2093 字符，传 max_chars=0 获取完整内容]\", \"total_chars\": 14093, \"truncated\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "016399ae-b243-4a8f-ba39-c73b65f76cb0",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "7d5d90b3-23e8-4266-9788-ff4907cb56f4",
  "sourceToolAssistantUUID": "016399ae-b243-4a8f-ba39-c73b65f76cb0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-17T01:20:08.142Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_019iAmSPHqBY7ReP3TPafkwa`</summary>

```json
{
  "project": "phase-gated-compound-sparse",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7d5d90b3-23e8-4266-9788-ff4907cb56f4",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GAnFaGzhC1ePJJn9xe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8c8ebcc6-1065-4443-a089-2cfa51d6e468",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GCBYKjsQ37YwnUQggdiCuh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5714,
      "cache_read_input_tokens": 24886,
      "output_tokens": 112,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5714
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 112,
          "cache_read_input_tokens": 24886,
          "cache_creation_input_tokens": 5714,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5714,
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

_source line 14 · 2026-05-17T01:20:08.162Z_

<details><summary>↩ Tool result · `toolu_019iAmSPHqBY7ReP3TPafkwa`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/paper_framing.md\", \"content\": \"# Paper Framing — Phase-Gated Compound Sparsity\\n\\n> 最后更新: 2026-05-17 (D102: C11 confirmed — recency triple NS across s015/s025/s030; s015+s025 primary, s030 supplementary) | 维护者: Director\\n\\n## Core Insight\\n\\nCompound sparsity（attention head pruning + KV cache eviction）的 severity 不是固定常数——它是 eviction strategy 和 reasoning phase 交互的涌现属性。Importance-based eviction 的 compound interaction severity（paired median difference: median(II_low_i − II_high_i)）随 sparsity 单调递增（DeepSeek: 0.39→1.21→3.99→8.48; Qwen: 0.07→0.31→1.07→3.16），而 random masking 在 s015/s020 NS，在 s025 跨模型显著但效应量远小于 importance（DS: 0.257 vs 3.986; QW: 0.393 vs 1.074, 2.7-17×差异），存在 sparsity threshold ~s020-s025（D063; s030 待定）。Cohen's d（per-problem paired, B=10000）从 medium 到 large（DeepSeek: 0.61→1.13; Qwen: 0.37→1.44，registry cohens_d s015→s030）。LLaMA 跨架构验证（D060, c8_llama_n250_fixed, n=250）：within-importance phase gradient 强（d_z=0.81-1.15, all p<10^-29, all monotonic），且 random 在 LLaMA 上所有条件均显著（d_z=0.41-0.46, all p<10^-12），imp/rand Δ ratio 仅 2.0-2.6×（vs DeepSeek 15-17×），strategy×phase 交互强度 architecture-dependent。GSM8K 跨 benchmark 验证（D075）：importance masking 的 phase gradient 在 GSM8K 上同样单调递增（QW: 0.039→0.158→1.100→2.092; DS: 0.241→0.740→1.992→4.682），但 strategy specificity（importance/random gradient ratio）从 MATH-500 的 15-17× 衰减至 GSM8K 的 2.3-3.8×。注意：\\\"反转\\\"仅在原始 II_low 值上（random > importance），phase gradient 层面 importance ≥ random。Strategy specificity 的 task-dependence 机制是开放问题（见 §6 Discussion）。这一发现挑战了 compound degradation 均匀分布的隐含假设。\\n\\n**数字基准**：所有数字基于 bf16 per-problem paired 统计量（B=10000 bootstrap）。median_diff 定义为 median(II_low_i − II_high_i)（逐 problem 配对差的中位数）。fp16 旧数据已弃用。\\n\\n## Narrative Arc\\n\\nCompound sparsity 是高效 LLM 推理的实用部署需求，但 prior work（SparK, Ada-KV, SLiM）将 compound interaction 视为均匀超可加。我们发现 severity 是 strategy × phase 交互的涌现属性：importance eviction 的 compound interaction 在 low-sparsity phase 远大于 high-sparsity phase（paired median difference 单调递增 0.39→8.48），而 random eviction 在低 sparsity (s015/s020) NS，在 s025+ 跨模型显著但效应量远小于 importance (2.7-17×)——存在 sparsity threshold (~s020-s025)，低于阈值 compound effect importance-specific，高于阈值两者均触发但 importance 主导。Cross-model replication 方向一致（Qwen magnitude ~1/4 of DeepSeek，onset threshold s≥0.20）。LLaMA 跨架构验证已完成（c8_llama_n250_fixed, n=250, D060）：within-importance phase gradient 强（d_z=0.81-1.15, all p<10^-29），random 所有条件显著（d_z=0.41-0.46, all p<10^-12），但 imp/rand ratio 仅 2.0-2.6×（远低于 DS 15-17×），strategy×phase 交互强度 architecture-dependent。Recency-based eviction（scoring-independent control, D100/D102）跨三个 sparsity level 均产生 null phase gradient（s015+s025 为 primary evidence，s030 supplementary due to numerical instability at extreme sparsity），确认 phase-dependent severity 是 attention-score-based eviction 的特有交互效应而非 token removal 的 trivial 副产物。我们通过 discrimination collapse 机制解释这一现象：head pruning → importance score 的判别力崩塌（Gini/CV 下降跨模型一致）→ importance eviction 退化为有偏伪随机。Attention entropy redistribution 作为 model-dependent secondary effect 在 DeepSeek 上观察到，但在 Qwen 上不稳健（D044）。\\n\\n**Framing 硬约束（D015）**：\\n- MUST: \\\\\\\"emergent phase-strategy interaction\\\\\\\"\\n- MUST NOT: \\\\\\\"importance metric limitation / importance is broken\\\\\\\"\\n- MUST NOT: claim \\\\\\\"importance masking produces super-additive interaction\\\\\\\" without qualifier — random masking also produces positive II, and at s025+ random is statistically significant (D063). The distinguishing signal is **magnitude gradient** (importance 2.7-17× larger) and **onset threshold** (random NS below ~s020, importance significant from s015+), not the existence of super-additivity itself (D023)\\n\\n## Core Claims\\n\\n| ID | Claim | Status | Key Evidence |\\n|----|-------|--------|-------------|\\n| C1 | Compound sparsity severity is strategy- and task-modulated | confirmed | MATH-500: importance gradient 15-17× random (DeepSeek s025-s030); GSM8K: ratio 衰减至 2.3-3.8× (D075)。Phase gradient 层面 importance ≥ random 跨 benchmark 成立，但 magnitude ratio task-dependent。Threshold ~s020-s025 (D063) |\\n| C2 | Severity is phase-modulated (amplified in low-sparsity phase) | confirmed | bf16 paired median difference 单调递增: 0.39→1.21→3.99→8.48; Bonferroni p<0.005 全 4 水平 (D032)。预注册：n=500 后若 QW s015 CI 仍跨零，叙事改为 'compound effect emerges above threshold sparsity (~s020)' |\\n| C3 | Phase-strategy crossover exists | confirmed | s=0.25: importance high_phase=0.032 < random=0.818, importance low_phase=7.196 > random=1.363 (bf16) |\\n| C4 | Discrimination collapse as primary mechanism; entropy redistribution model-dependent | partially_confirmed | D044: Gini/CV 下降跨模型一致; entropy collapse DeepSeek 一致但 Qwen s025 反转(+0.045) s030≈0。30/30 problems completed. |\\n| C5 | Phase-modulated compound severity generalizes across models | confirmed | DeepSeek + Qwen cross-model replication: 方向一致, Cohen's d ρ=1.0, gradient permutation p=0.043. Qwen magnitude ~1/4 of DeepSeek, onset threshold s≥0.20 (S3→C). |\\n| C5b | Phase-aware mitigation recovers compound degradation | future_work | D056: pilot 完成 gate_failed。Oracle recovery 18% < 30% gate (Wilcoxon p=0.002)，heuristic 32% 但 CI 跨零。方向正确但效应量不足，需更精细 phase boundary estimation → future work |\\n| C6 | Severity gradient is sub-exponential | confirmed | Growth rate decreasing: Δ增长因子 3.8×→4.8×→2.0×（递减） |\\n| C7 | Statistical power at n=500 confirms dose-response | confirmed | c2_n500_deepseek (success) + c2_qw_n500_r3 (success): 两模型 n=500 全 4 sparsity Bonferroni p<0.005, Spearman ρ=1.0 |\\n| C8 | Cross-architecture validation (LLaMA) | confirmed | c8_llama_n250_fixed (n=250, D060): within-importance phase gradient d_z=0.81-1.15 (all p<10^-29, all monotonic) ✓。Random 所有条件显著 (d_z=0.41-0.46, all p<10^-12)，与 DeepSeek/Qwen random 低 sparsity NS 模式定性不同。Imp/rand Δ ratio 2.0-2.6×（远低于 DS 15-17×）。Strategy specificity architecture-dependent。n=250 功效充分。 |\\n| C9 | Differentiation from Lethe/SparK prior work | planned | Related Work §2 引用区分 + SparK gap analysis |\\n| C10 | Phase gradient cross-benchmark robust; strategy specificity task-modulated | confirmed | GSM8K DS gradient 0.241→4.682 单调递增; QW gradient 0.039→2.092; imp/rand ratio 衰减至 2.3-3.8× (D075)。QW random s025+s030 均 success |\\n| C11 | Phase-dependent severity absent under scoring-independent eviction (recency control) | confirmed | D102: 三个 sparsity level 全部 NS。s015+s025 为 primary evidence (n=100 each, both d_z < 0.1, p > 0.5); s030 supplementary (numerical instability at extreme sparsity)。对比 importance: d_z=0.574-1.15, ratio=119.8×。Triple dissociation confirmed: importance 有 gradient, recency + random 均 NS。排除 (a) phase segmentation circularity (b) H2O scoring pathway confound。文献中无先例将 recency eviction 作为 methodological control (experimental design contribution)。 |\\n| S3→C | Onset threshold is model-dependent (DeepSeek s≥0.15, Qwen s≥0.20) | confirmed | D037/D038: Qwen s015 d_z=0.37 CI含0, s020+ 显著 |\\n| S7→C | Dose-response monotonicity (Spearman ρ=1.0) | confirmed | D047: 6-point dose-response, 单调递增 |\\n\\n## Anticipated Reviewer Concerns\\n\\n### RC1: Generalizability — 7B models only, benchmark scope\\n- **预期质疑**: \\\\\\\"Results on two 7B models and MATH-500 only. How do we know this generalizes to larger models or other reasoning tasks?\\\\\\\"\\n- **应对**: 四层泛化证据：(1) Cross-model: DeepSeek-R1-Distill-Qwen-7B + Qwen2.5-7B-Instruct（同架构不同训练，ρ=1.0）(2) Cross-architecture: c8_llama_n250_fixed (DeepSeek-R1-Distill-Llama-8B, LlamaForCausalLM, n=250)，within-importance phase gradient 强 (d_z=0.81-1.15)，但 strategy specificity 弱于 Qwen2 架构（2.0-2.6× vs 15-17×），strategy×phase 交互强度 architecture-dependent (3) **Cross-benchmark (D075)**: GSM8K（两模型）phase gradient 单调递增复现（DS: 0.241→4.682; QW: 0.039→2.092），但 strategy specificity ratio 从 MATH-500 15-17× 衰减至 2.3-3.8×，表明 phase modulation 跨 benchmark 稳健而 magnitude modulation task-dependent。Limitations 诚实声明：(a) 7B scale only；(b) strategy specificity 强度 task-dependent（GSM8K 衰减，可能因推理链更短）；(c) random phase gradient 行为 architecture-dependent。\\n- **实验支撑**: C5 (cross-model) + C8 (c8_llama_n250_fixed cross-architecture, n=250) + C10 (cross-benchmark GSM8K, D075)\\n\\n### RC2: Methodology — phase segmentation circularity and scoring confound\\n- **预期质疑**: \\\\\\\"Your phase segmentation uses perplexity computed from the same model whose sparsity you're measuring. Isn't this circular? And H2O's attention-score mechanism could itself create the phase gradient artifact.\\\\\\\"\\n- **应对**: Recency-based eviction (scoring-independent control, D102 confirmed) produces null phase gradient across all three sparsity levels (s015+s025 primary, s030 supplementary), confirming the observed severity pattern is specific to attention-score-based methods, not an artifact of (a) phase segmentation itself or (b) the scoring computation pathway. Triple dissociation: importance shows gradient (d_z=0.574+), recency and random both NS. Novel experimental design: repurposing recency eviction as methodological control has no precedent in literature (H2O/StreamingLLM use it only as performance baseline).\\n- **实验支撑**: C11 (recency_s015/s025/s030, D102 confirmed) + c4_entropy (discrimination collapse mechanism, D044)\\n\\n### RC3: Practical impact — 没有 throughput 数据\\n- **预期质疑**: \\\\\\\"No wall-clock or throughput measurements. Is the severity amplification reflected in actual inference speed?\\\\\\\"\\n- **应对**: 本文定位是 empirical finding paper（发现 + 机制解释），不是 method paper。Throughput 不是 claim 的一部分。Discussion 中明确 phase-gated controller 作为 future direction。\\n  - C5b pilot 已完成（D056）：oracle recovery 18%（Wilcoxon p=0.002），heuristic recovery 32%（p=0.024），但两者 95% CI 均跨零。方向正确（Wilcoxon 显著）但效应量不足（未达 30% gate），需更精细的 phase boundary estimation。论文 §6 Discussion 诚实报告 pilot 结果 + future work。\\n  - Heuristic > oracle 悖论值得提及：token position ratio 粗粒度划分可能恰好更适合 mitigation 场景，暗示 phase boundary 的最优粒度是开放问题。\\n- **实验支撑**: c5b_pilot (gate_failed, D056)\\n\\n### RC4: Statistical rigor — bootstrap 是否足够\\n- **预期质疑**: \\\\\\\"Per-problem bootstrap with 50 problems — sufficient sample size?\\\\\\\"\\n- **应对**: bf16 使用 B=10000 per-problem paired bootstrap，有效配对数 n=49 (DeepSeek) / n=46 (Qwen)；n=500 实验进一步验证 (C7 confirmed)。Permutation test 使用 paired median difference 作为 robust statistic（D032），Bonferroni 校正后全 4 水平 p<0.005。Dose-response 主用 Wilcoxon signed-rank p + median_diff（robust to outliers），Cohen's d 作为辅助效应量（DeepSeek 0.61→1.13, Qwen 0.37→1.44, registry cohens_d s015→s030），注释高 sparsity 下 d 受 outlier-driven variance 影响（DS s020→s025: median 3.3× jump 但 d 非单调，因极端 II 值影响分母，D064）。可在 appendix 补充 per-problem 分布图（已生成 fig4_per_problem_dist.pdf）。\\n- **实验支撑**: bf16 permutation test (D032) + Cohen's d per-problem paired (rebootstrap B=10000) + n=500 Wilcoxon (C7 confirmed)\\n\\n### RC5: Novelty — prior work 是否已覆盖 phase-dependent sparsity\\n- **预期质疑**: \\\"ThinKV and phase-aware methods already consider phase. What's new?\\\"\\n- **应对**: Prior work 在单轴上分析 phase（ThinKV: phase-aware eviction）或 compound（SparK: joint compression）。没有工作同时分析 compound × phase × strategy 的三维交互。Crossover 现象（同一 strategy 在不同 phase 方向反转）是全新发现。Related Work 加 Lethe 引用区分 + SparK 对比。具体区分：\\n  - **ThinKV** (arxiv 2510.01290, Oct 2025): 在 KV cache 单轴上做 phase-aware 压缩（按 CoT 阶段差异化 eviction），但不涉及 pruning × eviction 的 compound interaction。我们研究的是双轴（head pruning × KV eviction）compound interaction 如何随 phase 变化，ThinKV 的单轴 phase-aware 策略是我们分析维度的子集。\\n  - **Physics of KV Cache Compression** (arxiv 2603.01426, Mar 2026): 揭示了单轴 KV 压缩的 phase transition 和 representational rigidity，是机制层面最接近的工作。关键区分：他们刻画的是单一压缩轴上压缩率的 critical threshold（phase transition），我们刻画的是两种压缩方法的 compound interaction severity 如何被 reasoning phase 调制（phase-dependent gradient）——维度正交。\\n  - **HIES** (arxiv 2510.13832, Oct 2025): 发现 importance score collapse 并提出 entropy 补偿，为我们的 discrimination collapse 机制提供独立 supporting evidence——他们在单轴上观察到的 score collapse 正是我们在 compound setting 中发现的 Gini/CV 下降的单轴对应。\\n  - **R-KV** (arxiv 2505.24133, May 2025): 针对 reasoning task 做 KV compression 优化，属于 task-specific method。我们不是提出新方法，而是 mechanistic 分析 compound interaction 的 phase-dependent 行为，二者目标不同（optimization vs understanding）。\\n- **实验支撑**: C3 (crossover), Related Work §2 的 gap 分析\\n\\n### RC6: Novelty vs Lethe/SparK\\n- **预期质疑**: \\\"How does this differ from Lethe (AAAI 2026) which also does layer-time-adaptive KV pruning, or SparK which studies compound compression?\\\"\\n- **应对**: Lethe 和 SparK 都没有分析 phase × strategy 的交互效应。Lethe 是 method paper（提出 adaptive eviction 方法），我们是 empirical finding paper（发现 phase-dependent severity gradient）。SparK 研究 compound compression 但将 interaction 视为均匀超可加，我们发现 interaction severity 随 phase 和 strategy 变化。新近工作进一步确认我们的独特定位：\\n  - **Physics of KV Cache Compression** (arxiv 2603.01426, Mar 2026) 是最近的相关工作，研究单轴压缩的 phase transition 阈值行为。与我们的核心区别：他们的 phase transition 是压缩率维度上的 critical point，我们的 phase-dependent gradient 是 reasoning phase 维度上 compound interaction 的连续调制——两者刻画的 \\\"phase\\\" 语义不同（compression-rate phase vs reasoning phase）。\\n  - **ThinKV** (arxiv 2510.01290, Oct 2025) 和 **R-KV** (arxiv 2505.24133, May 2025) 都在 KV compression 单轴上引入 phase/reasoning awareness，但均未涉及 compound interaction。我们的贡献在于揭示 pruning × eviction 双轴交互如何被 reasoning phase 调制，这是单轴方法无法观察到的涌现现象。\\n  - **HIES** (arxiv 2510.13832, Oct 2025) 的 importance score collapse 发现为我们的 discrimination collapse 机制提供了独立佐证，但 HIES 聚焦于单轴补偿方法，未研究 collapse 在 compound setting 中的放大效应。\\n  - Related Work §2 明确区分三者定位：Lethe/SparK = method/compound method, ThinKV/R-KV = single-axis phase-aware, Physics of KV = single-axis phase transition, HIES = single-axis collapse。我们 = compound × phase × strategy 三维交互分析。\\n- **实验支撑**: 不需要额外实验，仅需 §2 引用区分\\n\\n## Paper Positioning\\n\\n**类型**: Empirical finding paper（非 method paper）\\n**核心贡献**:\\n1. 发现 compound sparsity severity 的 strategy × phase 交互\\n2. 量化 severity gradient（bf16 paired median difference 0.39→8.48, Cohen's d 0.61→1.13）和 crossover 现象\\n3. 提出 discrimination collapse 机制解释（Gini/CV 跨模型一致；entropy redistribution model-dependent）\\n4. Cross-model + cross-architecture (LLaMA, n=250) replication 验证泛化性（三模型两架构；strategy×phase 交互强度 architecture-dependent, D060）\\n5. Novel use of scoring-independent eviction (recency-based) as methodological control — experimental design contribution 排除 phase segmentation circularity 和 scoring pathway confound (C11, D102 confirmed)\\n\\n**投稿目标**: EMNLP 2026 ARR, deadline 2026-05-25\\n**Rebuttal 准备**: Day 9 (2026-05-23) 预留 rebuttal letter 写作时间\\n**关键时间线**：\\n- Day 9 (2026-05-23): 预留写 rebuttal letter\\n- Day 11 (2026-05-25): EMNLP 2026 ARR 截稿\\n\", \"total_chars\": 14093, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8c8ebcc6-1065-4443-a089-2cfa51d6e468",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "fe9749ee-320d-4ec0-b09f-099ef5daf23f",
  "sourceToolAssistantUUID": "8c8ebcc6-1065-4443-a089-2cfa51d6e468",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-17T01:20:11.178Z_

Now let me look at the actual paper artifacts to see what's been written.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fe9749ee-320d-4ec0-b09f-099ef5daf23f",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GB8BtRuJAn1W1B1tzb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "16f321e1-812e-4e49-be0c-8a2acbb47196",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hs75CSJL2J9hK6gKLamSGu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6447,
      "cache_read_input_tokens": 30600,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6447,
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

_source line 16 · 2026-05-17T01:20:13.196Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01Tycm8uxMxxYew59Cxknc2Y`</summary>

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
  "parentUuid": "16f321e1-812e-4e49-be0c-8a2acbb47196",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GB8BtRuJAn1W1B1tzb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7b260442-c547-4af7-9196-8cbd83c081fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hs75CSJL2J9hK6gKLamSGu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6447,
      "cache_read_input_tokens": 30600,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6447,
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

_source line 17 · 2026-05-17T01:20:13.230Z_

<details><summary>↩ Tool result · `toolu_01Tycm8uxMxxYew59Cxknc2Y`</summary>

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
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7b260442-c547-4af7-9196-8cbd83c081fa",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "e87feec4-c1a3-4a4b-be56-af8f1dc726f9",
  "sourceToolAssistantUUID": "7b260442-c547-4af7-9196-8cbd83c081fa",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 18 · 2026-05-17T01:20:13.728Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01AsjYKFoqxqD9hxE7s5JFTP`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e87feec4-c1a3-4a4b-be56-af8f1dc726f9",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GB8BtRuJAn1W1B1tzb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9fc8f482-fdef-4b9a-8483-eae596837d47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Hs75CSJL2J9hK6gKLamSGu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6447,
      "cache_read_input_tokens": 30600,
      "output_tokens": 201,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6447
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 201,
          "cache_read_input_tokens": 30600,
          "cache_creation_input_tokens": 6447,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6447,
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

_source line 19 · 2026-05-17T01:20:13.748Z_

<details><summary>↩ Tool result · `toolu_01AsjYKFoqxqD9hxE7s5JFTP`</summary>

```text
artifacts/_project/paper/references.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9fc8f482-fdef-4b9a-8483-eae596837d47",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "d4b23923-3f76-4a99-b75f-31533c013249",
  "sourceToolAssistantUUID": "9fc8f482-fdef-4b9a-8483-eae596837d47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-17T01:20:16.941Z_

<details open><summary>🔧 Tool call — Read · `toolu_016jvqpgHzsoLVTSiDiRJxsP`</summary>

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
  "parentUuid": "d4b23923-3f76-4a99-b75f-31533c013249",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GBXdHTqdRf7HGGvtP7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6991bc6d-e12b-4d2d-951f-de687bf32419",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JW8wGDunKvHL8trJAArXvx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 707,
      "cache_read_input_tokens": 37047,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 707,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 54,
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

_source line 21 · 2026-05-17T01:20:16.947Z_

<details><summary>↩ Tool result · `toolu_016jvqpgHzsoLVTSiDiRJxsP`</summary>

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
  "parentUuid": "6991bc6d-e12b-4d2d-951f-de687bf32419",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "f2ad426b-cd43-4e8e-b7c8-e684f6fa05ef",
  "sourceToolAssistantUUID": "6991bc6d-e12b-4d2d-951f-de687bf32419",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-17T01:20:17.141Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DtgYWVG8DQhxEFdH3SVjvj`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f2ad426b-cd43-4e8e-b7c8-e684f6fa05ef",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GBXdHTqdRf7HGGvtP7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ddb74de4-302e-4dda-b8be-f30e0953d287",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JW8wGDunKvHL8trJAArXvx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 707,
      "cache_read_input_tokens": 37047,
      "output_tokens": 170,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 707
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 170,
          "cache_read_input_tokens": 37047,
          "cache_creation_input_tokens": 707,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 707,
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

_source line 23 · 2026-05-17T01:20:17.147Z_

<details><summary>↩ Tool result · `toolu_01DtgYWVG8DQhxEFdH3SVjvj`</summary>

```text
1	
2	@inproceedings{streamingllm-iclr2024,
3	    title     = {Efficient Streaming Language Models with Attention Sinks},
4	    author    = {Xiao, Guangxuan and Tian, Yuandong and Chen, Beidi and Han, Song and Lewis, Mike},
5	    booktitle = {International Conference on Learning Representations},
6	    year      = {2024},
7	    url       = {https://arxiv.org/abs/2309.17453},
8	}
9	
10	@article{duoattention-2024,
11	    title   = {{DuoAttention}: Efficient Long-Context {LLM} Inference with Retrieval and Streaming Heads},
12	    author  = {Xiao, Guangxuan and Tang, Jiaming and Zuo, Jingwei and Guo, Junxian and Yang, Shang and Tang, Haotian and Fu, Yao and Han, Song},
13	    journal = {arXiv preprint arXiv:2410.10819},
14	    year    = {2024},
15	    url     = {https://arxiv.org/abs/2410.10819},
16	}
17	
18	@inproceedings{adakv-neurips2025,
19	    title     = {Ada-{KV}: Optimizing {KV} Cache Eviction by Adaptive Budget Allocation for Efficient {LLM} Inference},
20	    author    = {Feng, Yuan and Lv, Junlin and Cao, Yukun and Xie, Xike and Zhou, S. Kevin},
21	    booktitle = {Advances in Neural Information Processing Systems},
22	    year      = {2025},
23	    url       = {https://arxiv.org/abs/2407.11550},
24	}
25	
26	@article{decision-repr-transition-2026,
27	    title   = {Understanding Performance Collapse in Layer-Pruned Large Language Models via Decision Representation Transitions},
28	    author  = {Shi, Boyu and Liu, Chang and Gao, ChuanBao and Yang, Xu and Geng, Xin},
29	    journal = {arXiv preprint arXiv:2605.07271},
30	    year    = {2026},
31	    url     = {https://arxiv.org/abs/2605.07271},
32	}
33	
34	@article{deepseek-r1-2025,
35	    title   = {{DeepSeek-R1} incentivizes reasoning in {LLMs} through reinforcement learning},
36	    author  = {{DeepSeek-AI}},
37	    journal = {Nature},
38	    volume  = {645},
39	    pages   = {633--638},
40	    year    = {2025},
41	    doi     = {10.1038/s41586-025-09422-z},
42	}
43	
44	@inproceedings{defensivekv-iclr2026,
45	    title     = {{DefensiveKV}: Taming the Fragility of {KV} Cache Eviction in {LLM} Inference},
46	    author    = {Feng, Yuan and Guo, Haoyu and Lv, Junlin and Zhou, S. Kevin and Xie, Xike},
47	    booktitle = {International Conference on Learning Representations},
48	    year      = {2026},
49	    url       = {https://arxiv.org/abs/2510.13334},
50	}
51	
52	@article{doing-more-with-less-2026,
53	    title   = {Doing More With Less: Revisiting the Effectiveness of {LLM} Pruning for Test-Time Scaling},
54	    author  = {Monjur, Ocean and Nahin, Shahriar Kabir and Chhabra, Anshuman},
55	    journal = {arXiv preprint arXiv:2604.25098},
56	    year    = {2026},
57	    url     = {https://arxiv.org/abs/2604.25098},
58	}
59	
60	@book{efron-1993,
61	    title     = {An Introduction to the Bootstrap},
62	    author    = {Efron, Bradley and Tibshirani, Robert J.},
63	    publisher = {Chapman \& Hall/CRC},
64	    year      = {1993},
65	}
66	
67	@inproceedings{graspune-acl2026,
68	    title     = {{GRASPrune}: Global Gating for Budgeted Structured Pruning of Large Language Models},
69	    author    = {Wang, Ziyang and Xiao, Jiangfeng and Xiao, Chuan and Li, Ruoxiang and Mao, Rui and Qin, Jianbin},
70	    booktitle = {Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},
71	    year      = {2026},
72	    url       = {https://arxiv.org/abs/2604.19398},
73	}
74	
75	@article{greedy-bias-kvcache-2026,
76	    title   = {More Than a Quick Glance: Overcoming the Greedy Bias in {KV}-Cache Compression},
77	    author  = {Sood, Aryan and Sharma, Tanvi and Agrawal, Vansh},
78	    journal = {arXiv preprint arXiv:2602.02199},
79	    year    = {2026},
80	    url     = {https://arxiv.org/abs/2602.02199},
81	}
82	
83	@article{hold-onto-thought-neurips2025,
84	    title   = {Hold Onto That Thought: Assessing {KV} Cache Compression On Reasoning},
85	    author  = {Liu, Minghui and Palnitkar, Aadi and Rabbani, Tahseen and Jae, Hyunwoo and Sang, Kyle Rui and Yao, Dixi and Shabihi, Shayan and Zhao, Fuheng and Li, Tian and Zhang, Ce and Huang, Furong and Zhang, Kunpeng},
86	    journal = {arXiv preprint arXiv:2512.12008},
87	    year    = {2025},
88	    url     = {https://arxiv.org/abs/2512.12008},
89	}
90	
91	@inproceedings{h2o-neurips2023,
92	    title     = {{H2O}: Heavy-Hitter Oracle for Efficient Generative Inference of Large Language Models},
93	    author    = {Zhang, Zhenyu and Sheng, Ying and Zhou, Tianyi and Chen, Tianlong and Zheng, Lianmin and Cai, Ruisi and Song, Zhao and Tian, Yuandong and R{\'e}, Christopher and Barrett, Clark and Wang, Zhangyang and Chen, Beidi},
94	    booktitle = {Advances in Neural Information Processing Systems},
95	    year      = {2023},
96	    url       = {https://arxiv.org/abs/2306.14048},
97	}
98	
99	@article{hies-2025,
100	    title   = {Entropy Meets Importance: A Unified Head Importance-Entropy Score for Stable and Efficient Transformer Pruning},
101	    author  = {Choi, Minsik and Son, Hyegang and Kim, Changhoon and Kim, Young Geun},
102	    journal = {arXiv preprint arXiv:2510.13832},
103	    year    = {2025},
104	    url     = {https://arxiv.org/abs/2510.13832},
105	}
106	
107	@inproceedings{kwon-sosp2023,
108	    title     = {Efficient Memory Management for Large Language Model Serving with {PagedAttention}},
109	    author    = {Kwon, Woosuk and Li, Zhuohan and Zhuang, Siyuan and Sheng, Ying and Zheng, Lianmin and Yu, Cody Hao and Gonzalez, Joseph E. and Zhang, Hao and Stoica, Ion},
110	    booktitle = {Proceedings of the 29th Symposium on Operating Systems Principles},
111	    year      = {2023},
112	    url       = {https://arxiv.org/abs/2309.06180},
113	}
114	
115	@inproceedings{lethe-aaai2026,
116	    title     = {Lethe: Layer- and Time-Adaptive {KV} Cache Pruning for Reasoning-Intensive {LLM} Serving},
117	    author    = {Zeng, Hui and Zhao, Daming and Yang, Pengfei and Hou, WenXuan and Zheng, Tianyang and Li, Hui and Ji, Weiye and Zhai, Jidong},
118	    booktitle = {Proceedings of the AAAI Conference on Artificial Intelligence},
119	    year      = {2026},
120	    url       = {https://arxiv.org/abs/2511.06029},
121	}
122	
123	@inproceedings{math500-neurips2021,
124	    title     = {Measuring Mathematical Problem Solving With the {MATH} Dataset},
125	    author    = {Hendrycks, Dan and Burns, Collin and Kadavath, Saurav and Arora, Akul and Basart, Steven and Tang, Eric and Song, Dawn and Steinhardt, Jacob},
126	    booktitle = {Advances in Neural Information Processing Systems},
127	    year      = {2021},
128	    url       = {https://arxiv.org/abs/2103.03874},
129	}
130	
131	@inproceedings{michel-neurips2019,
132	    title     = {Are Sixteen Heads Really Better than One?},
133	    author    = {Michel, Paul and Levy, Omer and Neubig, Graham},
134	    booktitle = {Advances in Neural Information Processing Systems},
135	    year      = {2019},
136	    url       = {https://arxiv.org/abs/1905.10650},
137	}
138	
139	@inproceedings{nacl-acl2024,
140	    title     = {{NACL}: A General and Effective {KV} Cache Eviction Framework for {LLMs} at Inference Time},
141	    author    = {Chen, Yilong and Wang, Guoxia and Shang, Junyuan and Cui, Shiyao and Zhang, Zhenyu and Liu, Tingwen and Wang, Shuohuan and Sun, Yu and Yu, Dianhai and Wu, Hua},
142	    booktitle = {Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},
143	    year      = {2024},
144	    url       = {https://arxiv.org/abs/2408.03675},
145	}
146	
147	@article{phase-transition-compression-2026,
148	    title   = {Phase transitions in large language model compression},
149	    author  = {Ma, Ziyang and Li, Zuchao and Zhang, Lefei and Xia, Gui-Song and Du, Bo and Zhang, Liangpei and Tao, Dacheng},
150	    journal = {npj Artificial Intelligence},
151	    volume  = {2},
152	    number  = {21},
153	    year    = {2026},
154	    url     = {https://www.nature.com/articles/s44387-026-00072-8},
155	}
156	
157	@article{physics-kvcache-2026,
158	    title   = {Understanding the Physics of Key-Value Cache Compression for {LLMs} through Attention Dynamics},
159	    author  = {Ananthanarayanan, Samhruth and Sengupta, Ayan and Chakraborty, Tanmoy},
160	    journal = {arXiv preprint arXiv:2603.01426},
161	    year    = {2026},
162	    url     = {https://arxiv.org/abs/2603.01426},
163	}
164	
165	@inproceedings{pope-mlsys2023,
166	    title     = {Efficiently Scaling Transformer Inference},
167	    author    = {Pope, Reiner and Douglas, Sholto and Chowdhery, Aakanksha and Devlin, Jacob and Bradbury, James and Heek, Jonathan and Xiao, Kefan and Agrawal, Shivani and Dean, Jeff},
168	    booktitle = {Proceedings of Machine Learning and Systems},
169	    year      = {2023},
170	    url       = {https://arxiv.org/abs/2211.05102},
171	}
172	
173	@inproceedings{pyramidkv-colm2025,
174	    title     = {{PyramidKV}: Dynamic {KV} Cache Compression based on Pyramidal Information Funneling},
175	    author    = {Cai, Zefan and Zhang, Yichi and Gao, Bofei and Liu, Yuliang and Liu, Tianyu and Lu, Keming and Xiong, Wayne and Dong, Yue and Chang, Baobao and Hu, Junjie and Xiao, Wen},
176	    booktitle = {Conference on Language Modeling},
177	    year      = {2025},
178	    url       = {https://arxiv.org/abs/2406.02069},
179	}
180	
181	@article{qwen25-2024,
182	    title   = {{Qwen2.5} Technical Report},
183	    author  = {Yang, An and Yang, Baosong and Zhang, Beichen and Hui, Binyuan and Zheng, Bo and Yu, Bowen and Li, Chengyuan and Liu, Dayiheng and Huang, Fei and Wei, Haoran and others},
184	    journal = {arXiv preprint arXiv:2412.15115},
185	    year    = {2024},
186	    url     = {https://arxiv.org/abs/2412.15115},
187	}
188	
189	@article{retentivekv-2026,
190	    title   = {{RetentiveKV}: State-Space Memory for Uncertainty-Aware Multimodal {KV} Cache Eviction},
191	    author  = {Liu, Sihao and Xiong, YuFan and Jiang, Zhonghua and Wang, Zhaode and Lv, Chengfei and Zhang, Shengyu},
192	    journal = {arXiv preprint arXiv:2605.04075},
193	    year    = {2026},
194	    url     = {https://arxiv.org/abs/2605.04075},
195	}
196	
197	@inproceedings{rkv-neurips2025,
198	    title     = {{R-KV}: Redundancy-Aware {KV} Cache Compression for Reasoning Models},
199	    author    = {Cai, Zefan and Xiao, Wen and Sun, Hanshi and Luo, Cheng and Zhang, Yikai and Wan, Ke and Li, Yucheng and Zhou, Yeyang and Chang, Li-Wen and Gu, Jiuxiang and Dong, Zhen and Anandkumar, Anima and Asi, Abedelkadir and Hu, Junjie},
200	    booktitle = {Advances in Neural Information Processing Systems},
201	    year      = {2025},
202	    url       = {https://arxiv.org/abs/2505.24133},
203	}
204	
205	@inproceedings{slim-icml2025,
206	    title     = {{SLiM}: One-shot Quantization and Sparsity with Low-rank Approximation for {LLM} Weight Compression},
207	    author    = {Mozaffari, Mohammad and Yazdanbakhsh, Amir and Dehnavi, Maryam Mehri},
208	    booktitle = {Proceedings of the 42nd International Conference on Machine Learning},
209	    year      = {2025},
210	    url       = {https://arxiv.org/abs/2410.09615},
211	}
212	
213	@inproceedings{snapkv-neurips2024,
214	    title     = {{SnapKV}: {LLM} Knows What You Are Looking for Before Generation},
215	    author    = {Li, Yuhong and Huang, Yingbing and Yang, Bowen and Venkitesh, Bharat and Locatelli, Acyr and Ye, Hanchen and Cai, Tianle and Lewis, Patrick and Chen, Deming},
216	    booktitle = {Advances in Neural Information Processing Systems},
217	    year      = {2024},
218	    url       = {https://arxiv.org/abs/2404.14469},
219	}
220	
221	
222	@inproceedings{spark-aaai2026,
223	    title     = {{SparK}: Query-Aware Unstructured Sparsity with Recoverable {KV} Cache Channel Pruning},
224	    author    = {Liao, Huanxuan and Xu, Yixing and He, Shizhu and Li, Guanchen and Yin, Xuanwu and Li, Dong and Barsoum, Emad and Zhao, Jun and Liu, Kang},
225	    booktitle = {Proceedings of the AAAI Conference on Artificial Intelligence},
226	    year      = {2026},
227	    url       = {https://arxiv.org/abs/2508.15212},
228	}
229	
230	@article{sparse-frontier-2025,
231	    title   = {The Sparse Frontier: Sparse Attention Trade-offs in Transformer {LLMs}},
232	    author  = {Nawrot, Piotr and Li, Robert and Huang, Renjie and Ruder, Sebastian and Marchisio, Kelly and Ponti, Edoardo M.},
233	    journal = {arXiv preprint arXiv:2504.17768},
234	    year    = {2025},
235	    url     = {https://arxiv.org/abs/2504.17768},
236	}
237	
238	@inproceedings{thinkv-iclr2026,
239	    title     = {{ThinKV}: Thought-Adaptive {KV} Cache Compression for Efficient Reasoning Models},
240	    author    = {Ramachandran, Akshat and Neseem, Marina and Sakr, Charbel and Venkatesan, Rangharajan and Khailany, Brucek and Krishna, Tushar},
241	    booktitle = {International Conference on Learning Representations},
242	    year      = {2026},
243	    url       = {https://arxiv.org/abs/2510.01290},
244	}
245	
246	@article{unicomp-2026,
247	    title   = {{UniComp}: A Unified Evaluation of Large Language Model Compression via Pruning, Quantization and Distillation},
248	    author  = {von Rad, Jonathan and Cao, Yong and Geiger, Andreas},
249	    journal = {arXiv preprint arXiv:2602.09130},
250	    year    = {2026},
251	    url     = {https://arxiv.org/abs/2602.09130},
252	}
253	
254	@article{longflow-2026,
255	    title   = {{LongFlow}: Efficient {KV} Cache Compression for Reasoning Models},
256	    author  = {Su, Yi and Tian, Zhenxu and Qiao, Dan and Zhou, Yuechi and Li, Juntao and Zhang, Min},
257	    journal = {arXiv preprint arXiv:2603.11504},
258	    year    = {2026},
259	    url     = {https://arxiv.org/abs/2603.11504},
260	}
261	
262	@inproceedings{pmkvq-iclr2026,
263	    title     = {{PM-KVQ}: Progressive Mixed-precision {KV} Cache Quantization for Long-{CoT} {LLMs}},
264	    author    = {Liu, Tengxuan and Li, Shiyao and Yang, Jiayi and Zhao, Tianchen and Zhou, Feng and Song, Xiaohui and Dai, Guohao and Yan, Shengen and Yang, Huazhong and Wang, Yu},
265	    booktitle = {International Conference on Learning Representations},
266	    year      = {2026},
267	    url       = {https://arxiv.org/abs/2505.18610},
268	}
269	
270	@article{rlkv-2025,
271	    title   = {Which Heads Matter for Reasoning? {RL}-Guided {KV} Cache Compression},
272	    author  = {Du, Wenjie and Jiang, Li and Tao, Keda and Liu, Xue and Wang, Huan},
273	    journal = {arXiv preprint arXiv:2510.08525},
274	    year    = {2025},
275	    url     = {https://arxiv.org/abs/2510.08525},
276	}
277	
278	
279	@article{lkv-2026,
280	    title   = {{LKV}: End-to-End Learning of Head-wise Budgets and Token Selection for {LLM} {KV} Cache Eviction},
281	    author  = {Zhou, Enshuai and Hao, Yifan and Wang, Chao and Zhang, Rui and Huang, Di and Guo, Jiaming and Hu, Xing and Du, Zidong and Guo, Qi and Chen, Yunji},
282	    journal = {arXiv preprint arXiv:2605.06676},
283	    year    = {2026},
284	    url     = {https://arxiv.org/abs/2605.06676},
285	}
286	
287	@inproceedings{xu2025think,
288	    title     = {{ThinK}: Thinner Key Cache by Query-Driven Pruning},
289	    author    = {Xu, Yuhui and Jie, Zhanming and Dong, Hanze and Wang, Lei and Lu, Xudong and Zhou, Aojun and Saha, Amrita and Xiong, Caiming and Sahoo, Doyen},
290	    booktitle = {International Conference on Learning Representations},
291	    year      = {2025},
292	    url       = {https://arxiv.org/abs/2407.21018},
293	}
294	
295	@article{dong2026foresightkv,
296	    title   = {{ForesightKV}: Optimizing {KV} Cache Eviction for Reasoning Models by Learning Long-Term Contribution},
297	    author  = {Dong, Zican and Liu, Peiyu and Li, Junyi and Chen, Zhipeng and Peng, Han and Wang, Shuo and Zhao, Wayne Xin},
298	    journal = {arXiv preprint arXiv:2602.03203},
299	    year    = {2026},
300	    url     = {https://arxiv.org/abs/2602.03203},
301	}
302	
303	@inproceedings{kim2026pqqp,
304	    title     = {Prune-then-Quantize or Quantize-then-Prune? Understanding the Impact of Compression Order in Joint Model Compression},
305	    author    = {Kim, Minjun and Choi, Jaehyeon and Yang, Hyunwoo and Kim, Jongjin and Song, Jinho and Kang, U},
306	    booktitle = {International Conference on Learning Representations},
307	    year      = {2026},
308	    url       = {https://arxiv.org/abs/2603.18426},
309	}
310	
311	@article{lanham-2023-faithfulness,
312	    title   = {Measuring Faithfulness in Chain-of-Thought Reasoning},
313	    author  = {Lanham, Tamera and Chen, Anna and Radhakrishnan, Ansh and Steiner, Benoit and Denison, Carson and Hernandez, Danny and Li, Dustin and Durmus, Esin and Hubinger, Evan and Kernion, Jackson and others},
314	    journal = {arXiv preprint arXiv:2307.13702},
315	    year    = {2023},
316	    url     = {https://arxiv.org/abs/2307.13702},
317	}
318	
319	@inproceedings{turpin-2023-biased-cot,
320	    title     = {Language Models Don't Always Say What They Think: Unfaithful Explanations in Chain-of-Thought Prompting},
321	    author    = {Turpin, Miles and Michael, Julian and Perez, Ethan and Bowman, Samuel R.},
322	    booktitle = {Advances in Neural Information Processing Systems},
323	    year      = {2023},
324	    url       = {https://arxiv.org/abs/2305.04388},
325	}
326	
327	@inproceedings{voita-acl2019,
328	    title     = {Analyzing Multi-Head Self-Attention: Specialized Heads Do the Heavy Lifting, the Rest Can Be Pruned},
329	    author    = {Voita, Elena and Talbot, David and Moiseev, Fedor and Sennrich, Rico and Titov, Ivan},
330	    booktitle = {Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
331	    year      = {2019},
332	    url       = {https://arxiv.org/abs/1905.09418},
333	}
334	
335	@inproceedings{wei-neurips2022-cot,
336	    title     = {Chain-of-Thought Prompting Elicits Reasoning in Large Language Models},
337	    author    = {Wei, Jason and Wang, Xuezhi and Schuurmans, Dale and Bosma, Maarten and Ichter, Brian and Xia, Fei and Chi, Ed and Le, Quoc and Zhou, Denny},
338	    booktitle = {Advances in Neural Information Processing Systems},
339	    year      = {2022},
340	    url       = {https://arxiv.org/abs/2201.11903},
341	}
342	
343	@article{rein-gpqa-2024,
344	    title   = {{GPQA}: A Graduate-Level Google-Proof Q\&A Benchmark},
345	    author  = {Rein, David and Hou, Betty Li and Stickland, Asa Cooper and Petty, Jackson and Pang, Richard Yuanzhe and Dirani, Julien and Michael, Julian and Bowman, Samuel R.},
346	    journal = {arXiv preprint arXiv:2311.12022},
347	    year    = {2024},
348	    url     = {https://arxiv.org/abs/2311.12022},
349	}
350	
351	@inproceedings{frankle-iclr2019,
352	    title     = {The Lottery Ticket Hypothesis: Finding Sparse, Trainable Neural Networks},
353	    author    = {Frankle, Jonathan and Carlin, Michael},
354	    booktitle = {International Conference on Learning Representations},
355	    year      = {2019},
356	    url       = {https://arxiv.org/abs/1803.03635},
357	}
358	
359	@inproceedings{han-neurips2015,
360	    title     = {Learning both Weights and Connections for Efficient Neural Networks},
361	    author    = {Han, Song and Pool, Jeff and Tran, John and Dally, William J.},
362	    booktitle = {Advances in Neural Information Processing Systems},
363	    year      = {2015},
364	    url       = {https://arxiv.org/abs/1506.02626},
365	}
366	
367	@inproceedings{sanh-neurips2020,
368	    title     = {Movement Pruning: Adaptive Sparsity during Fine-Tuning},
369	    author    = {Sanh, Victor and Wolf, Thomas and Rush, Alexander M.},
370	    booktitle = {Advances in Neural Information Processing Systems},
371	    year      = {2020},
372	    url       = {https://arxiv.org/abs/2005.07683},
373	}
374	
375	@article{scissorhands-2023,
376	    title   = {Scissorhands: Exploiting the Persistence of Importance Hypothesis for {LLM} {KV} Cache Compression},
377	    author  = {Liu, Zichang and Desai, Aditya and Liao, Fangshuo and Wang, Weitao and Xie, Victor and Xu, Zhaozhuo and Kyrillidis, Anastasios and Shrivastava, Anshumali},
378	    journal = {arXiv preprint arXiv:2305.17118},
379	    year    = {2023},
380	    url     = {https://arxiv.org/abs/2305.17118},
381	}
382	
383	@article{snell-2024-scaling-test-time,
384	    title   = {Scaling {LLM} Test-Time Compute Optimally Can be More Effective Than Scaling Model Parameters},
385	    author  = {Snell, Charlie and Lee, Jaehoon and Xu, Kelvin and Kumar, Aviral},
386	    journal = {arXiv preprint arXiv:2408.03314},
387	    year    = {2024},
388	    url     = {https://arxiv.org/abs/2408.03314},
389	}
390	
391	@article{fedus-jmlr2022,
392	    title   = {Switch Transformers: Scaling to Trillion Parameter Models with Simple and Efficient Sparsity},
393	    author  = {Fedus, William and Zoph, Barret and Shazeer, Noam},
394	    journal = {Journal of Machine Learning Research},
395	    volume  = {23},
396	    number  = {120},
397	    pages   = {1--39},
398	    year    = {2022},
399	    url     = {https://arxiv.org/abs/2101.03961},
400	}
401	
402	@article{lazyeviction2025,
403	    title   = {{LazyEviction}: Lagged {KV} Eviction with Attention Pattern Observation for Efficient Long Reasoning},
404	    author  = {Zhang, Haoyue and Zhang, Hualei and Ma, Xiaosong and Zhang, Jie and Guo, Song},
405	    journal = {arXiv preprint arXiv:2506.15969},
406	    year    = {2025},
407	    url     = {https://arxiv.org/abs/2506.15969},
408	}
409	
410	@inproceedings{shazeer-2017-moe,
411	    title     = {Outrageously Large Neural Networks: The Sparsely-Gated Mixture-of-Experts Layer},
412	    author    = {Shazeer, Noam and Mirhoseini, Azalia and Maziarz, Krzysztof and Davis, Andy and Le, Quoc and Hinton, Geoffrey and Dean, Jeff},
413	    booktitle = {International Conference on Learning Representations},
414	    year      = {2017},
415	    url       = {https://arxiv.org/abs/1701.06538},
416	}
417	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ddb74de4-302e-4dda-b8be-f30e0953d287",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "fe90f4aa-5d64-4f3f-aeb2-d68bdfc4d141",
  "sourceToolAssistantUUID": "ddb74de4-302e-4dda-b8be-f30e0953d287",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-17T01:20:21.743Z_

<details open><summary>🔧 Tool call — Read · `toolu_01S1M6SwTTANwRvnC3EwU24a`</summary>

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
  "parentUuid": "fe90f4aa-5d64-4f3f-aeb2-d68bdfc4d141",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GBnRXHmfdNTy8MR6fM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7b1bfe71-722c-4c86-a2b1-786cd3c3df22",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EpgfH4qXPycjCDBzQB7WpM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10486,
      "cache_read_input_tokens": 37754,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10486,
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

_source line 25 · 2026-05-17T01:20:21.754Z_

<details><summary>↩ Tool result · `toolu_01S1M6SwTTANwRvnC3EwU24a`</summary>

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
  "parentUuid": "7b1bfe71-722c-4c86-a2b1-786cd3c3df22",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "d3fe84bf-1ce7-48fa-94f0-ccb2fdca2b5f",
  "sourceToolAssistantUUID": "7b1bfe71-722c-4c86-a2b1-786cd3c3df22",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-17T01:20:21.956Z_

<details open><summary>🔧 Tool call — Read · `toolu_013pjfjcn2sQnfBehuFBppet`</summary>

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
  "parentUuid": "d3fe84bf-1ce7-48fa-94f0-ccb2fdca2b5f",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GBnRXHmfdNTy8MR6fM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1cb69290-97de-4ae3-ae62-8e60a3e44285",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EpgfH4qXPycjCDBzQB7WpM",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10486,
      "cache_read_input_tokens": 37754,
      "output_tokens": 167,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 10486
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 167,
          "cache_read_input_tokens": 37754,
          "cache_creation_input_tokens": 10486,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 10486,
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

_source line 27 · 2026-05-17T01:20:21.963Z_

<details><summary>↩ Tool result · `toolu_013pjfjcn2sQnfBehuFBppet`</summary>

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
  "parentUuid": "1cb69290-97de-4ae3-ae62-8e60a3e44285",
  "isSidechain": true,
  "promptId": "e094363e-fd4f-4649-8867-0eb6b8a0e169",
  "agentId": "a0f61c367bd26458b",
  "type": "user",
  "uuid": "715db202-2663-497f-8b20-5d2f504633d3",
  "sourceToolAssistantUUID": "1cb69290-97de-4ae3-ae62-8e60a3e44285",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 28 · 2026-05-17T01:21:30.587Z_

Now I have sufficient information to write a comprehensive review. Let me compose it.

---

## Review: Phase-Gated Compound Sparsity (R2: Novelty and Related Work)

### 1. Summary

This paper empirically investigates how compound sparsity (simultaneous attention head pruning + KV cache eviction) interacts with reasoning phases in LLMs. The core finding is that the super-additive degradation from compound sparsity is not phase-invariant: importance-based eviction produces a monotonically increasing severity gradient across reasoning phases (low-sparsity phases suffer more), while recency-based and random eviction produce null or near-null gradients. The authors validate across 3 models, 2 architectures, and 3 benchmarks, and propose "discrimination collapse" (Gini/CV decline of importance scores) as a correlational mechanistic explanation.

### 2. Strengths

- **Well-controlled experimental design.** The triple dissociation (importance / recency / random) is a sound methodological structure. Using recency eviction as a scoring-independent control to rule out phase segmentation circularity is a thoughtful experimental choice, even if calling it a "methodological innovation" overstates its novelty.

- **Thorough statistical treatment.** Per-problem paired bootstrap (B=10000), Bonferroni correction, Wilcoxon signed-rank tests, and dose-response monotonicity (Spearman rho=1.0) at n=500 demonstrate genuine statistical rigor for an empirical paper. The effect sizes are non-trivial (d_z up to 1.15).

- **Multi-axis generalization.** The paper systematically varies models (DeepSeek-R1-Distill-Qwen, Qwen2.5, LLaMA), benchmarks (MATH-500, GSM8K, GPQA), and sparsity levels (s=0.15-0.30). The finding that strategy specificity is architecture-dependent (15-17x on Qwen2 vs 2.0-2.6x on LLaMA) is honestly reported and adds nuance.

- **Related work is comprehensive relative to typical empirical papers.** The paper cites ~40 references spanning compound compression, phase-aware methods, adaptive eviction, structured pruning, and conditional computation. The positioning paragraph at the end clearly differentiates from SparK, ThinKV, and HIES.

- **Honest limitations.** The paper acknowledges 7B-only scale, correlational (not causal) discrimination collapse, task-dependent strategy specificity, and the failure of the mitigation pilot (C5b).

### 3. Weaknesses

- **Incremental conceptual novelty.** The core finding can be restated as: "importance-based eviction degrades more in easy/low-entropy phases because head pruning destroys the score distribution that importance eviction relies on." This is arguably predictable from first principles once you combine two known facts: (a) HIES (2025) already showed importance scores collapse under pruning, and (b) ThinKV (2026) already showed phase-dependent compression tolerance. The paper's contribution is measuring this interaction rather than discovering a non-obvious phenomenon. For a top venue, the "so what" question looms large: now that we know this, what do we do differently? The mitigation pilot failed.

- **"Discrimination collapse" is a relabeling, not a new mechanism.** HIES (2025) described importance score collapse under compression and proposed entropy compensation. The paper acknowledges HIES provides "independent supporting evidence" but frames discrimination collapse as its own contribution. In reality, the Gini/CV analysis is the same phenomenon (score distribution flattening) measured with different statistics in a compound setting. The mechanistic depth is shallow: the paper shows Gini drops correlate with severity divergence but does not establish a causal chain, and entropy redistribution is model-dependent (fails on Qwen). This is not a mechanistic "explanation" but a correlational re-description.

- **Missing important related work on GQA/MQA architectures.** The paper tests standard MHA models (or Qwen2's GQA variant) but does not discuss how GQA/MQA (which share KV heads across query heads) fundamentally changes compound interaction. GQA-based models like Llama-3 are the deployment standard; the paper's head pruning assumes independent heads but does not address how shared KV heads alter the interaction. This is a significant gap in both related work coverage and experimental design.

- **No discussion of SnapKV-style observation window methods beyond a citation.** SnapKV, PyramidKV, and related methods that use observation windows rather than pure attention-score accumulation represent a different "strategy" category that could exhibit different phase-sensitivity. The paper only tests H2O-style importance eviction, which is the simplest and most fragile approach. The generality claim ("importance-based eviction") is narrower than presented.

- **Venue fit concern for a pure empirical finding paper.** The paper explicitly positions as "not a method paper" and the mitigation pilot failed. For EMNLP 2026, the standard question is: does this finding change how anyone builds systems? The dose-response characterization is intellectually interesting but the practical implication ("use phase-aware budgets") is obvious once stated, and the paper cannot demonstrate it works (C5b failed). The "phase-gated analysis framework" contribution (contribution 5 in Introduction) is essentially: segment by perplexity tertiles and compute Interaction Index per phase. This is a measurement protocol, not a framework.

- **Recency control is not as novel as claimed.** The paper states "no precedent in literature" for using recency eviction as a methodological control. However, StreamingLLM's recency-based approach is routinely used as a control condition in KV cache papers. The "innovation" is using it specifically to rule out phase segmentation circularity, which is a reasonable experimental choice but not a standalone contribution worth highlighting as a primary contribution (contribution 3).

- **Phase segmentation validity concern not fully resolved.** The perplexity-tertile segmentation from the uncompressed model defines "phases" that may not correspond to meaningful cognitive/computational boundaries. The paper uses this as a proxy for reasoning complexity, but perplexity conflates multiple factors (vocabulary rarity, syntactic complexity, uncertainty). Alternative segmentation methods (e.g., based on attention pattern structure, or token type) are not explored. The recency control rules out circularity artifacts, but does not validate that the phases correspond to anything mechanistically meaningful.

- **Strategy specificity varies so much across conditions that the headline numbers are cherry-picked.** The ratio ranges from 2.0x (LLaMA) to 17x (DeepSeek on MATH-500) depending on architecture and benchmark. Reporting "15-17x" in the abstract without immediately qualifying this as the maximum-case observation is potentially misleading.

### 4. Questions for Authors

1. **On mechanistic novelty:** Given that HIES already demonstrated importance score collapse under single-axis pruning and proposed a fix (entropy compensation), what is the specific new mechanistic insight from your "discrimination collapse" analysis beyond confirming the same phenomenon occurs in compound settings? Have you tried applying HIES's entropy compensation in your compound setting?

2. **On GQA interaction:** Your models include Qwen2 (which uses GQA with 4 KV head groups for 28 query heads). How does shared KV heads affect the interpretation of "head pruning" in your framework? When you prune attention heads that share KV caches, the interaction dynamics should differ fundamentally from MHA. Do you account for this?

3. **On eviction strategy generality:** You test H2O-style cumulative attention score eviction. Would observation-window methods (SnapKV, NACL) or learned eviction (LKV) show the same phase gradient? If the finding is specific to H2O's accumulation mechanism, the title should reflect this.

4. **On practical impact:** Given that the mitigation pilot (C5b) failed to achieve practical significance, what concrete guidance does this paper provide to practitioners? Is "avoid compound sparsity in low-perplexity phases" actionable without a working phase detector at inference time?

5. **On scale:** The paper exclusively uses 7B models. At 70B+ scale, attention patterns are known to differ substantially (more redundancy, more head specialization). Do you have any evidence, even indirect, that the phase-strategy interaction survives at scale?

6. **On the 15-17x claim:** This number comes from DeepSeek on MATH-500 at s>=0.25. On GSM8K the ratio drops to 2.3-3.8x, and on LLaMA it drops to 2.0-2.6x. Why should reviewers treat the maximum-case number as representative rather than the minimum?

### 5. Minor Issues

- The abstract uses "low-sparsity phase" and "high-sparsity phase" where "low-perplexity" and "high-perplexity" would be clearer. The terminology is confusing because "sparsity" already refers to the compression level.
- The Interaction Index formula (II_i = PPL_both - (PPL_prune + PPL_evict - PPL_base)) is standard for measuring super-additivity; it should be explicitly acknowledged as analogous to drug interaction indices in pharmacology or synergy metrics in biology.
- The paper would benefit from discussing when compound sparsity is actually deployed in practice. If practitioners rarely combine head pruning with KV eviction simultaneously, the motivation weakens.
- The GPQA experiments appear still running per the report. If these are not complete at submission time, this weakens the cross-benchmark claim.

### 6. Scores

| Dimension | Score | Justification |
|-----------|-------|---------------|
| **Overall** | 3 (Weak Reject) | The empirical methodology is sound but the conceptual novelty is limited. The finding is a predictable consequence of known phenomena (score collapse + phase-dependent attention), the mechanistic contribution repackages HIES, and the lack of actionable method or mitigation reduces practical significance. For a 25% acceptance rate venue, this falls below the threshold. |
| **Novelty** | 2/5 | The specific quantification is new, but the qualitative finding (importance scores degrade under compound stress, worse in certain phases) follows logically from prior work. The triple dissociation is methodologically competent but not conceptually surprising. |
| **Presentation** | 4/5 | Well-written, clearly structured, honest about limitations. The statistical reporting is exemplary. Minor terminology confusion (sparsity phases vs perplexity phases). |
| **Confidence** | 4/5 | I am familiar with the KV cache compression, attention head pruning, and reasoning-phase analysis literatures. I have moderate uncertainty about whether the EMNLP community would value this type of empirical characterization more than I currently estimate. |

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "715db202-2663-497f-8b20-5d2f504633d3",
  "isSidechain": true,
  "agentId": "a0f61c367bd26458b",
  "requestId": "req_011Cb7GC8z39ER81M6GwvxsR",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fa5a49f8-f336-4ff8-81ea-7bf2c6fbfeee",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse",
  "sessionId": "133834fc-cdb1-4626-a41f-e256628bff5f",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ADqiaWrnGjv54CNVHDKzGQ",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2776,
      "cache_read_input_tokens": 48240,
      "output_tokens": 2569,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2776
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2569,
          "cache_read_input_tokens": 48240,
          "cache_creation_input_tokens": 2776,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2776,
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
