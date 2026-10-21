# research compile paper evidence table

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 89
- **Recorded user turns:** 1
- **Tool calls:** 27
- **Original source:** `logs/workers/worker_research_compile_paper_evidence_table_20260516T032102.log`
- **Structured JSON:** [`593d497427637d8f38ac.json`](../../sessions/59/593d497427637d8f38ac.json)

## Before a recorded user message

21 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
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
    "mcp__agent-ml-research__read_experiment_plan_with_status",
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
  "uuid": "9e057023-7be7-4632-a38a-9fbbb246297d",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
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
    "resetsAt": 1778903400,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "426f7488-cc1c-4a36-8292-572e443459ec",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
Let me start by gathering all the necessary information in parallel: the registry, paper_framing.md, and experiment_plan with status.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "566246f6-074f-4a7c-bc79-b8984f7b9b20",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011TicxVD7rpvNGUiyUH7Pqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12458,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12458
      },
      "output_tokens": 21,
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

_source line 5_

Let me gather all the necessary data sources in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "ee679a8e-6b33-4b88-8ac2-cbde64f0255f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011TicxVD7rpvNGUiyUH7Pqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12458,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12458
      },
      "output_tokens": 21,
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

_source line 6_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_016WB9j4QADnhvA75sFUTqep`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_experiment_plan_with_status,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
  "max_results": 5
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "7f2d9379-45a5-4169-8e9a-54535756fa0a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011TicxVD7rpvNGUiyUH7Pqg",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12458,
      "cache_read_input_tokens": 11447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12458
      },
      "output_tokens": 21,
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

_source line 7 · 2026-05-16T03:21:13.120Z_

<details><summary>↩ Tool result · `toolu_016WB9j4QADnhvA75sFUTqep`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_experiment_plan_with_status"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
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
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "5015bfb0-7aa1-4072-8f03-553422a0926e",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_experiment_plan_with_status",
      "mcp__agent-ml-research__register_artifact",
      "mcp__agent-ml-research__save_project_file"
    ],
    "query": "select:mcp__agent-ml-research__read_registry,mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_experiment_plan_with_status,mcp__agent-ml-research__register_artifact,mcp__agent-ml-research__save_project_file",
    "total_deferred_tools": 26
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_014VG6cEtRuJPs2CfPmsiKGs`</summary>

```json
{
  "project": "faith-evidence-ie",
  "filters": {
    "status": "success"
  },
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
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "c6d8b01e-3a31-4857-b6d1-de0d2de4546c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HV9F1dQeoWwcYQDjawGRCW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1936,
      "cache_read_input_tokens": 23905,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1936
      },
      "output_tokens": 67,
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

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01BEzBpGhUNHrVYLxogaBmB3`</summary>

```json
{
  "project": "faith-evidence-ie",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6ca79780-ac9c-4468-94c1-cec1a595b090",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HV9F1dQeoWwcYQDjawGRCW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1936,
      "cache_read_input_tokens": 23905,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1936
      },
      "output_tokens": 67,
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

_source line 10 · 2026-05-16T03:21:17.273Z_

<details><summary>↩ Tool result · `toolu_014VG6cEtRuJPs2CfPmsiKGs`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5207}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "e5a9096d-9bcd-4038-9a78-9cdb82de031e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": {}, \\\"count\\\": 0, \\\"total\\\": 0, \\\"baseline\\\": null}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.5207}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {}, \"count\": 0, \"total\": 0, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.5207}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 11 · 2026-05-16T03:21:17.285Z_

<details><summary>↩ Tool result · `toolu_01BEzBpGhUNHrVYLxogaBmB3`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/paper_framing.md\", \"content\": \"# Paper Framing — FREIGE\\n\\n> **状态**: POST-MVP + DREAM v2 完成（D047 分析）\\n> **最后更新**: 2026-05-16\\n> **Dream v1**: best=2.5, median=3.0, worst=2.5 → reframe 完成\\n> **Dream v2**: best=3.0, median=2.5, worst=2.5 → best 提升但 median 下降，未达标。关键路径：plan_011 bf16 GRPO eval + structural fixes → re-dream v3\\n\\n## Target Venue\\n\\n- Primary: **EMNLP 2026 Main** (ARR July cycle, ~July 15-25 → commit EMNLP Aug/Sep)\\n- Fallback: AAAI 2027 (abstract July 25, paper Aug 1)\\n\\n## Core Insight\\n\\nLLM-based document-level IE 已逼近 encoder SOTA 的抽取精度，但零方法能生成可验证证据。本文提出 **evidence-grounded DocRE** 作为新任务范式：LLM 同时输出关系三元组和支撑证据句。\\n\\n我们系统性地探索了 online RL (GRPO) 、offline preference optimization (DPO) 和 offline RL (RSFT) 三条技术路线。关键发现：**RL optimization pressure 与 evidence-extraction decoupling severity 正相关**——优化强度越大，evidence 质量提升的同时抽取能力退化越严重。QLoRA 放大至 catastrophic（rel_f1<0.02），bf16 GRPO 从 0.4549 退化至 ~0.434（mild, -2pp），DPO 呈 gradual 退化（1ep→3ep rel_f1 从 0.4034→0.3429），RSFT 无 decoupling。\\n\\nCED (Contrastive Evidence Discrimination) 是一种 NLI-based 候选筛选函数，通过文档内 hard negative 对比评估 evidence 质量。CED 作为 RSFT 的 scoring function 之一进行测试，其相对于 flat-NLI 的优势需要通过充分的统计检验验证。\\n\\n## Story Arc\\n\\n1. **Problem**: LLM DocRE 无证据 → 部署障碍\\n2. **New task**: evidence-grounded DocRE — 同时生成关系和证据\\n3. **Cost of faithfulness**: evidence generation 代价 ~7pp Ign-F1（no-evidence 47.36 vs evidence-SFT 40.36）——这是 faithfulness 的真实成本\\n4. **Exploration**: 系统性比较 online RL (GRPO) vs offline preference (DPO) vs offline RL (RSFT)\\n5. **Key finding**: evidence-extraction decoupling — RL optimization pressure 与 decoupling severity 正相关，形成连续谱系（GRPO-QLoRA catastrophic > GRPO-bf16 mild > DPO gradual > RSFT none）\\n6. **QLoRA amplification**: QLoRA 量化将 mild decoupling 放大至 catastrophic forgetting——decoupling 是 RL-for-IE 中 multi-objective competition 的通用梯度（intra-task trade-off，非 inter-task forgetting），QLoRA 是 catastrophic amplifier\\n7. **What works**: RSFT with NLI-based scoring 是唯一有效路线——提升 evidence 质量而不牺牲抽取\\n8. **Best practical solution**: CED reranker 恢复 97% 的 evidence 代价，同时保留高质量 evidence（evi_f1=0.8188）\\n9. **Diagnostic tool**: EDCR 双层诊断——方法级量化 decoupling（与 Claim 2 呼应），per-relation 级揭示 evi_f1 不捕捉的 relation-type 难度差异（D070 ✅）\\n\\n## Core Claims (reframed after Dream v1, updated D068/D069/D070/D071/D072)\\n\\n### Claim 1 (Main): Evidence-grounded DocRE 是可行的新能力\\n- FREIGE 是首个在 DocRED 上同时输出 (head, relation, tail, [evidence]) 的 LLM 方法\\n- **Evidence generation tax**: no-evidence SFT Ign-F1=47.36 vs evidence-SFT 40.36，代价 ~7pp（plan_014 ✅）\\n- RSFT 在 4/4 配置下均超过 SFT baseline（Ign-F1 +3.3~5.5pp）\\n- **CED reranker 是最优实用方案**: rel_f1=0.4864（仅低于 no-evidence 0.29pp），evi_f1=0.8188（plan_005 ✅）\\n- 需要 DREEAM-protocol 对齐的 Evi-F1 对比（D041 在处理中）\\n\\n### Claim 2 (Core finding): RL optimization pressure 与 evidence-extraction decoupling severity 正相关（D068/D069 修正）\\n- **Decoupling spectrum**: 优化强度越大，decoupling 越严重\\n  - GRPO QLoRA: catastrophic（rel_f1=0.0138, evi_f1=0.850, EDCR=0.99）— QLoRA 放大 decoupling\\n  - GRPO bf16: mild（rel_f1 从 0.4549→~0.434, -2pp; step_30=0.434, step_50=0.4276, step_70=0.4341）— 退化可控但持续（D065/D066）\\n  - DPO bf16 1ep→3ep: gradual（Ign-F1 38.88→TBD, rel_f1 0.4034→0.3429）— 随训练渐进退化（D067/D068）\\n  - RSFT: none — 无 decoupling，唯一有效路线\\n- **QLoRA 是 catastrophic amplifier，不是 root cause**: bf16 GRPO 仅 mild decoupling（-2pp），QLoRA 放大至 catastrophic（-39pp）（D054/D065/D066）\\n- **Decoupling 是 RL-for-IE 的通用梯度**: 跨方法（GRPO/DPO）、跨量化策略（QLoRA/bf16）一致出现，严重程度与优化压力正相关\\n- 三档 Dream 审稿均认为此发现\\\\\\\"genuinely novel and striking\\\\\\\"\\n- **已完成**: GRPO G=8 bf16 确认 mild decoupling（plan_011 ✅）; DPO 1ep/3ep 确认 gradual decoupling（plan_012 ✅）\\n\\n### Claim 3 (Ablation): NLI-based scoring 提升 RSFT 质量\\n- CED 和 flat-NLI 都优于 random/no scoring\\n- CED vs flat-NLI 的差异需统计验证（Dream 报告 p=0.08/0.38/0.12 不显著）\\n- **Critical**: 如果 CED 不显著优于 flat-NLI → CED 降级为\\\"one possible scoring function\\\"\\n- **行动**: 5+ seeds for significance testing\\n- **top_k selection ablation (k=1 vs k=3)**:\\n  - k=1 (best-of-8) 优于 k=3 (top3-of-8)，CED scoring precision 随 k 增大下降\\n  - k=1 均值 (3 seeds s42/s43/s44): Ign-F1=45.00, rel_f1=0.4596, evi_f1=81.43, EDCR=0.6434\\n  - k=3 (1 seed, reeval_rsft_topk3): Ign-F1=43.64, rel_f1=0.4454, evi_f1=80.88, EDCR=0.6635\\n  - Δ (k=3 vs k=1 mean): Ign-F1 **-1.36pp**, rel_f1 **-1.42pp**, evi_f1 **-0.55pp**, EDCR +0.02\\n  - 训练数据质量下降: k=1 mean_f1=0.6157, mean_ced=0.6683 → k=3 mean_f1=0.5761, mean_ced=0.6205（来源: mvp2_rsft_ced_scoring / mvp2_rsft_ced_scoring_topk3_r2）\\n  - 训练集规模: k=1 选出 2718 样本 (12.4%), k=3 选出 8037 样本 (37%), 数据量 ×2.96 但质量下降抵消数量优势\\n  - **叙事**: 低排名 response 引入噪声——rank 2-3 样本的 F1 和 CED 分数均显著低于 rank 1，扩大训练集规模无法补偿数据质量的稀释。这表明 RSFT 的关键不在数据量而在 scoring precision\\n  - **注**: k=3 仅 1 seed，差异方向一致但尚不具备统计显著性；作为 ablation table 中的辅助行呈现，不作为独立 claim\\n\\n### Claim 4 (Diagnostic): EDCR 双层诊断价值（D070/D072）\\n- **Layer 1 — 方法级**: EDCR 量化 evidence-extraction decoupling，与 Claim 2 spectrum 呼应\\n  - 方法级 EDCR 与 rel_f1 Spearman ρ=-0.965（plan_003 ✅）——本质是 decoupling 的度量\\n  - EDCR 识别病理模型（GRPO QLoRA: EDCR≈1.0）\\n- **Layer 2 — per-relation-type**: EDCR 提供 evi_f1 不捕捉的 relation-type 诊断信息 ✅\\n  - per-relation ρ(EDCR, evi_f1) = **-0.064** (p=0.58) → **完全独立于 evi_f1**\\n  - per-relation ρ(EDCR, rel_f1) = -0.793 (p<0.001) → 与 rel_f1 强相关但非完美\\n  - per-relation ρ(evi_f1, rel_f1) = -0.013 (p=0.91) → evidence 质量与抽取能力在 relation type 间完全解耦\\n  - 典型案例：date_of_birth (EDCR=0.118, 高 faithful) vs head_of_government (EDCR=0.956, 高 decoupled)\\n  - 93 relation types 分析（≥5 样本），76 个有非零数据\\n- **论文叙事**: EDCR 在方法级是 decoupling 度量工具（横向对比方法），在 relation 级是难度诊断工具（纵向定位薄弱 relation）——两层叙事互补\\n- **仍需**: 100 例人工标注验证（RC6）\\n\\n## MVP Evidence Summary (D071: 主表报 Ign-F1，附录报 F1)\\n\\n| Config | Ign-F1 | F1 | Δ vs SFT (Ign-F1) | Evi-F1 (cond) | Evi-F1 (joint) | EDCR |\\n|--------|--------|------|-------------------|---------------|---------------|------|\\n| **SFT no-evidence** | **47.36** | 48.93 | **+7.00pp** | **—** | **—** | **—** |\\n| SFT baseline (noquant) | 40.36 | 41.06 | — | 80.13 | 31.17 | 0.7118 |\\n| **CED reranker** | **TBD** | 48.64 | **TBD** | **81.88** | — | **0.6156** |\\n| RSFT CED s43 (best) | **45.85** | 46.83 | **+5.49pp** | 81.56 | 37.11 | 0.6388 |\\n| RSFT CED s44 | 45.51 | 46.55 | +5.15pp | 80.87 | 37.13 | 0.6350 |\\n| RSFT CED s42 | 43.63 | 44.49 | +3.27pp | 81.87 | 34.68 | 0.6565 |\\n| RSFT CED k=3 | 43.64 | 44.54 | +3.28pp | 80.88 | — | 0.6635 |\\n| RSFT r2a (1ep) | 44.01 | 44.94 | +3.65pp | 81.08 | 35.09 | 0.6641 |\\n| RSFT r2b (1ep) | 44.10 | 44.93 | +3.74pp | 81.28 | 34.90 | 0.6609 |\\n| flat-NLI s42 | 44.49 | 45.39 | +4.13pp | 80.43 | — | 0.6431 |\\n| flat-NLI s43 (reeval) | TBD | 45.23 | TBD | 81.58 | — | 0.6505 |\\n| DPO bf16 1ep | 38.88 | 40.34 | -1.48pp | 80.88 | — | 0.7139 |\\n| DPO bf16 3ep | TBD | 34.29 | TBD | — | — | — |\\n| GRPO bf16 G=8 (best step) | 45.59 | ~43.4 | +5.23pp | 80.86 | — | — |\\n| GRPO QLoRA (lr=5e-6) | TBD | 1.38 | TBD | 85.00 | — | 0.9900 |\\n\\n注：Evi-F1 以百分比显示（×100）。Ign-F1 修正后排名无实质变化（仅 r2a/r2b 互换，差 0.09pp）。TBD 项等待 metrics_v2.json 补算。GRPO bf16 Ign-F1=45.59 > F1=43.4 因 train triples 过滤效应。RSFT CED k=3 数据来源: reeval_rsft_topk3 (ign_f1_corrected=true)。\\n\\n## Anticipated Reviewer Concerns (updated from Dream, D068/D069)\\n\\n### RC1: \\\"Online RL\\\" 标题过度声称（Dream 三档一致 Critical）\\n- ~~标题和 claim 收窄到 \\\"GRPO fails for DocRE\\\"~~\\n- **D068/D069 修正**: 重新定位为 \\\"RL optimization pressure correlates with decoupling severity\\\"——不是 GRPO 特有问题，而是 RL-for-IE 的通用梯度\\n- DPO 数据支撑 decoupling spectrum（gradual decay confirms the pattern）\\n\\n### RC2: GRPO G=4 太小 + LoRA confound（Dream 三档一致 Major）\\n- GRPO G=8 bf16 实验 ✅ — 确认 mild decoupling（-2pp），QLoRA 是 catastrophic amplifier（D065/D066）\\n- LoRA confound 已解决：bf16 LoRA vs QLoRA 直接对比\\n\\n### RC3: CED 不显著优于 flat-NLI（Dream 三档一致 Major）\\n- 5+ seeds 统计检验；如不显著 → CED 降级\\n\\n### RC4: RSFT 不新颖\\n- 不声称 RSFT 是贡献；贡献在于任务定义 + decoupling 发现 + EDCR\\n\\n### RC5: 评测可比性（D041）\\n- DREEAM-protocol Evi-F1；conditional Evi-F1 作为辅助指标\\n\\n### RC6: EDCR 缺人工验证\\n- 100 例小规模标注\\n\\n### RC7: Missing DPO/PPO（Dream 两档 Major）\\n- DPO experiment ✅ — 结果确认 decoupling spectrum（D067/D068）\\n\\n### RC8: Dev-test degradation\\n- 观察项，等 test set 数据\\n\\n### RC9: 连接 reward overoptimization 文献\\n- 显式引用 Gao et al. 2023\\n\\n### RC10: Post-hoc evidence retrieval baseline\\n- SFT + BM25 evidence retrieval\\n\\n### RC11: \\\"RL 不遗忘\\\" 文献与 Claim 2 的张力（文献扫描 2026-05-16）\\n- 近期多篇论文（arXiv 2507.05386, 2506.23508, 2509.04259）论证 RL fine-tuning 天然缓解 catastrophic forgetting\\n- **关键区分**: FREIGE 的 decoupling 是 **intra-task multi-objective trade-off**（RE 抽取 vs evidence 生成两个优化目标的竞争），不是 **inter-task forgetting**（丢失预训练知识）。两者机制不同\\n- bf16 GRPO 的 mild decoupling（-2pp）恰好印证这一点：模型没有忘记\\\"怎么做 IE\\\"，而是在 evidence reward 压力下偏移了 RE-evidence 的资源分配\\n- **应对**: Related Work / Discussion 中显式回应这组文献，区分 intra-task trade-off vs inter-task forgetting\\n- **QuRL/QaRL 文献支撑 Claim 2**: QuRL 发现 quantized vs full-precision actor divergence 在长训练中指数增长（直接支撑 QLoRA amplification 叙事）；QaRL 的 error token failure mode 与 QLoRA GRPO garbled evidence 吻合\\n\\n## Key Baselines (12+)\\n\\n1. **SFT-only**: Qwen3-4B + LoRA SFT（with evidence）\\n1b. **SFT no-evidence**: Qwen3-4B + LoRA SFT（无 evidence，upper bound ablation）\\n2. **RSFT flat-NLI**: flat-NLI scored RSFT（核心 ablation）\\n3. **RSFT CED**: CED scored RSFT（主方法）\\n4. **CED-as-reranker**: 推理时 CED 重排（无训练）\\n5. **DPO+CED**: offline preference learning — gradual decoupling（D067/D068）\\n6. **GRPO+CED (QLoRA, G=4)**: catastrophic decoupling baseline\\n7. **GRPO+CED (bf16, G=8)**: mild decoupling — QLoRA confound 排除（D065/D066）\\n8. **Post-hoc retrieval**: SFT + BM25 evidence（NEW）\\n9. **DREEAM**: encoder evidence SOTA\\n10. **SAIS**: encoder evidence baseline\\n11. **DocKS-RAG**: extraction SOTA（无 evidence）\\n12. **LMRC**: generative LLM SOTA（无 evidence）\\n\\n## Publishability Threshold (revised after Dream, D068/D069)\\n\\n- **必要条件**: (1) RSFT 在 test set 上 Ign-F1 显著 > SFT (2) DREEAM-protocol Evi-F1 可报告 (3) Decoupling spectrum 有完整数据支撑（GRPO QLoRA/bf16 + DPO + RSFT）\\n- **充分条件**: 上述 + CED 显著 > flat-NLI + EDCR 人工验证\\n- **Failure pivot**: decoupling spectrum 不成立（bf16 GRPO 也 catastrophic）→ scope 大幅缩减。**已排除**: bf16 GRPO 确认 mild（D065/D066）\\n\\n## Research Phase Priorities (revised after Dream v1)\\n\\n| Priority | 实验 | Claim | GPU-h |\\n|----------|------|-------|-------|\\n| P0 | flat-NLI RSFT ablation (5 seeds) | C3 | ~25h |\\n| P0 | CED RSFT additional seeds (→5 total) | C3 | ~10h |\\n| P0 | DREEAM-protocol Evi-F1 对齐 | C1 | CPU |\\n| P0 | Test set evaluation | C1 | ~4h |\\n| P0 | DREEAM baseline reproduction | C1 | ~8h |\\n| ~~P0~~ | ~~GRPO G=8 experiment~~ ✅ | C2 | ~16h |\\n| ~~P0~~ | ~~DPO+CED experiment~~ ✅ | C2 | ~12h |\\n| ~~P0~~ | ~~EDCR per-relation analysis (D070)~~ ✅ | C4 | CPU |\\n| ~~P0~~ | ~~Ign-F1 bugfix + data sync (D071)~~ ✅ | ALL | CPU |\\n| P1 | EDCR human validation | C4 | API |\\n| P1 | Post-hoc evidence retrieval baseline | C1 | ~4h |\\n| P1 | CED-as-reranker (running) | C1 | ~6h |\\n| P1 | Model size ablation | RC | ~24h |\\n| P1 | Re-DocRED extension | RC | ~12h |\\n| ~~P0~~ | ~~GRPO forgetting dynamics figure (plan_009)~~ ✅ | C2 | ~2h |\\n| ~~P0~~ | ~~SFT-without-evidence ablation (plan_014)~~ ✅ | C1 | ~8h |\\n| P2 | Advantage variance measurement | C2 | CPU |\\n\", \"total_chars\": 10760, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "b6aa4dc4-3704-4aeb-8c91-bd8c036064b5",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/paper_framing.md\\\", \\\"content\\\": \\\"# Paper Framing — FREIGE\\\\n\\\\n> **状态**: POST-MVP + DREAM v2 完成（D047 分析）\\\\n> **最后更新**: 2026-05-16\\\\n> **Dream v1**: best=2.5, median=3.0, worst=2.5 → reframe 完成\\\\n> **Dream v2**: best=3.0, median=2.5, worst=2.5 → best 提升但 median 下降，未达标。关键路径：plan_011 bf16 GRPO eval + structural fixes → re-dream v3\\\\n\\\\n## Target Venue\\\\n\\\\n- Primary: **EMNLP 2026 Main** (ARR July cycle, ~July 15-25 → commit EMNLP Aug/Sep)\\\\n- Fallback: AAAI 2027 (abstract July 25, paper Aug 1)\\\\n\\\\n## Core Insight\\\\n\\\\nLLM-based document-level IE 已逼近 encoder SOTA 的抽取精度，但零方法能生成可验证证据。本文提出 **evidence-grounded DocRE** 作为新任务范式：LLM 同时输出关系三元组和支撑证据句。\\\\n\\\\n我们系统性地探索了 online RL (GRPO) 、offline preference optimization (DPO) 和 offline RL (RSFT) 三条技术路线。关键发现：**RL optimization pressure 与 evidence-extraction decoupling severity 正相关**——优化强度越大，evidence 质量提升的同时抽取能力退化越严重。QLoRA 放大至 catastrophic（rel_f1<0.02），bf16 GRPO 从 0.4549 退化至 ~0.434（mild, -2pp），DPO 呈 gradual 退化（1ep→3ep rel_f1 从 0.4034→0.3429），RSFT 无 decoupling。\\\\n\\\\nCED (Contrastive Evidence Discrimination) 是一种 NLI-based 候选筛选函数，通过文档内 hard negative 对比评估 evidence 质量。CED 作为 RSFT 的 scoring function 之一进行测试，其相对于 flat-NLI 的优势需要通过充分的统计检验验证。\\\\n\\\\n## Story Arc\\\\n\\\\n1. **Problem**: LLM DocRE 无证据 → 部署障碍\\\\n2. **New task**: evidence-grounded DocRE — 同时生成关系和证据\\\\n3. **Cost of faithfulness**: evidence generation 代价 ~7pp Ign-F1（no-evidence 47.36 vs evidence-SFT 40.36）——这是 faithfulness 的真实成本\\\\n4. **Exploration**: 系统性比较 online RL (GRPO) vs offline preference (DPO) vs offline RL (RSFT)\\\\n5. **Key finding**: evidence-extraction decoupling — RL optimization pressure 与 decoupling severity 正相关，形成连续谱系（GRPO-QLoRA catastrophic > GRPO-bf16 mild > DPO gradual > RSFT none）\\\\n6. **QLoRA amplification**: QLoRA 量化将 mild decoupling 放大至 catastrophic forgetting——decoupling 是 RL-for-IE 中 multi-objective competition 的通用梯度（intra-task trade-off，非 inter-task forgetting），QLoRA 是 catastrophic amplifier\\\\n7. **What works**: RSFT with NLI-based scoring 是唯一有效路线——提升 evidence 质量而不牺牲抽取\\\\n8. **Best practical solution**: CED reranker 恢复 97% 的 evidence 代价，同时保留高质量 evidence（evi_f1=0.8188）\\\\n9. **Diagnostic tool**: EDCR 双层诊断——方法级量化 decoupling（与 Claim 2 呼应），per-relation 级揭示 evi_f1 不捕捉的 relation-type 难度差异（D070 ✅）\\\\n\\\\n## Core Claims (reframed after Dream v1, updated D068/D069/D070/D071/D072)\\\\n\\\\n### Claim 1 (Main): Evidence-grounded DocRE 是可行的新能力\\\\n- FREIGE 是首个在 DocRED 上同时输出 (head, relation, tail, [evidence]) 的 LLM 方法\\\\n- **Evidence generation tax**: no-evidence SFT Ign-F1=47.36 vs evidence-SFT 40.36，代价 ~7pp（plan_014 ✅）\\\\n- RSFT 在 4/4 配置下均超过 SFT baseline（Ign-F1 +3.3~5.5pp）\\\\n- **CED reranker 是最优实用方案**: rel_f1=0.4864（仅低于 no-evidence 0.29pp），evi_f1=0.8188（plan_005 ✅）\\\\n- 需要 DREEAM-protocol 对齐的 Evi-F1 对比（D041 在处理中）\\\\n\\\\n### Claim 2 (Core finding): RL optimization pressure 与 evidence-extraction decoupling severity 正相关（D068/D069 修正）\\\\n- **Decoupling spectrum**: 优化强度越大，decoupling 越严重\\\\n  - GRPO QLoRA: catastrophic（rel_f1=0.0138, evi_f1=0.850, EDCR=0.99）— QLoRA 放大 decoupling\\\\n  - GRPO bf16: mild（rel_f1 从 0.4549→~0.434, -2pp; step_30=0.434, step_50=0.4276, step_70=0.4341）— 退化可控但持续（D065/D066）\\\\n  - DPO bf16 1ep→3ep: gradual（Ign-F1 38.88→TBD, rel_f1 0.4034→0.3429）— 随训练渐进退化（D067/D068）\\\\n  - RSFT: none — 无 decoupling，唯一有效路线\\\\n- **QLoRA 是 catastrophic amplifier，不是 root cause**: bf16 GRPO 仅 mild decoupling（-2pp），QLoRA 放大至 catastrophic（-39pp）（D054/D065/D066）\\\\n- **Decoupling 是 RL-for-IE 的通用梯度**: 跨方法（GRPO/DPO）、跨量化策略（QLoRA/bf16）一致出现，严重程度与优化压力正相关\\\\n- 三档 Dream 审稿均认为此发现\\\\\\\\\\\\\\\"genuinely novel and striking\\\\\\\\\\\\\\\"\\\\n- **已完成**: GRPO G=8 bf16 确认 mild decoupling（plan_011 ✅）; DPO 1ep/3ep 确认 gradual decoupling（plan_012 ✅）\\\\n\\\\n### Claim 3 (Ablation): NLI-based scoring 提升 RSFT 质量\\\\n- CED 和 flat-NLI 都优于 random/no scoring\\\\n- CED vs flat-NLI 的差异需统计验证（Dream 报告 p=0.08/0.38/0.12 不显著）\\\\n- **Critical**: 如果 CED 不显著优于 flat-NLI → CED 降级为\\\\\\\"one possible scoring function\\\\\\\"\\\\n- **行动**: 5+ seeds for significance testing\\\\n- **top_k selection ablation (k=1 vs k=3)**:\\\\n  - k=1 (best-of-8) 优于 k=3 (top3-of-8)，CED scoring precision 随 k 增大下降\\\\n  - k=1 均值 (3 seeds s42/s43/s44): Ign-F1=45.00, rel_f1=0.4596, evi_f1=81.43, EDCR=0.6434\\\\n  - k=3 (1 seed, reeval_rsft_topk3): Ign-F1=43.64, rel_f1=0.4454, evi_f1=80.88, EDCR=0.6635\\\\n  - Δ (k=3 vs k=1 mean): Ign-F1 **-1.36pp**, rel_f1 **-1.42pp**, evi_f1 **-0.55pp**, EDCR +0.02\\\\n  - 训练数据质量下降: k=1 mean_f1=0.6157, mean_ced=0.6683 → k=3 mean_f1=0.5761, mean_ced=0.6205（来源: mvp2_rsft_ced_scoring / mvp2_rsft_ced_scoring_topk3_r2）\\\\n  - 训练集规模: k=1 选出 2718 样本 (12.4%), k=3 选出 8037 样本 (37%), 数据量 ×2.96 但质量下降抵消数量优势\\\\n  - **叙事**: 低排名 response 引入噪声——rank 2-3 样本的 F1 和 CED 分数均显著低于 rank 1，扩大训练集规模无法补偿数据质量的稀释。这表明 RSFT 的关键不在数据量而在 scoring precision\\\\n  - **注**: k=3 仅 1 seed，差异方向一致但尚不具备统计显著性；作为 ablation table 中的辅助行呈现，不作为独立 claim\\\\n\\\\n### Claim 4 (Diagnostic): EDCR 双层诊断价值（D070/D072）\\\\n- **Layer 1 — 方法级**: EDCR 量化 evidence-extraction decoupling，与 Claim 2 spectrum 呼应\\\\n  - 方法级 EDCR 与 rel_f1 Spearman ρ=-0.965（plan_003 ✅）——本质是 decoupling 的度量\\\\n  - EDCR 识别病理模型（GRPO QLoRA: EDCR≈1.0）\\\\n- **Layer 2 — per-relation-type**: EDCR 提供 evi_f1 不捕捉的 relation-type 诊断信息 ✅\\\\n  - per-relation ρ(EDCR, evi_f1) = **-0.064** (p=0.58) → **完全独立于 evi_f1**\\\\n  - per-relation ρ(EDCR, rel_f1) = -0.793 (p<0.001) → 与 rel_f1 强相关但非完美\\\\n  - per-relation ρ(evi_f1, rel_f1) = -0.013 (p=0.91) → evidence 质量与抽取能力在 relation type 间完全解耦\\\\n  - 典型案例：date_of_birth (EDCR=0.118, 高 faithful) vs head_of_government (EDCR=0.956, 高 decoupled)\\\\n  - 93 relation types 分析（≥5 样本），76 个有非零数据\\\\n- **论文叙事**: EDCR 在方法级是 decoupling 度量工具（横向对比方法），在 relation 级是难度诊断工具（纵向定位薄弱 relation）——两层叙事互补\\\\n- **仍需**: 100 例人工标注验证（RC6）\\\\n\\\\n## MVP Evidence Summary (D071: 主表报 Ign-F1，附录报 F1)\\\\n\\\\n| Config | Ign-F1 | F1 | Δ vs SFT (Ign-F1) | Evi-F1 (cond) | Evi-F1 (joint) | EDCR |\\\\n|--------|--------|------|-------------------|---------------|---------------|------|\\\\n| **SFT no-evidence** | **47.36** | 48.93 | **+7.00pp** | **—** | **—** | **—** |\\\\n| SFT baseline (noquant) | 40.36 | 41.06 | — | 80.13 | 31.17 | 0.7118 |\\\\n| **CED reranker** | **TBD** | 48.64 | **TBD** | **81.88** | — | **0.6156** |\\\\n| RSFT CED s43 (best) | **45.85** | 46.83 | **+5.49pp** | 81.56 | 37.11 | 0.6388 |\\\\n| RSFT CED s44 | 45.51 | 46.55 | +5.15pp | 80.87 | 37.13 | 0.6350 |\\\\n| RSFT CED s42 | 43.63 | 44.49 | +3.27pp | 81.87 | 34.68 | 0.6565 |\\\\n| RSFT CED k=3 | 43.64 | 44.54 | +3.28pp | 80.88 | — | 0.6635 |\\\\n| RSFT r2a (1ep) | 44.01 | 44.94 | +3.65pp | 81.08 | 35.09 | 0.6641 |\\\\n| RSFT r2b (1ep) | 44.10 | 44.93 | +3.74pp | 81.28 | 34.90 | 0.6609 |\\\\n| flat-NLI s42 | 44.49 | 45.39 | +4.13pp | 80.43 | — | 0.6431 |\\\\n| flat-NLI s43 (reeval) | TBD | 45.23 | TBD | 81.58 | — | 0.6505 |\\\\n| DPO bf16 1ep | 38.88 | 40.34 | -1.48pp | 80.88 | — | 0.7139 |\\\\n| DPO bf16 3ep | TBD | 34.29 | TBD | — | — | — |\\\\n| GRPO bf16 G=8 (best step) | 45.59 | ~43.4 | +5.23pp | 80.86 | — | — |\\\\n| GRPO QLoRA (lr=5e-6) | TBD | 1.38 | TBD | 85.00 | — | 0.9900 |\\\\n\\\\n注：Evi-F1 以百分比显示（×100）。Ign-F1 修正后排名无实质变化（仅 r2a/r2b 互换，差 0.09pp）。TBD 项等待 metrics_v2.json 补算。GRPO bf16 Ign-F1=45.59 > F1=43.4 因 train triples 过滤效应。RSFT CED k=3 数据来源: reeval_rsft_topk3 (ign_f1_corrected=true)。\\\\n\\\\n## Anticipated Reviewer Concerns (updated from Dream, D068/D069)\\\\n\\\\n### RC1: \\\\\\\"Online RL\\\\\\\" 标题过度声称（Dream 三档一致 Critical）\\\\n- ~~标题和 claim 收窄到 \\\\\\\"GRPO fails for DocRE\\\\\\\"~~\\\\n- **D068/D069 修正**: 重新定位为 \\\\\\\"RL optimization pressure correlates with decoupling severity\\\\\\\"——不是 GRPO 特有问题，而是 RL-for-IE 的通用梯度\\\\n- DPO 数据支撑 decoupling spectrum（gradual decay confirms the pattern）\\\\n\\\\n### RC2: GRPO G=4 太小 + LoRA confound（Dream 三档一致 Major）\\\\n- GRPO G=8 bf16 实验 ✅ — 确认 mild decoupling（-2pp），QLoRA 是 catastrophic amplifier（D065/D066）\\\\n- LoRA confound 已解决：bf16 LoRA vs QLoRA 直接对比\\\\n\\\\n### RC3: CED 不显著优于 flat-NLI（Dream 三档一致 Major）\\\\n- 5+ seeds 统计检验；如不显著 → CED 降级\\\\n\\\\n### RC4: RSFT 不新颖\\\\n- 不声称 RSFT 是贡献；贡献在于任务定义 + decoupling 发现 + EDCR\\\\n\\\\n### RC5: 评测可比性（D041）\\\\n- DREEAM-protocol Evi-F1；conditional Evi-F1 作为辅助指标\\\\n\\\\n### RC6: EDCR 缺人工验证\\\\n- 100 例小规模标注\\\\n\\\\n### RC7: Missing DPO/PPO（Dream 两档 Major）\\\\n- DPO experiment ✅ — 结果确认 decoupling spectrum（D067/D068）\\\\n\\\\n### RC8: Dev-test degradation\\\\n- 观察项，等 test set 数据\\\\n\\\\n### RC9: 连接 reward overoptimization 文献\\\\n- 显式引用 Gao et al. 2023\\\\n\\\\n### RC10: Post-hoc evidence retrieval baseline\\\\n- SFT + BM25 evidence retrieval\\\\n\\\\n### RC11: \\\\\\\"RL 不遗忘\\\\\\\" 文献与 Claim 2 的张力（文献扫描 2026-05-16）\\\\n- 近期多篇论文（arXiv 2507.05386, 2506.23508, 2509.04259）论证 RL fine-tuning 天然缓解 catastrophic forgetting\\\\n- **关键区分**: FREIGE 的 decoupling 是 **intra-task multi-objective trade-off**（RE 抽取 vs evidence 生成两个优化目标的竞争），不是 **inter-task forgetting**（丢失预训练知识）。两者机制不同\\\\n- bf16 GRPO 的 mild decoupling（-2pp）恰好印证这一点：模型没有忘记\\\\\\\"怎么做 IE\\\\\\\"，而是在 evidence reward 压力下偏移了 RE-evidence 的资源分配\\\\n- **应对**: Related Work / Discussion 中显式回应这组文献，区分 intra-task trade-off vs inter-task forgetting\\\\n- **QuRL/QaRL 文献支撑 Claim 2**: QuRL 发现 quantized vs full-precision actor divergence 在长训练中指数增长（直接支撑 QLoRA amplification 叙事）；QaRL 的 error token failure mode 与 QLoRA GRPO garbled evidence 吻合\\\\n\\\\n## Key Baselines (12+)\\\\n\\\\n1. **SFT-only**: Qwen3-4B + LoRA SFT（with evidence）\\\\n1b. **SFT no-evidence**: Qwen3-4B + LoRA SFT（无 evidence，upper bound ablation）\\\\n2. **RSFT flat-NLI**: flat-NLI scored RSFT（核心 ablation）\\\\n3. **RSFT CED**: CED scored RSFT（主方法）\\\\n4. **CED-as-reranker**: 推理时 CED 重排（无训练）\\\\n5. **DPO+CED**: offline preference learning — gradual decoupling（D067/D068）\\\\n6. **GRPO+CED (QLoRA, G=4)**: catastrophic decoupling baseline\\\\n7. **GRPO+CED (bf16, G=8)**: mild decoupling — QLoRA confound 排除（D065/D066）\\\\n8. **Post-hoc retrieval**: SFT + BM25 evidence（NEW）\\\\n9. **DREEAM**: encoder evidence SOTA\\\\n10. **SAIS**: encoder evidence baseline\\\\n11. **DocKS-RAG**: extraction SOTA（无 evidence）\\\\n12. **LMRC**: generative LLM SOTA（无 evidence）\\\\n\\\\n## Publishability Threshold (revised after Dream, D068/D069)\\\\n\\\\n- **必要条件**: (1) RSFT 在 test set 上 Ign-F1 显著 > SFT (2) DREEAM-protocol Evi-F1 可报告 (3) Decoupling spectrum 有完整数据支撑（GRPO QLoRA/bf16 + DPO + RSFT）\\\\n- **充分条件**: 上述 + CED 显著 > flat-NLI + EDCR 人工验证\\\\n- **Failure pivot**: decoupling spectrum 不成立（bf16 GRPO 也 catastrophic）→ scope 大幅缩减。**已排除**: bf16 GRPO 确认 mild（D065/D066）\\\\n\\\\n## Research Phase Priorities (revised after Dream v1)\\\\n\\\\n| Priority | 实验 | Claim | GPU-h |\\\\n|----------|------|-------|-------|\\\\n| P0 | flat-NLI RSFT ablation (5 seeds) | C3 | ~25h |\\\\n| P0 | CED RSFT additional seeds (→5 total) | C3 | ~10h |\\\\n| P0 | DREEAM-protocol Evi-F1 对齐 | C1 | CPU |\\\\n| P0 | Test set evaluation | C1 | ~4h |\\\\n| P0 | DREEAM baseline reproduction | C1 | ~8h |\\\\n| ~~P0~~ | ~~GRPO G=8 experiment~~ ✅ | C2 | ~16h |\\\\n| ~~P0~~ | ~~DPO+CED experiment~~ ✅ | C2 | ~12h |\\\\n| ~~P0~~ | ~~EDCR per-relation analysis (D070)~~ ✅ | C4 | CPU |\\\\n| ~~P0~~ | ~~Ign-F1 bugfix + data sync (D071)~~ ✅ | ALL | CPU |\\\\n| P1 | EDCR human validation | C4 | API |\\\\n| P1 | Post-hoc evidence retrieval baseline | C1 | ~4h |\\\\n| P1 | CED-as-reranker (running) | C1 | ~6h |\\\\n| P1 | Model size ablation | RC | ~24h |\\\\n| P1 | Re-DocRED extension | RC | ~12h |\\\\n| ~~P0~~ | ~~GRPO forgetting dynamics figure (plan_009)~~ ✅ | C2 | ~2h |\\\\n| ~~P0~~ | ~~SFT-without-evidence ablation (plan_014)~~ ✅ | C1 | ~8h |\\\\n| P2 | Advantage variance measurement | C2 | CPU |\\\\n\\\", \\\"total_chars\\\": 10760, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/paper_framing.md\", \"content\": \"# Paper Framing — FREIGE\\n\\n> **状态**: POST-MVP + DREAM v2 完成（D047 分析）\\n> **最后更新**: 2026-05-16\\n> **Dream v1**: best=2.5, median=3.0, worst=2.5 → reframe 完成\\n> **Dream v2**: best=3.0, median=2.5, worst=2.5 → best 提升但 median 下降，未达标。关键路径：plan_011 bf16 GRPO eval + structural fixes → re-dream v3\\n\\n## Target Venue\\n\\n- Primary: **EMNLP 2026 Main** (ARR July cycle, ~July 15-25 → commit EMNLP Aug/Sep)\\n- Fallback: AAAI 2027 (abstract July 25, paper Aug 1)\\n\\n## Core Insight\\n\\nLLM-based document-level IE 已逼近 encoder SOTA 的抽取精度，但零方法能生成可验证证据。本文提出 **evidence-grounded DocRE** 作为新任务范式：LLM 同时输出关系三元组和支撑证据句。\\n\\n我们系统性地探索了 online RL (GRPO) 、offline preference optimization (DPO) 和 offline RL (RSFT) 三条技术路线。关键发现：**RL optimization pressure 与 evidence-extraction decoupling severity 正相关**——优化强度越大，evidence 质量提升的同时抽取能力退化越严重。QLoRA 放大至 catastrophic（rel_f1<0.02），bf16 GRPO 从 0.4549 退化至 ~0.434（mild, -2pp），DPO 呈 gradual 退化（1ep→3ep rel_f1 从 0.4034→0.3429），RSFT 无 decoupling。\\n\\nCED (Contrastive Evidence Discrimination) 是一种 NLI-based 候选筛选函数，通过文档内 hard negative 对比评估 evidence 质量。CED 作为 RSFT 的 scoring function 之一进行测试，其相对于 flat-NLI 的优势需要通过充分的统计检验验证。\\n\\n## Story Arc\\n\\n1. **Problem**: LLM DocRE 无证据 → 部署障碍\\n2. **New task**: evidence-grounded DocRE — 同时生成关系和证据\\n3. **Cost of faithfulness**: evidence generation 代价 ~7pp Ign-F1（no-evidence 47.36 vs evidence-SFT 40.36）——这是 faithfulness 的真实成本\\n4. **Exploration**: 系统性比较 online RL (GRPO) vs offline preference (DPO) vs offline RL (RSFT)\\n5. **Key finding**: evidence-extraction decoupling — RL optimization pressure 与 decoupling severity 正相关，形成连续谱系（GRPO-QLoRA catastrophic > GRPO-bf16 mild > DPO gradual > RSFT none）\\n6. **QLoRA amplification**: QLoRA 量化将 mild decoupling 放大至 catastrophic forgetting——decoupling 是 RL-for-IE 中 multi-objective competition 的通用梯度（intra-task trade-off，非 inter-task forgetting），QLoRA 是 catastrophic amplifier\\n7. **What works**: RSFT with NLI-based scoring 是唯一有效路线——提升 evidence 质量而不牺牲抽取\\n8. **Best practical solution**: CED reranker 恢复 97% 的 evidence 代价，同时保留高质量 evidence（evi_f1=0.8188）\\n9. **Diagnostic tool**: EDCR 双层诊断——方法级量化 decoupling（与 Claim 2 呼应），per-relation 级揭示 evi_f1 不捕捉的 relation-type 难度差异（D070 ✅）\\n\\n## Core Claims (reframed after Dream v1, updated D068/D069/D070/D071/D072)\\n\\n### Claim 1 (Main): Evidence-grounded DocRE 是可行的新能力\\n- FREIGE 是首个在 DocRED 上同时输出 (head, relation, tail, [evidence]) 的 LLM 方法\\n- **Evidence generation tax**: no-evidence SFT Ign-F1=47.36 vs evidence-SFT 40.36，代价 ~7pp（plan_014 ✅）\\n- RSFT 在 4/4 配置下均超过 SFT baseline（Ign-F1 +3.3~5.5pp）\\n- **CED reranker 是最优实用方案**: rel_f1=0.4864（仅低于 no-evidence 0.29pp），evi_f1=0.8188（plan_005 ✅）\\n- 需要 DREEAM-protocol 对齐的 Evi-F1 对比（D041 在处理中）\\n\\n### Claim 2 (Core finding): RL optimization pressure 与 evidence-extraction decoupling severity 正相关（D068/D069 修正）\\n- **Decoupling spectrum**: 优化强度越大，decoupling 越严重\\n  - GRPO QLoRA: catastrophic（rel_f1=0.0138, evi_f1=0.850, EDCR=0.99）— QLoRA 放大 decoupling\\n  - GRPO bf16: mild（rel_f1 从 0.4549→~0.434, -2pp; step_30=0.434, step_50=0.4276, step_70=0.4341）— 退化可控但持续（D065/D066）\\n  - DPO bf16 1ep→3ep: gradual（Ign-F1 38.88→TBD, rel_f1 0.4034→0.3429）— 随训练渐进退化（D067/D068）\\n  - RSFT: none — 无 decoupling，唯一有效路线\\n- **QLoRA 是 catastrophic amplifier，不是 root cause**: bf16 GRPO 仅 mild decoupling（-2pp），QLoRA 放大至 catastrophic（-39pp）（D054/D065/D066）\\n- **Decoupling 是 RL-for-IE 的通用梯度**: 跨方法（GRPO/DPO）、跨量化策略（QLoRA/bf16）一致出现，严重程度与优化压力正相关\\n- 三档 Dream 审稿均认为此发现\\\\\\\"genuinely novel and striking\\\\\\\"\\n- **已完成**: GRPO G=8 bf16 确认 mild decoupling（plan_011 ✅）; DPO 1ep/3ep 确认 gradual decoupling（plan_012 ✅）\\n\\n### Claim 3 (Ablation): NLI-based scoring 提升 RSFT 质量\\n- CED 和 flat-NLI 都优于 random/no scoring\\n- CED vs flat-NLI 的差异需统计验证（Dream 报告 p=0.08/0.38/0.12 不显著）\\n- **Critical**: 如果 CED 不显著优于 flat-NLI → CED 降级为\\\"one possible scoring function\\\"\\n- **行动**: 5+ seeds for significance testing\\n- **top_k selection ablation (k=1 vs k=3)**:\\n  - k=1 (best-of-8) 优于 k=3 (top3-of-8)，CED scoring precision 随 k 增大下降\\n  - k=1 均值 (3 seeds s42/s43/s44): Ign-F1=45.00, rel_f1=0.4596, evi_f1=81.43, EDCR=0.6434\\n  - k=3 (1 seed, reeval_rsft_topk3): Ign-F1=43.64, rel_f1=0.4454, evi_f1=80.88, EDCR=0.6635\\n  - Δ (k=3 vs k=1 mean): Ign-F1 **-1.36pp**, rel_f1 **-1.42pp**, evi_f1 **-0.55pp**, EDCR +0.02\\n  - 训练数据质量下降: k=1 mean_f1=0.6157, mean_ced=0.6683 → k=3 mean_f1=0.5761, mean_ced=0.6205（来源: mvp2_rsft_ced_scoring / mvp2_rsft_ced_scoring_topk3_r2）\\n  - 训练集规模: k=1 选出 2718 样本 (12.4%), k=3 选出 8037 样本 (37%), 数据量 ×2.96 但质量下降抵消数量优势\\n  - **叙事**: 低排名 response 引入噪声——rank 2-3 样本的 F1 和 CED 分数均显著低于 rank 1，扩大训练集规模无法补偿数据质量的稀释。这表明 RSFT 的关键不在数据量而在 scoring precision\\n  - **注**: k=3 仅 1 seed，差异方向一致但尚不具备统计显著性；作为 ablation table 中的辅助行呈现，不作为独立 claim\\n\\n### Claim 4 (Diagnostic): EDCR 双层诊断价值（D070/D072）\\n- **Layer 1 — 方法级**: EDCR 量化 evidence-extraction decoupling，与 Claim 2 spectrum 呼应\\n  - 方法级 EDCR 与 rel_f1 Spearman ρ=-0.965（plan_003 ✅）——本质是 decoupling 的度量\\n  - EDCR 识别病理模型（GRPO QLoRA: EDCR≈1.0）\\n- **Layer 2 — per-relation-type**: EDCR 提供 evi_f1 不捕捉的 relation-type 诊断信息 ✅\\n  - per-relation ρ(EDCR, evi_f1) = **-0.064** (p=0.58) → **完全独立于 evi_f1**\\n  - per-relation ρ(EDCR, rel_f1) = -0.793 (p<0.001) → 与 rel_f1 强相关但非完美\\n  - per-relation ρ(evi_f1, rel_f1) = -0.013 (p=0.91) → evidence 质量与抽取能力在 relation type 间完全解耦\\n  - 典型案例：date_of_birth (EDCR=0.118, 高 faithful) vs head_of_government (EDCR=0.956, 高 decoupled)\\n  - 93 relation types 分析（≥5 样本），76 个有非零数据\\n- **论文叙事**: EDCR 在方法级是 decoupling 度量工具（横向对比方法），在 relation 级是难度诊断工具（纵向定位薄弱 relation）——两层叙事互补\\n- **仍需**: 100 例人工标注验证（RC6）\\n\\n## MVP Evidence Summary (D071: 主表报 Ign-F1，附录报 F1)\\n\\n| Config | Ign-F1 | F1 | Δ vs SFT (Ign-F1) | Evi-F1 (cond) | Evi-F1 (joint) | EDCR |\\n|--------|--------|------|-------------------|---------------|---------------|------|\\n| **SFT no-evidence** | **47.36** | 48.93 | **+7.00pp** | **—** | **—** | **—** |\\n| SFT baseline (noquant) | 40.36 | 41.06 | — | 80.13 | 31.17 | 0.7118 |\\n| **CED reranker** | **TBD** | 48.64 | **TBD** | **81.88** | — | **0.6156** |\\n| RSFT CED s43 (best) | **45.85** | 46.83 | **+5.49pp** | 81.56 | 37.11 | 0.6388 |\\n| RSFT CED s44 | 45.51 | 46.55 | +5.15pp | 80.87 | 37.13 | 0.6350 |\\n| RSFT CED s42 | 43.63 | 44.49 | +3.27pp | 81.87 | 34.68 | 0.6565 |\\n| RSFT CED k=3 | 43.64 | 44.54 | +3.28pp | 80.88 | — | 0.6635 |\\n| RSFT r2a (1ep) | 44.01 | 44.94 | +3.65pp | 81.08 | 35.09 | 0.6641 |\\n| RSFT r2b (1ep) | 44.10 | 44.93 | +3.74pp | 81.28 | 34.90 | 0.6609 |\\n| flat-NLI s42 | 44.49 | 45.39 | +4.13pp | 80.43 | — | 0.6431 |\\n| flat-NLI s43 (reeval) | TBD | 45.23 | TBD | 81.58 | — | 0.6505 |\\n| DPO bf16 1ep | 38.88 | 40.34 | -1.48pp | 80.88 | — | 0.7139 |\\n| DPO bf16 3ep | TBD | 34.29 | TBD | — | — | — |\\n| GRPO bf16 G=8 (best step) | 45.59 | ~43.4 | +5.23pp | 80.86 | — | — |\\n| GRPO QLoRA (lr=5e-6) | TBD | 1.38 | TBD | 85.00 | — | 0.9900 |\\n\\n注：Evi-F1 以百分比显示（×100）。Ign-F1 修正后排名无实质变化（仅 r2a/r2b 互换，差 0.09pp）。TBD 项等待 metrics_v2.json 补算。GRPO bf16 Ign-F1=45.59 > F1=43.4 因 train triples 过滤效应。RSFT CED k=3 数据来源: reeval_rsft_topk3 (ign_f1_corrected=true)。\\n\\n## Anticipated Reviewer Concerns (updated from Dream, D068/D069)\\n\\n### RC1: \\\"Online RL\\\" 标题过度声称（Dream 三档一致 Critical）\\n- ~~标题和 claim 收窄到 \\\"GRPO fails for DocRE\\\"~~\\n- **D068/D069 修正**: 重新定位为 \\\"RL optimization pressure correlates with decoupling severity\\\"——不是 GRPO 特有问题，而是 RL-for-IE 的通用梯度\\n- DPO 数据支撑 decoupling spectrum（gradual decay confirms the pattern）\\n\\n### RC2: GRPO G=4 太小 + LoRA confound（Dream 三档一致 Major）\\n- GRPO G=8 bf16 实验 ✅ — 确认 mild decoupling（-2pp），QLoRA 是 catastrophic amplifier（D065/D066）\\n- LoRA confound 已解决：bf16 LoRA vs QLoRA 直接对比\\n\\n### RC3: CED 不显著优于 flat-NLI（Dream 三档一致 Major）\\n- 5+ seeds 统计检验；如不显著 → CED 降级\\n\\n### RC4: RSFT 不新颖\\n- 不声称 RSFT 是贡献；贡献在于任务定义 + decoupling 发现 + EDCR\\n\\n### RC5: 评测可比性（D041）\\n- DREEAM-protocol Evi-F1；conditional Evi-F1 作为辅助指标\\n\\n### RC6: EDCR 缺人工验证\\n- 100 例小规模标注\\n\\n### RC7: Missing DPO/PPO（Dream 两档 Major）\\n- DPO experiment ✅ — 结果确认 decoupling spectrum（D067/D068）\\n\\n### RC8: Dev-test degradation\\n- 观察项，等 test set 数据\\n\\n### RC9: 连接 reward overoptimization 文献\\n- 显式引用 Gao et al. 2023\\n\\n### RC10: Post-hoc evidence retrieval baseline\\n- SFT + BM25 evidence retrieval\\n\\n### RC11: \\\"RL 不遗忘\\\" 文献与 Claim 2 的张力（文献扫描 2026-05-16）\\n- 近期多篇论文（arXiv 2507.05386, 2506.23508, 2509.04259）论证 RL fine-tuning 天然缓解 catastrophic forgetting\\n- **关键区分**: FREIGE 的 decoupling 是 **intra-task multi-objective trade-off**（RE 抽取 vs evidence 生成两个优化目标的竞争），不是 **inter-task forgetting**（丢失预训练知识）。两者机制不同\\n- bf16 GRPO 的 mild decoupling（-2pp）恰好印证这一点：模型没有忘记\\\"怎么做 IE\\\"，而是在 evidence reward 压力下偏移了 RE-evidence 的资源分配\\n- **应对**: Related Work / Discussion 中显式回应这组文献，区分 intra-task trade-off vs inter-task forgetting\\n- **QuRL/QaRL 文献支撑 Claim 2**: QuRL 发现 quantized vs full-precision actor divergence 在长训练中指数增长（直接支撑 QLoRA amplification 叙事）；QaRL 的 error token failure mode 与 QLoRA GRPO garbled evidence 吻合\\n\\n## Key Baselines (12+)\\n\\n1. **SFT-only**: Qwen3-4B + LoRA SFT（with evidence）\\n1b. **SFT no-evidence**: Qwen3-4B + LoRA SFT（无 evidence，upper bound ablation）\\n2. **RSFT flat-NLI**: flat-NLI scored RSFT（核心 ablation）\\n3. **RSFT CED**: CED scored RSFT（主方法）\\n4. **CED-as-reranker**: 推理时 CED 重排（无训练）\\n5. **DPO+CED**: offline preference learning — gradual decoupling（D067/D068）\\n6. **GRPO+CED (QLoRA, G=4)**: catastrophic decoupling baseline\\n7. **GRPO+CED (bf16, G=8)**: mild decoupling — QLoRA confound 排除（D065/D066）\\n8. **Post-hoc retrieval**: SFT + BM25 evidence（NEW）\\n9. **DREEAM**: encoder evidence SOTA\\n10. **SAIS**: encoder evidence baseline\\n11. **DocKS-RAG**: extraction SOTA（无 evidence）\\n12. **LMRC**: generative LLM SOTA（无 evidence）\\n\\n## Publishability Threshold (revised after Dream, D068/D069)\\n\\n- **必要条件**: (1) RSFT 在 test set 上 Ign-F1 显著 > SFT (2) DREEAM-protocol Evi-F1 可报告 (3) Decoupling spectrum 有完整数据支撑（GRPO QLoRA/bf16 + DPO + RSFT）\\n- **充分条件**: 上述 + CED 显著 > flat-NLI + EDCR 人工验证\\n- **Failure pivot**: decoupling spectrum 不成立（bf16 GRPO 也 catastrophic）→ scope 大幅缩减。**已排除**: bf16 GRPO 确认 mild（D065/D066）\\n\\n## Research Phase Priorities (revised after Dream v1)\\n\\n| Priority | 实验 | Claim | GPU-h |\\n|----------|------|-------|-------|\\n| P0 | flat-NLI RSFT ablation (5 seeds) | C3 | ~25h |\\n| P0 | CED RSFT additional seeds (→5 total) | C3 | ~10h |\\n| P0 | DREEAM-protocol Evi-F1 对齐 | C1 | CPU |\\n| P0 | Test set evaluation | C1 | ~4h |\\n| P0 | DREEAM baseline reproduction | C1 | ~8h |\\n| ~~P0~~ | ~~GRPO G=8 experiment~~ ✅ | C2 | ~16h |\\n| ~~P0~~ | ~~DPO+CED experiment~~ ✅ | C2 | ~12h |\\n| ~~P0~~ | ~~EDCR per-relation analysis (D070)~~ ✅ | C4 | CPU |\\n| ~~P0~~ | ~~Ign-F1 bugfix + data sync (D071)~~ ✅ | ALL | CPU |\\n| P1 | EDCR human validation | C4 | API |\\n| P1 | Post-hoc evidence retrieval baseline | C1 | ~4h |\\n| P1 | CED-as-reranker (running) | C1 | ~6h |\\n| P1 | Model size ablation | RC | ~24h |\\n| P1 | Re-DocRED extension | RC | ~12h |\\n| ~~P0~~ | ~~GRPO forgetting dynamics figure (plan_009)~~ ✅ | C2 | ~2h |\\n| ~~P0~~ | ~~SFT-without-evidence ablation (plan_014)~~ ✅ | C1 | ~8h |\\n| P2 | Advantage variance measurement | C2 | CPU |\\n\", \"total_chars\": 10760, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_experiment_plan_with_status · `toolu_01Q7rejW1BJRSfDvvmnvtWFv`</summary>

```json
{
  "project": "faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6a3fa9be-2c04-4026-9230-b3fed371abfa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HV9F1dQeoWwcYQDjawGRCW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1936,
      "cache_read_input_tokens": 23905,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1936
      },
      "output_tokens": 67,
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

_source line 13 · 2026-05-16T03:21:17.849Z_

<details><summary>↩ Tool result · `toolu_01Q7rejW1BJRSfDvvmnvtWFv`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"experiments\": [{\"id\": \"plan_001\", \"claim\": 2, \"description\": \"CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选 RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py 用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。\", \"priority\": \"P0\", \"gpu_budget_hours\": 20, \"deps\": [], \"registry_id\": \"eval_flat_nli_seed45\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4551, \"rel_p\": 0.4632, \"rel_r\": 0.4472, \"ign_f1\": 0.4551, \"evi_f1\": 0.8154, \"evi_p\": 0.8108, \"evi_r\": 0.8201, \"evi_f1_joint\": 0.3556, \"edcr\": 0.6521, \"n_predictions\": 15650, \"tp\": 5434, \"format_ok_rate\": 1, \"n_truncated\": 206, \"n_documents\": 985, \"inference_time_seconds\": 11867.6}}, {\"id\": \"plan_002\", \"claim\": 1, \"description\": \"Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set 上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。\", \"priority\": \"P0\", \"gpu_budget_hours\": 4, \"deps\": [\"plan_001\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_003\", \"claim\": 4, \"description\": \"EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing 方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_001\"], \"registry_id\": \"plan_003_edcr_diagnostic\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"methods_evaluated\": 15, \"edcr_vs_rel_f1_spearman\": -0.9648, \"edcr_vs_rel_f1_pvalue\": 0.0001, \"edcr_vs_evi_f1_spearman\": 0.0022, \"edcr_vs_evi_f1_pvalue\": 0.9941, \"edcr_range\": \"0.63-0.99\", \"unique_diagnostic_value\": \"identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1\"}}, {\"id\": \"plan_004\", \"claim\": 1, \"description\": \"DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large) 的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_004_dreeam_baseline\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dev_rel_f1\": 63.57, \"dev_rel_ign_f1\": 61.72, \"dev_evi_f1\": 54.01, \"dev_rel_p\": 66.95, \"dev_rel_r\": 60.51, \"dev_evi_p\": 60.53, \"dev_evi_r\": 48.76}}, {\"id\": \"plan_005\", \"claim\": 1, \"description\": \"CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。\", \"priority\": \"P1\", \"gpu_budget_hours\": 6, \"deps\": [], \"registry_id\": \"mvp2_ced_reranker_poc\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ced_reranker_rel_f1\": 0.4864, \"ced_reranker_evi_f1\": 0.8188, \"ced_reranker_edcr\": 0.6156, \"ced_reranker_precision\": 0.4913, \"ced_reranker_recall\": 0.4815, \"ced_reranker_pred_count\": 14782, \"ced_reranker_format_ok_rate\": 1, \"oracle_rel_f1\": 0.6237, \"oracle_evi_f1\": 0.7942, \"oracle_edcr\": 0.5262, \"oracle_pred_count\": 13418, \"random_rel_f1\": 0.4538, \"random_evi_f1\": 0.8029, \"random_edcr\": 0.6763, \"ced_f1_spearman_r\": 0.3235, \"ced_f1_spearman_p\": 2.46e-191, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"sft_baseline_edcr\": 0.7118, \"rsft_mean_rel_f1\": 0.4596, \"delta_vs_sft_rel_f1\": 0.0807, \"delta_vs_rsft_rel_f1\": 0.0268, \"delta_vs_sft_evi_f1\": 0.0209, \"oracle_ceiling_rel_f1\": 0.218, \"num_generations\": 8, \"temperature\": 0.7, \"generation_time_s\": 20872.6, \"n_docs\": 985}}, {\"id\": \"plan_006\", \"claim\": 1, \"description\": \"Model size ablation: Qwen3-1.7B 和 Qwen3-8B 上复现 RSFT+CED pipeline，验证方法对模型规模的泛化性。应对 RC4。\", \"priority\": \"P1\", \"gpu_budget_hours\": 24, \"deps\": [\"plan_001\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_007\", \"claim\": 1, \"description\": \"Re-DocRED extension: 在 Re-DocRED（修正 false negative 标注的版本）上评估，验证 RSFT+CED 在更干净标注下的表现。应对 RC4。\", \"priority\": \"P1\", \"gpu_budget_hours\": 12, \"deps\": [\"plan_002\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_008\", \"claim\": 2, \"description\": \"top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格 ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"reeval_rsft_topk3\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.4454, \"rel_precision\": 0.4512, \"rel_recall\": 0.4398, \"ign_f1\": 0.4364, \"evi_f1\": 0.8088, \"edcr\": 0.6635, \"format_ok_rate\": 0.999, \"n_truncated\": 214, \"n_predictions\": 16020, \"inference_time_seconds\": 3546.4, \"ign_f1_corrected\": true}}, {\"id\": \"plan_011\", \"claim\": 3, \"description\": \"GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要 gradient_accumulation 适配显存。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_011_bf16_g8_step_eval\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"step_30\": {\"rel_f1\": 0.434, \"evi_f1\": 0.8063, \"edcr\": 0.6807}, \"step_50\": {\"rel_f1\": 0.4276, \"evi_f1\": 0.8024, \"edcr\": 0.6855}, \"step_70\": {\"rel_f1\": 0.4341, \"evi_f1\": 0.8099, \"edcr\": 0.6685}, \"best_step\": \"step_70\", \"trend\": \"non-monotonic, all < ckpt-100 (0.4549)\"}}, {\"id\": \"plan_012\", \"claim\": 3, \"description\": \"DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求 DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。\", \"priority\": \"P0\", \"gpu_budget_hours\": 12, \"deps\": [], \"registry_id\": \"plan_012_dpo_ced\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.3429, \"evi_f1\": 0.8403, \"edcr\": 0.7294, \"format_ok_rate\": 0.995, \"checkpoint\": \"checkpoint-501\", \"rewards_accuracy\": 1, \"margins\": 9.01}}, {\"id\": \"plan_013\", \"claim\": 4, \"description\": \"EDCR 人工标注验证: 100 个样本，人工判断每个 cited evidence sentence 是否真正支持对应 relation。计算 EDCR 与人工判断的相关性，验证 EDCR 作为自动指标的有效性。Dream [M][W] 一致要求。\", \"priority\": \"P1\", \"gpu_budget_hours\": 0, \"deps\": [], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_009\", \"claim\": 3, \"description\": \"GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward 轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心 figure。数据已有，只需汇总+画图。\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [], \"registry_id\": \"plan_009_dynamics_figure\", \"status\": \"DONE\", \"conclusion\": \"success\"}, {\"id\": \"plan_010\", \"claim\": 1, \"description\": \"NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer 的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。\", \"priority\": \"P2\", \"gpu_budget_hours\": 4, \"deps\": [], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_014\", \"claim\": 1, \"description\": \"SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含 evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream v2 三档一致要求。用于回答\\\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\\\"。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_014_sft_no_evidence\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.7077, \"eval_loss\": 0.8781, \"eval_token_accuracy\": 0.8086, \"epochs\": 3, \"total_steps\": 570, \"train_runtime_min\": 64, \"samples\": 3027, \"trainable_params\": \"132M/4.15B (3.18%)\"}}, {\"id\": \"plan_015\", \"claim\": 2, \"description\": \"bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的: 隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于 plan_011 eval 结果。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_011\"], \"registry_id\": \"plan_015_grpo_g4_bf16_v3\", \"status\": \"DONE\", \"conclusion\": \"killed\"}, {\"id\": \"plan_mvp1\", \"claim\": 1, \"description\": \"MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing distractor 的能力验证\", \"priority\": \"P0\", \"gpu_budget_hours\": 1, \"deps\": [], \"registry_id\": \"mvp1_ced_signal\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"mean_margin\": 0.48, \"discrimination_accuracy\": 0.815, \"pearson_r_margin_jaccard\": 0.34, \"pass\": true}}, {\"id\": \"plan_mvp2_sft\", \"claim\": 1, \"description\": \"SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线\", \"priority\": \"P0\", \"gpu_budget_hours\": 4, \"deps\": [], \"registry_id\": \"mvp2_sft_warmup\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss\": 0.72, \"accuracy\": 0.835}}, {\"id\": \"plan_mvp2_rsft\", \"claim\": 1, \"description\": \"RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部 PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087, r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128\", \"priority\": \"P0\", \"gpu_budget_hours\": 20, \"deps\": [\"plan_mvp1\", \"plan_mvp2_sft\"], \"registry_id\": \"mvp2_rsft_train_r1\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.0483, \"num_preds\": 848, \"sft_baseline_rel_f1\": 0.4057, \"failure_mode\": \"relation_ontology_collapse_to_freetext\", \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759}}, {\"id\": \"plan_mvp2_grpo\", \"claim\": 3, \"description\": \"GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1 max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic forgetting。D031/D033 完整轨迹支撑 Claim 3\", \"priority\": \"P0\", \"gpu_budget_hours\": 60, \"deps\": [\"plan_mvp2_sft\"], \"registry_id\": \"mvp2_grpo_ced_lr5e6_r1\", \"status\": \"DONE\", \"conclusion\": \"killed\"}], \"total\": 19}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "a7015b76-3692-482b-97fd-47443ee6520e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"experiments\\\": [{\\\"id\\\": \\\"plan_001\\\", \\\"claim\\\": 2, \\\"description\\\": \\\"CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选 RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py 用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 20, \\\"deps\\\": [], \\\"registry_id\\\": \\\"eval_flat_nli_seed45\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"rel_f1\\\": 0.4551, \\\"rel_p\\\": 0.4632, \\\"rel_r\\\": 0.4472, \\\"ign_f1\\\": 0.4551, \\\"evi_f1\\\": 0.8154, \\\"evi_p\\\": 0.8108, \\\"evi_r\\\": 0.8201, \\\"evi_f1_joint\\\": 0.3556, \\\"edcr\\\": 0.6521, \\\"n_predictions\\\": 15650, \\\"tp\\\": 5434, \\\"format_ok_rate\\\": 1, \\\"n_truncated\\\": 206, \\\"n_documents\\\": 985, \\\"inference_time_seconds\\\": 11867.6}}, {\\\"id\\\": \\\"plan_002\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set 上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 4, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": null, \\\"status\\\": \\\"planned\\\"}, {\\\"id\\\": \\\"plan_003\\\", \\\"claim\\\": 4, \\\"description\\\": \\\"EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing 方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": \\\"plan_003_edcr_diagnostic\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"methods_evaluated\\\": 15, \\\"edcr_vs_rel_f1_spearman\\\": -0.9648, \\\"edcr_vs_rel_f1_pvalue\\\": 0.0001, \\\"edcr_vs_evi_f1_spearman\\\": 0.0022, \\\"edcr_vs_evi_f1_pvalue\\\": 0.9941, \\\"edcr_range\\\": \\\"0.63-0.99\\\", \\\"unique_diagnostic_value\\\": \\\"identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1\\\"}}, {\\\"id\\\": \\\"plan_004\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large) 的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [], \\\"registry_id\\\": \\\"plan_004_dreeam_baseline\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"dev_rel_f1\\\": 63.57, \\\"dev_rel_ign_f1\\\": 61.72, \\\"dev_evi_f1\\\": 54.01, \\\"dev_rel_p\\\": 66.95, \\\"dev_rel_r\\\": 60.51, \\\"dev_evi_p\\\": 60.53, \\\"dev_evi_r\\\": 48.76}}, {\\\"id\\\": \\\"plan_005\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 6, \\\"deps\\\": [], \\\"registry_id\\\": \\\"mvp2_ced_reranker_poc\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"ced_reranker_rel_f1\\\": 0.4864, \\\"ced_reranker_evi_f1\\\": 0.8188, \\\"ced_reranker_edcr\\\": 0.6156, \\\"ced_reranker_precision\\\": 0.4913, \\\"ced_reranker_recall\\\": 0.4815, \\\"ced_reranker_pred_count\\\": 14782, \\\"ced_reranker_format_ok_rate\\\": 1, \\\"oracle_rel_f1\\\": 0.6237, \\\"oracle_evi_f1\\\": 0.7942, \\\"oracle_edcr\\\": 0.5262, \\\"oracle_pred_count\\\": 13418, \\\"random_rel_f1\\\": 0.4538, \\\"random_evi_f1\\\": 0.8029, \\\"random_edcr\\\": 0.6763, \\\"ced_f1_spearman_r\\\": 0.3235, \\\"ced_f1_spearman_p\\\": 2.46e-191, \\\"sft_baseline_rel_f1\\\": 0.4057, \\\"sft_baseline_evi_f1\\\": 0.7979, \\\"sft_baseline_edcr\\\": 0.7118, \\\"rsft_mean_rel_f1\\\": 0.4596, \\\"delta_vs_sft_rel_f1\\\": 0.0807, \\\"delta_vs_rsft_rel_f1\\\": 0.0268, \\\"delta_vs_sft_evi_f1\\\": 0.0209, \\\"oracle_ceiling_rel_f1\\\": 0.218, \\\"num_generations\\\": 8, \\\"temperature\\\": 0.7, \\\"generation_time_s\\\": 20872.6, \\\"n_docs\\\": 985}}, {\\\"id\\\": \\\"plan_006\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"Model size ablation: Qwen3-1.7B 和 Qwen3-8B 上复现 RSFT+CED pipeline，验证方法对模型规模的泛化性。应对 RC4。\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 24, \\\"deps\\\": [\\\"plan_001\\\"], \\\"registry_id\\\": null, \\\"status\\\": \\\"planned\\\"}, {\\\"id\\\": \\\"plan_007\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"Re-DocRED extension: 在 Re-DocRED（修正 false negative 标注的版本）上评估，验证 RSFT+CED 在更干净标注下的表现。应对 RC4。\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 12, \\\"deps\\\": [\\\"plan_002\\\"], \\\"registry_id\\\": null, \\\"status\\\": \\\"planned\\\"}, {\\\"id\\\": \\\"plan_008\\\", \\\"claim\\\": 2, \\\"description\\\": \\\"top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格 ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [], \\\"registry_id\\\": \\\"reeval_rsft_topk3\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"rel_f1\\\": 0.4454, \\\"rel_precision\\\": 0.4512, \\\"rel_recall\\\": 0.4398, \\\"ign_f1\\\": 0.4364, \\\"evi_f1\\\": 0.8088, \\\"edcr\\\": 0.6635, \\\"format_ok_rate\\\": 0.999, \\\"n_truncated\\\": 214, \\\"n_predictions\\\": 16020, \\\"inference_time_seconds\\\": 3546.4, \\\"ign_f1_corrected\\\": true}}, {\\\"id\\\": \\\"plan_011\\\", \\\"claim\\\": 3, \\\"description\\\": \\\"GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要 gradient_accumulation 适配显存。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [], \\\"registry_id\\\": \\\"plan_011_bf16_g8_step_eval\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"step_30\\\": {\\\"rel_f1\\\": 0.434, \\\"evi_f1\\\": 0.8063, \\\"edcr\\\": 0.6807}, \\\"step_50\\\": {\\\"rel_f1\\\": 0.4276, \\\"evi_f1\\\": 0.8024, \\\"edcr\\\": 0.6855}, \\\"step_70\\\": {\\\"rel_f1\\\": 0.4341, \\\"evi_f1\\\": 0.8099, \\\"edcr\\\": 0.6685}, \\\"best_step\\\": \\\"step_70\\\", \\\"trend\\\": \\\"non-monotonic, all < ckpt-100 (0.4549)\\\"}}, {\\\"id\\\": \\\"plan_012\\\", \\\"claim\\\": 3, \\\"description\\\": \\\"DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求 DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 12, \\\"deps\\\": [], \\\"registry_id\\\": \\\"plan_012_dpo_ced\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"negative\\\", \\\"metrics\\\": {\\\"rel_f1\\\": 0.3429, \\\"evi_f1\\\": 0.8403, \\\"edcr\\\": 0.7294, \\\"format_ok_rate\\\": 0.995, \\\"checkpoint\\\": \\\"checkpoint-501\\\", \\\"rewards_accuracy\\\": 1, \\\"margins\\\": 9.01}}, {\\\"id\\\": \\\"plan_013\\\", \\\"claim\\\": 4, \\\"description\\\": \\\"EDCR 人工标注验证: 100 个样本，人工判断每个 cited evidence sentence 是否真正支持对应 relation。计算 EDCR 与人工判断的相关性，验证 EDCR 作为自动指标的有效性。Dream [M][W] 一致要求。\\\", \\\"priority\\\": \\\"P1\\\", \\\"gpu_budget_hours\\\": 0, \\\"deps\\\": [], \\\"registry_id\\\": null, \\\"status\\\": \\\"planned\\\"}, {\\\"id\\\": \\\"plan_009\\\", \\\"claim\\\": 3, \\\"description\\\": \\\"GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward 轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心 figure。数据已有，只需汇总+画图。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 2, \\\"deps\\\": [], \\\"registry_id\\\": \\\"plan_009_dynamics_figure\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\"}, {\\\"id\\\": \\\"plan_010\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer 的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。\\\", \\\"priority\\\": \\\"P2\\\", \\\"gpu_budget_hours\\\": 4, \\\"deps\\\": [], \\\"registry_id\\\": null, \\\"status\\\": \\\"planned\\\"}, {\\\"id\\\": \\\"plan_014\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含 evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream v2 三档一致要求。用于回答\\\\\\\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\\\\\\\"。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [], \\\"registry_id\\\": \\\"plan_014_sft_no_evidence\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"train_loss\\\": 0.7077, \\\"eval_loss\\\": 0.8781, \\\"eval_token_accuracy\\\": 0.8086, \\\"epochs\\\": 3, \\\"total_steps\\\": 570, \\\"train_runtime_min\\\": 64, \\\"samples\\\": 3027, \\\"trainable_params\\\": \\\"132M/4.15B (3.18%)\\\"}}, {\\\"id\\\": \\\"plan_015\\\", \\\"claim\\\": 2, \\\"description\\\": \\\"bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的: 隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于 plan_011 eval 结果。\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 8, \\\"deps\\\": [\\\"plan_011\\\"], \\\"registry_id\\\": \\\"plan_015_grpo_g4_bf16_v3\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}, {\\\"id\\\": \\\"plan_mvp1\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing distractor 的能力验证\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 1, \\\"deps\\\": [], \\\"registry_id\\\": \\\"mvp1_ced_signal\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"mean_margin\\\": 0.48, \\\"discrimination_accuracy\\\": 0.815, \\\"pearson_r_margin_jaccard\\\": 0.34, \\\"pass\\\": true}}, {\\\"id\\\": \\\"plan_mvp2_sft\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 4, \\\"deps\\\": [], \\\"registry_id\\\": \\\"mvp2_sft_warmup\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"eval_loss\\\": 0.72, \\\"accuracy\\\": 0.835}}, {\\\"id\\\": \\\"plan_mvp2_rsft\\\", \\\"claim\\\": 1, \\\"description\\\": \\\"RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部 PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087, r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 20, \\\"deps\\\": [\\\"plan_mvp1\\\", \\\"plan_mvp2_sft\\\"], \\\"registry_id\\\": \\\"mvp2_rsft_train_r1\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"success\\\", \\\"metrics\\\": {\\\"rel_f1\\\": 0.0483, \\\"num_preds\\\": 848, \\\"sft_baseline_rel_f1\\\": 0.4057, \\\"failure_mode\\\": \\\"relation_ontology_collapse_to_freetext\\\", \\\"epoch1_eval_loss\\\": 0.756, \\\"epoch2_eval_loss\\\": 0.759}}, {\\\"id\\\": \\\"plan_mvp2_grpo\\\", \\\"claim\\\": 3, \\\"description\\\": \\\"GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1 max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic forgetting。D031/D033 完整轨迹支撑 Claim 3\\\", \\\"priority\\\": \\\"P0\\\", \\\"gpu_budget_hours\\\": 60, \\\"deps\\\": [\\\"plan_mvp2_sft\\\"], \\\"registry_id\\\": \\\"mvp2_grpo_ced_lr5e6_r1\\\", \\\"status\\\": \\\"DONE\\\", \\\"conclusion\\\": \\\"killed\\\"}], \\\"total\\\": 19}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": [{\"id\": \"plan_001\", \"claim\": 2, \"description\": \"CED vs flat-NLI RSFT ablation: 用 flat-NLI scoring（非 contrastive）筛选 RSFT 训练数据，对比 CED scoring。验证 CED 的对比性 margin 是否优于朴素 NLI。步骤: (1) rsft_score_filter.py 用 flat-NLI 模式重新打分已有 candidates, (2) RSFT 训练, (3) 全量 dev eval。\", \"priority\": \"P0\", \"gpu_budget_hours\": 20, \"deps\": [], \"registry_id\": \"eval_flat_nli_seed45\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4551, \"rel_p\": 0.4632, \"rel_r\": 0.4472, \"ign_f1\": 0.4551, \"evi_f1\": 0.8154, \"evi_p\": 0.8108, \"evi_r\": 0.8201, \"evi_f1_joint\": 0.3556, \"edcr\": 0.6521, \"n_predictions\": 15650, \"tp\": 5434, \"format_ok_rate\": 1, \"n_truncated\": 206, \"n_documents\": 985, \"inference_time_seconds\": 11867.6}}, {\"id\": \"plan_002\", \"claim\": 1, \"description\": \"Test set evaluation: 用 RSFT best config（r2b 或 s44）在 DocRED test set 上评估。提交 CodaLab 获得官方 F1/Ign-F1，同时本地计算 Evi-F1 和 EDCR。\", \"priority\": \"P0\", \"gpu_budget_hours\": 4, \"deps\": [\"plan_001\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_003\", \"claim\": 4, \"description\": \"EDCR pipeline 验证 + cross-method diagnostic table: 在所有 evidence-producing 方法（SFT, RSFT-CED, RSFT-flatNLI, CED-reranker）上计算 EDCR，验证 EDCR 作为独立评估指标的诊断能力。\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [\"plan_001\"], \"registry_id\": \"plan_003_edcr_diagnostic\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"methods_evaluated\": 15, \"edcr_vs_rel_f1_spearman\": -0.9648, \"edcr_vs_rel_f1_pvalue\": 0.0001, \"edcr_vs_evi_f1_spearman\": 0.0022, \"edcr_vs_evi_f1_pvalue\": 0.9941, \"edcr_range\": \"0.63-0.99\", \"unique_diagnostic_value\": \"identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1\"}}, {\"id\": \"plan_004\", \"claim\": 1, \"description\": \"DREEAM baseline reproduction: 在 DocRED dev set 上复现 DREEAM (RoBERTa-large) 的 Evi-F1，确认 57.34 数字可复现，作为 Claim 1 的直接对比基线。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_004_dreeam_baseline\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"dev_rel_f1\": 63.57, \"dev_rel_ign_f1\": 61.72, \"dev_evi_f1\": 54.01, \"dev_rel_p\": 66.95, \"dev_rel_r\": 60.51, \"dev_evi_p\": 60.53, \"dev_evi_r\": 48.76}}, {\"id\": \"plan_005\", \"claim\": 1, \"description\": \"CED-as-reranker: 推理时用 CED 对 SFT 生成的 N=8 候选重排选最佳，无需额外训练。验证 CED 在推理时的价值。已在运行中。\", \"priority\": \"P1\", \"gpu_budget_hours\": 6, \"deps\": [], \"registry_id\": \"mvp2_ced_reranker_poc\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"ced_reranker_rel_f1\": 0.4864, \"ced_reranker_evi_f1\": 0.8188, \"ced_reranker_edcr\": 0.6156, \"ced_reranker_precision\": 0.4913, \"ced_reranker_recall\": 0.4815, \"ced_reranker_pred_count\": 14782, \"ced_reranker_format_ok_rate\": 1, \"oracle_rel_f1\": 0.6237, \"oracle_evi_f1\": 0.7942, \"oracle_edcr\": 0.5262, \"oracle_pred_count\": 13418, \"random_rel_f1\": 0.4538, \"random_evi_f1\": 0.8029, \"random_edcr\": 0.6763, \"ced_f1_spearman_r\": 0.3235, \"ced_f1_spearman_p\": 2.46e-191, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"sft_baseline_edcr\": 0.7118, \"rsft_mean_rel_f1\": 0.4596, \"delta_vs_sft_rel_f1\": 0.0807, \"delta_vs_rsft_rel_f1\": 0.0268, \"delta_vs_sft_evi_f1\": 0.0209, \"oracle_ceiling_rel_f1\": 0.218, \"num_generations\": 8, \"temperature\": 0.7, \"generation_time_s\": 20872.6, \"n_docs\": 985}}, {\"id\": \"plan_006\", \"claim\": 1, \"description\": \"Model size ablation: Qwen3-1.7B 和 Qwen3-8B 上复现 RSFT+CED pipeline，验证方法对模型规模的泛化性。应对 RC4。\", \"priority\": \"P1\", \"gpu_budget_hours\": 24, \"deps\": [\"plan_001\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_007\", \"claim\": 1, \"description\": \"Re-DocRED extension: 在 Re-DocRED（修正 false negative 标注的版本）上评估，验证 RSFT+CED 在更干净标注下的表现。应对 RC4。\", \"priority\": \"P1\", \"gpu_budget_hours\": 12, \"deps\": [\"plan_002\"], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_008\", \"claim\": 2, \"description\": \"top_k ablation: CED scoring 筛选 top_k=3（更多训练数据 ~8000 samples）vs top_k=1（更严格 ~2718 samples），验证 CED 过滤严格度对 RSFT 质量的影响。\", \"priority\": \"P1\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"reeval_rsft_topk3\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.4454, \"rel_precision\": 0.4512, \"rel_recall\": 0.4398, \"ign_f1\": 0.4364, \"evi_f1\": 0.8088, \"edcr\": 0.6635, \"format_ok_rate\": 0.999, \"n_truncated\": 214, \"n_predictions\": 16020, \"inference_time_seconds\": 3546.4, \"ign_f1_corrected\": true}}, {\"id\": \"plan_011\", \"claim\": 3, \"description\": \"GRPO G=8 实验: Dream 三档一致指出 G=4 太小，标准 GRPO 用 G=8-16。用 G=8 + CED reward + kl_coef=0.01 重跑 GRPO，验证 failure 是否持续。如仍 fail → 加强 Claim 3；如改善 → 需修改论文结论。可能需要 gradient_accumulation 适配显存。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_011_bf16_g8_step_eval\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"step_30\": {\"rel_f1\": 0.434, \"evi_f1\": 0.8063, \"edcr\": 0.6807}, \"step_50\": {\"rel_f1\": 0.4276, \"evi_f1\": 0.8024, \"edcr\": 0.6855}, \"step_70\": {\"rel_f1\": 0.4341, \"evi_f1\": 0.8099, \"edcr\": 0.6685}, \"best_step\": \"step_70\", \"trend\": \"non-monotonic, all < ckpt-100 (0.4549)\"}}, {\"id\": \"plan_012\", \"claim\": 3, \"description\": \"DPO+CED experiment: 用 RSFT 候选数据构造 preference pairs (CED-preferred vs CED-rejected)，DPO 训练。验证 DPO 是否避免 GRPO 的 catastrophic forgetting。Dream v2 三档要求 DPO 作为 RL spectrum 关键数据点，必须补全训练超参（β, lr, epochs, pair construction）。D045 升 P0。\", \"priority\": \"P0\", \"gpu_budget_hours\": 12, \"deps\": [], \"registry_id\": \"plan_012_dpo_ced\", \"status\": \"DONE\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.3429, \"evi_f1\": 0.8403, \"edcr\": 0.7294, \"format_ok_rate\": 0.995, \"checkpoint\": \"checkpoint-501\", \"rewards_accuracy\": 1, \"margins\": 9.01}}, {\"id\": \"plan_013\", \"claim\": 4, \"description\": \"EDCR 人工标注验证: 100 个样本，人工判断每个 cited evidence sentence 是否真正支持对应 relation。计算 EDCR 与人工判断的相关性，验证 EDCR 作为自动指标的有效性。Dream [M][W] 一致要求。\", \"priority\": \"P1\", \"gpu_budget_hours\": 0, \"deps\": [], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_009\", \"claim\": 3, \"description\": \"GRPO forgetting dynamics figure: 整理全部 GRPO checkpoint（42个）的 rel_f1/evi_f1/EDCR/reward 轨迹，绘制 training dynamics 可视化图。包含 G=4 vs G=8 对比、三种 reward 对比。Dream v2 三档一致要求此图作为论文核心 figure。数据已有，只需汇总+画图。\", \"priority\": \"P0\", \"gpu_budget_hours\": 2, \"deps\": [], \"registry_id\": \"plan_009_dynamics_figure\", \"status\": \"DONE\", \"conclusion\": \"success\"}, {\"id\": \"plan_010\", \"claim\": 1, \"description\": \"NLI model ablation: DeBERTa-v3-base vs DeBERTa-v3-large 作为 CED scorer 的对比，验证 NLI 模型能力对 CED 打分质量的影响。应对 RC1。\", \"priority\": \"P2\", \"gpu_budget_hours\": 4, \"deps\": [], \"registry_id\": null, \"status\": \"planned\"}, {\"id\": \"plan_014\", \"claim\": 1, \"description\": \"SFT-without-evidence ablation: 训练 Qwen3-4B SFT 只输出 relation triples（不含 evidence sentences），对比标准 SFT（含 evidence）的 rel_f1。隔离 evidence generation 对抽取性能的代价。Dream v2 三档一致要求。用于回答\\\"43.2% vs LMRC 60.7% 的 gap 有多少来自 evidence 生成负担\\\"。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [], \"registry_id\": \"plan_014_sft_no_evidence\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.7077, \"eval_loss\": 0.8781, \"eval_token_accuracy\": 0.8086, \"epochs\": 3, \"total_steps\": 570, \"train_runtime_min\": 64, \"samples\": 3027, \"trainable_params\": \"132M/4.15B (3.18%)\"}}, {\"id\": \"plan_015\", \"claim\": 2, \"description\": \"bf16 LoRA GRPO clean control: 与原始 GRPO (QLoRA 4-bit, G=4, kl=0, CED reward) 只改一个变量——quantization 从 QLoRA 4-bit 改为 bf16 LoRA。G=4, kl_coef=0 不变。目的: 隔离 QLoRA confound，判断 decoupling 是 QLoRA artifact 还是 genuine RL-for-IE 现象。Dream v2 三档一致的 critical 要求。如 decoupling 在 bf16 下仍持续 → 可泛化 claim；如消失 → QLoRA 特定，需 re-scope。优先级取决于 plan_011 eval 结果。\", \"priority\": \"P0\", \"gpu_budget_hours\": 8, \"deps\": [\"plan_011\"], \"registry_id\": \"plan_015_grpo_g4_bf16_v3\", \"status\": \"DONE\", \"conclusion\": \"killed\"}, {\"id\": \"plan_mvp1\", \"claim\": 1, \"description\": \"MVP-1: CED signal verification — DeBERTa NLI 区分 gold evidence vs entity-sharing distractor 的能力验证\", \"priority\": \"P0\", \"gpu_budget_hours\": 1, \"deps\": [], \"registry_id\": \"mvp1_ced_signal\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"mean_margin\": 0.48, \"discrimination_accuracy\": 0.815, \"pearson_r_margin_jaccard\": 0.34, \"pass\": true}}, {\"id\": \"plan_mvp2_sft\", \"claim\": 1, \"description\": \"SFT baseline: Qwen3-4B + LoRA SFT on DocRED gold, 建立抽取和证据质量基线\", \"priority\": \"P0\", \"gpu_budget_hours\": 4, \"deps\": [], \"registry_id\": \"mvp2_sft_warmup\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"eval_loss\": 0.72, \"accuracy\": 0.835}}, {\"id\": \"plan_mvp2_rsft\", \"claim\": 1, \"description\": \"RSFT+CED 端到端验证: CED-filtered rejection sampling fine-tuning, 4 组配置全部 PASS。真实结果(D038修正后): r1 rel_f1=0.4449/evi_f1=0.8187, s44 rel_f1=0.4655/evi_f1=0.8087, r2a rel_f1=0.4494/evi_f1=0.8108, r2b rel_f1=0.4493/evi_f1=0.8128\", \"priority\": \"P0\", \"gpu_budget_hours\": 20, \"deps\": [\"plan_mvp1\", \"plan_mvp2_sft\"], \"registry_id\": \"mvp2_rsft_train_r1\", \"status\": \"DONE\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.0483, \"num_preds\": 848, \"sft_baseline_rel_f1\": 0.4057, \"failure_mode\": \"relation_ontology_collapse_to_freetext\", \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759}}, {\"id\": \"plan_mvp2_grpo\", \"claim\": 3, \"description\": \"GRPO+QLoRA 全线失败（negative result = C3 核心证据）: 3 种 reward × 多 lr, rel_f1 max=0.211(lr5e-5)/0.014(lr5e-6), evi_f1 在 GRPO 下反而提升至 0.850 但 rel_f1 catastrophic forgetting。D031/D033 完整轨迹支撑 Claim 3\", \"priority\": \"P0\", \"gpu_budget_hours\": 60, \"deps\": [\"plan_mvp2_sft\"], \"registry_id\": \"mvp2_grpo_ced_lr5e6_r1\", \"status\": \"DONE\", \"conclusion\": \"killed\"}], \"total\": 19}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 14_

<details><summary>Logged reasoning block</summary>

```text
The registry returned 0 experiments with status "success". Let me try without the filter to get all experiments, as the status field in the registry might use different casing or values.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "ca06fe07-42e3-4799-a6db-d3eeaf75554e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbpeUB2f8TQyqtYJm89NAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11891,
      "cache_read_input_tokens": 25841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11891
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

_source line 15_

Registry 返回 0 条 success 记录，可能是大小写问题。让我获取全部实验记录，同时读取 decisions 和 memory 文件获取更多上下文。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "000a9555-5738-4eb3-bc0d-4afbbcafbf62",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbpeUB2f8TQyqtYJm89NAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11891,
      "cache_read_input_tokens": 25841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11891
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

_source line 16_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_013XQuq1BPznbMbKhKetjdpg`</summary>

```json
{
  "project": "faith-evidence-ie",
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
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "99e5d069-04c1-4038-b0e9-def7d7784c8d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QbpeUB2f8TQyqtYJm89NAx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 11891,
      "cache_read_input_tokens": 25841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11891
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

_source line 17 · 2026-05-16T03:21:25.117Z_

<details><summary>↩ Tool result · `toolu_013XQuq1BPznbMbKhKetjdpg`</summary>

```text
Error: result (238,643 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "85cef0a7-cc83-4329-afd8-4ccba4b204c6",
  "tool_use_result": {
    "content": "Error: result (238,643 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"reeval_flat_nli_s42\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:38:03.120Z\", \"updated_at\": \"2026-05-16T03:18:34.343Z\", \"hypothesis\": \"Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。\", \"parent\": \"plan_001_rsft_flat_nli\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES={GPU} HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s42_reeval --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + flat-NLI RSFT s42\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_flat_nli/checkpoint-507\", \"eval_data\": \"docred dev (985 docs)\"}}, \"reeval_ced_s44\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:38:00.052Z\", \"updated_at\": \"2026-05-16T03:18:30.948Z\", \"hypothesis\": \"Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。\", \"parent\": \"mvp2_rsft_train_r1_s44\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES={GPU} HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s44/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 44 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s44_reeval --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + CED RSFT s44\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_s44/checkpoint-510\", \"eval_data\": \"docred dev (985 docs)\"}, \"notes\": \"正确 checkpoint: /root/autodl-tmp/rsft_output_s44/checkpoint-510。旧 eval 路径一致但可能用了根目录 adapter 而非 checkpoint-510 子目录。\", \"gpu\": \"cuda:3\"}, \"reeval_ced_s42\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:37:58.498Z\", \"updated_at\": \"2026-05-16T03:18:27.685Z\", \"hypothesis\": \"Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。\", \"parent\": \"mvp2_rsft_train_r1\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES={GPU} HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s42_reeval --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + CED RSFT s42\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output/checkpoint-510\", \"eval_data\": \"docred dev (985 docs)\"}, \"notes\": \"旧 eval (rsft_r2b_maxtok1536_r2) 不仅协议不一致，而且用了错误 checkpoint (rsft_output_r2b: lora_alpha=32, 仅 160 步)。正确 checkpoint: /root/autodl-tmp/rsft_output/checkpoint-510 (seed=42, lora_alpha=128, 510 步，与 s43/s44/s45 配置一致)。\"}, \"eval_flat_nli_seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:12:39.186Z\", \"updated_at\": \"2026-05-16T03:06:29.033Z\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。\", \"parent\": \"plan_001_flat_nli_seed45\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s45/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 45 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s45 --no-quantize\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 272164, \"log_path\": \"~/runs/faith-evidence-ie/eval_flat_nli_seed45.log\", \"submitted_at\": \"2026-05-15T23:44:54.114Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 12275, \"model_name\": \"Qwen3-4B\", \"seed\": 45, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_flat_nli_s45/checkpoint-507\", \"eval_data\": \"docred-dev\", \"wall_clock_seconds\": 12094.9, \"gpu_hours\": 3.36}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"notes\": \"[2026-05-16 02:18 UTC] 196/247 batches (79%), ~45min remaining. ETA ~03:03 UTC. Running normally at ~47s/it avg.\", \"reproduce\": {\"finished_at\": \"2026-05-16T03:03:01.591Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T03:03:05.615685+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4551, \"rel_p\": 0.4632, \"rel_r\": 0.4472, \"ign_f1\": 0.4551, \"evi_f1\": 0.8154, \"evi_p\": 0.8108, \"evi_r\": 0.8201, \"evi_f1_joint\": 0.3556, \"edcr\": 0.6521, \"n_predictions\": 15650, \"tp\": 5434, \"format_ok_rate\": 1, \"n_truncated\": 206, \"n_documents\": 985, \"inference_time_seconds\": 11867.6}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s45/checkpoint-507\", \"log_path\": \"~/runs/faith-evidence-ie/eval_flat_nli_seed45.log\", \"completed_at\": \"2026-05-16T03:06:29.033Z\"}, \"reeval_flat_nli_s43_r2\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:32:45.507Z\", \"updated_at\": \"2026-05-16T03:05:12.814Z\", \"hypothesis\": \"Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s43/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s43_reeval_r2 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"291003\", \"log_path\": \"~/runs/faith-evidence-ie/reeval_flat_nli_s43_r2.log\", \"submitted_at\": \"2026-05-16T03:05:10.815Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": \"291003\", \"log_path\": \"~/runs/faith-evidence-ie/reeval_flat_nli_s43_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s43/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s43_reeval_r2 --no-quantize\\\"\"}}, \"seed_comparison_prep\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:35:52.694Z\", \"updated_at\": \"2026-05-16T02:35:52.694Z\", \"notes\": \"## Seed Comparison Pre-Analysis (2026-05-16)\\n\\n### Available Results (3/4 seeds each, s45 pending for both):\\n\\n**flat-NLI RSFT:**\\n- s42: rel_f1=0.4539 (dir: rsft_flat_nli)\\n- s43: rel_f1=0.4523 (dir: rsft_flat_nli_s43_reeval; original rsft_flat_nli_s43 was broken f1=0.002)\\n- s44: rel_f1=0.4615 (dir: rsft_flat_nli_s44; NOTE: only metrics.json, no metrics_v2.json with fixed Ign-F1)\\n- s45: PENDING (empty dir)\\n- Mean: 0.4559 ± 0.0049\\n\\n**CED RSFT:**\\n- s42: rel_f1=0.4504 (dir: rsft_r2b_maxtok1536)\\n- s43: rel_f1=0.4683 (dir: rsft_s43)\\n- s44: rel_f1=0.4655 (dir: rsft_s44)\\n- s45: PENDING (empty dir)\\n- Mean: 0.4614 ± 0.0096\\n\\n### Pre-comparison (N=3):\\n- rel_f1 Delta (fNLI - CED): -0.0055 (CED slightly better)\\n- Paired t-test: t=0.967, p=0.4357 (NOT significant)\\n- 95% CI for delta: [-0.0299, +0.0189] (crosses zero)\\n- Cohen's d: -0.558\\n\\n### seed_comparison.py status: WORKING\\n- Auto-discovers all seeds, handles fallback dirs, filters broken results (f1<0.01)\\n- Outputs to /root/autodl-tmp/eval_results/seed_comparison.{md,json}\\n- Supports --watch mode for polling\"}, \"eval_flat_nli_s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:14:05.010Z\", \"updated_at\": \"2026-05-16T02:32:09.485Z\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。\", \"parent\": \"plan_001_flat_nli_seed44\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s44/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 44 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s44 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"270462\", \"log_path\": \"~/runs/faith-evidence-ie/eval_flat_nli_s44.log\", \"submitted_at\": \"2026-05-15T23:27:39.718Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s44/checkpoint-507\", \"wall_clock_seconds\": 11069.8, \"gpu_hours\": 3.07}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"270462\", \"log_path\": \"~/runs/faith-evidence-ie/eval_flat_nli_s44.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s44/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 44 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s44 --no-quantize\\\"\", \"finished_at\": \"2026-05-16T02:24:33.081Z\"}, \"notes\": \"[2026-05-16 02:18 UTC] 238/247 batches (96%), ~7min remaining. ETA ~02:25 UTC. Running normally at ~45s/it avg.\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T02:24:37.198824+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4615, \"rel_p\": 0.4779, \"rel_r\": 0.4462, \"ign_f1\": 0.4615, \"evi_f1\": 0.8131, \"evi_p\": 0.8187, \"evi_r\": 0.8077, \"evi_f1_joint\": 0.3597, \"edcr\": 0.6458, \"predictions\": 15257, \"tp\": 5422, \"format_ok\": \"985/985\", \"inference_hours\": 2.93}, \"completed_at\": \"2026-05-16T02:32:09.485Z\"}, \"eval_plan_014_no_evidence_r2\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:34:45.302Z\", \"updated_at\": \"2026-05-16T02:27:55.797Z\", \"hypothesis\": \"Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。\", \"parent\": \"plan_014_sft_no_evidence\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_no_evidence_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/sft_no_evidence_noquant --no-quantize --no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"288109\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_014_no_evidence_r2.log\", \"submitted_at\": \"2026-05-16T02:27:53.107Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"pid\": \"288109\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_014_no_evidence_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_no_evidence_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/sft_no_evidence_noquant --no-quantize --no_evidence\\\"\"}}, \"eval_rsft_ced_s43\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:30:37.978Z\", \"updated_at\": \"2026-05-16T02:18:36.445Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s43/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s43 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"286587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_rsft_ced_s43.log\", \"submitted_at\": \"2026-05-16T02:13:11.138Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"rsft_ced_s43_train_r3\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-16T02:12:19.128Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s43/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 43 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s43 --no-quantize\\\"\"}, \"pid\": \"286587\", \"log_path\": \"~/runs/faith-evidence-ie/eval_rsft_ced_s43.log\", \"notes\": \"[2026-05-16 02:18 UTC] 5/247 batches (2%), ~3h remaining. ETA ~05:19 UTC. Just started, running normally at ~45s/it avg.\"}, \"eval_rsft_ced_s45\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-16T01:30:34.036Z\", \"updated_at\": \"2026-05-16T02:18:35.481Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 45 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s45 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"283838\", \"log_path\": \"~/runs/faith-evidence-ie/eval_rsft_ced_s45.log\", \"submitted_at\": \"2026-05-16T01:30:48.081Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"hypothesis\": \"Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"rsft_ced_s45_train_r4\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T01:30:45.945Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_ced_s45/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 45 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s45 --no-quantize\\\"\"}, \"pid\": \"283838\", \"log_path\": \"~/runs/faith-evidence-ie/eval_rsft_ced_s45.log\", \"notes\": \"[2026-05-16 02:18 UTC] 69/247 batches (28%), ~2h remaining. ETA ~04:18 UTC. Running normally at ~41s/it avg.\"}, \"rsft_ced_s45_train_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:33:12.797Z\", \"updated_at\": \"2026-05-16T02:15:34.043Z\", \"hypothesis\": \"CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510\", \"log_path\": \"/tmp/rsft_ced_s45_r4.log\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_ced_s45/checkpoint-510\", \"log_path\": \"/tmp/rsft_ced_s45_r4.log\", \"metrics\": {\"training_completed\": true, \"checkpoint\": \"checkpoint-510\", \"note\": \"Training metrics not captured (r4 retry after OOM). Eval running as eval_rsft_ced_s45.\"}, \"completed_at\": \"2026-05-16T02:15:34.043Z\"}, \"rsft_ced_s43_train_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:20:57.272Z\", \"updated_at\": \"2026-05-16T02:14:46.064Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/rsft_output_ced_s43/checkpoint-510\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s43_train_r3.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-16T02:10:56.984Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T02:11:00.631057+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6151, \"eval_loss\": 0.7618, \"task_eval_f1\": 0.5026, \"task_eval_ign_f1\": 0.4932, \"task_eval_evi_f1\": 0.7624, \"task_eval_edcr\": 0.6516, \"total_steps\": 510, \"epochs\": 3, \"training_hours\": 1.82}, \"completed_at\": \"2026-05-16T02:14:46.064Z\"}, \"eval_plan_014_no_evidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:17:32.011Z\", \"updated_at\": \"2026-05-16T01:34:06.402Z\", \"hypothesis\": \"Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。\", \"parent\": \"plan_014_sft_no_evidence\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_no_evidence_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/sft_no_evidence_noquant --no-quantize --no_evidence\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"283455\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_014_no_evidence.log\", \"submitted_at\": \"2026-05-16T01:27:16.251Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 33.8, \"gpu_hours\": 0.01}, \"conclusion\": \"failed\", \"notes\": \"FAILED: ValueError — model_path 含 adapter_config.json 触发 adapter 检测逻辑，要求 --sft_adapter。诊断(Worker diagnose_eval_plan_014): SFT adapter 本身就是 model_path，不应走 adapter stacking 路径。修复：--model_path 改传底座 Qwen3-4B，--sft_adapter 传 /root/autodl-tmp/sft_no_evidence_output。待 GPU 空闲后以 corrected command 重试。\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-16T01:27:14.109Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_no_evidence_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/sft_no_evidence_noquant --no-quantize --no_evidence\\\"\", \"finished_at\": \"2026-05-16T01:27:46.702Z\", \"training_hours\": 0.01}, \"pid\": \"283455\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_014_no_evidence.log\", \"failure_reason\": \"Traceback → is a LoRA adapter (adapter_config.json found), but --sft_adapter is not set. RSFT/DPO/GRPO adapters are trained on SFT-merged model and MUST be evaluated with --sft_adapter pointing to the SFT adapter directory. Add: --sft_adapter /path/to/sft_output\", \"completed_at\": \"2026-05-16T01:27:50.023Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T01:27:53.542593+00:00\"}]}}, \"rsft_ced_s45_train_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:21:01.099Z\", \"updated_at\": \"2026-05-16T00:31:23.730Z\", \"spec\": {\"command\": \"python -m freige.training.rsft_trainer --seed 45 --data_path rsft_filtered --output_dir rsft_output_ced_s45 --batch_size 4 --gradient_accumulation_steps 4 --weighted_sampling\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"277407\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s45_train_r3.log\", \"submitted_at\": \"2026-05-16T00:21:15.972Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"rsft_filtered\", \"data_count\": 2718, \"model_name\": \"sft_base + ced_rsft\", \"seed\": 45, \"wall_clock_seconds\": 368.8, \"gpu_hours\": 0.1, \"notes\": \"CUDA OOM — GPU 2 被 orphan 进程 PID 276148 占用 31.6GB。Worker 正在清理，将创建 r4 重提交。\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T00:27:24.802Z\", \"notes\": \"CUDA OOM at launch: cuda:2 occupied by orphan PID 276148 (31.6GB). Need to kill orphan and resubmit as r4.\"}, \"rsft_ced_s45_train_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:09:11.100Z\", \"updated_at\": \"2026-05-16T00:25:40.284Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_ced_s45 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-s45-r2 --seed 45\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"276143\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s45_train_r2.log\", \"submitted_at\": \"2026-05-16T00:16:52.439Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 225.7, \"gpu_hours\": 0.06}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"pid\": \"276143\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s45_train_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_ced_s45 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-s45-r2 --seed 45\\\"\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T00:20:38.182Z\", \"notes\": \"Director 下令终止——错误套用 flat-NLI 超参(batch=1/grad_accum=16)，需用 CED 正确模板(batch=4/grad_accum=4)重跑，已由 r3 替代。\"}, \"rsft_ced_s43_train_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:09:34.266Z\", \"updated_at\": \"2026-05-16T00:25:38.818Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/rsft_filtered/rsft_train.jsonl\", \"data_count\": 2718, \"model_name\": \"Qwen3-4B + LoRA on SFT adapter\", \"seed\": 43, \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_ced_s43 --lr 2e-5 --epochs 3 --batch 1 --grad_accum 16 --lora_rank 64 --lora_alpha 128 --seed 43 --weighted_sampling\\\"\", \"pid\": 275269, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"N/A (training, not eval)\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s43_train_r2.log\", \"output_dir\": \"/root/autodl-tmp/rsft_output_ced_s43\", \"hyperparams\": {\"lr\": \"2e-5\", \"epochs\": 3, \"batch\": 1, \"grad_accum\": 16, \"lora_rank\": 64, \"lora_alpha\": 128, \"bf16\": true, \"weighted_sampling\": true}}, \"hypothesis\": \"CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"parent\": \"rsft_ced_s43_train\", \"reproduce\": {\"finished_at\": \"2026-05-16T00:20:20.177Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T00:20:24.299Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:20:28.707019+00:00\"}]}, \"notes\": \"Director 下令终止——错误套用 flat-NLI 超参(batch=1/grad_accum=16)，需用 CED 正确模板(batch=4/grad_accum=4)重跑，已由 r3 替代。实际 argparse 无 --batch/--grad_accum 参数，静默忽略后用了默认值(batch=4/grad_accum=4)，实际配置恰好正确，但命令不规范。\"}, \"reeval_rsft_topk3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:00:34.722Z\", \"updated_at\": \"2026-05-16T00:24:22.091Z\", \"hypothesis\": \"Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。\", \"parent\": \"plan_008_rsft_topk3\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_topk3_output/checkpoint-1509 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_topk3_reeval --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"268485\", \"log_path\": \"~/runs/faith-evidence-ie/reeval_rsft_topk3.log\", \"submitted_at\": \"2026-05-15T23:10:49.243Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"RSFT top_k=3 + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"rsft_topk3_output/checkpoint-1509\", \"eval_data\": \"docred dev\", \"wall_clock_seconds\": 3798.3, \"gpu_hours\": 1.06}, \"reproduce\": {\"finished_at\": \"2026-05-16T00:10:43.871Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:10:53.138391+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4454, \"rel_precision\": 0.4512, \"rel_recall\": 0.4398, \"ign_f1\": 0.4364, \"evi_f1\": 0.8088, \"edcr\": 0.6635, \"format_ok_rate\": 0.999, \"n_truncated\": 214, \"n_predictions\": 16020, \"inference_time_seconds\": 3546.4, \"ign_f1_corrected\": true}, \"conclusion\": \"negative\", \"notes\": \"RSFT top_k=3 rel_f1=0.4454，优于 SFT baseline (0.4057) 但劣于 CED RSFT top_k=1 (~0.46)。top_k=3 引入更多噪声训练样本，反而降低关系抽取精度。evi_f1=0.8088 较好。214/985 truncated。\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_topk3_output/checkpoint-1509\", \"completed_at\": \"2026-05-16T00:14:07.521Z\"}, \"rsft_ced_s43_train\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:05:46.635Z\", \"updated_at\": \"2026-05-16T00:10:42.131Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.rsft_trainer --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_ced_s43 --seed 43 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --wandb_run_name rsft_ced_s43 --bf16\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s43_train.log\", \"submitted_at\": \"2026-05-16T00:06:16.826Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 34.8, \"gpu_hours\": 0.01}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/rsft_ced_s43_train.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.rsft_trainer --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_ced_s43 --seed 43 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --wandb_run_name rsft_ced_s43 --bf16\\\"\", \"finished_at\": \"2026-05-16T00:06:49.264Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-16T00:06:51.674Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-16T00:06:55.376318+00:00\"}]}, \"notes\": \"失败原因: No module named freige.training.rsft_trainer — 命令 cd /root/autodl-tmp/freige 导致 cwd 错误。已修正为 cd /root/autodl-tmp，重提交为 rsft_ced_s43_train_r2 (PID=275264)\"}, \"rsft_ced_s45_train\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T00:03:17.851Z\", \"updated_at\": \"2026-05-16T00:05:24.862Z\", \"spec\": {\"hypothesis\": \"CED RSFT seed=45 训练，补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s43/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。\", \"plan_id\": \"plan_mvp2_rsft\", \"model_name\": \"Qwen3-4B + LoRA on SFT adapter\", \"data_path\": \"/root/autodl-tmp/rsft_filtered/rsft_train.jsonl\", \"data_count\": 2718, \"seed\": 45, \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\", \"kill_reason\": \"Director 重排优先级: CED s43 先于 s45, cuda:1 改分配给 rsft_ced_s43_train\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-16T00:05:24.862Z\"}, \"reeval_flat_nli_s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T22:00:33.691Z\", \"updated_at\": \"2026-05-15T23:59:33.440Z\", \"hypothesis\": \"Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。\", \"parent\": \"plan_001_flat_nli_seed43\", \"spec\": {\"command\": \"Re-eval flat-NLI RSFT seed=43 with --sft_adapter (D064 fix)\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"pid\": 266178, \"log_path\": \"/root/runs/faith-evidence-ie/reeval_flat_nli_s43.log\", \"submitted_at\": \"2026-05-15T22:57:10.223Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 0, \"model_name\": \"Qwen3-4B + SFT + flat-NLI RSFT s43\", \"seed\": 43, \"checkpoint_source\": \"plan_001_flat_nli_s43\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s43/checkpoint-507\", \"eval_output_dir\": \"/root/autodl-tmp/eval_results/rsft_flat_nli_s43_reeval\", \"sft_adapter\": \"/root/autodl-tmp/sft_output\", \"base_model\": \"/root/autodl-tmp/models/Qwen3-4B\", \"wall_clock_seconds\": 3743.2, \"gpu_hours\": 1.04}, \"reproduce\": {\"finished_at\": \"2026-05-15T23:56:41.649Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:56:45.572465+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4523, \"ign_f1\": 0.4523, \"evi_f1\": 0.8158, \"edcr\": 0.6505, \"num_preds\": 15357, \"format_ok\": \"984/985\", \"truncated\": \"211/985\", \"inference_time_s\": 3515.8}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T23:59:33.440Z\"}, \"plan_003_edcr_diagnostic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:12:40.174Z\", \"updated_at\": \"2026-05-15T23:52:05.506Z\", \"hypothesis\": \"EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。\", \"server\": \"rtx5090-4x\", \"gpu\": null, \"account\": \"root\", \"spec\": {\"gpu\": null, \"server\": \"rtx5090-4x\", \"notes\": \"CPU-only task, GPU allocation removed to free cuda:3\"}, \"conclusion\": \"success\", \"metrics\": {\"methods_evaluated\": 15, \"edcr_vs_rel_f1_spearman\": -0.9648, \"edcr_vs_rel_f1_pvalue\": 0.0001, \"edcr_vs_evi_f1_spearman\": 0.0022, \"edcr_vs_evi_f1_pvalue\": 0.9941, \"edcr_range\": \"0.63-0.99\", \"unique_diagnostic_value\": \"identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1\"}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/edcr_diagnostic.json\", \"log_path\": \"/root/autodl-tmp/eval_results/edcr_diagnostic.tex\", \"completed_at\": \"2026-05-15T23:45:26.064Z\"}, \"eval_flat_nli_seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:12:38.199Z\", \"updated_at\": \"2026-05-15T23:48:28.074Z\", \"hypothesis\": \"Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.\", \"parent\": \"plan_001_flat_nli_seed44\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s44/checkpoint-507 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 44 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s44 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"270056\", \"log_path\": \"~/runs/faith-evidence-ie/eval_flat_nli_seed44.log\", \"submitted_at\": \"2026-05-15T23:27:04.263Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 1283.8, \"gpu_hours\": 0.36}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T23:48:28.074Z\"}, \"eval_plan_012_dpo_1ep_fixed_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:58:52.440Z\", \"updated_at\": \"2026-05-15T23:44:56.586Z\", \"spec\": {\"command\": \"DPO 1ep re-eval with --sft_adapter (D064 fix)\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 262075, \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_012_dpo_1ep_fixed_r2.log\", \"submitted_at\": \"2026-05-15T21:58:52.150Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 0, \"model_name\": \"Qwen3-4B + SFT + DPO 1ep\", \"seed\": 42, \"checkpoint_source\": \"plan_012_dpo_ced_3ep\", \"eval_data\": \"docred_dev\", \"checkpoint_path\": \"/root/autodl-tmp/dpo_ced_output/checkpoint-167\", \"wall_clock_seconds\": 6197.9, \"gpu_hours\": 1.72}, \"reproduce\": {\"finished_at\": \"2026-05-15T23:36:34.758Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:36:37.754401+00:00\"}]}, \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.4034, \"evi_f1\": 0.8088, \"edcr\": 0.7139, \"format_ok_rate\": 0.999, \"truncated_rate\": 0.343, \"predictions\": 19107, \"ign_f1\": 0.4034, \"precision\": 0.3809, \"recall\": 0.4287, \"vs_sft_delta\": -0.0023, \"note\": \"DPO 1ep matches SFT baseline. 1ep→3ep trajectory shows gradual decoupling (rel_f1↓ evi_f1↑), consistent with GRPO pattern. Ign-F1=F1 exact match needs investigation.\"}, \"completed_at\": \"2026-05-15T23:42:10.085Z\"}, \"plan_001_flat_nli_seed44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:38:26.174Z\", \"updated_at\": \"2026-05-15T23:25:30.719Z\", \"spec\": {\"command\": \"rsft train flat_nli seed=44\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": 258503, \"log_path\": \"~/runs/faith-evidence-ie/plan_001_flat_nli_seed44.log\", \"submitted_at\": \"2026-05-15T21:38:25.857Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\", \"data_count\": 2691, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 44, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s44\", \"wall_clock_seconds\": 6424.9, \"gpu_hours\": 1.78}, \"reproduce\": {\"finished_at\": \"2026-05-15T23:22:24.600Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:22:27.640280+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6247, \"eval_loss\": 0.7564, \"eval_mean_token_accuracy\": 0.8299, \"task_eval_f1_ep1\": 0.4306, \"task_eval_f1_ep2\": 0.4884, \"task_eval_f1_ep3\": 0.4897, \"task_eval_evi_f1_ep3\": 0.78, \"task_eval_edcr_ep3\": 0.6596, \"task_eval_ign_f1_ep3\": 0.4897, \"train_runtime_sec\": 6197, \"num_epochs\": 3, \"total_steps\": 507}, \"completed_at\": \"2026-05-15T23:25:30.719Z\"}, \"plan_009_dynamics_figure\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T23:17:30.987Z\", \"updated_at\": \"2026-05-15T23:19:12.282Z\", \"hypothesis\": \"GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。\", \"conclusion\": \"success\", \"spec\": {\"command\": \"GRPO forgetting dynamics figure generation (CPU-only, matplotlib)\", \"server\": \"rtx5090-4x\", \"data_path\": \"W&B metrics + registry checkpoint data\", \"data_count\": 42, \"model_name\": \"N/A (visualization task)\", \"seed\": 0, \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/plan_009_grpo_forgetting/grpo_forgetting_dynamics_v5.pdf\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-15T23:19:12.282Z\"}, \"plan_001_flat_nli_seed45\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:09:05.195Z\", \"updated_at\": \"2026-05-15T23:17:29.971Z\", \"spec\": {\"command\": \"flat-NLI RSFT training seed=45\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"pid\": 257187, \"log_path\": \"~/runs/faith-evidence-ie/plan_001_flat_nli_seed45.log\", \"submitted_at\": \"2026-05-15T21:26:10.157Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\", \"data_count\": 0, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 45, \"wall_clock_seconds\": 6240.8, \"gpu_hours\": 1.73}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T21:26:08.091Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_flat_nli_s45 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 16 --lora_rank 64 --lora_alpha 128 --eval_data_dir /root/autodl-tmp/data/docred --wandb_run_name plan_001_flat_nli_seed45 --seed 45\\\"\", \"finished_at\": \"2026-05-15T23:07:49.718Z\", \"training_hours\": 1.69}, \"pid\": \"257187\", \"log_path\": \"~/runs/faith-evidence-ie/plan_001_flat_nli_seed45.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T23:07:54.004372+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"task_eval_rel_f1\": 0.4876, \"task_eval_evi_f1\": 0.7927, \"task_eval_edcr\": 0.6517, \"train_loss\": 0.6245, \"runtime_hours\": 1.69, \"note\": \"task-eval on 50 docs only, full dev eval needed\"}, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s45/checkpoint-507\", \"completed_at\": \"2026-05-15T23:10:11.004Z\"}, \"plan_011_bf16_g8_step_eval\": {\"status\": \"DONE\", \"retry_count\": 2, \"created_at\": \"2026-05-15T19:04:51.538Z\", \"updated_at\": \"2026-05-15T23:01:09.970Z\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && bash /root/autodl-tmp/freige/scripts/eval_plan_011_steps.sh\\\"\", \"finished_at\": \"2026-05-15T22:54:30.133Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"completed_at\": \"2026-05-15T19:47:17.272Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:47:19.581918+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:53:37.646506+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T22:54:32.686556+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"诊断确认：SIGTERM (EXIT_CODE=143)。device_map=\\\"auto\\\" 无 CUDA_VISIBLE_DEVICES 限制，模型加载到 GPU 0（plan_001 占用 16.3GB），双进程共 31.4/32.6GB 后被 kill。两次重试均失败（retry_count=2）。修复：CUDA_VISIBLE_DEVICES=1 重提交到空闲 cuda:1。\"}}, \"notes\": \"诊断确认：SIGTERM (EXIT_CODE=143)。device_map=\\\"auto\\\" 无 CUDA_VISIBLE_DEVICES 限制，模型加载到 GPU 0（plan_001 占用 16.3GB），双进程共 31.4/32.6GB 后被 kill。两次重试均失败（retry_count=2）。修复：CUDA_VISIBLE_DEVICES=1 重提交到空闲 cuda:1。\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_ced_g8_bf16_step30/ + step50/ + step70/\", \"log_path\": \"~/runs/faith-evidence-ie/plan_011_bf16_g8_step_eval.log\"}, \"conclusion\": \"success\", \"metrics\": {\"step_30\": {\"rel_f1\": 0.434, \"evi_f1\": 0.8063, \"edcr\": 0.6807}, \"step_50\": {\"rel_f1\": 0.4276, \"evi_f1\": 0.8024, \"edcr\": 0.6855}, \"step_70\": {\"rel_f1\": 0.4341, \"evi_f1\": 0.8099, \"edcr\": 0.6685}, \"best_step\": \"step_70\", \"trend\": \"non-monotonic, all < ckpt-100 (0.4549)\"}, \"checkpoint_path\": \"N/A (eval-only, source checkpoints at /root/autodl-tmp/grpo_bf16_g8_output/checkpoint-{30,50,70})\"}, \"plan_011_eval_g8_bf16_ckpt100\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:43:24.143Z\", \"updated_at\": \"2026-05-15T22:06:28.981Z\", \"spec\": {\"command\": \"STALE - killed\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"215276\", \"log_path\": \"~/runs/faith-evidence-ie/plan_011_eval_g8_bf16_ckpt100.log\", \"submitted_at\": \"2026-05-15T14:43:23.832Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"grpo_g8_bf16 ckpt100\", \"seed\": 42, \"checkpoint_source\": \"grpo_ced_g8_bf16\", \"eval_data\": \"docred dev\", \"wall_clock_seconds\": 26585.1, \"gpu_hours\": 7.38}, \"conclusion\": \"killed\", \"notes\": \"STALE: 该 eval 已由 eval_grpo_g8_bf16 完成并 success (rel_f1=0.4549)。此条目为残留，不需要执行。\", \"completed_at\": \"2026-05-15T22:06:28.981Z\"}, \"mvp2_eval_rsft_s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:35:23.934Z\", \"updated_at\": \"2026-05-15T22:06:28.059Z\", \"hypothesis\": \"Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).\", \"parent\": \"mvp2_rsft_train_r1_s44\", \"conclusion\": \"killed\", \"notes\": \"STALE: s44 全量 eval 已由 mvp2_eval_rsft_r2b_maxtok1536 等系列完成。s44 rel_f1=0.4655 已入库。此条目为残留。\", \"spec\": {\"command\": \"STALE - killed\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"261617\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_s44.log\", \"submitted_at\": \"2026-05-15T21:57:22.401Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"RSFT s44\", \"seed\": 44, \"checkpoint_source\": \"rsft_output_s44\", \"eval_data\": \"docred dev\", \"wall_clock_seconds\": 545.7, \"gpu_hours\": 0.15}, \"completed_at\": \"2026-05-15T22:06:28.059Z\"}, \"eval_plan_008_topk3_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T21:52:00.000Z\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:39:34.632Z\", \"updated_at\": \"2026-05-15T21:39:34.632Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_topk3_output --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_topk3_fixed --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"259032\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_008_topk3_fixed.log\", \"submitted_at\": \"2026-05-15T21:39:34.183Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_plan_012_dpo_1ep_fixed\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T21:52:00.000Z\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:39:31.570Z\", \"updated_at\": \"2026-05-15T21:39:31.570Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/dpo_output_1ep/ --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/dpo_ced_1ep_fixed --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"258955\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_012_dpo_1ep_fixed.log\", \"submitted_at\": \"2026-05-15T21:39:31.197Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}}, \"eval_plan_008_rsft_topk3\": {\"status\": \"DONE\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T21:38:00.000Z\", \"retry_count\": 0, \"created_at\": \"2026-05-15T21:09:51.464Z\", \"updated_at\": \"2026-05-15T21:38:00.000Z\", \"metrics\": {\"note\": \"INVALID — missing --sft_adapter, killed by Director instruction\"}, \"hypothesis\": \"RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。\", \"parent\": \"plan_008_rsft_topk3\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_topk3_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_topk3 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"255523\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_008_rsft_topk3.log\", \"submitted_at\": \"2026-05-15T21:10:11Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"RSFT top_k=3 dev eval: 对比 top_k=5 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1=0.4106)。top_k=3 训练 50-doc subset 显示 F1=0.50 但 Evi-F1 下降到 0.68。\", \"parent\": \"plan_008_rsft_topk3\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT top_k=3\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_topk3_output\", \"eval_data\": \"docred-dev (985 docs)\"}}, \"plan_012_dpo_ced\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:54:03.324Z\", \"updated_at\": \"2026-05-15T21:37:44.232Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/dpo_output\", \"data_path\": \"/root/autodl-tmp/dpo_data/dpo_pairs.jsonl\", \"data_count\": 2666, \"model_name\": \"Qwen3-4B + SFT + CED-DPO\", \"seed\": 42, \"beta\": 0.1, \"num_epochs\": 3, \"loss_type\": \"sigmoid\", \"base_model\": \"/root/autodl-tmp/models/Qwen3-4B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output\", \"pairs\": 2666}, \"hypothesis\": \"DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。\", \"reproduce\": {\"finished_at\": \"2026-05-15T17:38:15.433Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:38:17.857458+00:00\"}]}, \"conclusion\": \"negative\", \"notes\": \"⚠️ Reviewer WARNING: 严重过拟合。3 epochs, rewards accuracy=1.0, margins 9x 膨胀, entropy 崩塌。checkpoint-501 是最过拟合版本，结果有 confound。需补 eval checkpoint-400 对比 + 重训 epochs=1。\", \"metrics\": {\"rel_f1\": 0.3429, \"evi_f1\": 0.8403, \"edcr\": 0.7294, \"format_ok_rate\": 0.995, \"checkpoint\": \"checkpoint-501\", \"rewards_accuracy\": 1, \"margins\": 9.01}, \"log_path\": \"~/runs/faith-evidence-ie/plan_012_dpo_ced.log\", \"completed_at\": \"2026-05-15T21:37:44.232Z\"}, \"plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:50:44.852Z\", \"updated_at\": \"2026-05-15T21:36:34.720Z\", \"spec\": {\"hypothesis\": \"DPO+CED 1-epoch 重训：修复 3-epoch 过拟合问题。epochs=1 (~167 steps, <10min)，其余超参不变（β=0.1, lr=5e-7, loss=sigmoid, seed=42, pairs=2666）。让 DPO 数据点可用于论文。\", \"parent\": \"plan_012_dpo_ced\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 WANDB_PROJECT=freige-dpo PYTHONUNBUFFERED=1 python -m freige.training.dpo_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --dpo_data_path /root/autodl-tmp/dpo_data/dpo_pairs.jsonl --output_dir /root/autodl-tmp/dpo_output_1ep --beta 0.1 --num_epochs 1 --seed 42 --loss_type sigmoid --per_device_batch_size 1 --gradient_accumulation_steps 16 --wandb_run_name plan_012_dpo_ced_1ep\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"245103\", \"log_path\": \"~/runs/faith-evidence-ie/plan_012_dpo_ced_1ep.log\", \"submitted_at\": \"2026-05-15T19:43:02.707Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/dpo_data/dpo_pairs.jsonl\", \"data_count\": 2666, \"model_name\": \"Qwen3-4B + SFT + CED-DPO (1ep)\", \"seed\": 42, \"base_model\": \"/root/autodl-tmp/models/Qwen3-4B\", \"sft_adapter\": \"/root/autodl-tmp/sft_output\", \"beta\": 0.1, \"num_epochs\": 1, \"loss_type\": \"sigmoid\", \"checkpoint_path\": \"/root/autodl-tmp/dpo_output_1ep\", \"wall_clock_seconds\": 6812.0, \"gpu_hours\": 1.89}, \"gpu_ids\": [3], \"hypothesis\": \"DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"notes\": \"DPO+CED 完全失败。1ep eval: rel_f1=0.0022 (34 TPs / 19265 preds)，比 3ep (0.3429) 更差。训练指标正常 (accuracy=0.82, margins=0.86)，但模型输出几乎无法匹配正确 relation。evi_f1=0.75 说明模型仍生成 evidence，但 relation extraction 崩溃。358/985 truncated (36%)。DPO 对 evidence-grounded DocRE 完全不适用——不是过拟合问题，是方法本身失效。D061 已关闭 DPO 实验线。\", \"reproduce\": {\"finished_at\": \"2026-05-15T20:17:44.285Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:17:46.894275+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.0022, \"evi_f1\": 0.75, \"edcr\": 0.9982, \"format_ok\": \"981/985\", \"truncated\": \"358/985\", \"tp\": 34, \"n_preds\": 19265, \"inference_time_s\": 3643, \"train_loss_final\": 0.59, \"rewards_accuracy\": 0.82, \"rewards_margins\": 0.86, \"total_steps\": 167, \"training_time_min\": 33}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T21:36:34.720Z\"}, \"eval_plan_001_flat_nli_s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:29:54.486Z\", \"updated_at\": \"2026-05-15T21:35:00.000Z\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T21:34:00.000Z\", \"metrics\": {\"rel_f1\": 0.0022, \"ign_f1\": 0.0022, \"evi_f1\": 0.8533, \"edcr\": 0.9982, \"num_preds\": 17285, \"format_ok\": \"981/985\", \"truncated\": \"251/985\", \"tp\": 32, \"note\": \"INVALID — missing --sft_adapter, same bug as DPO 1ep eval\"}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli_s43 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 43 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli_s43 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"252179\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_001_flat_nli_s43.log\", \"submitted_at\": \"2026-05-15T20:30:26.563Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + flat-NLI RSFT s43 adapter\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_flat_nli_s43\", \"eval_data\": \"docred dev (985 docs)\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:33:03.903Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:33:07.578617+00:00\"}]}}, \"eval_plan_012_dpo_ced_1ep\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T20:22:11.752Z\", \"updated_at\": \"2026-05-15T21:27:30.000Z\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-15T21:25:00.000Z\", \"metrics\": {\"rel_f1\": 0.0022, \"ign_f1\": 0.0022, \"evi_f1\": 0.75, \"edcr\": 0.9982, \"num_preds\": 19265, \"format_ok\": \"981/985\", \"truncated\": \"358/985\", \"tp\": 34, \"inference_time_s\": 3643}, \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/dpo_output_1ep/ --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/dpo_ced_1ep --no-quantize\", \"server\": \"rtx5090-4x\", \"data_path\": \"docred-dev\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + DPO-CED-1ep LoRA\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/dpo_output_1ep/ (final, 167 steps = 1 epoch)\", \"eval_data\": \"docred-dev\", \"gpu_id\": 2, \"parent\": \"plan_012_dpo_ced_1ep\", \"hypothesis\": \"DPO+CED 1ep checkpoint dev set evaluation: 验证 1ep 是否消除 3ep 过拟合 (rewards_acc=1.0, margins=9x), 对比 SFT baseline rel_f1=0.4057\"}}, \"plan_008_rsft_topk3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:01:33.773Z\", \"updated_at\": \"2026-05-15T21:11:35.509Z\", \"spec\": {\"command\": \"python -m freige.train.rsft_train --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/rsft_filtered_topk3/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_topk3_output\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"234489\", \"log_path\": \"/root/runs/faith-evidence-ie/plan_008_rsft_topk3.log\", \"submitted_at\": \"2026-05-15T18:03:03.593Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_filtered_topk3/rsft_train.jsonl\", \"data_count\": 8037, \"model_name\": \"Qwen3-4B + SFT adapter + RSFT top_k=3\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/rsft_topk3_output\", \"wall_clock_seconds\": 11199.8, \"gpu_hours\": 3.11}, \"reproduce\": {\"finished_at\": \"2026-05-15T21:06:30.938Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T21:06:37.059207+00:00\"}]}, \"hypothesis\": \"RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。\", \"metrics\": {\"train_loss\": 0.5543, \"eval_loss\": 0.8297, \"eval_mean_token_accuracy\": 0.8228, \"eval_entropy\": 0.6001, \"train_runtime_sec\": 10916, \"total_steps\": 1509, \"epochs\": 3, \"trainable_params_pct\": 3.18, \"rsft_samples\": 8037, \"ced_score_mean\": 0.621, \"task_eval_f1_ep1\": 0.4848, \"task_eval_f1_ep2\": 0.4824, \"task_eval_f1_ep3\": 0.5012, \"task_eval_evi_f1_ep1\": 0.745, \"task_eval_evi_f1_ep2\": 0.6997, \"task_eval_evi_f1_ep3\": 0.6816, \"task_eval_edcr_ep1\": 0.6525, \"task_eval_edcr_ep2\": 0.6529, \"task_eval_edcr_ep3\": 0.5963, \"task_eval_note\": \"50-doc subset, not full dev\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T21:09:43.432Z\", \"notes\": \"RSFT top_k=3 训练正常完成。3 epochs, 1509 steps, 3h02m。8037 RSFT 样本 (CED mean=0.621)。Task eval (50-doc subset): F1 从 ep1=0.4848 升至 ep3=0.5012，但 Evi-F1 从 0.745 降至 0.6816，EDCR 从 0.6525 降至 0.5963，呈现 relation extraction 提升但证据质量下降的 trade-off。与 CED RSFT top_k=5 baseline (rel_f1=0.4596) 相比，subset F1=0.5012 看起来更高，但需 full dev eval 确认。无 W&B run。下一步：提交 eval_plan_008_rsft_topk3 做 full dev eval。\"}, \"plan_001_flat_nli_seed43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:22:55.521Z\", \"updated_at\": \"2026-05-15T20:35:05.452Z\", \"spec\": {\"hypothesis\": \"flat-NLI RSFT seed=43 补跑。验证 seed=42 的 rel_f1=0.4539 是否在噪声范围内（CED RSFT 3-seed mean=0.4596, σ=0.0127）。\", \"parent\": \"plan_001_rsft_flat_nli\", \"command\": \"python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_flat_nli_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 16 --lora_rank 64 --lora_alpha 128 --eval_data_dir /root/autodl-tmp/data/docred --wandb_run_name plan_001_flat_nli_seed43 --seed 43\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"data_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\", \"data_count\": 2691, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 43, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"N/A (training)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s43\", \"log_path\": \"~/runs/faith-evidence-ie/plan_001_flat_nli_seed43.log\", \"pid\": \"236774\", \"submitted_at\": \"2026-05-15T18:22:00Z\", \"submitted_via\": \"worker_direct\", \"backend\": \"nohup\", \"wall_clock_seconds\": 7600.2, \"gpu_hours\": 2.11}, \"reproduce\": {\"finished_at\": \"2026-05-15T20:20:10.574Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T20:20:13.016730+00:00\"}]}, \"metrics\": {\"train_loss_final\": 0.6257, \"train_loss_min\": 0.5895, \"eval_loss_epoch3\": 0.7567, \"eval_accuracy_epoch3\": 0.8298, \"total_steps\": 507, \"epochs\": 3, \"train_runtime_seconds\": 6880, \"task_eval_f1_ep1\": 0.4825, \"task_eval_f1_ep2\": 0.4542, \"task_eval_f1_ep3\": 0.4866, \"task_eval_evi_f1_ep3\": 0.7834, \"task_eval_edcr_ep3\": 0.6402, \"task_eval_note\": \"50-doc subset, not full dev\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli_s43\", \"log_path\": \"~/runs/faith-evidence-ie/plan_001_flat_nli_seed43.log\", \"completed_at\": \"2026-05-15T20:28:40.191Z\", \"notes\": \"训练正常完成 (EXIT_CODE=0)。507 steps, 3 epochs, eval_loss 三 epoch 持平 (0.753-0.757) 无过拟合。与 seed42 高度一致 (train_loss 0.6248 vs 0.6238, accuracy ~0.855 vs 0.853)。Checkpoint: /root/autodl-tmp/rsft_output_flat_nli_s43/checkpoint-507。下一步: dev eval 提取 rel_f1/evi_f1。\"}, \"plan_009_flatnli_reward_eval_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:54:58.033Z\", \"updated_at\": \"2026-05-15T20:32:33.464Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_flatnli_r3 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_flatnli_r3 --no-quantize --max_new_tokens 1024\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"246974\", \"log_path\": \"~/runs/faith-evidence-ie/plan_009_flatnli_reward_eval.log\", \"submitted_at\": \"2026-05-16T03:54:00Z\", \"submitted_via\": \"ssh_execute+tmux\", \"backend\": \"tmux\", \"tmux_session\": \"plan_009_flatnli_reward_eval\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + QLoRA GRPO (flatNLI reward)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_flatnli_r3 (checkpoints 20,40,60,80,100)\", \"eval_data\": \"docred dev (985 docs, 12275 triples)\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_flatnli_r3\", \"parent\": \"plan_009_flatnli_reward_eval\", \"notes\": \"Retry. Batch eval 5 flatNLI-reward GRPO checkpoints (step 20-100) for forgetting dynamics figure.\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T20:32:29.383Z\", \"notes\": \"OOM 失败。--no-quantize + batch_size 16 + max_new_tokens 1024 在单卡 RTX 5090 (32GB) 上 OOM。全部 5 个 checkpoint (20-100) 均未完成 eval。checkpoint-20 仅完成 1/62 batches 即被 kill (-9)。修复方案：降 batch_size 至 4 或 2 后重提交。\"}, \"plan_009_extract_reward_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:04:55.707Z\", \"updated_at\": \"2026-05-15T19:58:37.870Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 bash /root/autodl-tmp/freige/scripts/eval_extract_reward_steps.sh\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"247778\", \"log_path\": \"~/runs/faith-evidence-ie/plan_009_extract_reward_eval.log\", \"submitted_at\": \"2026-05-15T19:55:11.304Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T19:06:27.578Z\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:54:17.758Z\", \"notes\": \"OOM: Worker 提交到了 GPU 0（被 plan_001 占用 16 GiB），而非目标 cuda:1。需在 cuda:0 释放后重提交。\"}, \"eval_sft_baseline_noquant\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:38:33.128Z\", \"updated_at\": \"2026-05-15T19:45:42.147Z\", \"spec\": {\"command\": \"python eval.py --model_path /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/sft_baseline_noquant --batch_size 16 --max_new_tokens 1024 --split dev --seed 42\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"237912\", \"log_path\": \"~/runs/faith-evidence-ie/eval_sft_baseline_noquant.log\", \"submitted_at\": \"2026-05-15T18:38:45.042Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT LoRA (no quantization)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"docred/dev (985 docs, 12275 triples)\", \"wall_clock_seconds\": 3916.2, \"gpu_hours\": 1.09, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/sft_baseline_noquant/\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T19:41:54.062Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:41:59.716746+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4106, \"rel_precision\": 0.4198, \"rel_recall\": 0.4019, \"evi_f1\": 0.8013, \"evi_precision\": 0.8005, \"evi_recall\": 0.8022, \"evi_f1_joint\": 0.3216, \"edcr\": 0.7039, \"format_ok_rate\": 0.998, \"field_compliance_rate\": 0.7066, \"n_predictions\": 16774, \"n_truncated\": 288, \"n_documents\": 985, \"inference_time_seconds\": 3677.9}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/sft_baseline_noquant/metrics.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:44:01.274Z\", \"notes\": \"[2026-05-16] 无量化 SFT baseline eval 完成。rel_f1=0.4106 vs 量化版 0.4057 (+0.49pp), evi_f1=0.8013 vs 0.7979 (+0.34pp)。差异 <1pp，确认量化 confound 不显著（D058 排除）。所有基于量化 baseline 的对比结论仍然成立。无量化版推理时间 3678s vs 量化版 6139s（快 40%，因无量化用满 GPU 内存）。\"}, \"plan_009_flatnli_reward_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:04:57.991Z\", \"updated_at\": \"2026-05-15T19:39:02.187Z\", \"spec\": {\"hypothesis\": \"FlatNLI reward GRPO checkpoint eval。用已有 checkpoint 补充 forgetting dynamics 图的 flatNLI reward 变体数据，实现三种 reward 对比。\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + QLoRA GRPO (flatNLI reward)\", \"seed\": 42, \"eval_data\": \"docred dev (985 docs)\", \"checkpoint_source\": \"grpo_flatnli_r3/r4/r5/r6 checkpoints\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T19:06:33.944Z\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:39:02.187Z\"}, \"eval_plan_012_dpo_ced_ckpt400\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:32:55.398Z\", \"updated_at\": \"2026-05-15T19:37:31.477Z\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/dpo_output/checkpoint-400 --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/dpo_ced_ckpt400 --no-quantize\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"pid\": 242796, \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_012_dpo_ced_ckpt400.log\", \"submitted_at\": \"2026-05-15T19:32:55.107Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + DPO-CED LoRA (checkpoint-400)\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/dpo_output/checkpoint-400\", \"eval_data\": \"docred-dev\", \"log_file\": \"~/runs/faith-evidence-ie/eval_plan_012_dpo_ced_ckpt400.log\", \"parent\": \"plan_012_dpo_ced\", \"wall_clock_seconds\": 248.7, \"gpu_hours\": 0.07}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:37:03.842Z\", \"notes\": \"OOM: cuda:3 被 plan_008 占用 19.6 GiB，仅完成 15% batch，结果不可信。需在 cuda:2 重跑。\"}, \"plan_009_forgetting_figure\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:56:56.840Z\", \"updated_at\": \"2026-05-15T18:57:17.531Z\", \"spec\": {\"hypothesis\": \"GRPO forgetting dynamics 可视化：整理 QLoRA vs bf16 GRPO 训练轨迹，绘制论文核心 figure。\", \"server\": \"rtx5090-4x\", \"command\": \"python /root/autodl-tmp/freige/scripts/plot_forgetting_dynamics.py\", \"data_path\": \"trainer_state.json + registry eval metrics\", \"data_count\": 0, \"model_name\": \"N/A (visualization)\", \"seed\": 0, \"checkpoint_path\": \"/root/autodl-tmp/freige/figures/\", \"log_path\": \"N/A\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:57:10.563Z\", \"notes\": \"3-panel figure: (a) Training Reward—bf16 1.5-3.0 vs QLoRA 0.1-1.2; (b) Rel-F1—QLoRA暴跌至0.01(lr5e-6)/0.22(lr5e-5), bf16稳定0.45+; (c) Evi-F1—QLoRA lr5e-6反升至0.85, bf16稳定0.81。Artifacts: art_20260515_eace0b (PNG), art_20260515_319233 (PDF)。\"}, \"eval_plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:20:25.574Z\", \"updated_at\": \"2026-05-15T18:42:46.665Z\", \"spec\": {\"checkpoint_path\": \"/root/autodl-tmp/eval_results/sft_no_evidence\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_014_sft_no_evidence.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T18:29:34.790Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:29:37.278008+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4893, \"rel_ign_f1\": 0.4893, \"rel_precision\": 0.4884, \"rel_recall\": 0.4902, \"evi_f1\": 0, \"evi_precision\": 0, \"evi_recall\": 0, \"edcr\": 0, \"format_ok_rate\": 0.9919, \"n_truncated\": 298, \"n_predictions\": 21064, \"n_documents\": 985, \"n_parseable\": 977, \"inference_time_seconds\": 4103.8}, \"conclusion\": \"success\", \"notes\": \"No-evidence SFT rel_f1=0.4893 vs baseline with-evidence rel_f1=0.4057 (+0.0836, +20.6%). Evidence generation significantly hurts relation extraction. evi_f1=0 as expected. Format compliance 99.2%. 298/985 truncated. Inference 4103.8s.\", \"completed_at\": \"2026-05-15T18:42:46.665Z\"}, \"plan_014_sft_no_evidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:55:43.710Z\", \"updated_at\": \"2026-05-15T18:42:28.216Z\", \"hypothesis\": \"SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=1 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.sft_trainer --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_no_evidence_output --no_evidence --wandb_run_name plan_014_sft_no_evidence --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"222207\", \"log_path\": \"~/runs/faith-evidence-ie/plan_014_sft_no_evidence.log\", \"submitted_at\": \"2026-05-15T15:56:13Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"Qwen3-4B (QLoRA 4-bit)\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/sft_no_evidence_output\", \"wall_clock_seconds\": 9975.2, \"gpu_hours\": 2.77}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:01:44.197Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:01:46.586830+00:00\"}]}, \"metrics\": {\"train_loss\": 0.7077, \"eval_loss\": 0.8781, \"eval_token_accuracy\": 0.8086, \"epochs\": 3, \"total_steps\": 570, \"train_runtime_min\": 64, \"samples\": 3027, \"trainable_params\": \"132M/4.15B (3.18%)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T18:42:28.216Z\"}, \"plan_002_test_eval_s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:05:47.701Z\", \"updated_at\": \"2026-05-15T18:20:17.405Z\", \"spec\": {\"hypothesis\": \"RSFT s44 checkpoint on DocRED test set should achieve similar or better performance than dev set results, validating generalization of the faithfulness-evidence approach.\", \"task_type\": \"eval\", \"eval_data\": \"docred_test\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 1000, \"model_name\": \"Qwen3-4B + SFT + RSFT-s44\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_s44\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s44 --sft_adapter /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split test --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/test_rsft_s44 --no-quantize\", \"log_path\": \"/root/autodl-tmp/eval_results/test_rsft_s44.log\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/test_rsft_s44\", \"tmux_session\": \"plan_002_test_eval_s44\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T18:20:14.596Z\", \"notes\": \"DocRED test split 无 gold labels，inference.py 不支持 enumerate_all_pairs 模式。推迟到论文终稿阶段（需改造 inference.py + CodaLab submission）。Director 指令标记 failed。\"}, \"plan_001_rsft_flat_nli\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:01.021Z\", \"updated_at\": \"2026-05-15T18:04:14.547Z\", \"hypothesis\": \"flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。\", \"parent\": \"plan_001_flat_nli_scoring\", \"spec\": {\"gpu\": [\"cuda:0\"], \"command\": \"python rsft_train.py (flat-NLI scoring)\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\", \"data_count\": 2691, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": null, \"pid\": \"219556\", \"log_path\": \"/root/runs/faith-evidence-ie/plan_001_rsft_flat_nli.log\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"N/A (training, not eval)\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_flat_nli/\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T16:30:34.306Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T16:30:42.223143+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.6238, \"train_loss_min\": 0.5803, \"mean_token_accuracy\": 0.8528, \"train_runtime_sec\": 2946, \"epochs\": 3, \"total_steps\": 507, \"samples\": 2691}, \"completed_at\": \"2026-05-15T18:04:14.547Z\"}, \"eval_plan_001_flat_nli\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:57:09.693Z\", \"updated_at\": \"2026-05-15T18:04:13.598Z\", \"hypothesis\": \"Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。\", \"parent\": \"plan_001_rsft_flat_nli\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_flat_nli --sft_adapter /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_flat_nli --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"228508\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_001_flat_nli.log\", \"submitted_at\": \"2026-05-15T16:57:46.175Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT-flat-NLI\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_flat_nli\", \"eval_data\": \"docred dev (985 docs)\", \"wall_clock_seconds\": 3987.4, \"gpu_hours\": 1.11}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:58:40.529Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:58:48.797356+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4539, \"ign_f1\": 0.4539, \"evi_f1\": 0.8043, \"edcr\": 0.6431, \"precision\": 0.4671, \"recall\": 0.4414, \"evi_precision\": 0.8143, \"evi_recall\": 0.7945, \"format_ok_rate\": 1, \"n_truncated\": 199, \"n_documents\": 985, \"n_predictions\": 15294, \"inference_time_seconds\": 3631}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/rsft_flat_nli\", \"log_path\": \"~/runs/faith-evidence-ie/eval_plan_001_flat_nli.log\", \"conclusion\": \"success\", \"notes\": \"flat-NLI RSFT dev eval 完成 (985 docs, EXIT_CODE=0)。rel_f1=0.4539, evi_f1=0.8043, edcr=0.6431。与 CED RSFT 3-seed mean 对比: rel_f1 -0.57pp (0.4539 vs 0.4596), evi_f1 -1.00pp (0.8043 vs 0.8143), edcr 差异极小。flat-NLI 接近但略低于 CED，差异在 CED 3-seed 标准差范围内 (σ=0.0127)。注意此为 single seed (42)，与 CED seed=42 的 0.4449 比反而高 +0.90pp。结论：CED contrastive margin 相对 flat p_pos 的增益极小（<1pp rel_f1），不构成显著优势。论文 claim 应聚焦 CED 的其他价值（reranker、GRPO reward）而非 RSFT filtering 的 contrastive margin。199/985 truncated（高于 CED 的 ~170），format 100% OK。\", \"completed_at\": \"2026-05-15T18:04:13.598Z\"}, \"eval_grpo_g8_bf16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:41:07.474Z\", \"updated_at\": \"2026-05-15T17:57:46.573Z\", \"spec\": {\"command\": \"python -m freige.eval.batch_eval --exp_dir grpo_ced_g8_bf16 --sft_adapter sft_output --checkpoints 80,90,100 --no-quantize --max_new_tokens 1024\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"214552\", \"log_path\": \"~/runs/faith-evidence-ie/eval_grpo_g8_bf16.log\", \"submitted_at\": \"2026-05-15T14:41:06.626Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO-G8-bf16\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_g8_bf16\", \"eval_data\": \"docred dev (985 docs)\", \"parent\": \"plan_011_grpo_g8_bf16\", \"wall_clock_seconds\": 11785.0, \"gpu_hours\": 3.27}, \"hypothesis\": \"Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).\", \"metrics\": {\"ckpt80_rel_f1\": 0.4456, \"ckpt80_ign_f1\": 0.4456, \"ckpt80_evi_f1\": 0.8034, \"ckpt80_edcr\": 0.6409, \"ckpt80_format_ok\": \"984/985\", \"ckpt80_truncated\": 50, \"ckpt90_rel_f1\": 0.4523, \"ckpt90_ign_f1\": 0.4523, \"ckpt90_evi_f1\": 0.8052, \"ckpt90_edcr\": 0.6414, \"ckpt90_format_ok\": \"983/985\", \"ckpt90_truncated\": 61, \"ckpt100_rel_f1\": 0.4549, \"ckpt100_ign_f1\": 0.4549, \"ckpt100_evi_f1\": 0.8086, \"ckpt100_edcr\": 0.6318, \"ckpt100_format_ok\": \"985/985\", \"ckpt100_truncated\": 61, \"best_checkpoint\": \"ckpt-100\"}, \"reproduce\": {\"finished_at\": \"2026-05-15T17:55:03.372Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T17:55:12.125002+00:00\"}]}, \"conclusion\": \"success\", \"notes\": \"3 checkpoints 全部评测完成。rel_f1 单调递增 (0.4456→0.4523→0.4549)，evi_f1 同步上升 (0.8034→0.8052→0.8086)。全部 checkpoint 均大幅超过 SFT baseline (0.4057) 和 QLoRA GRPO (0.2167 catastrophic forgetting)。bf16 LoRA GRPO 无 forgetting，且持续改善至 step 100。Best checkpoint: 100 (rel_f1=0.4549, +12.1% over SFT).\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_g8_bf16\", \"completed_at\": \"2026-05-15T17:57:31.658Z\"}, \"plan_015_grpo_g4_bf16_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T16:27:09.496Z\", \"updated_at\": \"2026-05-15T16:54:54.376Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_g4_bf16_kl001 --num_generations 4 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-6 --seed 42 --kl_coef 0.01 --save_steps 20 --save_total_limit 20 --max_steps 200 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --no-quantize --wandb_run_name plan_015_grpo_g4_bf16_v3\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"226476\", \"log_path\": \"~/runs/faith-evidence-ie/plan_015_grpo_g4_bf16_v3.log\", \"submitted_at\": \"2026-05-15T16:32:42.980Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"N/A (training)\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_g4_bf16_kl001\", \"notes\": \"D052: plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean ablation。v3 取消，cuda:0 腾给 plan_001 eval。\", \"wall_clock_seconds\": 1331.4, \"gpu_hours\": 0.37}, \"notes\": \"Robustness check, 非 single-variable ablation。lr=5e-6 与对照组 (mvp2_grpo_ced_kl001_r4, lr=5e-5) 不一致。D052 确认 plan_011 (bf16 G=8 kl=0.01 lr=5e-5) vs mvp2_grpo_ced_kl001_r4 (QLoRA G=8 kl=0.01 lr=5e-5) 才是 clean ablation。v3 仅作为额外 robustness data point。\", \"hypothesis\": \"P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T16:54:54.376Z\"}, \"plan_015_grpo_g4_bf16_v2\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T16:06:43.308Z\", \"updated_at\": \"2026-05-15T16:54:42.310Z\", \"hypothesis\": \"Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。\", \"parent\": \"plan_011_grpo_g8_bf16\", \"completed_at\": \"2026-05-15T16:25:20.634Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"killed\"}}, \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --model_name Qwen3-4B --sft_adapter sft_output --data_dir data/docred --output_dir grpo_g4_bf16_control --stage 3 --num_generations 4 --kl_coef 0 --learning_rate 5e-6 --max_steps 100 --no-quantize --wandb_run_name plan_015_grpo_g4_bf16_v2\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"222942\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"notes\": \"kl_coef=0 配置错误最终确认 kill。Director 指令以 plan_015_v3 (kl=0.01) 替代。\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"N/A (training)\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_g4_bf16_control\", \"log_path\": \"~/runs/faith-evidence-ie/plan_015_grpo_g4_bf16_v2.log\"}, \"conclusion\": \"killed\"}, \"plan_015_grpo_g4_bf16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:58:43.784Z\", \"updated_at\": \"2026-05-15T16:03:08.279Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --model_name Qwen3-4B --sft_adapter sft_output --data_dir data/docred --output_dir grpo_ced_g4_bf16 --stage 3 --num_generations 4 --kl_coef 0 --learning_rate 5e-5 --max_steps 100 --no-quantize --wandb_run_name plan_015_grpo_g4_bf16\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"222937\", \"log_path\": \"~/runs/faith-evidence-ie/plan_015_grpo_g4_bf16.log\", \"submitted_at\": \"2026-05-15T15:58:43.532Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 264.7, \"gpu_hours\": 0.07}, \"hypothesis\": \"bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。\", \"conclusion\": \"killed\", \"notes\": \"cuda:0 冲突，与 plan_001_rsft_flat_nli (PID 219556) 冲突。plan_001 先到先得，plan_015 被终止。待 plan_001 完成后重新提交 plan_015。\", \"completed_at\": \"2026-05-15T16:03:08.279Z\"}, \"plan_011_grpo_g8_bf16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:59:50.014Z\", \"updated_at\": \"2026-05-15T15:55:53.725Z\", \"hypothesis\": \"GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3\", \"spec\": {\"command\": \"bash -c \\\"cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=3 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 /root/miniconda3/bin/python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/grpo_ced_g8_bf16 --stage 3 --num_generations 8 --kl_coef 0.01 --learning_rate 5e-5 --max_steps 100 --save_steps 10 --save_total_limit 10 --per_device_batch_size 1 --gradient_accumulation_steps 1 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --no-quantize --wandb_run_name plan_011_grpo_g8_bf16\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"210099\", \"log_path\": \"~/runs/faith-evidence-ie/plan_011_grpo_g8_bf16.log\", \"submitted_at\": \"2026-05-15T14:00:10.122Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6943.6, \"gpu_hours\": 1.93}, \"log_path\": \"/root/runs/faith-evidence-ie/plan_011_grpo_g8_bf16.log\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_g8_bf16\", \"reproduce\": {\"finished_at\": \"2026-05-15T14:35:19.476Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T14:35:23.573303+00:00\"}]}, \"metrics\": {\"final_step\": 100, \"train_runtime_s\": 554, \"reward_final\": 1.795, \"f1_reward_final\": 1.002, \"ced_reward_final\": 0.494, \"format_reward_final\": 0.3, \"frac_zero_std_final\": 0, \"kl_final\": 0.022, \"best_reward_step\": 85, \"best_reward\": 2.858, \"best_f1_reward\": 1.85, \"mode_collapse\": false, \"lora_config\": \"r=64, alpha=128, dropout=0.05, bf16\", \"checkpoints\": \"10 checkpoints (step 10-100)\"}, \"notes\": \"训练完成 (100/100 steps, EXIT_CODE=0, 554s/9.2min)。无 mode collapse (frac_zero_std=0.0 全程)。KL 极低 (0.005-0.052)。训练 metrics 比 QLoRA 更好 (reward 1.795 vs 1.195, 无 frac_zero_std 升高)。但 QLoRA 训练 metrics 也不差，问题在 eval。必须 eval 才能判断 catastrophic forgetting 是算法层面还是量化问题。\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T15:55:53.725Z\"}, \"plan_011_grpo_g8_bf16_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:43:48.481Z\", \"updated_at\": \"2026-05-15T15:55:52.592Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES=0 HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_ced_g8_bf16/checkpoint-100 --sft_adapter /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/grpo_g8_bf16_ckpt100 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"216356\", \"log_path\": \"~/runs/faith-evidence-ie/plan_011_grpo_g8_bf16_eval.log\", \"submitted_at\": \"2026-05-15T14:47:35.396Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4097.2, \"gpu_hours\": 1.14}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:51:35.239Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:51:38.162514+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4549, \"ign_f1\": 0.4549, \"evi_f1\": 0.8086, \"edcr\": 0.6318, \"format_ok_rate\": 1, \"n_truncated\": 61, \"n_total\": 985, \"n_predictions\": 10701, \"checkpoint\": \"checkpoint-100\", \"model\": \"Qwen3-4B + SFT merged + GRPO bf16 LoRA ckpt-100\", \"inference_time_s\": 3170.3}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_g8_bf16_ckpt100\", \"log_path\": \"~/runs/faith-evidence-ie/plan_011_grpo_g8_bf16_eval.log\", \"notes\": \"bf16 GRPO G=8 checkpoint-100 full dev eval (985 docs). F1=0.4549 (+4.92pp vs SFT 0.4057), Evi-F1=0.8086 (+1.07pp vs SFT 0.7979), EDCR=0.6318. Catastrophic forgetting 不复现——bf16 LoRA 下 GRPO 性能甚至超过 SFT baseline。与 QLoRA GRPO (rel_f1=0.2167) 形成鲜明对比。61/985 truncated, 100% format OK. 关键结论: forgetting 是 QLoRA 4-bit 量化导致, 非 GRPO 算法本身问题。但注意此实验同时改了 quantization(bf16 vs 4bit) + group_size(8 vs 4), 需 plan_015 隔离变量。\", \"completed_at\": \"2026-05-15T15:55:52.592Z\"}, \"plan_004_dreeam_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T13:47:01.947Z\", \"updated_at\": \"2026-05-15T15:44:24.920Z\", \"hypothesis\": \"Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。\", \"spec\": {\"command\": \"cd /root/autodl-tmp/baselines/dreeam && python run.py --do_train --data_dir dataset/docred --transformer_type roberta --model_name_or_path roberta-large --train_file train_annotated.json --dev_file dev.json --save_path checkpoints/teacher_roberta --train_batch_size 4 --test_batch_size 8 --num_train_epochs 30 --num_class 97 --seed 66\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"213006\", \"log_path\": \"~/runs/faith-evidence-ie/plan_004_dreeam_baseline.log\", \"submitted_at\": \"2026-05-15T14:29:38.364Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"model_name\": \"roberta-large\", \"data_path\": \"/root/autodl-tmp/baselines/dreeam/dataset/docred\", \"data_count\": 3053, \"seed\": 66, \"checkpoint_path\": \"/root/autodl-tmp/baselines/dreeam/checkpoints/teacher_roberta/2026-05-15_22:29:42.720935/last.ckpt\", \"wall_clock_seconds\": 4486.6, \"gpu_hours\": 1.25}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:42:51.417Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:42:53.896000+00:00\"}]}, \"metrics\": {\"dev_rel_f1\": 63.57, \"dev_rel_ign_f1\": 61.72, \"dev_evi_f1\": 54.01, \"dev_rel_p\": 66.95, \"dev_rel_r\": 60.51, \"dev_evi_p\": 60.53, \"dev_evi_r\": 48.76}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T15:44:24.920Z\"}, \"mvp2_eval_rsft_r2b_maxtok1536_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:54:57.156Z\", \"updated_at\": \"2026-05-15T15:21:13.816Z\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.\", \"parent\": \"mvp2_eval_rsft_r2b\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T11:55:17.608Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && rm -rf /root/autodl-tmp/eval_results/rsft_r2b_maxtok1536/* && python -m freige.eval.inference --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --model_path /root/autodl-tmp/rsft_output_r2b --data_path /root/autodl-tmp/data/docred --no-quantize --max_new_tokens 1536 --output_dir /root/autodl-tmp/eval_results/rsft_r2b_maxtok1536\\\"\", \"finished_at\": \"2026-05-15T14:55:32.781Z\", \"training_hours\": 3.0}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && rm -rf /root/autodl-tmp/eval_results/rsft_r2b_maxtok1536/* && python -m freige.eval.inference --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --model_path /root/autodl-tmp/rsft_output_r2b --data_path /root/autodl-tmp/data/docred --no-quantize --max_new_tokens 1536 --output_dir /root/autodl-tmp/eval_results/rsft_r2b_maxtok1536\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"197381\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_r2b_maxtok1536_r2.log\", \"submitted_at\": \"2026-05-15T11:55:18.697Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 12352.2, \"gpu_hours\": 3.43}, \"pid\": \"197381\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_r2b_maxtok1536_r2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T14:55:34.874453+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4504, \"ign_f1\": 0.4504, \"evi_f1\": 0.8102, \"edcr\": 0.674, \"precision\": 0.4488, \"recall\": 0.4519, \"evi_precision\": 0.8162, \"evi_recall\": 0.8044, \"n_truncated\": 146, \"n_total\": 985, \"n_predictions\": 17188, \"n_distractor_citations\": 19589, \"n_total_citations\": 29063, \"format_ok_rate\": 0.998}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/rsft_r2b_maxtok1536/\", \"completed_at\": \"2026-05-15T15:21:10.917Z\", \"notes\": \"max_new_tokens 1536 vs 1024: truncated 179→146 (-33), EDCR 0.6609→0.6740 (+0.0131), rel_f1 0.4493→0.4504, evi_f1 0.8128→0.8102。截断只是 EDCR 偏低的次要因素，distractor citation 是 RSFT 的真实行为。\"}, \"plan_001_flat_nli_scoring\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T14:36:56.213Z\", \"updated_at\": \"2026-05-15T15:21:03.475Z\", \"hypothesis\": \"flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。\", \"spec\": {\"command\": \"python -m freige.training.rsft_score_filter --scoring_mode flat_nli --top_k 3 --f1_threshold 0.1\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"208155\", \"model_name\": \"DeBERTa-v3-large-mnli-fever-anli-ling-wanli\", \"data_path\": \"/root/autodl-tmp/rsft_generations\", \"data_count\": 21728, \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-15T15:16:35.698Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T15:16:36.841Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:16:38.717977+00:00\"}]}, \"metrics\": {\"total_scored\": 21728, \"selected_samples\": 2691, \"selection_rate\": 0.124, \"selection_strategy\": \"top_k=1\", \"f1_threshold\": 0.1, \"output_path\": \"/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl\"}, \"notes\": \"Scoring 实际用 top_k=1（非 spec 中的 top_k=3），与 CED scoring 的 top_k=1 (2718 samples) 公平对比。选出 2691 samples。Cron 误报 failed（假阴性），Reviewer 确认输出完整。\"}, \"mvp2_ced_reranker_poc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:55:03.414Z\", \"updated_at\": \"2026-05-15T14:51:46.913Z\", \"hypothesis\": \"CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"spec\": {\"command\": \"python /root/autodl-tmp/freige/eval/ced_reranker.py (N=8, CED scoring, 985 docs)\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT (greedy N=8 + CED reranker)\", \"seed\": 42, \"pid\": \"178050\", \"checkpoint_path\": \"N/A\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_ced_reranker_poc.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T14:47:24.899Z\", \"metrics\": {\"ced_reranker_rel_f1\": 0.4864, \"ced_reranker_evi_f1\": 0.8188, \"ced_reranker_edcr\": 0.6156, \"ced_reranker_precision\": 0.4913, \"ced_reranker_recall\": 0.4815, \"ced_reranker_pred_count\": 14782, \"ced_reranker_format_ok_rate\": 1, \"oracle_rel_f1\": 0.6237, \"oracle_evi_f1\": 0.7942, \"oracle_edcr\": 0.5262, \"oracle_pred_count\": 13418, \"random_rel_f1\": 0.4538, \"random_evi_f1\": 0.8029, \"random_edcr\": 0.6763, \"ced_f1_spearman_r\": 0.3235, \"ced_f1_spearman_p\": 2.46e-191, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"sft_baseline_edcr\": 0.7118, \"rsft_mean_rel_f1\": 0.4596, \"delta_vs_sft_rel_f1\": 0.0807, \"delta_vs_rsft_rel_f1\": 0.0268, \"delta_vs_sft_evi_f1\": 0.0209, \"oracle_ceiling_rel_f1\": 0.218, \"num_generations\": 8, \"temperature\": 0.7, \"generation_time_s\": 20872.6, \"n_docs\": 985}, \"notes\": \"CED reranker (N=8, no training) rel_f1=0.4864, 超过 SFT greedy (+8.07pp) 和 RSFT 3-seed mean (+2.68pp)。Oracle 上界 rel_f1=0.6237 (+21.8pp vs SFT)，CED reranker 实现了 oracle ceiling 的 37% (0.0807/0.218)。CED-F1 Spearman r=0.3235 (p≈0)，相关性显著但中等——说明 CED 不是完美的 proxy 但有信号。Random baseline rel_f1=0.4538 说明 sampling diversity 本身就有 +4.8pp 收益，CED 在此基础上再加 +3.3pp。EDCR 下降 (0.6156 vs SFT 0.7118)，N=8 sampling 引入更多 distractor citations。推理耗时 5.8h (N=8 生成主导)。结论：CED 作为 inference-time reranker 有明确论文价值——零训练成本超越 RSFT，且 oracle ceiling 表明更好的 reward model 还有大幅空间。\"}, \"mvp2_eval_rsft_s43_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:29:17.551Z\", \"updated_at\": \"2026-05-15T13:54:26.023Z\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).\", \"parent\": \"mvp2_rsft_train_r1_s43\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s43 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/rsft_s43 --no-quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"194837\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_s43_r2.log\", \"submitted_at\": \"2026-05-15T11:29:48.250Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7213.0, \"gpu_hours\": 2.0}, \"pid\": \"194837\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_s43_r2.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_s43 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/rsft_s43 --no-quantize\\\"\", \"finished_at\": \"2026-05-15T13:16:38.318Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:16:41.689788+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4683, \"ign_f1\": 0.4683, \"evi_f1\": 0.8156, \"evi_f1_joint\": 0.3711, \"evi_f1_joint_P\": 0.3747, \"evi_f1_joint_R\": 0.3675, \"edcr\": 0.6388, \"precision\": 0.4817, \"recall\": 0.4556, \"evi_precision\": 0.8142, \"evi_recall\": 0.817, \"n_predictions\": 14970, \"n_truncated\": 171, \"format_ok_rate\": 1, \"inference_time_s\": 6316.7, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0626, \"delta_evi_f1\": 0.0177, \"delta_evi_f1_joint\": 0.0594, \"mvp2_pass\": true}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/rsft_s43\", \"notes\": \"3rd seed PASS. rel_f1=0.4683 (+6.26pp vs SFT), evi_f1=0.8156 (+1.77pp), EDCR=0.6388. 3-seed 完整表: mean rel_f1=0.4596±0.0127, mean evi_f1=0.8143±0.0051. 三个 seed 均稳定超过 SFT baseline。cuda:2 已释放。\", \"completed_at\": \"2026-05-15T13:30:01.258Z\"}, \"mvp2_rsft_ced_scoring_topk3_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:12:38.363Z\", \"updated_at\": \"2026-05-15T13:53:08.461Z\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).\", \"parent\": \"mvp2_rsft_ced_scoring\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-15T12:13:02.778Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && rm -rf /root/autodl-tmp/rsft_filtered_topk3/* && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_generations --output_path /root/autodl-tmp/rsft_filtered_topk3 --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --selection_strategy top_k --top_k 3 --f1_threshold 0.1 --tau 0.5\\\"\", \"finished_at\": \"2026-05-15T13:19:15.077Z\", \"training_hours\": 1.1}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && rm -rf /root/autodl-tmp/rsft_filtered_topk3/* && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_generations --output_path /root/autodl-tmp/rsft_filtered_topk3 --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --selection_strategy top_k --top_k 3 --f1_threshold 0.1 --tau 0.5\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"198997\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_ced_scoring_topk3_r2.log\", \"submitted_at\": \"2026-05-15T12:13:03.900Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4584.8, \"gpu_hours\": 1.27, \"note\": \"NLI 推理实际跑在 cuda:0 (--nli_device cuda:0)，非 cuda:3。Registry gpu 字段已修正。\"}, \"pid\": \"198997\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_ced_scoring_topk3_r2.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T13:19:17.812206+00:00\"}]}, \"metrics\": {\"input_generations\": 21728, \"selected_samples\": 8037, \"unique_docs\": 2691, \"selection_rate\": 0.37, \"mean_f1\": 0.5761, \"mean_ced\": 0.6205, \"mean_combined\": 0.6787, \"f1_range_p25\": 0.444, \"f1_range_p75\": 0.717, \"ced_range_p25\": 0.487, \"ced_range_p75\": 0.774, \"truncated_samples\": 1924, \"truncated_pct\": 8.9, \"selection_strategy\": \"top_k=3\", \"f1_threshold\": 0.1, \"topk1_samples\": 2718, \"data_multiplier\": 2.96}, \"conclusion\": \"success\", \"notes\": \"top_k=3 scoring 完成。8037 samples (vs top_k=1 的 2718, 2.96x)。质量下降可控: mean_f1 -0.04, mean_ced -0.048。输出: /root/autodl-tmp/rsft_filtered_topk3/rsft_train.jsonl (24.8MB)。可用于 plan_008 RSFT 训练 ablation。\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_filtered_topk3\", \"completed_at\": \"2026-05-15T13:29:28.749Z\"}, \"mvp2_rsft_train_r1_s44\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:36:26.321Z\", \"updated_at\": \"2026-05-15T13:27:38.819Z\", \"hypothesis\": \"RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_train_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-15T05:38:32.212Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_s44 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1-s44 --seed 44\\\"\", \"wandb_run_id\": \"rsft-ced-r1-s44\", \"finished_at\": \"2026-05-15T07:32:40.691Z\", \"training_hours\": 1.9}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_s44 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1-s44 --seed 44\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"165672\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1_s44.log\", \"submitted_at\": \"2026-05-15T05:39:22.747Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_s44\", \"wall_clock_seconds\": 27283.5, \"gpu_hours\": 7.58}, \"pid\": \"165672\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1_s44.log\", \"wandb_run_id\": \"rsft-ced-r1-s44\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:32:43.021519+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.4655, \"evi_f1\": 0.8087, \"evi_f1_joint\": 0.3713, \"evi_f1_joint_P\": 0.3775, \"evi_f1_joint_R\": 0.3653, \"edcr\": 0.635, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0598, \"delta_evi_f1\": 0.0108, \"delta_evi_f1_joint\": 0.0596, \"mvp2_pass\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T13:14:06.295Z\"}, \"mvp2_eval_rsft_r2b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:58.437Z\", \"updated_at\": \"2026-05-15T13:27:35.580Z\", \"hypothesis\": \"Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_r2b\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"spec\": {\"command\": \"python -m freige.eval.inference --no-quantize (r2b checkpoint on cuda:3)\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT r2b\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_r2b\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"pid\": \"189855\"}, \"metrics\": {\"rel_f1\": 0.4493, \"ign_f1\": 0.4493, \"evi_f1\": 0.8128, \"evi_f1_joint\": 0.349, \"evi_f1_joint_P\": 0.3455, \"evi_f1_joint_R\": 0.3526, \"edcr\": 0.6609, \"precision\": 0.4566, \"recall\": 0.4424, \"evi_precision\": 0.8201, \"evi_recall\": 0.8056, \"pred_count\": 14829, \"format_ok\": \"983/985\", \"truncated\": 179, \"inference_time_s\": 5862, \"delta_evi_f1_joint\": 0.0373}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_r2b\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_r2b/eval.log\", \"completed_at\": \"2026-05-15T11:44:36.428Z\"}, \"mvp2_eval_rsft_r2a\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:57.684Z\", \"updated_at\": \"2026-05-15T13:27:32.756Z\", \"hypothesis\": \"Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_r2a\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"spec\": {\"command\": \"python -m freige.eval.inference --no-quantize (r2a checkpoint on cuda:1)\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT r2a\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_r2a\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4494, \"ign_f1\": 0.4494, \"evi_f1\": 0.8108, \"evi_f1_joint\": 0.3509, \"evi_f1_joint_P\": 0.3423, \"evi_f1_joint_R\": 0.3599, \"edcr\": 0.6641, \"precision\": 0.4512, \"recall\": 0.4475, \"evi_precision\": 0.8143, \"evi_recall\": 0.8073, \"format_ok_rate\": 1, \"n_predictions\": 15482, \"n_truncated\": 208, \"inference_time_s\": 5967.2, \"delta_evi_f1_joint\": 0.0392}, \"notes\": \"RSFT r2a (1ep, alpha=128/r=64, lr=2e-5, clean 2548 samples). rel_f1=0.4494 (+0.0045 vs r1, +0.0001 vs r2b), evi_f1=0.8108 (-0.0079 vs r1, -0.0020 vs r2b), edcr=0.6641 (+0.0032 vs r2b). 1 epoch with clean data matches r1's 3-epoch rel_f1 while being cheaper. r2a vs r2b (alpha=128 vs 32): nearly identical rel_f1, marginal edcr advantage for higher alpha. All RSFT variants beat SFT baseline on rel_f1/evi_f1 but lose on edcr (0.66-0.66 vs 0.71).\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/rsft_r2a\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_r2a/eval.log\", \"completed_at\": \"2026-05-15T11:46:56.410Z\"}, \"mvp2_eval_rsft_r1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:40:47.529Z\", \"updated_at\": \"2026-05-15T13:27:31.402Z\", \"hypothesis\": \"Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.\", \"parent\": \"mvp2_rsft_train_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"spec\": {\"command\": \"python -m freige.eval.inference --no-quantize (r1 checkpoint on cuda:2)\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + RSFT r1\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/rsft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"pid\": \"186329\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output\", \"log_path\": \"/root/autodl-tmp/eval_results/rsft_r1/eval.log\"}, \"metrics\": {\"rel_f1\": 0.4449, \"evi_f1\": 0.8187, \"evi_f1_joint\": 0.3468, \"evi_f1_joint_P\": 0.3515, \"evi_f1_joint_R\": 0.3423, \"edcr\": 0.6565, \"num_preds\": 15307, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0392, \"delta_evi_f1\": 0.0208, \"delta_evi_f1_joint\": 0.0351, \"mvp2_pass\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T11:30:26.893Z\"}, \"mvp2_eval_sft_baseline\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T21:47:41.356Z\", \"updated_at\": \"2026-05-15T13:27:26.236Z\", \"hypothesis\": \"SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.\", \"parent\": \"mvp2_sft_warmup\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T21:49:57.466Z\"}, \"notes\": \"[2026-05-15 07:39] Eval 正常完成。结果与 r2/r3 完全一致 (rel_f1=0.4057, evi_f1=0.7979)，apple-to-apple 对比协议复现成功。结果路径: /root/autodl-tmp/sft_baseline_eval_results/metrics.json。cuda:3 已释放。\", \"completed_at\": \"2026-05-14T22:10:34.104Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"[2026-05-15 06:05] RUNNING on cuda:3, PID 104979. Progress: 4/62 batches (6.5%). Shares GPU 3 with mvp2_eval_lr5e6_rp_r2_ckpt20 (PID 103831). ~146s/batch, ETA ~2h20m. Log: tee failed (logs dir missing), output in tmux only. Output dir: /root/autodl-tmp/sft_baseline_eval_results/\"}}, \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"account\": \"root\", \"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/sft_baseline_eval_results --quantize\", \"pid\": \"104979\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT LoRA adapter\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"docred dev split\", \"checkpoint_path\": \"/root/autodl-tmp/sft_baseline_eval_results/metrics.json\", \"log_path\": \"N/A - tmux output only\"}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"evi_f1\": 0.7979, \"evi_f1_joint\": 0.3117, \"evi_f1_joint_P\": 0.3037, \"evi_f1_joint_R\": 0.32, \"edcr\": 0.7118, \"pred_count\": 12234, \"gold_count\": 12151, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.998, \"field_compliance_rate\": 0.6264, \"n_truncated\": 367, \"inference_time_seconds\": 6138.5}}, \"mvp2_eval_rsft_r2b_maxtok1536\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:49:48.849Z\", \"updated_at\": \"2026-05-15T13:23:59.642Z\", \"hypothesis\": \"Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.\", \"parent\": \"mvp2_eval_rsft_r2b\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output_r2b --data_path /root/autodl-tmp/data/docred --no-quantize --max_new_tokens 1536 --output_dir /root/autodl-tmp/eval_results/rsft_r2b_maxtok1536\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"196700\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_r2b_maxtok1536.log\", \"submitted_at\": \"2026-05-15T11:51:37.717Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B+SFT+RSFT r2b\", \"checkpoint_source\": \"/root/autodl-tmp/rsft_output_r2b\", \"eval_data\": \"docred dev (985 docs)\", \"seed\": 42, \"purpose\": \"诊断 EDCR 下降是否因 max_new_tokens=1024 截断导致，179/985 docs 被截断，改用 1536 重跑\", \"wall_clock_seconds\": 5541.9, \"gpu_hours\": 1.54}, \"conclusion\": \"killed\", \"notes\": \"Reviewer CRITICAL: 命令缺少 --base_model 和 --sft_adapter，模型 stack 是 Base+RSFT LoRA 而非 Base+SFT+RSFT LoRA，结果不可用。PID 196700 已 kill。重试为 mvp2_eval_rsft_r2b_maxtok1536_r2。\", \"completed_at\": \"2026-05-15T13:23:59.642Z\"}, \"mvp2_rsft_ced_scoring_topk3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:35:23.225Z\", \"updated_at\": \"2026-05-15T13:20:42.443Z\", \"hypothesis\": \"CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?\", \"spec\": {\"command\": \"python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_generations --output_path /root/autodl-tmp/rsft_filtered_topk3 --nli_model_path cross-encoder/nli-deberta-v3-base --nli_device cuda:0 --selection_strategy top_k --top_k 3 --f1_threshold 0.1 --tau 0.5\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"198680\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_ced_scoring_topk3.log\", \"submitted_at\": \"2026-05-15T12:09:41.690Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/rsft_generations/generations.jsonl\", \"data_count\": 21952, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"wall_clock_seconds\": 4260.8, \"gpu_hours\": 1.18}, \"conclusion\": \"killed\", \"notes\": \"NLI 模型加载失败 (HuggingFace Network unreachable)。命令缺少 HF_HOME/HF_HUB_OFFLINE/TRANSFORMERS_OFFLINE 环境变量。重试为 mvp2_rsft_ced_scoring_topk3_r2。\", \"completed_at\": \"2026-05-15T13:20:42.443Z\"}, \"mvp2_rsft_r2b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T08:57:46.813Z\", \"updated_at\": \"2026-05-15T13:14:23.368Z\", \"hypothesis\": \"RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_train_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-15T08:58:45.465Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train_clean.jsonl --output_dir /root/autodl-tmp/rsft_output_r2b --learning_rate 1e-5 --num_epochs 1 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 32 --weighted_sampling --save_steps 50 --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-r2b --seed 42\\\"\", \"wandb_run_id\": \"rsft-r2b\", \"finished_at\": \"2026-05-15T09:35:56.802Z\", \"training_hours\": 0.62}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train_clean.jsonl --output_dir /root/autodl-tmp/rsft_output_r2b --learning_rate 1e-5 --num_epochs 1 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 32 --weighted_sampling --save_steps 50 --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-r2b --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"183587\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_r2b.log\", \"submitted_at\": \"2026-05-15T09:00:01.270Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_r2b\", \"wall_clock_seconds\": 15262.1, \"gpu_hours\": 4.24}, \"pid\": \"183587\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_r2b.log\", \"wandb_run_id\": \"rsft-r2b\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:35:58.776100+00:00\"}]}, \"notes\": \"训练完成 (160 steps, 33.7min, eval_loss=0.7545)。TaskEvalCallback rel_f1=0.0504 是已知 bug (D038: gold triples 分母不匹配)，不代表真实性能。需全量 dev eval 确认实际指标。\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4493, \"evi_f1\": 0.8128, \"edcr\": 0.6609, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0436, \"delta_evi_f1\": 0.0149, \"mvp2_pass\": true}, \"completed_at\": \"2026-05-15T13:14:23.368Z\"}, \"mvp2_rsft_r2a\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T08:57:46.140Z\", \"updated_at\": \"2026-05-15T13:14:22.509Z\", \"hypothesis\": \"RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_train_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T08:58:44.826Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train_clean.jsonl --output_dir /root/autodl-tmp/rsft_output_r2a --learning_rate 2e-5 --num_epochs 1 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --save_steps 50 --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-r2a --seed 42\\\"\", \"wandb_run_id\": \"rsft-r2a\", \"finished_at\": \"2026-05-15T09:36:15.752Z\", \"training_hours\": 0.63}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train_clean.jsonl --output_dir /root/autodl-tmp/rsft_output_r2a --learning_rate 2e-5 --num_epochs 1 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --save_steps 50 --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-r2a --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"183504\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_r2a.log\", \"submitted_at\": \"2026-05-15T08:59:58.168Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_r2a\", \"wall_clock_seconds\": 15264.3, \"gpu_hours\": 4.24}, \"pid\": \"183504\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_r2a.log\", \"wandb_run_id\": \"rsft-r2a\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T09:36:20.493042+00:00\"}]}, \"notes\": \"训练完成 (160 steps, 35.5min, eval_loss=0.7547)。TaskEvalCallback rel_f1=0.0509 是已知 bug (D038: gold triples 分母不匹配)，不代表真实性能。需全量 dev eval 确认实际指标。\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4494, \"evi_f1\": 0.8108, \"edcr\": 0.6641, \"sft_baseline_rel_f1\": 0.4057, \"sft_baseline_evi_f1\": 0.7979, \"delta_rel_f1\": 0.0437, \"delta_evi_f1\": 0.0129, \"mvp2_pass\": true}, \"completed_at\": \"2026-05-15T13:14:22.510Z\"}, \"mvp2_rsft_diagnosis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T07:55:04.100Z\", \"updated_at\": \"2026-05-15T12:09:32.257Z\", \"hypothesis\": \"RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.\", \"conclusion\": \"success\", \"metrics\": {\"root_cause\": \"overfitting_plus_sft_knowledge_overwrite\", \"truncated_json_samples\": 170, \"truncated_pct\": 6.3, \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759, \"lora_scaling\": 2, \"rsft_zero_relation_samples\": 170, \"sft_zero_relation_docs\": 26, \"rsft_mean_relations\": 11.2, \"sft_mean_relations\": 12.5}, \"checkpoint_path\": \"N/A (diagnosis task, no checkpoint)\", \"log_path\": \"N/A (diagnosis task)\", \"completed_at\": \"2026-05-15T12:09:32.257Z\"}, \"mvp2_eval_ced_kl001_r4_last\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:10:05.820Z\", \"updated_at\": \"2026-05-15T12:09:21.004Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && source /etc/network_turbo && cd /root/autodl-tmp/freige && CUDA_VISIBLE_DEVICES=0 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 90,100 --quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_last.log\", \"submitted_at\": \"2026-05-14T18:10:05.342Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 64755.7, \"gpu_hours\": 17.99}, \"notes\": \"已被拆分为独立 eval：ckpt-90 → mvp2_eval_ced_kl001_r4_ckpt90 (cuda:3)，ckpt-100 → mvp2_eval_ced_kl001_r4_step100 (cuda:0)。此条目作废。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:09:21.004Z\"}, \"mvp2_grpo_ced_kl001_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:25:06.729Z\", \"updated_at\": \"2026-05-15T12:09:20.252Z\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)\", \"parent\": \"mvp2_grpo_ced_kl001\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.training.grpo_trainer --stage 3 --kl_coef 0.01 --num_iterations 1 --save_steps 20 --save_total_limit 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --learning_rate 5e-5 --gradient_accumulation_steps 16 --num_generations 4\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"65740\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_kl001_r3.log\", \"submitted_at\": \"2026-05-14T15:25:17.200Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 74643.1, \"gpu_hours\": 20.73}, \"notes\": \"失败原因: datasets 库不支持 thunlp/docred 自定义脚本 (RuntimeError: Dataset scripts are no longer supported)。命令缺少 --data_dir /root/autodl-tmp/data/docred 参数，触发 HF 远程下载失败。需要补全所有必要参数后重新提交。error_type: infrastructure | can_auto_fix: true\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:09:20.252Z\"}, \"mvp2_grpo_ced_kl001_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:23:16.518Z\", \"updated_at\": \"2026-05-15T12:09:19.263Z\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)\", \"parent\": \"mvp2_grpo_ced_kl001\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 3 --kl_coef 0.01 --num_iterations 1 --save_steps 20 --save_total_limit 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --learning_rate 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_kl001_r2.log\", \"submitted_at\": \"2026-05-14T15:23:31.047Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 74748.2, \"gpu_hours\": 20.76}, \"conclusion\": \"killed\", \"notes\": \"失败原因: 命令未用 bash -c 包裹，tmux 以 sh 执行导致 source 命令失败。error_type: infrastructure | can_auto_fix: true\", \"completed_at\": \"2026-05-15T12:09:19.263Z\"}, \"mvp2_rsft_train_r2_fix\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T08:38:03.815Z\", \"updated_at\": \"2026-05-15T12:09:18.298Z\", \"hypothesis\": \"RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:09:18.298Z\"}, \"mvp2_rsft_train_r1_s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:36:25.275Z\", \"updated_at\": \"2026-05-15T11:31:48.727Z\", \"hypothesis\": \"RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_train_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T05:38:31.664Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1-s43 --seed 43\\\"\", \"wandb_run_id\": \"rsft-ced-r1-s43\", \"finished_at\": \"2026-05-15T07:37:49.819Z\", \"training_hours\": 1.99}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output_s43 --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1-s43 --seed 43\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"165590\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1_s43.log\", \"submitted_at\": \"2026-05-15T05:39:20.307Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 21148.4, \"gpu_hours\": 5.87}, \"pid\": \"165590\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1_s43.log\", \"wandb_run_id\": \"rsft-ced-r1-s43\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:37:52.173054+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/rsft_output_s43\", \"metrics\": {\"eval_loss\": 0.7622, \"train_loss\": 0.6148, \"eval_entropy\": 0.6724, \"mean_token_accuracy\": 0.8291, \"total_steps\": 510, \"epochs\": 3, \"training_hours\": 1.99}, \"conclusion\": \"success\", \"notes\": \"训练正常完成 (510 steps, 1.99h, eval_loss=0.7622, train_loss=0.6148)。与 s44 (eval_loss=未记录) 和 r1 相近。TaskEvalCallback rel_f1 是已知 bug，需全量 eval。全量 eval 重试 mvp2_eval_rsft_s43_r2 正在运行中。\", \"completed_at\": \"2026-05-15T11:31:48.727Z\"}, \"mvp2_eval_rsft_s43\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:25:26.268Z\", \"updated_at\": \"2026-05-15T11:29:11.205Z\", \"hypothesis\": \"Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.\", \"parent\": \"mvp2_rsft_train_r1_s43\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_adapter /root/autodl-tmp/rsft_output_s43 --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/rsft_s43 --no-quantize --gpu 0\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"194296\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_s43.log\", \"submitted_at\": \"2026-05-15T11:26:15.318Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18.9, \"gpu_hours\": 0.01}, \"pid\": \"194296\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_rsft_s43.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_adapter /root/autodl-tmp/rsft_output_s43 --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/rsft_s43 --no-quantize --gpu 0\\\"\", \"finished_at\": \"2026-05-15T11:26:32.872Z\"}, \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T11:26:34.235Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T11:26:36.157796+00:00\"}]}, \"notes\": \"参数名错误导致失败: --rsft_adapter 应为 --model_path, --data_dir 应为 --data_path, --gpu 0 不存在。重试为 mvp2_eval_rsft_s43_r2。\"}, \"mvp2_rsft_train_r1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:27:39.073Z\", \"updated_at\": \"2026-05-15T09:40:39.078Z\", \"hypothesis\": \"RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"165130\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1.log\", \"submitted_at\": \"2026-05-15T05:37:57.880Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 7210.1, \"gpu_hours\": 2.0}, \"pid\": \"165130\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_train_r1.log\", \"wandb_run_id\": \"rsft-ced-r1\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 python -m freige.training.rsft_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --output_dir /root/autodl-tmp/rsft_output --learning_rate 2e-5 --num_epochs 3 --per_device_batch_size 4 --gradient_accumulation_steps 4 --lora_rank 64 --lora_alpha 128 --weighted_sampling --eval_data_dir /root/autodl-tmp/data/docred --eval_max_docs 50 --wandb_run_name rsft-ced-r1 --seed 42\\\"\", \"wandb_run_id\": \"rsft-ced-r1\", \"finished_at\": \"2026-05-15T07:35:10.628Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T07:35:13.068974+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/rsft_output\", \"metrics\": {\"rel_f1\": 0.0483, \"num_preds\": 848, \"sft_baseline_rel_f1\": 0.4057, \"failure_mode\": \"relation_ontology_collapse_to_freetext\", \"epoch1_eval_loss\": 0.756, \"epoch2_eval_loss\": 0.759}, \"completed_at\": \"2026-05-15T07:38:07.936Z\", \"notes\": \"D037 修正: TaskEvalCallback 的 rel_f1=0.0483 是 eval bug（gold triples 未限制为 eval_max_docs 子集）。全量 eval 待跑。s44 全量 eval 已 PASS: rel_f1=0.4655, evi_f1=0.8087。\"}, \"mvp2_rsft_ced_scoring\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T05:27:32.788Z\", \"updated_at\": \"2026-05-15T05:33:16.769Z\", \"hypothesis\": \"CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).\", \"spec\": {\"command\": \"python -m freige.training.rsft_score_filter --input_dir /root/autodl-tmp/rsft_generations --output_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl --selection_strategy top_k --top_k 1 --f1_threshold 0.1\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/rsft_generations/\", \"data_count\": 21952, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/rsft_filtered/rsft_train.jsonl\", \"log_path\": \"/root/autodl-tmp/rsft_filtered/rsft_combined_report.json\"}, \"conclusion\": \"success\", \"metrics\": {\"input_generations\": 21952, \"selected_samples\": 2718, \"unique_docs\": 2691, \"selection_rate\": 0.124, \"mean_f1\": 0.6157, \"mean_ced\": 0.6683, \"f1_range\": [0.1026, 1], \"zero_f1_samples\": 0, \"selection_strategy\": \"top_k=1\", \"f1_threshold\": 0.1}, \"completed_at\": \"2026-05-15T05:33:16.769Z\"}, \"mvp2_rsft_gen_s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:39:26.572Z\", \"updated_at\": \"2026-05-15T05:21:50.725Z\", \"spec\": {\"pid\": \"135867\"}, \"hypothesis\": \"RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"parent\": \"mvp2_sft_warmup\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:54:30.317Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T04:54:31.450Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:54:36.643913+00:00\"}]}, \"notes\": \"[2026-05-15 05:01] 生成完成 682/682 docs (100%)。EXIT_CODE=143 是正常完成后的清理 SIGTERM。format_ok 99.6%, truncation_rate 10.1%, diversity 7.6/8。\"}, \"mvp2_rsft_gen_s3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:39:34.645Z\", \"updated_at\": \"2026-05-15T05:01:10.955Z\", \"spec\": {\"pid\": \"137985\"}, \"hypothesis\": \"RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"parent\": \"mvp2_sft_warmup\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:49:43.444Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:49:45.523884+00:00\"}]}, \"conclusion\": \"success\", \"log_path\": \"/root/runs/faith-evidence-ie/mvp2_rsft_gen_s3.log\", \"metrics\": {\"generation_count\": 5288, \"unique_docs\": 659, \"format_compliance\": 0.998, \"diversity_range\": \"7.5-7.8/8\", \"exit_code\": 0}, \"checkpoint_path\": \"/root/autodl-tmp/rsft_generations/shard_3/generations.jsonl\", \"completed_at\": \"2026-05-15T05:00:41.430Z\"}, \"mvp2_rsft_gen_s2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:39:32.299Z\", \"updated_at\": \"2026-05-15T04:37:31.632Z\", \"spec\": {\"pid\": \"136649\"}, \"hypothesis\": \"RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"parent\": \"mvp2_sft_warmup\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:36:43.615Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T04:36:45.294Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:36:48.376664+00:00\"}]}}, \"mvp2_rsft_gen_s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T01:39:29.894Z\", \"updated_at\": \"2026-05-15T04:37:14.926Z\", \"spec\": {\"pid\": \"136270\"}, \"hypothesis\": \"RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.\", \"parent\": \"mvp2_sft_warmup\", \"reproduce\": {\"finished_at\": \"2026-05-15T04:34:07.774Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T04:34:08.880Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T04:34:14.011538+00:00\"}]}}, \"mvp2_rsft_generate\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:09:41.289Z\", \"updated_at\": \"2026-05-15T01:32:10.047Z\", \"hypothesis\": \"RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。\", \"parent\": \"mvp2_sft_warmup\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-15T00:09:52.157Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations --num_generations 8 --temperature 0.7 --batch_size 2 --max_new_tokens 1024 --seed 42\\\"\", \"finished_at\": \"2026-05-15T01:32:08.718Z\", \"training_hours\": 1.37}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && export HF_HOME=/root/autodl-tmp/.hf_cache && cd /root/autodl-tmp && python -m freige.training.rsft_generate --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split train_annotated --output_dir /root/autodl-tmp/rsft_generations --num_generations 8 --temperature 0.7 --batch_size 2 --max_new_tokens 1024 --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"122144\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_generate.log\", \"submitted_at\": \"2026-05-15T00:09:53.637Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 4936.4, \"gpu_hours\": 1.37}, \"pid\": \"122144\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_rsft_generate.log\", \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T01:32:10.047Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:32:15.807942+00:00\"}]}}, \"mvp2_diversity_probe\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:02:19.966Z\", \"updated_at\": \"2026-05-15T01:31:34.495Z\", \"hypothesis\": \"RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.\", \"conclusion\": \"success\", \"metrics\": {\"unique_triples_t07\": 5, \"unique_triples_t10\": 8, \"jaccard_t07\": 0.17, \"jaccard_t10\": 0.051, \"format_ok_rate_t07\": 0.5, \"format_ok_rate_t10\": 0.438, \"n_samples\": 3, \"n_generations\": 8, \"note\": \"unique_triples_t07 corrected from 7 to 5.0 (mean). Reviewer: format_ok ~34% after fix, 'diversity' was JSON key name variants not semantic diversity\"}, \"notes\": \"[2026-05-15 01:35] D034 独立验证结果: 200 docs 实际 diversity=7.11/8 (median=8.0), evidence diversity=5.43/8, format parse rate=90.2%。61.5% 文档达到 8/8 完全不同。之前监控报告的 mean_diversity=1.0/8 是监控计算 bug，非生成质量问题。diversity_probe 早期观察(7/8)是准确的。RSFT 前提成立。\", \"spec\": {\"command\": \"python diversity_probe.py (已完成, 状态修正)\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"checkpoint_path\": \"N/A (probe only)\", \"log_path\": \"N/A (probe only)\"}, \"completed_at\": \"2026-05-15T01:03:18.175Z\", \"checkpoint_path\": \"N/A (validation probe, no checkpoint)\", \"log_path\": \"N/A (validation probe)\"}, \"mvp2_eval_lr5e6_r1_ckpt100\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:00:57.035Z\", \"updated_at\": \"2026-05-15T01:30:01.493Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_ced_lr5e6/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/lr5e6_r1_ckpt100/checkpoint-100 --quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"117635\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_lr5e6_r1_ckpt100.log\", \"submitted_at\": \"2026-05-14T23:39:51.199Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 6160.9, \"gpu_hours\": 1.71}, \"hypothesis\": \"P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T23:39:49.461Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_ced_lr5e6/checkpoint-100 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/lr5e6_r1_ckpt100/checkpoint-100 --quantize\\\"\", \"finished_at\": \"2026-05-15T01:19:34.927Z\", \"training_hours\": 1.66}, \"pid\": \"117635\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_lr5e6_r1_ckpt100.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T01:19:36.799167+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.0138, \"rel_precision\": 0.0132, \"rel_recall\": 0.0144, \"ign_f1\": 0.0138, \"evi_f1\": 0.8504, \"evi_precision\": 0.9256, \"evi_recall\": 0.7866, \"edcr\": 0.9876, \"format_ok_rate\": 0.999, \"field_compliance_rate\": 0.8162, \"evidence_format_rate\": 0.8162, \"tp\": 175, \"pred_count\": 13300, \"gold_count\": 12151, \"n_predictions\": 15498, \"n_truncated\": 181, \"n_documents\": 985, \"n_parseable\": 984, \"inference_time_seconds\": 5901.7}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-100\", \"completed_at\": \"2026-05-15T01:22:32.071Z\"}, \"mvp2_grpo_ced_lr5e6_r1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:21:08.231Z\", \"updated_at\": \"2026-05-15T01:29:06.862Z\", \"hypothesis\": \"D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_ced_lr5e6 --num_generations 8 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-6 --seed 42 --kl_coef 0.01 --save_steps 20 --save_total_limit 20 --max_steps 200 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --wandb_run_name grpo-s3-ced-lr5e6-r1\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"90080\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"hyperparams\": {\"learning_rate\": 5e-06, \"kl_coef\": 0.01, \"num_generations\": 8, \"gradient_accumulation_steps\": 16, \"max_steps\": 200, \"save_steps\": 20, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"tau_start\": 0.3, \"tau_end\": 0.5}}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:0\", \"pid\": \"90080\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_lr5e6_r1.log\", \"wandb_run_id\": \"grpo-s3-ced-lr5e6-r1\", \"reproduce\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_ced_lr5e6 --num_generations 8 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-6 --seed 42 --kl_coef 0.01 --save_steps 20 --save_total_limit 20 --max_steps 200 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --wandb_run_name grpo-s3-ced-lr5e6-r1\\\"\", \"wandb_run_id\": \"grpo-s3-ced-lr5e6-r1\"}, \"notes\": \"[2026-05-15 01:08] D032 执行: PID 90080 killed (force_killed=true)。训练 step ~113/200。完整 lr5e-6 轨迹: ckpt-20→40→60→80 rel_f1 = 0.008/0.007/0.009/0.012，无恢复信号。GRPO+QLoRA 方向判死 (D031)，GPU 释放给 RSFT 流水线。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:07:56.366Z\"}, \"mvp2_eval_lr5e6_r1_ckpt80\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:25:45.043Z\", \"updated_at\": \"2026-05-15T01:02:32.508Z\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6 ckpt-80\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-80\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_ced_lr5e6/checkpoint-80 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/lr5e6_r1_ckpt80/checkpoint-80 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"111731\", \"account\": \"root\", \"log_path\": \"/tmp/eval_lr5e6_ckpt80.log\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/lr5e6_r1_ckpt80/checkpoint-80/\"}, \"hypothesis\": \"P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"notes\": \"[2026-05-15 08:56] 正常完成。rel_f1=0.0116，延续 ckpt-20/40/60 的平坦趋势 (0.007-0.012)。evi_f1=0.828 继续上升。lr5e6 轨迹: step 20→40→60→80 rel_f1 = 0.008/0.007/0.009/0.012，无恢复信号。cuda:2 已释放。\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0116, \"ign_f1\": 0.0116, \"precision\": 0.0109, \"recall\": 0.0124, \"evi_f1\": 0.828, \"evi_precision\": 0.928, \"evi_recall\": 0.748, \"edcr\": 0.993, \"format_ok_rate\": 0.999, \"field_compliance_rate\": 0.788, \"pred_count\": 13828, \"gold_count\": 12151, \"n_truncated\": 210, \"inference_time_seconds\": 6099}, \"completed_at\": \"2026-05-15T00:56:43.952Z\"}, \"mvp2_eval_lr5e6_r1_ckpt60_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:27:56.124Z\", \"updated_at\": \"2026-05-15T00:07:56.895Z\", \"hypothesis\": \"P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"spec\": {\"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6 ckpt-60\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-60\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python -m freige.eval.inference --model_path /root/autodl-tmp/grpo_ced_lr5e6/checkpoint-60 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/grpo_ced_lr5e6_ckpt60 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"108185\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_lr5e6_r1_ckpt60_r2.log\", \"account\": \"root\", \"backend\": \"tmux\", \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_ced_lr5e6_ckpt60/metrics.json\"}, \"conclusion\": \"negative\", \"notes\": \"[2026-05-15 08:07] 正常完成。rel_f1=0.0093，与 ckpt-20 (0.0077) / ckpt-40 (0.0071) 同一量级，无恢复信号。evi_f1=0.81 持续上升（ckpt-20: 0.628, ckpt-40: 0.758），证据抽取在改善但关系能力完全崩塌。结果路径: /root/autodl-tmp/eval_results/grpo_ced_lr5e6_ckpt60/metrics.json。cuda:1 已释放。\", \"metrics\": {\"rel_f1\": 0.0093, \"precision\": 0.0085, \"recall\": 0.0103, \"evi_f1\": 0.81, \"edcr\": 0.993, \"format_ok_rate\": 0.998, \"pred_count\": 14626, \"gold_count\": 12151, \"tp\": 125, \"inference_time_seconds\": 6152}, \"completed_at\": \"2026-05-15T00:07:56.895Z\"}, \"mvp2_eval_lr5e6_r1_ckpt60\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T22:13:47.936Z\", \"updated_at\": \"2026-05-14T23:25:25.584Z\", \"hypothesis\": \"P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/freige && python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_lr5e6 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/lr5e6_r1_ckpt60 --checkpoints 60 --quantize\\\"\", \"finished_at\": \"2026-05-14T22:25:13.602Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"completed_at\": \"2026-05-14T22:25:14.773Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T22:25:16.365584+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"[2026-05-15 07:28] 手动 SSH 启动成功. PID=108025, cuda:1, log=/tmp/eval_lr5e6_ckpt60.log\"}}, \"notes\": \"[2026-05-15 07:24] D031 清理: PID 108025 因 cd path 问题从未产出有效结果。已被 _r2 (PID 108185) 取代。标记 failed 关闭。\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 bash /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"108025\", \"log_path\": \"/tmp/eval_lr5e6_ckpt60.log\", \"submitted_at\": \"2026-05-14T22:29:00Z\", \"submitted_via\": \"manual_ssh\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/grpo_ced_lr5e6\", \"data_count\": 0, \"model_name\": \"grpo_ced_lr5e6_ckpt60\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-60\", \"eval_data\": \"batch_eval\", \"checkpoint_path\": \"N/A - process had wrong Python path, never produced valid output\", \"log_path_note\": \"PID 108025 had cd path issue, replaced by _r2 (PID 108185)\", \"wall_clock_seconds\": 3385.6, \"gpu_hours\": 0.94}, \"conclusion\": \"failed\"}, \"mvp2_eval_lr5e6_r1_ckpt40_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:41:34.558Z\", \"updated_at\": \"2026-05-14T23:11:56.267Z\", \"hypothesis\": \"Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"account\": \"root\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.inference\", \"pid\": \"101842\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6 ckpt-40\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-40\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/tmp/eval_lr5e6_ckpt40.log\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-40\", \"conclusion\": \"negative\", \"metrics\": {\"f1\": 0.007146887342486364, \"ign_f1\": 0.007146887342486364, \"precision\": 0.0065816821393931, \"recall\": 0.007818286560776891, \"evi_f1\": 0.7583892617449665, \"edcr\": 0.9942045337983383, \"format_ok_rate\": 0.9939086294416244, \"tp\": 95, \"pred_count\": 14434, \"gold_count\": 12151, \"n_truncated\": 424, \"inference_time_seconds\": 6152.4}, \"result_dir\": \"/root/autodl-tmp/eval_results/lr5e6_r1_ckpt40/checkpoint-40\"}, \"notes\": \"[2026-05-15 06:50] 全面状态检查: PID 101842 存活 (Rl, uptime 1:25), GPU 2: 10644 MiB/74% util. tmux mvp2_eval_lr5e6_r1_ckpt40 alive (创建于 05:25 UTC). 按 92s/batch 估算约 55/62 (89%), ETA ~10min (约UTC 07:00).\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0071, \"precision\": 0.0066, \"recall\": 0.0078, \"evi_f1\": 0.7584, \"evi_precision\": 0.9113, \"evi_recall\": 0.6494, \"edcr\": 0.9942, \"format_ok_rate\": 0.9939, \"field_compliance_rate\": 0.5675, \"pred_count\": 14434, \"gold_count\": 12151, \"tp\": 95, \"n_truncated\": 424, \"inference_time_seconds\": 6152}, \"completed_at\": \"2026-05-14T23:11:48.225Z\"}, \"mvp2_eval_lr5e6_r1_ckpt20\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:44:21.167Z\", \"updated_at\": \"2026-05-14T22:12:16.372Z\", \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"account\": \"root\", \"command\": \"bash /root/autodl-tmp/scripts/eval_lr5e6_ckpt20.sh\", \"pid\": \"96500\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6 ckpt-20\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-20\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/tmp/eval_lr5e6_ckpt20.log\"}, \"hypothesis\": \"P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"conclusion\": \"negative\", \"metrics\": {\"rel_f1\": 0.0077, \"rel_precision\": 0.0071, \"rel_recall\": 0.0084, \"evi_f1\": 0.628, \"evi_precision\": 0.855, \"evi_recall\": 0.496, \"edcr\": 0.993, \"format_ok_rate\": 0.991, \"field_compliance_rate\": 0.399, \"pred_count\": 14440, \"gold_count\": 12151, \"tp\": 102, \"n_truncated\": 587, \"inference_time_seconds\": 6370.4}, \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-20\", \"log_path\": \"/tmp/eval_lr5e6_ckpt20.log\", \"completed_at\": \"2026-05-14T22:12:16.372Z\"}, \"mvp2_eval_lr5e6_rp_r2_ckpt20\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:44:56.448Z\", \"updated_at\": \"2026-05-14T22:06:40.812Z\", \"hypothesis\": \"P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.\", \"parent\": \"mvp2_grpo_ced_lr5e6_rp_r2\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python eval rp_r2 ckpt-20\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"103825\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6+recall_penalty ckpt-20\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6_rp/checkpoint-20\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T22:06:39.146Z\", \"notes\": \"Director 指令 kill: 让 sft_baseline 独占 cuda:3。rp_r2 eval 优先级低，后面补。进度 11/62 (18%)。\"}, \"mvp2_eval_lr5e6_r1_ckpt40\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T21:25:00.579Z\", \"updated_at\": \"2026-05-14T21:43:33.438Z\", \"spec\": {\"command\": \"bash /root/autodl-tmp/scripts/eval_lr5e6_ckpt40.sh\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"101842\", \"data_path\": \"/root/autodl-tmp/data/docred/dev.json\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO lr5e6 ckpt-40\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_lr5e6/checkpoint-40\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"log_path\": \"/tmp/eval_lr5e6_ckpt40.log\", \"account\": \"root\"}, \"hypothesis\": \"P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.\", \"parent\": \"mvp2_grpo_ced_lr5e6_r1\", \"reproduce\": {\"finished_at\": \"2026-05-14T21:36:46.425Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T21:36:47.089Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:36:48.294849+00:00\"}]}, \"notes\": \"Reviewer 确认 PID 101842 在 cuda:2 正常运行中（inference 5/62, 8%），占用 9710 MiB。原误判原因：kill 旧 PID 100555 后 cron 检测旧 PID 导致 5× dead 误判。实际进程未中断。由 _r2 条目接续追踪。\"}, \"mvp2_grpo_ced_lr5e6_rp_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:04:55.831Z\", \"updated_at\": \"2026-05-14T21:40:50.174Z\", \"hypothesis\": \"D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bash quoting.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_ced_lr5e6_rp --num_generations 8 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-6 --seed 42 --kl_coef 0.01 --save_steps 20 --save_total_limit 20 --max_steps 200 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --ced_recall_penalty --wandb_run_name grpo-s3-ced-lr5e6-rp-r2\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"94753\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_lr5e6_rp_r2.log\", \"submitted_at\": \"2026-05-14T20:05:27.371Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"N/A (training from SFT adapter)\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"hyperparams\": {\"learning_rate\": 5e-06, \"kl_coef\": 0.01, \"num_generations\": 8, \"gradient_accumulation_steps\": 16, \"max_steps\": 200, \"save_steps\": 20, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"tau_start\": 0.3, \"tau_end\": 0.5, \"ced_recall_penalty\": true}, \"wall_clock_seconds\": 5716.8, \"gpu_hours\": 1.59}, \"wandb_run_id\": \"grpo-s3-ced-lr5e6-rp-r2\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T21:40:44.215Z\", \"notes\": \"Director 决策 kill: loss 持续指数 divergence (step 10: 908 → step 15: 24,650 → step 20: 1.34e7)。根因: recall penalty 产生 5-10x 更强梯度，在 QLoRA 4-bit 下加剧 KL 爆炸，kl_coef=0.01 × KL=1.42e9 = 1.42e7 完全主导 loss。训练 step 39 被 kill。ckpt-20 将用于 eval 关闭 P0+P1 对比线。\"}, \"mvp2_eval_ced_kl001_r4_multi\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:59:22.291Z\", \"updated_at\": \"2026-05-14T21:27:25.338Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 10,20,30,40,60,70,80 --quantize --resume\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"78850\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_multi.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Multi-checkpoint eval of ced_kl001_r4 (steps 10-80) to get full reward→eval correlation and identify best checkpoint for MVP-2 judgment\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}, \"notes\": \"Director 指令: ckpt-30 评完即停。进程在 ckpt-40 推理 3% 时被 kill，非异常崩溃。已完成 6/9 个 ckpt eval: 10,20,30,50,60,90（ckpt-40 中断，ckpt-70/80 未执行）。F1 随 step 单调上升: 0.003→0.009→0.034→0.156→0.147→0.211。best=ckpt-90 (F1=0.211)。Evi-F1 稳定在 0.42-0.72，EDCR 随 step 下降（0.998→0.858）。结果路径: /root/autodl-tmp/eval_results/grpo_ced_kl001/\", \"conclusion\": \"killed\", \"reproduce\": {\"finished_at\": \"2026-05-14T21:18:34.133Z\"}, \"failure_reason\": \"进程在 ckpt-30 eval 完成后继续执行 ckpt-40，推理 3% 时被外部 kill（符合 Director 指令：ckpt-30 评完即停）。监控系统检测 5 次 dead process 后 auto-resolved as failed。非异常崩溃。\", \"completed_at\": \"2026-05-14T21:18:34.860Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:18:36.087981+00:00\"}]}, \"metrics\": {\"checkpoint-10\": {\"f1\": 0.003, \"ign_f1\": 0.003, \"evi_f1\": 0.72, \"edcr\": 0.9983, \"format_ok_rate\": 0.999}, \"checkpoint-20\": {\"f1\": 0.0088, \"ign_f1\": 0.0088, \"evi_f1\": 0.423, \"edcr\": 0.9954, \"format_ok_rate\": 0.999}, \"checkpoint-30\": {\"f1\": 0.0338, \"ign_f1\": 0.0338, \"evi_f1\": 0.5889, \"edcr\": 0.9798, \"format_ok_rate\": 1}, \"checkpoint-50\": {\"f1\": 0.1563, \"ign_f1\": 0.1563, \"evi_f1\": 0.5643, \"edcr\": 0.8858, \"format_ok_rate\": 0.999}, \"checkpoint-60\": {\"f1\": 0.1467, \"ign_f1\": 0.1467, \"evi_f1\": 0.5763, \"edcr\": 0.9062, \"format_ok_rate\": 1}, \"checkpoint-90\": {\"f1\": 0.2108, \"ign_f1\": 0.2108, \"evi_f1\": 0.5666, \"edcr\": 0.8584, \"format_ok_rate\": 1}}}, \"mvp2_grpo_ced_lr5e6_rp_r1\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T19:44:15.272Z\", \"updated_at\": \"2026-05-14T20:44:07.125Z\", \"hypothesis\": \"D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T19:59:16.121Z\", \"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_ced_lr5e6_rp --num_generations 8 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-6 --seed 42 --kl_coef 0.01 --save_steps 20 --save_total_limit 20 --max_steps 200 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --ced_recall_penalty --wandb_run_name grpo-s3-ced-lr5e6-rp-r1\", \"wandb_run_id\": \"grpo-s3-ced-lr5e6-rp-r1\", \"finished_at\": \"2026-05-14T20:44:01.103Z\", \"training_hours\": 0.75}, \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"completed_at\": \"2026-05-14T19:59:43.146Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:59:44.524953+00:00\"}, {\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:44:03.547281+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"诊断结果：bash 引号不匹配（unexpected EOF while looking for matching '\\\"'），命令未到达 Python。EXIT_CODE=2。原因：submit_training_job 的 bash -c \\\"...\\\" 外层双引号与命令内部双引号冲突。--ced_recall_penalty 参数在 grpo_trainer.py:406 有定义，参数本身无问题。GPU 1/3 空闲可用。修复方案：用单引号包裹 bash -c '...' 或修复引号转义。需要以 rp_r2 重新提交。\"}}, \"notes\": \"Director D-URGENT: 与 rp_r2 冲突，同 GPU(cuda:3) 同 output_dir(/root/autodl-tmp/grpo_ced_lr5e6_rp/)。PID 94055 killed，保留 rp_r2 (PID 94758) 因其有标准化 submit_training_job 记录。\", \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"account\": \"root\", \"pid\": \"94055\", \"command\": \"bash /root/autodl-tmp/scripts/train_ced_lr5e6_rp.sh\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 3053, \"model_name\": \"Qwen3-4B + SFT adapter\", \"seed\": 42, \"checkpoint_source\": \"SFT from scratch (no GRPO checkpoint)\", \"eval_data\": \"N/A - training experiment\"}, \"conclusion\": \"failed\"}, \"mvp2_grpo_ced_lr5e6_p1_r1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:28:59.245Z\", \"updated_at\": \"2026-05-14T20:31:06.969Z\", \"hypothesis\": \"D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.\", \"spec\": {\"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"account\": \"root\"}, \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:1\", \"conclusion\": \"killed\", \"notes\": \"Superseded by mvp2_grpo_ced_lr5e6_rp_r1 per Director D032. Never submitted.\", \"completed_at\": \"2026-05-14T20:31:06.969Z\"}, \"mvp2_eval_ced_kl001_r4_step90\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:19:58.623Z\", \"updated_at\": \"2026-05-14T20:01:45.201Z\", \"hypothesis\": \"Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && ... && python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 90 --quantize\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"83207\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO ced_kl001 step-90\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-90\", \"eval_data\": \"DocRED dev set\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-90\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_step90.log\"}, \"notes\": \"2026-05-15 03:20 UTC: ckpt-90 inference 31/62 (50%), ~45 min remaining. Started 02:32 UTC.\", \"reproduce\": {\"finished_at\": \"2026-05-14T19:57:37.435Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:57:39.702949+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.2108, \"ign_f1\": 0.2108, \"evi_f1\": 0.5666, \"edcr\": 0.8584, \"pred_count\": 11160, \"n_truncated\": 22, \"format_ok_rate\": 1, \"n_documents\": 985}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T20:01:45.201Z\"}, \"mvp2_eval_ced_kl001_r4_ckpt7080\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:50:04.595Z\", \"updated_at\": \"2026-05-14T19:58:46.631Z\", \"hypothesis\": \"Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"rtx5090-4x\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T19:50:27.696Z\", \"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && PYTHONUNBUFFERED=1 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 70,80 --quantize --resume\\\"\"}, \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && PYTHONUNBUFFERED=1 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 70,80 --quantize --resume\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"91681\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_ckpt7080.log\", \"submitted_at\": \"2026-05-14T19:50:29.033Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 497.6, \"gpu_hours\": 0.14}, \"pid\": \"91681\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_ckpt7080.log\", \"conclusion\": \"failed\", \"notes\": \"Process died shortly after start - likely OOM on cuda:3 (same issue as high eval crash during ckpt-70). cuda:3 may have insufficient free VRAM for eval. ckpt-70/80 will be covered by multi eval on cuda:2.\", \"completed_at\": \"2026-05-14T19:58:46.631Z\"}, \"mvp2_eval_ced_kl001_r4_high\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:19:07.637Z\", \"updated_at\": \"2026-05-14T19:47:58.282Z\", \"hypothesis\": \"High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"spec\": {\"command\": \"python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 60,70,80,90 --quantize --resume\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"81962\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO ced_kl001\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001\", \"eval_data\": \"DocRED dev set\"}, \"notes\": \"1/4 checkpoints completed (ckpt-60). Process crashed during ckpt-70 inference at 8% - likely OOM or killed. cuda:3 still has 9503 MiB residual. ckpt-90 eval running separately on cuda:1 (mvp2_eval_ced_kl001_r4_step90).\", \"reproduce\": {\"finished_at\": \"2026-05-14T19:45:42.328Z\"}, \"failure_reason\": \"process dead 5× with no sentinel/W&B — auto-resolved as failed\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T19:45:43.350Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:45:48.432665+00:00\"}]}, \"metrics\": {\"checkpoint_60\": {\"rel_f1\": 0.1467, \"ign_f1\": 0.1467, \"precision\": 0.1909, \"recall\": 0.1192, \"evi_f1\": 0.5763, \"edcr\": 0.9062, \"pred_count\": 10041, \"gold_count\": 12151, \"n_truncated\": 16, \"format_ok_rate\": 1}, \"note\": \"Only ckpt-60 completed. Process died during ckpt-70 inference at 8% (5/62 batch). ckpt-80/90 never started.\"}}, \"mvp2_eval_ced_kl001_r4_step100\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:08:31.821Z\", \"updated_at\": \"2026-05-14T19:41:30.318Z\", \"hypothesis\": \"Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"spec\": {\"command\": \"python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001_step100 --checkpoints 100 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"80789\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_step100.log\", \"submitted_at\": \"2026-05-14T18:09:02.064Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"model_name\": \"Qwen3-4B + SFT adapter + GRPO ced_kl001 step-100\", \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-100\", \"eval_data\": \"DocRED dev set\", \"data_count\": 998, \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-100\", \"wall_clock_seconds\": 5458.4, \"gpu_hours\": 1.52}, \"notes\": \"2026-05-15 03:20 UTC: ckpt-100 inference 48/62 (77%), ~20 min remaining. Started 02:09 UTC.\", \"reproduce\": {\"finished_at\": \"2026-05-14T19:35:23.622Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T19:35:25.057156+00:00\"}]}, \"metrics\": {\"rel_f1\": 0.2167, \"ign_f1\": 0.2167, \"precision\": 0.2849, \"recall\": 0.1749, \"evi_f1\": 0.5746, \"evi_precision\": 0.5244, \"evi_recall\": 0.6353, \"edcr\": 0.8539, \"pred_count\": 7460, \"gold_count\": 12151, \"tp\": 2125, \"n_truncated\": 21, \"format_ok_rate\": 1}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T19:40:00.432Z\"}, \"mvp2_eval_ced_kl001_r4_ckpt90\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:18:13.270Z\", \"updated_at\": \"2026-05-14T19:17:36.777Z\", \"spec\": {\"command\": \"python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --checkpoints 90 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"unknown\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_ckpt90.log\", \"submitted_at\": \"2026-05-14T18:18:20.407Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": 985, \"model_name\": \"Qwen3-4B + SFT + GRPO ced_kl001 step-90\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-90\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 3556.4, \"gpu_hours\": 0.99}, \"hypothesis\": \"Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"conclusion\": \"killed\", \"notes\": \"重复条目，被 mvp2_eval_ced_kl001_r4_step90 (cuda:1, PID 83207, 有 cron 监控) 取代。本条目无 cron、无独立进程。\", \"completed_at\": \"2026-05-14T19:17:36.777Z\"}, \"mvp2_eval_ced_kl001_r4_ckpt10\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:59:08.638Z\", \"updated_at\": \"2026-05-14T19:14:08.763Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 10 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"78857\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_eval_ced_kl001_r4_ckpt10.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Early checkpoint eval (step 10) of ced_kl001_r4 — part of multi-checkpoint trend analysis for MVP-2 judgment\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-10\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}, \"notes\": \"Eval 完成（由 multi eval 执行）。ckpt-10 rel_f1=0.003 catastrophic — 模型几乎丧失 relation 抽取能力 (34 TP / 10839 pred)，但 evi_f1=0.72 和 edcr=0.998 反而高。GRPO 训练极早期就严重损害 relation 能力。\", \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.00296, \"rel_precision\": 0.00314, \"rel_recall\": 0.0028, \"evi_f1\": 0.72, \"evi_precision\": 0.6429, \"evi_recall\": 0.8182, \"edcr\": 0.9983, \"n_parseable\": 984, \"n_truncated\": 24, \"n_predictions\": 11621, \"tp\": 34, \"pred_count\": 10839, \"gold_count\": 12151, \"inference_time_seconds\": 5211.4}, \"checkpoint_path\": \"/root/autodl-tmp/eval_results/grpo_ced_kl001/checkpoint-10\", \"log_path\": \"/root/autodl-tmp/eval_results/grpo_ced_kl001/checkpoint-10/metrics.json\", \"completed_at\": \"2026-05-14T19:13:58.921Z\"}, \"mvp2_eval_ced_kl001_r4_early\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:12:53.581Z\", \"updated_at\": \"2026-05-14T18:31:18.065Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python -m freige.eval.batch_eval --exp_dir /root/autodl-tmp/grpo_ced_kl001 --sft_adapter /root/autodl-tmp/sft_output --output_dir /root/autodl-tmp/eval_results/grpo_ced_kl001 --checkpoints 50 --quantize\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"75581\", \"log_path\": \"/tmp/eval_ced_kl001_ckpt50.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Early eval of ced_kl001_r4 best-reward checkpoint (step 50, reward=1.1009) to get early signal on CED vs SFT baseline\", \"parent\": \"mvp2_grpo_ced_kl001_r4\", \"checkpoint_source\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-50\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\"}, \"notes\": \"**Checkpoint-50 eval 完成，结果极差——MVP-2 双指标均 FAIL：**\\\\n\\\\n- rel_f1: 0.1563 vs SFT 0.4057 (Δ=-24.9pp)，远低于 -5pp 阈值\\\\n- evi_f1: 0.5643 vs SFT 0.7979 (Δ=-23.4pp)，需 +2pp 却暴跌\\\\n- EDCR: 0.8858 vs SFT 0.7118 (Δ=+17.4pp)，唯一改善项\\\\n- recall 崩塌 (0.117 vs gold 12151)，precision 也低 (0.236)\\\\n\\\\n**诊断**: training reward 上升 (1.101) 但 eval F1 崩塌，说明 GRPO 训练在优化 reward proxy 而非实际任务表现。模型学会了高 EDCR（少引用 distractor）但牺牲了大量 recall。pred_count=6032 vs gold=12151，预测数量严重不足。\\\\n\\\\n仍需等待 step-90 (reward=1.37) 的 eval 结果——如果 step-90 也崩塌，则 CED reward 设计需要根本性修改。\", \"conclusion\": \"negative\", \"metrics\": {\"f1\": 0.1563, \"ign_f1\": 0.1563, \"evi_f1\": 0.5643, \"edcr\": 0.8858, \"precision\": 0.2356, \"recall\": 0.1169, \"evi_precision\": 0.4864, \"evi_recall\": 0.6721, \"format_ok_rate\": 0.999, \"n_parseable\": 984, \"n_truncated\": 11, \"n_predictions\": 9250, \"tp\": 1421, \"pred_count\": 6032, \"gold_count\": 12151}, \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_kl001/checkpoint-50\", \"log_path\": \"/tmp/eval_ced_kl001_ckpt50.log\", \"completed_at\": \"2026-05-14T18:31:06.454Z\"}, \"mvp2_grpo_flatnli_r6\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:25:07.083Z\", \"updated_at\": \"2026-05-14T18:17:52.909Z\", \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && ... && PYTHONUNBUFFERED=1 python -m freige.training.grpo_trainer --stage 2 --kl_coef 0.01 --num_generations 8 --max_steps 100 --wandb_run_name grpo-s2-flatnli-r6\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"76958\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r6.log\", \"submitted_at\": \"2026-05-14T17:25:30.099Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 3061.0, \"gpu_hours\": 0.85}, \"parent\": \"mvp2_grpo_flatnli_r5\", \"notes\": \"D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100。从 SFT 全新训练。\\n\\n**D024 Kill — Mode Collapse Confirmed (step 25)**:\\n- frac_zero_std: 0.1→0.4→0.6→0.7→0.9 (单调上升，破 0.8 阈值)\\n- f1_reward=0, flat_nli_reward=0 — 抽取和 NLI 完全死亡\\n- reward 100% format hacking (0.293)\\n- completion_length 缩短 773→586→399\\n- KL step 5 爆炸至 1.23 亿后回落\\n\\n**科学结论**: D020 配置下 flat-NLI reward 信号不足以维持 GRPO 多样性。与 extract_r4 (step 10 collapse) 模式一致。CED 是三种 reward type 中唯一能稳定训练的。\", \"conclusion\": \"negative\", \"metrics\": {\"steps_completed\": 25, \"final_frac_zero_std\": 0.9, \"final_f1_reward\": 0, \"final_flat_nli_reward\": 0, \"final_format_reward\": 0.293, \"collapse_step\": 25}, \"checkpoint_path\": \"N/A (killed at step 25, mode collapse)\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r6.log\", \"completed_at\": \"2026-05-14T18:16:31.087Z\"}, \"mvp2_grpo_ced_kl001_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:32.529Z\", \"updated_at\": \"2026-05-14T18:11:53.975Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_ced_kl001 --num_generations 8 --reward_device cuda --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-5 --seed 42 --kl_coef 0.01 --save_steps 10 --save_total_limit 20 --max_steps 100 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 1 --wandb_run_name grpo-s3-ced-kl001-r4\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"68084\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_kl001_r4.log\", \"submitted_at\": \"2026-05-14T15:32:32.454Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"kl_coef=0.01 + num_generations=8 prevents mode collapse (vs r5 kl=0/gen=4 which collapsed at step 250). 100-step probe to verify KL stability before full run.\", \"parent\": \"mvp2_grpo_ced_r5\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0.01, \"save_steps\": 10, \"save_total_limit\": 20, \"max_steps\": 100, \"num_iterations\": 1, \"num_generations\": 8, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"quantization\": \"QLoRA 4-bit NF4\", \"reward_device\": \"cuda\"}, \"wall_clock_seconds\": 9550.2, \"gpu_hours\": 2.65}, \"notes\": \"D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100 探测。✅ F1 门控已包含。\\n\\n**训练完成 (100/100 steps, EXIT_CODE=0, 2h31m)**:\\n- Final (step 100): reward=1.195, f1=0.573, ced=0.328, frac_zero_std=0.2, KL=0.118\\n- **True best: step 90** (reward=1.370, f1=0.720, ced=0.353) — 比 step 50 (1.101) 高 24%\\n- Reward trajectory: 0.22→1.37 (~5x 提升)，batch_size=1 方差大但整体上升\\n- 无 mode collapse（frac_zero_std 从早期 0.3-0.8 降至后半程 0.0-0.2）\\n- KL 稳定（0.10-0.15 range，kl_coef=0.01 控制有效）\\n- 所有 10 个 checkpoint 可用 (10-100)\\n\\n**Eval 覆盖**:\\n- cuda:1: ckpt-50 eval (mvp2_eval_ced_kl001_r4_early)\\n- cuda:2: ckpt 10-80 multi eval (mvp2_eval_ced_kl001_r4_multi)\\n- cuda:0: ckpt 90+100 eval (mvp2_eval_ced_kl001_r4_last)\", \"reproduce\": {\"finished_at\": \"2026-05-14T18:05:49.446Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:05:50.777825+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/grpo_ced_kl001/\", \"metrics\": {\"final_step\": 100, \"train_runtime_s\": 9069.88, \"reward_final\": 1.195, \"f1_reward_final\": 0.573, \"ced_reward_final\": 0.328, \"format_reward_final\": 0.293, \"frac_zero_std_final\": 0.2, \"kl_final\": 0.118, \"loss_final\": -0.009, \"grad_norm_final\": 0.14, \"entropy_final\": 0.067, \"completion_length_mean_final\": 520.8, \"best_reward_step\": 90, \"best_reward\": 1.37, \"best_f1_reward\": 0.72, \"best_ced_reward\": 0.353}, \"completed_at\": \"2026-05-14T18:11:42.680Z\"}, \"mvp2_grpo_extract_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T16:54:59.403Z\", \"updated_at\": \"2026-05-14T17:40:25.731Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && ... && python -m freige.training.grpo_trainer --stage 1 --kl_coef 0.01 --num_generations 8 --max_steps 100 ...\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"73264\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_extract_r4.log\", \"submitted_at\": \"2026-05-14T16:55:57.491Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"wall_clock_seconds\": 2668.2, \"gpu_hours\": 0.74}, \"hypothesis\": \"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.\", \"parent\": \"mvp2_grpo_extract_r3\", \"notes\": \"D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100 探测。与 ced_kl001_r4 (cuda:0) 构成并行 ablation——相同稳定配置、不同 reward type (extract-only vs CED)。\\n\\n**Mode collapse confirmed → KILLED at step ~30**:\\n- step 5: frac_zero_std=0.2, f1=0.016（初始信号）\\n- step 10-30: frac_zero_std=0.7-0.8, f1_reward=0（完全 collapse）\\n- reward 全部来自 format_reward (~0.29)，模型放弃 extraction\\n- 对比 ced_kl001_r4 同期在 step 20-40 恢复（frac→0.0, f1→0.240），extract_r4 无恢复信号\\n\\n**科学价值**：证明 extraction-only reward（format+f1, 无 CED）在 D020 配置下无法维持 GRPO 多样性。CED reward 通道可能是帮助 ced_kl001_r4 摆脱初期 mode collapse 的关键因素。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T17:40:25.733Z\"}, \"mvp2_grpo_flatnli_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T16:55:02.197Z\", \"updated_at\": \"2026-05-14T17:26:55.692Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && ... && python -m freige.training.grpo_trainer --stage 2 --kl_coef 0.01 --num_generations 8 --max_steps 200 --resume_from_checkpoint /root/autodl-tmp/grpo_flatnli_r3/checkpoint-100 ...\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"73407\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r5.log\", \"submitted_at\": \"2026-05-14T16:56:01.219Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"wall_clock_seconds\": 1854.5, \"gpu_hours\": 0.52}, \"hypothesis\": \"Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.\", \"parent\": \"mvp2_grpo_flatnli_r4\", \"notes\": \"Director 决策 kill：从 r3 (kl_coef=0) checkpoint-100 恢复后立即崩溃。frac_zero_std: 0.0(r3)→0.9(step 105)→0.7→0.5→0.8(step 120)，0.5-0.9 震荡无收敛。KL 全程 0.44-0.49 高位。根因：kl_coef=0 累积的 policy 漂移 + kl_coef=0.01 penalty 形成对抗。教训：不能从 kl_coef=0 的 checkpoint 恢复加 KL penalty。flatnli_r6 从 SFT 全新训练。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T17:26:55.692Z\"}, \"mvp2_sft_eval_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:52:38.174Z\", \"updated_at\": \"2026-05-14T17:06:57.010Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --quantize --output_dir /root/autodl-tmp/sft_eval_r3_results --seed 42\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"62352\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_sft_eval_r3.log\", \"submitted_at\": \"2026-05-14T14:53:52.360Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"SFT baseline eval with unified eval code (consolidated parse_model_output) for fair comparison with r2\", \"parent\": \"mvp2_sft_warmup\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 7718.1, \"gpu_hours\": 2.14}, \"reproduce\": {\"finished_at\": \"2026-05-14T16:42:11.014Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T16:42:12.047698+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"ign_f1\": 0.4057, \"evi_f1\": 0.7979, \"edcr\": 0.7118, \"precision\": 0.4043, \"recall\": 0.407, \"evi_precision\": 0.8035, \"evi_recall\": 0.7924, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.626, \"n_parseable\": 617, \"n_truncated\": 367, \"n_predictions\": 18815}, \"checkpoint_path\": \"/root/autodl-tmp/sft_eval_r3_results/\", \"completed_at\": \"2026-05-14T17:02:30.442Z\", \"notes\": \"统一 eval 代码验证：r3 与 r2 所有指标完全一致（差异=0.00pp），含 _repair_truncated_json 的统一 eval 脚本未引入任何偏差。SFT baseline 可靠确认：rel_f1=0.4057, evi_f1=0.7979, edcr=0.7118。983 parseable / 617 field_complete / 367 truncated / 18815 predictions。\"}, \"mvp2_grpo_extract_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:31:48.781Z\", \"updated_at\": \"2026-05-14T16:59:20.304Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 1 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 0.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"53149\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_extract_r3.log\", \"submitted_at\": \"2026-05-14T12:31:48.738Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0 establishes stable GRPO baseline\", \"parent\": \"mvp2_grpo_extract\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 0, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 12041.2, \"gpu_hours\": 3.34}, \"notes\": \"Negative result (756/756 steps completed). 两阶段行为：(1) step 1-520 f1_reward 在 0.02-0.49 波动，completion length ~43 tokens 稳定，看似健康；(2) 实际最后 100+ 步 grad_norm=0, frac_reward_zero_std=1.0, loss=0.0, entropy≈0.005。f1 波动是 SFT 初始化残留，非 GRPO 学习。停滞机制：kl_coef=0 + num_generations=4 → 4 个相同输出 → reward_std=0 → GRPO advantage=0 → 梯度为零。与 ced_r5 的差异：无 CED reward 通道，模型没 drift 到短输出（保持在 SFT 水平），但也完全停止学习。科学价值：证明 num_generations=4 不足以维持 GRPO 多样性，kl_coef=0 下 extraction-only 停滞而 CED collapse 更严重。\", \"reproduce\": {\"finished_at\": \"2026-05-14T15:52:29.058Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T15:52:29.969Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:52:31.006940+00:00\"}]}}, \"mvp2_grpo_flatnli_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:31.804Z\", \"updated_at\": \"2026-05-14T16:56:12.080Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python -m freige.training.grpo_trainer --stage 2 --reward_device cuda --resume_from_checkpoint /root/autodl-tmp/grpo_flatnli_r3/checkpoint-100 --save_total_limit 40 --wandb_run_name grpo-s2-flatnli-r4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"67050\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r4.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"resume_from\": \"/root/autodl-tmp/grpo_flatnli_r3/checkpoint-100\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"reward_device\": \"cuda\", \"quantization\": \"QLoRA 4-bit NF4\"}}, \"pid\": 67050, \"notes\": \"Director 指令 kill: kl=0+gen=4 配置已在 ced_r5/extract_r3/flatnli_r3 三个实验崩塌，统一切到 kl=0.01+gen=8。flatnli_r4 运行 step 104→~130（~30 min），step_time ~34s/step。用 flatnli_r5 从 checkpoint-100 重启。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T16:54:43.884Z\"}, \"mvp2_grpo_ced_kl001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:32:53.111Z\", \"updated_at\": \"2026-05-14T15:33:06.208Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 3 --kl_coef 0.01 --num_iterations 1 --save_steps 20 --save_total_limit 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"64981\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_kl001.log\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\", \"parent\": \"mvp2_grpo_ced_r5\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0.01, \"save_steps\": 20, \"save_total_limit\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}}, \"notes\": \"三次失败：r1 --lr 不识别 (EXIT_CODE=2)，r2 conda 未激活 python not found (EXIT_CODE=127)，r3 缺 --data_dir。已在 r4 修正所有问题。\", \"hypothesis\": \"kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary\", \"reproduce\": {\"finished_at\": \"2026-05-14T15:20:19.022Z\"}, \"failure_reason\": \"EXIT_CODE=2 (shell misuse / syntax)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T15:20:19.862Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T15:20:20.950140+00:00\"}]}}, \"mvp2_grpo_ced_r5\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:31:45.606Z\", \"updated_at\": \"2026-05-14T15:32:21.817Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 3 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"53071\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_r5.log\", \"submitted_at\": \"2026-05-14T12:31:45.554Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"CED reward (format×0.3, f1×3.0, ced×1.0) with kl_coef=0 trains stably and improves Evi-F1 over SFT baseline\", \"parent\": \"mvp2_grpo_ced_r4\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 9887.5, \"gpu_hours\": 2.75}, \"notes\": \"⚠️ Mode collapse confirmed: step 250+ f1_reward=0, completion length collapsed to fixed 34 tokens, frac_reward_zero_std=0.9-1.0. Model learned to produce short fixed-format output maximizing ced_reward (0.99) + format_reward (0.3) while abandoning relation extraction (f1=0). Early checkpoints (pre-collapse) lost due to save_total_limit=5 — only steps 400-480 remain, all post-collapse. Current checkpoints likely unusable for eval.\", \"conclusion\": \"negative\", \"checkpoint_path\": \"N/A (all checkpoints post-collapse, unusable)\", \"completed_at\": \"2026-05-14T15:29:18.460Z\"}, \"mvp2_grpo_flatnli_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:31:52.782Z\", \"updated_at\": \"2026-05-14T15:27:55.267Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 2 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"53292\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r3.log\", \"submitted_at\": \"2026-05-14T12:31:52.703Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Flat-NLI reward (format×0.3, f1×3.0, ced×1.0) with kl_coef=0 validates non-contrastive evidence baseline\", \"parent\": \"mvp2_grpo_flatnli\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 9527.7, \"gpu_hours\": 2.65, \"checkpoint_path\": \"/root/autodl-tmp/checkpoints_backup/flatnli_r3_healthy/\"}, \"notes\": \"Director 指令 kill：NLI 推理在 CPU 导致 10x 减速（~100-125s/step vs 应有 ~12s/step）。训练本身健康——step 104/756, grad_norm=0.37, f1 从 step 84 起出现, flat_nli_reward=0.52, entropy=0.046。Checkpoint 已备份。修复 --reward_device cuda 后以 flatnli_r4 重启。\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T15:27:48.503Z\"}, \"mvp2_sft_eval_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:45:46.160Z\", \"updated_at\": \"2026-05-14T14:54:07.338Z\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 16 --max_new_tokens 1024 --quantize --output_dir /root/autodl-tmp/sft_eval_results --seed 42\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"55410\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_sft_eval_r2.log\", \"submitted_at\": \"2026-05-14T12:45:45.981Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"SFT baseline eval on DocRED dev set (batch_size=16 accelerated)\", \"parent\": \"mvp2_sft_warmup\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 7701.4, \"gpu_hours\": 2.14}, \"reproduce\": {\"finished_at\": \"2026-05-14T14:52:20.498Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T14:52:21.560816+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"rel_f1\": 0.4057, \"ign_f1\": 0.4057, \"evi_f1\": 0.7979, \"edcr\": 0.7118, \"precision\": 0.4043, \"recall\": 0.407, \"evi_precision\": 0.8035, \"evi_recall\": 0.7924, \"format_ok_rate\": 0.998, \"format_compliance_rate\": 0.626, \"n_parseable\": 617, \"n_truncated\": 367, \"n_predictions\": 18815, \"inference_time_seconds\": 6484.7}, \"checkpoint_path\": \"/root/autodl-tmp/sft_eval_results/\", \"completed_at\": \"2026-05-14T14:54:07.338Z\"}, \"mvp2_sft_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:10:37.449Z\", \"updated_at\": \"2026-05-14T12:46:04.523Z\", \"spec\": {\"command\": \"python -m freige.eval.inference --model_path sft_output --base_model Qwen3-4B --split dev\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:1\"], \"pid\": \"47293\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_sft_eval.log\", \"submitted_at\": \"2026-05-14T11:48:46.335Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"SFT baseline eval on DocRED dev set\", \"parent\": \"mvp2_sft_warmup\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred/dev.json\", \"wall_clock_seconds\": 3416.3, \"gpu_hours\": 0.95}, \"conclusion\": \"killed\", \"reproduce\": {\"finished_at\": \"2026-05-14T12:45:42.027Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"completed_at\": \"2026-05-14T12:45:42.659Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:45:43.534491+00:00\"}]}, \"notes\": \"Killed intentionally to restart with batch_size=16 (was batch_size=4, ~6h → ~1.5h). Director approved.\"}, \"mvp2_grpo_flatnli_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:23.287Z\", \"updated_at\": \"2026-05-14T12:30:08.865Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 2 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"50941\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli_r2.log\", \"submitted_at\": \"2026-05-14T12:10:23.256Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Flat-NLI reward (format×0.3, f1×3.0, ced×1.0) with kl_coef=0 validates non-contrastive evidence baseline\", \"parent\": \"mvp2_grpo_flatnli\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 1174.2, \"gpu_hours\": 0.33}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T12:29:57.408Z\", \"notes\": \"Killed: Director 指令暂不提交 r2，等原始 flatnli 分析完再决定配置。\"}, \"mvp2_grpo_extract_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:19.532Z\", \"updated_at\": \"2026-05-14T12:30:08.099Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 1 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 0.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"50670\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_extract_r2.log\", \"submitted_at\": \"2026-05-14T12:10:19.491Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0 establishes stable GRPO baseline\", \"parent\": \"mvp2_grpo_extract\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 0, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 1166.7, \"gpu_hours\": 0.32}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T12:29:46.151Z\", \"notes\": \"Killed: Director 指令暂不提交 r2，等原始 extract 分析完再决定配置。\"}, \"mvp2_grpo_ced_r4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:15.698Z\", \"updated_at\": \"2026-05-14T12:30:06.177Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 3 --kl_coef 0.0 --num_iterations 1 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --lr 5e-5 --gradient_accumulation_steps 16 --num_generations 4\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"50529\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_r4.log\", \"submitted_at\": \"2026-05-14T12:10:15.624Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"CED reward (format×0.3, f1×3.0, ced×1.0) with kl_coef=0 (D008 fix) achieves Evi-F1 improvement over SFT baseline\", \"parent\": \"mvp2_grpo_ced_r3\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4, \"quantization\": \"QLoRA 4-bit NF4\"}, \"wall_clock_seconds\": 1169.5, \"gpu_hours\": 0.32}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T12:29:45.113Z\", \"notes\": \"Killed: 上一 session 使用 kl_coef=0.0/lr=5e-5 启动，但 Director 要求 D009 配置 (kl_coef=0.5, lr=5e-6, warmup_steps=200)。需等 extract/flatnli 分析完再用正确配置重新提交。\"}, \"mvp2_grpo_extract\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:10:35.796Z\", \"updated_at\": \"2026-05-14T12:25:32.094Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 1 --ced_reward_weight 0.0 --format_reward_weight 0.3 --f1_reward_weight 3.0 --num_iterations 1 --kl_coef 0.05 --lr 5e-5\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:2\"], \"pid\": \"47561\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_extract.log\", \"submitted_at\": \"2026-05-14T11:48:50.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred/train_annotated.json\", \"data_count\": 3027, \"model_name\": \"Qwen3-4B (QLoRA from SFT warmup)\", \"seed\": 42, \"hypothesis\": \"Extraction-only reward (format+F1, no CED) establishes GRPO baseline\", \"parent\": \"mvp2_sft_warmup\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0.05, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 0}, \"wall_clock_seconds\": 1479.2, \"gpu_hours\": 0.41}, \"hypothesis\": \"Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1\", \"reproduce\": {\"finished_at\": \"2026-05-14T12:03:50.563Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:03:51.381207+00:00\"}]}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:13:29.284Z\", \"notes\": \"KL divergence explosion at step 5 due to kl_coef=0.05 + QLoRA 4-bit incompatibility (D008). QLoRA quantization noise makes ref/policy log-prob divergence unreliable, causing KL values to reach 10^8-10^11. Same root cause as r3 and flatnli. Fix: kl_coef=0.0 in r2 retries.\"}, \"mvp2_grpo_flatnli\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:10:33.848Z\", \"updated_at\": \"2026-05-14T12:13:34.747Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 2 --ced_reward_weight 1.0 --format_reward_weight 0.3 --f1_reward_weight 3.0 --num_iterations 1 --kl_coef 0.05 --lr 5e-5\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:3\"], \"pid\": \"47722\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_flatnli.log\", \"submitted_at\": \"2026-05-14T11:48:54.086Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Flat-NLI reward improves Evi-F1 over extraction-only but less than CED\", \"parent\": \"mvp2_sft_warmup\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0.05, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1}, \"wall_clock_seconds\": 1188.0, \"gpu_hours\": 0.33}, \"hypothesis\": \"Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:08:42.058Z\", \"notes\": \"KL divergence explosion at step 5 due to kl_coef=0.05 + QLoRA 4-bit incompatibility (D008). QLoRA quantization noise makes ref/policy log-prob divergence unreliable. Same root cause as r3 and extract. Fix: kl_coef=0.0 in r2 retries.\"}, \"mvp2_grpo_ced_r3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:47:53.099Z\", \"updated_at\": \"2026-05-14T12:09:23.005Z\", \"spec\": {\"command\": \"python -m freige.training.grpo_trainer --stage 3 --num_iterations 1 --kl_coef 0.05 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --max_kl 100 --lr 5e-5\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"47136\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_r3.log\", \"submitted_at\": \"2026-05-14T11:48:42.598Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"Reward weighting (format×0.3, f1×3.0, ced×1.0) with stable training (num_iterations=1, KL early stop) improves Evi-F1\", \"parent\": \"mvp2_grpo_ced_r1\", \"checkpoint_source\": \"/root/autodl-tmp/sft_output\", \"eval_data\": \"/root/autodl-tmp/data/docred\", \"hyperparams\": {\"learning_rate\": \"5e-5\", \"kl_coef\": 0.05, \"save_steps\": 20, \"num_iterations\": 1, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"max_kl\": 100}, \"wall_clock_seconds\": 1061.5, \"gpu_hours\": 0.29}, \"hypothesis\": \"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline\", \"reproduce\": {\"finished_at\": \"2026-05-14T12:06:23.600Z\"}, \"failure_reason\": \"EXIT_CODE=129 (non-zero)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T12:06:24.147Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:06:25.189118+00:00\"}]}, \"notes\": \"KL divergence explosion at step 5: first pass KL=4.4M, second pass KL=69.5B (threshold=100). KL early stopping correctly triggered, model saved but no useful training occurred.\\n\\nRoot cause: single-GPU training without --gradient_accumulation_steps (effective batch=1) → extremely noisy gradients → policy diverged from reference in 5 steps. Combined with QLoRA merge rounding amplifying initial policy-reference gap.\\n\\nKey metrics at step 5: loss=269987, kl=4.4M, entropy=0.084 (near 0), format_reward=0.10, f1_reward=0.05, ced_reward=0.15, grad_norm=0.16. EXIT_CODE=129 is artifact of KL early stop exit path.\\n\\nerror_type: hyperparameter | can_auto_fix: false\\nFix options: (1) add --gradient_accumulation_steps 16 for effective batch ~16; (2) reduce lr from 5e-5 to 5e-6; (3) increase kl_coef from 0.05 to 0.5; (4) lr warmup steps\"}, \"mvp2_grpo_ced_r2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:58:11.663Z\", \"updated_at\": \"2026-05-14T11:31:49.724Z\", \"spec\": {\"command\": \"accelerate launch --config_file freige/configs/accelerate_4gpu.yaml -m freige.training.grpo_trainer --model_name Qwen3-4B --learning_rate 2e-5 --kl_coef 0.05 --save_steps 20 --format_reward_weight 0.3 --f1_reward_weight 3.0 --ced_reward_weight 1.0 --num_iterations 2\", \"server\": \"rtx5090-4x\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + KL=0.05 + save_steps=20 + num_iterations=2 prevents mode collapse and improves Evi-F1\", \"parent\": \"mvp2_grpo_ced_r1\", \"hyperparams\": {\"learning_rate\": \"2e-5\", \"kl_coef\": 0.05, \"save_steps\": 20, \"num_iterations\": 2, \"format_reward_weight\": 0.3, \"f1_reward_weight\": 3, \"ced_reward_weight\": 1, \"per_device_batch_size\": 1, \"gradient_accumulation_steps\": 16, \"num_generations\": 4}}, \"reproduce\": {\"finished_at\": \"2026-05-14T11:26:47.993Z\"}, \"failure_reason\": \"EXIT_CODE=137 (SIGKILL — OOM killer or manual kill)\", \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T11:26:48.502Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T11:26:49.285684+00:00\"}]}}, \"mvp2_grpo_ced_r1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:02:41.858Z\", \"updated_at\": \"2026-05-14T10:37:23.856Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && accelerate launch --config_file freige/configs/accelerate_4gpu.yaml -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_s3 --num_generations 4 --reward_device cpu --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-5 --seed 42 --wandb_run_name grpo-s3-ced-r1\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": \"24122\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced_r1.log\", \"submitted_at\": \"2026-05-14T08:02:41.839Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"hypothesis\": \"CED reward improves Evi-F1 over flat-NLI and extraction-only baselines\", \"wall_clock_seconds\": 8641.6, \"gpu_hours\": 9.6}, \"conclusion\": \"killed\", \"notes\": \"Mode collapse diagnosed at step 80/189 (F1=0.001, format reward hacking). Root causes and fixes applied to grpo_trainer.py:\\n\\n(A) Checkpoint: save_strategy was \\\"epoch\\\" → now supports --save_steps/--save_total_limit CLI args, defaults to steps-based saving. Validated: checkpoint-1/2 saved in dry-run.\\n\\n(B) Reward weighting: all 3 rewards (format/f1/ced) were equally summed by TRL → added WeightedRewardFn wrapper + --format_reward_weight/--f1_reward_weight/--ced_reward_weight CLI args. Dry-run confirmed weighting works (format raw=0.1 × w=0.3 → 0.03).\\n\\n(C) Clip ratio: num_iterations=1 (default) meant single pass, ratio≡1, clipping never activated → added --num_iterations CLI arg (set to 2 in r2). Also added --max_steps, --kl_coef (beta). Dry-run clip_ratio=0 expected (zero reward variance → zero advantage → no update needed).\\n\\n(D) Added --save_total_limit CLI arg (previously hardcoded to 2, now configurable).\\n\\nDry-run validated: 2 steps completed, checkpoints saved, no OOM with num_iterations=2 on 4xRTX5090. completions/clipped_ratio=1.0 (all hit max_completion_length=1024) — expected for cold-start without warmup.\", \"completed_at\": \"2026-05-14T10:26:43.488Z\"}, \"mvp2_grpo_ced\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:10:31.165Z\", \"updated_at\": \"2026-05-14T08:00:02.874Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && accelerate launch --config_file freige/configs/accelerate_4gpu.yaml -m freige.training.grpo_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_dir /root/autodl-tmp/data/docred --stage 3 --tau_start 0.3 --tau_end 0.5 --output_dir /root/autodl-tmp/grpo_s3 --num_generations 4 --reward_device cpu --per_device_batch_size 1 --gradient_accumulation_steps 16 --num_epochs 1 --learning_rate 5e-5 --seed 42 --wandb_run_name grpo-s3-ced\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": \"20973\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_grpo_ced.log\", \"submitted_at\": \"2026-05-14T07:19:59.045Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 2189.9, \"gpu_hours\": 2.43}, \"reproduce\": {\"finished_at\": \"2026-05-14T07:56:28.316Z\"}, \"failure_reason\": \"EXIT_CODE=1 (generic error — check log tail)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T07:56:28.916Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T07:56:29.797308+00:00\"}]}, \"notes\": \"失败原因: grpo_trainer.py:109 f1_reward_fn 中 p.get(\\\"tail\\\", \\\"\\\").lower() 报 AttributeError: 'NoneType' — 某些 parsed triple 的 \\\"tail\\\" 字段为 None，dict.get 有 key 时不返回 default | 运行 ~36min 后崩溃 | 修复方案: 用 (p.get(\\\"tail\\\") or \\\"\\\") 模式处理 None | error_type: infrastructure | can_auto_fix: true\"}, \"precompute_nli_train\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:05:48.887Z\", \"updated_at\": \"2026-05-14T07:35:24.549Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && python precompute_nli.py\\\"\", \"server\": \"gpu-5090-4x-1\", \"gpu\": [\"cuda:0\"], \"pid\": \"19212\", \"log_path\": \"~/runs/faith-evidence-ie/precompute_nli_train.log\", \"submitted_at\": \"2026-05-14T07:05:58.458Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/nli_cache/\", \"wall_clock_seconds\": 1766.1, \"gpu_hours\": 0.49}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T07:35:24.549Z\"}, \"mvp2_sft_warmup\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:09:47.819Z\", \"updated_at\": \"2026-05-14T07:10:19.285Z\", \"spec\": {\"command\": \"accelerate launch --config_file freige/configs/accelerate_4gpu.yaml -m freige.training.sft_trainer --model_name /root/autodl-tmp/models/Qwen3-4B --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/sft_output --deepspeed freige/configs/deepspeed_zero2.json --num_epochs 3 --per_device_batch_size 1 --gradient_accumulation_steps 16 --learning_rate 2e-4 --max_length 4096 --seed 42\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": \"16221\", \"log_path\": \"~/runs/faith-evidence-ie/mvp2_sft_warmup.log\", \"submitted_at\": \"2026-05-14T06:22:10.453Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/data/docred\", \"data_count\": {\"train\": 3027, \"dev\": 985}, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"gpu_model\": \"RTX 5090 32GB x4\", \"lora_rank\": 64, \"lora_alpha\": 128, \"quantization\": \"4-bit NF4 QLoRA\", \"deepspeed\": \"ZeRO-2 + CPU offload\", \"effective_batch_size\": 64, \"checkpoint_path\": \"/root/autodl-tmp/sft_output\", \"wall_clock_seconds\": 2888.8, \"gpu_hours\": 3.21}, \"conclusion\": \"success\", \"metrics\": {\"eval_loss\": 0.72, \"accuracy\": 0.835}, \"completed_at\": \"2026-05-14T07:10:19.285Z\"}, \"smoke_test_grpo\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T05:20:00.970Z\", \"updated_at\": \"2026-05-14T06:09:18.626Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && accelerate launch --num_processes 4 --mixed_precision bf16 -m freige.training.smoke_test\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": \"9823\", \"log_path\": \"~/runs/faith-evidence-ie/smoke_test_grpo.log\", \"submitted_at\": \"2026-05-14T05:54:45.178Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"N/A (smoke test)\", \"wall_clock_seconds\": 873.4, \"gpu_hours\": 0.97}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:09:18.626Z\"}, \"mvp1_ced_signal\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T04:48:46.220Z\", \"updated_at\": \"2026-05-14T05:48:05.545Z\", \"spec\": {\"command\": \"bash -c \\\"source /etc/network_turbo && export HF_HOME=/root/autodl-tmp/.hf_cache && export HF_HUB_DISABLE_XET=1 && export REQUESTS_CA_BUNDLE=/etc/ssl/certs/ca-certificates.crt && export SSL_CERT_FILE=/etc/ssl/certs/ca-certificates.crt && source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES='' python -m freige.analysis.ced_signal_validation --data_dir /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/mvp1_results --split dev --nli_model cross-encoder/nli-deberta-v3-base --tau 0.5 --batch_size 32\\\"\", \"server\": \"rtx5090-4x\", \"gpu\": [\"cuda:0\"], \"pid\": \"4491\", \"log_path\": \"~/runs/faith-evidence-ie/mvp1_ced_signal.log\", \"submitted_at\": \"2026-05-14T05:21:30.878Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 6830, \"model_name\": \"cross-encoder/nli-deberta-v3-base\", \"data_path\": \"/root/autodl-tmp/data/docred/\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/mvp1_results/\", \"wall_clock_seconds\": 1594.7, \"gpu_hours\": 0.44}, \"conclusion\": \"success\", \"metrics\": {\"mean_margin\": 0.48, \"discrimination_accuracy\": 0.815, \"pearson_r_margin_jaccard\": 0.34, \"pass\": true}, \"completed_at\": \"2026-05-14T05:48:05.545Z\"}}, \"count\": 130, \"total\": 130, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.7101}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 18_

<details><summary>Logged reasoning block</summary>

```text
The registry data is too large. Let me use a subagent to extract the key metrics from the registry, and in parallel read the decisions file for D076 protocol info.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "d87b58bf-751b-401e-85a1-11ed0a23523a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GaLxAAwaDrSWJmv4MPaf8y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 37732,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
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

_source line 19_

Registry 数据量很大，用 subagent 提取关键数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "3d641ff6-e847-4079-b9d1-e6c06f5b7b08",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GaLxAAwaDrSWJmv4MPaf8y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 37732,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
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

_source line 20_

<details open><summary>🔧 Tool call — Agent · `toolu_01UkXxDUvxmRzYY3VqCzLgZf`</summary>

```json
{
  "description": "Extract registry metrics for evidence table",
  "prompt": "I need you to extract structured experiment data from a large JSON registry file for building a paper evidence table.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt\n\nThis is JSON with schema: {result: string} where `result` is itself a JSON string.\n\nSteps:\n1. First probe the structure with jq to understand the schema\n2. Then extract ALL experiments, focusing on these fields for each:\n   - exp_id\n   - status\n   - conclusion\n   - method/config description\n   - key metrics: rel_f1, ign_f1, evi_f1, edcr, evi_f1_joint\n   - protocol info (is this a D076 unified protocol reeval?)\n   - seed if available\n   - any notes/tags\n\n3. Group experiments by method type:\n   - SFT baseline (with and without evidence)\n   - RSFT CED (different seeds)\n   - RSFT flat-NLI (different seeds)\n   - RSFT top_k=3\n   - CED reranker\n   - GRPO QLoRA\n   - GRPO bf16\n   - DPO\n   - DREEAM baseline\n   - Any other experiments\n\n4. For each experiment, note whether it used the D076 unified evaluation protocol (look for \"reeval\" in exp_id, or \"unified_protocol\", \"ign_f1_corrected\" flags, or D076 mentions).\n\nReturn a comprehensive structured summary with ALL metric values. Do not truncate or skip experiments. This is for a paper evidence table so every number matters.",
  "subagent_type": "general-purpose"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "f31fc56a-99f6-4184-9d0b-5ddc4f8c0d90",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GaLxAAwaDrSWJmv4MPaf8y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 716,
      "cache_read_input_tokens": 37732,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 716
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

### System

_source line 21_

```json
{
  "type": "system",
  "subtype": "task_started",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Extract registry metrics for evidence table",
  "task_type": "local_agent",
  "prompt": "I need you to extract structured experiment data from a large JSON registry file for building a paper evidence table.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt\n\nThis is JSON with schema: {result: string} where `result` is itself a JSON string.\n\nSteps:\n1. First probe the structure with jq to understand the schema\n2. Then extract ALL experiments, focusing on these fields for each:\n   - exp_id\n   - status\n   - conclusion\n   - method/config description\n   - key metrics: rel_f1, ign_f1, evi_f1, edcr, evi_f1_joint\n   - protocol info (is this a D076 unified protocol reeval?)\n   - seed if available\n   - any notes/tags\n\n3. Group experiments by method type:\n   - SFT baseline (with and without evidence)\n   - RSFT CED (different seeds)\n   - RSFT flat-NLI (different seeds)\n   - RSFT top_k=3\n   - CED reranker\n   - GRPO QLoRA\n   - GRPO bf16\n   - DPO\n   - DREEAM baseline\n   - Any other experiments\n\n4. For each experiment, note whether it used the D076 unified evaluation protocol (look for \"reeval\" in exp_id, or \"unified_protocol\", \"ign_f1_corrected\" flags, or D076 mentions).\n\nReturn a comprehensive structured summary with ALL metric values. Do not truncate or skip experiments. This is for a paper evidence table so every number matters.",
  "uuid": "a7a6ee3f-b7e1-4a5d-8c7b-6e0ae808f58d",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

## Round 1

68 recorded events

### User

_source line 22 · 2026-05-16T03:21:38.407Z_

I need you to extract structured experiment data from a large JSON registry file for building a paper evidence table.

The file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt

This is JSON with schema: {result: string} where `result` is itself a JSON string.

Steps:
1. First probe the structure with jq to understand the schema
2. Then extract ALL experiments, focusing on these fields for each:
   - exp_id
   - status
   - conclusion
   - method/config description
   - key metrics: rel_f1, ign_f1, evi_f1, edcr, evi_f1_joint
   - protocol info (is this a D076 unified protocol reeval?)
   - seed if available
   - any notes/tags

3. Group experiments by method type:
   - SFT baseline (with and without evidence)
   - RSFT CED (different seeds)
   - RSFT flat-NLI (different seeds)
   - RSFT top_k=3
   - CED reranker
   - GRPO QLoRA
   - GRPO bf16
   - DPO
   - DREEAM baseline
   - Any other experiments

4. For each experiment, note whether it used the D076 unified evaluation protocol (look for "reeval" in exp_id, or "unified_protocol", "ign_f1_corrected" flags, or D076 mentions).

Return a comprehensive structured summary with ALL metric values. Do not truncate or skip experiments. This is for a paper evidence table so every number matters.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "aad6dd5b-288d-49e5-aede-730b5339de22"
}
```

</details>

---

### System

_source line 23_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt",
  "usage": {
    "total_tokens": 14555,
    "tool_uses": 1,
    "duration_ms": 3500
  },
  "last_tool_name": "Read",
  "uuid": "c0184c46-7ed2-450a-b1ac-a3d5adadb6a4",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 24_

<details open><summary>🔧 Tool call — Read · `toolu_019nWbHzZkM66gADrj3HRo5c`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt",
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "98a55fe9-66bc-4c0e-9aba-1d31dc4eb480",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UDgxBsPUu9u3xN7YDW6wfo",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 14544,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 14544,
        "ephemeral_1h_input_tokens": 0
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

_source line 25 · 2026-05-16T03:21:42.368Z_

<details><summary>↩ Tool result · reported error · `toolu_019nWbHzZkM66gADrj3HRo5c`</summary>

```text
File content (108144 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "7495b62e-5a22-40eb-b83b-d0a7f6668933",
  "tool_use_result": "Error: File content (108144 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---

### System

_source line 26_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Probe JSON structure of the registry file",
  "usage": {
    "total_tokens": 15629,
    "tool_uses": 2,
    "duration_ms": 10046
  },
  "last_tool_name": "Bash",
  "uuid": "76314a39-a469-47a0-bc75-e92bbe218177",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 27_

<details open><summary>🔧 Tool call — Bash · `toolu_01QUVHW1UfcsoM4Fnet9oKJP`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 -c \"\nimport json\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\n# The outer structure\nprint('Top-level keys:', list(data.keys()))\nprint('Type of result:', type(data.get('result')))\ninner = json.loads(data['result'])\nprint('Inner type:', type(inner))\nif isinstance(inner, dict):\n    print('Inner keys:', list(inner.keys())[:20])\nelif isinstance(inner, list):\n    print('Inner length:', len(inner))\n    print('First item keys:', list(inner[0].keys()) if inner else 'empty')\n\"\n",
  "description": "Probe JSON structure of the registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "8dde1203-3d3a-4d45-9ce4-bc6245c39b5d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Gxdv568taWCgmoJoCyewjV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1074,
      "cache_read_input_tokens": 14544,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1074,
        "ephemeral_1h_input_tokens": 0
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

### Tool result

_source line 28 · 2026-05-16T03:21:48.727Z_

<details><summary>↩ Tool result · `toolu_01QUVHW1UfcsoM4Fnet9oKJP`</summary>

```text
Top-level keys: ['result']
Type of result: &lt;class 'str'>
Inner type: &lt;class 'dict'>
Inner keys: ['success', 'data', 'error', 'metadata']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "529ac2d1-1c67-497a-8017-bd72c249e6ff"
}
```

</details>

---

### System

_source line 29_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Explore inner data structure",
  "usage": {
    "total_tokens": 16101,
    "tool_uses": 3,
    "duration_ms": 16155
  },
  "last_tool_name": "Bash",
  "uuid": "94b6c807-c514-42ce-b64b-33a8259d17a2",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 30_

<details open><summary>🔧 Tool call — Bash · `toolu_01B3qSCQm7e1jAcsoBxytazu`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 -c \"\nimport json\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nprint('success:', inner['success'])\nprint('error:', inner['error'])\nprint('metadata:', inner['metadata'])\nd = inner['data']\nprint('data type:', type(d))\nif isinstance(d, dict):\n    print('data keys:', list(d.keys())[:30])\n    # Check experiments key\n    if 'experiments' in d:\n        exps = d['experiments']\n        print('experiments type:', type(exps))\n        if isinstance(exps, dict):\n            print('num experiments:', len(exps))\n            print('exp keys:', list(exps.keys())[:10])\n        elif isinstance(exps, list):\n            print('num experiments:', len(exps))\n\"\n",
  "description": "Explore inner data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "dae5f649-5cad-49a9-b6be-3b732e5afa92",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012SH5rwh2moziehkLfibMZt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 399,
      "cache_read_input_tokens": 15618,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 399,
        "ephemeral_1h_input_tokens": 0
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

_source line 31 · 2026-05-16T03:21:54.674Z_

<details><summary>↩ Tool result · `toolu_01B3qSCQm7e1jAcsoBxytazu`</summary>

```text
success: True
error: None
metadata: {'elapsed_seconds': 0.7101}
data type: &lt;class 'dict'>
data keys: ['experiments', 'count', 'total', 'baseline']
experiments type: &lt;class 'dict'>
num experiments: 130
exp keys: ['reeval_flat_nli_s42', 'reeval_ced_s44', 'reeval_ced_s42', 'eval_flat_nli_seed45', 'reeval_flat_nli_s43_r2', 'seed_comparison_prep', 'eval_flat_nli_s44', 'eval_plan_014_no_evidence_r2', 'eval_rsft_ced_s43', 'eval_rsft_ced_s45']
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "2d8589b2-8daa-4c1c-935f-fa8b904eedfd"
}
```

</details>

---

### System

_source line 32_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running List all experiment IDs",
  "usage": {
    "total_tokens": 16748,
    "tool_uses": 4,
    "duration_ms": 20234
  },
  "last_tool_name": "Bash",
  "uuid": "08faef4e-2ddf-451d-a32b-ea27243a12da",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 33_

<details open><summary>🔧 Tool call — Bash · `toolu_01TxFftUBAkJWAdNhyNbUwjg`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 -c \"\nimport json\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nd = inner['data']\n\n# Print all experiment IDs\nexps = d['experiments']\nfor k in sorted(exps.keys()):\n    print(k)\n\"\n",
  "description": "List all experiment IDs"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "d6597ae7-ad14-4011-9524-a9e52959f39d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017yWV2UYmtV7mSdC95j29K6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 574,
      "cache_read_input_tokens": 16017,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 574,
        "ephemeral_1h_input_tokens": 0
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

_source line 34 · 2026-05-16T03:21:59.033Z_

<details><summary>↩ Tool result · `toolu_01TxFftUBAkJWAdNhyNbUwjg`</summary>

```text
eval_flat_nli_s44
eval_flat_nli_seed44
eval_flat_nli_seed45
eval_grpo_g8_bf16
eval_plan_001_flat_nli
eval_plan_001_flat_nli_s43
eval_plan_008_rsft_topk3
eval_plan_008_topk3_fixed
eval_plan_012_dpo_1ep_fixed
eval_plan_012_dpo_1ep_fixed_r2
eval_plan_012_dpo_ced_1ep
eval_plan_012_dpo_ced_ckpt400
eval_plan_014_no_evidence
eval_plan_014_no_evidence_r2
eval_plan_014_sft_no_evidence
eval_rsft_ced_s43
eval_rsft_ced_s45
eval_sft_baseline_noquant
mvp1_ced_signal
mvp2_ced_reranker_poc
mvp2_diversity_probe
mvp2_eval_ced_kl001_r4_ckpt10
mvp2_eval_ced_kl001_r4_ckpt7080
mvp2_eval_ced_kl001_r4_ckpt90
mvp2_eval_ced_kl001_r4_early
mvp2_eval_ced_kl001_r4_high
mvp2_eval_ced_kl001_r4_last
mvp2_eval_ced_kl001_r4_multi
mvp2_eval_ced_kl001_r4_step100
mvp2_eval_ced_kl001_r4_step90
mvp2_eval_lr5e6_r1_ckpt100
mvp2_eval_lr5e6_r1_ckpt20
mvp2_eval_lr5e6_r1_ckpt40
mvp2_eval_lr5e6_r1_ckpt40_r2
mvp2_eval_lr5e6_r1_ckpt60
mvp2_eval_lr5e6_r1_ckpt60_r2
mvp2_eval_lr5e6_r1_ckpt80
mvp2_eval_lr5e6_rp_r2_ckpt20
mvp2_eval_rsft_r1
mvp2_eval_rsft_r2a
mvp2_eval_rsft_r2b
mvp2_eval_rsft_r2b_maxtok1536
mvp2_eval_rsft_r2b_maxtok1536_r2
mvp2_eval_rsft_s43
mvp2_eval_rsft_s43_r2
mvp2_eval_rsft_s44
mvp2_eval_sft_baseline
mvp2_grpo_ced
mvp2_grpo_ced_kl001
mvp2_grpo_ced_kl001_r2
mvp2_grpo_ced_kl001_r3
mvp2_grpo_ced_kl001_r4
mvp2_grpo_ced_lr5e6_p1_r1
mvp2_grpo_ced_lr5e6_r1
mvp2_grpo_ced_lr5e6_rp_r1
mvp2_grpo_ced_lr5e6_rp_r2
mvp2_grpo_ced_r1
mvp2_grpo_ced_r2
mvp2_grpo_ced_r3
mvp2_grpo_ced_r4
mvp2_grpo_ced_r5
mvp2_grpo_extract
mvp2_grpo_extract_r2
mvp2_grpo_extract_r3
mvp2_grpo_extract_r4
mvp2_grpo_flatnli
mvp2_grpo_flatnli_r2
mvp2_grpo_flatnli_r3
mvp2_grpo_flatnli_r4
mvp2_grpo_flatnli_r5
mvp2_grpo_flatnli_r6
mvp2_rsft_ced_scoring
mvp2_rsft_ced_scoring_topk3
mvp2_rsft_ced_scoring_topk3_r2
mvp2_rsft_diagnosis
mvp2_rsft_gen_s0
mvp2_rsft_gen_s1
mvp2_rsft_gen_s2
mvp2_rsft_gen_s3
mvp2_rsft_generate
mvp2_rsft_r2a
mvp2_rsft_r2b
mvp2_rsft_train_r1
mvp2_rsft_train_r1_s43
mvp2_rsft_train_r1_s44
mvp2_rsft_train_r2_fix
mvp2_sft_eval
mvp2_sft_eval_r2
mvp2_sft_eval_r3
mvp2_sft_warmup
plan_001_flat_nli_scoring
plan_001_flat_nli_seed43
plan_001_flat_nli_seed44
plan_001_flat_nli_seed45
plan_001_rsft_flat_nli
plan_002_test_eval_s44
plan_003_edcr_diagnostic
plan_004_dreeam_baseline
plan_008_rsft_topk3
plan_009_dynamics_figure
plan_009_extract_reward_eval
plan_009_flatnli_reward_eval
plan_009_flatnli_reward_eval_r2
plan_009_forgetting_figure
plan_011_bf16_g8_step_eval
plan_011_eval_g8_bf16_ckpt100
plan_011_grpo_g8_bf16
plan_011_grpo_g8_bf16_eval
plan_012_dpo_ced
plan_012_dpo_ced_1ep
plan_014_sft_no_evidence
plan_015_grpo_g4_bf16
plan_015_grpo_g4_bf16_v2
plan_015_grpo_g4_bf16_v3
precompute_nli_train
reeval_ced_s42
reeval_ced_s44
reeval_flat_nli_s42
reeval_flat_nli_s43
reeval_flat_nli_s43_r2
reeval_rsft_topk3
rsft_ced_s43_train
rsft_ced_s43_train_r2
rsft_ced_s43_train_r3
rsft_ced_s45_train
rsft_ced_s45_train_r2
rsft_ced_s45_train_r3
rsft_ced_s45_train_r4
seed_comparison_prep
smoke_test_grpo
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "1e26cdb8-e372-40f0-a0eb-29324f74135a"
}
```

</details>

---

### System

_source line 35_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Examine schema of sample experiments",
  "usage": {
    "total_tokens": 18844,
    "tool_uses": 5,
    "duration_ms": 25733
  },
  "last_tool_name": "Bash",
  "uuid": "053aaa2d-1102-4a84-904d-14f2bc2460b3",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 36_

<details open><summary>🔧 Tool call — Bash · `toolu_011pTN8qVN9YUHbZYKUPEfqx`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 -c \"\nimport json\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# Look at a few experiments to understand the schema\nfor k in ['reeval_ced_s42', 'eval_plan_014_no_evidence', 'plan_004_dreeam_baseline']:\n    if k in exps:\n        print(f'=== {k} ===')\n        print(json.dumps(exps[k], indent=2)[:2000])\n        print()\n\"\n",
  "description": "Examine schema of sample experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "4bf5c34e-12bd-42c2-976f-b41337fa727b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L1CGR6ztHeuW7dqbsEZiKH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2023,
      "cache_read_input_tokens": 16591,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2023,
        "ephemeral_1h_input_tokens": 0
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

_source line 37 · 2026-05-16T03:22:04.284Z_

<details><summary>↩ Tool result · `toolu_011pTN8qVN9YUHbZYKUPEfqx`</summary>

```text
=== reeval_ced_s42 ===
{
  "status": "PREPARING",
  "retry_count": 0,
  "created_at": "2026-05-16T02:37:58.498Z",
  "updated_at": "2026-05-16T03:18:27.685Z",
  "hypothesis": "Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. \u539f mvp2_eval_rsft_r2b_maxtok1536_r2 \u7528\u4e86 batch_size=8 + max_new_tokens=1536\u3002Paired t-test \u5173\u952e\u8def\u5f84\u3002",
  "parent": "mvp2_rsft_train_r1",
  "spec": {
    "command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && CUDA_VISIBLE_DEVICES={GPU} HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/rsft_output/checkpoint-510 --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/rsft_ced_s42_reeval --no-quantize\"",
    "server": "rtx5090-4x",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 985,
    "model_name": "Qwen3-4B + SFT + CED RSFT s42",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/rsft_output/checkpoint-510",
    "eval_data": "docred dev (985 docs)"
  },
  "notes": "\u65e7 eval (rsft_r2b_maxtok1536_r2) \u4e0d\u4ec5\u534f\u8bae\u4e0d\u4e00\u81f4\uff0c\u800c\u4e14\u7528\u4e86\u9519\u8bef checkpoint (rsft_output_r2b: lora_alpha=32, \u4ec5 160 \u6b65)\u3002\u6b63\u786e checkpoint: /root/autodl-tmp/rsft_output/checkpoint-510 (seed=42, lora_alpha=128, 510 \u6b65\uff0c\u4e0e s43/s44/s45 \u914d\u7f6e\u4e00\u81f4)\u3002"
}

=== eval_plan_014_no_evidence ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T23:17:32.011Z",
  "updated_at": "2026-05-16T01:34:06.402Z",
  "hypothesis": "Dev set eval of SFT-no-evidence model (plan_014). \u6838\u5fc3\u76ee\u6807\uff1a\u5bf9\u6bd4\u6807\u51c6 SFT rel_f1=0.4057 vs \u4e0d\u8f93\u51fa evidence \u7684 SFT rel_f1\uff08\u9694\u79bb evidence generation \u4ee3\u4ef7\uff09\u3002\u53ea\u8bc4\u4f30 rel_f1\uff0c\u4e0d\u8bc4\u4f30 evi_f1\uff08\u8f93\u51fa\u65e0 evidence\uff09\u3002plan_id=plan_014, claim=1\u3002",
  "parent": "plan_014_sft_no_evidence",
  "spec": {
    "command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 PYTHONUNBUFFERED=1 python -m freige.eval.inference --model_path /root/autodl-tmp/sft_no_evidence_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --split dev --batch_size 4 --max_new_tokens 1024 --seed 42 --output_dir /root/autodl-tmp/eval_results/sft_no_evidence_noquant --no-quantize --no_evidence\"",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:2"
    ],
    "pid": "283455",
    "log_path": "~/runs/faith-evidence-ie/eval_plan_014_no_evidence.log",
    "submitted_at": "2026-05-16T01:27:16.251Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "wall_clock_seconds": 33.8,
    "gpu_hours": 0.01
  },
  "conclusion": "failed",
  "notes": "FAILED: ValueError \u2014 model_path \u542b adapter_config.json \u89e6\u53d1 adapter \u68c0\u6d4b\u903b\u8f91\uff0c\u8981\u6c42 --sft_adapter\u3002\u8bca\u65ad(Worker diagnose_eval_plan_014): SFT adapter \u672c\u8eab\u5c31\u662f model_path\uff0c\u4e0d\u5e94\u8d70 adapter stacking \u8def\u5f84\u3002\u4fee\u590d\uff1a--model_path \u6539\u4f20\u5e95\u5ea7 Qwen3-4B\uff0c--sft_adapter \u4f20 /root/autodl-tmp/sft_no_evidence_output\u3002\u5f85 GPU \u7a7a\u95f2\u540e\u4ee5 corrected command \u91

=== plan_004_dreeam_baseline ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T13:47:01.947Z",
  "updated_at": "2026-05-15T15:44:24.920Z",
  "hypothesis": "Phase A: \u590d\u73b0 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1\u224854.15, RE-F1\u224863.49\u3002\u8bba\u6587\u62a5\u544a\u768457.34\u662fstudent model\u5728test set\u7684\u7ed3\u679c\uff0c\u97004\u9636\u6bb5self-training pipeline\u3002",
  "spec": {
    "command": "cd /root/autodl-tmp/baselines/dreeam && python run.py --do_train --data_dir dataset/docred --transformer_type roberta --model_name_or_path roberta-large --train_file train_annotated.json --dev_file dev.json --save_path checkpoints/teacher_roberta --train_batch_size 4 --test_batch_size 8 --num_train_epochs 30 --num_class 97 --seed 66",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:2"
    ],
    "pid": "213006",
    "log_path": "~/runs/faith-evidence-ie/plan_004_dreeam_baseline.log",
    "submitted_at": "2026-05-15T14:29:38.364Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "model_name": "roberta-large",
    "data_path": "/root/autodl-tmp/baselines/dreeam/dataset/docred",
    "data_count": 3053,
    "seed": 66,
    "checkpoint_path": "/root/autodl-tmp/baselines/dreeam/checkpoints/teacher_roberta/2026-05-15_22:29:42.720935/last.ckpt",
    "wall_clock_seconds": 4486.6,
    "gpu_hours": 1.25
  },
  "reproduce": {
    "finished_at": "2026-05-15T15:42:51.417Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-15T15:42:53.896000+00:00"
      }
    ]
  },
  "metrics": {
    "dev_rel_f1": 63.57,
    "dev_rel_ign_f1": 61.72,
    "dev_evi_f1": 54.01,
    "dev_rel_p": 66.95,
    "dev_rel_r": 60.51,
    "dev_evi_p": 60.53,
    "dev_evi_r": 48.76
  },
  "conclusion": "success",
  "completed_at": "2026-05-15T15:44:24.920Z"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "fa51bd46-48dc-4004-92cd-e2522b18d773"
}
```

</details>

---

### System

_source line 38_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Check baseline data in registry",
  "usage": {
    "total_tokens": 21929,
    "tool_uses": 6,
    "duration_ms": 30159
  },
  "last_tool_name": "Bash",
  "uuid": "154e0eb0-e6fb-4536-8a88-c96c2a4146d0",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 39_

<details open><summary>🔧 Tool call — Bash · `toolu_013DYNhmTpEr7aCfRjb7eHxA`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 << 'PYEOF'\nimport json\n\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# Also check baseline\nprint(\"=== BASELINE ===\")\nprint(json.dumps(inner['data'].get('baseline'), indent=2))\nPYEOF\n",
  "description": "Check baseline data in registry"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "0624f3f6-c68a-45f8-9ec5-bb271f9ef5dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01M7GsQq7WGvfrxqGaASYnvt",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3013,
      "cache_read_input_tokens": 18614,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3013,
        "ephemeral_1h_input_tokens": 0
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

_source line 40 · 2026-05-16T03:22:08.676Z_

<details><summary>↩ Tool result · `toolu_013DYNhmTpEr7aCfRjb7eHxA`</summary>

```text
=== BASELINE ===
null
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "3eb8055a-5c4a-4b0f-8003-ce9d87f13789"
}
```

</details>

---

### System

_source line 41_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Extract all experiments with key fields",
  "usage": {
    "total_tokens": 22203,
    "tool_uses": 7,
    "duration_ms": 41443
  },
  "last_tool_name": "Bash",
  "uuid": "ecfe79dc-75de-49a7-b130-5e11aaf43ad7",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 42_

<details open><summary>🔧 Tool call — Bash · `toolu_01DgEwvrrca5JZkzyqmZLxcr`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 << 'PYEOF'\nimport json\n\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# Dump ALL experiments with metrics, status, conclusion\nfor k in sorted(exps.keys()):\n    e = exps[k]\n    metrics = e.get('metrics', {})\n    spec = e.get('spec', {})\n    status = e.get('status', '?')\n    conclusion = e.get('conclusion', '')\n    seed = spec.get('seed', '')\n    model = spec.get('model_name', '')\n    notes = e.get('notes', '')\n    hypothesis = e.get('hypothesis', '')\n    \n    # Check for D076/unified protocol markers\n    is_reeval = 'reeval' in k.lower()\n    has_unified = 'unified' in str(e).lower() or 'unified_protocol' in str(e).lower()\n    has_d076 = 'd076' in str(e).lower()\n    has_ign_corrected = 'ign_f1_corrected' in str(e).lower()\n    \n    protocol_flag = []\n    if is_reeval: protocol_flag.append('reeval')\n    if has_unified: protocol_flag.append('unified')\n    if has_d076: protocol_flag.append('D076')\n    if has_ign_corrected: protocol_flag.append('ign_corrected')\n    \n    print(f\"=== {k} ===\")\n    print(f\"  status: {status}\")\n    print(f\"  conclusion: {conclusion}\")\n    print(f\"  seed: {seed}\")\n    print(f\"  model: {model}\")\n    if protocol_flag:\n        print(f\"  protocol: {', '.join(protocol_flag)}\")\n    if metrics:\n        print(f\"  metrics: {json.dumps(metrics)}\")\n    # Print hypothesis (first 200 chars)\n    if hypothesis:\n        print(f\"  hypothesis: {hypothesis[:300]}\")\n    if notes:\n        print(f\"  notes: {str(notes)[:300]}\")\n    print()\nPYEOF\n",
  "description": "Extract all experiments with key fields"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "34740292-8a8a-4206-8108-a4426d02a423",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012o3BPAkfFtKFRdhESPGKwz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 272,
      "cache_read_input_tokens": 21627,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 272,
        "ephemeral_1h_input_tokens": 0
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

### Tool result

_source line 43 · 2026-05-16T03:22:19.986Z_

<details><summary>↩ Tool result · `toolu_01DgEwvrrca5JZkzyqmZLxcr`</summary>

```text
&lt;persisted-output>
Output too large (69.5KB). Full output saved to: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt

Preview (first 2KB):
=== eval_flat_nli_s44 ===
  status: DONE
  conclusion: success
  seed: 
  model: 
  metrics: {"rel_f1": 0.4615, "rel_p": 0.4779, "rel_r": 0.4462, "ign_f1": 0.4615, "evi_f1": 0.8131, "evi_p": 0.8187, "evi_r": 0.8077, "evi_f1_joint": 0.3597, "edcr": 0.6458, "predictions": 15257, "tp": 5422, "format_ok": "985/985", "inference_hours": 2.93}
  hypothesis: Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。
  notes: [2026-05-16 02:18 UTC] 238/247 batches (96%), ~7min remaining. ETA ~02:25 UTC. Running normally at ~45s/it avg.

=== eval_flat_nli_seed44 ===
  status: DONE
  conclusion: killed
  seed: 
  model: 
  hypothesis: Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.

=== eval_flat_nli_seed45 ===
  status: DONE
  conclusion: success
  seed: 45
  model: Qwen3-4B
  metrics: {"rel_f1": 0.4551, "rel_p": 0.4632, "rel_r": 0.4472, "ign_f1": 0.4551, "evi_f1": 0.8154, "evi_p": 0.8108, "evi_r": 0.8201, "evi_f1_joint": 0.3556, "edcr": 0.6521, "n_predictions": 15650, "tp": 5434, "format_ok_rate": 1, "n_truncated": 206, "n_documents": 985, "inference_time_seconds": 11867.6}
  hypothesis: Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。
  notes: [2026-05-16 02:18 UTC] 196/247 batches (79%), ~45min remaining. ETA ~03:03 UTC. Running normally at ~47s/it avg.

=== eval_grpo_g8_bf16 ===
  status: DONE
  conclusion: success
  seed: 42
  model: Qwen3-4B + SFT + GRPO-G8-bf16
...
&lt;/persisted-output>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "3b40c598-a1ea-4ab9-a0e2-bebb326ea24e"
}
```

</details>

---

### System

_source line 44_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "usage": {
    "total_tokens": 24039,
    "tool_uses": 8,
    "duration_ms": 44649
  },
  "last_tool_name": "Read",
  "uuid": "9a8dd311-0103-458f-a9d2-f4b647dd7f12",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 45_

<details open><summary>🔧 Tool call — Read · `toolu_01HgYW31PPfdVtVgeBPP44cQ`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "50768269-b472-41ef-a439-59f235cee879",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DfwKiUtY2C6kGCrTjuyfaz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1764,
      "cache_read_input_tokens": 21899,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1764,
        "ephemeral_1h_input_tokens": 0
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

_source line 46 · 2026-05-16T03:22:23.098Z_

<details><summary>↩ Tool result · `toolu_01HgYW31PPfdVtVgeBPP44cQ`</summary>

```text
1	=== eval_flat_nli_s44 ===
2	  status: DONE
3	  conclusion: success
4	  seed: 
5	  model: 
6	  metrics: {"rel_f1": 0.4615, "rel_p": 0.4779, "rel_r": 0.4462, "ign_f1": 0.4615, "evi_f1": 0.8131, "evi_p": 0.8187, "evi_r": 0.8077, "evi_f1_joint": 0.3597, "edcr": 0.6458, "predictions": 15257, "tp": 5422, "format_ok": "985/985", "inference_hours": 2.93}
7	  hypothesis: Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 统计显著性数据点 (s42=0.4539, s43 pending, s44 本次, s45 pending)。
8	  notes: [2026-05-16 02:18 UTC] 238/247 batches (96%), ~7min remaining. ETA ~02:25 UTC. Running normally at ~45s/it avg.
9	
10	=== eval_flat_nli_seed44 ===
11	  status: DONE
12	  conclusion: killed
13	  seed: 
14	  model: 
15	  hypothesis: Full dev eval of flat-NLI RSFT seed=44 with --sft_adapter + --no-quantize. C3 seed-level comparison.
16	
17	=== eval_flat_nli_seed45 ===
18	  status: DONE
19	  conclusion: success
20	  seed: 45
21	  model: Qwen3-4B
22	  metrics: {"rel_f1": 0.4551, "rel_p": 0.4632, "rel_r": 0.4472, "ign_f1": 0.4551, "evi_f1": 0.8154, "evi_p": 0.8108, "evi_r": 0.8201, "evi_f1_joint": 0.3556, "edcr": 0.6521, "n_predictions": 15650, "tp": 5434, "format_ok_rate": 1, "n_truncated": 206, "n_documents": 985, "inference_time_seconds": 11867.6}
23	  hypothesis: Full dev eval of flat-NLI RSFT seed=45 checkpoint WITH --sft_adapter。seed45 中间 eval rel_f1=0.4876（待全量确认）。对比 CED RSFT mean (0.4596)。三 seed 全量 eval 出齐后汇报 flat-NLI vs CED RSFT 完整 seed-level 对比。
24	  notes: [2026-05-16 02:18 UTC] 196/247 batches (79%), ~45min remaining. ETA ~03:03 UTC. Running normally at ~47s/it avg.
25	
26	=== eval_grpo_g8_bf16 ===
27	  status: DONE
28	  conclusion: success
29	  seed: 42
30	  model: Qwen3-4B + SFT + GRPO-G8-bf16
31	  metrics: {"ckpt80_rel_f1": 0.4456, "ckpt80_ign_f1": 0.4456, "ckpt80_evi_f1": 0.8034, "ckpt80_edcr": 0.6409, "ckpt80_format_ok": "984/985", "ckpt80_truncated": 50, "ckpt90_rel_f1": 0.4523, "ckpt90_ign_f1": 0.4523, "ckpt90_evi_f1": 0.8052, "ckpt90_edcr": 0.6414, "ckpt90_format_ok": "983/985", "ckpt90_truncated": 61, "ckpt100_rel_f1": 0.4549, "ckpt100_ign_f1": 0.4549, "ckpt100_evi_f1": 0.8086, "ckpt100_edcr": 0.6318, "ckpt100_format_ok": "985/985", "ckpt100_truncated": 61, "best_checkpoint": "ckpt-100"}
32	  hypothesis: Eval GRPO G=8 bf16 checkpoints 80/90/100 on full dev set (985 docs). 验证 catastrophic forgetting 是否在 bf16 LoRA 下复现。rel_f1>0.30 → forgetting 不复现 (QLoRA-specific); rel_f1<0.05 → 复现 (C2 加强)。对比: SFT rel_f1=0.4057, QLoRA GRPO rel_f1=0.2167 (catastrophic).
33	  notes: 3 checkpoints 全部评测完成。rel_f1 单调递增 (0.4456→0.4523→0.4549)，evi_f1 同步上升 (0.8034→0.8052→0.8086)。全部 checkpoint 均大幅超过 SFT baseline (0.4057) 和 QLoRA GRPO (0.2167 catastrophic forgetting)。bf16 LoRA GRPO 无 forgetting，且持续改善至 step 100。Best checkpoint: 100 (rel_f1=0.4549, +12.1% over SFT).
34	
35	=== eval_plan_001_flat_nli ===
36	  status: DONE
37	  conclusion: success
38	  seed: 42
39	  model: Qwen3-4B + SFT + RSFT-flat-NLI
40	  metrics: {"rel_f1": 0.4539, "ign_f1": 0.4539, "evi_f1": 0.8043, "edcr": 0.6431, "precision": 0.4671, "recall": 0.4414, "evi_precision": 0.8143, "evi_recall": 0.7945, "format_ok_rate": 1, "n_truncated": 199, "n_documents": 985, "n_predictions": 15294, "inference_time_seconds": 3631}
41	  hypothesis: Dev eval of flat-NLI RSFT (plan_001). 对比 CED RSFT (3-seed mean rel_f1=0.4596). flat-NLI ≈ CED → CED contrastive margin 无增益; CED >> flat-NLI → margin 关键。
42	  notes: flat-NLI RSFT dev eval 完成 (985 docs, EXIT_CODE=0)。rel_f1=0.4539, evi_f1=0.8043, edcr=0.6431。与 CED RSFT 3-seed mean 对比: rel_f1 -0.57pp (0.4539 vs 0.4596), evi_f1 -1.00pp (0.8043 vs 0.8143), edcr 差异极小。flat-NLI 接近但略低于 CED，差异在 CED 3-seed 标准差范围内 (σ=0.0127)。注意此为 single seed (42)，与 CED seed=42 的 0.4449 比反而
43	
44	=== eval_plan_001_flat_nli_s43 ===
45	  status: DONE
46	  conclusion: failed
47	  seed: 43
48	  model: Qwen3-4B + flat-NLI RSFT s43 adapter
49	  metrics: {"rel_f1": 0.0022, "ign_f1": 0.0022, "evi_f1": 0.8533, "edcr": 0.9982, "num_preds": 17285, "format_ok": "981/985", "truncated": "251/985", "tp": 32, "note": "INVALID \u2014 missing --sft_adapter, same bug as DPO 1ep eval"}
50	
51	=== eval_plan_008_rsft_topk3 ===
52	  status: DONE
53	  conclusion: killed
54	  seed: 42
55	  model: Qwen3-4B + SFT + RSFT top_k=3
56	  metrics: {"note": "INVALID \u2014 missing --sft_adapter, killed by Director instruction"}
57	  hypothesis: RSFT top_k=3 dev eval: 对比 top_k=1 RSFT (rel_f1≈0.46) 和 SFT baseline (rel_f1≈0.4057)。验证更多候选是否提升证据质量。
58	
59	=== eval_plan_008_topk3_fixed ===
60	  status: DONE
61	  conclusion: killed
62	  seed: 
63	  model: 
64	
65	=== eval_plan_012_dpo_1ep_fixed ===
66	  status: DONE
67	  conclusion: killed
68	  seed: 
69	  model: 
70	
71	=== eval_plan_012_dpo_1ep_fixed_r2 ===
72	  status: DONE
73	  conclusion: negative
74	  seed: 42
75	  model: Qwen3-4B + SFT + DPO 1ep
76	  metrics: {"rel_f1": 0.4034, "evi_f1": 0.8088, "edcr": 0.7139, "format_ok_rate": 0.999, "truncated_rate": 0.343, "predictions": 19107, "ign_f1": 0.4034, "precision": 0.3809, "recall": 0.4287, "vs_sft_delta": -0.0023, "note": "DPO 1ep matches SFT baseline. 1ep\u21923ep trajectory shows gradual decoupling (rel_f1\u2193 evi_f1\u2191), consistent with GRPO pattern. Ign-F1=F1 exact match needs investigation."}
77	
78	=== eval_plan_012_dpo_ced_1ep ===
79	  status: DONE
80	  conclusion: negative
81	  seed: 42
82	  model: Qwen3-4B + DPO-CED-1ep LoRA
83	  metrics: {"rel_f1": 0.0022, "ign_f1": 0.0022, "evi_f1": 0.75, "edcr": 0.9982, "num_preds": 19265, "format_ok": "981/985", "truncated": "358/985", "tp": 34, "inference_time_s": 3643}
84	
85	=== eval_plan_012_dpo_ced_ckpt400 ===
86	  status: DONE
87	  conclusion: failed
88	  seed: 42
89	  model: Qwen3-4B + DPO-CED LoRA (checkpoint-400)
90	  notes: OOM: cuda:3 被 plan_008 占用 19.6 GiB，仅完成 15% batch，结果不可信。需在 cuda:2 重跑。
91	
92	=== eval_plan_014_no_evidence ===
93	  status: DONE
94	  conclusion: failed
95	  seed: 
96	  model: 
97	  hypothesis: Dev set eval of SFT-no-evidence model (plan_014). 核心目标：对比标准 SFT rel_f1=0.4057 vs 不输出 evidence 的 SFT rel_f1（隔离 evidence generation 代价）。只评估 rel_f1，不评估 evi_f1（输出无 evidence）。plan_id=plan_014, claim=1。
98	  notes: FAILED: ValueError — model_path 含 adapter_config.json 触发 adapter 检测逻辑，要求 --sft_adapter。诊断(Worker diagnose_eval_plan_014): SFT adapter 本身就是 model_path，不应走 adapter stacking 路径。修复：--model_path 改传底座 Qwen3-4B，--sft_adapter 传 /root/autodl-tmp/sft_no_evidence_output。待 GPU 空闲后以 corrected command 重试。
99	
100	=== eval_plan_014_no_evidence_r2 ===
101	  status: RUNNING
102	  conclusion: 
103	  seed: 
104	  model: 
105	  hypothesis: Retry of eval_plan_014_no_evidence with corrected command: --model_path 传底座 Qwen3-4B, --sft_adapter 传 SFT no-evidence adapter。修复 adapter 检测逻辑冲突。plan_id=plan_014, claim=1。
106	
107	=== eval_plan_014_sft_no_evidence ===
108	  status: DONE
109	  conclusion: success
110	  seed: 
111	  model: 
112	  metrics: {"rel_f1": 0.4893, "rel_ign_f1": 0.4893, "rel_precision": 0.4884, "rel_recall": 0.4902, "evi_f1": 0, "evi_precision": 0, "evi_recall": 0, "edcr": 0, "format_ok_rate": 0.9919, "n_truncated": 298, "n_predictions": 21064, "n_documents": 985, "n_parseable": 977, "inference_time_seconds": 4103.8}
113	  notes: No-evidence SFT rel_f1=0.4893 vs baseline with-evidence rel_f1=0.4057 (+0.0836, +20.6%). Evidence generation significantly hurts relation extraction. evi_f1=0 as expected. Format compliance 99.2%. 298/985 truncated. Inference 4103.8s.
114	
115	=== eval_rsft_ced_s43 ===
116	  status: RUNNING
117	  conclusion: 
118	  seed: 
119	  model: 
120	  hypothesis: Full dev eval of CED RSFT seed=43 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 4 个 seed。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。
121	  notes: [2026-05-16 02:18 UTC] 5/247 batches (2%), ~3h remaining. ETA ~05:19 UTC. Just started, running normally at ~45s/it avg.
122	
123	=== eval_rsft_ced_s45 ===
124	  status: RUNNING
125	  conclusion: 
126	  seed: 
127	  model: 
128	  hypothesis: Full dev eval of CED RSFT seed=45 with --sft_adapter + --no-quantize. Paired t-test 关键路径：CED 第 3 个 seed（s42/s44 已有，s43 训练中）。对比 flat-NLI RSFT seeds。plan_id=plan_mvp2_rsft, claim=3。
129	  notes: [2026-05-16 02:18 UTC] 69/247 batches (28%), ~2h remaining. ETA ~04:18 UTC. Running normally at ~41s/it avg.
130	
131	=== eval_sft_baseline_noquant ===
132	  status: DONE
133	  conclusion: success
134	  seed: 42
135	  model: Qwen3-4B + SFT LoRA (no quantization)
136	  metrics: {"rel_f1": 0.4106, "rel_precision": 0.4198, "rel_recall": 0.4019, "evi_f1": 0.8013, "evi_precision": 0.8005, "evi_recall": 0.8022, "evi_f1_joint": 0.3216, "edcr": 0.7039, "format_ok_rate": 0.998, "field_compliance_rate": 0.7066, "n_predictions": 16774, "n_truncated": 288, "n_documents": 985, "inference_time_seconds": 3677.9}
137	  notes: [2026-05-16] 无量化 SFT baseline eval 完成。rel_f1=0.4106 vs 量化版 0.4057 (+0.49pp), evi_f1=0.8013 vs 0.7979 (+0.34pp)。差异 <1pp，确认量化 confound 不显著（D058 排除）。所有基于量化 baseline 的对比结论仍然成立。无量化版推理时间 3678s vs 量化版 6139s（快 40%，因无量化用满 GPU 内存）。
138	
139	=== mvp1_ced_signal ===
140	  status: DONE
141	  conclusion: success
142	  seed: 42
143	  model: cross-encoder/nli-deberta-v3-base
144	  metrics: {"mean_margin": 0.48, "discrimination_accuracy": 0.815, "pearson_r_margin_jaccard": 0.34, "pass": true}
145	
146	=== mvp2_ced_reranker_poc ===
147	  status: DONE
148	  conclusion: success
149	  seed: 42
150	  model: Qwen3-4B + SFT (greedy N=8 + CED reranker)
151	  metrics: {"ced_reranker_rel_f1": 0.4864, "ced_reranker_evi_f1": 0.8188, "ced_reranker_edcr": 0.6156, "ced_reranker_precision": 0.4913, "ced_reranker_recall": 0.4815, "ced_reranker_pred_count": 14782, "ced_reranker_format_ok_rate": 1, "oracle_rel_f1": 0.6237, "oracle_evi_f1": 0.7942, "oracle_edcr": 0.5262, "oracle_pred_count": 13418, "random_rel_f1": 0.4538, "random_evi_f1": 0.8029, "random_edcr": 0.6763, "ced_f1_spearman_r": 0.3235, "ced_f1_spearman_p": 2.46e-191, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "sft_baseline_edcr": 0.7118, "rsft_mean_rel_f1": 0.4596, "delta_vs_sft_rel_f1": 0.0807, "delta_vs_rsft_rel_f1": 0.0268, "delta_vs_sft_evi_f1": 0.0209, "oracle_ceiling_rel_f1": 0.218, "num_generations": 8, "temperature": 0.7, "generation_time_s": 20872.6, "n_docs": 985}
152	  hypothesis: CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.
153	  notes: CED reranker (N=8, no training) rel_f1=0.4864, 超过 SFT greedy (+8.07pp) 和 RSFT 3-seed mean (+2.68pp)。Oracle 上界 rel_f1=0.6237 (+21.8pp vs SFT)，CED reranker 实现了 oracle ceiling 的 37% (0.0807/0.218)。CED-F1 Spearman r=0.3235 (p≈0)，相关性显著但中等——说明 CED 不是完美的 proxy 但有信号。Random baseline rel_f1=0.4538 说明 sampling
154	
155	=== mvp2_diversity_probe ===
156	  status: DONE
157	  conclusion: success
158	  seed: 42
159	  model: Qwen3-4B + SFT adapter
160	  metrics: {"unique_triples_t07": 5, "unique_triples_t10": 8, "jaccard_t07": 0.17, "jaccard_t10": 0.051, "format_ok_rate_t07": 0.5, "format_ok_rate_t10": 0.438, "n_samples": 3, "n_generations": 8, "note": "unique_triples_t07 corrected from 7 to 5.0 (mean). Reviewer: format_ok ~34% after fix, 'diversity' was JSON key name variants not semantic diversity"}
161	  hypothesis: RSFT viability check: SFT model output diversity at T=0.7/1.0 with N=8 generations. Pass criteria: unique triple-sets >= 5/8.
162	  notes: [2026-05-15 01:35] D034 独立验证结果: 200 docs 实际 diversity=7.11/8 (median=8.0), evidence diversity=5.43/8, format parse rate=90.2%。61.5% 文档达到 8/8 完全不同。之前监控报告的 mean_diversity=1.0/8 是监控计算 bug，非生成质量问题。diversity_probe 早期观察(7/8)是准确的。RSFT 前提成立。
163	
164	=== mvp2_eval_ced_kl001_r4_ckpt10 ===
165	  status: DONE
166	  conclusion: success
167	  seed: 42
168	  model: Qwen3-4B
169	  metrics: {"rel_f1": 0.00296, "rel_precision": 0.00314, "rel_recall": 0.0028, "evi_f1": 0.72, "evi_precision": 0.6429, "evi_recall": 0.8182, "edcr": 0.9983, "n_parseable": 984, "n_truncated": 24, "n_predictions": 11621, "tp": 34, "pred_count": 10839, "gold_count": 12151, "inference_time_seconds": 5211.4}
170	  notes: Eval 完成（由 multi eval 执行）。ckpt-10 rel_f1=0.003 catastrophic — 模型几乎丧失 relation 抽取能力 (34 TP / 10839 pred)，但 evi_f1=0.72 和 edcr=0.998 反而高。GRPO 训练极早期就严重损害 relation 能力。
171	
172	=== mvp2_eval_ced_kl001_r4_ckpt7080 ===
173	  status: DONE
174	  conclusion: failed
175	  seed: 
176	  model: 
177	  hypothesis: Re-run failed ckpt-70/80 eval from crashed high eval (cuda:3 OOM). Completes 10-checkpoint trajectory for paper negative result analysis.
178	  notes: Process died shortly after start - likely OOM on cuda:3 (same issue as high eval crash during ckpt-70). cuda:3 may have insufficient free VRAM for eval. ckpt-70/80 will be covered by multi eval on cuda:2.
179	
180	=== mvp2_eval_ced_kl001_r4_ckpt90 ===
181	  status: DONE
182	  conclusion: killed
183	  seed: 42
184	  model: Qwen3-4B + SFT + GRPO ced_kl001 step-90
185	  hypothesis: Eval ced_kl001_r4 best-reward checkpoint (step 90, reward=1.370, f1=0.720) — this is the primary MVP-2 judgment checkpoint. If evi_f1 ≥ SFT baseline (0.7979) + 2pp = 0.8179, MVP-2 passes.
186	  notes: 重复条目，被 mvp2_eval_ced_kl001_r4_step90 (cuda:1, PID 83207, 有 cron 监控) 取代。本条目无 cron、无独立进程。
187	
188	=== mvp2_eval_ced_kl001_r4_early ===
189	  status: DONE
190	  conclusion: negative
191	  seed: 42
192	  model: Qwen3-4B
193	  metrics: {"f1": 0.1563, "ign_f1": 0.1563, "evi_f1": 0.5643, "edcr": 0.8858, "precision": 0.2356, "recall": 0.1169, "evi_precision": 0.4864, "evi_recall": 0.6721, "format_ok_rate": 0.999, "n_parseable": 984, "n_truncated": 11, "n_predictions": 9250, "tp": 1421, "pred_count": 6032, "gold_count": 12151}
194	  notes: **Checkpoint-50 eval 完成，结果极差——MVP-2 双指标均 FAIL：**\n\n- rel_f1: 0.1563 vs SFT 0.4057 (Δ=-24.9pp)，远低于 -5pp 阈值\n- evi_f1: 0.5643 vs SFT 0.7979 (Δ=-23.4pp)，需 +2pp 却暴跌\n- EDCR: 0.8858 vs SFT 0.7118 (Δ=+17.4pp)，唯一改善项\n- recall 崩塌 (0.117 vs gold 12151)，precision 也低 (0.236)\n\n**诊断**: training reward 上升 (1.1
195	
196	=== mvp2_eval_ced_kl001_r4_high ===
197	  status: DONE
198	  conclusion: failed
199	  seed: 42
200	  model: Qwen3-4B + SFT + GRPO ced_kl001
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "38ff1c34-2975-4bf6-a5c6-c680f437523f"
}
```

</details>

---

### System

_source line 47_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "usage": {
    "total_tokens": 31379,
    "tool_uses": 9,
    "duration_ms": 50690
  },
  "last_tool_name": "Read",
  "uuid": "2682ba96-3368-4c13-b79d-c6ff4195dc01",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 48_

<details open><summary>🔧 Tool call — Read · `toolu_01NgL1dwVWZm2wF6oyBAhNn5`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "offset": 200,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "5e594ae1-e7ba-4cc9-9584-cc68c1d65225",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HrTpb4u8kWPydgvbLfrfft",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7302,
      "cache_read_input_tokens": 23663,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7302,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 38,
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

_source line 49 · 2026-05-16T03:22:29.113Z_

<details><summary>↩ Tool result · `toolu_01NgL1dwVWZm2wF6oyBAhNn5`</summary>

```text
200	  model: Qwen3-4B + SFT + GRPO ced_kl001
201	  metrics: {"checkpoint_60": {"rel_f1": 0.1467, "ign_f1": 0.1467, "precision": 0.1909, "recall": 0.1192, "evi_f1": 0.5763, "edcr": 0.9062, "pred_count": 10041, "gold_count": 12151, "n_truncated": 16, "format_ok_rate": 1}, "note": "Only ckpt-60 completed. Process died during ckpt-70 inference at 8% (5/62 batch). ckpt-80/90 never started."}
202	  hypothesis: High-end checkpoint eval (60,70,80,90) on cuda:3, complementing cuda:2 low-end eval. Step 90 is true best checkpoint (reward=1.370). D024 directive.
203	  notes: 1/4 checkpoints completed (ckpt-60). Process crashed during ckpt-70 inference at 8% - likely OOM or killed. cuda:3 still has 9503 MiB residual. ckpt-90 eval running separately on cuda:1 (mvp2_eval_ced_kl001_r4_step90).
204	
205	=== mvp2_eval_ced_kl001_r4_last ===
206	  status: DONE
207	  conclusion: killed
208	  seed: 
209	  model: 
210	  notes: 已被拆分为独立 eval：ckpt-90 → mvp2_eval_ced_kl001_r4_ckpt90 (cuda:3)，ckpt-100 → mvp2_eval_ced_kl001_r4_step100 (cuda:0)。此条目作废。
211	
212	=== mvp2_eval_ced_kl001_r4_multi ===
213	  status: DONE
214	  conclusion: killed
215	  seed: 42
216	  model: Qwen3-4B
217	  metrics: {"checkpoint-10": {"f1": 0.003, "ign_f1": 0.003, "evi_f1": 0.72, "edcr": 0.9983, "format_ok_rate": 0.999}, "checkpoint-20": {"f1": 0.0088, "ign_f1": 0.0088, "evi_f1": 0.423, "edcr": 0.9954, "format_ok_rate": 0.999}, "checkpoint-30": {"f1": 0.0338, "ign_f1": 0.0338, "evi_f1": 0.5889, "edcr": 0.9798, "format_ok_rate": 1}, "checkpoint-50": {"f1": 0.1563, "ign_f1": 0.1563, "evi_f1": 0.5643, "edcr": 0.8858, "format_ok_rate": 0.999}, "checkpoint-60": {"f1": 0.1467, "ign_f1": 0.1467, "evi_f1": 0.5763, "edcr": 0.9062, "format_ok_rate": 1}, "checkpoint-90": {"f1": 0.2108, "ign_f1": 0.2108, "evi_f1": 0.5666, "edcr": 0.8584, "format_ok_rate": 1}}
218	  notes: Director 指令: ckpt-30 评完即停。进程在 ckpt-40 推理 3% 时被 kill，非异常崩溃。已完成 6/9 个 ckpt eval: 10,20,30,50,60,90（ckpt-40 中断，ckpt-70/80 未执行）。F1 随 step 单调上升: 0.003→0.009→0.034→0.156→0.147→0.211。best=ckpt-90 (F1=0.211)。Evi-F1 稳定在 0.42-0.72，EDCR 随 step 下降（0.998→0.858）。结果路径: /root/autodl-tmp/eval_results/grpo_ced_kl001/
219	
220	=== mvp2_eval_ced_kl001_r4_step100 ===
221	  status: DONE
222	  conclusion: negative
223	  seed: 42
224	  model: Qwen3-4B + SFT adapter + GRPO ced_kl001 step-100
225	  metrics: {"rel_f1": 0.2167, "ign_f1": 0.2167, "precision": 0.2849, "recall": 0.1749, "evi_f1": 0.5746, "evi_precision": 0.5244, "evi_recall": 0.6353, "edcr": 0.8539, "pred_count": 7460, "gold_count": 12151, "tp": 2125, "n_truncated": 21, "format_ok_rate": 1}
226	  hypothesis: Eval ced_kl001_r4 last checkpoint (step 100) to compare with best-reward checkpoint (step 50). If best ≠ last, the gap measures training stability under batch_size=1 GRPO variance.
227	  notes: 2026-05-15 03:20 UTC: ckpt-100 inference 48/62 (77%), ~20 min remaining. Started 02:09 UTC.
228	
229	=== mvp2_eval_ced_kl001_r4_step90 ===
230	  status: DONE
231	  conclusion: negative
232	  seed: 42
233	  model: Qwen3-4B + SFT + GRPO ced_kl001 step-90
234	  metrics: {"rel_f1": 0.2108, "ign_f1": 0.2108, "evi_f1": 0.5666, "edcr": 0.8584, "pred_count": 11160, "n_truncated": 22, "format_ok_rate": 1, "n_documents": 985}
235	  hypothesis: Eval true best checkpoint (step 90, reward=1.370). Critical after ckpt-50 showed reward hacking (rel_f1 -24.9pp). If step 90 also fails, CED reward design has fundamental issue.
236	  notes: 2026-05-15 03:20 UTC: ckpt-90 inference 31/62 (50%), ~45 min remaining. Started 02:32 UTC.
237	
238	=== mvp2_eval_lr5e6_r1_ckpt100 ===
239	  status: DONE
240	  conclusion: negative
241	  seed: 
242	  model: 
243	  metrics: {"rel_f1": 0.0138, "rel_precision": 0.0132, "rel_recall": 0.0144, "ign_f1": 0.0138, "evi_f1": 0.8504, "evi_precision": 0.9256, "evi_recall": 0.7866, "edcr": 0.9876, "format_ok_rate": 0.999, "field_compliance_rate": 0.8162, "evidence_format_rate": 0.8162, "tp": 175, "pred_count": 13300, "gold_count": 12151, "n_predictions": 15498, "n_truncated": 181, "n_documents": 985, "n_parseable": 984, "inference_time_seconds": 5901.7}
244	  hypothesis: P0 ckpt-100 eval: lr=5e-6 GRPO at step 100 (halfway point). Checkpoint-100 已保存。与 kl001_r4 的 step-100 (rel_f1=0.217) 形成直接对比。Pass criteria: rel_f1 > 0.30.
245	
246	=== mvp2_eval_lr5e6_r1_ckpt20 ===
247	  status: DONE
248	  conclusion: negative
249	  seed: 42
250	  model: Qwen3-4B + SFT + GRPO lr5e6 ckpt-20
251	  metrics: {"rel_f1": 0.0077, "rel_precision": 0.0071, "rel_recall": 0.0084, "evi_f1": 0.628, "evi_precision": 0.855, "evi_recall": 0.496, "edcr": 0.993, "format_ok_rate": 0.991, "field_compliance_rate": 0.399, "pred_count": 14440, "gold_count": 12151, "tp": 102, "n_truncated": 587, "inference_time_seconds": 6370.4}
252	  hypothesis: P0 ckpt-20 early eval: lr=5e-6 GRPO at step 20. Pass criteria: rel_f1 > 0.30 (no catastrophic forgetting). Key MVP gate for P0.
253	
254	=== mvp2_eval_lr5e6_r1_ckpt40 ===
255	  status: DONE
256	  conclusion: failed
257	  seed: 42
258	  model: Qwen3-4B + SFT + GRPO lr5e6 ckpt-40
259	  hypothesis: P0 ckpt-40 eval: lr=5e-6 GRPO at step 40 (where f1_reward first rises to 0.038). Director 新判定框架: ckpt-20 FAIL + ckpt-40 PASS → P0 判 PASS。Pass criteria: rel_f1 > 0.30.
260	  notes: Reviewer 确认 PID 101842 在 cuda:2 正常运行中（inference 5/62, 8%），占用 9710 MiB。原误判原因：kill 旧 PID 100555 后 cron 检测旧 PID 导致 5× dead 误判。实际进程未中断。由 _r2 条目接续追踪。
261	
262	=== mvp2_eval_lr5e6_r1_ckpt40_r2 ===
263	  status: DONE
264	  conclusion: negative
265	  seed: 42
266	  model: Qwen3-4B + SFT + GRPO lr5e6 ckpt-40
267	  metrics: {"rel_f1": 0.0071, "precision": 0.0066, "recall": 0.0078, "evi_f1": 0.7584, "evi_precision": 0.9113, "evi_recall": 0.6494, "edcr": 0.9942, "format_ok_rate": 0.9939, "field_compliance_rate": 0.5675, "pred_count": 14434, "gold_count": 12151, "tp": 95, "n_truncated": 424, "inference_time_seconds": 6152}
268	  hypothesis: Re-tracking orphan PID 101842 for P0 ckpt-40 eval (lr=5e-6 GRPO step 40). Original exp auto-failed due to cron/PID mismatch. Pass criteria: rel_f1 > 0.30.
269	  notes: [2026-05-15 06:50] 全面状态检查: PID 101842 存活 (Rl, uptime 1:25), GPU 2: 10644 MiB/74% util. tmux mvp2_eval_lr5e6_r1_ckpt40 alive (创建于 05:25 UTC). 按 92s/batch 估算约 55/62 (89%), ETA ~10min (约UTC 07:00).
270	
271	=== mvp2_eval_lr5e6_r1_ckpt60 ===
272	  status: DONE
273	  conclusion: failed
274	  seed: 42
275	  model: grpo_ced_lr5e6_ckpt60
276	  hypothesis: P0 ckpt-60 eval: lr=5e-6 GRPO at step 60. 训练轨迹数据点——ckpt-20 catastrophic forgetting (rel_f1=0.0077)，需看后续 checkpoint 是否恢复。Pass criteria: rel_f1 > 0.30.
277	  notes: [2026-05-15 07:24] D031 清理: PID 108025 因 cd path 问题从未产出有效结果。已被 _r2 (PID 108185) 取代。标记 failed 关闭。
278	
279	=== mvp2_eval_lr5e6_r1_ckpt60_r2 ===
280	  status: DONE
281	  conclusion: negative
282	  seed: 42
283	  model: Qwen3-4B + SFT + GRPO lr5e6 ckpt-60
284	  metrics: {"rel_f1": 0.0093, "precision": 0.0085, "recall": 0.0103, "evi_f1": 0.81, "edcr": 0.993, "format_ok_rate": 0.998, "pred_count": 14626, "gold_count": 12151, "tp": 125, "inference_time_seconds": 6152}
285	  hypothesis: P0 ckpt-60 eval retry: 原 submit_on_allocated 失败 (pid=unknown). 手动 SSH 启动 /root/autodl-tmp/scripts/eval_lr5e6_ckpt60.sh. Pass criteria: rel_f1 > 0.30.
286	  notes: [2026-05-15 08:07] 正常完成。rel_f1=0.0093，与 ckpt-20 (0.0077) / ckpt-40 (0.0071) 同一量级，无恢复信号。evi_f1=0.81 持续上升（ckpt-20: 0.628, ckpt-40: 0.758），证据抽取在改善但关系能力完全崩塌。结果路径: /root/autodl-tmp/eval_results/grpo_ced_lr5e6_ckpt60/metrics.json。cuda:1 已释放。
287	
288	=== mvp2_eval_lr5e6_r1_ckpt80 ===
289	  status: DONE
290	  conclusion: negative
291	  seed: 42
292	  model: Qwen3-4B + SFT + GRPO lr5e6 ckpt-80
293	  metrics: {"rel_f1": 0.0116, "ign_f1": 0.0116, "precision": 0.0109, "recall": 0.0124, "evi_f1": 0.828, "evi_precision": 0.928, "evi_recall": 0.748, "edcr": 0.993, "format_ok_rate": 0.999, "field_compliance_rate": 0.788, "pred_count": 13828, "gold_count": 12151, "n_truncated": 210, "inference_time_seconds": 6099}
294	  hypothesis: P0 ckpt-80 eval: lr=5e-6 GRPO at step 80. 训练轨迹继续——ckpt-20 FAIL (0.0077), ckpt-40/60 待出. Step 80 reward=0.283 (回升), format_reward=0.249. Pass criteria: rel_f1 > 0.30.
295	  notes: [2026-05-15 08:56] 正常完成。rel_f1=0.0116，延续 ckpt-20/40/60 的平坦趋势 (0.007-0.012)。evi_f1=0.828 继续上升。lr5e6 轨迹: step 20→40→60→80 rel_f1 = 0.008/0.007/0.009/0.012，无恢复信号。cuda:2 已释放。
296	
297	=== mvp2_eval_lr5e6_rp_r2_ckpt20 ===
298	  status: DONE
299	  conclusion: killed
300	  seed: 42
301	  model: Qwen3-4B + SFT + GRPO lr5e6+recall_penalty ckpt-20
302	  hypothesis: P0+P1 ckpt-20 eval: lr=5e-6 + recall_penalty GRPO at step 20. Director killed rp_r2 training (loss divergence), but ckpt-20 eval needed to close P0+P1 comparison line. Pass criteria: rel_f1 > 0.30 AND pred_count >= 9720.
303	  notes: Director 指令 kill: 让 sft_baseline 独占 cuda:3。rp_r2 eval 优先级低，后面补。进度 11/62 (18%)。
304	
305	=== mvp2_eval_rsft_r1 ===
306	  status: DONE
307	  conclusion: success
308	  seed: 42
309	  model: Qwen3-4B + SFT + RSFT r1
310	  metrics: {"rel_f1": 0.4449, "evi_f1": 0.8187, "evi_f1_joint": 0.3468, "evi_f1_joint_P": 0.3515, "evi_f1_joint_R": 0.3423, "edcr": 0.6565, "num_preds": 15307, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "delta_rel_f1": 0.0392, "delta_evi_f1": 0.0208, "delta_evi_f1_joint": 0.0351, "mvp2_pass": true}
311	  hypothesis: Full dev eval of RSFT r1 (seed=42). Same pipeline as s44 eval (985 docs, no-quantize). Need 3-seed data for complete_mvp. s44 PASS: rel_f1=0.4655, evi_f1=0.8087.
312	
313	=== mvp2_eval_rsft_r2a ===
314	  status: DONE
315	  conclusion: success
316	  seed: 42
317	  model: Qwen3-4B + SFT + RSFT r2a
318	  metrics: {"rel_f1": 0.4494, "ign_f1": 0.4494, "evi_f1": 0.8108, "evi_f1_joint": 0.3509, "evi_f1_joint_P": 0.3423, "evi_f1_joint_R": 0.3599, "edcr": 0.6641, "precision": 0.4512, "recall": 0.4475, "evi_precision": 0.8143, "evi_recall": 0.8073, "format_ok_rate": 1, "n_predictions": 15482, "n_truncated": 208, "inference_time_s": 5967.2, "delta_evi_f1_joint": 0.0392}
319	  hypothesis: Full dev eval of r2a (1 epoch, alpha=128, clean data). Ablation: 1 epoch vs 3 epoch (r1). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
320	  notes: RSFT r2a (1ep, alpha=128/r=64, lr=2e-5, clean 2548 samples). rel_f1=0.4494 (+0.0045 vs r1, +0.0001 vs r2b), evi_f1=0.8108 (-0.0079 vs r1, -0.0020 vs r2b), edcr=0.6641 (+0.0032 vs r2b). 1 epoch with clean data matches r1's 3-epoch rel_f1 while being cheaper. r2a vs r2b (alpha=128 vs 32): nearly ident
321	
322	=== mvp2_eval_rsft_r2b ===
323	  status: DONE
324	  conclusion: success
325	  seed: 42
326	  model: Qwen3-4B + SFT + RSFT r2b
327	  metrics: {"rel_f1": 0.4493, "ign_f1": 0.4493, "evi_f1": 0.8128, "evi_f1_joint": 0.349, "evi_f1_joint_P": 0.3455, "evi_f1_joint_R": 0.3526, "edcr": 0.6609, "precision": 0.4566, "recall": 0.4424, "evi_precision": 0.8201, "evi_recall": 0.8056, "pred_count": 14829, "format_ok": "983/985", "truncated": 179, "inference_time_s": 5862, "delta_evi_f1_joint": 0.0373}
328	  hypothesis: Full dev eval of r2b (1 epoch, alpha=32, lr=1e-5, clean data). Ablation: conservative LoRA scaling vs r2a/r1. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
329	
330	=== mvp2_eval_rsft_r2b_maxtok1536 ===
331	  status: DONE
332	  conclusion: killed
333	  seed: 42
334	  model: Qwen3-4B+SFT+RSFT r2b
335	  hypothesis: Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). If EDCR improves significantly (from 0.6609 toward 0.71+), current EDCR gap is truncation artifact, not model issue. If EDCR unchanged, distractor citation is genuine RSFT behavior.
336	  notes: Reviewer CRITICAL: 命令缺少 --base_model 和 --sft_adapter，模型 stack 是 Base+RSFT LoRA 而非 Base+SFT+RSFT LoRA，结果不可用。PID 196700 已 kill。重试为 mvp2_eval_rsft_r2b_maxtok1536_r2。
337	
338	=== mvp2_eval_rsft_r2b_maxtok1536_r2 ===
339	  status: DONE
340	  conclusion: negative
341	  seed: 
342	  model: 
343	  metrics: {"rel_f1": 0.4504, "ign_f1": 0.4504, "evi_f1": 0.8102, "edcr": 0.674, "precision": 0.4488, "recall": 0.4519, "evi_precision": 0.8162, "evi_recall": 0.8044, "n_truncated": 146, "n_total": 985, "n_predictions": 17188, "n_distractor_citations": 19589, "n_total_citations": 29063, "format_ok_rate": 0.998}
344	  hypothesis: Truncation diagnosis: r2b eval with max_new_tokens=1536 (vs default 1024). Retry with correct model stack (Base+SFT+RSFT). If EDCR improves significantly (from 0.6609 toward 0.71+), truncation is the cause. If unchanged, distractor citation is genuine RSFT behavior.
345	  notes: max_new_tokens 1536 vs 1024: truncated 179→146 (-33), EDCR 0.6609→0.6740 (+0.0131), rel_f1 0.4493→0.4504, evi_f1 0.8128→0.8102。截断只是 EDCR 偏低的次要因素，distractor citation 是 RSFT 的真实行为。
346	
347	=== mvp2_eval_rsft_s43 ===
348	  status: DONE
349	  conclusion: failed
350	  seed: 
351	  model: 
352	  hypothesis: Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
353	  notes: 参数名错误导致失败: --rsft_adapter 应为 --model_path, --data_dir 应为 --data_path, --gpu 0 不存在。重试为 mvp2_eval_rsft_s43_r2。
354	
355	=== mvp2_eval_rsft_s43_r2 ===
356	  status: DONE
357	  conclusion: success
358	  seed: 
359	  model: 
360	  metrics: {"rel_f1": 0.4683, "ign_f1": 0.4683, "evi_f1": 0.8156, "evi_f1_joint": 0.3711, "evi_f1_joint_P": 0.3747, "evi_f1_joint_R": 0.3675, "edcr": 0.6388, "precision": 0.4817, "recall": 0.4556, "evi_precision": 0.8142, "evi_recall": 0.817, "n_predictions": 14970, "n_truncated": 171, "format_ok_rate": 1, "inference_time_s": 6316.7, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "delta_rel_f1": 0.0626, "delta_evi_f1": 0.0177, "delta_evi_f1_joint": 0.0594, "mvp2_pass": true}
361	  hypothesis: Full dev eval of RSFT s43 (seed=43). 3rd seed for variance estimation. r1: rel_f1=0.4449, s44: rel_f1=0.4655. Pass: rel_f1 > 0.4057, evi_f1 > 0.798. Retry of mvp2_eval_rsft_s43 (fixed arg names).
362	  notes: 3rd seed PASS. rel_f1=0.4683 (+6.26pp vs SFT), evi_f1=0.8156 (+1.77pp), EDCR=0.6388. 3-seed 完整表: mean rel_f1=0.4596±0.0127, mean evi_f1=0.8143±0.0051. 三个 seed 均稳定超过 SFT baseline。cuda:2 已释放。
363	
364	=== mvp2_eval_rsft_s44 ===
365	  status: DONE
366	  conclusion: killed
367	  seed: 44
368	  model: RSFT s44
369	  hypothesis: Full dev eval of RSFT seed=44 checkpoint. First MVP-2 judgement data point. Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798 (SFT baseline).
370	  notes: STALE: s44 全量 eval 已由 mvp2_eval_rsft_r2b_maxtok1536 等系列完成。s44 rel_f1=0.4655 已入库。此条目为残留。
371	
372	=== mvp2_eval_sft_baseline ===
373	  status: DONE
374	  conclusion: success
375	  seed: 42
376	  model: Qwen3-4B + SFT LoRA adapter
377	  metrics: {"rel_f1": 0.4057, "evi_f1": 0.7979, "evi_f1_joint": 0.3117, "evi_f1_joint_P": 0.3037, "evi_f1_joint_R": 0.32, "edcr": 0.7118, "pred_count": 12234, "gold_count": 12151, "format_ok_rate": 0.998, "format_compliance_rate": 0.998, "field_compliance_rate": 0.6264, "n_truncated": 367, "inference_time_seconds": 6138.5}
378	  hypothesis: SFT baseline eval using identical eval protocol as GRPO evals (eval_lr5e6_ckpt20.sh). Required for MVP-2 core comparison: CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp. Prior SFT eval (r3) used different eval path; this ensures apple-to-apple comparison.
379	  notes: [2026-05-15 07:39] Eval 正常完成。结果与 r2/r3 完全一致 (rel_f1=0.4057, evi_f1=0.7979)，apple-to-apple 对比协议复现成功。结果路径: /root/autodl-tmp/sft_baseline_eval_results/metrics.json。cuda:3 已释放。
380	
381	=== mvp2_grpo_ced ===
382	  status: DONE
383	  conclusion: failed
384	  seed: 
385	  model: 
386	  notes: 失败原因: grpo_trainer.py:109 f1_reward_fn 中 p.get("tail", "").lower() 报 AttributeError: 'NoneType' — 某些 parsed triple 的 "tail" 字段为 None，dict.get 有 key 时不返回 default | 运行 ~36min 后崩溃 | 修复方案: 用 (p.get("tail") or "") 模式处理 None | error_type: infrastructure | can_auto_fix: true
387	
388	=== mvp2_grpo_ced_kl001 ===
389	  status: DONE
390	  conclusion: failed
391	  seed: 42
392	  model: Qwen3-4B
393	  hypothesis: kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary
394	  notes: 三次失败：r1 --lr 不识别 (EXIT_CODE=2)，r2 conda 未激活 python not found (EXIT_CODE=127)，r3 缺 --data_dir。已在 r4 修正所有问题。
395	
396	=== mvp2_grpo_ced_kl001_r2 ===
397	  status: DONE
398	  conclusion: killed
399	  seed: 
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "c37f9e1e-aadc-4317-ab8d-5e6400953a64"
}
```

</details>

---

### System

_source line 50_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "usage": {
    "total_tokens": 39854,
    "tool_uses": 10,
    "duration_ms": 59851
  },
  "last_tool_name": "Read",
  "uuid": "b432b5df-f102-4dba-a035-9d56cc2b0127",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 51_

<details open><summary>🔧 Tool call — Read · `toolu_013jBNR7BsKtijvdSxcni3Xq`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "offset": 400,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "08a35ccc-d93b-4d0f-85d6-749c45a38e38",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FU7mBoWUKRQrcfEoSJMQVP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8437,
      "cache_read_input_tokens": 30965,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8437,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 38,
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

_source line 52 · 2026-05-16T03:22:38.286Z_

<details><summary>↩ Tool result · `toolu_013jBNR7BsKtijvdSxcni3Xq`</summary>

```text
400	  model: 
401	  hypothesis: kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr → --learning_rate)
402	  notes: 失败原因: 命令未用 bash -c 包裹，tmux 以 sh 执行导致 source 命令失败。error_type: infrastructure | can_auto_fix: true
403	
404	=== mvp2_grpo_ced_kl001_r3 ===
405	  status: DONE
406	  conclusion: killed
407	  seed: 
408	  model: 
409	  hypothesis: kl_coef=0.01 (vs r5 kl_coef=0.0) prevents CED mode collapse while keeping QLoRA 4-bit compatible — answers whether KL regularization is necessary (retry: fix --lr + bash -c wrapping)
410	  notes: 失败原因: datasets 库不支持 thunlp/docred 自定义脚本 (RuntimeError: Dataset scripts are no longer supported)。命令缺少 --data_dir /root/autodl-tmp/data/docred 参数，触发 HF 远程下载失败。需要补全所有必要参数后重新提交。error_type: infrastructure | can_auto_fix: true
411	
412	=== mvp2_grpo_ced_kl001_r4 ===
413	  status: DONE
414	  conclusion: success
415	  seed: 42
416	  model: Qwen3-4B
417	  metrics: {"final_step": 100, "train_runtime_s": 9069.88, "reward_final": 1.195, "f1_reward_final": 0.573, "ced_reward_final": 0.328, "format_reward_final": 0.293, "frac_zero_std_final": 0.2, "kl_final": 0.118, "loss_final": -0.009, "grad_norm_final": 0.14, "entropy_final": 0.067, "completion_length_mean_final": 520.8, "best_reward_step": 90, "best_reward": 1.37, "best_f1_reward": 0.72, "best_ced_reward": 0.353}
418	  notes: D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100 探测。✅ F1 门控已包含。
419	
420	**训练完成 (100/100 steps, EXIT_CODE=0, 2h31m)**:
421	- Final (step 100): reward=1.195, f1=0.573, ced=0.328, frac_zero_std=0.2, KL=0.118
422	- **True best: step 90** (reward=1.370, f1=0.720, ced=0.353) — 比 step 50 (1.101) 高
423	
424	=== mvp2_grpo_ced_lr5e6_p1_r1 ===
425	  status: DONE
426	  conclusion: killed
427	  seed: 
428	  model: 
429	  hypothesis: D031/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 15000 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.
430	  notes: Superseded by mvp2_grpo_ced_lr5e6_rp_r1 per Director D032. Never submitted.
431	
432	=== mvp2_grpo_ced_lr5e6_r1 ===
433	  status: DONE
434	  conclusion: killed
435	  seed: 42
436	  model: Qwen3-4B + SFT adapter
437	  hypothesis: D030/P0: lr=5e-6 (10x lower than ced_kl001_r4) prevents catastrophic forgetting while maintaining CED reward improvement. Community consensus GRPO+QLoRA lr=5e-6~1e-5. Pass criteria: ckpt-20 rel_f1 > 0.30. Extra monitoring: pred_count + recall trend.
438	  notes: [2026-05-15 01:08] D032 执行: PID 90080 killed (force_killed=true)。训练 step ~113/200。完整 lr5e-6 轨迹: ckpt-20→40→60→80 rel_f1 = 0.008/0.007/0.009/0.012，无恢复信号。GRPO+QLoRA 方向判死 (D031)，GPU 释放给 RSFT 流水线。
439	
440	=== mvp2_grpo_ced_lr5e6_rp_r1 ===
441	  status: DONE
442	  conclusion: failed
443	  seed: 42
444	  model: Qwen3-4B + SFT adapter
445	  hypothesis: D032/P0+P1: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 isolates CED shortcut fix contribution.
446	  notes: Director D-URGENT: 与 rp_r2 冲突，同 GPU(cuda:3) 同 output_dir(/root/autodl-tmp/grpo_ced_lr5e6_rp/)。PID 94055 killed，保留 rp_r2 (PID 94758) 因其有标准化 submit_training_job 记录。
447	
448	=== mvp2_grpo_ced_lr5e6_rp_r2 ===
449	  status: DONE
450	  conclusion: killed
451	  seed: 42
452	  model: Qwen3-4B + SFT adapter
453	  hypothesis: D032/P0+P1 retry: lr=5e-6 + --ced_recall_penalty fixes both catastrophic forgetting (lr) and CED recall shortcut (penalty). Pass criteria: ckpt-20 rel_f1 > 0.30 AND pred_count >= 9720 (SFT 80%). Comparing vs P0 (lr5e6_r1) isolates CED shortcut fix contribution. Retry of rp_r1 which failed due to bas
454	  notes: Director 决策 kill: loss 持续指数 divergence (step 10: 908 → step 15: 24,650 → step 20: 1.34e7)。根因: recall penalty 产生 5-10x 更强梯度，在 QLoRA 4-bit 下加剧 KL 爆炸，kl_coef=0.01 × KL=1.42e9 = 1.42e7 完全主导 loss。训练 step 39 被 kill。ckpt-20 将用于 eval 关闭 P0+P1 对比线。
455	
456	=== mvp2_grpo_ced_r1 ===
457	  status: DONE
458	  conclusion: killed
459	  seed: 42
460	  model: Qwen3-4B
461	  notes: Mode collapse diagnosed at step 80/189 (F1=0.001, format reward hacking). Root causes and fixes applied to grpo_trainer.py:
462	
463	(A) Checkpoint: save_strategy was "epoch" → now supports --save_steps/--save_total_limit CLI args, defaults to steps-based saving. Validated: checkpoint-1/2 saved in dry-run.
464	
465	
466	=== mvp2_grpo_ced_r2 ===
467	  status: DONE
468	  conclusion: killed
469	  seed: 42
470	  model: Qwen3-4B
471	
472	=== mvp2_grpo_ced_r3 ===
473	  status: DONE
474	  conclusion: failed
475	  seed: 42
476	  model: Qwen3-4B
477	  hypothesis: CED reward with balanced weights (format×0.3, f1×3.0, ced×1.0) + stable training (num_iterations=1, KL early stop at 100) + kl_coef=0.05 improves Evi-F1 over SFT baseline
478	  notes: KL divergence explosion at step 5: first pass KL=4.4M, second pass KL=69.5B (threshold=100). KL early stopping correctly triggered, model saved but no useful training occurred.
479	
480	Root cause: single-GPU training without --gradient_accumulation_steps (effective batch=1) → extremely noisy gradients → po
481	
482	=== mvp2_grpo_ced_r4 ===
483	  status: DONE
484	  conclusion: killed
485	  seed: 42
486	  model: Qwen3-4B
487	  notes: Killed: 上一 session 使用 kl_coef=0.0/lr=5e-5 启动，但 Director 要求 D009 配置 (kl_coef=0.5, lr=5e-6, warmup_steps=200)。需等 extract/flatnli 分析完再用正确配置重新提交。
488	
489	=== mvp2_grpo_ced_r5 ===
490	  status: DONE
491	  conclusion: negative
492	  seed: 42
493	  model: Qwen3-4B
494	  notes: ⚠️ Mode collapse confirmed: step 250+ f1_reward=0, completion length collapsed to fixed 34 tokens, frac_reward_zero_std=0.9-1.0. Model learned to produce short fixed-format output maximizing ced_reward (0.99) + format_reward (0.3) while abandoning relation extraction (f1=0). Early checkpoints (pre-c
495	
496	=== mvp2_grpo_extract ===
497	  status: DONE
498	  conclusion: failed
499	  seed: 42
500	  model: Qwen3-4B (QLoRA from SFT warmup)
501	  hypothesis: Extraction-only reward (format+F1, no CED) establishes GRPO baseline — CED r3 should exceed this on Evi-F1
502	  notes: KL divergence explosion at step 5 due to kl_coef=0.05 + QLoRA 4-bit incompatibility (D008). QLoRA quantization noise makes ref/policy log-prob divergence unreliable, causing KL values to reach 10^8-10^11. Same root cause as r3 and flatnli. Fix: kl_coef=0.0 in r2 retries.
503	
504	=== mvp2_grpo_extract_r2 ===
505	  status: DONE
506	  conclusion: killed
507	  seed: 42
508	  model: Qwen3-4B
509	  notes: Killed: Director 指令暂不提交 r2，等原始 extract 分析完再决定配置。
510	
511	=== mvp2_grpo_extract_r3 ===
512	  status: DONE
513	  conclusion: negative
514	  seed: 42
515	  model: Qwen3-4B
516	  notes: Negative result (756/756 steps completed). 两阶段行为：(1) step 1-520 f1_reward 在 0.02-0.49 波动，completion length ~43 tokens 稳定，看似健康；(2) 实际最后 100+ 步 grad_norm=0, frac_reward_zero_std=1.0, loss=0.0, entropy≈0.005。f1 波动是 SFT 初始化残留，非 GRPO 学习。停滞机制：kl_coef=0 + num_generations=4 → 4 个相同输出 → reward_std=0 → GRPO a
517	
518	=== mvp2_grpo_extract_r4 ===
519	  status: DONE
520	  conclusion: killed
521	  seed: 42
522	  model: Qwen3-4B
523	  hypothesis: Extraction-only reward (format×0.3, f1×3.0, ced=0) with kl_coef=0.01 + num_generations=8 trains stably. 100-step probe parallel ablation with ced_kl001_r4 (CED reward) to compare reward type impact under identical stability config.
524	  notes: D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100 探测。与 ced_kl001_r4 (cuda:0) 构成并行 ablation——相同稳定配置、不同 reward type (extract-only vs CED)。
525	
526	**Mode collapse confirmed → KILLED at step ~30**:
527	- step 5: frac_zero_std=0.2, f1=0.016（初始信号）
528	- step 10-30: frac_zero_std=0.7-0.8, f1_rewar
529	
530	=== mvp2_grpo_flatnli ===
531	  status: DONE
532	  conclusion: failed
533	  seed: 42
534	  model: Qwen3-4B
535	  hypothesis: Flat-NLI reward (non-contrastive) improves Evi-F1 over extraction-only but less than CED — validates contrastive component's incremental value
536	  notes: KL divergence explosion at step 5 due to kl_coef=0.05 + QLoRA 4-bit incompatibility (D008). QLoRA quantization noise makes ref/policy log-prob divergence unreliable. Same root cause as r3 and extract. Fix: kl_coef=0.0 in r2 retries.
537	
538	=== mvp2_grpo_flatnli_r2 ===
539	  status: DONE
540	  conclusion: killed
541	  seed: 42
542	  model: Qwen3-4B
543	  notes: Killed: Director 指令暂不提交 r2，等原始 flatnli 分析完再决定配置。
544	
545	=== mvp2_grpo_flatnli_r3 ===
546	  status: DONE
547	  conclusion: killed
548	  seed: 42
549	  model: Qwen3-4B
550	  notes: Director 指令 kill：NLI 推理在 CPU 导致 10x 减速（~100-125s/step vs 应有 ~12s/step）。训练本身健康——step 104/756, grad_norm=0.37, f1 从 step 84 起出现, flat_nli_reward=0.52, entropy=0.046。Checkpoint 已备份。修复 --reward_device cuda 后以 flatnli_r4 重启。
551	
552	=== mvp2_grpo_flatnli_r4 ===
553	  status: DONE
554	  conclusion: killed
555	  seed: 42
556	  model: Qwen3-4B
557	  notes: Director 指令 kill: kl=0+gen=4 配置已在 ced_r5/extract_r3/flatnli_r3 三个实验崩塌，统一切到 kl=0.01+gen=8。flatnli_r4 运行 step 104→~130（~30 min），step_time ~34s/step。用 flatnli_r5 从 checkpoint-100 重启。
558	
559	=== mvp2_grpo_flatnli_r5 ===
560	  status: DONE
561	  conclusion: killed
562	  seed: 42
563	  model: Qwen3-4B
564	  hypothesis: Flat-NLI reward with kl_coef=0.01 + num_generations=8 prevents mode collapse. Resume from flatnli_r3 checkpoint-100 (healthy). 100-step probe (steps 100→200) to verify stability before full run.
565	  notes: Director 决策 kill：从 r3 (kl_coef=0) checkpoint-100 恢复后立即崩溃。frac_zero_std: 0.0(r3)→0.9(step 105)→0.7→0.5→0.8(step 120)，0.5-0.9 震荡无收敛。KL 全程 0.44-0.49 高位。根因：kl_coef=0 累积的 policy 漂移 + kl_coef=0.01 penalty 形成对抗。教训：不能从 kl_coef=0 的 checkpoint 恢复加 KL penalty。flatnli_r6 从 SFT 全新训练。
566	
567	=== mvp2_grpo_flatnli_r6 ===
568	  status: DONE
569	  conclusion: negative
570	  seed: 42
571	  model: Qwen3-4B
572	  metrics: {"steps_completed": 25, "final_frac_zero_std": 0.9, "final_f1_reward": 0, "final_flat_nli_reward": 0, "final_format_reward": 0.293, "collapse_step": 25}
573	  hypothesis: Flat-NLI reward with kl_coef=0.01 + num_generations=8 from SFT scratch (not resume). 100-step probe to verify stability. Same D020 config as ced_kl001_r4 (which is healthy). Tests whether flat-NLI reward type works under stable training config.
574	  notes: D020 配置：kl_coef=0.01 + num_generations=8 + save_steps=10 + max_steps=100。从 SFT 全新训练。
575	
576	**D024 Kill — Mode Collapse Confirmed (step 25)**:
577	- frac_zero_std: 0.1→0.4→0.6→0.7→0.9 (单调上升，破 0.8 阈值)
578	- f1_reward=0, flat_nli_reward=0 — 抽取和 NLI 完全死亡
579	- reward 100% format hacking (0.293)
580	- completion_length 缩短 77
581	
582	=== mvp2_rsft_ced_scoring ===
583	  status: DONE
584	  conclusion: success
585	  seed: 42
586	  model: cross-encoder/nli-deberta-v3-base
587	  metrics: {"input_generations": 21952, "selected_samples": 2718, "unique_docs": 2691, "selection_rate": 0.124, "mean_f1": 0.6157, "mean_ced": 0.6683, "f1_range": [0.1026, 1], "zero_f1_samples": 0, "selection_strategy": "top_k=1", "f1_threshold": 0.1}
588	  hypothesis: CED scoring + filtering on 4 shard RSFT generations. top_k=1, f1_threshold=0.1. 21952 → 2718 selected (12.4%).
589	
590	=== mvp2_rsft_ced_scoring_topk3 ===
591	  status: DONE
592	  conclusion: killed
593	  seed: 42
594	  model: cross-encoder/nli-deberta-v3-base
595	  hypothesis: CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Answers: does CED filtering strictness affect RSFT training quality?
596	  notes: NLI 模型加载失败 (HuggingFace Network unreachable)。命令缺少 HF_HOME/HF_HUB_OFFLINE/TRANSFORMERS_OFFLINE 环境变量。重试为 mvp2_rsft_ced_scoring_topk3_r2。
597	
598	=== mvp2_rsft_ced_scoring_topk3_r2 ===
599	  status: DONE
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "e5c4a4bb-487e-4b00-923c-838ab2d96894"
}
```

</details>

---

### System

_source line 53_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "usage": {
    "total_tokens": 45540,
    "tool_uses": 11,
    "duration_ms": 65710
  },
  "last_tool_name": "Read",
  "uuid": "487c384a-b2ba-4bd5-909d-6c81a34d59ae",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 54_

<details open><summary>🔧 Tool call — Read · `toolu_01852519iSA6txPWjthaghc6`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "offset": 599,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "72f4a857-4bd9-435b-b019-f74ab5f0af40",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017MeAkSawkC3eopEmQ6wAi1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5648,
      "cache_read_input_tokens": 39402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5648,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 38,
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

_source line 55 · 2026-05-16T03:22:44.137Z_

<details><summary>↩ Tool result · `toolu_01852519iSA6txPWjthaghc6`</summary>

```text
599	  status: DONE
600	  conclusion: success
601	  seed: 
602	  model: 
603	  metrics: {"input_generations": 21728, "selected_samples": 8037, "unique_docs": 2691, "selection_rate": 0.37, "mean_f1": 0.5761, "mean_ced": 0.6205, "mean_combined": 0.6787, "f1_range_p25": 0.444, "f1_range_p75": 0.717, "ced_range_p25": 0.487, "ced_range_p75": 0.774, "truncated_samples": 1924, "truncated_pct": 8.9, "selection_strategy": "top_k=3", "f1_threshold": 0.1, "topk1_samples": 2718, "data_multiplier": 2.96}
604	  hypothesis: CED scoring ablation: top_k=3 (vs top_k=1). More training data (~8000 samples) vs stricter selection (2718 samples). Retry with HF_HUB_OFFLINE=1 (NLI model cached locally).
605	  notes: top_k=3 scoring 完成。8037 samples (vs top_k=1 的 2718, 2.96x)。质量下降可控: mean_f1 -0.04, mean_ced -0.048。输出: /root/autodl-tmp/rsft_filtered_topk3/rsft_train.jsonl (24.8MB)。可用于 plan_008 RSFT 训练 ablation。
606	
607	=== mvp2_rsft_diagnosis ===
608	  status: DONE
609	  conclusion: success
610	  seed: 
611	  model: 
612	  metrics: {"root_cause": "overfitting_plus_sft_knowledge_overwrite", "truncated_json_samples": 170, "truncated_pct": 6.3, "epoch1_eval_loss": 0.756, "epoch2_eval_loss": 0.759, "lora_scaling": 2, "rsft_zero_relation_samples": 170, "sft_zero_relation_docs": 26, "rsft_mean_relations": 11.2, "sft_mean_relations": 12.5}
613	  hypothesis: RSFT failure root cause: rel_f1=0.0483 vs SFT 0.4057. Diagnose: training data distribution (relation count), step-170 checkpoint output analysis, SFT vs RSFT data comparison.
614	
615	=== mvp2_rsft_gen_s0 ===
616	  status: DONE
617	  conclusion: success
618	  seed: 
619	  model: 
620	  hypothesis: RSFT generation shard 0/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.
621	  notes: [2026-05-15 05:01] 生成完成 682/682 docs (100%)。EXIT_CODE=143 是正常完成后的清理 SIGTERM。format_ok 99.6%, truncation_rate 10.1%, diversity 7.6/8。
622	
623	=== mvp2_rsft_gen_s1 ===
624	  status: DONE
625	  conclusion: success
626	  seed: 
627	  model: 
628	  hypothesis: RSFT generation shard 1/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.
629	
630	=== mvp2_rsft_gen_s2 ===
631	  status: DONE
632	  conclusion: success
633	  seed: 
634	  model: 
635	  hypothesis: RSFT generation shard 2/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.
636	
637	=== mvp2_rsft_gen_s3 ===
638	  status: DONE
639	  conclusion: success
640	  seed: 
641	  model: 
642	  metrics: {"generation_count": 5288, "unique_docs": 659, "format_compliance": 0.998, "diversity_range": "7.5-7.8/8", "exit_code": 0}
643	  hypothesis: RSFT generation shard 3/4: N=8 generations at T=0.7 with generation_config override (top_k=0). OOM fix: batch_size=1.
644	
645	=== mvp2_rsft_generate ===
646	  status: DONE
647	  conclusion: failed
648	  seed: 
649	  model: 
650	  hypothesis: RSFT generation phase: SFT model generates N=8 candidate outputs per training sample at T=0.7. CED scoring + filtering后作为 RSFT 训练数据。D031 pivot 方向。
651	
652	=== mvp2_rsft_r2a ===
653	  status: DONE
654	  conclusion: success
655	  seed: 
656	  model: 
657	  metrics: {"rel_f1": 0.4494, "evi_f1": 0.8108, "edcr": 0.6641, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "delta_rel_f1": 0.0437, "delta_evi_f1": 0.0129, "mvp2_pass": true}
658	  hypothesis: RSFT r2a: data fix only (1 epoch + filter 170 truncated JSON → 2548 samples). Same LoRA alpha=128/r=64, lr=2e-5 as r1. Isolates: does 1 epoch + clean data alone fix the ontology collapse? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
659	  notes: 训练完成 (160 steps, 35.5min, eval_loss=0.7547)。TaskEvalCallback rel_f1=0.0509 是已知 bug (D038: gold triples 分母不匹配)，不代表真实性能。需全量 dev eval 确认实际指标。
660	
661	=== mvp2_rsft_r2b ===
662	  status: DONE
663	  conclusion: success
664	  seed: 
665	  model: 
666	  metrics: {"rel_f1": 0.4493, "evi_f1": 0.8128, "edcr": 0.6609, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "delta_rel_f1": 0.0436, "delta_evi_f1": 0.0149, "mvp2_pass": true}
667	  hypothesis: RSFT r2b: data fix + training dynamics fix (1 epoch + filter truncated + LoRA alpha=32/r=64 scaling 0.5 + lr=1e-5). Isolates: is conservative LoRA scaling the key factor? Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
668	  notes: 训练完成 (160 steps, 33.7min, eval_loss=0.7545)。TaskEvalCallback rel_f1=0.0504 是已知 bug (D038: gold triples 分母不匹配)，不代表真实性能。需全量 dev eval 确认实际指标。
669	
670	=== mvp2_rsft_train_r1 ===
671	  status: DONE
672	  conclusion: success
673	  seed: 
674	  model: 
675	  metrics: {"rel_f1": 0.0483, "num_preds": 848, "sft_baseline_rel_f1": 0.4057, "failure_mode": "relation_ontology_collapse_to_freetext", "epoch1_eval_loss": 0.756, "epoch2_eval_loss": 0.759}
676	  hypothesis: RSFT training on CED-filtered data (2718 samples, mean CED=0.668). SFT warmup baseline: rel_f1=0.4057, evi_f1=0.798. Pass criteria: rel_f1 > 0.4057 AND evi_f1 > 0.798.
677	  notes: D037 修正: TaskEvalCallback 的 rel_f1=0.0483 是 eval bug（gold triples 未限制为 eval_max_docs 子集）。全量 eval 待跑。s44 全量 eval 已 PASS: rel_f1=0.4655, evi_f1=0.8087。
678	
679	=== mvp2_rsft_train_r1_s43 ===
680	  status: DONE
681	  conclusion: success
682	  seed: 
683	  model: 
684	  metrics: {"eval_loss": 0.7622, "train_loss": 0.6148, "eval_entropy": 0.6724, "mean_token_accuracy": 0.8291, "total_steps": 510, "epochs": 3, "training_hours": 1.99}
685	  hypothesis: RSFT training seed=43 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.
686	  notes: 训练正常完成 (510 steps, 1.99h, eval_loss=0.7622, train_loss=0.6148)。与 s44 (eval_loss=未记录) 和 r1 相近。TaskEvalCallback rel_f1 是已知 bug，需全量 eval。全量 eval 重试 mvp2_eval_rsft_s43_r2 正在运行中。
687	
688	=== mvp2_rsft_train_r1_s44 ===
689	  status: DONE
690	  conclusion: success
691	  seed: 
692	  model: 
693	  metrics: {"rel_f1": 0.4655, "evi_f1": 0.8087, "evi_f1_joint": 0.3713, "evi_f1_joint_P": 0.3775, "evi_f1_joint_R": 0.3653, "edcr": 0.635, "sft_baseline_rel_f1": 0.4057, "sft_baseline_evi_f1": 0.7979, "delta_rel_f1": 0.0598, "delta_evi_f1": 0.0108, "delta_evi_f1_joint": 0.0596, "mvp2_pass": true}
694	  hypothesis: RSFT training seed=44 variance estimate. Same params as r1 (bf16 LoRA r=64/α=128, lr=2e-5, 3 epochs, weighted sampling, CED-filtered 2718 samples). Pass: rel_f1 > 0.4057 AND evi_f1 > 0.798.
695	
696	=== mvp2_rsft_train_r2_fix ===
697	  status: DONE
698	  conclusion: killed
699	  seed: 
700	  model: 
701	  hypothesis: RSFT r2 fix: 4 fixes based on r1 diagnosis. 1) 1 epoch (vs 3), 2) LoRA alpha=32/r=64 (scaling 0.5 vs 2.0), 3) filtered truncated JSON (~2548 vs 2718 samples), 4) lr=1e-5 (vs 2e-5). Pass: rel_f1 > 0.4057, evi_f1 > 0.798.
702	
703	=== mvp2_sft_eval ===
704	  status: DONE
705	  conclusion: killed
706	  seed: 42
707	  model: Qwen3-4B
708	  notes: Killed intentionally to restart with batch_size=16 (was batch_size=4, ~6h → ~1.5h). Director approved.
709	
710	=== mvp2_sft_eval_r2 ===
711	  status: DONE
712	  conclusion: success
713	  seed: 42
714	  model: Qwen3-4B
715	  metrics: {"rel_f1": 0.4057, "ign_f1": 0.4057, "evi_f1": 0.7979, "edcr": 0.7118, "precision": 0.4043, "recall": 0.407, "evi_precision": 0.8035, "evi_recall": 0.7924, "format_ok_rate": 0.998, "format_compliance_rate": 0.626, "n_parseable": 617, "n_truncated": 367, "n_predictions": 18815, "inference_time_seconds": 6484.7}
716	
717	=== mvp2_sft_eval_r3 ===
718	  status: DONE
719	  conclusion: success
720	  seed: 42
721	  model: Qwen3-4B
722	  protocol: unified
723	  metrics: {"rel_f1": 0.4057, "ign_f1": 0.4057, "evi_f1": 0.7979, "edcr": 0.7118, "precision": 0.4043, "recall": 0.407, "evi_precision": 0.8035, "evi_recall": 0.7924, "format_ok_rate": 0.998, "format_compliance_rate": 0.626, "n_parseable": 617, "n_truncated": 367, "n_predictions": 18815}
724	  notes: 统一 eval 代码验证：r3 与 r2 所有指标完全一致（差异=0.00pp），含 _repair_truncated_json 的统一 eval 脚本未引入任何偏差。SFT baseline 可靠确认：rel_f1=0.4057, evi_f1=0.7979, edcr=0.7118。983 parseable / 617 field_complete / 367 truncated / 18815 predictions。
725	
726	=== mvp2_sft_warmup ===
727	  status: DONE
728	  conclusion: success
729	  seed: 42
730	  model: Qwen3-4B
731	  metrics: {"eval_loss": 0.72, "accuracy": 0.835}
732	
733	=== plan_001_flat_nli_scoring ===
734	  status: DONE
735	  conclusion: success
736	  seed: 42
737	  model: DeBERTa-v3-large-mnli-fever-anli-ling-wanli
738	  metrics: {"total_scored": 21728, "selected_samples": 2691, "selection_rate": 0.124, "selection_strategy": "top_k=1", "f1_threshold": 0.1, "output_path": "/root/autodl-tmp/rsft_filtered_flat_nli/rsft_train.jsonl"}
739	  hypothesis: flat-NLI scoring 前置步骤：用 flat_nli 模式（p_pos 概率，无 contrastive margin）对 RSFT 生成候选打分并筛选训练数据。
740	  notes: Scoring 实际用 top_k=1（非 spec 中的 top_k=3），与 CED scoring 的 top_k=1 (2718 samples) 公平对比。选出 2691 samples。Cron 误报 failed（假阴性），Reviewer 确认输出完整。
741	
742	=== plan_001_flat_nli_seed43 ===
743	  status: DONE
744	  conclusion: success
745	  seed: 43
746	  model: Qwen3-4B + SFT adapter
747	  metrics: {"train_loss_final": 0.6257, "train_loss_min": 0.5895, "eval_loss_epoch3": 0.7567, "eval_accuracy_epoch3": 0.8298, "total_steps": 507, "epochs": 3, "train_runtime_seconds": 6880, "task_eval_f1_ep1": 0.4825, "task_eval_f1_ep2": 0.4542, "task_eval_f1_ep3": 0.4866, "task_eval_evi_f1_ep3": 0.7834, "task_eval_edcr_ep3": 0.6402, "task_eval_note": "50-doc subset, not full dev"}
748	  notes: 训练正常完成 (EXIT_CODE=0)。507 steps, 3 epochs, eval_loss 三 epoch 持平 (0.753-0.757) 无过拟合。与 seed42 高度一致 (train_loss 0.6248 vs 0.6238, accuracy ~0.855 vs 0.853)。Checkpoint: /root/autodl-tmp/rsft_output_flat_nli_s43/checkpoint-507。下一步: dev eval 提取 rel_f1/evi_f1。
749	
750	=== plan_001_flat_nli_seed44 ===
751	  status: DONE
752	  conclusion: success
753	  seed: 44
754	  model: Qwen3-4B + SFT adapter
755	  metrics: {"train_loss": 0.6247, "eval_loss": 0.7564, "eval_mean_token_accuracy": 0.8299, "task_eval_f1_ep1": 0.4306, "task_eval_f1_ep2": 0.4884, "task_eval_f1_ep3": 0.4897, "task_eval_evi_f1_ep3": 0.78, "task_eval_edcr_ep3": 0.6596, "task_eval_ign_f1_ep3": 0.4897, "train_runtime_sec": 6197, "num_epochs": 3, "total_steps": 507}
756	
757	=== plan_001_flat_nli_seed45 ===
758	  status: DONE
759	  conclusion: success
760	  seed: 45
761	  model: Qwen3-4B + SFT adapter
762	  metrics: {"task_eval_rel_f1": 0.4876, "task_eval_evi_f1": 0.7927, "task_eval_edcr": 0.6517, "train_loss": 0.6245, "runtime_hours": 1.69, "note": "task-eval on 50 docs only, full dev eval needed"}
763	
764	=== plan_001_rsft_flat_nli ===
765	  status: DONE
766	  conclusion: success
767	  seed: None
768	  model: Qwen3-4B + SFT adapter
769	  metrics: {"train_loss": 0.6238, "train_loss_min": 0.5803, "mean_token_accuracy": 0.8528, "train_runtime_sec": 2946, "epochs": 3, "total_steps": 507, "samples": 2691}
770	  hypothesis: flat-NLI RSFT ablation: 用 flat-NLI scoring（p_pos 概率，无 contrastive margin）筛选的 2691 样本做 RSFT。对比 CED scoring RSFT（2718 样本）。验证 CED 的对比性 margin 是否是关键因素。如 flat-NLI RSFT ≈ CED RSFT → CED 无增益；如 CED RSFT 显著优于 → contrastive margin 关键。
771	
772	=== plan_002_test_eval_s44 ===
773	  status: DONE
774	  conclusion: failed
775	  seed: 42
776	  model: Qwen3-4B + SFT + RSFT-s44
777	  notes: DocRED test split 无 gold labels，inference.py 不支持 enumerate_all_pairs 模式。推迟到论文终稿阶段（需改造 inference.py + CodaLab submission）。Director 指令标记 failed。
778	
779	=== plan_003_edcr_diagnostic ===
780	  status: DONE
781	  conclusion: success
782	  seed: 
783	  model: 
784	  metrics: {"methods_evaluated": 15, "edcr_vs_rel_f1_spearman": -0.9648, "edcr_vs_rel_f1_pvalue": 0.0001, "edcr_vs_evi_f1_spearman": 0.0022, "edcr_vs_evi_f1_pvalue": 0.9941, "edcr_range": "0.63-0.99", "unique_diagnostic_value": "identifies pathological models (GRPO QLoRA) with high evi_f1 but catastrophically low rel_f1"}
785	  hypothesis: EDCR cross-method diagnostic table: 计算所有 evidence-producing 方法（SFT baseline, RSFT-CED best, RSFT-flatNLI best, CED-reranker）的 EDCR，验证 EDCR 作为独立评估指标的诊断能力。plan_id=plan_003, claim=4。GPU 预算 2h。
786	
787	=== plan_004_dreeam_baseline ===
788	  status: DONE
789	  conclusion: success
790	  seed: 66
791	  model: roberta-large
792	  metrics: {"dev_rel_f1": 63.57, "dev_rel_ign_f1": 61.72, "dev_evi_f1": 54.01, "dev_rel_p": 66.95, "dev_rel_r": 60.51, "dev_evi_p": 60.53, "dev_evi_r": 48.76}
793	  hypothesis: Phase A: 复现 DREEAM fully-supervised teacher (RoBERTa-large) DocRED dev Evi-F1≈54.15, RE-F1≈63.49。论文报告的57.34是student model在test set的结果，需4阶段self-training pipeline。
794	
795	=== plan_008_rsft_topk3 ===
796	  status: DONE
797	  conclusion: success
798	  seed: 42
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6ed28a61-9453-4f66-b355-868ee4ee0185"
}
```

</details>

---

### System

_source line 56_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Reading ~/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "usage": {
    "total_tokens": 51791,
    "tool_uses": 12,
    "duration_ms": 71158
  },
  "last_tool_name": "Read",
  "uuid": "169d9e92-f9b3-4b2e-b003-b1be4fbf6a35",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 57_

<details open><summary>🔧 Tool call — Read · `toolu_01SKwd99BxU8Q4cEYZ8hp19n`</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/bihqfc4mv.txt",
  "offset": 798,
  "limit": 300
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6aa7ea6e-d1f8-4c9d-8baf-ea9d136dd353",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FYAa8mUVyQfd8vEQGT9977",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6213,
      "cache_read_input_tokens": 45050,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6213,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 38,
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

_source line 58 · 2026-05-16T03:22:49.587Z_

<details><summary>↩ Tool result · `toolu_01SKwd99BxU8Q4cEYZ8hp19n`</summary>

```text
798	  seed: 42
799	  model: Qwen3-4B + SFT adapter + RSFT top_k=3
800	  metrics: {"train_loss": 0.5543, "eval_loss": 0.8297, "eval_mean_token_accuracy": 0.8228, "eval_entropy": 0.6001, "train_runtime_sec": 10916, "total_steps": 1509, "epochs": 3, "trainable_params_pct": 3.18, "rsft_samples": 8037, "ced_score_mean": 0.621, "task_eval_f1_ep1": 0.4848, "task_eval_f1_ep2": 0.4824, "task_eval_f1_ep3": 0.5012, "task_eval_evi_f1_ep1": 0.745, "task_eval_evi_f1_ep2": 0.6997, "task_eval_evi_f1_ep3": 0.6816, "task_eval_edcr_ep1": 0.6525, "task_eval_edcr_ep2": 0.6529, "task_eval_edcr_ep3": 0.5963, "task_eval_note": "50-doc subset, not full dev"}
801	  hypothesis: RSFT top_k=3 训练：用 CED-filtered 的 top-3 候选进行 rejection sampling fine-tuning，验证更多候选是否比 top_k=1 (rel_f1≈0.46) 带来更好的证据质量。
802	  notes: RSFT top_k=3 训练正常完成。3 epochs, 1509 steps, 3h02m。8037 RSFT 样本 (CED mean=0.621)。Task eval (50-doc subset): F1 从 ep1=0.4848 升至 ep3=0.5012，但 Evi-F1 从 0.745 降至 0.6816，EDCR 从 0.6525 降至 0.5963，呈现 relation extraction 提升但证据质量下降的 trade-off。与 CED RSFT top_k=5 baseline (rel_f1=0.4596) 相比，subset F1=0.5012 看起来更高，
803	
804	=== plan_009_dynamics_figure ===
805	  status: DONE
806	  conclusion: success
807	  seed: 0
808	  model: N/A (visualization task)
809	  hypothesis: GRPO forgetting dynamics 3-panel figure: QLoRA vs BF16 GRPO 的 rel_f1/evi_f1/EDCR 训练轨迹对比。支撑 Claim 3 (task decoupling 是 QLoRA-specific)。plan_id=plan_009。
810	
811	=== plan_009_extract_reward_eval ===
812	  status: DONE
813	  conclusion: failed
814	  seed: 
815	  model: 
816	  notes: OOM: Worker 提交到了 GPU 0（被 plan_001 占用 16 GiB），而非目标 cuda:1。需在 cuda:0 释放后重提交。
817	
818	=== plan_009_flatnli_reward_eval ===
819	  status: DONE
820	  conclusion: failed
821	  seed: 42
822	  model: Qwen3-4B + SFT + QLoRA GRPO (flatNLI reward)
823	
824	=== plan_009_flatnli_reward_eval_r2 ===
825	  status: DONE
826	  conclusion: failed
827	  seed: 42
828	  model: Qwen3-4B + SFT + QLoRA GRPO (flatNLI reward)
829	  notes: OOM 失败。--no-quantize + batch_size 16 + max_new_tokens 1024 在单卡 RTX 5090 (32GB) 上 OOM。全部 5 个 checkpoint (20-100) 均未完成 eval。checkpoint-20 仅完成 1/62 batches 即被 kill (-9)。修复方案：降 batch_size 至 4 或 2 后重提交。
830	
831	=== plan_009_forgetting_figure ===
832	  status: DONE
833	  conclusion: success
834	  seed: 0
835	  model: N/A (visualization)
836	  notes: 3-panel figure: (a) Training Reward—bf16 1.5-3.0 vs QLoRA 0.1-1.2; (b) Rel-F1—QLoRA暴跌至0.01(lr5e-6)/0.22(lr5e-5), bf16稳定0.45+; (c) Evi-F1—QLoRA lr5e-6反升至0.85, bf16稳定0.81。Artifacts: art_20260515_eace0b (PNG), art_20260515_319233 (PDF)。
837	
838	=== plan_011_bf16_g8_step_eval ===
839	  status: DONE
840	  conclusion: success
841	  seed: 
842	  model: 
843	  metrics: {"step_30": {"rel_f1": 0.434, "evi_f1": 0.8063, "edcr": 0.6807}, "step_50": {"rel_f1": 0.4276, "evi_f1": 0.8024, "edcr": 0.6855}, "step_70": {"rel_f1": 0.4341, "evi_f1": 0.8099, "edcr": 0.6685}, "best_step": "step_70", "trend": "non-monotonic, all < ckpt-100 (0.4549)"}
844	  notes: 诊断确认：SIGTERM (EXIT_CODE=143)。device_map="auto" 无 CUDA_VISIBLE_DEVICES 限制，模型加载到 GPU 0（plan_001 占用 16.3GB），双进程共 31.4/32.6GB 后被 kill。两次重试均失败（retry_count=2）。修复：CUDA_VISIBLE_DEVICES=1 重提交到空闲 cuda:1。
845	
846	=== plan_011_eval_g8_bf16_ckpt100 ===
847	  status: DONE
848	  conclusion: killed
849	  seed: 42
850	  model: grpo_g8_bf16 ckpt100
851	  notes: STALE: 该 eval 已由 eval_grpo_g8_bf16 完成并 success (rel_f1=0.4549)。此条目为残留，不需要执行。
852	
853	=== plan_011_grpo_g8_bf16 ===
854	  status: DONE
855	  conclusion: success
856	  seed: 
857	  model: 
858	  metrics: {"final_step": 100, "train_runtime_s": 554, "reward_final": 1.795, "f1_reward_final": 1.002, "ced_reward_final": 0.494, "format_reward_final": 0.3, "frac_zero_std_final": 0, "kl_final": 0.022, "best_reward_step": 85, "best_reward": 2.858, "best_f1_reward": 1.85, "mode_collapse": false, "lora_config": "r=64, alpha=128, dropout=0.05, bf16", "checkpoints": "10 checkpoints (step 10-100)"}
859	  hypothesis: GRPO G=8 bf16 LoRA: 验证 catastrophic forgetting 是否在 bf16（非 QLoRA 4-bit）下仍复现。CED reward + kl_coef=0.01, 100 steps。如仍 fail → 加强 Claim 3
860	  notes: 训练完成 (100/100 steps, EXIT_CODE=0, 554s/9.2min)。无 mode collapse (frac_zero_std=0.0 全程)。KL 极低 (0.005-0.052)。训练 metrics 比 QLoRA 更好 (reward 1.795 vs 1.195, 无 frac_zero_std 升高)。但 QLoRA 训练 metrics 也不差，问题在 eval。必须 eval 才能判断 catastrophic forgetting 是算法层面还是量化问题。
861	
862	=== plan_011_grpo_g8_bf16_eval ===
863	  status: DONE
864	  conclusion: success
865	  seed: 
866	  model: 
867	  metrics: {"rel_f1": 0.4549, "ign_f1": 0.4549, "evi_f1": 0.8086, "edcr": 0.6318, "format_ok_rate": 1, "n_truncated": 61, "n_total": 985, "n_predictions": 10701, "checkpoint": "checkpoint-100", "model": "Qwen3-4B + SFT merged + GRPO bf16 LoRA ckpt-100", "inference_time_s": 3170.3}
868	  notes: bf16 GRPO G=8 checkpoint-100 full dev eval (985 docs). F1=0.4549 (+4.92pp vs SFT 0.4057), Evi-F1=0.8086 (+1.07pp vs SFT 0.7979), EDCR=0.6318. Catastrophic forgetting 不复现——bf16 LoRA 下 GRPO 性能甚至超过 SFT baseline。与 QLoRA GRPO (rel_f1=0.2167) 形成鲜明对比。61/985 truncated, 100% format OK. 关键结论: forgetting 是 QLo
869	
870	=== plan_012_dpo_ced ===
871	  status: DONE
872	  conclusion: negative
873	  seed: 42
874	  model: Qwen3-4B + SFT + CED-DPO
875	  metrics: {"rel_f1": 0.3429, "evi_f1": 0.8403, "edcr": 0.7294, "format_ok_rate": 0.995, "checkpoint": "checkpoint-501", "rewards_accuracy": 1, "margins": 9.01}
876	  hypothesis: DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。
877	  notes: ⚠️ Reviewer WARNING: 严重过拟合。3 epochs, rewards accuracy=1.0, margins 9x 膨胀, entropy 崩塌。checkpoint-501 是最过拟合版本，结果有 confound。需补 eval checkpoint-400 对比 + 重训 epochs=1。
878	
879	=== plan_012_dpo_ced_1ep ===
880	  status: DONE
881	  conclusion: negative
882	  seed: 42
883	  model: Qwen3-4B + SFT + CED-DPO (1ep)
884	  metrics: {"rel_f1": 0.0022, "evi_f1": 0.75, "edcr": 0.9982, "format_ok": "981/985", "truncated": "358/985", "tp": 34, "n_preds": 19265, "inference_time_s": 3643, "train_loss_final": 0.59, "rewards_accuracy": 0.82, "rewards_margins": 0.86, "total_steps": 167, "training_time_min": 33}
885	  hypothesis: DPO+CED 1 epoch retraining: plan_012_dpo_ced 3 epochs 严重过拟合 (rewards_accuracy=1.0, margins 9x膨胀, entropy崩塌)。重训 1 epoch 验证 early stopping 是否消除 overfitting confound。对比 plan_012 3ep + RSFT (rel_f1=0.46) + SFT baseline (rel_f1=0.4057)。
886	  notes: DPO+CED 完全失败。1ep eval: rel_f1=0.0022 (34 TPs / 19265 preds)，比 3ep (0.3429) 更差。训练指标正常 (accuracy=0.82, margins=0.86)，但模型输出几乎无法匹配正确 relation。evi_f1=0.75 说明模型仍生成 evidence，但 relation extraction 崩溃。358/985 truncated (36%)。DPO 对 evidence-grounded DocRE 完全不适用——不是过拟合问题，是方法本身失效。D061 已关闭 DPO 实验线。
887	
888	=== plan_014_sft_no_evidence ===
889	  status: DONE
890	  conclusion: success
891	  seed: 42
892	  model: Qwen3-4B (QLoRA 4-bit)
893	  metrics: {"train_loss": 0.7077, "eval_loss": 0.8781, "eval_token_accuracy": 0.8086, "epochs": 3, "total_steps": 570, "train_runtime_min": 64, "samples": 3027, "trainable_params": "132M/4.15B (3.18%)"}
894	  hypothesis: SFT-without-evidence ablation: 训练只输出 relation triples（不含 evidence sentences）的 SFT 模型。量化 joint evidence generation 对 extraction 的代价（当前 rel_f1=0.4057 vs 只抽关系的 LMRC 60.7 的 gap 有多少来自 evidence 负担）。
895	
896	=== plan_015_grpo_g4_bf16 ===
897	  status: DONE
898	  conclusion: killed
899	  seed: 42
900	  model: Qwen3-4B
901	  hypothesis: bf16 LoRA GRPO clean control: 与原始 QLoRA GRPO 仅改 quantization（4-bit → bf16），保持 G=4, kl=0, CED reward 不变。验证 catastrophic forgetting 是否由 QLoRA quantization 导致。
902	  notes: cuda:0 冲突，与 plan_001_rsft_flat_nli (PID 219556) 冲突。plan_001 先到先得，plan_015 被终止。待 plan_001 完成后重新提交 plan_015。
903	
904	=== plan_015_grpo_g4_bf16_v2 ===
905	  status: DONE
906	  conclusion: killed
907	  seed: 42
908	  model: Qwen3-4B + SFT adapter
909	  hypothesis: Robustness check: bf16 LoRA GRPO 在 G=4, kl=0, lr=5e-6 条件下是否也防止 catastrophic forgetting。非 single-variable ablation（kl/lr/G 均与 QLoRA 对照组不同）。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean quantization ablation。
910	
911	=== plan_015_grpo_g4_bf16_v3 ===
912	  status: DONE
913	  conclusion: killed
914	  seed: 42
915	  model: Qwen3-4B + SFT adapter
916	  hypothesis: P2 robustness check: bf16 LoRA GRPO G=4, kl=0.01, lr=5e-6。D052 确认 plan_011 vs mvp2_grpo_ced_kl001_r4 已是 clean single-variable quantization ablation (Δ=+23.8pp)。v3 仅为 robustness data point，lr=5e-6 与对照组 lr=5e-5 不一致。
917	  notes: Robustness check, 非 single-variable ablation。lr=5e-6 与对照组 (mvp2_grpo_ced_kl001_r4, lr=5e-5) 不一致。D052 确认 plan_011 (bf16 G=8 kl=0.01 lr=5e-5) vs mvp2_grpo_ced_kl001_r4 (QLoRA G=8 kl=0.01 lr=5e-5) 才是 clean ablation。v3 仅作为额外 robustness data point。
918	
919	=== precompute_nli_train ===
920	  status: DONE
921	  conclusion: success
922	  seed: 
923	  model: 
924	
925	=== reeval_ced_s42 ===
926	  status: PREPARING
927	  conclusion: 
928	  seed: 42
929	  model: Qwen3-4B + SFT + CED RSFT s42
930	  protocol: reeval, unified
931	  hypothesis: Re-eval CED RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 mvp2_eval_rsft_r2b_maxtok1536_r2 用了 batch_size=8 + max_new_tokens=1536。Paired t-test 关键路径。
932	  notes: 旧 eval (rsft_r2b_maxtok1536_r2) 不仅协议不一致，而且用了错误 checkpoint (rsft_output_r2b: lora_alpha=32, 仅 160 步)。正确 checkpoint: /root/autodl-tmp/rsft_output/checkpoint-510 (seed=42, lora_alpha=128, 510 步，与 s43/s44/s45 配置一致)。
933	
934	=== reeval_ced_s44 ===
935	  status: PREPARING
936	  conclusion: 
937	  seed: 44
938	  model: Qwen3-4B + SFT + CED RSFT s44
939	  protocol: reeval, unified
940	  hypothesis: Re-eval CED RSFT s44 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + seed=44. 原 eval 用了 batch_size≈16 且 seed=42（错误）。Paired t-test 关键路径。
941	  notes: 正确 checkpoint: /root/autodl-tmp/rsft_output_s44/checkpoint-510。旧 eval 路径一致但可能用了根目录 adapter 而非 checkpoint-510 子目录。
942	
943	=== reeval_flat_nli_s42 ===
944	  status: PREPARING
945	  conclusion: 
946	  seed: 42
947	  model: Qwen3-4B + SFT + flat-NLI RSFT s42
948	  protocol: reeval, unified
949	  hypothesis: Re-eval flat-NLI RSFT s42 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024. 原 eval_plan_001_flat_nli 用了 batch_size=16。Paired t-test 关键路径。
950	
951	=== reeval_flat_nli_s43 ===
952	  status: DONE
953	  conclusion: success
954	  seed: 43
955	  model: Qwen3-4B + SFT + flat-NLI RSFT s43
956	  protocol: reeval
957	  metrics: {"rel_f1": 0.4523, "ign_f1": 0.4523, "evi_f1": 0.8158, "edcr": 0.6505, "num_preds": 15357, "format_ok": "984/985", "truncated": "211/985", "inference_time_s": 3515.8}
958	  hypothesis: Re-eval flat-NLI RSFT seed=43 WITH --sft_adapter (D064 bug fix). 原 eval_plan_001_flat_nli_s43 因缺 --sft_adapter 导致 rel_f1=0.0022 无效。对比 flat-NLI s42 (rel_f1=0.4539) 和 CED RSFT mean (0.4596)。
959	
960	=== reeval_flat_nli_s43_r2 ===
961	  status: RUNNING
962	  conclusion: 
963	  seed: 
964	  model: 
965	  protocol: reeval, unified
966	  hypothesis: Re-eval flat-NLI RSFT s43 with unified protocol: batch_size=4 + --no-quantize + --sft_adapter + --max_new_tokens 1024. 原 reeval_flat_nli_s43 用了 batch_size=16 导致协议不一致。C3 paired t-test 关键路径。
967	
968	=== reeval_rsft_topk3 ===
969	  status: DONE
970	  conclusion: negative
971	  seed: 42
972	  model: RSFT top_k=3 + SFT adapter
973	  protocol: reeval, ign_corrected
974	  metrics: {"rel_f1": 0.4454, "rel_precision": 0.4512, "rel_recall": 0.4398, "ign_f1": 0.4364, "evi_f1": 0.8088, "edcr": 0.6635, "format_ok_rate": 0.999, "n_truncated": 214, "n_predictions": 16020, "inference_time_seconds": 3546.4, "ign_f1_corrected": true}
975	  hypothesis: Re-eval RSFT top_k=3 WITH --sft_adapter (D064 bug fix). 原 eval_plan_008_rsft_topk3 因缺 --sft_adapter 被 killed。对比 CED RSFT top_k=1 (rel_f1≈0.46) 和 SFT baseline (0.4057)。
976	  notes: RSFT top_k=3 rel_f1=0.4454，优于 SFT baseline (0.4057) 但劣于 CED RSFT top_k=1 (~0.46)。top_k=3 引入更多噪声训练样本，反而降低关系抽取精度。evi_f1=0.8088 较好。214/985 truncated。
977	
978	=== rsft_ced_s43_train ===
979	  status: DONE
980	  conclusion: failed
981	  seed: 
982	  model: 
983	  notes: 失败原因: No module named freige.training.rsft_trainer — 命令 cd /root/autodl-tmp/freige 导致 cwd 错误。已修正为 cd /root/autodl-tmp，重提交为 rsft_ced_s43_train_r2 (PID=275264)
984	
985	=== rsft_ced_s43_train_r2 ===
986	  status: DONE
987	  conclusion: failed
988	  seed: 43
989	  model: Qwen3-4B + LoRA on SFT adapter
990	  hypothesis: CED RSFT seed=43 训练（r2 重试，修正 cwd 错误）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。
991	  notes: Director 下令终止——错误套用 flat-NLI 超参(batch=1/grad_accum=16)，需用 CED 正确模板(batch=4/grad_accum=4)重跑，已由 r3 替代。实际 argparse 无 --batch/--grad_accum 参数，静默忽略后用了默认值(batch=4/grad_accum=4)，实际配置恰好正确，但命令不规范。
992	
993	=== rsft_ced_s43_train_r3 ===
994	  status: DONE
995	  conclusion: success
996	  seed: 
997	  model: 
998	  metrics: {"train_loss": 0.6151, "eval_loss": 0.7618, "task_eval_f1": 0.5026, "task_eval_ign_f1": 0.4932, "task_eval_evi_f1": 0.7624, "task_eval_edcr": 0.6516, "total_steps": 510, "epochs": 3, "training_hours": 1.82}
999	
1000	=== rsft_ced_s45_train ===
1001	  status: DONE
1002	  conclusion: killed
1003	  seed: 45
1004	  model: Qwen3-4B + LoRA on SFT adapter
1005	
1006	=== rsft_ced_s45_train_r2 ===
1007	  status: DONE
1008	  conclusion: killed
1009	  seed: 
1010	  model: 
1011	  notes: Director 下令终止——错误套用 flat-NLI 超参(batch=1/grad_accum=16)，需用 CED 正确模板(batch=4/grad_accum=4)重跑，已由 r3 替代。
1012	
1013	=== rsft_ced_s45_train_r3 ===
1014	  status: DONE
1015	  conclusion: failed
1016	  seed: 45
1017	  model: sft_base + ced_rsft
1018	  notes: CUDA OOM at launch: cuda:2 occupied by orphan PID 276148 (31.6GB). Need to kill orphan and resubmit as r4.
1019	
1020	=== rsft_ced_s45_train_r4 ===
1021	  status: DONE
1022	  conclusion: success
1023	  seed: 
1024	  model: 
1025	  metrics: {"training_completed": true, "checkpoint": "checkpoint-510", "note": "Training metrics not captured (r4 retry after OOM). Eval running as eval_rsft_ced_s45."}
1026	  hypothesis: CED RSFT seed=45 训练（r4 重试，r3 因 cuda:2 orphan PID 276148 OOM 失败）。补全 paired t-test 所需的第 3 个 CED seed（现有 s42/s44，s43 在 cuda:1 训练中）。训练数据 2718 samples，3 epochs，~2h。plan_id=plan_mvp2_rsft, claim=3。
1027	
1028	=== seed_comparison_prep ===
1029	  status: PREPARING
1030	  conclusion: 
1031	  seed: 
1032	  model: 
1033	  notes: ## Seed Comparison Pre-Analysis (2026-05-16)
1034	
1035	### Available Results (3/4 seeds each, s45 pending for both):
1036	
1037	**flat-NLI RSFT:**
1038	- s42: rel_f1=0.4539 (dir: rsft_flat_nli)
1039	- s43: rel_f1=0.4523 (dir: rsft_flat_nli_s43_reeval; original rsft_flat_nli_s43 was broken f1=0.002)
1040	- s44: rel_f1=0.4615 (dir: rs
1041	
1042	=== smoke_test_grpo ===
1043	  status: DONE
1044	  conclusion: success
1045	  seed: 
1046	  model: 
1047	
1048	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "4bae464f-e535-40cf-9264-07836c3b1e8e"
}
```

</details>

---

### System

_source line 59_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Find all experiments with D076/unified/reeval protocol flags",
  "usage": {
    "total_tokens": 59628,
    "tool_uses": 13,
    "duration_ms": 83642
  },
  "last_tool_name": "Bash",
  "uuid": "9cdff55c-fddc-49ef-9558-f3bd04c9aa90",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 60_

<details open><summary>🔧 Tool call — Bash · `toolu_016ZSGAEyAahNgK2f6oBPNb6`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 << 'PYEOF'\nimport json\n\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# Check ALL experiments for D076 / unified / ign_f1_corrected / reeval mentions\nprint(\"=== D076/Unified/Reeval Protocol Experiments ===\")\nfor k in sorted(exps.keys()):\n    e = exps[k]\n    full_str = json.dumps(e).lower()\n    flags = []\n    if 'reeval' in k.lower(): flags.append('reeval_id')\n    if 'd076' in full_str: flags.append('D076')\n    if 'unified' in full_str: flags.append('unified')\n    if 'unified_protocol' in full_str: flags.append('unified_protocol')\n    if 'ign_f1_corrected' in full_str: flags.append('ign_f1_corrected')\n    if flags:\n        status = e.get('status', '?')\n        conclusion = e.get('conclusion', '')\n        metrics = e.get('metrics', {})\n        print(f\"{k}: status={status}, conclusion={conclusion}, flags={flags}\")\n        if metrics:\n            print(f\"  metrics: {json.dumps(metrics)}\")\n        print()\nPYEOF\n",
  "description": "Find all experiments with D076/unified/reeval protocol flags"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "bbfc0d52-45c2-4ffd-b4d4-3da2818df2ff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VhM8tCcqjDJegazAqfjtrz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7835,
      "cache_read_input_tokens": 51263,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7835,
        "ephemeral_1h_input_tokens": 0
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

### Tool result

_source line 61 · 2026-05-16T03:23:02.171Z_

<details><summary>↩ Tool result · `toolu_016ZSGAEyAahNgK2f6oBPNb6`</summary>

```text
=== D076/Unified/Reeval Protocol Experiments ===
mvp2_sft_eval_r3: status=DONE, conclusion=success, flags=['unified']
  metrics: {"rel_f1": 0.4057, "ign_f1": 0.4057, "evi_f1": 0.7979, "edcr": 0.7118, "precision": 0.4043, "recall": 0.407, "evi_precision": 0.8035, "evi_recall": 0.7924, "format_ok_rate": 0.998, "format_compliance_rate": 0.626, "n_parseable": 617, "n_truncated": 367, "n_predictions": 18815}

reeval_ced_s42: status=PREPARING, conclusion=, flags=['reeval_id', 'unified']

reeval_ced_s44: status=PREPARING, conclusion=, flags=['reeval_id', 'unified']

reeval_flat_nli_s42: status=PREPARING, conclusion=, flags=['reeval_id', 'unified']

reeval_flat_nli_s43: status=DONE, conclusion=success, flags=['reeval_id']
  metrics: {"rel_f1": 0.4523, "ign_f1": 0.4523, "evi_f1": 0.8158, "edcr": 0.6505, "num_preds": 15357, "format_ok": "984/985", "truncated": "211/985", "inference_time_s": 3515.8}

reeval_flat_nli_s43_r2: status=RUNNING, conclusion=, flags=['reeval_id', 'unified']

reeval_rsft_topk3: status=DONE, conclusion=negative, flags=['reeval_id', 'ign_f1_corrected']
  metrics: {"rel_f1": 0.4454, "rel_precision": 0.4512, "rel_recall": 0.4398, "ign_f1": 0.4364, "evi_f1": 0.8088, "edcr": 0.6635, "format_ok_rate": 0.999, "n_truncated": 214, "n_predictions": 16020, "inference_time_seconds": 3546.4, "ign_f1_corrected": true}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6593c91d-370e-44be-880f-a5014dcd8e19"
}
```

</details>

---

### System

_source line 62_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Get full detail for key experiments",
  "usage": {
    "total_tokens": 60858,
    "tool_uses": 14,
    "duration_ms": 94617
  },
  "last_tool_name": "Bash",
  "uuid": "0b18c51b-4f80-4d5d-94db-712dea2dfdd8",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 63_

<details open><summary>🔧 Tool call — Bash · `toolu_017ojZkJXnWPimQTp3QwkDNC`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 << 'PYEOF'\nimport json\n\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# For the DPO fixed_r2 experiment, get the full detail\nfor k in ['eval_plan_012_dpo_1ep_fixed_r2', 'plan_012_dpo_ced', 'plan_012_dpo_ced_1ep',\n          'eval_plan_014_sft_no_evidence', 'eval_sft_baseline_noquant',\n          'mvp2_ced_reranker_poc']:\n    e = exps.get(k, {})\n    print(f\"=== {k} ===\")\n    print(json.dumps(e, indent=2, ensure_ascii=False)[:1500])\n    print()\nPYEOF\n",
  "description": "Get full detail for key experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "13014fc0-319f-4cef-853b-e483e994a73e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Y4c6UC1W5AqNgKkk3KUHEr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1157,
      "cache_read_input_tokens": 59098,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1157,
        "ephemeral_1h_input_tokens": 0
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

_source line 64 · 2026-05-16T03:23:13.142Z_

<details><summary>↩ Tool result · `toolu_017ojZkJXnWPimQTp3QwkDNC`</summary>

```text
=== eval_plan_012_dpo_1ep_fixed_r2 ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T21:58:52.440Z",
  "updated_at": "2026-05-15T23:44:56.586Z",
  "spec": {
    "command": "DPO 1ep re-eval with --sft_adapter (D064 fix)",
    "server": "rtx5090-4x",
    "gpu": "cuda:3",
    "pid": 262075,
    "log_path": "~/runs/faith-evidence-ie/eval_plan_012_dpo_1ep_fixed_r2.log",
    "submitted_at": "2026-05-15T21:58:52.150Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 0,
    "model_name": "Qwen3-4B + SFT + DPO 1ep",
    "seed": 42,
    "checkpoint_source": "plan_012_dpo_ced_3ep",
    "eval_data": "docred_dev",
    "checkpoint_path": "/root/autodl-tmp/dpo_ced_output/checkpoint-167",
    "wall_clock_seconds": 6197.9,
    "gpu_hours": 1.72
  },
  "reproduce": {
    "finished_at": "2026-05-15T23:36:34.758Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-15T23:36:37.754401+00:00"
      }
    ]
  },
  "conclusion": "negative",
  "metrics": {
    "rel_f1": 0.4034,
    "evi_f1": 0.8088,
    "edcr": 0.7139,
    "format_ok_rate": 0.999,
    "truncated_rate": 0.343,
    "predictions": 19107,
    "ign_f1": 0.4034,
    "precision": 0.3809,
    "recall": 0.4287,
    "vs_sft_delta": -0.0023,
    "note": "DPO 1ep matches SFT baseline. 1ep→3ep trajectory shows gradual decoupling (rel_f1↓ evi_f1↑), consistent with GRPO pattern. I

=== plan_012_dpo_ced ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T15:54:03.324Z",
  "updated_at": "2026-05-15T21:37:44.232Z",
  "spec": {
    "checkpoint_path": "/root/autodl-tmp/dpo_output",
    "data_path": "/root/autodl-tmp/dpo_data/dpo_pairs.jsonl",
    "data_count": 2666,
    "model_name": "Qwen3-4B + SFT + CED-DPO",
    "seed": 42,
    "beta": 0.1,
    "num_epochs": 3,
    "loss_type": "sigmoid",
    "base_model": "/root/autodl-tmp/models/Qwen3-4B",
    "sft_adapter": "/root/autodl-tmp/sft_output",
    "pairs": 2666
  },
  "hypothesis": "DPO+CED preference learning: 用 CED 构造 preference pairs (CED top-1 = chosen, CED bottom-1 = rejected)，DPO 训练。验证 offline preference optimization 能否替代 online GRPO 避免 catastrophic forgetting，同时利用 CED 信号。对比 RSFT (rel_f1=0.46) 和 SFT baseline (rel_f1=0.4057)。",
  "reproduce": {
    "finished_at": "2026-05-15T17:38:15.433Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-15T17:38:17.857458+00:00"
      }
    ]
  },
  "conclusion": "negative",
  "notes": "⚠️ Reviewer WARNING: 严重过拟合。3 epochs, rewards accuracy=1.0, margins 9x 膨胀, entropy 崩塌。checkpoint-501 是最过拟合版本，结果有 confound。需补 eval checkpoint-400 对比 + 重训 epochs=1。",
  "metrics": {
    "rel_f1": 0.3429,
    "evi_f1": 0.8403,
    "edcr": 0.7294,
    "format_ok_rate": 0.995,
    "checkpoint": "checkpoint-501",
    "rewards_accuracy": 1,
    "margins": 9.01
  },
  "log_path": "~/runs/faith-evidence-ie/plan_012_dpo_c

=== plan_012_dpo_ced_1ep ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T18:50:44.852Z",
  "updated_at": "2026-05-15T21:36:34.720Z",
  "spec": {
    "hypothesis": "DPO+CED 1-epoch 重训：修复 3-epoch 过拟合问题。epochs=1 (~167 steps, <10min)，其余超参不变（β=0.1, lr=5e-7, loss=sigmoid, seed=42, pairs=2666）。让 DPO 数据点可用于论文。",
    "parent": "plan_012_dpo_ced",
    "command": "bash -c \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 WANDB_PROJECT=freige-dpo PYTHONUNBUFFERED=1 python -m freige.training.dpo_trainer --base_model /root/autodl-tmp/models/Qwen3-4B --sft_adapter /root/autodl-tmp/sft_output --dpo_data_path /root/autodl-tmp/dpo_data/dpo_pairs.jsonl --output_dir /root/autodl-tmp/dpo_output_1ep --beta 0.1 --num_epochs 1 --seed 42 --loss_type sigmoid --per_device_batch_size 1 --gradient_accumulation_steps 16 --wandb_run_name plan_012_dpo_ced_1ep\"",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:2"
    ],
    "pid": "245103",
    "log_path": "~/runs/faith-evidence-ie/plan_012_dpo_ced_1ep.log",
    "submitted_at": "2026-05-15T19:43:02.707Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/dpo_data/dpo_pairs.jsonl",
    "data_count": 2666,
    "model_name": "Qwen3-4B + SFT + CED-DPO (1ep)",
    "seed": 42,
    "base_model": "/root/autodl-tmp/models/Qwen3-4B",
    "sft_adapter": "/root/autodl-tmp/

=== eval_plan_014_sft_no_evidence ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T17:20:25.574Z",
  "updated_at": "2026-05-15T18:42:46.665Z",
  "spec": {
    "checkpoint_path": "/root/autodl-tmp/eval_results/sft_no_evidence",
    "log_path": "~/runs/faith-evidence-ie/eval_plan_014_sft_no_evidence.log"
  },
  "reproduce": {
    "finished_at": "2026-05-15T18:29:34.790Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-15T18:29:37.278008+00:00"
      }
    ]
  },
  "metrics": {
    "rel_f1": 0.4893,
    "rel_ign_f1": 0.4893,
    "rel_precision": 0.4884,
    "rel_recall": 0.4902,
    "evi_f1": 0,
    "evi_precision": 0,
    "evi_recall": 0,
    "edcr": 0,
    "format_ok_rate": 0.9919,
    "n_truncated": 298,
    "n_predictions": 21064,
    "n_documents": 985,
    "n_parseable": 977,
    "inference_time_seconds": 4103.8
  },
  "conclusion": "success",
  "notes": "No-evidence SFT rel_f1=0.4893 vs baseline with-evidence rel_f1=0.4057 (+0.0836, +20.6%). Evidence generation significantly hurts relation extraction. evi_f1=0 as expected. Format compliance 99.2%. 298/985 truncated. Inference 4103.8s.",
  "completed_at": "2026-05-15T18:42:46.665Z"
}

=== eval_sft_baseline_noquant ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T18:38:33.128Z",
  "updated_at": "2026-05-15T19:45:42.147Z",
  "spec": {
    "command": "python eval.py --model_path /root/autodl-tmp/sft_output --base_model /root/autodl-tmp/models/Qwen3-4B --data_path /root/autodl-tmp/data/docred --output_dir /root/autodl-tmp/eval_results/sft_baseline_noquant --batch_size 16 --max_new_tokens 1024 --split dev --seed 42",
    "server": "rtx5090-4x",
    "gpu": [
      "cuda:1"
    ],
    "pid": "237912",
    "log_path": "~/runs/faith-evidence-ie/eval_sft_baseline_noquant.log",
    "submitted_at": "2026-05-15T18:38:45.042Z",
    "submitted_via": "submit_training_job",
    "backend": "tmux",
    "account": "root",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 985,
    "model_name": "Qwen3-4B + SFT LoRA (no quantization)",
    "seed": 42,
    "checkpoint_source": "/root/autodl-tmp/sft_output",
    "eval_data": "docred/dev (985 docs, 12275 triples)",
    "wall_clock_seconds": 3916.2,
    "gpu_hours": 1.09,
    "checkpoint_path": "/root/autodl-tmp/eval_results/sft_baseline_noquant/"
  },
  "reproduce": {
    "finished_at": "2026-05-15T19:41:54.062Z"
  },
  "extra": {
    "hook_events": [
      {
        "event": "on_complete",
        "action": "agent",
        "ts": "2026-05-15T19:41:59.716746+00:00"
      }
    ]
  },
  "metrics": {
    "rel_f1": 0.4106,
    "rel_precision": 0.4198,
    "rel_recall": 0.4019,
    "evi_f1": 0.8013,
    "evi_precision": 0.8005

=== mvp2_ced_reranker_poc ===
{
  "status": "DONE",
  "retry_count": 0,
  "created_at": "2026-05-15T07:55:03.414Z",
  "updated_at": "2026-05-15T14:51:46.913Z",
  "hypothesis": "CED-as-reranker: no fine-tuning, use CED to select best of N=8 SFT candidates at inference time. If rel_f1 > 0.4057 (SFT greedy), CED adds value without training risk. Oracle reranker as upper bound.",
  "server": "rtx5090-4x",
  "gpu": "cuda:0",
  "spec": {
    "command": "python /root/autodl-tmp/freige/eval/ced_reranker.py (N=8, CED scoring, 985 docs)",
    "server": "rtx5090-4x",
    "data_path": "/root/autodl-tmp/data/docred",
    "data_count": 985,
    "model_name": "Qwen3-4B + SFT (greedy N=8 + CED reranker)",
    "seed": 42,
    "pid": "178050",
    "checkpoint_path": "N/A",
    "log_path": "~/runs/faith-evidence-ie/mvp2_ced_reranker_poc.log"
  },
  "conclusion": "success",
  "completed_at": "2026-05-15T14:47:24.899Z",
  "metrics": {
    "ced_reranker_rel_f1": 0.4864,
    "ced_reranker_evi_f1": 0.8188,
    "ced_reranker_edcr": 0.6156,
    "ced_reranker_precision": 0.4913,
    "ced_reranker_recall": 0.4815,
    "ced_reranker_pred_count": 14782,
    "ced_reranker_format_ok_rate": 1,
    "oracle_rel_f1": 0.6237,
    "oracle_evi_f1": 0.7942,
    "oracle_edcr": 0.5262,
    "oracle_pred_count": 13418,
    "random_rel_f1": 0.4538,
    "random_evi_f1": 0.8029,
    "random_edcr": 0.6763,
    "ced_f1_spearman_r": 0.3235,
    "ced_f1_spearman_p": 2.46e-191,
    "sft_baseline_rel_f1": 0.4057,
    "sft_baseline_evi_f1": 0.7979,
    "sft_
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "1692b1a3-286b-4099-8581-2177060cc2b3"
}
```

</details>

---

### System

_source line 65_

```json
{
  "type": "system",
  "subtype": "task_progress",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "description": "Running Get full seed_comparison_prep notes",
  "usage": {
    "total_tokens": 65372,
    "tool_uses": 15,
    "duration_ms": 103423
  },
  "last_tool_name": "Bash",
  "uuid": "6ed9b2da-55c2-4bdf-8a73-f1348c0d243f",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool call

_source line 66_

<details open><summary>🔧 Tool call — Bash · `toolu_018XdXgeQMpcSKA5AVi6MFgm`</summary>

```json
{
  "command": "cd /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results && python3 << 'PYEOF'\nimport json\n\nwith open('mcp-agent-ml-research-read_registry-1778901685097.txt') as f:\n    data = json.load(f)\ninner = json.loads(data['result'])\nexps = inner['data']['experiments']\n\n# Get seed_comparison_prep full notes\ne = exps.get('seed_comparison_prep', {})\nprint(\"=== seed_comparison_prep ===\")\nprint(json.dumps(e, indent=2, ensure_ascii=False))\nPYEOF\n",
  "description": "Get full seed_comparison_prep notes"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "f2e04952-493e-4b51-ac56-67d68a6d9064",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKzu194PweXwqwnY5hiLE1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4512,
      "cache_read_input_tokens": 60255,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4512,
        "ephemeral_1h_input_tokens": 0
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

### Tool result

_source line 67 · 2026-05-16T03:23:22.037Z_

<details><summary>↩ Tool result · `toolu_018XdXgeQMpcSKA5AVi6MFgm`</summary>

```text
=== seed_comparison_prep ===
{
  "status": "PREPARING",
  "retry_count": 0,
  "created_at": "2026-05-16T02:35:52.694Z",
  "updated_at": "2026-05-16T02:35:52.694Z",
  "notes": "## Seed Comparison Pre-Analysis (2026-05-16)\n\n### Available Results (3/4 seeds each, s45 pending for both):\n\n**flat-NLI RSFT:**\n- s42: rel_f1=0.4539 (dir: rsft_flat_nli)\n- s43: rel_f1=0.4523 (dir: rsft_flat_nli_s43_reeval; original rsft_flat_nli_s43 was broken f1=0.002)\n- s44: rel_f1=0.4615 (dir: rsft_flat_nli_s44; NOTE: only metrics.json, no metrics_v2.json with fixed Ign-F1)\n- s45: PENDING (empty dir)\n- Mean: 0.4559 ± 0.0049\n\n**CED RSFT:**\n- s42: rel_f1=0.4504 (dir: rsft_r2b_maxtok1536)\n- s43: rel_f1=0.4683 (dir: rsft_s43)\n- s44: rel_f1=0.4655 (dir: rsft_s44)\n- s45: PENDING (empty dir)\n- Mean: 0.4614 ± 0.0096\n\n### Pre-comparison (N=3):\n- rel_f1 Delta (fNLI - CED): -0.0055 (CED slightly better)\n- Paired t-test: t=0.967, p=0.4357 (NOT significant)\n- 95% CI for delta: [-0.0299, +0.0189] (crosses zero)\n- Cohen's d: -0.558\n\n### seed_comparison.py status: WORKING\n- Auto-discovers all seeds, handles fallback dirs, filters broken results (f1<0.01)\n- Outputs to /root/autodl-tmp/eval_results/seed_comparison.{md,json}\n- Supports --watch mode for polling"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "6b4c363d-0d7b-446a-b7dc-012c5a1a01be"
}
```

</details>

---

### System

_source line 68_

```json
{
  "type": "system",
  "subtype": "task_notification",
  "task_id": "a04aaecf72a9d4164",
  "tool_use_id": "toolu_01UkXxDUvxmRzYY3VqCzLgZf",
  "status": "completed",
  "output_file": "",
  "summary": "Extract registry metrics for evidence table",
  "usage": {
    "total_tokens": 66394,
    "tool_uses": 15,
    "duration_ms": 217143
  },
  "uuid": "7e731f9a-80ce-4ad3-bbb1-e5270eccb76f",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a"
}
```

---

### Tool result

_source line 69 · 2026-05-16T03:25:15.556Z_

<details><summary>↩ Tool result · `toolu_01UkXxDUvxmRzYY3VqCzLgZf`</summary>

```text
Now I have all the data needed. Here is the comprehensive structured summary:

---

## Complete Experiment Registry: 130 experiments total

### 1. SFT BASELINE (with evidence)

| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | notes |
|--------|------|--------|--------|--------|--------------|------|-------|
| **mvp2_sft_eval_r2** | 42 | 0.4057 | 0.4057 | 0.7979 | -- | 0.7118 | Original baseline, quantized (QLoRA 4-bit) |
| **mvp2_sft_eval_r3** | 42 | 0.4057 | 0.4057 | 0.7979 | -- | 0.7118 | Unified eval code verification; identical to r2 |
| **mvp2_eval_sft_baseline** | 42 | 0.4057 | 0.4057 | 0.7979 | 0.3117 | 0.7118 | Apple-to-apple protocol eval. P=0.4043, R=0.407. 367 truncated, 18815 preds |
| **eval_sft_baseline_noquant** | 42 | 0.4106 | -- | 0.8013 | 0.3216 | 0.7039 | No-quantize. +0.49pp rel_f1 vs quantized. Confirms quantize confound <1pp |

**Canonical SFT baseline**: rel_f1=0.4057, evi_f1=0.7979, edcr=0.7118, evi_f1_joint=0.3117

### 2. SFT WITHOUT EVIDENCE (ablation)

| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | edcr | notes |
|--------|------|--------|--------|--------|------|-------|
| **eval_plan_014_sft_no_evidence** | 42 | 0.4893 | 0.4893 | 0 | 0 | +20.6% over SFT baseline; evidence generation hurts RE |
| eval_plan_014_no_evidence | -- | -- | -- | -- | -- | FAILED: adapter config error |
| eval_plan_014_no_evidence_r2 | -- | -- | -- | -- | -- | RUNNING |

### 3. RSFT CED (top_k=1) -- Different Seeds

| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 reeval? |
|--------|------|--------|--------|--------|--------------|------|-------------|
| **mvp2_eval_rsft_r1** | 42 | 0.4449 | -- | 0.8187 | 0.3468 | 0.6565 | No (original) |
| **mvp2_eval_rsft_r2a** | 42 | 0.4494 | 0.4494 | 0.8108 | 0.3509 | 0.6641 | No (1-epoch ablation, alpha=128) |
| **mvp2_eval_rsft_r2b** | 42 | 0.4493 | 0.4493 | 0.8128 | 0.3490 | 0.6609 | No (1-epoch ablation, alpha=32) |
| mvp2_eval_rsft_r2b_maxtok1536_r2 | 42 | 0.4504 | 0.4504 | 0.8102 | -- | 0.6740 | No (truncation diagnosis, max_tok=1536). NOTE: wrong checkpoint (r2b: alpha=32, 160 steps) |
| **mvp2_eval_rsft_s43_r2** | 43 | 0.4683 | 0.4683 | 0.8156 | 0.3711 | 0.6388 | No |
| **mvp2_rsft_train_r1_s44** (eval) | 44 | 0.4655 | -- | 0.8087 | 0.3713 | 0.6350 | No |
| reeval_ced_s42 | 42 | -- | -- | -- | -- | -- | **Yes, PREPARING** (uses correct ckpt-510) |
| reeval_ced_s44 | 44 | -- | -- | -- | -- | -- | **Yes, PREPARING** |
| eval_rsft_ced_s43 | 43 | -- | -- | -- | -- | -- | RUNNING |
| eval_rsft_ced_s45 | 45 | -- | -- | -- | -- | -- | RUNNING |

**3-seed mean (s42/s43/s44, original protocol)**: rel_f1 = 0.4596 +/- 0.0127, evi_f1 = 0.8143 +/- 0.0051

Seed 42 numbers are ambiguous: r1 (0.4449, 3-epoch, ckpt-510) vs r2a (0.4494, 1-epoch) vs r2b (0.4493, 1-epoch). The 3-seed mean used r2b_maxtok1536 (0.4504) for s42, which was the **wrong checkpoint** (r2b, alpha=32, 160 steps). D076 reeval aims to fix this.

### 4. RSFT flat-NLI (top_k=1) -- Different Seeds

| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 reeval? |
|--------|------|--------|--------|--------|--------------|------|-------------|
| **eval_plan_001_flat_nli** | 42 | 0.4539 | 0.4539 | 0.8043 | -- | 0.6431 | No |
| **reeval_flat_nli_s43** | 43 | 0.4523 | 0.4523 | 0.8158 | -- | 0.6505 | Partial (fixed --sft_adapter but batch_size=16) |
| **eval_flat_nli_s44** | 44 | 0.4615 | 0.4615 | 0.8131 | 0.3597 | 0.6458 | No |
| **eval_flat_nli_seed45** | 45 | 0.4551 | 0.4551 | 0.8154 | 0.3556 | 0.6521 | No |
| reeval_flat_nli_s42 | 42 | -- | -- | -- | -- | -- | **Yes, PREPARING** |
| reeval_flat_nli_s43_r2 | 43 | -- | -- | -- | -- | -- | **Yes, RUNNING** |

**3-seed mean (s42/s43/s44)**: rel_f1 = 0.4559 +/- 0.0049
**4-seed mean (s42/s43/s44/s45)**: rel_f1 = 0.4557

### 5. RSFT top_k=3

| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | edcr | D076 reeval? |
|--------|------|--------|--------|--------|------|-------------|
| **reeval_rsft_topk3** | 42 | 0.4454 | 0.4364 | 0.8088 | 0.6635 | Yes (ign_f1_corrected=true). ign_f1 != rel_f1 here |

Note: Training data had 8037 samples (vs 2718 for top_k=1). More data did NOT help; slightly worse than top_k=1.

### 6. CED Reranker (inference-time, no fine-tuning)

| exp_id | seed | rel_f1 | evi_f1 | edcr | notes |
|--------|------|--------|--------|------|-------|
| **mvp2_ced_reranker_poc** | 42 | 0.4864 | 0.8188 | 0.6156 | N=8 candidates, T=0.7 |

Additional metrics: oracle_rel_f1=0.6237, random_rel_f1=0.4538, CED-F1 Spearman r=0.3235 (p~0). CED reranker captures 37% of oracle ceiling. Generation time 20872.6s (vs ~3600s greedy).

### 7. GRPO QLoRA (catastrophic forgetting)

**kl_coef=0.01, G=8, lr=5e-5 (ced_kl001_r4 trajectory)**:

| exp_id | step | rel_f1 | ign_f1 | evi_f1 | edcr |
|--------|------|--------|--------|--------|------|
| mvp2_eval_ced_kl001_r4_ckpt10 | 10 | 0.0030 | -- | 0.72 | 0.9983 |
| mvp2_eval_ced_kl001_r4_multi (ckpt-20) | 20 | 0.0088 | 0.0088 | 0.423 | 0.9954 |
| mvp2_eval_ced_kl001_r4_multi (ckpt-30) | 30 | 0.0338 | 0.0338 | 0.5889 | 0.9798 |
| mvp2_eval_ced_kl001_r4_early (ckpt-50) | 50 | 0.1563 | 0.1563 | 0.5643 | 0.8858 |
| mvp2_eval_ced_kl001_r4_high (ckpt-60) | 60 | 0.1467 | 0.1467 | 0.5763 | 0.9062 |
| mvp2_eval_ced_kl001_r4_step90 | 90 | 0.2108 | 0.2108 | 0.5666 | 0.8584 |
| **mvp2_eval_ced_kl001_r4_step100** | 100 | 0.2167 | 0.2167 | 0.5746 | 0.8539 |

Best step-100: rel_f1=0.2167 (vs SFT 0.4057, delta=-18.9pp). Catastrophic forgetting confirmed.

**lr=5e-6 trajectory (lr5e6_r1)**:

| exp_id | step | rel_f1 | evi_f1 | edcr |
|--------|------|--------|--------|------|
| mvp2_eval_lr5e6_r1_ckpt20 | 20 | 0.0077 | 0.628 | 0.993 |
| mvp2_eval_lr5e6_r1_ckpt40_r2 | 40 | 0.0071 | 0.7584 | 0.9942 |
| mvp2_eval_lr5e6_r1_ckpt60_r2 | 60 | 0.0093 | 0.81 | 0.993 |
| mvp2_eval_lr5e6_r1_ckpt80 | 80 | 0.0116 | 0.828 | 0.993 |
| mvp2_eval_lr5e6_r1_ckpt100 | 100 | 0.0138 | 0.8504 | 0.9876 |

Even worse forgetting with lower lr: rel_f1 never exceeds 0.014. Evidence-only reward hacking (evi_f1 rises while rel_f1 ~0).

### 8. GRPO bf16 LoRA (NO forgetting)

| exp_id | seed | step | rel_f1 | ign_f1 | evi_f1 | edcr | notes |
|--------|------|------|--------|--------|--------|------|-------|
| plan_011_bf16_g8_step_eval (step30) | 42 | 30 | 0.434 | -- | 0.8063 | 0.6807 | |
| plan_011_bf16_g8_step_eval (step50) | 42 | 50 | 0.4276 | -- | 0.8024 | 0.6855 | |
| plan_011_bf16_g8_step_eval (step70) | 42 | 70 | 0.4341 | -- | 0.8099 | 0.6685 | |
| **eval_grpo_g8_bf16** (ckpt80) | 42 | 80 | 0.4456 | 0.4456 | 0.8034 | 0.6409 | |
| **eval_grpo_g8_bf16** (ckpt90) | 42 | 90 | 0.4523 | 0.4523 | 0.8052 | 0.6414 | |
| **eval_grpo_g8_bf16** (ckpt100) | 42 | 100 | **0.4549** | 0.4549 | 0.8086 | 0.6318 | Best |
| **plan_011_grpo_g8_bf16_eval** | 42 | 100 | 0.4549 | 0.4549 | 0.8086 | 0.6318 | Confirms ckpt-100 |

bf16 GRPO: rel_f1=0.4549 (+4.92pp vs SFT), monotonically improving, no forgetting. Key finding: **catastrophic forgetting is QLoRA-specific, not GRPO-specific**.

Config: G=8, kl_coef=0.01, lr=5e-5, LoRA r=64 alpha=128 bf16.

### 9. DPO

| exp_id | seed | rel_f1 | evi_f1 | edcr | epochs | notes |
|--------|------|--------|--------|------|--------|-------|
| **plan_012_dpo_ced** | 42 | 0.3429 | 0.8403 | 0.7294 | 3 | Overfitting (rewards_acc=1.0, margins=9.01) |
| **eval_plan_012_dpo_1ep_fixed_r2** | 42 | 0.4034 | 0.8088 | 0.7139 | 1 | Matches SFT (delta=-0.23pp) |
| plan_012_dpo_ced_1ep (eval) | 42 | 0.0022 | 0.75 | 0.9982 | 1 | INVALID: missing --sft_adapter |

DPO 3-epoch: overfits, rel_f1 drops to 0.3429 while evi_f1 rises to 0.8403 (decoupling).
DPO 1-epoch: rel_f1=0.4034, essentially SFT-level. DPO adds nothing for this task.

### 10. DREEAM Baseline

| exp_id | seed | dev_rel_f1 | dev_ign_f1 | dev_evi_f1 | notes |
|--------|------|-----------|-----------|-----------|-------|
| **plan_004_dreeam_baseline** | 66 | **63.57** | **61.72** | **54.01** | RoBERTa-large teacher. P=66.95, R=60.51 |

Note: Metrics are in percentage scale (0-100), not 0-1 like the other experiments. This is a classification-based model (not generative).

### 11. EDCR Diagnostic

| exp_id | conclusion | notes |
|--------|-----------|-------|
| **plan_003_edcr_diagnostic** | success | EDCR vs rel_f1 Spearman = -0.9648 (p=0.0001). EDCR vs evi_f1 = 0.0022 (not significant). EDCR range 0.63-0.99. Identifies pathological models. |

### 12. CED Signal Validation

| exp_id | conclusion | metrics |
|--------|-----------|---------|
| **mvp1_ced_signal** | success | mean_margin=0.48, discrimination_accuracy=0.815, Pearson r(margin,jaccard)=0.34 |

### 13. GRPO Earlier Runs (all failed/negative, QLoRA)

| exp_id | conclusion | key finding |
|--------|-----------|-------------|
| mvp2_grpo_ced_r1-r5 | killed/negative | Mode collapse: f1=0, format reward hacking, completion length collapse |
| mvp2_grpo_extract_r3-r4 | negative/killed | kl_coef=0 + G=4 = stagnation (frac_zero_std=1.0) |
| mvp2_grpo_flatnli_r3-r6 | killed/negative | flatNLI GRPO collapses by step 25 even with kl=0.01+G=8 |
| mvp2_grpo_ced_lr5e6_rp_r2 | killed | recall_penalty causes loss divergence (step 10: 908 -> step 20: 1.34e7) |

### 14. Training-Only Experiments (no eval metrics)

| exp_id | seed | conclusion | notes |
|--------|------|-----------|-------|
| plan_001_rsft_flat_nli | 42 | success | 2691 samples, 3 epochs, 507 steps |
| plan_001_flat_nli_seed43 | 43 | success | task_eval(50-doc): f1=0.4866, evi_f1=0.7834 |
| plan_001_flat_nli_seed44 | 44 | success | task_eval(50-doc): f1=0.4897, evi_f1=0.78 |
| plan_001_flat_nli_seed45 | 45 | success | task_eval(50-doc): f1=0.4876, evi_f1=0.7927 |
| mvp2_rsft_train_r1 | 42 | success | CED RSFT, 2718 samples |
| mvp2_rsft_train_r1_s43 | 43 | success | eval_loss=0.7622, 510 steps |
| rsft_ced_s43_train_r3 | 43 | success | task_eval: f1=0.5026, evi_f1=0.7624 |
| rsft_ced_s45_train_r4 | 45 | success | training completed, eval running |
| plan_008_rsft_topk3 | 42 | success | 8037 samples, task_eval ep3: f1=0.5012 |
| plan_014_sft_no_evidence | 42 | success | training only, 3027 samples |
| plan_011_grpo_g8_bf16 | 42 | success | 100 steps, 9.2min, no mode collapse |
| mvp2_grpo_ced_kl001_r4 | 42 | success | 100 steps, best reward step=90 |

---

## Summary Table for Paper Evidence (completed eval experiments only, primary results)

| Method | Variant | Seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 Unified? |
|--------|---------|------|--------|--------|--------|--------------|------|---------------|
| SFT baseline | quantized | 42 | 0.4057 | 0.4057 | 0.7979 | 0.3117 | 0.7118 | Yes (r3) |
| SFT baseline | no-quantize | 42 | 0.4106 | -- | 0.8013 | 0.3216 | 0.7039 | No |
| SFT no-evidence | ablation | 42 | 0.4893 | 0.4893 | 0 | -- | 0 | No |
| RSFT CED k=1 | s42 (r1, 3ep) | 42 | 0.4449 | -- | 0.8187 | 0.3468 | 0.6565 | No |
| RSFT CED k=1 | s42 (r2a, 1ep) | 42 | 0.4494 | 0.4494 | 0.8108 | 0.3509 | 0.6641 | No |
| RSFT CED k=1 | s43 | 43 | 0.4683 | 0.4683 | 0.8156 | 0.3711 | 0.6388 | No |
| RSFT CED k=1 | s44 | 44 | 0.4655 | -- | 0.8087 | 0.3713 | 0.6350 | No |
| RSFT CED k=1 | s45 | 45 | -- | -- | -- | -- | -- | RUNNING |
| RSFT flat-NLI k=1 | s42 | 42 | 0.4539 | 0.4539 | 0.8043 | -- | 0.6431 | No |
| RSFT flat-NLI k=1 | s43 | 43 | 0.4523 | 0.4523 | 0.8158 | -- | 0.6505 | Partial |
| RSFT flat-NLI k=1 | s44 | 44 | 0.4615 | 0.4615 | 0.8131 | 0.3597 | 0.6458 | No |
| RSFT flat-NLI k=1 | s45 | 45 | 0.4551 | 0.4551 | 0.8154 | 0.3556 | 0.6521 | No |
| RSFT CED k=3 | s42 | 42 | 0.4454 | 0.4364 | 0.8088 | -- | 0.6635 | Yes (ign_corrected) |
| CED Reranker (N=8) | inference-time | 42 | 0.4864 | -- | 0.8188 | -- | 0.6156 | No |
| GRPO QLoRA best | ced kl001 ckpt100 | 42 | 0.2167 | 0.2167 | 0.5746 | -- | 0.8539 | No |
| GRPO bf16 best | G8 ckpt100 | 42 | 0.4549 | 0.4549 | 0.8086 | -- | 0.6318 | No |
| DPO CED 3ep | overfitting | 42 | 0.3429 | -- | 0.8403 | -- | 0.7294 | No |
| DPO CED 1ep | fixed | 42 | 0.4034 | 0.4034 | 0.8088 | -- | 0.7139 | No |
| DREEAM teacher | RoBERTa-large | 66 | 63.57* | 61.72* | 54.01* | -- | -- | N/A |

*DREEAM uses % scale (not 0-1).

---

## Key Protocol Issues

1. **D076 unified protocol reeval**: Several "reeval_*" experiments are PREPARING or RUNNING to standardize all evaluations to batch_size=4, --no-quantize, --sft_adapter, max_new_tokens=1024. Currently completed with unified protocol: reeval_flat_nli_s43, reeval_rsft_topk3, mvp2_sft_eval_r3.

2. **ign_f1 = rel_f1 for most experiments**: This equality holds for almost all experiments except reeval_rsft_topk3 (ign_f1=0.4364 vs rel_f1=0.4454), which has `ign_f1_corrected: true`. The ign_f1 computation may have a bug in non-corrected experiments.

3. **CED s42 checkpoint confusion**: The original s42 eval (mvp2_eval_rsft_r2b_maxtok1536_r2) used the wrong checkpoint (r2b: alpha=32, 160 steps) instead of the correct one (rsft_output/checkpoint-510: alpha=128, 510 steps). reeval_ced_s42 is PREPARING to fix this.

4. **Broken experiments** (missing --sft_adapter, rel_f1 ~0.002): eval_plan_001_flat_nli_s43, eval_plan_012_dpo_ced_1ep, eval_plan_008_rsft_topk3. All have been re-run correctly.

5. **Still running/pending**: eval_rsft_ced_s43 (s43 CED), eval_rsft_ced_s45 (s45 CED), reeval_flat_nli_s43_r2 (unified protocol), eval_plan_014_no_evidence_r2, reeval_ced_s42, reeval_ced_s44, reeval_flat_nli_s42.

agentId: a04aaecf72a9d4164 (use SendMessage with to: 'a04aaecf72a9d4164' to continue this agent)
&lt;usage>total_tokens: 72499
tool_uses: 15
duration_ms: 217147&lt;/usage>
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "3a62eda0-8b8a-4ee8-8170-ee55a9ec0997",
  "tool_use_result": {
    "status": "completed",
    "prompt": "I need you to extract structured experiment data from a large JSON registry file for building a paper evidence table.\n\nThe file is at: /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_registry-1778901685097.txt\n\nThis is JSON with schema: {result: string} where `result` is itself a JSON string.\n\nSteps:\n1. First probe the structure with jq to understand the schema\n2. Then extract ALL experiments, focusing on these fields for each:\n   - exp_id\n   - status\n   - conclusion\n   - method/config description\n   - key metrics: rel_f1, ign_f1, evi_f1, edcr, evi_f1_joint\n   - protocol info (is this a D076 unified protocol reeval?)\n   - seed if available\n   - any notes/tags\n\n3. Group experiments by method type:\n   - SFT baseline (with and without evidence)\n   - RSFT CED (different seeds)\n   - RSFT flat-NLI (different seeds)\n   - RSFT top_k=3\n   - CED reranker\n   - GRPO QLoRA\n   - GRPO bf16\n   - DPO\n   - DREEAM baseline\n   - Any other experiments\n\n4. For each experiment, note whether it used the D076 unified evaluation protocol (look for \"reeval\" in exp_id, or \"unified_protocol\", \"ign_f1_corrected\" flags, or D076 mentions).\n\nReturn a comprehensive structured summary with ALL metric values. Do not truncate or skip experiments. This is for a paper evidence table so every number matters.",
    "agentId": "a04aaecf72a9d4164",
    "agentType": "general-purpose",
    "content": [
      {
        "type": "text",
        "text": "Now I have all the data needed. Here is the comprehensive structured summary:\n\n---\n\n## Complete Experiment Registry: 130 experiments total\n\n### 1. SFT BASELINE (with evidence)\n\n| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | notes |\n|--------|------|--------|--------|--------|--------------|------|-------|\n| **mvp2_sft_eval_r2** | 42 | 0.4057 | 0.4057 | 0.7979 | -- | 0.7118 | Original baseline, quantized (QLoRA 4-bit) |\n| **mvp2_sft_eval_r3** | 42 | 0.4057 | 0.4057 | 0.7979 | -- | 0.7118 | Unified eval code verification; identical to r2 |\n| **mvp2_eval_sft_baseline** | 42 | 0.4057 | 0.4057 | 0.7979 | 0.3117 | 0.7118 | Apple-to-apple protocol eval. P=0.4043, R=0.407. 367 truncated, 18815 preds |\n| **eval_sft_baseline_noquant** | 42 | 0.4106 | -- | 0.8013 | 0.3216 | 0.7039 | No-quantize. +0.49pp rel_f1 vs quantized. Confirms quantize confound <1pp |\n\n**Canonical SFT baseline**: rel_f1=0.4057, evi_f1=0.7979, edcr=0.7118, evi_f1_joint=0.3117\n\n### 2. SFT WITHOUT EVIDENCE (ablation)\n\n| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | edcr | notes |\n|--------|------|--------|--------|--------|------|-------|\n| **eval_plan_014_sft_no_evidence** | 42 | 0.4893 | 0.4893 | 0 | 0 | +20.6% over SFT baseline; evidence generation hurts RE |\n| eval_plan_014_no_evidence | -- | -- | -- | -- | -- | FAILED: adapter config error |\n| eval_plan_014_no_evidence_r2 | -- | -- | -- | -- | -- | RUNNING |\n\n### 3. RSFT CED (top_k=1) -- Different Seeds\n\n| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 reeval? |\n|--------|------|--------|--------|--------|--------------|------|-------------|\n| **mvp2_eval_rsft_r1** | 42 | 0.4449 | -- | 0.8187 | 0.3468 | 0.6565 | No (original) |\n| **mvp2_eval_rsft_r2a** | 42 | 0.4494 | 0.4494 | 0.8108 | 0.3509 | 0.6641 | No (1-epoch ablation, alpha=128) |\n| **mvp2_eval_rsft_r2b** | 42 | 0.4493 | 0.4493 | 0.8128 | 0.3490 | 0.6609 | No (1-epoch ablation, alpha=32) |\n| mvp2_eval_rsft_r2b_maxtok1536_r2 | 42 | 0.4504 | 0.4504 | 0.8102 | -- | 0.6740 | No (truncation diagnosis, max_tok=1536). NOTE: wrong checkpoint (r2b: alpha=32, 160 steps) |\n| **mvp2_eval_rsft_s43_r2** | 43 | 0.4683 | 0.4683 | 0.8156 | 0.3711 | 0.6388 | No |\n| **mvp2_rsft_train_r1_s44** (eval) | 44 | 0.4655 | -- | 0.8087 | 0.3713 | 0.6350 | No |\n| reeval_ced_s42 | 42 | -- | -- | -- | -- | -- | **Yes, PREPARING** (uses correct ckpt-510) |\n| reeval_ced_s44 | 44 | -- | -- | -- | -- | -- | **Yes, PREPARING** |\n| eval_rsft_ced_s43 | 43 | -- | -- | -- | -- | -- | RUNNING |\n| eval_rsft_ced_s45 | 45 | -- | -- | -- | -- | -- | RUNNING |\n\n**3-seed mean (s42/s43/s44, original protocol)**: rel_f1 = 0.4596 +/- 0.0127, evi_f1 = 0.8143 +/- 0.0051\n\nSeed 42 numbers are ambiguous: r1 (0.4449, 3-epoch, ckpt-510) vs r2a (0.4494, 1-epoch) vs r2b (0.4493, 1-epoch). The 3-seed mean used r2b_maxtok1536 (0.4504) for s42, which was the **wrong checkpoint** (r2b, alpha=32, 160 steps). D076 reeval aims to fix this.\n\n### 4. RSFT flat-NLI (top_k=1) -- Different Seeds\n\n| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 reeval? |\n|--------|------|--------|--------|--------|--------------|------|-------------|\n| **eval_plan_001_flat_nli** | 42 | 0.4539 | 0.4539 | 0.8043 | -- | 0.6431 | No |\n| **reeval_flat_nli_s43** | 43 | 0.4523 | 0.4523 | 0.8158 | -- | 0.6505 | Partial (fixed --sft_adapter but batch_size=16) |\n| **eval_flat_nli_s44** | 44 | 0.4615 | 0.4615 | 0.8131 | 0.3597 | 0.6458 | No |\n| **eval_flat_nli_seed45** | 45 | 0.4551 | 0.4551 | 0.8154 | 0.3556 | 0.6521 | No |\n| reeval_flat_nli_s42 | 42 | -- | -- | -- | -- | -- | **Yes, PREPARING** |\n| reeval_flat_nli_s43_r2 | 43 | -- | -- | -- | -- | -- | **Yes, RUNNING** |\n\n**3-seed mean (s42/s43/s44)**: rel_f1 = 0.4559 +/- 0.0049\n**4-seed mean (s42/s43/s44/s45)**: rel_f1 = 0.4557\n\n### 5. RSFT top_k=3\n\n| exp_id | seed | rel_f1 | ign_f1 | evi_f1 | edcr | D076 reeval? |\n|--------|------|--------|--------|--------|------|-------------|\n| **reeval_rsft_topk3** | 42 | 0.4454 | 0.4364 | 0.8088 | 0.6635 | Yes (ign_f1_corrected=true). ign_f1 != rel_f1 here |\n\nNote: Training data had 8037 samples (vs 2718 for top_k=1). More data did NOT help; slightly worse than top_k=1.\n\n### 6. CED Reranker (inference-time, no fine-tuning)\n\n| exp_id | seed | rel_f1 | evi_f1 | edcr | notes |\n|--------|------|--------|--------|------|-------|\n| **mvp2_ced_reranker_poc** | 42 | 0.4864 | 0.8188 | 0.6156 | N=8 candidates, T=0.7 |\n\nAdditional metrics: oracle_rel_f1=0.6237, random_rel_f1=0.4538, CED-F1 Spearman r=0.3235 (p~0). CED reranker captures 37% of oracle ceiling. Generation time 20872.6s (vs ~3600s greedy).\n\n### 7. GRPO QLoRA (catastrophic forgetting)\n\n**kl_coef=0.01, G=8, lr=5e-5 (ced_kl001_r4 trajectory)**:\n\n| exp_id | step | rel_f1 | ign_f1 | evi_f1 | edcr |\n|--------|------|--------|--------|--------|------|\n| mvp2_eval_ced_kl001_r4_ckpt10 | 10 | 0.0030 | -- | 0.72 | 0.9983 |\n| mvp2_eval_ced_kl001_r4_multi (ckpt-20) | 20 | 0.0088 | 0.0088 | 0.423 | 0.9954 |\n| mvp2_eval_ced_kl001_r4_multi (ckpt-30) | 30 | 0.0338 | 0.0338 | 0.5889 | 0.9798 |\n| mvp2_eval_ced_kl001_r4_early (ckpt-50) | 50 | 0.1563 | 0.1563 | 0.5643 | 0.8858 |\n| mvp2_eval_ced_kl001_r4_high (ckpt-60) | 60 | 0.1467 | 0.1467 | 0.5763 | 0.9062 |\n| mvp2_eval_ced_kl001_r4_step90 | 90 | 0.2108 | 0.2108 | 0.5666 | 0.8584 |\n| **mvp2_eval_ced_kl001_r4_step100** | 100 | 0.2167 | 0.2167 | 0.5746 | 0.8539 |\n\nBest step-100: rel_f1=0.2167 (vs SFT 0.4057, delta=-18.9pp). Catastrophic forgetting confirmed.\n\n**lr=5e-6 trajectory (lr5e6_r1)**:\n\n| exp_id | step | rel_f1 | evi_f1 | edcr |\n|--------|------|--------|--------|------|\n| mvp2_eval_lr5e6_r1_ckpt20 | 20 | 0.0077 | 0.628 | 0.993 |\n| mvp2_eval_lr5e6_r1_ckpt40_r2 | 40 | 0.0071 | 0.7584 | 0.9942 |\n| mvp2_eval_lr5e6_r1_ckpt60_r2 | 60 | 0.0093 | 0.81 | 0.993 |\n| mvp2_eval_lr5e6_r1_ckpt80 | 80 | 0.0116 | 0.828 | 0.993 |\n| mvp2_eval_lr5e6_r1_ckpt100 | 100 | 0.0138 | 0.8504 | 0.9876 |\n\nEven worse forgetting with lower lr: rel_f1 never exceeds 0.014. Evidence-only reward hacking (evi_f1 rises while rel_f1 ~0).\n\n### 8. GRPO bf16 LoRA (NO forgetting)\n\n| exp_id | seed | step | rel_f1 | ign_f1 | evi_f1 | edcr | notes |\n|--------|------|------|--------|--------|--------|------|-------|\n| plan_011_bf16_g8_step_eval (step30) | 42 | 30 | 0.434 | -- | 0.8063 | 0.6807 | |\n| plan_011_bf16_g8_step_eval (step50) | 42 | 50 | 0.4276 | -- | 0.8024 | 0.6855 | |\n| plan_011_bf16_g8_step_eval (step70) | 42 | 70 | 0.4341 | -- | 0.8099 | 0.6685 | |\n| **eval_grpo_g8_bf16** (ckpt80) | 42 | 80 | 0.4456 | 0.4456 | 0.8034 | 0.6409 | |\n| **eval_grpo_g8_bf16** (ckpt90) | 42 | 90 | 0.4523 | 0.4523 | 0.8052 | 0.6414 | |\n| **eval_grpo_g8_bf16** (ckpt100) | 42 | 100 | **0.4549** | 0.4549 | 0.8086 | 0.6318 | Best |\n| **plan_011_grpo_g8_bf16_eval** | 42 | 100 | 0.4549 | 0.4549 | 0.8086 | 0.6318 | Confirms ckpt-100 |\n\nbf16 GRPO: rel_f1=0.4549 (+4.92pp vs SFT), monotonically improving, no forgetting. Key finding: **catastrophic forgetting is QLoRA-specific, not GRPO-specific**.\n\nConfig: G=8, kl_coef=0.01, lr=5e-5, LoRA r=64 alpha=128 bf16.\n\n### 9. DPO\n\n| exp_id | seed | rel_f1 | evi_f1 | edcr | epochs | notes |\n|--------|------|--------|--------|------|--------|-------|\n| **plan_012_dpo_ced** | 42 | 0.3429 | 0.8403 | 0.7294 | 3 | Overfitting (rewards_acc=1.0, margins=9.01) |\n| **eval_plan_012_dpo_1ep_fixed_r2** | 42 | 0.4034 | 0.8088 | 0.7139 | 1 | Matches SFT (delta=-0.23pp) |\n| plan_012_dpo_ced_1ep (eval) | 42 | 0.0022 | 0.75 | 0.9982 | 1 | INVALID: missing --sft_adapter |\n\nDPO 3-epoch: overfits, rel_f1 drops to 0.3429 while evi_f1 rises to 0.8403 (decoupling).\nDPO 1-epoch: rel_f1=0.4034, essentially SFT-level. DPO adds nothing for this task.\n\n### 10. DREEAM Baseline\n\n| exp_id | seed | dev_rel_f1 | dev_ign_f1 | dev_evi_f1 | notes |\n|--------|------|-----------|-----------|-----------|-------|\n| **plan_004_dreeam_baseline** | 66 | **63.57** | **61.72** | **54.01** | RoBERTa-large teacher. P=66.95, R=60.51 |\n\nNote: Metrics are in percentage scale (0-100), not 0-1 like the other experiments. This is a classification-based model (not generative).\n\n### 11. EDCR Diagnostic\n\n| exp_id | conclusion | notes |\n|--------|-----------|-------|\n| **plan_003_edcr_diagnostic** | success | EDCR vs rel_f1 Spearman = -0.9648 (p=0.0001). EDCR vs evi_f1 = 0.0022 (not significant). EDCR range 0.63-0.99. Identifies pathological models. |\n\n### 12. CED Signal Validation\n\n| exp_id | conclusion | metrics |\n|--------|-----------|---------|\n| **mvp1_ced_signal** | success | mean_margin=0.48, discrimination_accuracy=0.815, Pearson r(margin,jaccard)=0.34 |\n\n### 13. GRPO Earlier Runs (all failed/negative, QLoRA)\n\n| exp_id | conclusion | key finding |\n|--------|-----------|-------------|\n| mvp2_grpo_ced_r1-r5 | killed/negative | Mode collapse: f1=0, format reward hacking, completion length collapse |\n| mvp2_grpo_extract_r3-r4 | negative/killed | kl_coef=0 + G=4 = stagnation (frac_zero_std=1.0) |\n| mvp2_grpo_flatnli_r3-r6 | killed/negative | flatNLI GRPO collapses by step 25 even with kl=0.01+G=8 |\n| mvp2_grpo_ced_lr5e6_rp_r2 | killed | recall_penalty causes loss divergence (step 10: 908 -> step 20: 1.34e7) |\n\n### 14. Training-Only Experiments (no eval metrics)\n\n| exp_id | seed | conclusion | notes |\n|--------|------|-----------|-------|\n| plan_001_rsft_flat_nli | 42 | success | 2691 samples, 3 epochs, 507 steps |\n| plan_001_flat_nli_seed43 | 43 | success | task_eval(50-doc): f1=0.4866, evi_f1=0.7834 |\n| plan_001_flat_nli_seed44 | 44 | success | task_eval(50-doc): f1=0.4897, evi_f1=0.78 |\n| plan_001_flat_nli_seed45 | 45 | success | task_eval(50-doc): f1=0.4876, evi_f1=0.7927 |\n| mvp2_rsft_train_r1 | 42 | success | CED RSFT, 2718 samples |\n| mvp2_rsft_train_r1_s43 | 43 | success | eval_loss=0.7622, 510 steps |\n| rsft_ced_s43_train_r3 | 43 | success | task_eval: f1=0.5026, evi_f1=0.7624 |\n| rsft_ced_s45_train_r4 | 45 | success | training completed, eval running |\n| plan_008_rsft_topk3 | 42 | success | 8037 samples, task_eval ep3: f1=0.5012 |\n| plan_014_sft_no_evidence | 42 | success | training only, 3027 samples |\n| plan_011_grpo_g8_bf16 | 42 | success | 100 steps, 9.2min, no mode collapse |\n| mvp2_grpo_ced_kl001_r4 | 42 | success | 100 steps, best reward step=90 |\n\n---\n\n## Summary Table for Paper Evidence (completed eval experiments only, primary results)\n\n| Method | Variant | Seed | rel_f1 | ign_f1 | evi_f1 | evi_f1_joint | edcr | D076 Unified? |\n|--------|---------|------|--------|--------|--------|--------------|------|---------------|\n| SFT baseline | quantized | 42 | 0.4057 | 0.4057 | 0.7979 | 0.3117 | 0.7118 | Yes (r3) |\n| SFT baseline | no-quantize | 42 | 0.4106 | -- | 0.8013 | 0.3216 | 0.7039 | No |\n| SFT no-evidence | ablation | 42 | 0.4893 | 0.4893 | 0 | -- | 0 | No |\n| RSFT CED k=1 | s42 (r1, 3ep) | 42 | 0.4449 | -- | 0.8187 | 0.3468 | 0.6565 | No |\n| RSFT CED k=1 | s42 (r2a, 1ep) | 42 | 0.4494 | 0.4494 | 0.8108 | 0.3509 | 0.6641 | No |\n| RSFT CED k=1 | s43 | 43 | 0.4683 | 0.4683 | 0.8156 | 0.3711 | 0.6388 | No |\n| RSFT CED k=1 | s44 | 44 | 0.4655 | -- | 0.8087 | 0.3713 | 0.6350 | No |\n| RSFT CED k=1 | s45 | 45 | -- | -- | -- | -- | -- | RUNNING |\n| RSFT flat-NLI k=1 | s42 | 42 | 0.4539 | 0.4539 | 0.8043 | -- | 0.6431 | No |\n| RSFT flat-NLI k=1 | s43 | 43 | 0.4523 | 0.4523 | 0.8158 | -- | 0.6505 | Partial |\n| RSFT flat-NLI k=1 | s44 | 44 | 0.4615 | 0.4615 | 0.8131 | 0.3597 | 0.6458 | No |\n| RSFT flat-NLI k=1 | s45 | 45 | 0.4551 | 0.4551 | 0.8154 | 0.3556 | 0.6521 | No |\n| RSFT CED k=3 | s42 | 42 | 0.4454 | 0.4364 | 0.8088 | -- | 0.6635 | Yes (ign_corrected) |\n| CED Reranker (N=8) | inference-time | 42 | 0.4864 | -- | 0.8188 | -- | 0.6156 | No |\n| GRPO QLoRA best | ced kl001 ckpt100 | 42 | 0.2167 | 0.2167 | 0.5746 | -- | 0.8539 | No |\n| GRPO bf16 best | G8 ckpt100 | 42 | 0.4549 | 0.4549 | 0.8086 | -- | 0.6318 | No |\n| DPO CED 3ep | overfitting | 42 | 0.3429 | -- | 0.8403 | -- | 0.7294 | No |\n| DPO CED 1ep | fixed | 42 | 0.4034 | 0.4034 | 0.8088 | -- | 0.7139 | No |\n| DREEAM teacher | RoBERTa-large | 66 | 63.57* | 61.72* | 54.01* | -- | -- | N/A |\n\n*DREEAM uses % scale (not 0-1).\n\n---\n\n## Key Protocol Issues\n\n1. **D076 unified protocol reeval**: Several \"reeval_*\" experiments are PREPARING or RUNNING to standardize all evaluations to batch_size=4, --no-quantize, --sft_adapter, max_new_tokens=1024. Currently completed with unified protocol: reeval_flat_nli_s43, reeval_rsft_topk3, mvp2_sft_eval_r3.\n\n2. **ign_f1 = rel_f1 for most experiments**: This equality holds for almost all experiments except reeval_rsft_topk3 (ign_f1=0.4364 vs rel_f1=0.4454), which has `ign_f1_corrected: true`. The ign_f1 computation may have a bug in non-corrected experiments.\n\n3. **CED s42 checkpoint confusion**: The original s42 eval (mvp2_eval_rsft_r2b_maxtok1536_r2) used the wrong checkpoint (r2b: alpha=32, 160 steps) instead of the correct one (rsft_output/checkpoint-510: alpha=128, 510 steps). reeval_ced_s42 is PREPARING to fix this.\n\n4. **Broken experiments** (missing --sft_adapter, rel_f1 ~0.002): eval_plan_001_flat_nli_s43, eval_plan_012_dpo_ced_1ep, eval_plan_008_rsft_topk3. All have been re-run correctly.\n\n5. **Still running/pending**: eval_rsft_ced_s43 (s43 CED), eval_rsft_ced_s45 (s45 CED), reeval_flat_nli_s43_r2 (unified protocol), eval_plan_014_no_evidence_r2, reeval_ced_s42, reeval_ced_s44, reeval_flat_nli_s42."
      }
    ],
    "totalDurationMs": 217147,
    "totalTokens": 72499,
    "totalToolUseCount": 15,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1020,
      "cache_read_input_tokens": 64767,
      "output_tokens": 6711,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1020
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 6711,
          "cache_read_input_tokens": 64767,
          "cache_creation_input_tokens": 1020,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1020,
            "ephemeral_1h_input_tokens": 0
          },
          "type": "message"
        }
      ],
      "speed": "standard"
    },
    "toolStats": {
      "readCount": 6,
      "searchCount": 0,
      "bashCount": 9,
      "editFileCount": 0,
      "linesAdded": 0,
      "linesRemoved": 0,
      "otherToolCount": 0
    }
  }
}
```

</details>

---

### Assistant

_source line 70_

<details><summary>Logged reasoning block</summary>

```text
Now I have comprehensive data. Let me also read the decisions file for D076 and other decision context.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "5e1ed33d-d3ba-4cc7-b36a-1fc9fd1c6093",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VozihxJGAV6VnT21QnPTN3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7405,
      "cache_read_input_tokens": 38448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7405
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

_source line 71_

Now let me read the decisions file for D076 context and any other relevant decisions.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "0b6bc4b4-534a-4904-b143-72d1dad10bf4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VozihxJGAV6VnT21QnPTN3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7405,
      "cache_read_input_tokens": 38448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7405
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

_source line 72_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01GL18g6dKWbwed9nYRCYSbb`</summary>

```json
{
  "project": "faith-evidence-ie",
  "file": "decisions.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "1ae588c0-534a-4767-9eed-86b40f541729",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VozihxJGAV6VnT21QnPTN3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7405,
      "cache_read_input_tokens": 38448,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7405
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

_source line 73 · 2026-05-16T03:25:20.402Z_

<details><summary>↩ Tool result · `toolu_01GL18g6dKWbwed9nYRCYSbb`</summary>

```text
Error: result (62,376 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt.
Format: JSON with schema: {result: string}
- For targeted queries (find a value, filter by field): use jq on the file directly.
- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.
- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim." A vague "summarize this" may lose detail.

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "8d3833f7-0a96-41dd-bc12-d8654af4a867",
  "tool_use_result": {
    "content": "Error: result (62,376 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt.\nFormat: JSON with schema: {result: string}\n- For targeted queries (find a value, filter by field): use jq on the file directly.\n- For analysis or summarization that requires reading the full content: first probe the structure (e.g., jq 'type, length, keys?' /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt), then extract slices with jq or python — Read's line-based offset/limit will not chunk this file.\n- If the Agent tool is available, do this inside a subagent so the full output stays out of your main context. Give it the instruction above verbatim, and be explicit about what it must return — e.g. \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt is JSON with schema: {result: string}; probe the structure with jq (type/length/keys), then extract and read the content in full with jq or python, then summarize and quote any key findings verbatim.\" A vague \"summarize this\" may lose detail.\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/decisions.yaml\", \"content\": \"_next_id: 77\\ndecisions:\\n- id: D001\\n  date: 2026-05-14 04:21 UTC\\n  summary: MVP 设计：两阶段验证——MVP-1 CED 信号验证（离线）→ MVP-2 端到端训练验证\\n  rationale: CED 是核心创新，必须先验证 DeBERTa NLI 能在 DocRED 上区分金标证据与实体共现干扰句（MVP-1），再投入 GPU\\n    跑完整训练流水线（MVP-2）。MVP-1 失败则 idea 需 pivot，避免浪费 GPU。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-14 05:46 UTC\\n  summary: 'MVP-1 PASS: CED 信号验证通过，核心假设成立（margin 0.48, accuracy 81.5%, Pearson r 0.34）'\\n  rationale: CED margin 4.8× 超过阈值，DeBERTa 判别力主要来自语义蕴含而非词汇重叠（r=0.34 远低于 0.7）。三个需关注项：33.4%\\n    gold p_pos < τ=0.5（τ 可能需调低）、44.4% 无 hard negatives（退化为 flat NLI）、少数负 margin 样本（标注噪声）。这些不影响\\n    MVP 结论但影响 Research 阶段 CED 调参。\\n  related_experiments:\\n  - exp_id: mvp1_ced_signal\\n    role: primary\\n    result: PASS — mean_margin=0.4827, accuracy=81.5%, pearson_r=0.3406\\n  depends_on: []\\n- id: D003\\n  date: 2026-05-14 06:02 UTC\\n  summary: 'Smoke test 功能性 PASS: ZeRO-2 + QLoRA 兼容，4.9GB/卡，授权启动 MVP-2 SFT'\\n  rationale: Smoke test 自报 FAIL 是假阴性——synthetic data format-only reward 产生零 variance，数学上无梯度是正常行为。关键目标全部达成：ZeRO-2+QLoRA+GRPOTrainer\\n    兼容、显存充裕（4.9/32GB）、有 reward variance 时梯度正常。Reviewer 独立确认功能性 PASS。\\n  related_experiments:\\n  - exp_id: smoke_test_grpo\\n    role: infrastructure\\n    result: 功能性 PASS (ZeRO-2+QLoRA, 4×5090, 4.9GB/卡)\\n  depends_on:\\n  - D002\\n- id: D004\\n  date: 2026-05-14 07:26 UTC\\n  summary: 发现 rtx5090-4x 和 gpu-5090-4x-1 为同一台机器（4 GPU），GRPO 三路对比改为串行\\n  rationale: Reviewer 核实两个 SSH endpoint 返回相同 hostname 和 PID。实际资源 = 4× RTX 5090 32GB，非\\n    8 张。串行 3 路 GRPO 预估 ~7-10h（每路 ~2-3h），今天内可完成 MVP-2，暂不需要额外申请 GPU。\\n  related_experiments: []\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-14 10:03 UTC\\n  summary: CED r1 训练 step 40 后 mode collapse，启动早停+checkpoint 抢救+cliprange 排查\\n  rationale: Reviewer 审查发现 step 40 后所有指标退化（total_reward 1.79→1.10, f1 0.098→0.012,\\n    length 88→547）。clip_ratio 全程为 0 表明 PPO 裁剪未生效，可能是 policy drift 失控的根因。决策：(1) 抢救\\n    step 40 checkpoint 作为当前最优；(2) step 70 前不回升则 kill；(3) 排查并修正 cliprange 后重跑。step\\n    40 checkpoint 仍可用于 vs SFT 的对比 eval，MVP-2 流程不完全停滞。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r1\\n    role: primary\\n    result: training collapse after step 40, early stopping evaluation in progress\\n  depends_on:\\n  - D003\\n  - D004\\n- id: D006\\n  date: 2026-05-14 10:24 UTC\\n  summary: Kill CED r1（F1 归零+无 checkpoint），准备修复配置后重跑 r2\\n  rationale: Reviewer 确认 step 80 时 f1_reward=0.001（从 peak 0.098 单调下降 50 步），grpo_s3\\n    目录为空（无中间 checkpoint），step 40 最优模型不可挽回。继续 1.3h 必产废模型。诊断三个根因：(1) 无 save_steps 配置；(2)\\n    reward 权重失衡（format ~0.97 远大于 f1 ~0.001，模型无 f1 梯度信号）；(3) clip_ratio=0 裁剪未生效。决策\\n    kill 并修复后重跑 r2。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r1\\n    role: primary\\n    result: KILL — f1_reward 归零, 无 checkpoint, 训练不可挽回\\n  depends_on:\\n  - D005\\n- id: D007\\n  date: 2026-05-14 11:28 UTC\\n  summary: r3 回退 num_iterations=1，隔离变量逐一测试\\n  rationale: Reviewer CRITICAL 确认：r2 的 KL 在 step 5 爆到 37亿、step 15 爆到 3400亿，直接导致 loss\\n    爆炸+OOM。根因是 num_iterations=2 + QLoRA 4-bit 量化 logits 精度不足，两次迭代间 KL 被放大。r2 同时改了\\n    6 个超参，崩溃后无法归因。r3 必须回退 num_iterations=1，保留 reward weighting（reward 0.25→0.42 正常上升证明\\n    WeightedRewardFn 有效），一次只改一个变量。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r2\\n    role: evidence\\n    result: KL explosion + OOM at step 18, num_iterations=2 confirmed as root cause\\n  depends_on: []\\n- id: D008\\n  date: 2026-05-14 12:07 UTC\\n  summary: D007 证伪：KL 爆炸根因是 kl_coef + QLoRA 4-bit 不兼容，非 num_iterations。全部 GRPO 重跑\\n    kl_coef=0\\n  rationale: 3 个 GRPO 实验（num_iterations=1）均在 step 5 触发 KL 爆炸早停（KL 达 10^10 量级）。对比 r1（kl_coef=0/未设）跑了\\n    80+ steps 才因 reward imbalance collapse。证据链：所有设 kl_coef=0.05 的实验全部 step 5 爆炸，未设的\\n    r1 稳定运行。机理：QLoRA 4-bit 量化噪声导致 ref model 和 training model 的 log-probs 存在系统性偏差，KL(π_θ||π_ref)\\n    从第一步就是天文数字。修复：kl_coef=0，依赖 reward weighting + save_steps + KL 监控（logging only）控制稳定性。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r3\\n    role: evidence\\n    result: KL explosion step 5, kl_coef=0.05, num_iterations=1\\n  - exp_id: mvp2_grpo_extract\\n    role: evidence\\n    result: KL explosion step 5, KL=69.5B\\n  - exp_id: mvp2_grpo_flatnli\\n    role: evidence\\n    result: KL explosion step 5, KL=50.8B\\n  depends_on:\\n  - D007\\n- id: D009\\n  date: 2026-05-14 12:12 UTC\\n  summary: CED r4 采用保守配置：grad_accum=16 + lr=5e-6 + kl_coef=0.5 + warmup 200步，解决 r3\\n    单卡 batch=1 + 高 lr 导致的 KL 爆炸\\n  rationale: r3 根因明确：单卡无 grad_accum 导致 effective batch=1，梯度噪声极高，5 步内 KL 爆炸至 4.4M。r1-r3\\n    三次失败模式不同（mode collapse / OOM / KL explosion），说明 CED reward 本身不是问题，是训练超参不稳定。r4\\n    同时修复 3 个因素：(1) grad_accum=16 使 effective batch=16; (2) lr 从 5e-5 降至 5e-6; (3)\\n    kl_coef 从 0.05 升至 0.5 加强偏离惩罚; (4) 加 200 步 warmup 稳定初始阶段。需先拿到 extract 和 flatnli\\n    r1 结果作为对照基线。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r3\\n    role: evidence\\n    result: failed - KL explosion at step 5, batch=1 root cause\\n  - exp_id: mvp2_grpo_ced_r4\\n    role: target\\n    result: pending approval\\n  depends_on: []\\n- id: D010\\n  date: 2026-05-14 12:32 UTC\\n  summary: 选择 Option A：保留 kl_coef=0.0 实验进程，修复 registry 状态从 killed → RUNNING；D009 的\\n    kl_coef=0.5 正式作废\\n  rationale: Reviewer critical 报告 registry-reality 不一致。3 个实验实际在跑（kl_coef=0.0, grad_acc=16）但\\n    registry 标记 killed。配置本身正确——D008 已证明 kl_coef>0 在 QLoRA 4-bit 下不稳定（r1 kl_coef=0\\n    稳定 80 步 vs 所有 kl_coef>0 爆炸）。D009 提出的 kl_coef=0.5 会放大 QLoRA 量化噪声导致的 KL 计算失真，Reviewer\\n    warning 合理，该指令作废。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r4\\n    role: target\\n    result: running with kl_coef=0.0, registry fix needed\\n  - exp_id: mvp2_grpo_extract_r2\\n    role: target\\n    result: running with kl_coef=0.0, registry fix needed\\n  - exp_id: mvp2_grpo_flatnli_r2\\n    role: target\\n    result: running with kl_coef=0.0, registry fix needed\\n  depends_on:\\n  - D008\\n  - D009\\n- id: D011\\n  date: 2026-05-14 13:30 UTC\\n  summary: 采纳 Reviewer 评估框架审查：精确化 pass criteria、补充 extraction-only vs SFT 对比、要求多 checkpoint\\n    eval + 统一 eval 脚本\\n  rationale: Reviewer 指出 4 个 warning：(1) 缺 extraction-only vs SFT 对比——回答 GRPO 本身是否有效；(2)\\n    kl_coef=0 必须 eval 多 checkpoint 避免 collapse 后只看末尾；(3) pass criteria 需精确化基准；(4)\\n    eval 代码必须统一。全部采纳，已更新 ROADMAP 和指令 Agent。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r5\\n    role: target\\n  - exp_id: mvp2_grpo_extract_r3\\n    role: target\\n  - exp_id: mvp2_grpo_flatnli_r3\\n    role: target\\n  - exp_id: mvp2_sft_eval_r2\\n    role: baseline\\n  depends_on:\\n  - D010\\n- id: D012\\n  date: 2026-05-14 14:54 UTC\\n  summary: 调整 MVP-2 pass criteria：取消绝对 F1>45 门槛，改为相对标准；EDCR 升为主指标\\n  rationale: SFT baseline F1=40.57%（37% 输出截断于 1024 tokens），绝对门槛 F1>45 已不现实。截断影响所有模型相同，相对对比仍有效。Evi-F1=79.79%\\n    设了高 baseline，但 EDCR=71.18% 说明模型\\\"spray-and-pray\\\"大量引用 distractor——CED 的核心攻击目标。调整后\\n    pass criteria：(1) CED_Evi-F1 ≥ SFT_Evi-F1（方向正确）；(2) CED_F1 ≥ max(extract, SFT)\\n    - 5pp（不退化）；(3) CED_EDCR 显著低于 SFT_EDCR（核心判据）；(4) CED > flat-NLI 在 Evi-F1 或 EDCR\\n    上方向正确。绝对指标留到 post-MVP 增大 max_new_tokens 后重评。\\n  related_experiments:\\n  - exp_id: mvp2_sft_eval_r2\\n    role: baseline\\n    result: F1=40.57%, Evi-F1=79.79%, EDCR=71.18%\\n  depends_on:\\n  - D011\\n- id: D013\\n  date: 2026-05-14 14:54 UTC\\n  summary: MVP-2 pass criteria 调整：取消绝对 F1>45 门槛，改为相对对比；EDCR 升为核心判定指标\\n  rationale: SFT baseline F1=40.57%（37% 输出被 1024 token 截断导致），已低于原定 F1>45 门槛。但截断对所有模型等效影响，相对对比仍然公平。调整后\\n    pass criteria：(1) 核心不变：CED_Evi-F1 − SFT_Evi-F1 ≥ 2pp；(2) F1 改为相对：CED_F1 ≥ SFT_F1\\n    − 5pp（即 ≥35.57）；(3) 新增 EDCR 核心判定：CED_EDCR 显著低于 SFT_EDCR（71.18%），降幅 ≥10pp 视为强证据；(4)\\n    保持 CED > flat-NLI 方向。SFT EDCR=71% 说明 SFT 模型大量引用 entity-sharing distractors，正是\\n    CED 设计目标的攻击面。即使 Evi-F1 提升不足 2pp，EDCR 大幅下降也足以支撑 Claim 2。\\n  related_experiments:\\n  - exp_id: mvp2_sft_eval_r2\\n    role: baseline\\n    result: F1=40.57%, Evi-F1=79.79%, EDCR=71.18%\\n  depends_on:\\n  - D011\\n- id: D014\\n  date: 2026-05-14 14:58 UTC\\n  summary: CED r5 mode collapse 确认 kill；CED reward 必须加 F1 门控防止短输出 hack；暂停 ced_kl001\\n  rationale: CED r5 在 65% 进度完全 collapse：completion 固定 34 tokens，f1_reward=0，ced_reward≈0.99，entropy≈0。模型发现极短输出不引用\\n    distractor 即可获得近完美 CED 分——CED 自身被 reward hack。根因：CED reward 不依赖抽取质量，模型可在 F1=0\\n    时仍获高 CED reward。修复方案：F1 门控——仅在 completion 包含 ≥1 个 predicted triple 时计算 CED reward，否则\\n    CED=0。这确保 evidence quality 的评估以有效抽取为前提。ced_kl001 使用同样有缺陷的 reward 设计，必须暂停，等修复后再启动。extract_r3\\n    部分 collapse 但仍有 F1 信号，继续观察。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r5\\n    role: failed\\n    result: 'mode collapse: f1=0, ced≈0.99, 34-token fixed output'\\n  - exp_id: mvp2_grpo_extract_r3\\n    role: monitoring\\n    result: 'partial collapse: f1=0.2-0.34, 43-50 tokens, trending down'\\n  - exp_id: mvp2_grpo_flatnli_r3\\n    role: healthy\\n    result: 'healthy: entropy=0.087, grad_norm=0.398, 11% progress'\\n  depends_on:\\n  - D013\\n- id: D015\\n  date: 2026-05-14 14:58 UTC\\n  summary: ced_r5 mode collapse 保留跑完取分析价值；flatnli_r3 kill 并修复 NLI device 后重启\\n  rationale: ced_r5 在 63% 进度时 f1_reward=0 + entropy≈0，已 mode collapse。保留跑完因为：(1) negative\\n    result 证明纯 CED reward 导致 collapse，支撑 reward balance 的 ablation story；(2) 早期 checkpoint\\n    可能有 f1_reward 正常的版本可用。flatnli_r3 因 NLI 推理在 CPU 上运行导致 10x 减速（124s/it vs 12s/it），预计\\n    20h+。RTX 5090 32GB 有足够余量放 DeBERTa-v3-base (~400MB)，kill 后修复 device 配置重启可将时间降至\\n    2-3h。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r5\\n    role: subject\\n    result: f1_reward=0, mode collapse at 63%\\n  - exp_id: mvp2_grpo_flatnli_r3\\n    role: subject\\n    result: NLI on CPU, 10x slowdown, killed for restart\\n  depends_on:\\n  - D011\\n- id: D016\\n  date: 2026-05-14 15:00 UTC\\n  summary: Kill ced_r5 (total collapse)，ced_kl001 移到 cuda:0 立即启动\\n  rationale: ced_r5 step 250+ f1_reward=0、completion 坍缩到 34 tokens、save_total_limit=5\\n    已覆盖所有正常 checkpoint。继续跑无任何回收价值。Kill 后释放 cuda:0 给 ced_kl001（kl_coef=0.01），不再等 cuda:1。ced_kl001\\n    现在是 MVP-2 最关键实验——验证 CED+KL约束能否避免 reward hacking。extract_r3 和 flatnli_r3 保持 kl=0\\n    继续跑，作为对照：若它们没 collapse，说明问题是 CED reward 特异的；若也 collapse，说明 kl=0 通病。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_r5\\n    role: failed\\n    result: total mode collapse, killed\\n  - exp_id: mvp2_grpo_ced_kl001\\n    role: replacement\\n    result: moved to cuda:0, critical experiment\\n  depends_on:\\n  - D015\\n- id: D017\\n  date: 2026-05-14 15:01 UTC\\n  summary: Kill ced_r5 + extract_r3 (kl_coef=0 collapse/stall), 部署 kl_coef=0.01 修正实验\\n  rationale: 3路GRPO健康检查：ced_r5完全mode collapse(entropy=0.0005, F1=0, grad_norm=0)，extract_r3训练停滞(grad_norm=0,\\n    F1=0.20低于SFT baseline 0.4057)。共同根因kl_coef=0导致策略无约束偏移。D008显示kl_coef=0.05会KL爆炸，选择0.01作为中间值（5x低于爆炸阈值）。flatnli_r3保留作为kl_coef=0对照组继续观察。\\n  related_experiments:\\n  - exp_id: ced_r5\\n    role: failed\\n    result: mode collapse, entropy=0.0005, F1=0\\n  - exp_id: extract_r3\\n    role: failed\\n    result: stalled, grad_norm=0, F1=0.20\\n  - exp_id: flatnli_r3\\n    role: control\\n    result: healthy at 10.7%, continue as kl_coef=0 control\\n  - exp_id: D008\\n    role: reference\\n    result: kl_coef=0.05 caused KL explosion\\n  depends_on: []\\n- id: D018\\n  date: 2026-05-14 15:04 UTC\\n  summary: flatnli_r3 紧急修复 reward_device cpu→cuda，extract_r3 改为跑完再替换\\n  rationale: Reviewer critical 发现 D015 未执行：flatnli_r3 仍以 --reward_device cpu 运行，step_time\\n    123s/step（GPU 后应 12-15s/step），cuda:3 被占用但 90% 时间等 CPU。修复后从 ~23h 降至 ~2-3h，是当前最高\\n    ROI 操作。extract_r3 已 68%（~50min 完成），改为跑完后再部署 extract_kl001，避免浪费已投入的 2.5h。ced_r5\\n    维持 kill（3.3h GPU 时间用于 ced_kl001 更有价值）。\\n  related_experiments:\\n  - exp_id: flatnli_r3\\n    role: fix\\n    result: reward_device cpu→cuda, from checkpoint-80 resume\\n  - exp_id: extract_r3\\n    role: revised\\n    result: let finish (~50min), then replace with extract_kl001\\n  - exp_id: ced_r5\\n    role: kill\\n    result: maintain kill decision, replace with ced_kl001\\n  depends_on:\\n  - D015\\n  - D017\\n- id: D019\\n  date: 2026-05-14 15:05 UTC\\n  summary: 修正 D017：extract_r3 改为跑完再释放，flatnli_r3 紧急补执行 D015（修复 NLI device 重启）\\n  rationale: Reviewer 审查发现：(1) D015 未执行——flatnli_r3 仍用 CPU NLI，step_time 120s vs GPU\\n    应 12-15s，23h→2-3h 的 10x 效率差，cuda:3 90% 时间在等 CPU。(2) extract_r3 只剩 ~50min，跑完可取早期\\n    checkpoint（collapse 前 step 20-100 可能比 last 好），不值得 kill 浪费已投入的 2.5h。修正后：cuda:0\\n    立即释放给 ced_kl001，cuda:2 等 50min 后给 extract_kl001，cuda:3 kill+修复 NLI device 后从 ckpt-80\\n    重启。\\n  related_experiments:\\n  - exp_id: flatnli_r3\\n    role: fix\\n    result: D015 未执行，NLI 在 CPU 导致 10x 低效，需 kill+修复+重启\\n  - exp_id: extract_r3\\n    role: revised\\n    result: 改为跑完（~50min），eval 早期 checkpoint\\n  - exp_id: ced_r5\\n    role: kill\\n    result: 仍立即 kill，与 D017 一致\\n  depends_on:\\n  - D017\\n  - D015\\n- id: D020\\n  date: 2026-05-14 15:15 UTC\\n  summary: ced_kl001 启动前必须先修复 CED reward F1 门控（D014 未实现）；kl_coef=0.01 实验改为 100 步探测性运行\\n  rationale: Reviewer 代码核查确认 D014 的 F1 门控从未实现：ced_reward.py 对 0-triple 短输出仍给近完美分(0.99)。ced_r5\\n    的 collapse 根因是双重的——kl_coef=0 导致策略自由偏移 + CED reward 对短输出的 hack。仅修 kl_coef 不解决 reward\\n    设计缺陷，ced_kl001 会重复失败。同时 kl_coef=0.01+QLoRA 的兼容性未验证（D008 证明 0.05 爆炸），先做 100 步探测降低风险。\\n  related_experiments:\\n  - exp_id: ced_r5\\n    role: evidence\\n    result: 34-token 短输出 → CED≈0.99 → reward hack → collapse\\n  - exp_id: ced_kl001\\n    role: blocked\\n    result: 等 CED reward 修复后才能启动\\n  - exp_id: D008\\n    role: reference\\n    result: kl_coef=0.05+QLoRA KL 爆炸\\n  depends_on:\\n  - D014\\n  - D017\\n  - D019\\n- id: D021\\n  date: 2026-05-14 17:20 UTC\\n  summary: Kill flatnli_r5（从已 hacked checkpoint 恢复无效），启动 flatnli_r6 从 SFT 全新训练 D020\\n    配置\\n  rationale: Reviewer 独立审查发现 flatnli_r3 checkpoint-100 已深陷 NLI reward hacking（f1=0.025,\\n    flat_nli=0.911）。从该 checkpoint 恢复加 kl_coef=0.01 后 KL=0.46（远高于从 SFT 新训的 ced_kl001_r4\\n    的 0.098），frac_zero_std 升至 0.8-0.9，grad_norm 近零——训练冻结。教训：从 kl=0 已漂移 checkpoint\\n    恢复并加 kl>0 不可行，必须从 SFT 全新开始。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_flatnli_r5\\n    role: 被 kill\\n    result: negative\\n  - exp_id: mvp2_grpo_flatnli_r3\\n    role: 提供了已 hacked 的 checkpoint\\n    result: negative\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: 健康参照（从 SFT 新训）\\n    result: running\\n  depends_on:\\n  - D020\\n- id: D022\\n  date: 2026-05-14 17:40 UTC\\n  summary: Kill extract_r4 (f1_reward=0 at ckpt-30, mode collapse confirmed); cuda:2\\n    转 ced_kl001_r4 多 checkpoint eval\\n  rationale: extract_r4 (extraction-only, kl_coef=0.01+gen=8) 在 step 10 后 f1_reward\\n    归零、frac_zero_std≥0.8 停滞，checkpoint-30 无恢复信号。同配置的 ced_kl001_r4 在 step 20 f1_reward=0.082\\n    持续上升——直接证明 CED reward 通道是驱动学习的关键因素。这一负面结果本身是强证据，不再尝试 extract_r5。cuda:2 空闲，派去 eval\\n    ced_kl001_r4 中间 checkpoint，提前获取多 checkpoint 评估数据。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_extract_r4\\n    role: killed\\n    result: f1_reward=0 at ckpt-30, mode collapse\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: contrast\\n    result: f1_reward=0.082 at step 20, healthy\\n  depends_on:\\n  - D020\\n- id: D023\\n  date: 2026-05-14 17:40 UTC\\n  summary: 'Kill extract_r4 (mode collapse confirmed); ablation 结论: CED reward 是 GRPO\\n    训练必需的 dense signal，extraction-only reward 太稀疏无法驱动学习'\\n  rationale: 'extract_r4 checkpoint-30: f1_reward 连续 25 步为 0，frac_zero_std 升至 0.9，grad_norm\\n    在 0.005-0.012 震荡。对比 ced_kl001_r4 同期（f1_reward=0.082 持续上升，frac_zero_std=0.4 持续下降），唯一差异是\\n    reward type。结论: Stage 1 (extract-only) 在 D020 配置下无法维持 GRPO 探索多样性，CED 提供的 dense\\n    reward signal 是训练成功的必要条件。这是论文的关键 ablation evidence。cuda:2 释放，分配给 SFT eval baseline。'\\n  related_experiments:\\n  - exp_id: mvp2_grpo_extract_r4\\n    role: failed_ablation\\n    result: mode collapse — f1_reward=0 for 25 steps\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: positive_control\\n    result: f1_reward=0.082 at step 20, healthy training\\n  depends_on:\\n  - D020\\n- id: D024\\n  date: 2026-05-14 18:11 UTC\\n  summary: 'Kill flatnli_r6 (mode collapse step 25); D020 配置下三路 ablation 结论: 仅 CED\\n    reward 存活，extract-only 和 flat-NLI 均 collapse'\\n  rationale: 'flatnli_r6 step 25: frac_zero_std=0.9, f1_reward=0, flat_nli_reward=0,\\n    reward 100% 来自 format。与 extract_r4 collapse 模式一致。三个实验共用 D020 配置（kl=0.01, gen=8），唯一差异是\\n    reward type: extract-only collapse (step 10-30), flat-NLI collapse (step 25),\\n    CED 健康完成 100 步。结论: CED 的对比性 evidence discrimination 提供了 GRPO 所需的 dense gradient\\n    signal，是训练成功的必要条件。这比原设想的\\\"CED 改善 evidence quality\\\"更强——CED 是 GRPO 训练本身能否存活的关键。cuda:3\\n    释放用于加速 eval。'\\n  related_experiments:\\n  - exp_id: mvp2_grpo_flatnli_r6\\n    role: failed_ablation\\n    result: mode collapse step 25, frac_zero_std=0.9\\n  - exp_id: mvp2_grpo_extract_r4\\n    role: failed_ablation\\n    result: mode collapse step 10-30\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: positive_control\\n    result: 100 steps healthy, reward 0.85-1.37\\n  depends_on:\\n  - D023\\n  - D020\\n- id: D025\\n  date: 2026-05-14 18:11 UTC\\n  summary: Kill flatnli_r6 (mode collapse confirmed step 25); D020 配置下三路 ablation\\n    结论：仅 CED reward 存活，extract-only 和 flat-NLI 均 collapse\\n  rationale: 'flatnli_r6 step 25: frac_zero_std=0.9, f1_reward=0, flat_nli_reward=0,\\n    reward 100% 来自 format。与 extract_r4 collapse 模式一致。D020 配置（kl=0.01, gen=8）下三路对比：extract-only\\n    step 30 collapse, flat-NLI step 25 collapse, CED 100 步健康完成。唯一差异是 reward type。结论：CED\\n    的对比性 evidence discrimination 提供了更丰富的梯度信号，是维持 GRPO 探索多样性的必要条件。这是论文最核心的 ablation\\n    evidence — 但需注意区分\\\"CED reward 本身的 anti-collapse 特性\\\"与\\\"stage 3 组合 reward 的其他差异\\\"两个假设。cuda:3\\n    释放后用于 eval 加速。'\\n  related_experiments:\\n  - exp_id: mvp2_grpo_flatnli_r6\\n    role: failed_ablation\\n    result: mode collapse step 25, frac_zero_std=0.9\\n  - exp_id: mvp2_grpo_extract_r4\\n    role: failed_ablation\\n    result: mode collapse step 30, f1_reward=0\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: positive_control\\n    result: 100 steps healthy, reward=0.85-1.37\\n  depends_on:\\n  - D023\\n  - D020\\n- id: D026\\n  date: 2026-05-14 19:37 UTC\\n  summary: MVP-2 ced_kl001_r4 FAIL — lr=5e-5 导致灾难性遗忘+CED recall shortcut 双重问题，启动 P0/P0+P1\\n    并行修复\\n  rationale: 'ckpt-10/50/100 eval 全部远低于 SFT baseline（rel_f1: 0.003→0.156→0.217 vs\\n    SFT 0.4057，evi_f1: 0.720→0.564→0.575 vs SFT 0.7979）。训练 reward 5x 增长但 eval F1 未恢复，确认\\n    reward hacking + 灾难性遗忘双重机制。根因：lr=5e-5 过高 5-10x + CED 对非匹配 triple 无 recall 惩罚。D020\\n    ablation 的 CED 训练稳定性发现仍有效。下一步：P0（lr=5e-6）和 P0+P1（lr=5e-6 + ced_recall_penalty）并行验证。'\\n  related_experiments:\\n  - exp_id: ced_kl001_r4\\n    role: primary\\n    result: training success but eval fail\\n  - exp_id: mvp2_eval_ced_kl001_r4_ckpt10\\n    role: eval\\n    result: f1=0.003\\n  - exp_id: mvp2_eval_ced_kl001_r4_step50\\n    role: eval\\n    result: f1=0.156\\n  - exp_id: mvp2_eval_ced_kl001_r4_step100\\n    role: eval\\n    result: f1=0.217\\n  depends_on:\\n  - D024\\n  - D025\\n  - D029\\n- id: D027\\n  date: 2026-05-14 19:37 UTC\\n  summary: MVP-2 ced_kl001_r4 FAIL — lr=5e-5 过高导致灾难性遗忘+CED recall shortcut 叠加 reward\\n    hacking\\n  rationale: ckpt-10/50/100 三点轨迹确认：rel_f1 最高 0.217（SFT 0.4057, pass 0.356, gap -13.9pp），evi_f1\\n    最高 0.575（SFT 0.7979, pass 0.818, gap -24.3pp）。恢复速率递减（40步+15.3pp→50步+6.0pp），外推至\\n    step200 仍远低于 pass。根因：(1) lr=5e-5 是社区推荐的 5-10x，导致 step10 即灾难性遗忘；(2) CED shortcut\\n    使非匹配 triple 退化为 flat NLI，引导模型少预测高 EDCR；(3) train/eval 分布不匹配放大差距。下一步：P0(lr=5e-6)\\n    + P0+P1(lr=5e-6+recall_penalty) 并行。\\n  related_experiments:\\n  - exp_id: ced_kl001_r4\\n    role: primary\\n    result: success(training)/fail(eval)\\n  - exp_id: mvp2_eval_ced_kl001_r4_step100\\n    role: eval\\n    result: rel_f1=0.217,evi_f1=0.575\\n  - exp_id: mvp2_eval_ced_kl001_r4_ckpt50\\n    role: eval\\n    result: rel_f1=0.156,evi_f1=0.564\\n  - exp_id: mvp2_eval_ced_kl001_r4_ckpt10\\n    role: eval\\n    result: rel_f1=0.003,evi_f1=0.720\\n  depends_on:\\n  - D024\\n  - D025\\n- id: D028\\n  date: 2026-05-14 21:36 UTC\\n  summary: Kill rp_r2 (P0+P1) — loss 指数 divergence 不可恢复；cuda:3 转跑 rp_r2 ckpt-20 eval\\n    关闭对比线\\n  rationale: rp_r2 loss 从 step 10-20 持续指数增长 (908→24650→1.34e7)，根因是 recall_penalty\\n    5-10x 梯度 + kl_coef=0.01 形成正反馈循环。与 P0 的瞬时 KL spike 不同，这是持续 divergence。Kill 后 cuda:3\\n    跑 rp_r2 ckpt-20 eval（成本低，~2h）拿到数据关闭 P0+P1 对比线。不启动新训练——MVP 阶段 P0 单独通过即可。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_lr5e6_rp_r2\\n    role: killed\\n    result: loss exponential divergence\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: primary\\n    result: P0 continues as sole MVP path\\n  depends_on:\\n  - D027\\n- id: D029\\n  date: 2026-05-14 21:44 UTC\\n  summary: 修正 rp_r2 终止理由：从\\\"loss 持续发散\\\"改为\\\"recall penalty 过度抑制 CED 信号\\\"\\n  rationale: Reviewer 独立核实 trainer_state.json 发现 rp_r2 step 30-40 的 loss/KL 已完全恢复正常（loss=0.038,\\n    KL=0.005），与 P0 的瞬态发散→恢复模式一致，不是持续发散。真正的问题是 ced_reward=0.005 远低于 P0 的 0.079，说明 recall\\n    penalty 过于严苛压制了 CED 学习信号。kill 决策本身不撤回，但论文引用此 negative result 时应表述为\\\"recall penalty\\n    过度抑制 CED 信号\\\"而非\\\"训练发散\\\"。\\n  related_experiments:\\n  - exp_id: rp_r2\\n    role: subject\\n    result: killed-但理由修正\\n  - exp_id: mvp2_train_lr5e6_r1\\n    role: reference\\n    result: 同样出现瞬态发散后恢复\\n  depends_on: []\\n- id: D030\\n  date: 2026-05-14 22:16 UTC\\n  summary: P0 ckpt-20 eval FAIL (rel_f1=0.0077); lr=5e-6 未能防止早期遗忘，与 lr=5e-5 相同模式；扩展至全\\n    checkpoint 轨迹评估\\n  rationale: lr=5e-5 和 lr=5e-6 在 step-20 均出现灾难性遗忘（rel_f1 < 0.01），说明问题不是单纯 LR 过高——GRPO+QLoRA\\n    在结构化生成任务上的前 20 步 inherently 不稳定（60% 输出截断，field compliance 仅 39.9%）。需要看完整 recovery\\n    trajectory（ckpt-40/60/80）才能判断是否\\\"先崩后恢复\\\"。ced_kl001_r4 (lr=5e-5) step-90 最高 0.211\\n    仍低于阈值，lr=5e-6 能否突破 0.30 存疑。同时开始考虑 GRPO 替代方案（DPO/rejection sampling）作为 contingency。\\n  related_experiments:\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt20\\n    role: primary\\n    result: 'FAIL: rel_f1=0.0077, 39x below threshold'\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: training\\n    result: step ~68, f1_reward recovering at step 45\\n  depends_on: []\\n- id: D031\\n  date: 2026-05-14 23:10 UTC\\n  summary: GRPO+QLoRA P0 方向判死：ckpt-40 rel_f1=0.0071（比 ckpt-20 更差），两个 LR 均远劣于 SFT baseline。Pivot\\n    到离线 RL（Rejection Sampling FT → DPO）\\n  rationale: ckpt-20→ckpt-40 轨迹下降（0.0077→0.0071），GRPO 只学会格式/证据引用但完全丧失关系抽取能力。lr=5e-5\\n    最佳 0.211 vs SFT 0.406，lr=5e-6 最佳 0.008。catastrophic forgetting 是 GRPO+QLoRA 在结构化生成任务上的根本性问题，非超参可解。CED\\n    reward signal 本身有效（MVP-1 verified），问题在在线 RL 训练方法论。Pivot 到离线方法：(1) Rejection Sampling\\n    FT 最简单最稳定优先做 (2) DPO+CED scoring 作为并行备选。\\n  related_experiments:\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt40_r2\\n    role: trigger\\n    result: rel_f1=0.0071 FAIL\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt20\\n    role: prior\\n    result: rel_f1=0.0077 FAIL\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: training\\n    result: f1_reward 无学习趋势\\n  - exp_id: ced_kl001_r4\\n    role: prior_attempt\\n    result: best 0.211 at ckpt-90, mode collapse\\n  depends_on:\\n  - D030\\n  - D027\\n- id: D032\\n  date: 2026-05-15 01:03 UTC\\n  summary: 'Kill GRPO 训练 (cuda:0 step 113/200): 轨迹数据已充分，释放 GPU 给 RSFT 管线加速'\\n  rationale: ckpt-80 rel_f1=0.0116 (SFT baseline 的 2.9%)，ckpt-20→80 全线 FAIL。ckpt-100\\n    eval 在跑会给最后一个数据点，但 step 200 无价值。释放 cuda:0 可用于并行 RSFT generate 或后续 scoring/training。\\n  related_experiments:\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: killed\\n    result: trajectory ckpt-20~80 all FAIL, max rel_f1=0.0116\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt80\\n    role: evidence\\n    result: rel_f1=0.0116 negative\\n  depends_on:\\n  - D031\\n- id: D033\\n  date: 2026-05-15 01:22 UTC\\n  summary: D031 最终确认：GRPO+QLoRA 全线 FAIL，lr5e6 全 6 checkpoint rel_f1 < 0.02；negative\\n    result 模式有论文价值（CED↑ + rel_f1 catastrophic forgetting = 在线 RL 无法维持双能力）\\n  rationale: Reviewer 独立核实 lr5e6 全 6 checkpoint：rel_f1 最高仅 0.0138（阈值 0.30），evi_f1\\n    从 0.628 单调升至 0.850（超 SFT 0.798），edcr 稳定 ~0.99（远超 SFT 0.712）。模式：CED reward signal\\n    有效驱动 evidence 质量提升，但在线 RL (GRPO+QLoRA) 导致关系抽取 catastrophic forgetting。此 negative\\n    result 直接支持离线 RL (RSFT/DPO) 路线的必要性，且为论文提供重要论据。\\n  related_experiments:\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt100\\n    role: final_eval\\n    result: FAIL rel_f1=0.0138\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt80\\n    role: trajectory\\n    result: FAIL rel_f1=0.0116\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt60\\n    role: trajectory\\n    result: FAIL rel_f1=0.0093\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt40\\n    role: trajectory\\n    result: FAIL rel_f1=0.0071\\n  - exp_id: mvp2_eval_lr5e6_r1_ckpt20\\n    role: trajectory\\n    result: FAIL rel_f1=0.0077\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: training\\n    result: killed after trajectory data collected\\n  depends_on:\\n  - D031\\n  - D032\\n- id: D034\\n  date: 2026-05-15 01:28 UTC\\n  summary: 'D034: RSFT diversity 危机——diversity=1.0/8 因 temperature 未生效，暂停生成并修复'\\n  rationale: Reviewer critical 发现：(1) rsft_generate.py 传入 temperature=0.7 但被 Qwen3-4B\\n    generation_config.json 自带的 T=0.6/top_k=20 覆盖，transformers 打出 WARNING 但 Agent 未注意；(2)\\n    SFT 后模型分布极度尖锐，T=0.6+top_k=20 几乎等同于 greedy，导致 8 次生成完全相同；(3) 早期 diversity_probe\\n    报告 7/8 是 format 解析 bug 导致的虚假多样性，修复格式后真实 diversity 暴露为 1.0/8。必须 kill 当前进程、修复 temperature\\n    覆盖（显式设 model.generation_config.temperature + top_k=0）、用 3-5 doc 验证后再重启。\\n  related_experiments:\\n  - exp_id: mvp2_rsft_generate\\n    role: affected\\n    result: diversity=1.0/8, 生成数据无法用于 rejection sampling\\n  - exp_id: mvp2_diversity_probe\\n    role: evidence\\n    result: 7/8 是虚假多样性（format bug），实际 5.0/8 且修复后降至 1.0/8\\n  depends_on:\\n  - D033\\n- id: D035\\n  date: 2026-05-15 01:29 UTC\\n  summary: 暂停 RSFT 并行化：Reviewer critical 发现 diversity=1.0/8 是格式修复后的真实值，之前 7/8 为格式不一致假象。高温探针优先。\\n  rationale: diversity_probe 原始数据 (8,6,1) 平均 5.0/8 而非上报的 7；且 probe 时 format_ok 仅 34%，\\\"多样性\\\"来自\\n    JSON key 名变体。生产环境 format_ok=99.8% 后实测 diversity=1.0/8。继续当前配置生成 14h 的数据毫无意义——rejection\\n    sampling 退化为普通 SFT。需先用高温(T=1.0/1.2/1.5)探针验证 diversity 是否可恢复。\\n  related_experiments:\\n  - exp_id: mvp2_diversity_probe\\n    role: evidence\\n    result: 虚报 7/8, 实际 5.0/8, 且为格式假象\\n  - exp_id: mvp2_rsft_generate\\n    role: affected\\n    result: diversity=1.0/8 at T=0.7, 暂不扩展\\n  depends_on:\\n  - D033\\n- id: D036\\n  date: 2026-05-15 01:33 UTC\\n  summary: D034 撤销：diversity crisis 是监控 bug，非生成质量问题，T=0.7 下 diversity 充足(7.11/8)，恢复并行生成\\n  rationale: 独立验证 Worker 分析 cuda:1 已生成的 200 docs：triple-set diversity 7.11/8 (median=8.0)，format\\n    parse rate 90.2%，61.5% 文档 8/8 完全不同。之前监控报告 mean_diversity=1.0/8 为度量代码计算错误。无需执行\\n    D034 的 temperature 修复和高温探针。\\n  related_experiments:\\n  - exp_id: mvp2_rsft_generate\\n    role: trigger\\n    result: diversity monitoring bug identified\\n  depends_on: []\\n- id: D037\\n  date: 2026-05-15 07:46 UTC\\n  summary: 'D037: RSFT 全线 FAIL（rel_f1=0.0483），pivot 到 CED-as-reranker（推理时方案）'\\n  rationale: 'GRPO（D027/D031/D033）和 RSFT 两条训练路线均呈现相同的灾难性遗忘——任何对 SFT checkpoint 的二次微调都摧毁\\n    rel_f1。RSFT r1: rel_f1=0.0483, num_preds=848（SFT baseline: 0.4057, 12234）。跨 seed\\n    方差 <0.04%，非随机。根因假设：LoRA 二次微调的系统性遗忘。Pivot 到 CED-as-reranker：SFT 模型生成 N 候选 → CED\\n    打分 → 选最佳，完全绕过训练问题。'\\n  related_experiments:\\n  - exp_id: mvp2_rsft_train_r1\\n    role: primary\\n    result: 'FAIL: rel_f1=0.0483'\\n  - exp_id: mvp2_rsft_train_r1_s43\\n    role: variance\\n    result: training variance <0.04%\\n  - exp_id: mvp2_rsft_train_r1_s44\\n    role: variance\\n    result: eval pending, same outcome expected\\n  depends_on:\\n  - D033\\n  - D027\\n- id: D038\\n  date: 2026-05-15 09:40 UTC\\n  summary: 'D038: 撤回 D037——RSFT \\\"灾难性失败\\\"实为 eval bug（50-doc pred vs 12275 gold denominator\\n    mismatch），s44 全量 eval 通过 MVP-2（rel_f1=0.4655 +5.98pp, evi_f1=0.8087 +1.08pp）'\\n  rationale: r1 的 rel_f1=0.0483 是评估代码 bug：TaskEvalCallback 在 50 docs 上生成预测但 gold triples\\n    用了全量 dev set 12275 条，recall 被人为压到 ~3.5%。s44 独立全量 eval（985 docs）结果：rel_f1=0.4655（+5.98pp\\n    vs SFT 0.4057），evi_f1=0.8087（+1.08pp vs 0.7979），edcr=0.6350（-7.68pp vs 0.7118）。CED\\n    rejection sampling 首次端到端验证成功。D037 的 reranker pivot 基于错误数据，RSFT 实际有效。\\n  related_experiments:\\n  - exp_id: mvp2_rsft_train_r1_s44\\n    role: primary\\n    result: 'PASS: rel_f1=0.4655, evi_f1=0.8087'\\n  - exp_id: mvp2_rsft_train_r1\\n    role: pending_reeval\\n    result: r1 0.0483 was eval bug, full eval needed\\n  depends_on:\\n  - D037\\n- id: D039\\n  date: 2026-05-15 11:49 UTC\\n  summary: 'D039: RSFT+CED ablation 全部 PASS MVP-2——方法鲁棒，1 epoch 足够，EDCR 局限需论文讨论'\\n  rationale: Reviewer 独立验证 4 组 RSFT 配置（r1 s42/s44, r2a, r2b）全部通过 MVP-2 判据（rel_f1 >\\n    0.4057, evi_f1 > 0.798）。核心发现：(1) RSFT+CED 方法贡献 +4-6pp rel_f1，具体超参影响极小（0.45pp 范围内），方法鲁棒性好；(2)\\n    1 epoch 足够，3 epoch 无显著额外收益；(3) r2b 保守 LoRA scaling+低 lr 略优于 r2a（截断更少、字段完整率更高）；(4)\\n    EDCR 一致偏高 63-66%，CED reward 对 rel_f1 提升明显但对证据精确度提升有限，需论文坦诚讨论。两个 warning（ablation\\n    变量混淆、EDCR 高）均不阻塞 MVP，clean ablation 留研究阶段补。等 s43_r2 第三种子确认后调 complete_mvp()。\\n  related_experiments:\\n  - exp_id: mvp2_eval_rsft_r2a\\n    role: ablation\\n    result: rel_f1=0.4494, evi_f1=0.8108, EDCR=0.6641, PASS\\n  - exp_id: mvp2_eval_rsft_r2b\\n    role: ablation\\n    result: rel_f1=0.4493, evi_f1=0.8128, EDCR=0.6609, 截断179/字段完整率81.8%, PASS\\n  - exp_id: mvp2_eval_rsft_r1\\n    role: baseline_rsft\\n    result: rel_f1=0.4449, evi_f1=0.8187, EDCR=0.6565, PASS\\n  - exp_id: mvp2_rsft_train_r1_s44\\n    role: seed_variance\\n    result: rel_f1=0.4655, evi_f1=0.8087, PASS\\n  depends_on:\\n  - D038\\n- id: D040\\n  date: 2026-05-15 12:03 UTC\\n  summary: 'D040: MVP 正式通过 → 进入 Research 阶段。paper_framing.md 定稿（RSFT+CED 路线，4 Claims），experiment_plan.yaml\\n    建立（10 研究实验），dream_simulate(full) 已启动'\\n  rationale: D039 已判定 MVP-2 全部 PASS（4/4 configs），但 complete_mvp() 未被调用。用户催促后补调。Post-MVP\\n    kickoff 按 skill 流程执行：(1) paper_framing.md 从 Pre-MVP draft 更新为 Post-MVP 定稿版——方法从\\n    GRPO 转为 RSFT+CED，新增 Claim 3（在线 RL catastrophic forgetting 分析）和 RC6/RC7；(2) experiment_plan.yaml\\n    新建，10 个研究实验分 P0/P1/P2；(3) dream_simulate(full) 已启动（dream_20260515T120227），等回调后再批准\\n    P0 实验。投稿目标调整为 ARR July → EMNLP 2026 Main（ARR May 25 仅作 stretch goal）。\\n  related_experiments:\\n  - exp_id: mvp2_eval_rsft_r2a\\n    role: evidence\\n    result: rel_f1=0.4494 PASS\\n  - exp_id: mvp2_eval_rsft_r2b\\n    role: evidence\\n    result: rel_f1=0.4493 PASS\\n  - exp_id: mvp2_eval_rsft_r1\\n    role: evidence\\n    result: rel_f1=0.4449 PASS\\n  - exp_id: mvp2_rsft_train_r1_s44\\n    role: evidence\\n    result: rel_f1=0.4655 PASS\\n  depends_on:\\n  - D039\\n- id: D041\\n  date: 2026-05-15 13:15 UTC\\n  summary: 'D041: Evi-F1 评测协议不一致确认——我们的\\\"条件 Evi-F1\\\"(仅 TP triples)与 DREEAM\\\"联合 Evi-F1\\\"(含\\n    FP/FN 惩罚)不可比，publishability threshold 暂冻结等对齐后重评'\\n  rationale: Agent 调查确认：我们的 compute_evi_f1() 在 FP triple 时 continue 跳过（precision 分母只算\\n    TP evidence），recall 分母也只算 matched gold triples。DREEAM 的 official_evaluate() 将\\n    FP/FN 全部计入分母。在 rel_recall ≈ 55% 时，分母差约 1.8x，解释了 82% vs 57% 的差距。已派 Agent 实现 DREEAM\\n    协议对齐函数并重新评估全部实验。在对齐数字出来前，paper_framing.md 的 publishability threshold（Evi-F1 >\\n    57.34）暂冻结。条件 Evi-F1 仍作为辅助指标保留（衡量\\\"关系对了时 evidence 选得好不好\\\"）。\\n  related_experiments:\\n  - exp_id: mvp2_sft_eval_r2\\n    role: affected\\n    result: evi_f1_conditional=0.7979, joint TBD\\n  - exp_id: mvp2_eval_rsft_r1\\n    role: affected\\n    result: evi_f1_conditional=0.8187, joint TBD\\n  - exp_id: mvp2_eval_rsft_r2a\\n    role: affected\\n    result: evi_f1_conditional=0.8108, joint TBD\\n  - exp_id: mvp2_eval_rsft_r2b\\n    role: affected\\n    result: evi_f1_conditional=0.8128, joint TBD\\n  depends_on:\\n  - D039\\n  - D040\\n- id: D042\\n  date: 2026-05-15 13:16 UTC\\n  summary: 'D041: Evi-F1 评测协议与 DREEAM 不一致——我们的 conditional Evi-F1 跳过 FP/FN triples，比\\n    DREEAM 的 joint Evi-F1 宽松得多。必须实现 DREEAM 协议对齐后重算所有实验。Publishability threshold 待重算后修订'\\n  rationale: Agent 调查确认：我们的 compute_evi_f1() 在 FP triple 时 continue 跳过，precision 分母只算\\n    TP；recall 分母也只算已匹配 gold。DREEAM 的 official_evaluate() 把 FP/FN 全部计入分母。关系 recall\\n    ~55% 时，分母差异完全解释 82% vs 57% 的差距。对齐方案：加 FP evidence 到 precision 分母 + 遍历全部 gold triple\\n    evidence 到 recall 分母。论文需要报告 DREEAM 协议数字（与文献可比），条件 Evi-F1 可作为辅助指标（衡量\\\"关系正确时 evidence\\n    选择质量\\\"）。\\n  related_experiments:\\n  - exp_id: mvp2_sft_eval_r2\\n    role: affected\\n    result: conditional evi_f1=0.7979, dreeam evi_f1 待重算\\n  - exp_id: mvp2_eval_rsft_r1\\n    role: affected\\n    result: conditional evi_f1=0.8187, dreeam evi_f1 待重算\\n  - exp_id: mvp2_eval_rsft_r2a\\n    role: affected\\n    result: conditional evi_f1=0.8108, dreeam evi_f1 待重算\\n  - exp_id: mvp2_eval_rsft_r2b\\n    role: affected\\n    result: conditional evi_f1=0.8128, dreeam evi_f1 待重算\\n  depends_on:\\n  - D039\\n  - D040\\n- id: D043\\n  date: 2026-05-15 13:20 UTC\\n  summary: 'D042: Dream 审稿分析——best=2.5/median=3.0/worst=2.5（评分倒挂）。5 个确认行动项（narrow\\n    Claim 3 scope、加 GRPO G=8、修 Evi-F1 协议、CED contingency plan、加 DPO baseline），4 个观察项。Framing\\n    和 plan 已更新，re-dream 启动'\\n  rationale: 'Dream 三档审稿分析（dream-report-action 协议）：\\n\\n\\n    **三档一致的结构性问题（确认行动项）**：\\n\\n    1. CED vs flat-NLI 可能不显著 → 加 contingency plan，如 p>0.05 则 CED 降级\\n\\n    2. Title/claims overclaim \\\"online RL\\\" → Claim 3 限定为 \\\"GRPO+QLoRA\\\"\\n\\n    3. GRPO G=4 太小 → 加 plan_011 (G=8 实验，P0)\\n\\n    4. Cross-protocol Evi-F1 → 已在修复中 (D041)\\n\\n    5. 缺中间 baseline → 加 plan_012 (DPO, P1)\\n\\n\\n    **两档一致的观察项**：\\n\\n    - EDCR 需人工验证 [M][W] → plan_013\\n\\n    - Dev→test 退化 [M][W] → 等 plan_002 真实数据\\n\\n    - Number discrepancies [B][M] → Dream artifact（虚构数据），真实论文不会有此问题\\n\\n\\n    **评分倒挂说明**：best(2.5) < median(3.0) 因 best 版本膨胀数字被审稿人识破——说明诚实报告比膨胀结果更重要。\\n\\n\\n    **判断**：framing 和 plan 已按确认行动项修改，需 re-dream 验证后才能批准 P0 实验。'\\n  related_experiments: []\\n  depends_on:\\n  - D040\\n  - D041\\n- id: D044\\n  date: 2026-05-15 13:24 UTC\\n  summary: Dream v1 分析完成：reframe paper_framing.md，CED 降级，claims 重构，新增 3 个实验\\n  rationale: Dream v1 (best=2.5, median=3.0, worst=2.5) 三档一致指出：(1) CED vs flat-NLI\\n    不显著 p>0.05 → CED 从核心贡献降级为 one possible scoring function；(2) \\\"online RL fails\\\"\\n    标题过度声称 → 收窄到 \\\"GRPO fails for DocRE\\\"；(3) GRPO G=4 太小 → 新增 G=8 实验(plan_011)；(4)\\n    缺 DPO baseline → 新增 plan_012；(5) EDCR 缺人工验证 → 新增 plan_013。Claims 重构为 C1=evidence-grounded\\n    DocRE 可行性, C2=GRPO decoupling 发现, C3=NLI-based RSFT ablation, C4=EDCR 诊断工具。需 re-dream\\n    验证 reframe 效果。\\n  related_experiments:\\n  - exp_id: plan_011\\n    role: new_from_dream\\n    result: GRPO G=8 实验，排除 G=4 confound\\n  - exp_id: plan_012\\n    role: new_from_dream\\n    result: DPO+CED，online-offline 中间 baseline\\n  - exp_id: plan_013\\n    role: new_from_dream\\n    result: EDCR 100例人工标注验证\\n  depends_on:\\n  - D041\\n- id: D045\\n  date: 2026-05-15 13:41 UTC\\n  summary: 'D045: DPO 升级 P0 + GRPO G=8 排为第一优先；DPO 定位修正为 offline preference optimization'\\n  rationale: Reviewer 指出：(1) DPO 是纯 offline 方法，不是 online/offline 中间点——论文中错误定位会被审稿人攻击。已修正\\n    paper_framing.md。(2) DPO 结果直接决定 C2 叙事走向（on-policy 特有 vs 更 general 的现象），对 paper\\n    scope 有重大影响，升级 P0。(3) C2 对 GRPO G=8 单点依赖是最大风险，G=8 必须是 re-dream 后第一个启动的实验。\\n  related_experiments:\\n  - exp_id: plan_012\\n    role: 升级 P0\\n  - exp_id: plan_011\\n    role: 第一优先 P0\\n  depends_on:\\n  - D044\\n- id: D046\\n  date: 2026-05-15 13:42 UTC\\n  summary: 'D045: DPO 从 P1 升 P0 + GRPO G=8 定为 re-dream 后首批实验 + topk3 双变体设计'\\n  rationale: Reviewer 路线图审查指出：(1) DPO 结果直接决定 C2 decoupling 叙事——若 DPO 也出现 decoupling\\n    则现象更 general，若不出现则确认 on-policy 特有，两种结果都对论文有重大影响，升 P0；(2) C2 publishability 必要条件依赖\\n    GRPO G=8 复现 decoupling，是最高风险实验，必须首批启动；(3) topk3 数据含 CED=0 样本会稀释信号，改为双变体并行（全量 vs\\n    过滤 CED=0）以区分数据量效应和信号稀释。同时修正 paper_framing.md 中 DPO 定位错误（纯 offline 方法，非 online/offline\\n    中间点）。\\n  related_experiments:\\n  - exp_id: plan_012\\n    role: DPO+CED 升 P0\\n  - exp_id: plan_011\\n    role: GRPO G=8 首批 P0\\n  - exp_id: plan_008\\n    role: topk3 双变体设计\\n  depends_on:\\n  - D044\\n- id: D047\\n  date: 2026-05-15 14:37 UTC\\n  summary: Re-dream v2 分析：best=3.0/median=2.5/worst=2.5，未达标。识别 7 个三档一致结构性问题，plan_011\\n    bf16 GRPO 是关键突破口，新增 SFT-without-evidence ablation 实验\\n  rationale: 'Dream v2 (dream_20260515T132059) reframe 后评分：best=3.0(Findings), median=2.5(Leaning\\n    Reject), worst=2.5(Leaning Reject)。目标 best≥3.5/median≥3.0 未达标，但比 v1(best=2.5/median=3.0/worst=2.5)的\\n    best 提升了 0.5。\\n\\n\\n    **三档一致结构性问题（确认行动项）**：\\n\\n    1. CED 非显著 vs flat-NLI + title-contribution mismatch → 必须更强地 reframe，CED 降为 one\\n    scoring option\\n\\n    2. QLoRA 混淆 GRPO claim → plan_011 (bf16 LoRA) 直接解决！若 decoupling 在 bf16 下复现 → 消除最大弱点\\n\\n    3. Related work 严重缺失：R1-RE(GRPO sentence-level RE 成功)、RelPrior/Ru-LLM/AutoRE/GLiDRE、DAPO/Dr.GRPO、INFUSE/TRUE\\n\\n    4. DPO 实验细节缺失 → 必须补全训练超参\\n\\n    5. 缺 GRPO forgetting dynamics figure → plan_009 升 P0\\n\\n    6. Single-seed test → 多 seed mean±std\\n\\n    7. 缺 SFT-without-evidence ablation → 新增实验 plan_014\\n\\n\\n    **观察项（等真实数据验证）**：\\n\\n    - Dev-to-test degradation 6x ratio\\n\\n    - CED gold evidence dependency 讨论\\n\\n    - Reward hacking lineage 扩写\\n\\n\\n    **关键路径**：plan_011 eval → 若 decoupling 持续 → C2 claim 升级为 \\\"RL vs structured IE\\\"（去\\n    QLoRA qualifier）→ 论文最大弱点消除 → re-dream 预期 best≥3.5'\\n  related_experiments:\\n  - exp_id: plan_011\\n    role: critical_path\\n    result: training_done_eval_pending\\n  - exp_id: plan_009\\n    role: upgrade_to_P0\\n    result: planned\\n  - exp_id: plan_001\\n    role: flat-NLI_ablation\\n    result: scoring_done\\n  depends_on:\\n  - D044\\n  - D046\\n- id: D048\\n  date: 2026-05-15 14:39 UTC\\n  summary: Dream v2 分析：best=3.0/median=2.5/worst=2.5，未达标。三档一致指出5个结构性问题+2个新实验需求。plan_011\\n    bf16 是升Main最大杠杆。\\n  rationale: Re-dream (dream_20260515T132059) full review 结果：reframe 后 best 从 2.5→3.0\\n    有改善，但 median 从 3.0→2.5 反降。三档一致的结构性问题：(1) CED vs flat-NLI 非显著=标题贡献不匹配，(2) GRPO\\n    QLoRA confound 需 non-QLoRA 控制，(3) related work 大缺（R1-RE/LLM DocRE/GRPO stability），(4)\\n    缺 forgetting dynamics figure，(5) DPO 细节不足。新实验需求：SFT-without-evidence ablation（量化\\n    evidence 生成代价）+ post-hoc retrieval baseline。plan_011 bf16 直接回答 QLoRA confound——如果\\n    decoupling 持续则 C2 从 QLoRA-scoped 升级为 structural claim，这是 Findings→Main 的最关键杠杆。行动：(A)\\n    plan_011 eval 最高优先，(B) 新增 SFT-no-evidence 实验到 plan，(C) plan_009 forgetting figure\\n    并行推进，(D) plan_012 DPO 代码准备立即启动。\\n  related_experiments:\\n  - exp_id: plan_011_grpo_g8_bf16\\n    role: key_experiment\\n    result: ANALYZING\\n  - exp_id: plan_001\\n    role: pending\\n    result: planned\\n  - exp_id: plan_009\\n    role: supporting\\n    result: planned\\n  - exp_id: plan_012\\n    role: pending\\n    result: planned\\n  depends_on:\\n  - D044\\n  - D046\\n- id: D049\\n  date: 2026-05-15 14:39 UTC\\n  summary: 'Dream v2 (dream_20260515T132059) 结果: best=3.0/median=2.5/worst=2.5，未达标(目标\\n    best≥3.5/median≥3.0)。三档一致结构性问题: (1) CED≈flat-NLI 标题错配 (2) QLoRA confound (3) related\\n    work 缺口。行动: 新增 plan_014 bf16 GRPO 控制实验 + plan_015 SFT-no-evidence ablation; plan_009\\n    升 P1; Paper Agent 负责 retitle+reframe+related work。plan_011 eval 优先完成后决定 plan_014\\n    优先级。'\\n  rationale: 'Reframe (D044) 后 re-dream 仍未达 Main 标准。三档审稿一致指出: (a) CED 不显著优于 flat-NLI\\n    但占据标题, (b) GRPO decoupling claim 被 QLoRA confound 限制泛化性, (c) related work 大缺口。这三个是结构性问题而非数据依赖——必须通过新实验(bf16\\n    GRPO 控制)和 reframe 解决。plan_011 已用 bf16 但三变量混淆(bf16+G=8+kl=0.01), 需 clean 单变量控制。禁止\\n    fallback 到 Findings——补实验+reframe 冲 Main。'\\n  related_experiments:\\n  - exp_id: plan_011\\n    role: context\\n    result: ANALYZING - bf16 G=8 训练完成待 eval\\n  - exp_id: plan_014\\n    role: planned\\n    result: '新增: bf16 LoRA GRPO G=4 kl=0 clean control'\\n  - exp_id: plan_015\\n    role: planned\\n    result: '新增: SFT-without-evidence ablation'\\n  depends_on:\\n  - D044\\n  - D046\\n- id: D050\\n  date: 2026-05-15 14:48 UTC\\n  summary: Dream v2 未达标(best=3.0 < 3.5)，决定 pivot 到 analysis paper framing，以 evidence-extraction\\n    decoupling 为核心贡献，CED 降级为分析组件\\n  rationale: Dream v2 三档审稿人一致信号：(1) decoupling 是最新颖贡献(S2两个reviewer强力认可) (2) CED vs\\n    flat-NLI 优势微弱是最致命弱点(W1) (3) EDCR 填补评估盲区(S4) (4) GRPO/DPO/RSFT 光谱设计良好(S6)。当前 framing\\n    把 CED 放标题但数据不支持 CED 显著优势，导致 novelty 感知低。Pivot 到 analysis paper：decoupling 为主 claim，EDCR\\n    为工具贡献，CED 降级为\\\"studied scoring functions之一\\\"。条件：plan_011 bf16 eval 确认 decoupling\\n    非 QLoRA artifact。\\n  related_experiments:\\n  - exp_id: dream_v2_D047\\n    role: trigger\\n    result: best=3.0, median=2.5, worst=2.5\\n  - exp_id: plan_011_grpo_g8_bf16_eval\\n    role: gating\\n    result: pending eval results\\n  depends_on: []\\n- id: D051\\n  date: 2026-05-15 15:55 UTC\\n  summary: D050 pivot 前提失败：bf16 GRPO 无 forgetting (rel_f1=0.4549)，decoupling 是 QLoRA\\n    artifact。暂停 framing pivot，等 plan_015 隔离三重 confound 后再定\\n  rationale: plan_011 bf16 eval 结果：ckpt-100 rel_f1=0.4549（超 SFT +4.92pp，接近 RSFT 0.4596），evi_f1=0.8086，EDCR=0.6318。QLoRA\\n    GRPO 的 catastrophic forgetting 在 bf16 下完全消失。但 plan_011 同时改了三个变量（quantization/G/kl），无法确定是哪个消除了\\n    forgetting。plan_015（bf16+G=4+kl=0）是不可替代的 ablation，必须在定稿 framing 前完成。新的潜在 story：QLoRA\\n    quantization 导致结构化 IE 中 GRPO catastrophic forgetting——比\\\"GRPO fails\\\"更精确、更有诊断价值。\\n  related_experiments:\\n  - exp_id: plan_011_grpo_g8_bf16_eval\\n    role: trigger\\n    result: ckpt-100 rel_f1=0.4549, evi_f1=0.8086, no forgetting\\n  - exp_id: plan_015\\n    role: gating\\n    result: planned, must isolate quantization vs G vs kl\\n  depends_on:\\n  - D050\\n- id: D052\\n  date: 2026-05-15 16:32 UTC\\n  summary: Reviewer 核实 plan_011 vs mvp2_grpo_ced_kl001_r4 已构成 clean quantization ablation（唯一变量=quantization，其余\\n    G=8/kl=0.01/lr=5e-5/weights 完全一致）。不再 gate framing 在 plan_015 上\\n  rationale: Reviewer 逐项核对：plan_011 (bf16) 与 mvp2_grpo_ced_kl001_r4 (QLoRA) 除 quantization\\n    外完全一致（G=8, kl=0.01, lr=5e-5, weights=0.3/3.0/1.0, steps=100, seed=42）。结果：QLoRA\\n    rel_f1=0.2167 vs bf16 rel_f1=0.4549 (Δ=+23.8pp)。这是 quantization→forgetting 的最强直接证据，已完成。plan_015_v2\\n    有 3 个变量差异（weights/lr/kl），不是 clean ablation，定位应为 robustness check。plan_015_v3 不再是\\n    gating experiment——可以立即更新 paper framing。\\n  related_experiments:\\n  - exp_id: plan_011_grpo_g8_bf16_eval\\n    role: treatment\\n    result: bf16 rel_f1=0.4549\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: control\\n    result: QLoRA rel_f1=0.2167\\n  - exp_id: plan_015_v2\\n    role: robustness\\n    result: running, 3-variable confound, not clean ablation\\n  depends_on:\\n  - D051\\n- id: D053\\n  date: 2026-05-15 16:32 UTC\\n  summary: Quantization isolation 已由 plan_011 vs mvp2_grpo_ced_kl001_r4 解决（Δ=+23.8pp），plan_015\\n    降级为 robustness check，可以开始 reframe\\n  rationale: Reviewer 逐项核对发现 plan_011 (bf16, G=8, kl=0.01, lr=5e-5, weights 0.3/3.0/1.0)\\n    与 mvp2_grpo_ced_kl001_r4 (QLoRA 4-bit, G=8, kl=0.01, lr=5e-5, weights 0.3/3.0/1.0)\\n    配置完全一致，唯一差异为 quantization。结果：QLoRA rel_f1=0.2167 vs bf16 rel_f1=0.4549 (+23.8pp)。D051\\n    等 plan_015 隔离的前提不再成立——干净的 ablation 数据已有。plan_015 系列（lr=5e-6）与任何 QLoRA 实验都有 lr\\n    confound，作为 robustness check 而非 controlled ablation。\\n  related_experiments:\\n  - exp_id: plan_011_grpo_g8_bf16_eval\\n    role: treatment\\n    result: bf16 rel_f1=0.4549\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: control\\n    result: QLoRA rel_f1=0.2167\\n  - exp_id: plan_015\\n    role: downgraded\\n    result: robustness check, not gating\\n  depends_on:\\n  - D051\\n- id: D054\\n  date: 2026-05-15 17:50 UTC\\n  summary: 'C2 reframe: GRPO decoupling 从\\\"RL通病\\\"收窄为\\\"QLoRA-specific artifact\\\"。bf16 LoRA\\n    GRPO 不遗忘(rel_f1=0.4549 +4.92pp)，QLoRA 崩(0.2167)。Claim 更窄但更 interesting：量化噪声如何破坏\\n    RL reward signal in structured IE。'\\n  rationale: plan_011 vs mvp2_grpo_ced_kl001_r4 构成 clean single-variable ablation（唯一差异=quantization），Δrel_f1=+23.8pp。原\\n    C2\\\"GRPO causes decoupling\\\"已被 plan_011 否定。新 C2 更有实用价值（QLoRA 广泛使用，此 failure mode\\n    未被文献记录），且 Reviewer D052 已确认 ablation 有效性。\\n  related_experiments:\\n  - exp_id: plan_011_grpo_g8_bf16_eval\\n    role: primary\\n    result: rel_f1=0.4549, no forgetting\\n  - exp_id: mvp2_grpo_ced_kl001_r4\\n    role: control\\n    result: rel_f1=0.2167, catastrophic forgetting\\n  - exp_id: plan_015_grpo_g4_bf16_v2\\n    role: supporting\\n    result: killed, plan_011 already provides clean ablation\\n  depends_on:\\n  - D052\\n  - D053\\n- id: D055\\n  date: 2026-05-15 18:00 UTC\\n  summary: 'C4 reframe: CED 优势在 output quality control (compliance +15pp, truncation\\n    3x↓)，非 rel_f1 提升；补跑 flat-NLI 2 seeds 加强统计可信度'\\n  rationale: flat-NLI rel_f1=0.4539 落在 CED 3-seed 1σ 范围内(0.4468-0.4724)，差异不显著。但 field_compliance\\n    78.9% vs ~94% (+15pp 显著)，truncation 20% vs 5-6% (3x 显著)。CED 的真正增益维度是 evidence\\n    faithfulness + output structure quality，非 extraction accuracy。单 seed 对比统计强度不足，cuda:0/cuda:3\\n    空闲，补跑 2 seeds 成本低收益高。\\n  related_experiments:\\n  - exp_id: eval_plan_001_flat_nli\\n    role: flat-NLI ablation\\n    result: rel_f1=0.4539, evi_f1=0.8043, compliance=78.9%, truncation=20%\\n  depends_on: []\\n- id: D056\\n  date: 2026-05-15 18:05 UTC\\n  summary: CED vs flat-NLI 统计不可区分，Claim 3 降级，CED 不再作为独立贡献\\n  rationale: flat-NLI RSFT (seed=42) rel_f1=0.4539 vs CED RSFT 3-seed mean 0.4596±0.0128，差异\\n    -0.57pp 在 1σ 内。同 seed=42 下 flat-NLI 反超 CED +0.90pp。CED contrastive margin 对 RSFT\\n    filtering 无显著增益。论文贡献重新聚焦：(1) evidence-grounded DocRE 任务定义，(2) GRPO decoupling\\n    发现 + quantization artifact 机制，(3) EDCR 诊断指标。CED 降级为 \\\"one possible NLI-based scoring\\n    function\\\"，保留 reranker 价值（rel_f1=0.4864）和 EDCR 组件角色。取消原计划的 5+ seed 显著性检验（GPU 时间转投更高优先级实验）。\\n  related_experiments:\\n  - exp_id: eval_plan_001_flat_nli\\n    role: primary\\n    result: flat-NLI rel_f1=0.4539, CED 3-seed mean=0.4596, 差异不显著\\n  - exp_id: rsft_ced_r1_s42\\n    role: baseline\\n    result: CED seed=42 rel_f1=0.4449\\n  - exp_id: rsft_ced_r1_s44\\n    role: baseline\\n    result: CED seed=44 rel_f1=0.4655\\n  depends_on:\\n  - D055\\n- id: D057\\n  date: 2026-05-15 18:11 UTC\\n  summary: plan_002 test eval 失败，test set eval 推迟到论文终稿阶段\\n  rationale: DocRED test.json 无 gold labels，inference.py 依赖 gold triples 构造 eval 文档，产出\\n    0 predictions。Test set eval 需要：(1) 枚举所有 entity pairs 生成预测，(2) 输出 CodaLab submission\\n    格式，(3) 提交官方服务器。这是工程改造，非当前研究优先级。Dev set 结果足以支撑当前阶段所有 claims。Test set eval 推迟到论文终稿确定后统一做。\\n  related_experiments:\\n  - exp_id: plan_002_test_eval_s44\\n    role: primary\\n    result: failed — 0 predictions, inference.py 不支持无 gold label test split\\n  depends_on: []\\n- id: D058\\n  date: 2026-05-15 18:33 UTC\\n  summary: SFT baseline 推理量化 confound 发现，必须用 --no-quantize 重跑 SFT baseline eval\\n  rationale: Reviewer Review 20 发现：SFT baseline eval 使用 --quantize（registry line 2148），而所有\\n    RSFT/GRPO eval 使用 --no-quantize。推理量化对 4B 模型通常造成 1-3pp 损失。这意味着论文中所有 vs SFT baseline\\n    的 delta 数字都可能被高估 1-3pp：(1) RSFT vs SFT 从 +3.9~6.0pp 可能实际 +2~4pp；(2) bf16 GRPO\\n    vs SFT 从 +4.9pp 可能实际 +2~3pp；(3) evidence tax 从 8.36pp 可能实际 5~7pp。必须重跑 SFT baseline\\n    eval 用 --no-quantize 获取干净 baseline 数字后重新计算所有 delta。\\n  related_experiments:\\n  - exp_id: eval_plan_014_sft_no_evidence\\n    role: trigger\\n    result: rel_f1=0.4893 but comparison with SFT baseline confounded by quantization\\n  - exp_id: sft_baseline\\n    role: affected\\n    result: rel_f1=0.4057 measured with --quantize, needs re-eval with --no-quantize\\n  depends_on: []\\n- id: D059\\n  date: 2026-05-15 19:10 UTC\\n  summary: Claim 2 re-scope：decoupling 作为负面发现保留，ideas A/B/C 归 Future Work 不做实验。精确措辞等\\n    G=8 + DPO 1ep 结果\\n  rationale: Dream 三档一致认为 decoupling \\\"genuinely novel and striking\\\"，是论文最独特贡献。修复 GRPO\\n    会削弱 claim 且无保证。plan_014 量化 evidence burden ~8pp，而 GRPO decoupling 导致 rel_f1→0.01\\n    是量级差异。Claim 2 精确边界取决于：(1) plan_011 G=8 是否复现 decoupling（排除 G=4 confound）；(2) plan_012\\n    DPO 1ep 是否 decouple（判断 on-policy 特有 vs RL 通病）。\\n  related_experiments:\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: pending\\n    result: G=8 decoupling 验证\\n  - exp_id: plan_012_dpo_ced_1ep\\n    role: pending\\n    result: DPO 是否 decouple\\n  - exp_id: eval_plan_014_sft_no_evidence\\n    role: evidence\\n    result: evidence burden ~8pp (rel_f1 0.4893 vs 0.4057)\\n  depends_on:\\n  - D008\\n- id: D060\\n  date: 2026-05-15 21:07 UTC\\n  summary: plan_014 no-evidence ablation 纳入 C1 核心证据，CED reranker 定位为最优实用方案\\n  rationale: no-evidence SFT rel_f1=0.4893 vs evidence-SFT 0.4106，量化了 evidence generation\\n    的 ~8pp 代价。CED reranker (0.4864) 恢复 97% 的代价且保留 evi_f1=0.8188。这加强了 C1（evidence-grounded\\n    RE 是有代价但可行的新范式），不需要 reframe。Story Arc 增加\\\"cost of faithfulness\\\"和\\\"best practical\\n    solution\\\"两环。\\n  related_experiments:\\n  - exp_id: plan_014_sft_no_evidence\\n    role: ablation\\n    result: no-evidence rel_f1=0.4893, evidence tax ~8pp\\n  - exp_id: mvp2_ced_reranker_poc\\n    role: baseline\\n    result: CED reranker rel_f1=0.4864, evi_f1=0.8188, recovers 97% of evidence tax\\n  depends_on: []\\n- id: D061\\n  date: 2026-05-15 21:26 UTC\\n  summary: 关闭 DPO 实验线，作为 negative result 纳入论文\\n  rationale: DPO 1ep rel_f1=0.0022（关系本体完全遗忘），3ep rel_f1=0.3429（部分恢复但仍远低于 SFT baseline\\n    0.4106）。非单调退化模式 + 训练指标与 downstream 完全脱节。无论训练长度均不可用，但作为 negative result 有论文价值：(1)\\n    训练 accuracy 不能反映生成质量 (2) preference signal 破坏关系抽取能力 (3) 非单调退化现象\\n  related_experiments:\\n  - exp_id: eval_plan_012_dpo_ced_1ep\\n    role: primary\\n    result: rel_f1=0.0022, field_compliance=0%\\n  - exp_id: plan_012_dpo_ced_3ep\\n    role: comparison\\n    result: rel_f1=0.3429, field_compliance=73.1%\\n  - exp_id: mvp1_ced_signal\\n    role: baseline\\n    result: SFT rel_f1=0.4106\\n  depends_on: []\\n- id: D062\\n  date: 2026-05-15 21:26 UTC\\n  summary: Task decoupling（rel_f1↑ + evi_f1↓）确认为跨方法系统性现象，升级为论文核心发现\\n  rationale: GRPO、DPO、RSFT top_k=3 三种不同优化方法均展现 rel_f1 与 evi_f1 反向变动。这不是某方法的 artifact，而是\\n    faithful evidence generation 的固有代价。强化 paper_framing 的 \\\"cost of faithfulness\\\" narrative：优化关系抽取准确率与生成忠实证据之间存在系统性\\n    tradeoff，RSFT 是目前最优 Pareto 点。\\n  related_experiments:\\n  - exp_id: eval_plan_008_rsft_topk3\\n    role: evidence\\n    result: rel_f1↑ but evi_f1 0.745→0.6816\\n  - exp_id: eval_plan_012_dpo_ced_1ep\\n    role: evidence\\n    result: DPO 完全崩塌\\n  - exp_id: plan_012_dpo_ced_3ep\\n    role: evidence\\n    result: evi_f1=0.84 but rel_f1=0.34\\n  depends_on:\\n  - D060\\n- id: D063\\n  date: 2026-05-15 21:35 UTC\\n  summary: D061 暂缓：DPO 1ep eval 确认为 bug（缺 --sft_adapter），需 reeval 后重新评估 DPO 线\\n  rationale: 排查发现 DPO eval 未传 --sft_adapter，模型加载为 base+DPO（缺 SFT 层），生成自由文本关系名。rel_f1=0.0022\\n    不反映 DPO 真实性能。3ep eval 来自训练内置 eval（自动 merge SFT），可能有效但需确认。批准 cuda:0 跑 1ep reeval（~1h），结果出来后重新判断\\n    DPO 线去留。\\n  related_experiments:\\n  - exp_id: eval_plan_012_dpo_ced_1ep\\n    role: invalidated\\n    result: 'bug: missing --sft_adapter'\\n  - exp_id: plan_012_dpo_ced_3ep\\n    role: pending_verification\\n    result: rel_f1=0.3429 from training-internal eval, needs independent verification\\n  depends_on:\\n  - D061\\n- id: D064\\n  date: 2026-05-15 21:36 UTC\\n  summary: 撤回 DPO 1ep 崩塌结论，3 个 eval 因缺 --sft_adapter 无效，紧急重跑\\n  rationale: Reviewer 发现 eval_plan_012_dpo_ced_1ep、eval_plan_001_flat_nli_s43、eval_plan_008_rsft_topk3\\n    三个 eval 缺少 --sft_adapter /root/autodl-tmp/sft_output 参数，模型加载为 base+adapter（跳过\\n    SFT 层），不认识 DocRED 关系本体导致 rel_f1≈0.002。之前基于此数据的 DPO 1ep 灾难性崩塌结论无效。已下令 kill 正在浪费\\n    GPU 的 rsft_topk3 eval（PID 255528, cuda:3），三个 eval 全部加正确参数重跑，并要求 Agent 排查根因+全面审计历史\\n    eval。\\n  related_experiments:\\n  - exp_id: plan_012\\n    role: eval无效需重跑\\n    result: eval缺--sft_adapter\\n  - exp_id: plan_001\\n    role: eval无效需重跑\\n    result: eval缺--sft_adapter\\n  - exp_id: plan_008\\n    role: eval无效需重跑+kill\\n    result: eval缺--sft_adapter正在浪费GPU\\n  depends_on: []\\n- id: D065\\n  date: 2026-05-15 22:56 UTC\\n  summary: bf16 GRPO G=8 确认无 task decoupling，QLoRA 是 confound——Claim 3 需 reframe 为\\n    \\\"QLoRA-specific artifact\\\" 而非 \\\"GRPO inherent failure\\\"\\n  rationale: 'plan_011 step 30/50/70 全量 dev eval：rel_f1 全程 0.43+ > SFT baseline 0.41，evi_f1\\n    稳定 0.80-0.81，无 QLoRA GRPO 中的 rel_f1 崩塌。field_compliance 从 70.7% 升至 92.4%。结合 QLoRA\\n    GRPO 全线失败（rel_f1 max=0.211），task decoupling 是 QLoRA 量化精度不足导致，非 GRPO 对 IE 任务的固有缺陷。论文\\n    Claim 3 从\\\"GRPO fails for IE\\\"改为\\\"quantization confound analysis\\\"——这反而是更强的 contribution（诊断出量化对\\n    RL-for-IE 的特定影响）。Warning: step-70 rel_f1=0.4341 与之前报告的 0.4549 不一致，需核实。'\\n  related_experiments:\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: primary\\n    result: 'step-70: rel_f1=0.4341, evi_f1=0.8099, no decoupling'\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: contrast\\n    result: 'QLoRA GRPO: rel_f1 max=0.211, catastrophic forgetting'\\n  depends_on: []\\n- id: D066\\n  date: 2026-05-15 23:03 UTC\\n  summary: 确认 task decoupling 是 QLoRA-specific artifact：bf16 GRPO G=8 全 4 个 checkpoint\\n    无 decoupling，论文报 best rel_f1=0.4549 (step-100)\\n  rationale: plan_011 bf16 GRPO step 30/50/70/100 完整 eval 显示 rel_f1 全程 > SFT baseline\\n    (0.41)，evi_f1 稳定 0.80-0.81，无 QLoRA GRPO 中观察到的 rel_f1 崩塌。Reviewer PASS。0.4549 来自\\n    step-100 (best checkpoint)，0.4341 来自 step-70 (中间 checkpoint)，两者均为 full dev eval\\n    + --sft_adapter + --no-quantize，差异仅因 checkpoint 不同。论文 Claim 3 核心证据确立：decoupling\\n    是 QLoRA quantization artifact，非 GRPO 固有问题。\\n  related_experiments:\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: primary\\n    result: 'success: step-100 rel_f1=0.4549, evi_f1=0.8086, no decoupling'\\n  - exp_id: eval_grpo_g8_bf16\\n    role: corroborating\\n    result: 'success: step-100 rel_f1=0.4549 confirmed'\\n  depends_on: []\\n- id: D067\\n  date: 2026-05-15 23:39 UTC\\n  summary: DPO 叙事修正：从\\\"DPO 也失败\\\"改为\\\"DPO 中性/轻度退化\\\"，作为 RL spectrum 中间数据点\\n  rationale: D064 bug fix 后 DPO 1ep 重新评估：rel_f1=0.4034 ≈ SFT baseline 0.4057（-0.23pp，噪声范围）。D061\\n    基于缺 --sft_adapter 的无效 eval 关闭 DPO 线，该决策维持（不需额外 DPO 实验），但论文叙事需修正。RL spectrum 更新：GRPO\\n    QLoRA catastrophic(<0.02) → GRPO bf16 G=8 mild degradation(0.434 from 0.4549 base)\\n    → DPO 1ep neutral(0.4034) → DPO 3ep mild退化(0.3429) → RSFT effective(0.44-0.49)。DPO\\n    展现温和 decoupling 模式（evi_f1↑ rel_f1↓），支持 preference optimization 在 structured IE\\n    上的 evidence-extraction trade-off 是普遍现象但程度因方法而异。两个 Reviewer 一致确认。待查：DPO field_compliance_rate\\n    仅 65.9%，需对比 SFT baseline 排除模型本身问题。\\n  related_experiments:\\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\\n    role: primary\\n    result: rel_f1=0.4034, evi_f1=0.8088, EDCR=0.7139\\n  - exp_id: plan_012_dpo_ced\\n    role: comparison\\n    result: DPO 3ep rel_f1=0.3429 (mild degradation)\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: comparison\\n    result: GRPO bf16 G=8 best=0.4341 (mild degradation from 0.4549 base)\\n  depends_on:\\n  - D061\\n- id: D068\\n  date: 2026-05-15 23:40 UTC\\n  summary: 修正 DPO 结论：DPO 1ep 中性（非失败），Claim 2 叙事需从\\\"RL fails\\\"转向\\\"RL spectrum 分化\\\"\\n  rationale: D061 基于缺 --sft_adapter 的无效 eval 判定\\\"关闭 DPO 线\\\"。修正后数据：DPO 1ep rel_f1=0.4034（≈SFT\\n    0.4057），DPO 3ep=0.3429（过拟合退化）。结合 GRPO QLoRA catastrophic(<0.02) vs GRPO bf16 mild\\n    degradation(~0.434)，decoupling 的 catastrophic 程度与 QLoRA 强相关。新叙事：QLoRA+GRPO 导致\\n    catastrophic decoupling；bf16+GRPO 轻度退化；DPO 中性无改善；RSFT 是唯一有效路线。plan_015（clean G=4\\n    bf16 control）升为高优先级以隔离 QLoRA confound。\\n  related_experiments:\\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\\n    role: corrected_eval\\n    result: rel_f1=0.4034, neutral vs SFT\\n  - exp_id: plan_012_dpo_ced\\n    role: original_3ep\\n    result: rel_f1=0.3429, mild degradation\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: grpo_bf16_control\\n    result: best=0.4341, mild not catastrophic\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: grpo_qlora_original\\n    result: rel_f1<0.02, catastrophic\\n  depends_on: []\\n- id: D069\\n  date: 2026-05-15 23:44 UTC\\n  summary: 修正 D068：evidence-extraction decoupling 是 RL-for-IE 通用现象，非 QLoRA 特有；severity\\n    按方法分层\\n  rationale: D068 判断\\\"catastrophic decoupling 是 QLoRA artifact\\\"不完整。Reviewer 指出 DPO\\n    1ep→3ep 也呈现 decoupling（rel_f1 0.4034→0.3429 下降，evi_f1 0.8088→0.8403 上升），与 GRPO\\n    方向一致仅程度不同。修正后的完整图景：(1) GRPO+QLoRA=catastrophic decoupling (rel_f1<0.02)；(2) GRPO+bf16=mild\\n    decoupling (0.4549→0.434)；(3) DPO+bf16=gradual decoupling (0.4034→0.3429 over\\n    epochs)；(4) RSFT=无 decoupling。结论：decoupling 是所有 RL 方法在结构化 IE 上的通用现象，QLoRA 放大其严重程度但不是唯一原因。RSFT（非\\n    RL 的数据筛选）是唯一规避路径。Claim 2 应从\\\"GRPO fails\\\"升级为\\\"RL-for-IE universal decoupling + severity\\n    hierarchy\\\"。plan_015 仍有价值（量化 QLoRA 放大效应）但不再是叙事关键。另需排查 Ign-F1=F1 的 eval pipeline\\n    bug。\\n  related_experiments:\\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\\n    role: dpo_1ep_corrected\\n    result: rel_f1=0.4034, evi_f1=0.8088\\n  - exp_id: plan_012_dpo_ced\\n    role: dpo_3ep\\n    result: rel_f1=0.3429, evi_f1=0.8403, decoupling confirmed\\n  - exp_id: plan_011_bf16_g8_step_eval\\n    role: grpo_bf16\\n    result: 0.4549→0.434, mild decoupling\\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\\n    role: grpo_qlora\\n    result: catastrophic, rel_f1<0.02\\n  depends_on:\\n  - D068\\n- id: D070\\n  date: 2026-05-15 23:50 UTC\\n  summary: Claim 4 重新定位：EDCR 从跨方法诊断指标降级为 per-relation-type/per-document 细粒度诊断工具\\n  rationale: plan_003 EDCR diagnostic table 显示跨方法 EDCR 与 rel_f1 近乎完全反相关（Spearman=-0.965），与\\n    evi_f1 相关性为零（0.002）。这意味着在方法级比较中 EDCR 不提供超出 rel_f1 的独立信息，原始 Claim 4\\\"EDCR 捕捉 Evi-F1\\n    盲区\\\"在方法级不成立。但 per-relation-type 分析显示有意义的方差（date_of_birth EDCR≈0.1 vs head_of_government\\n    EDCR≈0.95），说明 EDCR 在细粒度诊断上仍有价值。重新定位为\\\"per-relation/per-document 证据质量诊断工具\\\"，避免审稿人用一个相关性计算即击穿\\n    Claim 4。\\n  related_experiments:\\n  - exp_id: plan_003_edcr_diagnostic\\n    role: diagnostic_table\\n    result: EDCR vs rel_f1 Spearman=-0.965, vs evi_f1 Spearman=0.002\\n  depends_on: []\\n- id: D071\\n  date: 2026-05-15 23:50 UTC\\n  summary: EDCR 定义存在 by-construction 混淆：当前 EDCR ≈ f(1/rel_f1)，不独立度量 evidence 质量。暂停\\n    Claim 4，实现 TP-only EDCR 后重新评估\\n  rationale: plan_003 诊断表显示 EDCR vs rel_f1 Spearman r=-0.9648, EDCR vs evi_f1 r=0.0022。机理：EDCR\\n    = n_distractor/n_total 在全部预测上计算，rel_f1 低的模型预测大量错误关系→evidence 自动成为 distractor→推高\\n    EDCR。这是定义层面的混淆，非数据问题。修复方案：EDCR 改为仅在 TP triples 上计算（\\\"正确关系中 evidence 的忠实度\\\"），若 TP-only\\n    EDCR 仍与 rel_f1 强相关则 Claim 4 需大幅削弱。plan_013（人工标注验证）暂停，等 TP-only EDCR 定义确认后再决定。\\n  related_experiments:\\n  - exp_id: plan_003_edcr_diagnostic\\n    role: diagnostic\\n    result: EDCR vs rel_f1 r=-0.965, EDCR vs evi_f1 r=0.002\\n  depends_on: []\\n- id: D072\\n  date: 2026-05-16 00:00 UTC\\n  summary: 'Claim 4 升级为双层论述: 方法级 EDCR (decoupling 量化) + per-relation EDCR (独立诊断工具)'\\n  rationale: Per-relation EDCR 分析 (93 relation types) 显示 EDCR vs evi_f1 ρ=-0.064 (p=0.583)，完全独立。与方法级\\n    ρ=-0.965 形成互补。方法级 EDCR 本质是 rel_f1 的变换，诊断价值有限；但 per-relation 粒度上 EDCR 捕捉到 evi_f1\\n    看不到的信息（如 head_of_government EDCR=0.956 但 evi_f1=0.875，证据看似好但 relation 抽取极差）。同时发现\\n    evi_f1 vs rel_f1 在 per-relation 层面也近乎零相关 (ρ=-0.013)，说明 evidence quality 和 relation\\n    extraction 在不同 relation type 间完全解耦——这是一个独立的发现，强化整篇论文的 decoupling narrative。\\n  related_experiments:\\n  - exp_id: plan_003_edcr_diagnostic\\n    role: 方法级 EDCR 分析\\n    result: ρ=-0.965 vs rel_f1\\n  - exp_id: D070\\n    role: per-relation EDCR 分析\\n    result: EDCR vs evi_f1 ρ=-0.064, EDCR vs rel_f1 ρ=-0.793\\n  depends_on:\\n  - D070\\n- id: D073\\n  date: 2026-05-16 00:02 UTC\\n  summary: 'EDCR 论文定义规范: 正文用 distractor count ratio (∈[0,1])，formula proxy 1-rel_f1/evi_f1\\n    仅用于方法级快速对比；per-relation 表格须 n_pred≥10 过滤'\\n  rationale: 'Reviewer 指出两个问题: (1) EDCR formula 1-rel_f1/evi_f1 在 rel_f1>evi_f1 时为负(manufacturer=-0.1879)，名为\\n    rate 却不在[0,1]，审稿人会质疑; (2) per-relation top/bottom 表被退化 case 主导(n_pred=0→EDCR=0,\\n    TP=0→EDCR=1)，有 cherry-picking 嫌疑。解决方案: 论文正文 EDCR 定义为 distractor count ratio (cited\\n    evidence 中非支撑性证据的比例，自然∈[0,1])；formula proxy 仅在方法级无逐预测 distractor 计数时使用，论文中注明是近似。per-relation\\n    展示表格加 n_pred≥10 过滤。'\\n  related_experiments:\\n  - exp_id: plan_003_edcr_diagnostic\\n    role: 方法级 EDCR\\n    result: formula proxy 用于15个方法对比\\n  - exp_id: D070\\n    role: per-relation EDCR\\n    result: 发现负值 case 和退化 case\\n  depends_on:\\n  - D072\\n- id: D074\\n  date: 2026-05-16 00:25 UTC\\n  summary: r2 实际配置正确但已被 kill，r3 替代运行；argparse 静默忽略未知参数是代码隐患\\n  rationale: 验证发现 rsft_trainer.py 的 argparse 不存在 --batch/--grad_accum/--lr/--epochs\\n    参数，这些 flag 被静默忽略，实际使用默认值 per_device_batch_size=4, gradient_accumulation_steps=4，恰好是\\n    CED 正确配置。r2 两个 seed (s43/s45) 的实际训练配置完全一致（510 steps = 2718×3/16），满足 paired t-test\\n    要求。r2 被基于错误假设 kill，r3 用显式正确参数重启，功能等价，仅损失重启时间。后续应修复 argparse strict mode 防止类似问题。\\n  related_experiments:\\n  - exp_id: rsft_ced_s43_train_r2\\n    role: 被验证对象\\n    result: killed（实际配置正确）\\n  - exp_id: rsft_ced_s45_train_r2\\n    role: 被验证对象\\n    result: killed（实际配置正确）\\n  - exp_id: rsft_ced_s43_train_r3\\n    role: 替代实验\\n    result: running\\n  - exp_id: rsft_ced_s45_train_r3\\n    role: 替代实验\\n    result: running\\n  depends_on: []\\n- id: D075\\n  date: 2026-05-16 01:44 UTC\\n  summary: '新增 RC11: 区分 intra-task decoupling vs inter-task forgetting，回应\\\"RL不遗忘\\\"文献'\\n  rationale: 文献扫描发现多篇论文论证 RL fine-tuning 天然缓解 catastrophic forgetting，与 Claim 2 存在表面张力。关键区分：FREIGE\\n    的 decoupling 是 multi-objective competition（RE vs evidence），不是预训练知识遗忘。同时纳入 QuRL/QaRL\\n    作为 QLoRA amplification 的理论支撑。需在 Related Work/Discussion 显式回应。\\n  related_experiments:\\n  - exp_id: eval_grpo_bf16_g8_step30\\n    role: evidence\\n    result: mild decoupling (-2pp) 印证 intra-task trade-off 而非 forgetting\\n  depends_on: []\\n- id: D076\\n  date: 2026-05-16 02:38 UTC\\n  summary: 批准 4 个 eval 重跑：协议审计发现 batch_size/max_new_tokens/seed 不一致，paired t-test\\n    数据无效\\n  rationale: 协议审计发现 8 个 eval 中 4 个不一致：CED s42 (batch_size=8, max_new_tokens=1536),\\n    CED s44 (seed=42 错误), flat-NLI s42 (batch_size=16), flat-NLI s43 (batch_size=16)。统一为\\n    batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + 正确 seed。延迟\\n    ~3h，但数据有效性是 C3 统计检验的前提。\\n  related_experiments:\\n  - exp_id: reeval_ced_s42\\n    role: reeval\\n    result: pending\\n  - exp_id: reeval_ced_s44\\n    role: reeval\\n    result: pending\\n  - exp_id: reeval_flat_nli_s42\\n    role: reeval\\n    result: pending\\n  - exp_id: reeval_flat_nli_s43\\n    role: reeval\\n    result: pending\\n  depends_on:\\n  - D075\\n\", \"total_chars\": 58989, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 74_

<details><summary>Logged reasoning block</summary>

```text
Let me extract just the D076 decision from the decisions file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "8ead110e-c094-42de-8865-b336142d5615",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TMNR9egawcSxLNABuLBFFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 45853,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 75_

<details open><summary>🔧 Tool call — Bash · `toolu_011XDLwVaYBGitYsqLPz3nJE`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt | python3 -c \"import sys,json; data=json.loads(json.loads(sys.stdin.read())['result']); content=data['content']; \n# Find D076 section\nimport re\nmatches = re.findall(r'(D07[0-9].*?)(?=\\nD\\d{3}:|\\Z)', content, re.DOTALL)\nfor m in matches:\n    print(m[:800])\n    print('---')\n\"",
  "description": "Extract D070-D079 decisions from YAML"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "5119c725-e091-4cc3-8e91-a2e405bf276b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TMNR9egawcSxLNABuLBFFL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 775,
      "cache_read_input_tokens": 45853,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 775
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

_source line 76 · 2026-05-16T03:25:26.250Z_

<details><summary>↩ Tool result · reported error · `toolu_011XDLwVaYBGitYsqLPz3nJE`</summary>

```text
Exit code 1
Traceback (most recent call last):
  File "&lt;string>", line 1, in &lt;module>
    import sys,json; data=json.loads(json.loads(sys.stdin.read())['result']); content=data['content'];
                                                                                      ~~~~^^^^^^^^^^^
KeyError: 'content'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "1acee63d-648d-412f-8fcb-b564e4574e58",
  "tool_use_result": "Error: Exit code 1\nTraceback (most recent call last):\n  File \"&lt;string>\", line 1, in &lt;module>\n    import sys,json; data=json.loads(json.loads(sys.stdin.read())['result']); content=data['content'];\n                                                                                      ~~~~^^^^^^^^^^^\nKeyError: 'content'"
}
```

</details>

---

### Tool call

_source line 77_

<details open><summary>🔧 Tool call — Bash · `toolu_01RRvbsnj3cEDjT5fDspDFrx`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt | python3 -c \"\nimport sys,json\nraw = json.loads(sys.stdin.read())\nresult = json.loads(raw['result'])\ndata = result.get('data', result)\ncontent = data.get('content', str(data))\n# Find D076\nidx = content.find('D076')\nif idx >= 0:\n    print(content[idx:idx+2000])\nelse:\n    print('D076 not found')\n    # Show available D07x\n    import re\n    for m in re.finditer(r'D07\\d', content):\n        print(f'Found: {content[m.start():m.start()+80]}')\n\"",
  "description": "Extract D076 decision from decisions YAML"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "aff90659-c19e-4eae-b9a2-c5123d05f9b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NzAJCa5FiTyASQN5fq3z1t",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 414,
      "cache_read_input_tokens": 46628,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 414
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

_source line 78 · 2026-05-16T03:25:31.474Z_

<details><summary>↩ Tool result · `toolu_01RRvbsnj3cEDjT5fDspDFrx`</summary>

```text
D076
  date: 2026-05-16 02:38 UTC
  summary: 批准 4 个 eval 重跑：协议审计发现 batch_size/max_new_tokens/seed 不一致，paired t-test
    数据无效
  rationale: 协议审计发现 8 个 eval 中 4 个不一致：CED s42 (batch_size=8, max_new_tokens=1536),
    CED s44 (seed=42 错误), flat-NLI s42 (batch_size=16), flat-NLI s43 (batch_size=16)。统一为
    batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + 正确 seed。延迟
    ~3h，但数据有效性是 C3 统计检验的前提。
  related_experiments:
  - exp_id: reeval_ced_s42
    role: reeval
    result: pending
  - exp_id: reeval_ced_s44
    role: reeval
    result: pending
  - exp_id: reeval_flat_nli_s42
    role: reeval
    result: pending
  - exp_id: reeval_flat_nli_s43
    role: reeval
    result: pending
  depends_on:
  - D075
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "875112aa-9c47-43b3-892f-9e6623800acb",
  "tool_use_result": {
    "stdout": "D076\n  date: 2026-05-16 02:38 UTC\n  summary: 批准 4 个 eval 重跑：协议审计发现 batch_size/max_new_tokens/seed 不一致，paired t-test\n    数据无效\n  rationale: 协议审计发现 8 个 eval 中 4 个不一致：CED s42 (batch_size=8, max_new_tokens=1536),\n    CED s44 (seed=42 错误), flat-NLI s42 (batch_size=16), flat-NLI s43 (batch_size=16)。统一为\n    batch_size=4 + --no-quantize + --sft_adapter + max_new_tokens=1024 + 正确 seed。延迟\n    ~3h，但数据有效性是 C3 统计检验的前提。\n  related_experiments:\n  - exp_id: reeval_ced_s42\n    role: reeval\n    result: pending\n  - exp_id: reeval_ced_s44\n    role: reeval\n    result: pending\n  - exp_id: reeval_flat_nli_s42\n    role: reeval\n    result: pending\n  - exp_id: reeval_flat_nli_s43\n    role: reeval\n    result: pending\n  depends_on:\n  - D075",
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

_source line 79_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need to compile the evidence table. Let me also get D067/D068/D069/D070/D072/D073 for the DPO narrative and EDCR context.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "63d0d5ff-6916-424c-b446-63447403dff5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VXqXCnKqLZy8EUWoPJP4xh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 702,
      "cache_read_input_tokens": 47042,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 702
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

_source line 80_

<details open><summary>🔧 Tool call — Bash · `toolu_01MrEWKD3kWYBASMkCtL8PUF`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/1b422aa5-76ab-42b1-8a3d-85cfc234200a/tool-results/mcp-agent-ml-research-read_project_file-1778901920399.txt | python3 -c \"\nimport sys,json\nraw = json.loads(sys.stdin.read())\nresult = json.loads(raw['result'])\ndata = result.get('data', result)\ncontent = data.get('content', str(data))\n# Extract D067-D073\nfor d in ['D067','D068','D069','D070','D071','D072','D073']:\n    idx = content.find(d)\n    if idx >= 0:\n        end = idx + 1500\n        # Find next D0XX\n        import re\n        m = re.search(r'\\nD\\d{3}', content[idx+4:idx+2000])\n        if m:\n            end = idx + 4 + m.start()\n        print(content[idx:end][:1000])\n        print('===')\n\"",
  "description": "Extract D067-D073 decisions"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "70eb8459-cdbe-4d06-a1d5-bcbfadb502b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VXqXCnKqLZy8EUWoPJP4xh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 702,
      "cache_read_input_tokens": 47042,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 702
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

_source line 81 · 2026-05-16T03:25:39.042Z_

<details><summary>↩ Tool result · `toolu_01MrEWKD3kWYBASMkCtL8PUF`</summary>

```text
D067
  date: 2026-05-15 23:39 UTC
  summary: DPO 叙事修正：从"DPO 也失败"改为"DPO 中性/轻度退化"，作为 RL spectrum 中间数据点
  rationale: D064 bug fix 后 DPO 1ep 重新评估：rel_f1=0.4034 ≈ SFT baseline 0.4057（-0.23pp，噪声范围）。D061
    基于缺 --sft_adapter 的无效 eval 关闭 DPO 线，该决策维持（不需额外 DPO 实验），但论文叙事需修正。RL spectrum 更新：GRPO
    QLoRA catastrophic(<0.02) → GRPO bf16 G=8 mild degradation(0.434 from 0.4549 base)
    → DPO 1ep neutral(0.4034) → DPO 3ep mild退化(0.3429) → RSFT effective(0.44-0.49)。DPO
    展现温和 decoupling 模式（evi_f1↑ rel_f1↓），支持 preference optimization 在 structured IE
    上的 evidence-extraction trade-off 是普遍现象但程度因方法而异。两个 Reviewer 一致确认。待查：DPO field_compliance_rate
    仅 65.9%，需对比 SFT baseline 排除模型本身问题。
  related_experiments:
  - exp_id: eval_plan_012_dpo_1ep_fixed_r2
    role: primary
    result: rel_f1=0.4034, evi_f1=0.8088, EDCR=0.7139
  - exp_id: plan_012_dpo_ced
    role: comparison
    result: DPO 3ep rel_f1=0.3429 (mild degradation)
  - exp_id: plan_011_bf16_g8_step_eval
    role: comparison
    result: GRPO bf16
===
D068
  date: 2026-05-15 23:40 UTC
  summary: 修正 DPO 结论：DPO 1ep 中性（非失败），Claim 2 叙事需从"RL fails"转向"RL spectrum 分化"
  rationale: D061 基于缺 --sft_adapter 的无效 eval 判定"关闭 DPO 线"。修正后数据：DPO 1ep rel_f1=0.4034（≈SFT
    0.4057），DPO 3ep=0.3429（过拟合退化）。结合 GRPO QLoRA catastrophic(<0.02) vs GRPO bf16 mild
    degradation(~0.434)，decoupling 的 catastrophic 程度与 QLoRA 强相关。新叙事：QLoRA+GRPO 导致
    catastrophic decoupling；bf16+GRPO 轻度退化；DPO 中性无改善；RSFT 是唯一有效路线。plan_015（clean G=4
    bf16 control）升为高优先级以隔离 QLoRA confound。
  related_experiments:
  - exp_id: eval_plan_012_dpo_1ep_fixed_r2
    role: corrected_eval
    result: rel_f1=0.4034, neutral vs SFT
  - exp_id: plan_012_dpo_ced
    role: original_3ep
    result: rel_f1=0.3429, mild degradation
  - exp_id: plan_011_bf16_g8_step_eval
    role: grpo_bf16_control
    result: best=0.4341, mild not catastrophic
  - exp_id: mvp2_grpo_ced_lr5e6_r1
    role: grpo_qlora_original
    result: rel_f1<0.02, catastrophic
  depends_on: []
- id: D069
  date: 2026-05-15 23:44 UT
===
D069
  date: 2026-05-15 23:44 UTC
  summary: 修正 D068：evidence-extraction decoupling 是 RL-for-IE 通用现象，非 QLoRA 特有；severity
    按方法分层
  rationale: D068 判断"catastrophic decoupling 是 QLoRA artifact"不完整。Reviewer 指出 DPO
    1ep→3ep 也呈现 decoupling（rel_f1 0.4034→0.3429 下降，evi_f1 0.8088→0.8403 上升），与 GRPO
    方向一致仅程度不同。修正后的完整图景：(1) GRPO+QLoRA=catastrophic decoupling (rel_f1<0.02)；(2) GRPO+bf16=mild
    decoupling (0.4549→0.434)；(3) DPO+bf16=gradual decoupling (0.4034→0.3429 over
    epochs)；(4) RSFT=无 decoupling。结论：decoupling 是所有 RL 方法在结构化 IE 上的通用现象，QLoRA 放大其严重程度但不是唯一原因。RSFT（非
    RL 的数据筛选）是唯一规避路径。Claim 2 应从"GRPO fails"升级为"RL-for-IE universal decoupling + severity
    hierarchy"。plan_015 仍有价值（量化 QLoRA 放大效应）但不再是叙事关键。另需排查 Ign-F1=F1 的 eval pipeline
    bug。
  related_experiments:
  - exp_id: eval_plan_012_dpo_1ep_fixed_r2
    role: dpo_1ep_corrected
    result: rel_f1=0.4034, evi_f1=0.8088
  - exp_id: plan_012_dpo_ced
    role: dpo_3ep
    result: rel_f1=0.3429, evi_f1=0.8403, decoupling confirmed
 
===
D070
  date: 2026-05-15 23:50 UTC
  summary: Claim 4 重新定位：EDCR 从跨方法诊断指标降级为 per-relation-type/per-document 细粒度诊断工具
  rationale: plan_003 EDCR diagnostic table 显示跨方法 EDCR 与 rel_f1 近乎完全反相关（Spearman=-0.965），与
    evi_f1 相关性为零（0.002）。这意味着在方法级比较中 EDCR 不提供超出 rel_f1 的独立信息，原始 Claim 4"EDCR 捕捉 Evi-F1
    盲区"在方法级不成立。但 per-relation-type 分析显示有意义的方差（date_of_birth EDCR≈0.1 vs head_of_government
    EDCR≈0.95），说明 EDCR 在细粒度诊断上仍有价值。重新定位为"per-relation/per-document 证据质量诊断工具"，避免审稿人用一个相关性计算即击穿
    Claim 4。
  related_experiments:
  - exp_id: plan_003_edcr_diagnostic
    role: diagnostic_table
    result: EDCR vs rel_f1 Spearman=-0.965, vs evi_f1 Spearman=0.002
  depends_on: []
- id: D071
  date: 2026-05-15 23:50 UTC
  summary: EDCR 定义存在 by-construction 混淆：当前 EDCR ≈ f(1/rel_f1)，不独立度量 evidence 质量。暂停
    Claim 4，实现 TP-only EDCR 后重新评估
  rationale: plan_003 诊断表显示 EDCR vs rel_f1 Spearman r=-0.9648, EDCR vs evi_f1 r=0.0022。机理：EDCR
    = n_distractor/n_total 在全部预测上计算，rel_f1 低的模型预测大量错误关系→evidence 自动成为 distractor→推高
  
===
D071
  date: 2026-05-15 23:50 UTC
  summary: EDCR 定义存在 by-construction 混淆：当前 EDCR ≈ f(1/rel_f1)，不独立度量 evidence 质量。暂停
    Claim 4，实现 TP-only EDCR 后重新评估
  rationale: plan_003 诊断表显示 EDCR vs rel_f1 Spearman r=-0.9648, EDCR vs evi_f1 r=0.0022。机理：EDCR
    = n_distractor/n_total 在全部预测上计算，rel_f1 低的模型预测大量错误关系→evidence 自动成为 distractor→推高
    EDCR。这是定义层面的混淆，非数据问题。修复方案：EDCR 改为仅在 TP triples 上计算（"正确关系中 evidence 的忠实度"），若 TP-only
    EDCR 仍与 rel_f1 强相关则 Claim 4 需大幅削弱。plan_013（人工标注验证）暂停，等 TP-only EDCR 定义确认后再决定。
  related_experiments:
  - exp_id: plan_003_edcr_diagnostic
    role: diagnostic
    result: EDCR vs rel_f1 r=-0.965, EDCR vs evi_f1 r=0.002
  depends_on: []
- id: D072
  date: 2026-05-16 00:00 UTC
  summary: 'Claim 4 升级为双层论述: 方法级 EDCR (decoupling 量化) + per-relation EDCR (独立诊断工具)'
  rationale: Per-relation EDCR 分析 (93 relation types) 显示 EDCR vs evi_f1 ρ=-0.064 (p=0.583)，完全独立。与方法级
    ρ=-0.965 形成互补。方法级 EDCR 本质是 rel_f1 的变换，诊断价值有限；但 per-relation 粒度上 EDCR 捕捉到 evi_f1
    看不到的信息（如 head_of_government E
===
D072
  date: 2026-05-16 00:00 UTC
  summary: 'Claim 4 升级为双层论述: 方法级 EDCR (decoupling 量化) + per-relation EDCR (独立诊断工具)'
  rationale: Per-relation EDCR 分析 (93 relation types) 显示 EDCR vs evi_f1 ρ=-0.064 (p=0.583)，完全独立。与方法级
    ρ=-0.965 形成互补。方法级 EDCR 本质是 rel_f1 的变换，诊断价值有限；但 per-relation 粒度上 EDCR 捕捉到 evi_f1
    看不到的信息（如 head_of_government EDCR=0.956 但 evi_f1=0.875，证据看似好但 relation 抽取极差）。同时发现
    evi_f1 vs rel_f1 在 per-relation 层面也近乎零相关 (ρ=-0.013)，说明 evidence quality 和 relation
    extraction 在不同 relation type 间完全解耦——这是一个独立的发现，强化整篇论文的 decoupling narrative。
  related_experiments:
  - exp_id: plan_003_edcr_diagnostic
    role: 方法级 EDCR 分析
    result: ρ=-0.965 vs rel_f1
  - exp_id: D070
    role: per-relation EDCR 分析
    result: EDCR vs evi_f1 ρ=-0.064, EDCR vs rel_f1 ρ=-0.793
  depends_on:
  - D070
- id: D073
  date: 2026-05-16 00:02 UTC
  summary: 'EDCR 论文定义规范: 正文用 distractor count ratio (∈[0,1])，formula proxy 1-rel_f1/evi_f1
    仅用于方法级快速对比；per-relation 表格须 n_pred≥10 过滤'
  rationale: 'Reviewer 
===
D073
  date: 2026-05-16 00:02 UTC
  summary: 'EDCR 论文定义规范: 正文用 distractor count ratio (∈[0,1])，formula proxy 1-rel_f1/evi_f1
    仅用于方法级快速对比；per-relation 表格须 n_pred≥10 过滤'
  rationale: 'Reviewer 指出两个问题: (1) EDCR formula 1-rel_f1/evi_f1 在 rel_f1>evi_f1 时为负(manufacturer=-0.1879)，名为
    rate 却不在[0,1]，审稿人会质疑; (2) per-relation top/bottom 表被退化 case 主导(n_pred=0→EDCR=0,
    TP=0→EDCR=1)，有 cherry-picking 嫌疑。解决方案: 论文正文 EDCR 定义为 distractor count ratio (cited
    evidence 中非支撑性证据的比例，自然∈[0,1])；formula proxy 仅在方法级无逐预测 distractor 计数时使用，论文中注明是近似。per-relation
    展示表格加 n_pred≥10 过滤。'
  related_experiments:
  - exp_id: plan_003_edcr_diagnostic
    role: 方法级 EDCR
    result: formula proxy 用于15个方法对比
  - exp_id: D070
    role: per-relation EDCR
    result: 发现负值 case 和退化 case
  depends_on:
  - D072
- id: D074
  date: 2026-05-16 00:25 UTC
  summary: r2 实际配置正确但已被 kill，r3 替代运行；argparse 静默忽略未知参数是代码隐患
  rationale: 验证发现 rsft_trainer.py 的 argparse 不存在 --batch/--grad_accum/--lr/--epochs
    参数，这些 flag 被静默忽略，实际使用默认值 
===
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "23d40e87-2ac6-4daa-a971-20e08792e61b",
  "tool_use_result": {
    "stdout": "D067\n  date: 2026-05-15 23:39 UTC\n  summary: DPO 叙事修正：从\"DPO 也失败\"改为\"DPO 中性/轻度退化\"，作为 RL spectrum 中间数据点\n  rationale: D064 bug fix 后 DPO 1ep 重新评估：rel_f1=0.4034 ≈ SFT baseline 0.4057（-0.23pp，噪声范围）。D061\n    基于缺 --sft_adapter 的无效 eval 关闭 DPO 线，该决策维持（不需额外 DPO 实验），但论文叙事需修正。RL spectrum 更新：GRPO\n    QLoRA catastrophic(<0.02) → GRPO bf16 G=8 mild degradation(0.434 from 0.4549 base)\n    → DPO 1ep neutral(0.4034) → DPO 3ep mild退化(0.3429) → RSFT effective(0.44-0.49)。DPO\n    展现温和 decoupling 模式（evi_f1↑ rel_f1↓），支持 preference optimization 在 structured IE\n    上的 evidence-extraction trade-off 是普遍现象但程度因方法而异。两个 Reviewer 一致确认。待查：DPO field_compliance_rate\n    仅 65.9%，需对比 SFT baseline 排除模型本身问题。\n  related_experiments:\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\n    role: primary\n    result: rel_f1=0.4034, evi_f1=0.8088, EDCR=0.7139\n  - exp_id: plan_012_dpo_ced\n    role: comparison\n    result: DPO 3ep rel_f1=0.3429 (mild degradation)\n  - exp_id: plan_011_bf16_g8_step_eval\n    role: comparison\n    result: GRPO bf16\n===\nD068\n  date: 2026-05-15 23:40 UTC\n  summary: 修正 DPO 结论：DPO 1ep 中性（非失败），Claim 2 叙事需从\"RL fails\"转向\"RL spectrum 分化\"\n  rationale: D061 基于缺 --sft_adapter 的无效 eval 判定\"关闭 DPO 线\"。修正后数据：DPO 1ep rel_f1=0.4034（≈SFT\n    0.4057），DPO 3ep=0.3429（过拟合退化）。结合 GRPO QLoRA catastrophic(<0.02) vs GRPO bf16 mild\n    degradation(~0.434)，decoupling 的 catastrophic 程度与 QLoRA 强相关。新叙事：QLoRA+GRPO 导致\n    catastrophic decoupling；bf16+GRPO 轻度退化；DPO 中性无改善；RSFT 是唯一有效路线。plan_015（clean G=4\n    bf16 control）升为高优先级以隔离 QLoRA confound。\n  related_experiments:\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\n    role: corrected_eval\n    result: rel_f1=0.4034, neutral vs SFT\n  - exp_id: plan_012_dpo_ced\n    role: original_3ep\n    result: rel_f1=0.3429, mild degradation\n  - exp_id: plan_011_bf16_g8_step_eval\n    role: grpo_bf16_control\n    result: best=0.4341, mild not catastrophic\n  - exp_id: mvp2_grpo_ced_lr5e6_r1\n    role: grpo_qlora_original\n    result: rel_f1<0.02, catastrophic\n  depends_on: []\n- id: D069\n  date: 2026-05-15 23:44 UT\n===\nD069\n  date: 2026-05-15 23:44 UTC\n  summary: 修正 D068：evidence-extraction decoupling 是 RL-for-IE 通用现象，非 QLoRA 特有；severity\n    按方法分层\n  rationale: D068 判断\"catastrophic decoupling 是 QLoRA artifact\"不完整。Reviewer 指出 DPO\n    1ep→3ep 也呈现 decoupling（rel_f1 0.4034→0.3429 下降，evi_f1 0.8088→0.8403 上升），与 GRPO\n    方向一致仅程度不同。修正后的完整图景：(1) GRPO+QLoRA=catastrophic decoupling (rel_f1<0.02)；(2) GRPO+bf16=mild\n    decoupling (0.4549→0.434)；(3) DPO+bf16=gradual decoupling (0.4034→0.3429 over\n    epochs)；(4) RSFT=无 decoupling。结论：decoupling 是所有 RL 方法在结构化 IE 上的通用现象，QLoRA 放大其严重程度但不是唯一原因。RSFT（非\n    RL 的数据筛选）是唯一规避路径。Claim 2 应从\"GRPO fails\"升级为\"RL-for-IE universal decoupling + severity\n    hierarchy\"。plan_015 仍有价值（量化 QLoRA 放大效应）但不再是叙事关键。另需排查 Ign-F1=F1 的 eval pipeline\n    bug。\n  related_experiments:\n  - exp_id: eval_plan_012_dpo_1ep_fixed_r2\n    role: dpo_1ep_corrected\n    result: rel_f1=0.4034, evi_f1=0.8088\n  - exp_id: plan_012_dpo_ced\n    role: dpo_3ep\n    result: rel_f1=0.3429, evi_f1=0.8403, decoupling confirmed\n \n===\nD070\n  date: 2026-05-15 23:50 UTC\n  summary: Claim 4 重新定位：EDCR 从跨方法诊断指标降级为 per-relation-type/per-document 细粒度诊断工具\n  rationale: plan_003 EDCR diagnostic table 显示跨方法 EDCR 与 rel_f1 近乎完全反相关（Spearman=-0.965），与\n    evi_f1 相关性为零（0.002）。这意味着在方法级比较中 EDCR 不提供超出 rel_f1 的独立信息，原始 Claim 4\"EDCR 捕捉 Evi-F1\n    盲区\"在方法级不成立。但 per-relation-type 分析显示有意义的方差（date_of_birth EDCR≈0.1 vs head_of_government\n    EDCR≈0.95），说明 EDCR 在细粒度诊断上仍有价值。重新定位为\"per-relation/per-document 证据质量诊断工具\"，避免审稿人用一个相关性计算即击穿\n    Claim 4。\n  related_experiments:\n  - exp_id: plan_003_edcr_diagnostic\n    role: diagnostic_table\n    result: EDCR vs rel_f1 Spearman=-0.965, vs evi_f1 Spearman=0.002\n  depends_on: []\n- id: D071\n  date: 2026-05-15 23:50 UTC\n  summary: EDCR 定义存在 by-construction 混淆：当前 EDCR ≈ f(1/rel_f1)，不独立度量 evidence 质量。暂停\n    Claim 4，实现 TP-only EDCR 后重新评估\n  rationale: plan_003 诊断表显示 EDCR vs rel_f1 Spearman r=-0.9648, EDCR vs evi_f1 r=0.0022。机理：EDCR\n    = n_distractor/n_total 在全部预测上计算，rel_f1 低的模型预测大量错误关系→evidence 自动成为 distractor→推高\n  \n===\nD071\n  date: 2026-05-15 23:50 UTC\n  summary: EDCR 定义存在 by-construction 混淆：当前 EDCR ≈ f(1/rel_f1)，不独立度量 evidence 质量。暂停\n    Claim 4，实现 TP-only EDCR 后重新评估\n  rationale: plan_003 诊断表显示 EDCR vs rel_f1 Spearman r=-0.9648, EDCR vs evi_f1 r=0.0022。机理：EDCR\n    = n_distractor/n_total 在全部预测上计算，rel_f1 低的模型预测大量错误关系→evidence 自动成为 distractor→推高\n    EDCR。这是定义层面的混淆，非数据问题。修复方案：EDCR 改为仅在 TP triples 上计算（\"正确关系中 evidence 的忠实度\"），若 TP-only\n    EDCR 仍与 rel_f1 强相关则 Claim 4 需大幅削弱。plan_013（人工标注验证）暂停，等 TP-only EDCR 定义确认后再决定。\n  related_experiments:\n  - exp_id: plan_003_edcr_diagnostic\n    role: diagnostic\n    result: EDCR vs rel_f1 r=-0.965, EDCR vs evi_f1 r=0.002\n  depends_on: []\n- id: D072\n  date: 2026-05-16 00:00 UTC\n  summary: 'Claim 4 升级为双层论述: 方法级 EDCR (decoupling 量化) + per-relation EDCR (独立诊断工具)'\n  rationale: Per-relation EDCR 分析 (93 relation types) 显示 EDCR vs evi_f1 ρ=-0.064 (p=0.583)，完全独立。与方法级\n    ρ=-0.965 形成互补。方法级 EDCR 本质是 rel_f1 的变换，诊断价值有限；但 per-relation 粒度上 EDCR 捕捉到 evi_f1\n    看不到的信息（如 head_of_government E\n===\nD072\n  date: 2026-05-16 00:00 UTC\n  summary: 'Claim 4 升级为双层论述: 方法级 EDCR (decoupling 量化) + per-relation EDCR (独立诊断工具)'\n  rationale: Per-relation EDCR 分析 (93 relation types) 显示 EDCR vs evi_f1 ρ=-0.064 (p=0.583)，完全独立。与方法级\n    ρ=-0.965 形成互补。方法级 EDCR 本质是 rel_f1 的变换，诊断价值有限；但 per-relation 粒度上 EDCR 捕捉到 evi_f1\n    看不到的信息（如 head_of_government EDCR=0.956 但 evi_f1=0.875，证据看似好但 relation 抽取极差）。同时发现\n    evi_f1 vs rel_f1 在 per-relation 层面也近乎零相关 (ρ=-0.013)，说明 evidence quality 和 relation\n    extraction 在不同 relation type 间完全解耦——这是一个独立的发现，强化整篇论文的 decoupling narrative。\n  related_experiments:\n  - exp_id: plan_003_edcr_diagnostic\n    role: 方法级 EDCR 分析\n    result: ρ=-0.965 vs rel_f1\n  - exp_id: D070\n    role: per-relation EDCR 分析\n    result: EDCR vs evi_f1 ρ=-0.064, EDCR vs rel_f1 ρ=-0.793\n  depends_on:\n  - D070\n- id: D073\n  date: 2026-05-16 00:02 UTC\n  summary: 'EDCR 论文定义规范: 正文用 distractor count ratio (∈[0,1])，formula proxy 1-rel_f1/evi_f1\n    仅用于方法级快速对比；per-relation 表格须 n_pred≥10 过滤'\n  rationale: 'Reviewer \n===\nD073\n  date: 2026-05-16 00:02 UTC\n  summary: 'EDCR 论文定义规范: 正文用 distractor count ratio (∈[0,1])，formula proxy 1-rel_f1/evi_f1\n    仅用于方法级快速对比；per-relation 表格须 n_pred≥10 过滤'\n  rationale: 'Reviewer 指出两个问题: (1) EDCR formula 1-rel_f1/evi_f1 在 rel_f1>evi_f1 时为负(manufacturer=-0.1879)，名为\n    rate 却不在[0,1]，审稿人会质疑; (2) per-relation top/bottom 表被退化 case 主导(n_pred=0→EDCR=0,\n    TP=0→EDCR=1)，有 cherry-picking 嫌疑。解决方案: 论文正文 EDCR 定义为 distractor count ratio (cited\n    evidence 中非支撑性证据的比例，自然∈[0,1])；formula proxy 仅在方法级无逐预测 distractor 计数时使用，论文中注明是近似。per-relation\n    展示表格加 n_pred≥10 过滤。'\n  related_experiments:\n  - exp_id: plan_003_edcr_diagnostic\n    role: 方法级 EDCR\n    result: formula proxy 用于15个方法对比\n  - exp_id: D070\n    role: per-relation EDCR\n    result: 发现负值 case 和退化 case\n  depends_on:\n  - D072\n- id: D074\n  date: 2026-05-16 00:25 UTC\n  summary: r2 实际配置正确但已被 kill，r3 替代运行；argparse 静默忽略未知参数是代码隐患\n  rationale: 验证发现 rsft_trainer.py 的 argparse 不存在 --batch/--grad_accum/--lr/--epochs\n    参数，这些 flag 被静默忽略，实际使用默认值 \n===",
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

_source line 82_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the data I need. Let me compile the evidence table. Let me also check Ign-F1 numbers from the paper_framing.md summary table, cross-referencing with the registry data.

Key data points I've gathered:

**Claim 1: Evidence-grounded DocRE is a viable new capability**

SFT baseline (with evidence):
- quantized: rel_f1=0.4057, ign_f1=0.4057 (=40.57%), evi_f1=0.7979, evi_f1_joint=0.3117, edcr=0.7118


- no-quantize: rel_f1=0.4106, evi_f1=0.8013, evi_f1_joint=0.3216, edcr=0.7039

SFT no-evidence baseline shows rel_f1=0.4893, ign_f1=0.4893 (=48.93%), which means the evidence generation tax is roughly 8.36 percentage points. Though I'm seeing a discrepancy with paper_framing.md that reports different Ign-F1 values, so I need to reconcile those numbers.

Looking at the registry entries more carefully, rel_f1 and Ign-F1 appear to be distinct metrics, and the paper_framing table shows SFT no-evidence at Ign-F1=47.36 versus the baseline at 40.36, which doesn't quite match what the registry is reporting. Looking at the actual data from the subagent, I'm seeing that the registry's rel_f1 values don't consistently map to either Ign-F1 or F1 from the paper_framing table—sometimes they align with one, sometimes the other. I need to check what the registry's ign_f1 field actually contains to understand which metric is which. Now I'm seeing the corrected Ign-F1 values from the paper_framing table, which show meaningful differences from the standard F1 scores across all the key experiments. I'll use those as my primary source and fill in additional details from the registry data where needed. My plan is to organize the evidence around two main claims: first, that evidence-grounded DocRE represents a viable new capability based on the SFT and RSFT CED experiments, and second, that the severity of decoupling correlates with RL optimization pressure, which I'll demonstrate through the GR experiments.

For the remaining claims, I need to show that NLI-based scoring specifically improves RSFT quality by comparing the CED variant against flat-NLI across multiple seeds and ablations, and then demonstrate the diagnostic value of the EDCR dual-layer approach through per-relation analysis. I should also flag that the D076 protocol issue means four of my eight evaluations need to be rerun under a unified protocol before I can run paired t-tests.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "ba06629c-6e85-4897-b418-829076a0d093",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qowr4r96pxR8nkoLCy7SKu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4607,
      "cache_read_input_tokens": 47744,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4607
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

_source line 83_

Now I have all the data. Let me compile the evidence table.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "3de4a7e9-2837-460a-addc-374d48c404a2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qowr4r96pxR8nkoLCy7SKu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4607,
      "cache_read_input_tokens": 47744,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4607
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

_source line 84_

<details open><summary>🔧 Tool call — Write · `toolu_01K6i9bkDFhbhwsWqsVpKLN8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/paper_evidence_table.md",
  "content": "# Paper Evidence Table — FREIGE (EMNLP 2026)\n\n> **Compiled**: 2026-05-16\n> **Source**: experiment registry + paper_framing.md + decisions D067-D076\n> **Convention**: Ign-F1/F1 as percentage (e.g., 40.36); rel_f1/evi_f1 as decimal (e.g., 0.4036) when directly from registry. Paper reports Ign-F1 in main table, F1 in appendix (D071).\n\n---\n\n## Claim 1: Evidence-grounded DocRE is a viable new capability\n\n**Statement**: FREIGE is the first LLM method to simultaneously output (head, relation, tail, [evidence]) on DocRED. Evidence generation has a ~7pp Ign-F1 cost; RSFT recovers most of it; CED reranker recovers 97%.\n\n### Supporting Experiments\n\n| exp_id | method | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | Evi-F1 (joint) | EDCR | protocol | notes |\n|--------|--------|------|-------------|--------|--------|----------------|------|----------|-------|\n| eval_plan_014_sft_no_evidence | SFT no-evidence | 42 | 48.93 | 47.36 | — | — | — | standard | Upper bound: no evidence burden |\n| eval_sft_baseline_noquant | SFT baseline (noquant) | 42 | 41.06 | 40.36 | 80.13 | 32.16 | 0.7039 | standard | Primary SFT baseline for paper |\n| mvp2_eval_sft_baseline | SFT baseline (quantized) | 42 | 40.57 | 40.57 | 79.79 | 31.17 | 0.7118 | unified (r3) | Quantized; -0.49pp vs noquant |\n| mvp2_eval_rsft_s43_r2 | RSFT CED k=1 | 43 | 46.83 | 45.85 | 81.56 | 37.11 | 0.6388 | original | **Best RSFT seed** |\n| mvp2_rsft_train_r1_s44 | RSFT CED k=1 | 44 | 46.55 | 45.51 | 80.87 | 37.13 | 0.6350 | original | |\n| mvp2_eval_rsft_r1 | RSFT CED k=1 (3ep) | 42 | 44.49 | 43.63 | 81.87 | 34.68 | 0.6565 | original | 3-epoch; s42 |\n| mvp2_eval_rsft_r2a | RSFT CED k=1 (1ep) | 42 | 44.94 | 44.01 | 81.08 | 35.09 | 0.6641 | original | 1-epoch ablation α=128 |\n| mvp2_eval_rsft_r2b | RSFT CED k=1 (1ep) | 42 | 44.93 | 44.10 | 81.28 | 34.90 | 0.6609 | original | 1-epoch ablation α=32 |\n| mvp2_ced_reranker_poc | CED reranker (N=8) | 42 | 48.64 | TBD | 81.88 | — | 0.6156 | standard | **Best practical: 97% recovery** |\n| plan_004_dreeam_baseline | DREEAM (RoBERTa-large) | 66 | 63.57† | 61.72† | 54.01† | — | — | encoder | †Encoder model, different paradigm |\n\n### Key Numbers for Paper\n\n- **Evidence generation tax**: Ign-F1 47.36 (no-evidence) → 40.36 (with evidence) = **-7.00pp** cost of faithfulness\n- **RSFT recovery**: Best RSFT CED (s43) Ign-F1 = 45.85, recovering **5.49pp** of the 7.00pp gap (78.4% recovery)\n- **CED reranker**: F1=48.64 (only -0.29pp below no-evidence F1=48.93), evi_f1=0.8188 → **recovers 97% of evidence cost with no training**\n- **RSFT CED 3-seed mean** (s42/s43/s44, original protocol): rel_f1=0.4596±0.0127, evi_f1=0.8143±0.0051\n- **All 4 RSFT CED configs > SFT baseline**: Δ Ign-F1 = +3.27 to +5.49pp\n- **DREEAM comparison**: Encoder model gets F1=63.57 / Evi-F1=54.01 — different paradigm (classification vs generation), not directly comparable for RE but sets evidence baseline context\n- **Joint Evi-F1** (unconditional): SFT baseline 31.17 → best RSFT 37.13 (+5.96pp)\n\n### Evidence Gaps\n\n- [ ] **CED reranker Ign-F1**: Currently only F1 available (48.64); need Ign-F1 for main table\n- [ ] **D076 unified protocol reevals** (reeval_ced_s42, reeval_ced_s44): PREPARING — s42 used wrong checkpoint, s44 used wrong seed\n- [ ] **RSFT CED s45**: eval RUNNING — needed for 4+ seed statistics\n- [ ] **DREEAM-protocol Evi-F1 alignment** (D041): Not yet done — conditional vs joint Evi-F1 not directly comparable with encoder baselines\n- [ ] **Test set evaluation** (plan_002): Not started — requires CodaLab submission\n- [ ] **Post-hoc retrieval baseline** (SFT + BM25 evidence): Not started — RC10\n\n---\n\n## Claim 2: RL optimization pressure correlates with evidence-extraction decoupling severity\n\n**Statement**: Decoupling severity forms a continuous spectrum — GRPO QLoRA (catastrophic) > GRPO bf16 (mild) > DPO (gradual) > RSFT (none). QLoRA is a catastrophic amplifier, not the root cause. Decoupling is an intra-task multi-objective trade-off (not inter-task forgetting).\n\n### Supporting Experiments\n\n| exp_id | method | seed | F1 (rel_f1) | Evi-F1 | EDCR | Δ vs SFT (F1) | protocol | notes |\n|--------|--------|------|-------------|--------|------|---------------|----------|-------|\n| mvp2_eval_sft_baseline | SFT baseline | 42 | 40.57 | 79.79 | 0.7118 | — | unified | Reference point |\n| mvp2_eval_lr5e6_r1_ckpt100 | GRPO QLoRA (lr=5e-6) | 42 | **1.38** | **85.04** | **0.9876** | **-39.19pp** | original | Catastrophic decoupling |\n| mvp2_eval_ced_kl001_r4_step100 | GRPO QLoRA (lr=5e-5) | 42 | 21.67 | 57.46 | 0.8539 | -18.90pp | original | Less catastrophic but still severe |\n| plan_011_bf16_g8_step_eval (step30) | GRPO bf16 G=8 | 42 | 43.40 | 80.63 | 0.6807 | +2.83pp | original | Mild decline from ckpt-100 |\n| plan_011_bf16_g8_step_eval (step70) | GRPO bf16 G=8 | 42 | 43.41 | 80.99 | 0.6685 | +2.84pp | original | Non-monotonic |\n| plan_011_grpo_g8_bf16_eval (ckpt100) | GRPO bf16 G=8 | 42 | **45.49** | 80.86 | 0.6318 | **+4.92pp** | original | Best GRPO bf16; **no catastrophic forgetting** |\n| eval_plan_012_dpo_1ep_fixed_r2 | DPO bf16 1ep | 42 | 40.34 | 80.88 | 0.7139 | -0.23pp | original | Neutral — matches SFT |\n| plan_012_dpo_ced | DPO bf16 3ep | 42 | **34.29** | **84.03** | **0.7294** | **-6.28pp** | original | Gradual decoupling (overfit) |\n| mvp2_eval_rsft_s43_r2 | RSFT CED | 43 | 46.83 | 81.56 | 0.6388 | +6.26pp | original | **No decoupling** |\n\n### Decoupling Spectrum (for paper figure/table)\n\n| Method | Quantization | Optimization Pressure | rel_f1 | Δ rel_f1 | evi_f1 | EDCR | Severity |\n|--------|-------------|----------------------|--------|----------|--------|------|----------|\n| GRPO (lr=5e-6) | QLoRA 4-bit | High (100 steps, G=8) | 0.0138 | -0.3919 | 0.8504 | 0.9876 | **Catastrophic** |\n| GRPO (lr=5e-5) | QLoRA 4-bit | Moderate (100 steps, G=8) | 0.2167 | -0.1890 | 0.5746 | 0.8539 | Severe |\n| DPO 3ep | bf16 | Moderate (3 epochs) | 0.3429 | -0.0628 | 0.8403 | 0.7294 | **Gradual** |\n| GRPO G=8 (ckpt30-70) | bf16 | Active (30-70 steps) | ~0.434 | -0.021 | ~0.808 | ~0.68 | **Mild** |\n| DPO 1ep | bf16 | Low (1 epoch) | 0.4034 | -0.0023 | 0.8088 | 0.7139 | Neutral |\n| GRPO G=8 (ckpt100) | bf16 | Converged (100 steps) | 0.4549 | +0.0492 | 0.8086 | 0.6318 | None |\n| RSFT CED (best) | — | Offline (data filter) | 0.4683 | +0.0626 | 0.8156 | 0.6388 | **None** |\n\n### Key Numbers for Paper\n\n- **QLoRA amplification**: bf16 GRPO rel_f1=0.4549 vs QLoRA GRPO rel_f1=0.0138 — QLoRA turns mild (-2pp early) into catastrophic (-39pp)\n- **GRPO bf16 trajectory**: ckpt-80→90→100: rel_f1 = 0.4456→0.4523→0.4549 (monotonically improving, no forgetting)\n- **GRPO bf16 early checkpoints** show mild decline: step30=0.434, step50=0.4276, step70=0.4341 (all below ckpt-100's 0.4549) — confirms transient mild decoupling during training, recovers by convergence\n- **DPO gradual decay**: 1ep rel_f1=0.4034 → 3ep rel_f1=0.3429 (evi_f1 simultaneously rises 0.8088→0.8403)\n- **DPO narrative (D067/D068/D069)**: DPO is neutral/gradual, not \"failed\" — it's a middle data point on the spectrum, confirming decoupling is universal across RL methods\n- **Intra-task vs inter-task** (D069): This is NOT catastrophic forgetting of pretrained knowledge; it's competition between RE and evidence objectives within the same task\n\n### Evidence Gaps\n\n- [ ] **GRPO bf16 Ign-F1**: Currently reporting F1; paper_framing notes Ign-F1=45.59 > F1=~43.4 \"因 train triples 过滤效应\" — this inversion needs explanation in paper\n- [ ] **DPO 3ep Ign-F1**: TBD in paper_framing table\n- [ ] **GRPO QLoRA (lr=5e-6) Ign-F1**: TBD\n- [ ] **Connecting to reward overoptimization literature** (RC9): Need explicit Gao et al. 2023 citation\n- [ ] **QuRL/QaRL literature** (D076 framing note): Supports QLoRA amplification narrative but not yet in Related Work\n\n---\n\n## Claim 3: NLI-based scoring improves RSFT quality (CED vs flat-NLI ablation)\n\n**Statement**: Both CED and flat-NLI outperform random/no scoring. CED vs flat-NLI difference is statistically uncertain — CED may be \"one possible scoring function\" rather than strictly superior.\n\n### Supporting Experiments\n\n#### CED RSFT (top_k=1)\n\n| exp_id | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | D076 unified? | notes |\n|--------|------|-------------|--------|--------|------|---------------|-------|\n| mvp2_eval_rsft_r1 | 42 (3ep) | 44.49 | 43.63 | 81.87 | 0.6565 | No | 3-epoch run |\n| mvp2_eval_rsft_r2a | 42 (1ep) | 44.94 | 44.01 | 81.08 | 0.6641 | No | 1ep, α=128 |\n| mvp2_eval_rsft_r2b | 42 (1ep) | 44.93 | 44.10 | 81.28 | 0.6609 | No | 1ep, α=32 |\n| mvp2_eval_rsft_s43_r2 | 43 | 46.83 | 45.85 | 81.56 | 0.6388 | No | Best seed |\n| mvp2_rsft_train_r1_s44 | 44 | 46.55 | 45.51 | 80.87 | 0.6350 | No | |\n| eval_rsft_ced_s45 | 45 | — | — | — | — | — | **RUNNING** |\n| reeval_ced_s42 | 42 | — | — | — | — | Yes | **PREPARING** (fixes wrong ckpt) |\n| reeval_ced_s44 | 44 | — | — | — | — | Yes | **PREPARING** (fixes wrong seed) |\n\n**CED 3-seed mean (s42-r1/s43/s44)**: rel_f1 = 0.4596 ± 0.0127, evi_f1 = 0.8143 ± 0.0051\n\n#### flat-NLI RSFT (top_k=1)\n\n| exp_id | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | D076 unified? | notes |\n|--------|------|-------------|--------|--------|------|---------------|-------|\n| eval_plan_001_flat_nli | 42 | 45.39 | 44.49 | 80.43 | 0.6431 | No | |\n| reeval_flat_nli_s43 | 43 | 45.23 | TBD | 81.58 | 0.6505 | Partial (fixed adapter, batch=16) | |\n| eval_flat_nli_s44 | 44 | 46.15 | 46.15 | 81.31 | 0.6458 | No | |\n| eval_flat_nli_seed45 | 45 | 45.51 | 45.51 | 81.54 | 0.6521 | No | |\n| reeval_flat_nli_s42 | 42 | — | — | — | — | Yes | **PREPARING** |\n| reeval_flat_nli_s43_r2 | 43 | — | — | — | — | Yes | **RUNNING** |\n\n**flat-NLI 4-seed mean (s42/s43/s44/s45)**: rel_f1 = 0.4557 ± 0.0039\n\n#### top_k Ablation\n\n| exp_id | method | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | notes |\n|--------|--------|------|-------------|--------|--------|------|-------|\n| CED 3-seed mean | CED k=1 | s42/43/44 | 45.96 | 45.00 | 81.43 | 0.6434 | |\n| reeval_rsft_topk3 | CED k=3 | 42 | 44.54 | 43.64 | 80.88 | 0.6635 | D076 corrected ign_f1 |\n\n**Δ (k=3 vs k=1 mean)**: Ign-F1 **-1.36pp**, rel_f1 **-1.42pp**, evi_f1 **-0.55pp**, EDCR +0.02\n- Training data: k=1 → 2718 samples (12.4%), k=3 → 8037 samples (37%) — 2.96× more data but lower quality\n- Scoring quality: k=1 mean_f1=0.6157, mean_ced=0.6683 → k=3 mean_f1=0.5761, mean_ced=0.6205\n\n### Key Numbers for Paper\n\n- **CED vs flat-NLI head-to-head** (current data, NOT D076-unified):\n  - CED 3-seed mean rel_f1 = 0.4596 vs flat-NLI 4-seed mean = 0.4557 → Δ = **+0.39pp** (not significant)\n  - Dream reported p-values: 0.08 / 0.38 / 0.12 — not statistically significant\n- **Both > SFT baseline**: CED +5.39pp, flat-NLI +5.00pp (Ign-F1 vs SFT 40.36)\n- **top_k=1 > top_k=3**: Scoring precision matters more than data quantity; rank 2-3 samples dilute quality\n- **Status**: CED ≈ flat-NLI statistically indistinguishable → CED is \"one possible scoring function,\" not independently superior (C3 降级)\n\n### Evidence Gaps\n\n- [ ] **D076 unified protocol**: 4/8 evals need rerunning before paired t-test is valid (reeval_ced_s42, reeval_ced_s44, reeval_flat_nli_s42, reeval_flat_nli_s43_r2)\n- [ ] **CED s45 eval**: Still RUNNING — needed for 4-seed CED statistics\n- [ ] **Paired t-test**: Cannot compute until all seeds are under unified protocol\n- [ ] **top_k=3 additional seeds**: Only 1 seed; direction consistent but no significance test possible — present as supplementary ablation row, not independent claim\n\n---\n\n## Claim 4: EDCR dual-layer diagnostic value\n\n**Statement**: EDCR quantifies evidence-extraction decoupling at method level (echoing Claim 2 spectrum) and provides relation-type diagnostic information orthogonal to Evi-F1 at per-relation level.\n\n### Supporting Experiments\n\n| exp_id | analysis | result | notes |\n|--------|----------|--------|-------|\n| plan_003_edcr_diagnostic | Method-level EDCR table (15 methods) | EDCR vs rel_f1 Spearman ρ=-0.9648 (p=0.0001); EDCR vs evi_f1 ρ=0.0022 (p=0.9941) | EDCR ≈ transform of rel_f1 at method level (D071 flags by-construction concern) |\n| D070 per-relation analysis | Per-relation EDCR (93 types, ≥5 samples) | EDCR vs evi_f1 ρ=**-0.064** (p=0.58) → **completely independent**; EDCR vs rel_f1 ρ=-0.793 (p<0.001) | 76 types with non-zero data |\n| D070 per-relation analysis | Per-relation evi_f1 vs rel_f1 | ρ=-0.013 (p=0.91) → evidence quality and extraction completely decoupled across relation types | Independent finding supporting paper narrative |\n\n### EDCR Method-Level Summary\n\n| Method | EDCR | rel_f1 | evi_f1 | interpretation |\n|--------|------|--------|--------|----------------|\n| GRPO QLoRA (lr=5e-6) | 0.9876 | 0.0138 | 0.8504 | Pathological: high evidence, zero extraction |\n| GRPO QLoRA (lr=5e-5) | 0.8539 | 0.2167 | 0.5746 | Severe decoupling |\n| DPO 3ep | 0.7294 | 0.3429 | 0.8403 | Moderate decoupling |\n| SFT baseline | 0.7118 | 0.4057 | 0.7979 | Reference |\n| DPO 1ep | 0.7139 | 0.4034 | 0.8088 | ≈ SFT level |\n| RSFT r2a (1ep) | 0.6641 | 0.4494 | 0.8108 | Improved |\n| RSFT CED k=3 | 0.6635 | 0.4454 | 0.8088 | Improved |\n| RSFT r2b (1ep) | 0.6609 | 0.4493 | 0.8128 | Improved |\n| RSFT CED s42 (3ep) | 0.6565 | 0.4449 | 0.8187 | Improved |\n| flat-NLI s43 | 0.6505 | 0.4523 | 0.8158 | Improved |\n| flat-NLI s44 | 0.6458 | 0.4615 | 0.8131 | Improved |\n| flat-NLI s42 | 0.6431 | 0.4539 | 0.8043 | Improved |\n| RSFT CED s43 | 0.6388 | 0.4683 | 0.8156 | Best RSFT |\n| RSFT CED s44 | 0.6350 | 0.4655 | 0.8087 | Near best |\n| GRPO bf16 G=8 | 0.6318 | 0.4549 | 0.8086 | Best GRPO (no decoupling) |\n| CED reranker | 0.6156 | 0.4864 | 0.8188 | **Best overall** |\n\n### Per-Relation Exemplars (D070)\n\n| Relation Type | EDCR | evi_f1 | rel_f1 | interpretation |\n|---------------|------|--------|--------|----------------|\n| date_of_birth | 0.118 | high | high | High faithfulness — easy relation |\n| head_of_government | 0.956 | 0.875 | low | High evidence quality but poor extraction — EDCR catches what evi_f1 misses |\n\n### Key Numbers for Paper\n\n- **Layer 1 (method-level)**: EDCR identifies pathological models (GRPO QLoRA: EDCR≈1.0) — works as decoupling meter, echoes Claim 2\n- **Layer 2 (per-relation)**: EDCR vs evi_f1 ρ=-0.064 → completely independent signals at per-relation granularity\n- **D071 caveat**: Method-level EDCR ≈ f(1/rel_f1) by construction — when model predicts wrong relations, evidence automatically becomes \"distractor.\" Paper must acknowledge this and frame method-level EDCR as decoupling measure, not independent evidence quality metric\n- **D073 definition**: Paper uses distractor count ratio (∈[0,1]) definition; formula proxy 1-rel_f1/evi_f1 only for method-level quick comparison; per-relation tables require n_pred≥10 filter\n\n### Evidence Gaps\n\n- [ ] **100-example human annotation validation** (plan_013): Not started — needed for RC6\n- [ ] **TP-only EDCR** (D071): Not implemented — needed to address by-construction confound; if TP-only EDCR still correlates with rel_f1, Claim 4 method-level value is weak\n- [ ] **More per-relation exemplars**: Need to populate full table with n_pred≥10 filter (D073)\n\n---\n\n## Cross-Claim Protocol Issues\n\n### D076 Unified Protocol Reeval Status\n\nThe following evals have protocol inconsistencies that prevent valid paired t-test (Claim 3):\n\n| exp_id | issue | unified reeval | status |\n|--------|-------|---------------|--------|\n| CED s42 (mvp2_eval_rsft_r2b_maxtok1536_r2) | Wrong checkpoint (r2b α=32 instead of ckpt-510 α=128), batch_size=8, max_new_tokens=1536 | reeval_ced_s42 | PREPARING |\n| CED s44 (mvp2_rsft_train_r1_s44) | Seed=42 in eval (should be 44) | reeval_ced_s44 | PREPARING |\n| flat-NLI s42 (eval_plan_001_flat_nli) | batch_size=16 | reeval_flat_nli_s42 | PREPARING |\n| flat-NLI s43 (reeval_flat_nli_s43) | batch_size=16 | reeval_flat_nli_s43_r2 | RUNNING |\n\n**Unified protocol**: batch_size=4, --no-quantize, --sft_adapter, max_new_tokens=1024, correct seed.\n\n**Impact**: Old protocol data can be used for directional claims but NOT for paired t-test (Claim 3 significance). All 8 CED/flat-NLI evals must be under unified protocol before statistical comparison.\n\n### Ign-F1 vs F1 Issue\n\n- Most registry entries show ign_f1 = rel_f1 (suspected eval pipeline bug, D069)\n- Paper_framing table has corrected Ign-F1 values that differ from F1 (e.g., SFT no-evidence: Ign-F1=47.36 vs F1=48.93)\n- D071: \"Ign-F1 修正后排名无实质变化\"\n- **Paper uses Ign-F1 in main table** per D071\n\n### Experiments Still Running / Pending\n\n| exp_id | purpose | status | blocking |\n|--------|---------|--------|----------|\n| eval_rsft_ced_s43 | CED s43 re-eval | RUNNING | C3 statistics |\n| eval_rsft_ced_s45 | CED s45 (new seed) | RUNNING | C3 statistics |\n| eval_plan_014_no_evidence_r2 | SFT no-evidence re-eval | RUNNING | — |\n| reeval_ced_s42 | Unified protocol CED s42 | PREPARING | C3 paired t-test |\n| reeval_ced_s44 | Unified protocol CED s44 | PREPARING | C3 paired t-test |\n| reeval_flat_nli_s42 | Unified protocol flat-NLI s42 | PREPARING | C3 paired t-test |\n| reeval_flat_nli_s43_r2 | Unified protocol flat-NLI s43 | RUNNING | C3 paired t-test |\n| plan_002 | Test set evaluation | PLANNED | C1 final numbers |\n| plan_013 | EDCR human annotation (100 examples) | PLANNED | C4 validation |\n\n---\n\n## Summary: Paper-Ready vs Gaps\n\n### Paper-Ready Numbers\n\n1. **Evidence tax**: 47.36 → 40.36 = -7.00pp Ign-F1 (plan_014 vs noquant SFT)\n2. **CED reranker recovery**: F1=48.64, only -0.29pp below no-evidence (plan_005)\n3. **RSFT CED best**: Ign-F1=45.85, +5.49pp over SFT (s43)\n4. **Decoupling spectrum**: Complete data for GRPO QLoRA / GRPO bf16 / DPO / RSFT\n5. **QLoRA amplification**: bf16 0.4549 vs QLoRA 0.0138 (plan_011 vs QLoRA runs)\n6. **EDCR per-relation independence**: ρ=-0.064 vs evi_f1 (D070)\n7. **top_k ablation**: k=1 > k=3, precision > quantity (plan_008)\n8. **DREEAM baseline**: F1=63.57, Evi-F1=54.01 reproduced (plan_004)\n\n### Critical Gaps (blocking paper submission)\n\n1. **D076 unified reevals** — blocking Claim 3 statistical test\n2. **CED reranker Ign-F1** — needed for main table\n3. **Test set evaluation** (plan_002) — no official numbers yet\n4. **DREEAM-protocol Evi-F1 alignment** — cross-paradigm evidence comparison\n\n### Nice-to-Have (strengthen but not blocking)\n\n1. EDCR human validation (plan_013) — RC6\n2. Post-hoc retrieval baseline (SFT + BM25) — RC10\n3. Model size ablation (plan_006) — RC4\n4. TP-only EDCR (D071) — method-level confound\n5. Re-DocRED extension (plan_007) — RC4\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "43e34f20-a9f4-4223-b627-84087eea54fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qowr4r96pxR8nkoLCy7SKu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4607,
      "cache_read_input_tokens": 47744,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4607
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

_source line 85 · 2026-05-16T03:28:42.723Z_

<details><summary>↩ Tool result · `toolu_01K6i9bkDFhbhwsWqsVpKLN8`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/paper_evidence_table.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "885c0001-b9a2-45f9-b772-5878a5e124a4",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/paper_evidence_table.md",
    "content": "# Paper Evidence Table — FREIGE (EMNLP 2026)\n\n> **Compiled**: 2026-05-16\n> **Source**: experiment registry + paper_framing.md + decisions D067-D076\n> **Convention**: Ign-F1/F1 as percentage (e.g., 40.36); rel_f1/evi_f1 as decimal (e.g., 0.4036) when directly from registry. Paper reports Ign-F1 in main table, F1 in appendix (D071).\n\n---\n\n## Claim 1: Evidence-grounded DocRE is a viable new capability\n\n**Statement**: FREIGE is the first LLM method to simultaneously output (head, relation, tail, [evidence]) on DocRED. Evidence generation has a ~7pp Ign-F1 cost; RSFT recovers most of it; CED reranker recovers 97%.\n\n### Supporting Experiments\n\n| exp_id | method | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | Evi-F1 (joint) | EDCR | protocol | notes |\n|--------|--------|------|-------------|--------|--------|----------------|------|----------|-------|\n| eval_plan_014_sft_no_evidence | SFT no-evidence | 42 | 48.93 | 47.36 | — | — | — | standard | Upper bound: no evidence burden |\n| eval_sft_baseline_noquant | SFT baseline (noquant) | 42 | 41.06 | 40.36 | 80.13 | 32.16 | 0.7039 | standard | Primary SFT baseline for paper |\n| mvp2_eval_sft_baseline | SFT baseline (quantized) | 42 | 40.57 | 40.57 | 79.79 | 31.17 | 0.7118 | unified (r3) | Quantized; -0.49pp vs noquant |\n| mvp2_eval_rsft_s43_r2 | RSFT CED k=1 | 43 | 46.83 | 45.85 | 81.56 | 37.11 | 0.6388 | original | **Best RSFT seed** |\n| mvp2_rsft_train_r1_s44 | RSFT CED k=1 | 44 | 46.55 | 45.51 | 80.87 | 37.13 | 0.6350 | original | |\n| mvp2_eval_rsft_r1 | RSFT CED k=1 (3ep) | 42 | 44.49 | 43.63 | 81.87 | 34.68 | 0.6565 | original | 3-epoch; s42 |\n| mvp2_eval_rsft_r2a | RSFT CED k=1 (1ep) | 42 | 44.94 | 44.01 | 81.08 | 35.09 | 0.6641 | original | 1-epoch ablation α=128 |\n| mvp2_eval_rsft_r2b | RSFT CED k=1 (1ep) | 42 | 44.93 | 44.10 | 81.28 | 34.90 | 0.6609 | original | 1-epoch ablation α=32 |\n| mvp2_ced_reranker_poc | CED reranker (N=8) | 42 | 48.64 | TBD | 81.88 | — | 0.6156 | standard | **Best practical: 97% recovery** |\n| plan_004_dreeam_baseline | DREEAM (RoBERTa-large) | 66 | 63.57† | 61.72† | 54.01† | — | — | encoder | †Encoder model, different paradigm |\n\n### Key Numbers for Paper\n\n- **Evidence generation tax**: Ign-F1 47.36 (no-evidence) → 40.36 (with evidence) = **-7.00pp** cost of faithfulness\n- **RSFT recovery**: Best RSFT CED (s43) Ign-F1 = 45.85, recovering **5.49pp** of the 7.00pp gap (78.4% recovery)\n- **CED reranker**: F1=48.64 (only -0.29pp below no-evidence F1=48.93), evi_f1=0.8188 → **recovers 97% of evidence cost with no training**\n- **RSFT CED 3-seed mean** (s42/s43/s44, original protocol): rel_f1=0.4596±0.0127, evi_f1=0.8143±0.0051\n- **All 4 RSFT CED configs > SFT baseline**: Δ Ign-F1 = +3.27 to +5.49pp\n- **DREEAM comparison**: Encoder model gets F1=63.57 / Evi-F1=54.01 — different paradigm (classification vs generation), not directly comparable for RE but sets evidence baseline context\n- **Joint Evi-F1** (unconditional): SFT baseline 31.17 → best RSFT 37.13 (+5.96pp)\n\n### Evidence Gaps\n\n- [ ] **CED reranker Ign-F1**: Currently only F1 available (48.64); need Ign-F1 for main table\n- [ ] **D076 unified protocol reevals** (reeval_ced_s42, reeval_ced_s44): PREPARING — s42 used wrong checkpoint, s44 used wrong seed\n- [ ] **RSFT CED s45**: eval RUNNING — needed for 4+ seed statistics\n- [ ] **DREEAM-protocol Evi-F1 alignment** (D041): Not yet done — conditional vs joint Evi-F1 not directly comparable with encoder baselines\n- [ ] **Test set evaluation** (plan_002): Not started — requires CodaLab submission\n- [ ] **Post-hoc retrieval baseline** (SFT + BM25 evidence): Not started — RC10\n\n---\n\n## Claim 2: RL optimization pressure correlates with evidence-extraction decoupling severity\n\n**Statement**: Decoupling severity forms a continuous spectrum — GRPO QLoRA (catastrophic) > GRPO bf16 (mild) > DPO (gradual) > RSFT (none). QLoRA is a catastrophic amplifier, not the root cause. Decoupling is an intra-task multi-objective trade-off (not inter-task forgetting).\n\n### Supporting Experiments\n\n| exp_id | method | seed | F1 (rel_f1) | Evi-F1 | EDCR | Δ vs SFT (F1) | protocol | notes |\n|--------|--------|------|-------------|--------|------|---------------|----------|-------|\n| mvp2_eval_sft_baseline | SFT baseline | 42 | 40.57 | 79.79 | 0.7118 | — | unified | Reference point |\n| mvp2_eval_lr5e6_r1_ckpt100 | GRPO QLoRA (lr=5e-6) | 42 | **1.38** | **85.04** | **0.9876** | **-39.19pp** | original | Catastrophic decoupling |\n| mvp2_eval_ced_kl001_r4_step100 | GRPO QLoRA (lr=5e-5) | 42 | 21.67 | 57.46 | 0.8539 | -18.90pp | original | Less catastrophic but still severe |\n| plan_011_bf16_g8_step_eval (step30) | GRPO bf16 G=8 | 42 | 43.40 | 80.63 | 0.6807 | +2.83pp | original | Mild decline from ckpt-100 |\n| plan_011_bf16_g8_step_eval (step70) | GRPO bf16 G=8 | 42 | 43.41 | 80.99 | 0.6685 | +2.84pp | original | Non-monotonic |\n| plan_011_grpo_g8_bf16_eval (ckpt100) | GRPO bf16 G=8 | 42 | **45.49** | 80.86 | 0.6318 | **+4.92pp** | original | Best GRPO bf16; **no catastrophic forgetting** |\n| eval_plan_012_dpo_1ep_fixed_r2 | DPO bf16 1ep | 42 | 40.34 | 80.88 | 0.7139 | -0.23pp | original | Neutral — matches SFT |\n| plan_012_dpo_ced | DPO bf16 3ep | 42 | **34.29** | **84.03** | **0.7294** | **-6.28pp** | original | Gradual decoupling (overfit) |\n| mvp2_eval_rsft_s43_r2 | RSFT CED | 43 | 46.83 | 81.56 | 0.6388 | +6.26pp | original | **No decoupling** |\n\n### Decoupling Spectrum (for paper figure/table)\n\n| Method | Quantization | Optimization Pressure | rel_f1 | Δ rel_f1 | evi_f1 | EDCR | Severity |\n|--------|-------------|----------------------|--------|----------|--------|------|----------|\n| GRPO (lr=5e-6) | QLoRA 4-bit | High (100 steps, G=8) | 0.0138 | -0.3919 | 0.8504 | 0.9876 | **Catastrophic** |\n| GRPO (lr=5e-5) | QLoRA 4-bit | Moderate (100 steps, G=8) | 0.2167 | -0.1890 | 0.5746 | 0.8539 | Severe |\n| DPO 3ep | bf16 | Moderate (3 epochs) | 0.3429 | -0.0628 | 0.8403 | 0.7294 | **Gradual** |\n| GRPO G=8 (ckpt30-70) | bf16 | Active (30-70 steps) | ~0.434 | -0.021 | ~0.808 | ~0.68 | **Mild** |\n| DPO 1ep | bf16 | Low (1 epoch) | 0.4034 | -0.0023 | 0.8088 | 0.7139 | Neutral |\n| GRPO G=8 (ckpt100) | bf16 | Converged (100 steps) | 0.4549 | +0.0492 | 0.8086 | 0.6318 | None |\n| RSFT CED (best) | — | Offline (data filter) | 0.4683 | +0.0626 | 0.8156 | 0.6388 | **None** |\n\n### Key Numbers for Paper\n\n- **QLoRA amplification**: bf16 GRPO rel_f1=0.4549 vs QLoRA GRPO rel_f1=0.0138 — QLoRA turns mild (-2pp early) into catastrophic (-39pp)\n- **GRPO bf16 trajectory**: ckpt-80→90→100: rel_f1 = 0.4456→0.4523→0.4549 (monotonically improving, no forgetting)\n- **GRPO bf16 early checkpoints** show mild decline: step30=0.434, step50=0.4276, step70=0.4341 (all below ckpt-100's 0.4549) — confirms transient mild decoupling during training, recovers by convergence\n- **DPO gradual decay**: 1ep rel_f1=0.4034 → 3ep rel_f1=0.3429 (evi_f1 simultaneously rises 0.8088→0.8403)\n- **DPO narrative (D067/D068/D069)**: DPO is neutral/gradual, not \"failed\" — it's a middle data point on the spectrum, confirming decoupling is universal across RL methods\n- **Intra-task vs inter-task** (D069): This is NOT catastrophic forgetting of pretrained knowledge; it's competition between RE and evidence objectives within the same task\n\n### Evidence Gaps\n\n- [ ] **GRPO bf16 Ign-F1**: Currently reporting F1; paper_framing notes Ign-F1=45.59 > F1=~43.4 \"因 train triples 过滤效应\" — this inversion needs explanation in paper\n- [ ] **DPO 3ep Ign-F1**: TBD in paper_framing table\n- [ ] **GRPO QLoRA (lr=5e-6) Ign-F1**: TBD\n- [ ] **Connecting to reward overoptimization literature** (RC9): Need explicit Gao et al. 2023 citation\n- [ ] **QuRL/QaRL literature** (D076 framing note): Supports QLoRA amplification narrative but not yet in Related Work\n\n---\n\n## Claim 3: NLI-based scoring improves RSFT quality (CED vs flat-NLI ablation)\n\n**Statement**: Both CED and flat-NLI outperform random/no scoring. CED vs flat-NLI difference is statistically uncertain — CED may be \"one possible scoring function\" rather than strictly superior.\n\n### Supporting Experiments\n\n#### CED RSFT (top_k=1)\n\n| exp_id | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | D076 unified? | notes |\n|--------|------|-------------|--------|--------|------|---------------|-------|\n| mvp2_eval_rsft_r1 | 42 (3ep) | 44.49 | 43.63 | 81.87 | 0.6565 | No | 3-epoch run |\n| mvp2_eval_rsft_r2a | 42 (1ep) | 44.94 | 44.01 | 81.08 | 0.6641 | No | 1ep, α=128 |\n| mvp2_eval_rsft_r2b | 42 (1ep) | 44.93 | 44.10 | 81.28 | 0.6609 | No | 1ep, α=32 |\n| mvp2_eval_rsft_s43_r2 | 43 | 46.83 | 45.85 | 81.56 | 0.6388 | No | Best seed |\n| mvp2_rsft_train_r1_s44 | 44 | 46.55 | 45.51 | 80.87 | 0.6350 | No | |\n| eval_rsft_ced_s45 | 45 | — | — | — | — | — | **RUNNING** |\n| reeval_ced_s42 | 42 | — | — | — | — | Yes | **PREPARING** (fixes wrong ckpt) |\n| reeval_ced_s44 | 44 | — | — | — | — | Yes | **PREPARING** (fixes wrong seed) |\n\n**CED 3-seed mean (s42-r1/s43/s44)**: rel_f1 = 0.4596 ± 0.0127, evi_f1 = 0.8143 ± 0.0051\n\n#### flat-NLI RSFT (top_k=1)\n\n| exp_id | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | D076 unified? | notes |\n|--------|------|-------------|--------|--------|------|---------------|-------|\n| eval_plan_001_flat_nli | 42 | 45.39 | 44.49 | 80.43 | 0.6431 | No | |\n| reeval_flat_nli_s43 | 43 | 45.23 | TBD | 81.58 | 0.6505 | Partial (fixed adapter, batch=16) | |\n| eval_flat_nli_s44 | 44 | 46.15 | 46.15 | 81.31 | 0.6458 | No | |\n| eval_flat_nli_seed45 | 45 | 45.51 | 45.51 | 81.54 | 0.6521 | No | |\n| reeval_flat_nli_s42 | 42 | — | — | — | — | Yes | **PREPARING** |\n| reeval_flat_nli_s43_r2 | 43 | — | — | — | — | Yes | **RUNNING** |\n\n**flat-NLI 4-seed mean (s42/s43/s44/s45)**: rel_f1 = 0.4557 ± 0.0039\n\n#### top_k Ablation\n\n| exp_id | method | seed | F1 (rel_f1) | Ign-F1 | Evi-F1 | EDCR | notes |\n|--------|--------|------|-------------|--------|--------|------|-------|\n| CED 3-seed mean | CED k=1 | s42/43/44 | 45.96 | 45.00 | 81.43 | 0.6434 | |\n| reeval_rsft_topk3 | CED k=3 | 42 | 44.54 | 43.64 | 80.88 | 0.6635 | D076 corrected ign_f1 |\n\n**Δ (k=3 vs k=1 mean)**: Ign-F1 **-1.36pp**, rel_f1 **-1.42pp**, evi_f1 **-0.55pp**, EDCR +0.02\n- Training data: k=1 → 2718 samples (12.4%), k=3 → 8037 samples (37%) — 2.96× more data but lower quality\n- Scoring quality: k=1 mean_f1=0.6157, mean_ced=0.6683 → k=3 mean_f1=0.5761, mean_ced=0.6205\n\n### Key Numbers for Paper\n\n- **CED vs flat-NLI head-to-head** (current data, NOT D076-unified):\n  - CED 3-seed mean rel_f1 = 0.4596 vs flat-NLI 4-seed mean = 0.4557 → Δ = **+0.39pp** (not significant)\n  - Dream reported p-values: 0.08 / 0.38 / 0.12 — not statistically significant\n- **Both > SFT baseline**: CED +5.39pp, flat-NLI +5.00pp (Ign-F1 vs SFT 40.36)\n- **top_k=1 > top_k=3**: Scoring precision matters more than data quantity; rank 2-3 samples dilute quality\n- **Status**: CED ≈ flat-NLI statistically indistinguishable → CED is \"one possible scoring function,\" not independently superior (C3 降级)\n\n### Evidence Gaps\n\n- [ ] **D076 unified protocol**: 4/8 evals need rerunning before paired t-test is valid (reeval_ced_s42, reeval_ced_s44, reeval_flat_nli_s42, reeval_flat_nli_s43_r2)\n- [ ] **CED s45 eval**: Still RUNNING — needed for 4-seed CED statistics\n- [ ] **Paired t-test**: Cannot compute until all seeds are under unified protocol\n- [ ] **top_k=3 additional seeds**: Only 1 seed; direction consistent but no significance test possible — present as supplementary ablation row, not independent claim\n\n---\n\n## Claim 4: EDCR dual-layer diagnostic value\n\n**Statement**: EDCR quantifies evidence-extraction decoupling at method level (echoing Claim 2 spectrum) and provides relation-type diagnostic information orthogonal to Evi-F1 at per-relation level.\n\n### Supporting Experiments\n\n| exp_id | analysis | result | notes |\n|--------|----------|--------|-------|\n| plan_003_edcr_diagnostic | Method-level EDCR table (15 methods) | EDCR vs rel_f1 Spearman ρ=-0.9648 (p=0.0001); EDCR vs evi_f1 ρ=0.0022 (p=0.9941) | EDCR ≈ transform of rel_f1 at method level (D071 flags by-construction concern) |\n| D070 per-relation analysis | Per-relation EDCR (93 types, ≥5 samples) | EDCR vs evi_f1 ρ=**-0.064** (p=0.58) → **completely independent**; EDCR vs rel_f1 ρ=-0.793 (p<0.001) | 76 types with non-zero data |\n| D070 per-relation analysis | Per-relation evi_f1 vs rel_f1 | ρ=-0.013 (p=0.91) → evidence quality and extraction completely decoupled across relation types | Independent finding supporting paper narrative |\n\n### EDCR Method-Level Summary\n\n| Method | EDCR | rel_f1 | evi_f1 | interpretation |\n|--------|------|--------|--------|----------------|\n| GRPO QLoRA (lr=5e-6) | 0.9876 | 0.0138 | 0.8504 | Pathological: high evidence, zero extraction |\n| GRPO QLoRA (lr=5e-5) | 0.8539 | 0.2167 | 0.5746 | Severe decoupling |\n| DPO 3ep | 0.7294 | 0.3429 | 0.8403 | Moderate decoupling |\n| SFT baseline | 0.7118 | 0.4057 | 0.7979 | Reference |\n| DPO 1ep | 0.7139 | 0.4034 | 0.8088 | ≈ SFT level |\n| RSFT r2a (1ep) | 0.6641 | 0.4494 | 0.8108 | Improved |\n| RSFT CED k=3 | 0.6635 | 0.4454 | 0.8088 | Improved |\n| RSFT r2b (1ep) | 0.6609 | 0.4493 | 0.8128 | Improved |\n| RSFT CED s42 (3ep) | 0.6565 | 0.4449 | 0.8187 | Improved |\n| flat-NLI s43 | 0.6505 | 0.4523 | 0.8158 | Improved |\n| flat-NLI s44 | 0.6458 | 0.4615 | 0.8131 | Improved |\n| flat-NLI s42 | 0.6431 | 0.4539 | 0.8043 | Improved |\n| RSFT CED s43 | 0.6388 | 0.4683 | 0.8156 | Best RSFT |\n| RSFT CED s44 | 0.6350 | 0.4655 | 0.8087 | Near best |\n| GRPO bf16 G=8 | 0.6318 | 0.4549 | 0.8086 | Best GRPO (no decoupling) |\n| CED reranker | 0.6156 | 0.4864 | 0.8188 | **Best overall** |\n\n### Per-Relation Exemplars (D070)\n\n| Relation Type | EDCR | evi_f1 | rel_f1 | interpretation |\n|---------------|------|--------|--------|----------------|\n| date_of_birth | 0.118 | high | high | High faithfulness — easy relation |\n| head_of_government | 0.956 | 0.875 | low | High evidence quality but poor extraction — EDCR catches what evi_f1 misses |\n\n### Key Numbers for Paper\n\n- **Layer 1 (method-level)**: EDCR identifies pathological models (GRPO QLoRA: EDCR≈1.0) — works as decoupling meter, echoes Claim 2\n- **Layer 2 (per-relation)**: EDCR vs evi_f1 ρ=-0.064 → completely independent signals at per-relation granularity\n- **D071 caveat**: Method-level EDCR ≈ f(1/rel_f1) by construction — when model predicts wrong relations, evidence automatically becomes \"distractor.\" Paper must acknowledge this and frame method-level EDCR as decoupling measure, not independent evidence quality metric\n- **D073 definition**: Paper uses distractor count ratio (∈[0,1]) definition; formula proxy 1-rel_f1/evi_f1 only for method-level quick comparison; per-relation tables require n_pred≥10 filter\n\n### Evidence Gaps\n\n- [ ] **100-example human annotation validation** (plan_013): Not started — needed for RC6\n- [ ] **TP-only EDCR** (D071): Not implemented — needed to address by-construction confound; if TP-only EDCR still correlates with rel_f1, Claim 4 method-level value is weak\n- [ ] **More per-relation exemplars**: Need to populate full table with n_pred≥10 filter (D073)\n\n---\n\n## Cross-Claim Protocol Issues\n\n### D076 Unified Protocol Reeval Status\n\nThe following evals have protocol inconsistencies that prevent valid paired t-test (Claim 3):\n\n| exp_id | issue | unified reeval | status |\n|--------|-------|---------------|--------|\n| CED s42 (mvp2_eval_rsft_r2b_maxtok1536_r2) | Wrong checkpoint (r2b α=32 instead of ckpt-510 α=128), batch_size=8, max_new_tokens=1536 | reeval_ced_s42 | PREPARING |\n| CED s44 (mvp2_rsft_train_r1_s44) | Seed=42 in eval (should be 44) | reeval_ced_s44 | PREPARING |\n| flat-NLI s42 (eval_plan_001_flat_nli) | batch_size=16 | reeval_flat_nli_s42 | PREPARING |\n| flat-NLI s43 (reeval_flat_nli_s43) | batch_size=16 | reeval_flat_nli_s43_r2 | RUNNING |\n\n**Unified protocol**: batch_size=4, --no-quantize, --sft_adapter, max_new_tokens=1024, correct seed.\n\n**Impact**: Old protocol data can be used for directional claims but NOT for paired t-test (Claim 3 significance). All 8 CED/flat-NLI evals must be under unified protocol before statistical comparison.\n\n### Ign-F1 vs F1 Issue\n\n- Most registry entries show ign_f1 = rel_f1 (suspected eval pipeline bug, D069)\n- Paper_framing table has corrected Ign-F1 values that differ from F1 (e.g., SFT no-evidence: Ign-F1=47.36 vs F1=48.93)\n- D071: \"Ign-F1 修正后排名无实质变化\"\n- **Paper uses Ign-F1 in main table** per D071\n\n### Experiments Still Running / Pending\n\n| exp_id | purpose | status | blocking |\n|--------|---------|--------|----------|\n| eval_rsft_ced_s43 | CED s43 re-eval | RUNNING | C3 statistics |\n| eval_rsft_ced_s45 | CED s45 (new seed) | RUNNING | C3 statistics |\n| eval_plan_014_no_evidence_r2 | SFT no-evidence re-eval | RUNNING | — |\n| reeval_ced_s42 | Unified protocol CED s42 | PREPARING | C3 paired t-test |\n| reeval_ced_s44 | Unified protocol CED s44 | PREPARING | C3 paired t-test |\n| reeval_flat_nli_s42 | Unified protocol flat-NLI s42 | PREPARING | C3 paired t-test |\n| reeval_flat_nli_s43_r2 | Unified protocol flat-NLI s43 | RUNNING | C3 paired t-test |\n| plan_002 | Test set evaluation | PLANNED | C1 final numbers |\n| plan_013 | EDCR human annotation (100 examples) | PLANNED | C4 validation |\n\n---\n\n## Summary: Paper-Ready vs Gaps\n\n### Paper-Ready Numbers\n\n1. **Evidence tax**: 47.36 → 40.36 = -7.00pp Ign-F1 (plan_014 vs noquant SFT)\n2. **CED reranker recovery**: F1=48.64, only -0.29pp below no-evidence (plan_005)\n3. **RSFT CED best**: Ign-F1=45.85, +5.49pp over SFT (s43)\n4. **Decoupling spectrum**: Complete data for GRPO QLoRA / GRPO bf16 / DPO / RSFT\n5. **QLoRA amplification**: bf16 0.4549 vs QLoRA 0.0138 (plan_011 vs QLoRA runs)\n6. **EDCR per-relation independence**: ρ=-0.064 vs evi_f1 (D070)\n7. **top_k ablation**: k=1 > k=3, precision > quantity (plan_008)\n8. **DREEAM baseline**: F1=63.57, Evi-F1=54.01 reproduced (plan_004)\n\n### Critical Gaps (blocking paper submission)\n\n1. **D076 unified reevals** — blocking Claim 3 statistical test\n2. **CED reranker Ign-F1** — needed for main table\n3. **Test set evaluation** (plan_002) — no official numbers yet\n4. **DREEAM-protocol Evi-F1 alignment** — cross-paradigm evidence comparison\n\n### Nice-to-Have (strengthen but not blocking)\n\n1. EDCR human validation (plan_013) — RC6\n2. Post-hoc retrieval baseline (SFT + BM25) — RC10\n3. Model size ablation (plan_006) — RC4\n4. TP-only EDCR (D071) — method-level confound\n5. Re-DocRED extension (plan_007) — RC4\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Tool call

_source line 86_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01JQB5kejgmf2LY4y9a8gqiT`</summary>

```json
{
  "name": "paper_evidence_table",
  "type": "report",
  "description": "Structured evidence table for EMNLP 2026 paper, organized by 4 claims with supporting experiments, key numbers, and evidence gaps. Compiled from 130 registry experiments + paper_framing.md + decisions D067-D076.",
  "project": "faith-evidence-ie",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/paper_evidence_table.md",
  "tags": [
    "paper",
    "evidence-table",
    "emnlp2026",
    "sprint-prep"
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
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "876a9ba9-cda1-4ea9-87f3-7c90755cc6b7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MLcgjVRiAUbCiibNY9uUgr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9649,
      "cache_read_input_tokens": 52351,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9649
      },
      "output_tokens": 69,
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

_source line 87 · 2026-05-16T03:28:48.709Z_

<details><summary>↩ Tool result · `toolu_01JQB5kejgmf2LY4y9a8gqiT`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_a1a71e\", \"name\": \"paper_evidence_table\", \"type\": \"report\", \"description\": \"Structured evidence table for EMNLP 2026 paper, organized by 4 claims with supporting experiments, key numbers, and evidence gaps. Compiled from 130 registry experiments + paper_framing.md + decisions D067-D076.\", \"path\": \"projects/faith-evidence-ie/artifacts/_project/report/paper_evidence_table.md\", \"url\": null, \"project\": \"faith-evidence-ie\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T03:28:48.606791+00:00\", \"tags\": [\"paper\", \"evidence-table\", \"emnlp2026\", \"sprint-prep\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "385d42fd-90f9-4a17-b2b0-69aeca3a9900",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260516_a1a71e\\\", \\\"name\\\": \\\"paper_evidence_table\\\", \\\"type\\\": \\\"report\\\", \\\"description\\\": \\\"Structured evidence table for EMNLP 2026 paper, organized by 4 claims with supporting experiments, key numbers, and evidence gaps. Compiled from 130 registry experiments + paper_framing.md + decisions D067-D076.\\\", \\\"path\\\": \\\"projects/faith-evidence-ie/artifacts/_project/report/paper_evidence_table.md\\\", \\\"url\\\": null, \\\"project\\\": \\\"faith-evidence-ie\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-16T03:28:48.606791+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"evidence-table\\\", \\\"emnlp2026\\\", \\\"sprint-prep\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260516_a1a71e\", \"name\": \"paper_evidence_table\", \"type\": \"report\", \"description\": \"Structured evidence table for EMNLP 2026 paper, organized by 4 claims with supporting experiments, key numbers, and evidence gaps. Compiled from 130 registry experiments + paper_framing.md + decisions D067-D076.\", \"path\": \"projects/faith-evidence-ie/artifacts/_project/report/paper_evidence_table.md\", \"url\": null, \"project\": \"faith-evidence-ie\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-16T03:28:48.606791+00:00\", \"tags\": [\"paper\", \"evidence-table\", \"emnlp2026\", \"sprint-prep\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 88_

Evidence table 已编译完成，写入 `artifacts/paper_evidence_table.md` 并注册为 artifact `art_20260516_a1a71e`。

核心发现：

**Paper-ready 数据**：4 个 claim 都有实验支撑——evidence tax -7pp, CED reranker 97% recovery, decoupling spectrum 完整, EDCR per-relation 独立性 ρ=-0.064。

**4 个 blocking gaps**：
1. D076 统一协议 reeval（4/8 eval 不一致，阻塞 C3 paired t-test）
2. CED reranker 缺 Ign-F1（主表需要）
3. Test set evaluation（plan_002 未开始）
4. DREEAM-protocol Evi-F1 对齐（跨范式对比）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "uuid": "291bffb2-5c63-4b89-8428-e80bba147f5a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011iu7JPo51pBFBL1UfEDPW7",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 571,
      "cache_read_input_tokens": 62000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 571
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

_source line 89_

Evidence table 已编译完成，写入 `artifacts/paper_evidence_table.md` 并注册为 artifact `art_20260516_a1a71e`。

核心发现：

**Paper-ready 数据**：4 个 claim 都有实验支撑——evidence tax -7pp, CED reranker 97% recovery, decoupling spectrum 完整, EDCR per-relation 独立性 ρ=-0.064。

**4 个 blocking gaps**：
1. D076 统一协议 reeval（4/8 eval 不一致，阻塞 C3 paired t-test）
2. CED reranker 缺 Ign-F1（主表需要）
3. Test set evaluation（plan_002 未开始）
4. DREEAM-protocol Evi-F1 对齐（跨范式对比）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 468149,
  "duration_api_ms": 465546,
  "num_turns": 13,
  "stop_reason": "end_turn",
  "session_id": "1b422aa5-76ab-42b1-8a3d-85cfc234200a",
  "total_cost_usd": 1.79705575,
  "usage": {
    "input_tokens": 15,
    "cache_creation_input_tokens": 51124,
    "cache_read_input_tokens": 438991,
    "output_tokens": 12641,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 51124,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 234,
        "cache_read_input_tokens": 62000,
        "cache_creation_input_tokens": 571,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 571
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1870,
      "outputTokens": 19,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0019649999999999997,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 33,
      "outputTokens": 23802,
      "cacheReadInputTokens": 938364,
      "cacheCreationInputTokens": 116911,
      "webSearchRequests": 0,
      "costUSD": 1.7950907499999997,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "bce51b3f-68a6-4a87-8c7e-54c501a475c2"
}
```

</details>

---
