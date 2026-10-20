# Research conversation: You are Reviewer 2 (R2) for a top ML venue peer review. Your focus areas are **novelty/originality** and **related work/

**OntoCoDec: Type-Constrained Information Extraction via Compiled Schema Constraints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 77
- **Recorded user turns:** 1
- **Tool calls:** 32
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-a77dd280799b6b550.jsonl`
- **Structured JSON:** [`58cfbddc364e3dc7c06a.json`](../../sessions/58/58cfbddc364e3dc7c06a.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

77 recorded events

### User

_source line 1 · 2026-05-16T02:52:27.633Z_

You are Reviewer 2 (R2) for a top ML venue peer review. Your focus areas are **novelty/originality** and **related work/positioning**. Use a 6-point scale: 1=Strong Reject, 2=Reject, 3=Weak Reject, 4=Weak Accept, 5=Accept, 6=Strong Accept. Target venue acceptance rate ~25%.

## Paper Summary

**OntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints**

The paper presents OntoCoDec, a framework that compiles IE ontology schemas into two composable decoding constraint layers for LLM-based information extraction:
1. A **grammar layer** (via XGrammar) enforcing JSON structure, valid relation names, and entity types through CFG constraints.
2. A **semantic layer** (TypeConstraintProcessor) enforcing per-relation domain-range rules via a stateful entity registry and dynamic logit masking.

**Core claims:**
- OntoCoDec eliminates 90-99% of domain-range violations in zero-shot IE at neutral/positive F1 impact.
- Composability with fine-tuning is regime-dependent: beneficial on simple ontologies, detrimental on complex ones.
- A "constraint ROI" metric formalizes when to apply constrained decoding.

**Related work section covers:**
1. Constrained Decoding for Structured Generation: Willard & Louf 2023, Scholak et al. 2021, Poesia et al. 2022, Dong et al. (XGrammar) 2024
2. Type-Constrained IE: Zhang et al. 2017, Han et al. 2018, Wadhwa et al. 2023, Li et al. 2023
3. Ontology-Guided NLP: Li et al. 2020, Zhang et al. 2019, Bordes et al. 2013
4. Quality Degradation Under Constraints: Park et al. 2024 ("structure snowballing")

**Key method details:**
- Grammar layer uses XGrammar (existing tool) to enforce JSON schema with enumerated valid relation names and entity types
- Semantic layer (TypeConstraintProcessor) is the novel component: maintains entity registry, enforces domain-range constraints via logit masking
- Composition is bitwise AND of masks with graceful degradation (fallback to grammar-only on empty intersection)
- "Constraint tightness" τ(r) = 1 - |dom(r)|·|ran(r)| / |E|² measures how restrictive each relation's constraints are
- Constraint ROI = ΔDR(pp) / ΔR-F1 cost(pp)
- Only S1 (single-pass) decoding strategy evaluated

**Paper structure:** 8 pages, Abstract, Intro, Background, Method, Zero-Shot Experiments (§4, results "from prior work, summarized"), Fine-Tuned Experiments + Regime Analysis (§5), Related Work, Limitations, Conclusion.

**Experimental design reference:** The review_context.yaml shows planned experiments were specifically:
1. Qwen DocRED LoRA + Full S1 Constrained Eval
2. Llama DocRED LoRA + Full S1 Constrained Eval
These match the paper's §5 content exactly. Zero-shot results are referenced as "prior work" but appear to be the same authors' earlier experiments.

## Your Review (R2: Novelty + Related Work)

Please provide a structured review covering:

1. **Summary** (2-3 sentences)
2. **Strengths** (bullet points, focus on novelty, contribution significance, positioning)
3. **Weaknesses** (bullet points, focus on originality gaps, missing related work, positioning issues)
4. **Questions for Authors** (specific clarifications needed)
5. **Novelty Assessment**: How novel is (a) the grammar+semantic layer composition, (b) the constraint tightness metric, (c) the regime-dependent analysis, (d) the ROI framework? Is this incremental over XGrammar + standard constrained decoding?
6. **Related Work Assessment**: Are important baselines or prior systems missing? Is the differentiation from prior work clear? Specifically consider:
   - Recent structured generation work (Guidance, Outlines, SGLang, LMQL)
   - Ontology-aware IE systems beyond what's cited
   - Constraint satisfaction / constraint propagation literature
   - Whether the "first to compile ontology constraints into decoding masks" claim holds
7. **Score** (1-6) and **Confidence** (1-5, where 5=expert)
8. **Key concerns that would change your score**

Be rigorous. Pay attention to:
- Whether the semantic layer is truly novel or a straightforward extension of grammar-constrained decoding
- Whether the "regime-dependent composability" finding is the main contribution and if it's sufficiently novel/surprising
- The paper explicitly acknowledges zero-shot results are "from prior work" — is this paper then just the FT analysis? Is that enough?
- Whether the paper is positioned as a method paper or an analysis paper, and whether it succeeds as either
- Missing citations to recent structured generation frameworks
- The constraint tightness metric is simple — is it a real contribution?
- Whether the ROI metric, while intuitive, is formally well-defined (division by zero when F1 improves)


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "4c89dc61-5864-411c-acc5-98a230216381",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-16T02:52:27.638Z_

```json
{
  "parentUuid": "4c89dc61-5864-411c-acc5-98a230216381",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
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
  "uuid": "8eeaa01c-fec3-46b4-b017-e3bfff9c2c77",
  "timestamp": "2026-05-16T02:52:27.638Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 3 · 2026-05-16T02:52:30.598Z_



I'll start by reading the paper and all relevant project files to conduct a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8eeaa01c-fec3-46b4-b017-e3bfff9c2c77",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQYHqYh8rCtajmhWZG",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c6905341-eb59-48b8-8023-709c527e360a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EEQiudyk4KM4BzG92gNuem",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7117,
      "cache_read_input_tokens": 8252,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7117,
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

_source line 4 · 2026-05-16T02:52:31.595Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01UgE64t6VKCSyrsLizVwgRM`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__director_get_project_overview,mcp__agent-ml-research__submit_dream_review_report",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c6905341-eb59-48b8-8023-709c527e360a",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQYHqYh8rCtajmhWZG",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a138fbb8-a887-45d7-a11f-643dca6e6412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EEQiudyk4KM4BzG92gNuem",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7117,
      "cache_read_input_tokens": 8252,
      "output_tokens": 142,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7117
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 142,
          "cache_read_input_tokens": 8252,
          "cache_creation_input_tokens": 7117,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7117,
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

_source line 5 · 2026-05-16T02:52:31.598Z_

<details><summary>↩ Tool result · `toolu_01UgE64t6VKCSyrsLizVwgRM`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__director_get_project_overview"
}
```

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
  "parentUuid": "a138fbb8-a887-45d7-a11f-643dca6e6412",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "68e0cb17-2a45-4098-8270-54c5957d8667",
  "sourceToolAssistantUUID": "a138fbb8-a887-45d7-a11f-643dca6e6412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 6 · 2026-05-16T02:52:34.644Z_



Let me read the paper and all relevant project files to conduct a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "68e0cb17-2a45-4098-8270-54c5957d8667",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQqG3vucsz9cLF9n6a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e15ffef1-5b83-4168-9d63-8b30dec3fa21",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A9on7wAhCFmocUG8RUNzHb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2015,
      "cache_read_input_tokens": 15369,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2015,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 7 · 2026-05-16T02:52:35.144Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__director_get_project_overview · `toolu_01NRs8dK4s5iP8Vut7wCQ67a`</summary>

```json
{
  "project": "schema_semantic_constrained_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e15ffef1-5b83-4168-9d63-8b30dec3fa21",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQqG3vucsz9cLF9n6a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "5512f2f1-6183-4900-a264-f21b1380e5c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A9on7wAhCFmocUG8RUNzHb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2015,
      "cache_read_input_tokens": 15369,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2015,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 8 · 2026-05-16T02:52:35.307Z_

<details><summary>↩ Tool result · `toolu_01NRs8dK4s5iP8Vut7wCQ67a`</summary>

```text
{"result":"# 项目 schema_semantic_constrained_ie 概况\n\n## 实验状态 (40 个)\n\n- **llama_scierc_unconstrained**: DONE (success) — \n- **phase2_scierc_full_s2**: DONE (success) — \n- **phase2_scierc_full_s1**: DONE (success) — \n- **phase2_scierc_semantic_only**: DONE (success) — \n- **phase2_scierc_grammar_only**: DONE (success) — \n- **phase2_scierc_unconstrained**: DONE (success) — \n- **phase2_docred_full_s1**: DONE (success) — \n- **phase2_docred_semantic_only**: DONE (success) — \n- **phase2_docred_unconstrained**: DONE (success) — \n- **mvp_phase0_docred_schema_r2**: DONE (killed) — \n- **phase2_s2_pilot50**: DONE (success) — \n- **mvp_phase0_docred_schema**: DONE (success) — \n- **mvp_phase0_violation_rate_docred**: DONE (success) — \n- **mvp_phase0_scierc_schema**: DONE (success) — \n- **mvp_phase0_violation_rate**: DONE (success) — \n\n## 最新报告\n# Handover — 2026-05-16\n\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\n\n## 运行中\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\n|--------|------|------|---------|-----|\n| w5_qwen_docred_lora_constrained_eval | Fine-tuned Qwen3-8B DocRED LoRA + OntoCoDec constrained eval — 验证 composability：约束解码在 fine-tuned Qwen DocRED 上是否仍能消除残余 DR 且不损 R-F1 | — | — | — |\n| w5_llama_docred_lora_constrained_eval | Fine-tuned Llama-3.1-8B DocRED LoRA + OntoCoDec constrained eval — 验证 composability：约束解码在 fine-tuned Llama DocRED 上是否仍能消除残余 DR 且不损 R-F1 | — | — | — |\n\n## 待处理\n- w1_cf_fallback_llama_scierc（准备中）\n- w1_cf_fallback_llama_docred（准备中）\n- w5_llama_docred_sft_data_gen: Generate Llama-3.1-8B-Instruct format DocRED SFT train/dev JSONL — prerequisite for Llama DocRED LoRA fine-tune (composability matrix Llama×DocRED cell)（准备中）\n\n## 近期结论\n- **w5_qwen_docred_lora_unconstrained_eval** (success): Fine-tuned Qwen3-8B DocRED LoRA unconstrained eval — 获取 fine-tuned baseline DR/R-F1，与 constrained eval 对比计算 composability delta ← 基于 w5_qwen_docred_lora_training\n- **w5_llama_docred_lora_unconstrained_eval** (success): Fine-tuned Llama-3.1-8B DocRED LoRA unconstrained eval — 获取 fine-tuned baseline DR/R-F1，与 constrained eval 对比计算 composability delta ← 基于 w5_llama_docred_lora_training\n- **w5_qwen_docred_lora_training** (success): Qwen3-8B LoRA fine-tune on DocRED — 填补 Qwen DocRED composability 2×2 matrix 的 FT 行。预期：(1) LoRA 后 E-F1/R-F1 大幅提升；(2) 残余 DR > 0% 证明 OntoCoDec 在 DocRED FT 上仍有 composability 价值。\n\n## 趋势\n成功 32 / 负向 1 / 失败 0 / 共 35\n\n## 下一步\n（无活跃 idea，请通过 ideas.md 添加）\n\n## 资源状态\nwestd-16980: 无 GPU 信息\n\n## 告警\n- mvp_phase0_docred_schema_r2: 已被终止 — unknown\n- w1_cf_fallback_docred: 已被终止 — unknown"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5512f2f1-6183-4900-a264-f21b1380e5c7",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "f590e002-ce3f-435e-bbce-c8fa54cf1c25",
  "sourceToolAssistantUUID": "5512f2f1-6183-4900-a264-f21b1380e5c7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-16T02:52:35.611Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01G53tywRZvANkojvECjcWpn`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "report.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f590e002-ce3f-435e-bbce-c8fa54cf1c25",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQqG3vucsz9cLF9n6a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "b2357f18-1743-489b-812d-d939257db653",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A9on7wAhCFmocUG8RUNzHb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2015,
      "cache_read_input_tokens": 15369,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2015,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 10 · 2026-05-16T02:52:35.621Z_

<details><summary>↩ Tool result · `toolu_01G53tywRZvANkojvECjcWpn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/report.md\", \"content\": \"# Handover — 2026-05-16\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\\n|--------|------|------|---------|-----|\\n| w5_qwen_docred_lora_constrained_eval | Fine-tuned Qwen3-8B DocRED LoRA + OntoCoDec constrained eval — 验证 composability：约束解码在 fine-tuned Qwen DocRED 上是否仍能消除残余 DR 且不损 R-F1 | — | — | — |\\n| w5_llama_docred_lora_constrained_eval | Fine-tuned Llama-3.1-8B DocRED LoRA + OntoCoDec constrained eval — 验证 composability：约束解码在 fine-tuned Llama DocRED 上是否仍能消除残余 DR 且不损 R-F1 | — | — | — |\\n\\n## 待处理\\n- w1_cf_fallback_llama_scierc（准备中）\\n- w1_cf_fallback_llama_docred（准备中）\\n- w5_llama_docred_sft_data_gen: Generate Llama-3.1-8B-Instruct format DocRED SFT train/dev JSONL — prerequisite for Llama DocRED LoRA fine-tune (composability matrix Llama×DocRED cell)（准备中）\\n\\n## 近期结论\\n- **w5_qwen_docred_lora_unconstrained_eval** (success): Fine-tuned Qwen3-8B DocRED LoRA unconstrained eval — 获取 fine-tuned baseline DR/R-F1，与 constrained eval 对比计算 composability delta ← 基于 w5_qwen_docred_lora_training\\n- **w5_llama_docred_lora_unconstrained_eval** (success): Fine-tuned Llama-3.1-8B DocRED LoRA unconstrained eval — 获取 fine-tuned baseline DR/R-F1，与 constrained eval 对比计算 composability delta ← 基于 w5_llama_docred_lora_training\\n- **w5_qwen_docred_lora_training** (success): Qwen3-8B LoRA fine-tune on DocRED — 填补 Qwen DocRED composability 2×2 matrix 的 FT 行。预期：(1) LoRA 后 E-F1/R-F1 大幅提升；(2) 残余 DR > 0% 证明 OntoCoDec 在 DocRED FT 上仍有 composability 价值。\\n\\n## 趋势\\n成功 32 / 负向 1 / 失败 0 / 共 35\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-16980: 无 GPU 信息\\n\\n## 告警\\n- mvp_phase0_docred_schema_r2: 已被终止 — unknown\\n- w1_cf_fallback_docred: 已被终止 — unknown\\n\", \"total_chars\": 1653, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b2357f18-1743-489b-812d-d939257db653",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "2a03e8a9-b0ed-42ff-9d09-c3652affc8ca",
  "sourceToolAssistantUUID": "b2357f18-1743-489b-812d-d939257db653",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-16T02:52:36.241Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_019znL5HS4b21xHjy4RGGyZ5`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "literature_map.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2a03e8a9-b0ed-42ff-9d09-c3652affc8ca",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VQqG3vucsz9cLF9n6a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ce73c5af-9a70-492f-bcf1-4ee88a4509af",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01A9on7wAhCFmocUG8RUNzHb",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 2015,
      "cache_read_input_tokens": 15369,
      "output_tokens": 278,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2015
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 278,
          "cache_read_input_tokens": 15369,
          "cache_creation_input_tokens": 2015,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2015,
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

_source line 12 · 2026-05-16T02:52:36.252Z_

<details><summary>↩ Tool result · `toolu_019znL5HS4b21xHjy4RGGyZ5`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No literature_map.yaml found for 'schema_semantic_constrained_ie'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ce73c5af-9a70-492f-bcf1-4ee88a4509af",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "38fe39ba-fb0f-487a-b94f-5b386d7e626b",
  "sourceToolAssistantUUID": "ce73c5af-9a70-492f-bcf1-4ee88a4509af",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-16T02:52:39.931Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01XL1YBRQ32tb2AQLv1RVn2j`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "38fe39ba-fb0f-487a-b94f-5b386d7e626b",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRBJ4Ex6MNM1vRNJbA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8122cb43-c099-4bd4-af3a-f79d7e5ea38b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LHYWxXM2y79T9rbHu8Yefe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2742,
      "cache_read_input_tokens": 17384,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2742,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 66,
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

_source line 14 · 2026-05-16T02:52:39.942Z_

<details><summary>↩ Tool result · `toolu_01XL1YBRQ32tb2AQLv1RVn2j`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/paper_framing.md\", \"content\": \"# OntoCoDec — Paper Framing\\n\\n## Target Venue\\nEMNLP 2026 (ARR submission May 25, 2026)\\n\\n## Title\\nOntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints\\n(D015: \\\"Near-Complete\\\" dropped — DocRED residual DR=10.21% (Qwen) 不算 near-complete。论文贡献是方法，不是特定消除率。SciERC 0.93% 和 DocRED 2.55% (Llama) 可在正文中描述为 near-complete，但 title 不宜 overclaim。)\\n\\n## Core Insight\\nLLM-based IE systems produce systematic ontology constraint violations concentrated in specific relation types. Prompt-level intervention (schema-informed prompting) reduces violations by ~62% but cannot eliminate them — certain relation types retain 25-30% violation rates even with explicit constraint descriptions. OntoCoDec provides **near-complete elimination (DR 15.4%→0.93%, ↓94%) at zero or positive F1 impact** through automatic ontology-to-decoder constraint compilation with two complementary layers.\\n\\n**Phase 2 confirmed (D012 bootstrap CI, v2 fix)**: Grammar+Semantic dual-layer constrained decoding reduces domain/range violations by 94%, eliminates entity-type and relation-vocabulary violations entirely (→0%). F1 impact is **dataset-dependent**:\\n- SciERC: Rel F1 neutral (+0.13pp, p=0.58), Ent F1 neutral (-0.03pp, p=0.53)\\n- DocRED: Rel F1 **significantly improved** (+0.50pp, p<0.001, 95% CI [+0.23, +0.81]); Ent F1 **significantly improved** (+1.23pp, p<0.001, 95% CI [+0.94, +1.55])\\n- Mechanism: grammar 消除 OOV relation names (DocRED RV 29.66%→0.03%) + 非标 entity types (ET 2.48%→0%)。all_set F1 方法下 OOV=FP → fewer FP → higher precision/F1。SciERC baseline RV/ET 已很低，效果不显著。\\n- **Grammar 层是 F1 提升的唯一来源**: grammar_only Ent F1=59.38% ≈ full_s1 59.37% (Δ+0.01pp, p=0.66)。Semantic 层对 F1 无额外贡献，专注 DR reduction。\\n\\n## Core Claims\\n\\n### Claim 1 (Empirical): Violation Landscape\\nLLM-based IE systems violate ontology type constraints at non-trivial rates (15.4% per-triple on SciERC, 18.7% on DocRED). Violations are **not uniformly distributed** — they concentrate on relation types with tight domain/range constraints (Feature-of 33.5%, Compare 42.4%) while loose-constraint relations show near-zero violation (Used-for 0.8%).\\n\\n**Key insight**: Violation rate is driven by **constraint tightness**, not ontology size. A small ontology with tight constraints can produce more violations than a large ontology with loose constraints.\\n\\n**D014 修订**: DR reduction ceiling 由 **tightness × model RV baseline** 共同决定，非 tightness 单因素。Llama DocRED DR↓90.2% vs Qwen DR↓44.7%（同一 ontology τ̄=0.842）。机制：Qwen RV=29.66% >> Llama RV=16.03% → grammar 层将 OOV triples 强制匹配有效关系名 → 揭露大量 latent DR violations → 残余 DR 更高。这是比单一 tightness 更深的 insight。\\n\\n**Evidence**: SciERC (7 relations) 15.4%; DocRED (96 relations) 18.7% — comparable rates despite 14× ontology size difference. Schema-informed prompt on DocRED only achieves DR↓32% (vs SciERC ↓62%), confirming **prompt-level intervention scales poorly with ontology complexity**.\\n\\n### Claim 2 (Empirical): Prompt Insufficiency\\nSchema-informed prompting (explicitly describing domain/range constraints in the prompt) reduces but does not eliminate violations:\\n- Overall: 15.4% → 5.78% (-62.4%), still above 5%\\n- Per-relation: Compare 42.4% → 27.6%, Evaluate-for 24.1% → 29.9% (**worse**)\\n- Prompt intervention is unreliable at the per-relation level — some relations improve, one regresses\\n\\n**Narrative**: This is NOT about \\\"5.78% barely above 5%\\\". The story is: **prompt-level intervention is fundamentally unreliable as a guarantee mechanism**. It works statistically but cannot provide per-instance compliance. Three specific relation types retain >10% violation rates with schema-informed prompts. For safety-critical IE (biomedical, legal, regulatory), statistical reduction is insufficient — guaranteed compliance is required.\\n\\n### Claim 3 (Methodological): Composable Constraint Framework\\nOntoCoDec automatically compiles IE ontology schemas into two composable constraint layers:\\n1. **Grammar layer** (XGrammar): JSON structure + type vocabulary constraints (CFG-expressible)\\n2. **Semantic layer** (TypeConstraintProcessor): Cross-field domain/range constraints via stateful entity registry + dynamic logit masking\\n\\nThe two layers are **complementary with enabling dependency**: grammar ensures every generated relation type is in the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type. Without grammar, the semantic layer encounters unknown relation types and cannot enforce constraints (explaining why semantic_only achieves only ↓24% vs full_s1 ↓94%). This is NOT \\\"synergistic\\\" (mutual amplification) — grammar is a prerequisite for semantic, not vice versa.\\n\\nThe two layers compose via bitwise AND of token masks. Recommended framing: \\\"Grammar and semantic constraints compose via bitwise AND with an enabling dependency: grammar ensures structural validity, enabling semantic constraints to enforce domain/range rules. When constraint tightness creates empty intersection between layers, the system degrades gracefully to grammar-only constraints, maintaining structural validity as a guaranteed floor.\\\"\\n\\n**Graceful degradation + Fallback 频率量化** (D008 + Reviewer 发现):\\nWhen $M_{semantic} \\\\cap M_{grammar} = \\\\emptyset$, the system falls back to grammar-only control.\\n\\n**关键量化数据（Reviewer 从日志挖掘）**:\\n- Llama DocRED full_s1: **32,921 次 fallback / 577 docs = ~57 次/doc**\\n- Llama SciERC full_s1: **5,882 次 fallback / 550 docs = ~10.7 次/doc**\\n- DocRED fallback 频率是 SciERC 的 **5.3×**\\n- Qwen DocRED fallback 率未知（日志当时无 fallback logging，需估算）\\n\\n**这直接解释了 DocRED DR 残余 10.19% vs SciERC 0.93%**: 更多 token 位置退化为 grammar-only → grammar-only 的 DR 已知为 26.17% → 高 fallback = 高残余 DR。\\n\\n**论文建议**: 在 §5 tightness 段报告 fallback 率，定义 \\\"Constraint Coverage\\\" 指标（semantic masking 实际生效的 token 比例）。这把 \\\"10.19% DR 残余\\\" 从弱点变成可量化分析的 finding。Frame as \\\"engineering robustness\\\" in §4; fallback 频率 + tightness 作为 §5 定量分析。\\n\\n**Decidability taxonomy**: Constraints classified by prefix-decidability:\\n- (a) Purely local: entity type ∈ vocabulary (grammar layer)\\n- (b) Prefix-decidable with state: relation argument types compatible with domain/range (semantic layer, requires entity registry)\\n- (c) Truly non-local: forward coreference — out of scope for forward-only decoding\\n\\n### Claim 4 (Methodological): S1 vs S2 Decoding Strategies — Architectural Ablation\\n- S1 (single-pass): Both layers applied throughout generation. **Recommended primary strategy** — simpler, slightly better metrics across the board.\\n- S2 (two-pass): Pass 1 extracts entities (grammar-only), Pass 2 generates relations with input-dependent grammar compiled from Pass 1 entities.\\n\\n**S2 full results (551/551 SciERC)**: DR 0.97% (vs S1 0.93%), CF 8.03% (vs S1 9.9%), R-F1 8.03% (vs S1 8.36%). S2 does NOT solve CF — the 1.87pp reduction is not significant. S2 also slightly worse on DR and F1. **S2 is an architectural variant demonstrating framework flexibility, not a CF solution.** Position in paper as ablation (Section 5 or Appendix), not as a core contribution.\\n\\n⚠️ **Do NOT cite pilot50 DR=0% as S2 evidence** — small-sample artifact; full run shows DR=0.97%. Per-relation S2 DR is worse than S1 on Compare (4.6% vs 2.82%), Part-of (1.25% vs 0%), Used-for (0.12% vs 0%).\\n\\n## Anticipated Reviewer Concerns\\n\\n### C1: \\\"5.78% is barely above 5% — threshold is arbitrary\\\"\\n**Response**: Don't argue about the threshold. Argue about per-relation distribution: Compare (27.6%), Evaluate-for (29.9%), Feature-of (11.3%) have double-digit violation rates with schema-informed prompt. The value proposition is per-relation guaranteed compliance, not overall statistical rate.\\n\\n### C2: \\\"Why not just post-hoc filter?\\\"\\n**Response (D013, 实验结果已出)**:\\n\\nPost-hoc filtering 实验结果：post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.24）——因 low F1 regime 下移除 FP 大幅提升 precision。\\n\\n**论文 framing（不以 F1 论高低，多维对比）**:\\n1. **Recall 维度（核心论点）**: OntoCoDec recall 上升 (SciERC +0.20pp, DocRED +0.56pp) = 概率质量重分配到合法 token 生效。Post-hoc recall 下降 (SciERC -0.72pp, DocRED -1.06pp) = 正确 triple 被误删。\\n2. **Information coverage**: DocRED post-hoc 丢弃 **48.1%** triples（近半数信息丢失），SciERC 16.8%。OntoCoDec 保留全部 triple slots。\\n3. **Operational**: OntoCoDec 产出即合规、无需后处理、支持流式。Post-hoc 需额外管线、不适用实时场景。\\n4. **Precision trade-off（诚实承认）**: \\\"Post-hoc achieves higher precision by removing a large fraction of triples, many of which are incorrect. This trades information coverage for precision — valid when FP are costly, but inadequate when completeness matters.\\\"\\n\\n数据表：SciERC post-hoc rejection 16.8%, OntoCoDec recall 11.60 vs post-hoc 10.68; DocRED post-hoc rejection 48.1%, OntoCoDec recall 10.02 vs post-hoc 8.40。\\n\\n**Reviewer 补充发现（D013 后）**:\\n5. **ET 残余**：post-hoc 只删 triples 不改 entity list，残余 ET=0.4% (SciERC) / 2.47% (DocRED)。OntoCoDec ET=0%。Post-hoc 无法解决 entity type 违规。\\n6. **127 个被删 TP (DocRED)**：过滤前 TP=1137，过滤后 TP=1010。丢失的 127 个 TP（11.2%）是正确提取但 entity type 违规的 triple。OntoCoDec 通过生成时强制合法 type 保留这些 TP——\\\"prevent vs detect\\\" 核心论据的具体数据。\\n7. **OntoCoDec+post-hoc 组合**（future work idea）：先 constrain 再 filter 残余 DR。低优先级，May 19 前不做。\\n\\n### C3: \\\"Bitwise AND of two masks is not novel\\\"\\n**Response**: The novelty is not the AND operation — it's (a) the automatic compilation from ontology definitions (zero-code schema compliance), (b) the stateful entity registry enabling cross-field constraints during autoregressive generation, (c) the decidability taxonomy providing theoretical guidance, and (d) the systematic violation landscape measurement motivating the approach.\\n\\n### C4: \\\"Evaluate-for violation rate increases with schema-informed prompt\\\"\\n**Response (prior-constraint conflict framework)**: Evaluate-for has 23/36 valid pairs; Method→Task is invalid for Evaluate-for but natural in the LLM's distributional prior (\\\"Method X evaluates for Task Y\\\" is semantically plausible). Schema-informed prompting creates a **prior-constraint conflict**: the model learns to avoid Method→Task for Evaluate-for (reducing count 133→87, -34.6%), but the remaining instances are harder boundary cases where the model's type assignment strategy becomes less stable. This is not just \\\"harder instances\\\" — it's an active interference between prompt-level constraint signals and the model's learned type associations.\\n\\n**This strengthens the paper's claim**: prompt-level intervention is not merely insufficient but potentially **counterproductive** for specific constraint configurations. Decoding-time enforcement avoids this issue entirely — it operates on logits, not on the model's reasoning process, so there is no prior-constraint conflict.\\n\\n### C5: \\\"Only tested on one model (Qwen3-8B)\\\"\\n**Response**: Cross-model validation DONE (D016 bootstrap verified). Llama-3.1-8B 零代码修改：\\n- SciERC: DR 13.34%→0.08% (↓99.4%), R-F1 -0.14pp (p=0.011, negligible), E-F1 NS\\n- DocRED: DR 26.07%→2.55% (↓90.2%), R-F1 +0.29pp (p=0.013, significant), E-F1 -0.64pp (p=0.022, modest decline)\\n- Parse failures: unconstrained 68 vs full_s1 91 (6.8% vs 9.1%)\\n\\n**Cross-model claim 指导（Reviewer 专项评估）**:\\n- ✅ 可声明：\\\"OntoCoDec generalizes across model families without code modification\\\"（程序性事实，铁证）\\n- ❌ 不可声明：\\\"consistently achieves the same reduction rate\\\"（仅 2 模型，不足以量化声明）\\n- **RV↓DR↑ 正交性 finding**: Llama RV baseline 低(16%) 但 DR baseline 高(26%)，反向于 Qwen。证明两层约束解决正交 failure modes——vocabulary compliance ≠ semantic compliance。应作为 §5 cross-model 独立 finding 展开。\\n- **Parse failure 偏差**: checker skip parse failures (不计入 F1)，Llama 68/998=6.8% vs Qwen 12/998=1.2%。偏差方向保守（不利于 constrained），不威胁 claim。但需 footnote 披露 + cross-model 表增加 parse failure rate 行。\\n- **Llama SciERC CF=6.56%**: 比 Qwen 同量级更高，non-local constraint 问题在 Llama 上更突出，limitations 提及。\\n- 等 llama_docred_full_s1 出来后定最终 claim 措辞。\\n\\n### C6: \\\"Constrained decoding degrades generation quality (CRANE, Structure Snowballing)\\\"\\n**Response**: OntoCoDec's semantic constraints are narrower than full grammar constraints — only type tokens are masked, free text is unconstrained. **Bootstrap CI (10000×, D012 Qwen + D016 Llama, all registry-aligned)**:\\n\\n**Qwen3-8B**: SciERC R-F1 +0.13pp (p=0.58, NS), E-F1 -0.03pp (NS). DocRED R-F1 +0.50pp (p<0.001), E-F1 +1.23pp (p<0.001).\\n**Llama-3.1-8B**: SciERC R-F1 -0.14pp (p=0.011, negligible), E-F1 NS. DocRED R-F1 +0.29pp (p=0.013), E-F1 -0.64pp (p=0.022).\\n\\n**Cross-model pattern**: DocRED R-F1 显著提升（两个模型）。E-F1 model-dependent（Qwen +1.23pp, Llama -0.64pp）。\\n- 机制：grammar 消除 OOV relation names + 非标 entity types → all_set 方法下减少 FP → precision 提升。Grammar 是 F1 提升的唯一来源（grammar_only Ent F1=59.38% ≈ full_s1 59.37%, Δ=0.01pp, p=0.66）。Semantic 层对 F1 无额外贡献。\\n- Frame as: \\\"On DocRED, R-F1 gains are significant for both models. Entity F1 impact is model-dependent.\\\"\\n- 不升级为 core claim，但如实报告。\\n\\n### C7: \\\"Your method trades DR violations for CF violations (cross-field consistency)\\\"\\n**Response**: Both S1 and S2 show elevated CF (per-triple rate ~8-10%). This is an inherent limitation of per-relation independent type enforcement. Must be proactively reported as a limitation. Defense:\\n\\n**CF 子类型分析（根因已确认）**：\\n- **EVR（entity-vs-relation type drift）**: 占 CF 的 >90%。同一 entity 在 entity list 和 relation triple 中被赋予不同 type。S1: 245 entities (7.34%), S2: 178 entities (5.54%, -27%)\\n- **Within-rel（同 entity 跨 relation type 不一致）**: S1: 10 (0.36%), S2: 18 (0.72%)\\n- S2 减少 EVR 但增加 within-rel——trade-off 更复杂，不是单纯好/差\\n\\n**Top 冲突模式**: Generic↔OtherScientificTerm (60次), Material↔OtherScientificTerm (28次), Material↔Method (20次)。**这些是 SciERC type system 固有的语义边界模糊区**——同一术语在不同学术语境下确实可以被合理归类为不同 type。CF 在相当程度上是 type system 模糊性的体现，非纯粹的方法缺陷。\\n\\n**论证层次**：\\n1. DR violations = structurally invalid triples（下游系统不可用）→ hard constraint\\n2. CF violations = same entity gets different types across relations → individual triples remain type-valid, only cross-triple consistency broken → soft preference\\n3. CF 的根因是 type system 语义边界模糊 + per-relation 独立 enforcement，非 bug\\n4. Future work: cross-relation global consistency pass (entity-level type consensus before relation-specific enforcement)\\n\\n**机制归因（口径对账确认）**：grammar_only CF=0.08%（与 unconstrained 持平），full_s1 CF=9.90%，full_s2 CF=8.03%。**CF 100% 由 semantic 层引入，grammar 层无贡献。** 这为 \\\"CF 是 semantic type enforcement 的系统性副作用\\\" 提供干净的消融证据。\\n\\n**论文数字口径**：CF rate 用 violation_checker 口径（denominator=total_entities，与 DR/RV/ET 一致）。分析段落额外给 entity-level EVR 率 + 受影响样本比例。注意：analyze_cf 脚本的 EVR/WR 两维度不是独立的（WR⊂EVR），论文中不要作为两个独立维度报告。\\n\\n**Do NOT hide this data.** Proactive disclosure + severity distinction + root cause analysis + type ambiguity evidence + 消融归因 = 最强防御策略。\\n\\n### C8: \\\"Absolute F1 is too low (~8%) — results are not meaningful\\\"\\n**Response**: This is a zero-shot extraction setting (no training data, no fine-tuning). Low F1 is expected — supervised SOTA on SciERC relation F1 is ~40-50%. Our contribution is the constraint enforcement method, not extraction quality. F1 is a control variable verifying constraints don't degrade quality, not an optimization target. Recommended framing: \\\"We evaluate in a zero-shot setting to demonstrate that our constraint enforcement method works without task-specific training. F1 is reported to verify that constraint enforcement does not degrade extraction quality, not as a claim of state-of-the-art performance.\\\"\\n\\n## Paper Structure (Draft)\\n1. Introduction: Violation landscape motivation + composable constraint framework overview\\n2. Background: Grammar-constrained decoding (XGrammar) + IE ontology structure\\n3. Violation Landscape Study (Phase 0 empirics — independent contribution)\\n4. OntoCoDec Framework: Compiler + TypeConstraintProcessor + S1/S2 strategies\\n5. Experiments: Constrained vs unconstrained vs post-hoc vs prompt-based\\n6. Related Work: 5 constraint paradigms (grammar, vocabulary, structural, type-checking, ontology)\\n7. Conclusion\\n\\n## Claim Calibration (per Reviewer assessment)\\n\\n**Safe to claim (sufficient evidence from Phase 2)**:\\n- \\\"First systematic study of ontology constraint violations in LLM-based IE\\\"\\n- \\\"Violation rate correlates with constraint tightness, not ontology size\\\" (D014: DR reduction ceiling 由 tightness × model RV baseline 共同决定)\\n- \\\"Grammar+semantic constrained decoding eliminates 94% of DR violations at zero F1 cost\\\" ✅ Phase 2 confirmed\\n- \\\"Two-layer architecture provides complementary coverage — grammar enables semantic\\\" ✅ Ablation confirmed\\n- \\\"Prompt-level intervention scales poorly with ontology complexity\\\" ✅ SciERC ↓62% vs DocRED ↓32%\\n\\n**Claim with caution**:\\n- \\\"Near-complete type-valid IE\\\" — S1 0.93%, S2 0.97% residual, not truly 0%. Title updated to \\\"Near-Complete\\\"\\n- \\\"Principled framework applicable to arbitrary IE ontologies\\\" — validated on 2 datasets + 1 model only\\n- \\\"F1 improvement\\\" — SciERC: not significant (p=0.58), frame as F1-neutral; DocRED: significant (+0.50pp, p<0.001), 可报告但不升级为 core claim，归因于 OOV elimination 而非约束解码本身的提升\\n- \\\"CF reveals type system ambiguity\\\" — 可在 §5.3 作为 analysis finding 展开（Generic↔OtherScientificTerm 等模式有独立 insight 价值），但 §7 必须同时保留 CF 作为 limitation + future work。**两处都要有，缺一不可。** 不能暗示\\\"因为是 type ambiguity 所以 CF 可接受\\\"\\n\\n**Do NOT claim**:\\n- \\\"General infrastructure for IE\\\" — only zero-shot extraction validated\\n- \\\"State-of-the-art\\\" — F1 is control variable, not optimization target (see C8)\\n- \\\"Synergistic effect\\\" — mechanism is enabling dependency, not mutual amplification (see Claim 3)\\n- \\\"S2 solves CF\\\" or \\\"S2 mitigates Structure Snowballing\\\" — data shows S2 ≈ S1 on all metrics; position as architectural variant only\\n- \\\"Pilot50 DR=0%\\\" — small-sample artifact, full S2 has DR=0.97%\\n- \\\"Grammar-first invariant\\\" 作为独立 claim — 证据不足（仅 1 次崩溃触发，实现是 fallback 非形式化保证）。写入 §4 方法论设计原则（1-2 句），不升级为 claim\\n- \\\"Robust dual-layer composition across schema complexities\\\" — 等 DocRED 完成。最终如 fallback ≤5/998，可写经验性陈述，不做泛化 claim\\n\\n## Risk Ranking (ordered by reject probability)\\n\\n1. **CF violation trade-off under-addressed** (MEDIUM-HIGH): S1 9.9%, S2 8.03% — both elevated. **S2 confirmed: does NOT solve CF.** This is the #1 attack surface. Mitigated by proactive disclosure + severity distinction + root cause analysis (C7). Must be reported as explicit limitation with future work direction (global entity-type consensus).\\n2. ~~**Single model limitation**~~ (RESOLVED): Llama-3.1-8B SciERC ✅ (DR↓99.4%) + DocRED ✅ (DR↓90.2%). 2 模型 × 2 数据集全矩阵完成。\\n3. **Novelty perception** (MEDIUM): \\\"PLDI'25 for code → OntoCoDec for IE\\\" attack line. Must argue IE constraint structure differs fundamentally.\\n4. ~~**DocRED Phase 2 weak**~~ (RESOLVED → reframed as D014): Qwen DR↓44.7%, Llama DR↓90.2% — both substantial. Weaker Qwen reduction explained by RV baseline interaction (D014), not method failure.\\n5. ~~**Phase 2 F1 drop**~~ (RESOLVED): F1 confirmed neutral (SciERC) or positive (DocRED, p<0.001). Bootstrap CI D012 confirms. No longer a risk.\\n\\n## Critical Path to EMNLP Submission (May 25)\\n\\n- **May 13-14**: Phase 0 + Phase 1 + Phase 2 SciERC ✅\\n- **May 14**: Phase 2 DocRED 4-way ablation ✅ + Llama SciERC cross-model ✅ + Dream 完成 (3/6)\\n- **May 14-15**: Llama DocRED 2 组实验 ✅ + Checker 修正 ✅ + post-hoc baseline ✅ + bootstrap CI ✅ + related work ✅\\n- **May 14-15**: D014 tightness claim 修订 + §5 cross-model subsection + abstract/conclusion 修正 (Agent 执行中)\\n- **May 15-17**: 全文校对 + Discussion 整合 + 最终数字确认\\n- **May 19**: 内部稿 → submit_paper_to_review\\n- **May 19-24**: Review 修改 + 最终提交\\n\\n**当前瓶颈**: 无技术 blocker。等 Reviewer 跨文件一致性审查 + 编译验证后即可 submit_paper_to_review。\\n\\n## Status\\n- Phase 0 SciERC: ✅ Complete (minimal + schema-informed)\\n- Phase 0 DocRED: ✅ Complete (minimal 18.7% DR + schema-informed 12.8% DR)\\n- Phase 1 Compiler: ✅ Complete (grammar + semantic layers integrated)\\n- Phase 2 SciERC (5 configs): ✅ Complete (S1 DR↓94% F1-neutral, S2 降级为 ablation)\\n- Phase 2 DocRED (4 configs): ✅ Complete (full_s1 DR↓45%, grammar ET/RV→0%)\\n- Llama SciERC cross-model: ✅ Complete (DR↓99.4%, F1-neutral, 零代码修改)\\n- Llama DocRED cross-model: ✅ Complete (full_s1 DR↓90.2%, unconstrained DR=26.07%)\\n- Checker v2 (D011): ✅ Fixed (ET triple-counting → unique entity dedup)\\n- Bootstrap CI (D012): ✅ Fixed + confirmed (entity filter bug resolved)\\n- Post-hoc baseline (D013): ✅ Complete (multi-dimensional framing)\\n- Related work: ✅ 42 bib entries, 4 additions merged\\n- Dream 6/6 actions: ✅ All complete\\n- CF violation analysis: ✅ Confirmed inherent limitation (S1 9.9% SciERC / 2.57% DocRED / 12.02% Llama DocRED)\\n- D014 tightness revision: ✅ Complete (tightness × RV baseline dual-factor)\\n- Llama bootstrap CI (D016): ✅ Fixed + verified (registry-aligned ≤0.05pp, all p-values in paper)\\n- Paper compilation: ✅ 8 pages正文 + appendix\\n\", \"total_chars\": 20295, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8122cb43-c099-4bd4-af3a-f79d7e5ea38b",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "85fbfa62-7d32-440c-b992-9f80b3d35546",
  "sourceToolAssistantUUID": "8122cb43-c099-4bd4-af3a-f79d7e5ea38b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-16T02:52:40.395Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01WY4z6USB1GqY3VHcAjgFmM`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "ideas.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "85fbfa62-7d32-440c-b992-9f80b3d35546",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRBJ4Ex6MNM1vRNJbA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a32e9951-5cd9-4633-b12e-12d98ac1543a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LHYWxXM2y79T9rbHu8Yefe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2742,
      "cache_read_input_tokens": 17384,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2742,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 66,
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

_source line 16 · 2026-05-16T02:52:40.405Z_

<details><summary>↩ Tool result · `toolu_01WY4z6USB1GqY3VHcAjgFmM`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No ideas.md found for 'schema_semantic_constrained_ie'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a32e9951-5cd9-4633-b12e-12d98ac1543a",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "be20808c-7ebf-4b06-8177-a5b286ec82bb",
  "sourceToolAssistantUUID": "a32e9951-5cd9-4633-b12e-12d98ac1543a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-16T02:52:41.401Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_015MC6ZLUZWr5M9xgbnJ7nvt`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "decisions.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "be20808c-7ebf-4b06-8177-a5b286ec82bb",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRBJ4Ex6MNM1vRNJbA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0038041a-53fc-4eea-bfe6-5b43641297e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LHYWxXM2y79T9rbHu8Yefe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2742,
      "cache_read_input_tokens": 17384,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2742,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 66,
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

_source line 18 · 2026-05-16T02:52:41.413Z_

<details><summary>↩ Tool result · `toolu_015MC6ZLUZWr5M9xgbnJ7nvt`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/decisions.yaml\", \"content\": \"_next_id: 30\\ndecisions:\\n- id: D001\\n  date: 2026-05-13 17:38 UTC\\n  summary: 主目标调整为 EMNLP 2026 ARR (5/25), AAAI 2027 为后备\\n  rationale: 用户明确指出 EMNLP ARR 5/25 时间不紧、不要保守、资源会给够。12 天 AI 团队速度足够：Phase 0 (1-2天) →\\n    Phase 1 compiler (2-3天) → Phase 2 experiments (2-3天) → Paper (2-3天)。禁止 fallback\\n    思维，冲最高目标。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-13 19:14 UTC\\n  summary: SciERC Phase 0 结果确认 GO — domain_range violation rate 15.4%，3× 超阈值\\n  rationale: 'SciERC 全量 test set (551 sentences, 1724 triples): domain_range_violation_rate\\n    = 15.4%，远超 5% go/no-go 阈值。违规分布极不均匀 (Feature-of 33.5%, Compare 42.4% vs Used-for\\n    0.76%)，支持\\\"特定 relation types 需要 decoding-time enforcement\\\"的论文 claim。DocRED dry-run\\n    (37 docs) 同样显示 14.4%。两个数据集均为 GO 信号，MVP 核心假设得到强验证。等 schema-informed prompt 结果确认\\n    prompt 级干预不足以解决问题后正式宣布 MVP 通过。'\\n  related_experiments:\\n  - exp_id: mvp_phase0_violation_rate\\n    role: primary\\n    result: domain_range_violation_rate=15.4%, go_nogo=GO\\n  depends_on:\\n  - D001\\n- id: D003\\n  date: 2026-05-13 21:48 UTC\\n  summary: MVP 通过，进入 Research 阶段，立即启动 Phase 2 constrained decoding 实验\\n  rationale: Phase 0 三个实验完成：SciERC 15.4%/5.78%, DocRED 18.7% domain_range violation\\n    rate。两个数据集均远超 5% 阈值，核心假设得到强验证。Phase 1 compiler 代码就绪（36 tests 通过），Phase 2 脚本就绪（S1\\n    路径可用，S2 bug 修复中）。cuda:1 空闲，立即启动 Phase 2 SciERC grammar_only/semantic_only/full_s1\\n    实验。\\n  related_experiments:\\n  - exp_id: mvp_phase0_violation_rate\\n    role: primary\\n    result: SciERC DR=15.4%, GO\\n  - exp_id: mvp_phase0_scierc_schema\\n    role: primary\\n    result: SciERC DR=5.78%, prompt insufficient\\n  - exp_id: mvp_phase0_violation_rate_docred\\n    role: primary\\n    result: DocRED DR=18.7%, GO\\n  depends_on:\\n  - D002\\n- id: D004\\n  date: 2026-05-14 01:53 UTC\\n  summary: Phase 2 SciERC 核心结果确认：grammar+semantic (full_s1) DR↓94% F1 neutral，两层约束协同效应成立\\n  rationale: _v2 干净数据 551 样本全量结果：full_s1 DR=0.93%（baseline 15.37%，↓94%），R-F1 微升 +0.0013。grammar\\n    单独消除 RV/ET，semantic 单独降 DR 24%，组合后 94%——超加性效应。论文核心 claim 站住。早期污染数据 semantic_only\\n    DR=16.43% 已修正为 11.65%。\\n  related_experiments:\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline\\n    result: DR=15.37%\\n  - exp_id: phase2_scierc_grammar_only\\n    role: ablation\\n    result: DR=14.84%, RV/ET=0%\\n  - exp_id: phase2_scierc_semantic_only\\n    role: ablation\\n    result: DR=11.65%\\n  - exp_id: phase2_scierc_full_s1\\n    role: core_result\\n    result: DR=0.93%, F1=0.0836\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-14 01:53 UTC\\n  summary: Phase 2 SciERC 核心结果确认：Full S1 DR↓94% F1无损，CF violation↑124x 作为已知 tradeoff\\n    待 S2 对比后决定处理策略\\n  rationale: v2 干净数据 551/551 全量验证，Reviewer PASS。Grammar+Semantic 协同效应成立，ablation story\\n    清晰。CF violation（0.08%→9.9%）是约束副作用，需等 S2 结果判断是在论文中作为 limitation 还是加 CF 约束修复。\\n  related_experiments:\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline\\n    result: DR=15.37%, RV=1.39%, ET=0.4%, RF1=0.0823\\n  - exp_id: phase2_scierc_grammar_only\\n    role: ablation\\n    result: DR=14.84%, RV=0%, ET=0%, RF1=0.0823\\n  - exp_id: phase2_scierc_semantic_only\\n    role: ablation\\n    result: DR=11.65%, RV=1.51%, ET=0.4%, RF1=0.0815\\n  - exp_id: phase2_scierc_full_s1\\n    role: core_result\\n    result: DR=0.93%, RV=0%, ET=0%, RF1=0.0836, CF=9.9%\\n  depends_on: []\\n- id: D006\\n  date: 2026-05-14 01:54 UTC\\n  summary: Phase 2 SciERC 核心结果确认：Full S1 DR -94% 且 F1 无损，CF violation 上升为已知 limitation\\n  rationale: v2 干净数据全量（551/551）结果经 Reviewer PASS 验证：Full S1 DR 15.37%→0.93%（↓94%），R-F1\\n    +0.13pp，ET/RV→0%。Ablation story 清晰（grammar 管格式、semantic 管语义、双层协同）。CF violation\\n    从 0.08%→9.9% 是已知副作用，需在论文中正面报告并论述与 DR 的性质差异。Semantic-only DR=11.65% 说明两层是 multiplicative\\n    关系。决定推进 DocRED Phase 2 跨数据集验证 + 等 S2 对比。\\n  related_experiments:\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline\\n    result: DR=15.37%, R-F1=0.0823\\n  - exp_id: phase2_scierc_grammar_only\\n    role: ablation\\n    result: DR=14.84%, RV/ET=0%, F1持平\\n  - exp_id: phase2_scierc_semantic_only\\n    role: ablation\\n    result: DR=11.65%, F1-0.08pp\\n  - exp_id: phase2_scierc_full_s1\\n    role: core_result\\n    result: DR=0.93%, R-F1=0.0836(+0.13pp)\\n  - exp_id: mvp_phase0_docred_schema\\n    role: motivation\\n    result: DocRED DR=12.8%(-32%), 验证prompt级不足\\n  depends_on: []\\n- id: D007\\n  date: 2026-05-14 02:09 UTC\\n  summary: S2 降级为架构 ablation，S1 为主推策略；标题去掉 \\\"Guaranteed\\\" 改 \\\"Near-Complete\\\"\\n  rationale: S2 全量结果(551/551)确认：DR 0.97%(vs S1 0.93%)、CF 8.03%(vs S1 9.9%，降幅不显著)、R-F1\\n    8.03%(vs S1 8.36%)。S2 在所有指标上均未优于 S1，两通道分离未能解决 CF 问题。CF 是 per-relation 独立 type\\n    enforcement 的固有限制，非架构可解。S2 定位从\\\"CF 解决方案\\\"调整为\\\"架构灵活性展示\\\"，论文中放 ablation/appendix。标题\\n    \\\"Guaranteed\\\" 与 0.93% 残余不符，改为 \\\"Near-Complete\\\"。\\n  related_experiments:\\n  - exp_id: phase2_scierc_full_s2\\n    role: primary\\n    result: DR=0.97%, CF=8.03%, R-F1=8.03% — no advantage over S1\\n  - exp_id: phase2_scierc_full_s1\\n    role: baseline\\n    result: DR=0.93%, CF=9.9%, R-F1=8.36%\\n  depends_on: []\\n- id: D008\\n  date: 2026-05-14 04:33 UTC\\n  summary: 补跑 DocRED semantic_only 完成跨数据集全消融；论文写作提前至 DocRED 分析完成后立即启动\\n  rationale: 'SciERC 有 5 路消融但 DocRED 只有 grammar_only + full_s1，缺 semantic_only。Claim\\n    3 (enabling dependency) 在 DocRED 上的证据链不完整——审稿人必问\\\"为何 DocRED 不做 semantic_only 对比\\\"。DocRED\\n    约束更紧(avg 5.68 valid pairs)，semantic_only 预期效果更差，反而是 enabling dependency 的更强证据。论文写作从\\n    5/19 提前到 DocRED 分析完成后(~5/16)，DocRED semantic_only 与写作并行，结果 patch 进去。grammar-semantic\\n    交互 bug (invariant: semantic mask ⊆ grammar allowed set) 需写入 Method section 作为\\n    resolution protocol。'\\n  related_experiments:\\n  - exp_id: phase2_docred_grammar_only\\n    role: running\\n    result: pending\\n  - exp_id: phase2_docred_full_s1\\n    role: running\\n    result: pending\\n  - exp_id: phase2_scierc_semantic_only\\n    role: reference\\n    result: DR↓24% but ET/RV not eliminated\\n  depends_on:\\n  - D006\\n  - D007\\n- id: D009\\n  date: 2026-05-14 06:19 UTC\\n  summary: Llama-3.1-8B cross-model 验证升级为 should-have，SciERC-only (unconstrained +\\n    full_s1)\\n  rationale: Reviewer 实测 DocRED 实验进度远超预期（May 15 早间全部完成 vs 原估 May 17-18），多出 2-3 天 buffer。单模型是最可能的\\n    EMNLP reviewer 批评 (C5)，2 组 SciERC 实验 4-6 GPU 小时即可完成，风险可控。constraint compiler 声称\\n    model-agnostic，跨模型验证是最直接的证据。\\n  related_experiments:\\n  - exp_id: phase2_scierc_full_s1\\n    role: baseline_same_model\\n    result: DR↓94% F1无损\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline_same_model\\n    result: DR 15.37%\\n  depends_on:\\n  - D006\\n  - D008\\n- id: D010\\n  date: 2026-05-14 17:59 UTC\\n  summary: Dream 三档 Weak Reject (3/6) → 制定 6 项结构性补强计划：post-hoc baseline + bootstrap\\n    CI + related work 20+ + PICARD 对比 + CF/F1 Discussion 段\\n  rationale: Dream 模拟三档一致指出 6 个结构性缺陷：(1) 单模型泛化弱 → Llama cross-model 已在跑，(2) 无 post-hoc\\n    filtering baseline → 必须加，(3) related work 仅 7 引用 → 扩到 20+，(4) 无统计显著性 → bootstrap\\n    CI，(5) CF trade-off 无下游验证 → 加强论证，(6) 低 F1 实用性 → Discussion 段。Dream 基于缺少 Llama\\n    数据 + 有 bug 的 violation 数字，实际情况好于模拟。补强后预期从 3/6 提升到 4-5/6 区间。\\n  related_experiments:\\n  - exp_id: llama_docred_full_s1\\n    role: addresses U1 (cross-model)\\n    result: RUNNING\\n  - exp_id: llama_docred_unconstrained\\n    role: addresses U1 (cross-model)\\n    result: RUNNING\\n  - exp_id: llama_scierc_full_s1\\n    role: addresses U1 (cross-model)\\n    result: success\\n  depends_on:\\n  - D009\\n- id: D011\\n  date: 2026-05-14 18:16 UTC\\n  summary: 推翻之前 ET 计数口径决定——修正 ET triple-counting，每个 entity 只计 1 次 ET violation（不在\\n    entity_list + head + tail 各计一次）\\n  rationale: Reviewer 审查指出：(1) ET=8.18% 被 inflate 至多 3× (实际 ~2.47%)，是不必要的攻击面；(2) grammar/full_s1\\n    ET=0% 不受影响；(3) 相对对比仍有效；(4) 距 May 19 DDL 仍有修正窗口。之前\\\"保持一致性\\\"的理由成立但 Reviewer 认为论文可信度\\n    > 方法学惰性。修正后所有非零 ET 数字将变小，但 constrained decoding 的 ET→0% 仍然成立，paper story 更干净。\\n  related_experiments:\\n  - exp_id: phase2_docred_unconstrained\\n    role: ET 8.18%→~2.47%\\n    result: 需重算\\n  - exp_id: phase2_docred_semantic_only\\n    role: ET 10.44%→~3.5%\\n    result: 需重算\\n  depends_on:\\n  - D010\\n- id: D012\\n  date: 2026-05-14 18:26 UTC\\n  summary: 'Bootstrap CI framing: 选 (B) 逐数据集报告 F1 significance，DocRED +0.50pp p<0.001，SciERC\\n    neutral p=0.58'\\n  rationale: Bootstrap CI (10000×) 揭示 DocRED F1 提升统计显著，机制为 grammar 消除 OOV relation\\n    names (RV 29.66%→0.03%) 减少 FP。SciERC RV 仅 1.39% 故效果不显著。选逐数据集报告而非统一 framing，最诚实且不升级为\\n    core claim。更新 paper_framing.md 中 C6/C8 相关表述。\\n  related_experiments:\\n  - exp_id: phase2_docred_full_s1\\n    role: primary\\n    result: R-F1 +0.50pp vs unconstrained, p<0.001\\n  - exp_id: phase2_scierc_full_s1\\n    role: primary\\n    result: R-F1 +0.13pp vs unconstrained, p=0.58 (non-significant)\\n  depends_on:\\n  - D010\\n- id: D013\\n  date: 2026-05-14 18:28 UTC\\n  summary: 'Post-hoc baseline framing: 不以 F1 论高低，多维对比 (recall + coverage + operational)，诚实承认\\n    precision trade-off'\\n  rationale: Post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.24），因\\n    low F1 regime 下移除 FP 大幅提升 precision。但 post-hoc recall 下降（SciERC -0.72pp, DocRED\\n    -1.06pp），DocRED 丢弃 48.1% triples。OntoCoDec recall 上升（+0.20/+0.56pp）= 概率质量重分配生效。Framing\\n    重心放在 recall preservation + information coverage + streaming compatibility，诚实承认\\n    precision trade-off。\\n  related_experiments:\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline\\n    result: R-F1 8.23\\n  - exp_id: phase2_scierc_full_s1\\n    role: primary\\n    result: R-F1 8.36, recall 11.60\\n  - exp_id: phase2_docred_unconstrained\\n    role: baseline\\n    result: R-F1 7.74\\n  - exp_id: phase2_docred_full_s1\\n    role: primary\\n    result: R-F1 8.24, recall 10.02\\n  depends_on:\\n  - D010\\n  - D012\\n- id: D014\\n  date: 2026-05-14 20:33 UTC\\n  summary: Tightness scaling claim 修订：从单因素(tightness)改为双因素(tightness × model RV baseline)。Llama\\n    DocRED DR↓90.2% 打破原 \\\"scales inversely with tightness\\\" claim。\\n  rationale: Llama DocRED full_s1 DR 26.07%→2.55% (↓90.2%) vs Qwen 18.46%→10.21% (↓44.7%)。同一\\n    ontology (τ̄=0.842) 下差距巨大。原因：Qwen RV=29.66% 远高于 Llama RV=16.03%，grammar 层将 OOV\\n    triples 强制匹配有效关系名后揭露大量 latent DR violations。修订为\\\"tightness 与 model RV baseline\\n    共同决定 enforcement ceiling\\\"。这实际强化论文——揭示 model-constraint 交互效应。同时 E-F1 claim 需限定为\\n    Qwen-specific（Llama E-F1 -0.64pp）。\\n  related_experiments:\\n  - exp_id: llama_docred_full_s1\\n    role: primary\\n    result: DR 26.07→2.55 (↓90.2%), R-F1 +0.29pp, E-F1 -0.64pp, CF 12.02%\\n  - exp_id: llama_docred_unconstrained\\n    role: baseline\\n    result: DR 26.07%, RV 16.03%, R-F1 5.98%\\n  - exp_id: phase2_docred_full_s1\\n    role: comparison\\n    result: DR 10.21% (↓44.7%), Qwen RV baseline 29.66%\\n  depends_on:\\n  - D012\\n  - D013\\n- id: D015\\n  date: 2026-05-14 22:29 UTC\\n  summary: 'D015: Dream #2 结果处理 — Title 去掉 \\\"Near-Complete\\\"，6 项 action items 按优先级处理'\\n  rationale: 'Dream #2 三档 worst=2.5/median=3.0/best=3.0，比 Dream #1 (全 3/6) 改善。三档共识：(1)\\n    Title \\\"Near-Complete\\\" overclaim (DocRED 10.21% residual)，(2) CF severity 无 downstream\\n    验证，(3) 技术新颖性质疑。Title 修订为去掉 \\\"Near-Complete\\\"——论文贡献是方法（compiled ontology constraints），不是特定消除率；结果从\\n    0.93% 到 10.21% 变异太大不适合 \\\"Near-Complete\\\"。CF downstream 验证需架构修改，5天内不可行，保持在 limitations。技术新颖性通过\\n    §6 positioning 强化 IE-specific 贡献（stateful entity registry, prefix-decidable constraints）。'\\n  related_experiments:\\n  - exp_id: dream_20260514T205155\\n    role: dream\\n    result: worst=2.5, median=3.0, best=3.0\\n  depends_on:\\n  - D014\\n  - D013\\n  - D012\\n- id: D016\\n  date: 2026-05-14 22:57 UTC\\n  summary: 'D016: Llama bootstrap CI 修复完成，全部 p-values 写入论文，framing 从 \\\"F1-neutral\\\"\\n    升级为 \\\"both models significant R-F1 gains on DocRED\\\"'\\n  rationale: v2 bootstrap 脚本修复了两个 bug（int entity crash + entity type normalization），8\\n    项 point estimate 全部 registry-aligned (≤0.05pp)。结果：Llama DocRED R-F1 +0.29pp p=0.013（显著正向），E-F1\\n    -0.64pp p=0.022（显著负向）。这使得 DocRED 上两个模型 R-F1 都显著提升，是比 \\\"F1-neutral\\\" 更强的 claim。E-F1\\n    模型依赖性如实报告。已更新 crossmodel §5、abstract、conclusion。\\n  related_experiments:\\n  - exp_id: llama_scierc_unconstrained\\n    role: baseline\\n    result: R-F1=2.68, E-F1=23.56\\n  - exp_id: llama_scierc_full_s1\\n    role: treatment\\n    result: R-F1=2.54 (-0.14pp p=0.011), E-F1=23.49 (NS)\\n  - exp_id: llama_docred_unconstrained\\n    role: baseline\\n    result: R-F1=5.98, E-F1=55.65\\n  - exp_id: llama_docred_full_s1\\n    role: treatment\\n    result: R-F1=6.27 (+0.29pp p=0.013), E-F1=55.01 (-0.64pp p=0.022)\\n  depends_on:\\n  - D015\\n  - D014\\n  - D012\\n- id: D017\\n  date: 2026-05-15 14:10 UTC\\n  summary: 'D017: 批准 pair-based σ(r) enforcement 升级，与 W1 CF fallback 合并实现。SciERC DR\\n    0.93%→0% 可期，DocRED DR 再降 ~28%'\\n  rationale: Rectangularity 分析显示 SciERC 0/7、DocRED 73/96 relations 非矩形。当前 independent\\n    enforcement (head∈dom ∧ tail∈range) 是 pair-based σ(r) 的松弛近似，SciERC 全部 16 个残余 DR\\n    violations 属于 over-permissive gap。实现 pair-based 改动量小（set membership → tuple lookup），可与\\n    CF fallback 代码合并，无额外 GPU 开销。收益：SciERC DR=0% 是 complete elimination claim，显著强于\\n    near-complete。\\n  related_experiments:\\n  - exp_id: phase2_scierc_full_s1\\n    role: evidence\\n    result: 16 residual DR all from over-permissive gap\\n  - exp_id: phase2_docred_full_s1\\n    role: evidence\\n    result: 491/1770 DR (27.7%) from over-permissive gap\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: baseline\\n    result: running, validates CF mechanism\\n  depends_on:\\n  - D014\\n- id: D018\\n  date: 2026-05-15 14:14 UTC\\n  summary: 'D018: 批准 W5 LoRA fine-tune 实验（Qwen3-8B on SciERC），条件启动——先验 baseline DR\\n    再决定跑 constrained'\\n  rationale: Reviewer 分析指出 W5 是从 Weak Reject → Accept 的最大杠杆（预估 +0.5 分）。LoRA fine-tune\\n    Qwen3-8B on SciERC 是最受控实验（同模型同数据只加 fine-tuning 变量），~6 GPU-hrs，可与 W1 CF fallback\\n    并行。风险控制：先跑 unconstrained fine-tuned baseline 检查 DR 率，若 DR<2% 则边际收益不显著需重新评估。10\\n    天 DDL 内时间充裕。\\n  related_experiments:\\n  - exp_id: phase2_scierc_full_s1\\n    role: baseline\\n    result: DR=0.93%, R-F1=8.36%\\n  - exp_id: phase2_scierc_unconstrained\\n    role: baseline\\n    result: DR=15.21%, R-F1=8.23%\\n  depends_on:\\n  - D017\\n- id: D019\\n  date: 2026-05-15 14:14 UTC\\n  summary: 'D018: 修正 D017 — 代码已是 pair-based，取消代码改动，改为纯写作修复 + 残余 DR 根因调查。批准 W5 LoRA\\n    fine-tune 实验（~6 GPU-hrs）'\\n  rationale: 'Reviewer 独立核实 type_mask_processor.py:360 调用 valid_tail_types_for_head(head_type)，combined\\n    enforcement 等价于 full pair-based。§3 Eq.(2) 和 line 106-107 描述错误（写了 independent dom/range），W2\\n    标注 resolved 不正确。D017 的代码改动取消，转为：(1) §3 formalization 与代码对齐（σ-notation）(2) 调查 SciERC\\n    16 个残余 DR 的真实原因（代码已 pair-based 却仍有 violations）(3) rectangularity 量化数据作为新 finding\\n    写入论文。同时批准 W5 LoRA fine-tune SciERC 实验（~6 GPU-hrs），staged approach: 先跑 unconstrained\\n    fine-tuned baseline 检查 DR，>5% 再跑 constrained。这是从 Weak Reject 到 Accept 的最大杠杆。'\\n  related_experiments:\\n  - exp_id: phase2_scierc_full_s1\\n    role: evidence\\n    result: 16 residual DR despite pair-based code — cause unknown\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: ongoing\\n    result: running, validates CF mechanism\\n  depends_on:\\n  - D017\\n- id: D020\\n  date: 2026-05-15 14:59 UTC\\n  summary: 'D020: W1 CF fallback 定为 analytical finding（方案 A 变体），取消剩余 3 个 CF 实验，GPU\\n    全转 W5'\\n  rationale: CF fallback pilot 结果明确：CF 9.90%→0.04% 但 DR 0.93%→14.78%，总违规预算反增 3.99pp。本质是约束优先级\\n    re-routing 而非 reduction。无需跨模型/数据集确认——机制层面已解释清楚（registry 一致性 vs DR enforcement\\n    的基本张力）。加上之前 CF 63.3% 来自 Generic↔OST schema 歧义的分析，W1 回应转为：\\\"CF↔DR 根本性张力 + 当前系统近最优\\n    + CF 主要来自 schema 歧义\\\"。这比\\\"我们消除了 CF\\\"更诚实也更有深度。取消 3 个 CF 实验释放 ~12 GPU-hrs，全部投入更高 impact\\n    的 W5 LoRA（+0.5 分 vs +0.3 分）。\\n  related_experiments:\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: evidence\\n    result: CF 0.04% but DR 14.78%, total +3.99pp, NEGATIVE\\n  - exp_id: phase2_scierc_full_s1\\n    role: baseline\\n    result: CF 9.90%, DR 0.93%, total 10.83%\\n  depends_on:\\n  - D017\\n  - D018\\n- id: D021\\n  date: 2026-05-15 15:37 UTC\\n  summary: 'D021: 保留 w1_cf_fallback_docred 实验（修正 D020），取消仅限 2 个 Llama CF 实验'\\n  rationale: D020 说取消 3 个 CF 实验，但 docred CF 已在 D020 后 4min 被提交到 cuda:1。当前不阻塞 W5（W5\\n    eval 在 cuda:0）。DocRED τ̄=0.842（远高于 SciERC 0.333），跨数据集验证 CF↔DR trade-off 有独立价值——特别是\\n    tightness→fallback rate 的 6× 相关性。Python 进程已加载代码到内存，磁盘上回退 CF fallback 代码不影响运行中的\\n    DocRED 实验。保留 docred，仅取消 llama_scierc 和 llama_docred。\\n  related_experiments:\\n  - exp_id: w1_cf_fallback_docred\\n    role: target\\n    result: RUNNING cuda:1, 9% progress\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: reference\\n    result: NEGATIVE, DR 14.78%\\n  depends_on:\\n  - D020\\n- id: D022\\n  date: 2026-05-15 15:57 UTC\\n  summary: 'D022: W5 gate DR=1.95%≈2%, 仍跑 constrained eval 收集完整 2×2 矩阵（base/FT × unconstrained/constrained）'\\n  rationale: 1) 1.95% vs 2% 差异在噪声范围内，不应以硬阈值卡掉有价值的数据；2) 完整 2×2 对比表是论文 composability\\n    story 的核心证据——fine-tuning 内化常见约束，OntoCoDec 消除剩余 schema-ambiguous 违规（Evaluate-for\\n    13.1%），两者互补；3) 成本极低（~30min 1×GPU）；4) 无数据的 claim 不如有数据的 nuanced claim\\n  related_experiments:\\n  - exp_id: w5_lora_scierc_unconstrained_eval\\n    role: gate_check\\n    result: DR=1.95%, R-F1=43.9%, E-F1=67.1%\\n  - exp_id: w5_lora_scierc_training\\n    role: prerequisite\\n    result: success, loss=0.0586, acc=98.16%\\n  depends_on:\\n  - D018\\n- id: D023\\n  date: 2026-05-15 16:01 UTC\\n  summary: 'Reframe Claim 3 (composability): 从 \\\"fine-tuning 后仍有高 DR\\\" 转为 \\\"fine-tuning\\n    消除大部分违规，tight-constraint 关系是 learning-resistant 长尾，约束解码精确覆盖此尾部\\\"'\\n  rationale: W5 unconstrained eval 聚合 DR=1.95% 以 0.05pp 之差未过 2% 阈值，但按关系类型拆分后 Evaluate-for\\n    DR=13.13%（tightness=0.361，仅 23 个合法 pair），而宽松关系（Used-for 0.16%、Hyponym-of 0%）几乎被\\n    fine-tuning 消灭。新叙事更精确、更可辩护：约束解码的价值不是全局覆盖，而是精确靶向 learning 难以覆盖的 tight-constraint\\n    长尾。这比原来的\\\"一刀切需要约束\\\"论点更强。\\n  related_experiments:\\n  - exp_id: w5_lora_scierc_unconstrained_eval\\n    role: evidence\\n    result: DR=1.95% aggregate, Evaluate-for 13.13%, fine-tuning +36pp E-F1 +35pp\\n      R-F1\\n  depends_on: []\\n- id: D024\\n  date: 2026-05-15 16:27 UTC\\n  summary: 'D024: W5 composability 确认 — Fine-tuned + OntoCoDec 实现 DR=0.0%，R-F1 仅损\\n    0.09pp，CF 从 9.90pp 降至 1.18pp。2×2 矩阵是 Claim 3 最强证据。'\\n  rationale: 'Reviewer #11 PASS。2×2 矩阵清晰证明 fine-tuning 和 OntoCoDec 互补而非冗余：fine-tuning\\n    负责质量(F1+35pp)，OntoCoDec 负责合规保障(DR→0%)。Tight-constraint 关系(Evaluate-for 13.13%→0%)是\\n    OntoCoDec 的独特价值——fine-tuning 无法学会紧约束。CF 残余 1.18% 源于 schema 歧义(Generic↔X)，非系统缺陷，放\\n    limitations。目标分数从 2.75 升至 3.75-4.0。'\\n  related_experiments:\\n  - exp_id: w5_lora_scierc_constrained_eval\\n    role: primary\\n    result: DR=0.0%, CF=1.18%, R-F1=43.77%, composability confirmed\\n  - exp_id: w5_lora_scierc_unconstrained_eval\\n    role: baseline\\n    result: DR=1.95%, CF=0%, R-F1=43.86%\\n  - exp_id: w5_lora_scierc_training\\n    role: prerequisite\\n    result: LoRA adapter trained successfully\\n  - exp_id: phase2_scierc_full_s1\\n    role: comparison\\n    result: zero-shot DR=0.93%, CF=9.90%, R-F1=8.36%\\n  depends_on:\\n  - D022\\n  - D023\\n- id: D025\\n  date: 2026-05-15 16:27 UTC\\n  summary: 'D024: W5 composability 确认——Fine-tuned + OntoCoDec 实现 DR=0.0%，R-F1 仅损 0.09pp，CF\\n    从 9.90pp 降至 1.18pp。2×2 矩阵是论文最强证据。'\\n  rationale: 'Reviewer #11 独立核实 551/551 样本完整，violation_report 与 registry 交叉验证一致。2×2\\n    矩阵三个核心洞察：(1) composability 成立——FT 负责质量(+35pp F1)，OntoCoDec 负责合规(DR 0%)；(2) CF\\n    干扰随 FT 降低 88%（9.82pp→1.18pp）；(3) tight-constraint 关系（如 Evaluate-for τ=0.361）是\\n    OntoCoDec 独特价值——FT 后仍有 13.13% DR，OntoCoDec 降至 0%。目标分数从 2.75 提升至 3.75-4.0 (Accept)。'\\n  related_experiments:\\n  - exp_id: w5_lora_scierc_constrained_eval\\n    role: primary\\n    result: DR=0.0%, CF=1.18%, R-F1=43.77%, R-F1 delta=-0.09pp\\n  - exp_id: w5_lora_scierc_unconstrained_eval\\n    role: baseline\\n    result: DR=1.95%, CF=0%, R-F1=43.86%\\n  - exp_id: w5_lora_scierc_training\\n    role: prerequisite\\n    result: LoRA fine-tune success\\n  - exp_id: phase2_scierc_full_s1\\n    role: zero-shot comparison\\n    result: DR=0.93%, CF=9.90%, R-F1=8.36%\\n  depends_on:\\n  - D022\\n  - D023\\n- id: D026\\n  date: 2026-05-15 16:33 UTC\\n  summary: 'D026: 确认 w1_cf_fallback_docred 代码不含 CF fallback 逻辑（Reviewer 第三次核实），要求\\n    Agent 停止并修正'\\n  rationale: 'Reviewer 在 review #10, #12, #13 三次独立确认：cuda:1 上运行的 w1_cf_fallback_docred\\n    实际是普通 full_s1 配置，grep 无 cf_fallback 相关代码。继续运行只会产出与 phase2_docred_full_s1 重复的结果。要求\\n    Agent 立即验证并修正——实现真正 CF fallback 代码后重跑，或改为 D020 analytical finding 的 DocRED 延伸分析。'\\n  related_experiments:\\n  - exp_id: w1_cf_fallback_docred\\n    role: subject\\n    result: code mismatch confirmed 3x\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: reference\\n    result: D020 analytical finding\\n  depends_on:\\n  - D021\\n  - D020\\n- id: D027\\n  date: 2026-05-15 16:34 UTC\\n  summary: 'D026: 杀掉 w1_cf_fallback_docred（实际跑普通 full_s1，CF fallback 代码已回退），W1 转为\\n    analytical resolution + W5 FT 证据'\\n  rationale: 'Reviewer #12 确认 CF fallback 代码 grep 0 匹配，w1_cf_fallback_docred 实际运行\\n    plain full_s1，与已完成的 phase2_docred_full_s1 重复。W1 的实质回应已由 D020 analytical finding（CF↔DR\\n    根本性张力）+ W5 FT+OntoCoDec（CF 降 88%）充分覆盖。释放 cuda:1 用于 Llama SciERC eval 和潜在的 DocRED\\n    LoRA。'\\n  related_experiments:\\n  - exp_id: w1_cf_fallback_docred\\n    role: killed\\n    result: redundant plain full_s1, CF fallback code reverted\\n  - exp_id: phase2_docred_full_s1\\n    role: existing_equivalent\\n    result: success\\n  - exp_id: w1_cf_fallback_scierc_pilot\\n    role: analytical_basis\\n    result: D020 analytical finding\\n  depends_on:\\n  - D020\\n  - D021\\n  - D025\\n- id: D028\\n  date: 2026-05-15 18:13 UTC\\n  summary: 'D028: Llama SciERC 2×2 composability 确认——FT+OntoCoDec DR=0.09%, R-F1 +0.02pp，跨模型一致性成立'\\n  rationale: 'Llama FT+OntoCoDec: DR 从 1.11%→0.09%（-91.9%），R-F1 45.47%（+0.02pp 零代价）。与\\n    Qwen FT+OntoCoDec（DR=0.0%, R-F1 -0.09pp）高度一致，跨模型 composability claim 成立。论文 Table\\n    3/5 和 §5.4/5.5 已更新。'\\n  related_experiments:\\n  - exp_id: w5_llama_lora_scierc_constrained_eval\\n    role: primary\\n    result: DR=0.09%, R-F1=45.47%, E-F1=67.76%\\n  - exp_id: w5_llama_lora_scierc_unconstrained_eval\\n    role: baseline\\n    result: DR=1.11%, R-F1=45.45%, E-F1=67.76%\\n  - exp_id: w5_llama_lora_scierc_training\\n    role: prerequisite\\n    result: token_acc=98.17%, 654s\\n  depends_on:\\n  - D025\\n  - D023\\n- id: D029\\n  date: 2026-05-15 18:21 UTC\\n  summary: Kill all DocRED training processes and resubmit with CUDA_VISIBLE_DEVICES\\n    fix\\n  rationale: 'Reviewer critical: spec.command内层CUDA_VISIBLE_DEVICES=0硬编码覆盖wrapper注入值，导致Qwen跑在GPU\\n    0而非GPU 1；僵尸进程未清理占56 GiB致Llama OOM。全部kill后修复硬编码bug重新提交。Qwen才跑9%，重跑成本低于保留错误状态的风险。'\\n  related_experiments:\\n  - exp_id: w5_llama_docred_lora_training\\n    role: affected\\n    result: OOM crashed due to GPU 0 memory exhaustion\\n  - exp_id: w5_qwen_docred_lora_training\\n    role: affected\\n    result: Running on wrong GPU (0 instead of 1), zombie process from retry not cleaned\\n  depends_on: []\\n\", \"total_chars\": 22045, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0038041a-53fc-4eea-bfe6-5b43641297e2",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "9e755e73-6899-46f3-8744-2bc3488bd4e4",
  "sourceToolAssistantUUID": "0038041a-53fc-4eea-bfe6-5b43641297e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-16T02:52:41.679Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01BfHYsdPc21bAx6a5z9KhGP`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "ROADMAP.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9e755e73-6899-46f3-8744-2bc3488bd4e4",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRBJ4Ex6MNM1vRNJbA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "419b1895-d155-4fff-a5f1-8fe42153a6c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LHYWxXM2y79T9rbHu8Yefe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2742,
      "cache_read_input_tokens": 17384,
      "output_tokens": 390,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2742
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 390,
          "cache_read_input_tokens": 17384,
          "cache_creation_input_tokens": 2742,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2742,
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

_source line 20 · 2026-05-16T02:52:41.689Z_

<details><summary>↩ Tool result · `toolu_01BfHYsdPc21bAx6a5z9KhGP`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/ROADMAP.md\", \"content\": \"# schema_semantic_constrained_ie — Research Dashboard\\n\\n> 最后更新: 2026-05-15 18:13 UTC | 更新原因: D028: Llama SciERC 2×2 完成 + DocRED LoRA 双卡并行训练中\\n\\n## 核心方向\\nOntoCoDec: 两层约束解码（grammar + semantic）自动编译 IE ontology schema 为 token-level constraints，消除 LLM-based IE 的 ontology constraint violations。详见 paper_framing.md。\\n\\n## 当前进展\\n**阶段**: Round 1 审稿应对 — composability matrix 扩展中\\n- **Qwen SciERC 2×2**: ✅ DR=0.0%, R-F1 -0.09pp\\n- **Llama SciERC 2×2**: ✅ DR=0.09%, R-F1 +0.02pp (D028)\\n- **跨模型一致性确认**: Claim 3 composability 两模型坚实支撑\\n- **Issue Tracker**: 15/16 resolved + W1 in_progress (analytical finding + Paper Agent 写作中)\\n- **论文**: Table 3/5, §5.4/5.5, Appendix B 已更新，PDF 编译通过\\n\\n## Composability 覆盖进展\\n| | SciERC | DocRED |\\n|--|--------|--------|\\n| Qwen3-8B | ✅ 完整 2×2 | 🔥 LoRA 训练中 (cuda:1, ETA ~2h) |\\n| Llama3.1-8B | ✅ 完整 2×2 (D028) | ⏳ SFT 数据生成中 → cuda:0 训练 |\\n\\n## 2×2 Composability Matrices\\n\\n### Qwen3-8B × SciERC\\n| | Unconstrained | Constrained | ΔDR | ΔR-F1 |\\n|--|--|--|--|--|\\n| Zero-shot | DR=15.37%, R-F1=8.23% | DR=0.93%, R-F1=8.36% | -94% | +0.13pp |\\n| Fine-tuned LoRA | DR=1.95%, R-F1=43.86% | DR=0.0%, R-F1=43.77% | -100% | -0.09pp |\\n\\n### Llama3.1-8B × SciERC\\n| | Unconstrained | Constrained | ΔDR | ΔR-F1 |\\n|--|--|--|--|--|\\n| Zero-shot | DR=13.34%, R-F1=2.68% | DR=0.08%, R-F1=2.54% | -99.4% | -0.14pp |\\n| Fine-tuned LoRA | DR=1.11%, R-F1=45.45% | DR=0.09%, R-F1=45.47% | -91.9% | +0.02pp |\\n\\n## 关键路径\\n1. ~~Llama SciERC 2×2~~ ✅ (D028)\\n2. **Qwen DocRED LoRA** ← cuda:1 训练中 (~2h)\\n3. **Llama DocRED LoRA** ← cuda:0 准备中（SFT 数据 + 脚本适配）\\n4. 各自跑 unconstrained + constrained eval → 完整 4 格 matrix\\n5. 全文数字一致性审查 → Round 2 review\\n6. May 19 内部稿交付 → May 25 EMNLP ARR 提交\\n\\n## GPU 调度\\nwestd-16980: cuda:0 + cuda:1\\n- cuda:0: ⏳ Llama DocRED LoRA 待提交（SFT 数据生成中）\\n- cuda:1: 🔥 Qwen DocRED LoRA 训练中 (PID 295334)\\n\\n## 关键数字速查\\n| 指标 | Qwen SciERC | Qwen DocRED | Llama SciERC | Llama DocRED |\\n|------|-------------|-------------|--------------|--------------|\\n| DR reduction (ZS) | 94% | 45% | 99.4% | 90.2% |\\n| R-F1 delta (ZS) | +0.13pp | +0.50pp*** | -0.14pp | +0.29pp* |\\n| **FT+OntoCoDec DR** | **0.0%** | **TBD** | **0.09%** | **TBD** |\\n| **FT+OntoCoDec ΔF1** | **-0.09pp** | **TBD** | **+0.02pp** | **TBD** |\\n\\n## CF Fallback Ablation（D020 analytical finding）\\n| 指标 | full_s1 baseline | CF fallback | Delta |\\n|------|-----------------|-------------|-------|\\n| CF | 9.90% | 0.04% | -9.86pp |\\n| DR | 0.93% | 14.78% | +13.85pp |\\n| Total | 10.83% | 14.82% | +3.99pp |\\n结论：CF↔DR 根本性张力，当前系统近最优。63.3% CF 来自 schema 歧义。\\n\\n## 目标分数路径\\n- ~~Weak Reject 2.75/5~~\\n- ~~W1+W2 写作修复: 3.5/5~~\\n- ~~W5 LoRA 成功: 3.75-4.0/5~~\\n- **Llama LoRA 成功: 4.0/5+ (强 Accept)** ← 当前\\n- DocRED LoRA 全补完: 4.25/5 (very strong)\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D029 | 2026-05-15 | Kill all DocRED training processes and resubmit wi | w5_llama_docred_lora_training, w5_qwen_docred_lora_training |\\n| D028 | 2026-05-15 | D028: Llama SciERC 2×2 composability 确认——FT+OntoCo | w5_llama_lora_scierc_constrained_eval, w5_llama_lora_scierc_unconstrained_eval, w5_llama_lora_scierc_training |\\n| D027 | 2026-05-15 | D026: 杀掉 w1_cf_fallback_docred（实际跑普通 full_s1，CF fa | w1_cf_fallback_docred, phase2_docred_full_s1, w1_cf_fallback_scierc_pilot |\\n| D026 | 2026-05-15 | D026: 确认 w1_cf_fallback_docred 代码不含 CF fallback 逻辑 | w1_cf_fallback_docred, w1_cf_fallback_scierc_pilot |\\n| D025 | 2026-05-15 | D024: W5 composability 确认——Fine-tuned + OntoCoDec  | w5_lora_scierc_constrained_eval, w5_lora_scierc_unconstrained_eval, w5_lora_scierc_training, phase2_scierc_full_s1 |\\n| D024 | 2026-05-15 | D024: W5 composability 确认 — Fine-tuned + OntoCoDec | w5_lora_scierc_constrained_eval, w5_lora_scierc_unconstrained_eval, w5_lora_scierc_training, phase2_scierc_full_s1 |\\n| D023 | 2026-05-15 | Reframe Claim 3 (composability): 从 \\\"fine-tuning 后仍 | w5_lora_scierc_unconstrained_eval |\\n| D022 | 2026-05-15 | D022: W5 gate DR=1.95%≈2%, 仍跑 constrained eval 收集完 | w5_lora_scierc_unconstrained_eval, w5_lora_scierc_training |\\n| D021 | 2026-05-15 | D021: 保留 w1_cf_fallback_docred 实验（修正 D020），取消仅限 2  | w1_cf_fallback_docred, w1_cf_fallback_scierc_pilot |\\n| D020 | 2026-05-15 | D020: W1 CF fallback 定为 analytical finding（方案 A 变体 | w1_cf_fallback_scierc_pilot, phase2_scierc_full_s1 |\\n\\n\", \"total_chars\": 4203, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "419b1895-d155-4fff-a5f1-8fe42153a6c2",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "5be9b6fa-f469-44a6-b746-e9e3f9f3879a",
  "sourceToolAssistantUUID": "419b1895-d155-4fff-a5f1-8fe42153a6c2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-16T02:52:44.660Z_

Now let me read the actual paper and related work section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5be9b6fa-f469-44a6-b746-e9e3f9f3879a",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRac2Eej6iH42QKEuz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9b602e2a-82b5-482e-a777-571afa268aae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T2VATvYiAikPQPDYe9bKh3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23498,
      "cache_read_input_tokens": 20126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23498,
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

_source line 22 · 2026-05-16T02:52:45.270Z_

<details open><summary>🔧 Tool call — Glob · `toolu_015sVfutxuZEnySzobnvvoV9`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9b602e2a-82b5-482e-a777-571afa268aae",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRac2Eej6iH42QKEuz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0943e2ea-69f5-446d-9374-833d2ce2204d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T2VATvYiAikPQPDYe9bKh3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23498,
      "cache_read_input_tokens": 20126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23498,
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

_source line 23 · 2026-05-16T02:52:45.281Z_

<details><summary>↩ Tool result · `toolu_015sVfutxuZEnySzobnvvoV9`</summary>

```text
artifacts/_project/paper/section5_scierc_draft_4796e8.tex
artifacts/_project/paper/abstract_fd4b26.tex
artifacts/_project/paper/abstract_d3264e.tex
artifacts/_project/paper/section7_conclusion_550cbf.tex
artifacts/dream_reports/dream_20260514T094226/best/paper.tex
artifacts/dream_reports/dream_20260514T094226/median/paper.tex
artifacts/dream_reports/dream_20260514T094226/worst/paper.tex
artifacts/_project/paper/section5_docred_draft_9b84f1.tex
artifacts/_project/paper/discussion_paragraphs_cf83d1.tex
artifacts/_project/paper/section6_relwork_additions.tex
artifacts/_project/paper/discussion_paragraphs.tex
artifacts/dream_reports/dream_20260514T205155/best/paper.tex
artifacts/dream_reports/dream_20260514T205155/median/paper.tex
artifacts/dream_reports/dream_20260514T205155/worst/paper.tex
artifacts/_project/paper/section6_relwork_outline.tex
artifacts/_project/paper/section7_conclusion.tex
artifacts/_project/paper/appendix_llama_per_relation.tex
artifacts/_project/paper/appendix_related_work.tex
artifacts/_project/paper/appendix_prompts.tex
artifacts/_project/paper/section6_related_work.tex
artifacts/_project/paper/section3_violation_landscape.tex
artifacts/_project/paper/paper_tables_draft.tex
artifacts/_project/paper/section2_background.tex
artifacts/_project/paper/section5_docred_draft.tex
artifacts/_project/paper/section5_crossmodel_draft.tex
artifacts/_project/paper/section5_runtime.tex
artifacts/_project/paper/section3_method_draft.tex
artifacts/_project/paper/section4_composition_draft.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/section1_introduction_draft.tex
artifacts/_project/paper/section7_conclusion_compressed.tex
artifacts/_project/paper/appendix_discussion.tex
artifacts/_project/paper/section5_scierc_draft.tex
artifacts/_project/paper/main.tex
artifacts/dream_reports/dream_20260516T021434/best/paper.tex
artifacts/dream_reports/dream_20260516T021434/median/paper.tex
artifacts/dream_reports/dream_20260516T021434/worst/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0943e2ea-69f5-446d-9374-833d2ce2204d",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "eae267ab-8763-4166-a30a-1de68e80e4ae",
  "sourceToolAssistantUUID": "0943e2ea-69f5-446d-9374-833d2ce2204d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-16T02:52:46.133Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01GRgEJYjoKsPZrsd2c1imMs`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eae267ab-8763-4166-a30a-1de68e80e4ae",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRac2Eej6iH42QKEuz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8c01811a-a6f8-4e61-8c45-81e3f8f2065f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T2VATvYiAikPQPDYe9bKh3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23498,
      "cache_read_input_tokens": 20126,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 23498,
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

_source line 25 · 2026-05-16T02:52:46.143Z_

<details><summary>↩ Tool result · `toolu_01GRgEJYjoKsPZrsd2c1imMs`</summary>

```text
artifacts/dream_reports/dream_20260514T094226/median/references.bib
artifacts/_project/paper/relwork_new_entries.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8c01811a-a6f8-4e61-8c45-81e3f8f2065f",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "574eb726-0037-4ca9-be6f-d0ae693e48e7",
  "sourceToolAssistantUUID": "8c01811a-a6f8-4e61-8c45-81e3f8f2065f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-16T02:52:46.731Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01Sxdg1eG9oVXVFQY8Fg5Wb5`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "writing_plan.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "574eb726-0037-4ca9-be6f-d0ae693e48e7",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRac2Eej6iH42QKEuz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a8db95be-c6b3-4c6b-ae67-57bfec04c505",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01T2VATvYiAikPQPDYe9bKh3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 23498,
      "cache_read_input_tokens": 20126,
      "output_tokens": 295,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 23498
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 295,
          "cache_read_input_tokens": 20126,
          "cache_creation_input_tokens": 23498,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 23498,
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

_source line 27 · 2026-05-16T02:52:46.741Z_

<details><summary>↩ Tool result · `toolu_01Sxdg1eG9oVXVFQY8Fg5Wb5`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/writing_plan.yaml\", \"content\": \"meta:\\n  venue: EMNLP 2026\\n  track: long paper (ARR)\\n  template: \\\"acl\\\"\\n  page_limit: 8  # + unlimited references + appendix\\n  deadline: 2026-05-25\\n  core_claim: >\\n    LLM-based IE 系统存在系统性 ontology constraint violations（15-19% per-triple），\\n    prompt-level 干预统计有效但 per-relation 不可靠（甚至恶化），OntoCoDec 通过\\n    grammar+semantic 双层 compiled constrained decoding 实现 94% DR reduction 且 F1-neutral。\\n  title: \\\"OntoCoDec: Near-Complete Type-Valid Information Extraction via Compiled Ontology Constraints\\\"\\n  created_at: 2026-05-14T12:00:00Z\\n  approved_at: 2026-05-14\\n  compression_plan:\\n    version: 2\\n    reason: \\\"正文 16 页→8 页压缩\\\"\\n    date: 2026-05-14\\n    current_words: 11611\\n    target_words: 5500\\n    strategy: >\\n      Related Work 大幅精简为 positioning；Discussion 选 2 段精简后合并入 Conclusion；\\n      Violation Landscape 并入 Experiments §5.1；Background 精简只留 notation+problem；\\n      Introduction 适度压缩；Method+Composition 精简表述；Experiments 保持完整但精简 DocRED 文字。\\n      移出内容进入 Appendix。\\n\\n# ============================================================================\\n# 压缩后论文结构（8 页正文）\\n# ============================================================================\\npaper_outline:\\n  - section: abstract\\n    file: abstract.tex\\n    word_budget: 200  # from 225, -11%\\n    action: trim\\n    instructions: >\\n      删减重复措辞。确保 4 要素齐全：problem, method, results, limitation flag。\\n      数字保留：DR 15.4%→0.93%（↓94%），F1-neutral。CF 9.9% 作为 limitation 一句话提及。\\n\\n  - section: \\\"§1 Introduction\\\"\\n    file: section1_introduction_draft.tex\\n    word_budget: 550  # from 669, -18%\\n    action: trim\\n    instructions: >\\n      保留所有核心内容但精简表述：\\n      (1) Hook: violation 数据不变\\n      (2) Gap: 合并 prompt/grammar/posthoc/training 4 段为 2 段更紧凑的对比\\n      (3) Method: 保持 OntoCoDec 描述但删减细节（Worker 不展开 entity registry 工作原理）\\n      (4) Contributions: 从 4 条压缩为 3 条（合并 C2+C3 为一条：framework + decidability taxonomy）\\n      不含 fig1_overview（图移入 Method §3）\\n\\n  - section: \\\"§2 Background\\\"\\n    file: section2_background.tex\\n    word_budget: 250  # from 564, -56%\\n    action: heavy_trim\\n    instructions: >\\n      大幅压缩，只保留后续正文需要的 notation 定义和 problem statement：\\n      (1) §2.1 IE Ontology Structure: 保留 O=(E,R,σ) 定义 + type-valid 定义 + \\n          constraint tightness 定义（1 句 + 1 个公式）。删除 SciERC/DocRED 具体数字\\n          （这些在 Experiments 中自然出现）\\n      (2) §2.2 Grammar-Constrained Decoding: 压缩为 2-3 句（cite XGrammar+Outlines，\\n          点明 CFG 限制——不能做 cross-field semantic constraints）\\n      (3) §2.3 Problem Statement: 保留 2 条 desiderata（structural + type validity），\\n          保留 prefix-decidability 关键 insight（1 句）\\n\\n  - section: \\\"§3 Method\\\"\\n    file: section3_method_draft.tex\\n    word_budget: 1100  # from 1578, -30%\\n    action: trim\\n    instructions: >\\n      核心贡献，保留技术细节但精简表述：\\n      (1) §3.1 Problem Formulation: 保留 eq:output-schema + eq:type-valid + violation 定义，\\n          但删减解释性文字（公式自解释）\\n      (2) §3.2 Grammar Layer: 保留 JSON Schema→XGrammar→M_g 的编译流程，\\n          删减 XGrammar 实现细节（读者可 cite 原文）\\n      (3) §3.3 Semantic Layer: 完整保留 entity registry + position detection + dynamic masking，\\n          这是核心新贡献\\n      (4) §3.4 Layer Interaction: 保留 enabling dependency + grammar-first invariant，\\n          但精简为 1 段（不需要完整的 conjunction 公式——Composition section 有）\\n      (5) §3.5 Decoding Strategies: 保留 S1 描述（3-4 句），S2 压缩为 1 句 +\\n          \\\"details in Appendix A\\\"\\n      图 fig1_overview 放在 Method 开头\\n\\n  - section: \\\"§4 Constraint Composition\\\"\\n    file: section4_composition_draft.tex\\n    word_budget: 500  # from 787, -36%\\n    action: trim\\n    instructions: >\\n      保留所有公式但精简文字：\\n      (1) M_final = M_grammar ∧ M_semantic: 保留 eq:composition + 2 句解释\\n      (2) Grammar-First Fallback: 压缩为 1 段（保留核心 rule + 1 句 rationale，\\n          删除 logit threshold 细节）\\n      (3) Constraint Tightness: 保留 eq:tightness + 1 句 intuition + SciERC/DocRED \\n          数字对比。删除 Used-for example（读者不需要这个 level 的细节）\\n      (4) Decidability Taxonomy: 保留 3-class 列表但每类压缩为 1 句。\\n          删除最后段（OntoCoDec 覆盖前两类——读者已知）\\n\\n  - section: \\\"§5 Experiments\\\"\\n    subsections:\\n      - subsection: \\\"§5.1 Setup and Violation Landscape\\\"\\n        file: section3_violation_landscape.tex\\n        word_budget: 450  # from 838, -46%\\n        action: restructure_and_trim\\n        instructions: >\\n          原 §3 Violation Landscape 整合为 §5.1，结构重构：\\n          (1) 删除独立 section header，改为 \\\\subsection{Experimental Setup and Violation Landscape}\\n          (2) Setup: 2-3 句（models, datasets, metrics 定义）\\n          (3) 保留 tab:prompt_comparison（已创建），但删除表格周围的冗余文字描述\\n          (4) Violation Distribution: 压缩为 1 段 key findings（DR 15.4% vs 18.7%，\\n              tightness drives violations）。Per-relation analysis 压缩为 2 句\\n              （Compare 42.4% vs Used-for 0.8% + correlation with tightness）\\n          (5) Prompt Insufficiency: 压缩为 1 段（SciERC ↓62% but DocRED only ↓31%；\\n              Evaluate-for 反而 +5.8pp → prompt 不可靠）\\n          (6) fig:per_relation_dr 保留\\n          注意：需要把 \\\\section{Violation Landscape} 改为 \\\\subsection，\\n          内部 \\\\subsection 降级为 \\\\paragraph 或删除\\n\\n      - subsection: \\\"§5.2 Results on SciERC\\\"\\n        file: section5_scierc_draft.tex\\n        word_budget: 550  # from 742, -26%\\n        action: trim\\n        instructions: >\\n          保留 tab:scierc-ablation + 关键数字，精简分析文字：\\n          (1) Main result: DR 15.37%→0.93%（↓94%），ET/RV→0%，F1-neutral\\n          (2) Layer decomposition: grammar 消除 RV+ET，semantic+grammar 消除 DR\\n          (3) CF analysis: 保留核心发现（CF 9.9% 由 semantic 层引入，grammar CF=0.08%）\\n              压缩根因分析为 2 句（EVR pattern + Generic↔OtherScientificTerm）\\n          (4) S1 vs S2: 删除详细对比，1 句 \\\"S2 achieves comparable results (Appendix A)\\\"\\n\\n      - subsection: \\\"§5.3 Cross-Dataset Validation on DocRED\\\"\\n        file: section5_docred_draft.tex\\n        word_budget: 600  # from 1450, -59%\\n        action: heavy_trim\\n        instructions: >\\n          这是压缩最大的 experiments 子节。保留核心数字，大砍文字：\\n          (1) 保留 tab:docred-ablation（如有），压缩为关键数字段\\n          (2) Grammar layer on DocRED: 1 段（RV 29.66%→0.03%，ET 2.48%→0%）\\n          (3) Full S1: DR 18.46%→10.21%（↓45%），F1 +0.50pp significant\\n          (4) Tightness 对比: DocRED τ̄=0.842 vs SciERC τ̄=0.333 解释 residual DR\\n          (5) 删除详细的 per-mode 分析段、DocRED-specific per-relation 分析、\\n              与 SciERC 的冗长对比文字。数字让 table 说话\\n\\n      - subsection: \\\"§5.4 Cross-Model Validation\\\"\\n        file: section5_crossmodel_draft.tex\\n        word_budget: 400  # from 830, -52%\\n        action: heavy_trim\\n        instructions: >\\n          保留 tab:cross-model + 关键发现：\\n          (1) Llama-3.1-8B 零代码修改即可使用\\n          (2) SciERC: DR 13.3%→0.08%，DocRED: DR 26.07%→2.55%（↓90%）\\n          (3) 不同模型的 violation profile 差异（Llama DR更高 but RV更低）\\n          (4) 删除详细的 per-metric 讨论、CF 在 Llama 上的详细分析、\\n              parse failure 讨论\\n\\n  - section: \\\"§6 Related Work\\\"\\n    file: section6_related_work.tex\\n    word_budget: 400  # from 2441, -84%\\n    action: rewrite\\n    instructions: >\\n      完全重写为 positioning statements，每类工作 2-3 句 + citations：\\n      (1) Grammar-constrained decoding: XGrammar/Outlines/LMQL 保证 syntactic validity \\n          但不做 semantic constraints [3 citations, 2 句]\\n      (2) Semantic constrained decoding (code): Synchromesh/PICARD/MGD/PLDI'25 \\n          在代码域做 type checking [4 citations, 2 句]\\n      (3) Vocabulary/type-constrained IE: GCD/AdaKGC/GoLLIE/GENRE 做 vocabulary\\n          约束但不做 cross-field semantic [4 citations, 2 句]\\n      (4) Post-hoc validation: ODKE+/OntoGPT/OntoLogX 检测-修复但不 prevent \\n          [3 citations, 2 句]\\n      (5) Constrained decoding quality: CRANE/Hidden Cost 担忧质量下降，\\n          但 IE 是 extraction 非 reasoning [2 citations, 1 句]\\n      (6) OntoCoDec positioning: 1 句总结差异化\\n      完整版 Related Work 移入 Appendix B\\n\\n  - section: \\\"§7 Conclusion\\\"\\n    file: section7_conclusion_compressed.tex  # new merged file\\n    word_budget: 500  # from 668+819=1487, -66%\\n    action: merge_and_rewrite\\n    instructions: >\\n      合并 discussion_paragraphs.tex 关键内容 + section7_conclusion.tex：\\n      (1) Contributions summary: 3 句话（violation landscape + framework + empirical 94%）\\n      (2) CF severity 精简版（from discussion ¶2）: 3 句——CF 是 per-relation independent \\n          enforcement 的系统性副作用，grammar-only CF=0.08% 证实 100% 由 semantic 层引入，\\n          dominant pattern Generic↔OtherScientificTerm 反映 type system 歧义\\n      (3) F1 significance explanation 精简版（from discussion ¶3）: 2 句——DocRED F1 gain \\n          来自 grammar 消除 OOV relations（29.66% RV → 0%），SciERC RV 仅 1.39% 故 F1 \\n          effect 不显著\\n      (4) Limitations: 3-4 句（CF 9.9% open challenge，2 models，zero-shot only，\\n          parse failures on DocRED-Llama）\\n      (5) Future work: 2 句（global entity consensus + fine-tuned integration）\\n      Low F1 practical significance 和 Post-hoc comparison 移入 Appendix C\\n\\n  - section: \\\"Appendix\\\"\\n    files:\\n      - appendix_related_work.tex  # full version of §6\\n      - appendix_discussion.tex    # moved discussion paragraphs\\n      - appendix_s1_vs_s2.tex      # S1 vs S2 details\\n      - appendix_prompts.tex       # prompt templates\\n    word_budget: unlimited\\n    action: create_from_moved_content\\n    instructions: >\\n      Appendix 结构：\\n      A. Full Related Work（当前 section6_related_work.tex 几乎原样保留）\\n      B. Extended Discussion（Low F1 practical significance + Post-hoc comparison 原文）\\n      C. S1 vs S2 Decoding Strategy Details（tab4_s1_vs_s2 + 分析）\\n      D. Prompt Templates（minimal vs schema-informed）\\n\\n# ============================================================================\\n# 表格计划（压缩版）\\n# ============================================================================\\ntable_plan:\\n  main_text:\\n    - table_id: tab_prompt_comparison\\n      placement: \\\"§5.1\\\"\\n      status: created  # 已在 section3_violation_landscape.tex 中\\n      notes: \\\"prompt comparison across SciERC+DocRED，已有 label tab:prompt_comparison\\\"\\n\\n    - table_id: tab_scierc_ablation\\n      placement: \\\"§5.2\\\"\\n      status: exists  # 在 section5_scierc_draft.tex 中\\n      notes: \\\"5-way ablation (unconstrained/grammar/semantic/full_s1/full_s2)\\\"\\n\\n    - table_id: tab_docred_ablation\\n      placement: \\\"§5.3\\\"\\n      status: exists  # 在 section5_docred_draft.tex 中\\n      notes: \\\"DocRED ablation results\\\"\\n\\n    - table_id: tab_cross_model\\n      placement: \\\"§5.4\\\"\\n      status: exists  # 在 section5_crossmodel_draft.tex 中\\n      notes: \\\"Qwen vs Llama comparison\\\"\\n\\n  appendix:\\n    - table_id: tab_s1_vs_s2\\n      placement: \\\"Appendix C\\\"\\n      status: exists_in_paper_tables_draft\\n\\n# ============================================================================\\n# 图表计划\\n# ============================================================================\\nvisualization_plan:\\n  main_text:\\n    - fig_id: fig1_overview\\n      placement: \\\"§3 Method\\\"\\n      status: generated  # fig1_overview.pdf exists\\n      notes: \\\"OntoCoDec 架构图。需确认是否已 \\\\\\\\includegraphics\\\"\\n\\n    - fig_id: fig2_per_relation_dr\\n      placement: \\\"§5.1\\\"\\n      status: included  # 已在 section3_violation_landscape.tex 中添加 figure 环境\\n      notes: \\\"Per-relation DR violation rates bar chart\\\"\\n\\n  appendix:\\n    - fig_id: fig3_ablation_layers\\n      placement: \\\"Appendix C\\\"\\n      status: uncertain  # Worker spawned but server restart\\n\\n# ============================================================================\\n# 执行计划（串行，按压缩收益排序）\\n# ============================================================================\\nexecution_order:\\n  - step: 1\\n    target: section6_related_work.tex\\n    action: rewrite\\n    estimated_savings: \\\"-2 pages\\\"\\n    priority: highest\\n    notes: \\\"2441→400 words。完全重写为 positioning only。原文移入 appendix_related_work.tex\\\"\\n\\n  - step: 2\\n    target: \\\"[section7_conclusion.tex + discussion_paragraphs.tex]\\\"\\n    action: merge_and_rewrite\\n    estimated_savings: \\\"-1.5 pages\\\"\\n    priority: high\\n    notes: >\\n      1487→500 words。合并为 section7_conclusion_compressed.tex。\\n      保留 CF severity + F1 significance 精简版 + contributions + limitations + future work。\\n      移出内容到 appendix_discussion.tex。\\n\\n  - step: 3\\n    target: section3_violation_landscape.tex\\n    action: restructure_and_trim\\n    estimated_savings: \\\"-1 page\\\"\\n    priority: high\\n    notes: >\\n      838→450 words。删除 \\\\section header 改为 \\\\subsection（main.tex 需同步修改）。\\n      §3 改编号后变为 §5.1。保留 tab:prompt_comparison + fig:per_relation_dr。\\n\\n  - step: 4\\n    target: section2_background.tex\\n    action: heavy_trim\\n    estimated_savings: \\\"-0.5 page\\\"\\n    priority: medium\\n    notes: \\\"564→250 words。只留 notation + problem statement。\\\"\\n\\n  - step: 5\\n    target: section1_introduction_draft.tex\\n    action: trim\\n    estimated_savings: \\\"-0.5 page\\\"\\n    priority: medium\\n    notes: \\\"669→550 words。合并 gap 段落，contributions 4→3 条。\\\"\\n\\n  - step: 6\\n    target: \\\"[section3_method_draft.tex + section4_composition_draft.tex]\\\"\\n    action: trim\\n    estimated_savings: \\\"-0.5 page\\\"\\n    priority: medium\\n    notes: >\\n      (1578+787)→(1100+500) words。Method 精简例子减少重复。\\n      Composition 每段精简但保留所有公式。\\n\\n  - step: 7\\n    target: \\\"[section5_docred_draft.tex + section5_crossmodel_draft.tex]\\\"\\n    action: heavy_trim\\n    estimated_savings: \\\"-0.5 page\\\"\\n    priority: medium\\n    notes: >\\n      DocRED 1450→600（最大单文件压缩），Cross-model 830→400。\\n      让 table 说话，删冗余文字分析。\\n\\n  - step: 8\\n    target: main.tex\\n    action: restructure\\n    estimated_savings: \\\"structural\\\"\\n    priority: required\\n    notes: >\\n      调整 section 编号：\\n      §1 Introduction → §1\\n      §2 Background → §2（精简版）\\n      §3 Method → §3（含 fig1）\\n      §4 Constraint Composition → §4\\n      §5 Experiments → §5\\n        §5.1 Setup + Violation Landscape（原 §3 violation landscape 合并入）\\n        §5.2 SciERC\\n        §5.3 DocRED\\n        §5.4 Cross-Model\\n      §6 Related Work → §6（精简版）\\n      §7 Conclusion → §7（合并 Discussion）\\n      Appendix A-D\\n\\n  - step: 9\\n    target: abstract.tex\\n    action: trim\\n    estimated_savings: \\\"minor\\\"\\n    priority: low\\n    notes: \\\"225→200 words。最后调整，与正文同步。\\\"\\n\\n  - step: 10\\n    target: compilation\\n    action: compile_and_verify\\n    estimated_savings: \\\"N/A\\\"\\n    priority: required\\n    notes: >\\n      pdflatex + bibtex 全量编译。\\n      验证：(1) ≤8 pages content, (2) 0 undefined refs,\\n      (3) 0 undefined citations, (4) no severe overfull hbox。\\n\\n# ============================================================================\\n# 附加信息\\n# ============================================================================\\nliterature_strategy:\\n  citation_budget: 35\\n  notes: \\\"压缩不影响 citation——Related Work 精简但保留所有 \\\\\\\\cite\\\"\\n\\nwriting_order:\\n  - \\\"Step 1: Related Work rewrite\\\"\\n  - \\\"Step 2: Conclusion merge\\\"\\n  - \\\"Step 3: Violation Landscape restructure\\\"\\n  - \\\"Step 4: Background trim\\\"\\n  - \\\"Step 5: Introduction trim\\\"\\n  - \\\"Step 6: Method+Composition trim\\\"\\n  - \\\"Step 7: DocRED+CrossModel trim\\\"\\n  - \\\"Step 8: main.tex restructure\\\"\\n  - \\\"Step 9: Abstract trim\\\"\\n  - \\\"Step 10: Final compilation\\\"\\n\", \"total_chars\": 14399, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a8db95be-c6b3-4c6b-ae67-57bfec04c505",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "fcafb10c-1627-4d6c-bd46-247c598091a9",
  "sourceToolAssistantUUID": "a8db95be-c6b3-4c6b-ae67-57bfec04c505",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-16T02:52:50.663Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Xv7ppvgJZQaBtBp38pYafz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fcafb10c-1627-4d6c-bd46-247c598091a9",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VRxCHkPoZpPxj7JcDj",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a6e98cdc-f1cd-4e1e-94dd-cf1d967c66d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XaKhGo4jhKtQAMeCafM21j",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7375,
      "cache_read_input_tokens": 43624,
      "output_tokens": 92,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7375
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 92,
          "cache_read_input_tokens": 43624,
          "cache_creation_input_tokens": 7375,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7375,
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

_source line 29 · 2026-05-16T02:52:50.669Z_

<details><summary>↩ Tool result · `toolu_01Xv7ppvgJZQaBtBp38pYafz`</summary>

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
10	\usepackage{graphicx}
11	\usepackage{booktabs}
12	\usepackage{multirow}
13	\usepackage{amsmath}
14	\usepackage{amssymb}
15	\usepackage{enumitem}
16	\usepackage{xcolor}
17	
18	\title{OntoCoDec: Type-Constrained Information Extraction\\via Compiled Ontology Constraints}
19	
20	\author{Anonymous ACL submission}
21	
22	\begin{document}
23	\maketitle
24	
25	% === Abstract ===
26	\input{abstract}
27	
28	% === §1 Introduction ===
29	\input{section1_introduction_draft}
30	
31	% === §2 Background ===
32	\input{section2_background}
33	
34	% === §3 Method ===
35	\input{section3_method_draft}
36	
37	% === §4 Constraint Composition ===
38	\section{Constraint Composition}
39	\label{sec:composition}
40	\input{section4_composition_draft}
41	
42	% === §5 Experiments ===
43	\section{Experiments}
44	\label{sec:experiments}
45	
46	\subsection{Violation Landscape}
47	\input{section3_violation_landscape}
48	
49	\input{section5_scierc_draft}
50	\input{section5_docred_draft}
51	\input{section5_crossmodel_draft}
52	\input{section5_runtime}
53	
54	% === §6 Related Work ===
55	\input{section6_related_work}
56	
57	% === §7 Discussion and Conclusion ===
58	\section{Discussion and Conclusion}
59	\label{sec:discussion}
60	\input{section7_conclusion_compressed}
61	
62	% === Limitations (ARR requirement: standalone section, does not count toward page limit) ===
63	\clearpage
64	\section*{Limitations}
65	
66	The semantic layer introduces cross-field consistency (CF) violations (up to 12.02\%), a systematic consequence of per-relation independent enforcement.
67	CF fallback ablation shows that eliminating CF re-routes violations to DR ($+$13.85\,pp), confirming that CF$\leftrightarrow$DR represents a fundamental trade-off in composable constraint systems rather than an independently resolvable limitation (Appendix~\ref{app:cf-dr-tradeoff}).
68	Entity F1 impact is model-dependent ($+$1.22\,pp for Qwen vs.\ $-$0.64\,pp for Llama on DocRED), partially confounded by increased parse failures under constraints (Llama: 9.1\% vs.\ 6.8\%).
69	Results cover two 8B-class models under zero-shot prompting, where relation F1 remains around 8\% compared to $\sim$50\% for fine-tuned systems.
70	Composability with fine-tuned models is validated on SciERC with both Qwen3-8B and Llama-3.1-8B (DR\,$\leq$\,0.09\%, R-F1 loss $<$0.1\,pp), but evaluation is limited to one dataset and one fine-tuning method (LoRA); residual CF (Qwen 1.18\%, Llama 0.46\%) traces to schema-level type ambiguity (\textsc{Generic}$\leftrightarrow$X) rather than enforcement failure.
71	The semantic layer's dynamic masking assumes each entity type maps to a unique first subword token---verified for both tokenizers on our two ontologies (6 entity types each), but ontologies with many types or multi-token type names would require prefix-tree masking, which we have not implemented.
72	Global entity-level type consensus during decoding offers the most direct path to resolving CF violations.
73	Both models tested are 8B-parameter class; scaling behavior to larger (70B+) or smaller models has not been verified, and the dual-factor pattern's predictive scope may differ at other scales.
74	CF type inconsistencies may propagate to downstream tasks that consume extracted triples (e.g., knowledge graph construction, question answering); the impact of such propagation has not been evaluated.
75	Residual DR (e.g., 10.21\% for Qwen on DocRED) correlates with grammar-first fallback frequency and cannot be reduced beyond the schema constraint scope without complementary approaches such as global type consensus or post-hoc correction.
76	Validation with fine-tuned models, larger scales, and non-English ontologies remains to be explored.
77	
78	% === Ethics Statement ===
79	\section*{Ethics Statement}
80	
81	This work uses publicly available benchmark datasets (SciERC and DocRED) with no personally identifiable information.
82	No human subjects were involved in the experiments.
83	The constrained decoding method operates on model outputs and does not introduce new privacy or safety risks beyond those inherent in the base language models.
84	
85	% === Bibliography ===
86	\bibliography{relwork_new_entries}
87	
88	% === Appendix ===
89	\appendix
90	
91	\input{appendix_prompts}
92	\input{appendix_related_work}
93	\input{appendix_discussion}
94	\input{appendix_llama_per_relation}
95	
96	\end{document}
97	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a6e98cdc-f1cd-4e1e-94dd-cf1d967c66d9",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "1b33a6ed-0ef0-4c55-9f01-a7d01c7624da",
  "sourceToolAssistantUUID": "a6e98cdc-f1cd-4e1e-94dd-cf1d967c66d9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-16T02:52:53.970Z_

<details open><summary>🔧 Tool call — Read · `toolu_015ArbbUPQWzeoHyf4x4gZZM`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1b33a6ed-0ef0-4c55-9f01-a7d01c7624da",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSEiiVeqKvgrd9tWZf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3b3d239f-fb54-4b95-8041-ed969d38f974",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F4316es1weZyaNB1kXgLez",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1586,
      "cache_read_input_tokens": 50999,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1586,
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

_source line 31 · 2026-05-16T02:52:53.974Z_

<details><summary>↩ Tool result · `toolu_015ArbbUPQWzeoHyf4x4gZZM`</summary>

```text
1	\begin{abstract}
2	LLM-based information extraction systems can produce systematic ontology constraint violations during autoregressive generation.
3	On SciERC (7 relation types), 15.37\% of extracted triples violate domain/range type constraints; on DocRED (96 relation types), 18.46\%---comparable rates governed by \emph{constraint tightness} rather than ontology scale.
4	%
5	We present \textsc{OntoCoDec}, which compiles IE ontology schemas into two composable decoding constraint layers:
6	(1)~a \emph{grammar layer} (XGrammar CFG) enforcing JSON structural validity and restricting entity/relation vocabularies to schema-defined values (ET, RV\,$\to$\,0\%); and
7	(2)~a \emph{semantic layer} enforcing domain/range constraints via a stateful entity registry and dynamic logit masking.
8	The grammar layer is an enabling prerequisite; the two compose via bitwise AND on token-level masks.
9	%
10	On SciERC, \textsc{OntoCoDec} reduces domain/range violations by 94\% (15.37\%\,$\to$\,0.93\%) while maintaining extraction F1 ({+}0.13pp, $p{=}0.58$).
11	On DocRED, violations decrease by 45--90\% depending on the model, with significant relation F1 gains for both Qwen3-8B ({+}0.50pp, $p{<}0.001$) and Llama-3.1-8B ({+}0.29pp, $p{=}0.013$; DR$\downarrow$90.2\%).
12	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1
13	Quantitative analysis reveals that residual DR varies predictably with ontology tightness $\times$ baseline violation rate ($R^2{=}0.886$; Appendix~\ref{app:dual-factor}).
14	Composed with LoRA fine-tuning on SciERC, \textsc{OntoCoDec} achieves DR\,=\,0\% at R-F1 43.77 (loss $<$0.1\,pp), confirming that fine-tuning and constrained decoding are complementary.
15	\end{abstract}
16	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3b3d239f-fb54-4b95-8041-ed969d38f974",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "b73ea434-8a55-4e18-80cc-d0bacd778487",
  "sourceToolAssistantUUID": "3b3d239f-fb54-4b95-8041-ed969d38f974",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-16T02:52:54.499Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SwUDF3SUAizgvVKCUixSEF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section1_introduction_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b73ea434-8a55-4e18-80cc-d0bacd778487",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSEiiVeqKvgrd9tWZf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c937aa70-29a0-43a1-b659-37cd76e40003",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F4316es1weZyaNB1kXgLez",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1586,
      "cache_read_input_tokens": 50999,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1586,
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

_source line 33 · 2026-05-16T02:52:54.513Z_

<details><summary>↩ Tool result · `toolu_01SwUDF3SUAizgvVKCUixSEF`</summary>

```text
1	% Section 1: Introduction (compressed, 669→~550 words)
2	
3	\section{Introduction}
4	\label{sec:introduction}
5	
6	Large language models are increasingly deployed for zero-shot information extraction~\cite{li2023codeie,sainz2024gollie,wei2023zeroshot}, but when generating relation triples $(h, r, t)$, neither entity is guaranteed to carry a type consistent with the ontology's domain/range constraints for $r$.
7	We call such outputs \emph{domain/range violations}---structurally valid triples that are ontologically invalid.
8	In a systematic study, we find violations are pervasive: 15.4\% of triples on SciERC~\cite{luan2018scierc} and 18.5\% on DocRED~\cite{yao2019docred}, driven by \emph{constraint tightness} (few valid type pairs per relation) rather than ontology scale.
9	Relations with tight constraints exhibit far higher rates (\textsc{Compare}: 42.4\%) than loosely constrained ones (\textsc{Used-for}: 0.8\%).
10	
11	Existing approaches leave a fundamental gap.
12	Schema-informed prompting reduces violations by 62\% on average but is per-relation unreliable---violations for \textsc{Evaluate-for} actually \emph{increase} by 5.8\,pp.
13	Grammar-constrained decoding~\cite{dong2025xgrammar,willard2023outlines,beurer-kellner2023lmql} guarantees syntactic well-formedness but cannot encode cross-field semantic constraints.
14	Post-hoc validation wastes compute on discarded outputs and cannot redirect probability mass during decoding.
15	Training-based approaches~\cite{sainz2024gollie,lu2022uie} provide only soft guidance that cannot eliminate violations.
16	
17	We propose \textbf{OntoCoDec} (\textbf{Onto}logy-\textbf{Co}mpiled \textbf{Dec}oding), a framework that compiles an IE ontology into two composable layers of decoding-time constraints.
18	The \emph{grammar layer} enforces JSON well-formedness and vocabulary validity via XGrammar.
19	The \emph{semantic layer} maintains a stateful entity registry during generation: as entities are decoded, the registry records type assignments; when relation arguments are generated, dynamic logit masking restricts output to types compatible with the relation's domain/range specification.
20	The layers compose via bitwise AND with an \emph{enabling dependency}: the grammar layer guarantees vocabulary membership, enabling the semantic layer to look up domain/range rules.
21	On SciERC, OntoCoDec reduces DR violations from 15.37\% to 0.93\% ($\downarrow$94\%) while remaining F1-neutral ($+$0.13\,pp).
22	
23	Our contributions:
24	\begin{enumerate}
25	    \item The first systematic study of ontological constraint violations in LLM-based IE (spanning per-relation tightness analysis, dual-factor characterization, and post-hoc baseline comparison), showing that violation rates are driven by constraint tightness rather than ontology size, and that prompt-level intervention is per-relation unreliable.
26	    \item OntoCoDec, a two-layer compiled constraint framework that enforces cross-field type validity during autoregressive IE---the first to automatically compile IE ontology domain/range constraints into token-level semantic masks.
27	    \item Empirical validation on 2 models $\times$ 2 datasets: DR $\downarrow$94\% on SciERC and $\downarrow$45--90\% on DocRED, with significant R-F1 gains on DocRED ($p \leq 0.013$), model-agnostic structural guarantees, and composability with fine-tuning (DR\,$\to$\,0\% at $<$0.1\,pp F1 cost).
28	\end{enumerate}
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c937aa70-29a0-43a1-b659-37cd76e40003",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "df75f800-d78a-4e2d-bde8-f83c1ec22d01",
  "sourceToolAssistantUUID": "c937aa70-29a0-43a1-b659-37cd76e40003",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-16T02:52:54.955Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Q1KPM4Dep3WzHBERiFD2jz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section6_related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "df75f800-d78a-4e2d-bde8-f83c1ec22d01",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSEiiVeqKvgrd9tWZf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7c34b1c8-4182-49b3-b249-16bd494d1823",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01F4316es1weZyaNB1kXgLez",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1586,
      "cache_read_input_tokens": 50999,
      "output_tokens": 252,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1586
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 252,
          "cache_read_input_tokens": 50999,
          "cache_creation_input_tokens": 1586,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1586,
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

_source line 35 · 2026-05-16T02:52:54.959Z_

<details><summary>↩ Tool result · `toolu_01Q1KPM4Dep3WzHBERiFD2jz`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Grammar-Constrained Decoding.}
5	XGrammar~\cite{dong2025xgrammar}, Outlines~\cite{willard2023outlines}, Guidance~\cite{guidance2023}, LMQL~\cite{beurer-kellner2023lmql}, DOMINO~\cite{beurer-kellner2024domino}, and ASAp~\cite{park2024grammar} ensure every token belongs to a grammar-valid continuation.
6	These methods operate at the syntactic level---they guarantee format validity but cannot enforce cross-field semantic constraints such as ontology domain/range rules.
7	
8	\paragraph{Semantic Constrained Decoding for Code.}
9	Synchromesh~\cite{synchromesh_iclr2022}, PICARD~\cite{scholak2021picard}, MGD~\cite{mgd_neurips2023}, and \citet{pldi2025_type_constrained_codegen} extend constrained decoding beyond CFG to enforce type and scope constraints in code generation.
10	OntoCoDec migrates this paradigm to information extraction.
11	
12	\paragraph{Vocabulary and Type-Constrained Generation.}
13	\citet{roth_yih_2004} establish relational type compatibility as a hard constraint via ILP, though applied post-hoc.
14	GENRE~\cite{decao2021genre}, NeuroLogic~\cite{lu2021neurologic}, AdaKGC~\cite{adakgc_emnlp2023}, GCD~\cite{geng2023gcd}, and GoLLIE~\cite{sainz2024gollie} constrain \emph{which tokens} can appear but not \emph{which type combinations} are valid per relation.
15	Training-based methods---TANL~\cite{paolini2021tanl}, REBEL~\cite{cabot2021rebel}, UIE~\cite{lu2022uie}, KnowCoder~\cite{knowcoder_acl2024}, CodeIE~\cite{li2023codeie}---encode IE structure through training or schema-as-code prompting but provide only \emph{soft} guidance that cannot guarantee compliance.
16	
17	\paragraph{Post-hoc Ontology Validation.}
18	ODKE+~\cite{khorshidi2025odke}, OntoGPT~\cite{spires_2024}, and OntoLogX~\cite{ontologx_2025} validate outputs against ontologies post-generation.
19	These detect-then-fix approaches waste compute on violated outputs; OntoCoDec \emph{prevents} violations during decoding.
20	
21	\paragraph{Quality Impact of Constrained Decoding.}
22	CRANE~\cite{banerjee2025crane} and \citet{schall2025hiddencost} show grammar restrictions can degrade reasoning, but \citet{tam2024letmespeak} find extraction-style tasks are robust to---or benefit from---constraints.
23	OntoCoDec confirms this: violations decrease by 94\% on SciERC with zero F1 degradation.
24	
25	An extended survey is provided in Appendix~\ref{app:related_work}.
26	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7c34b1c8-4182-49b3-b249-16bd494d1823",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "39ef5367-778d-4745-8903-645250987d51",
  "sourceToolAssistantUUID": "7c34b1c8-4182-49b3-b249-16bd494d1823",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-16T02:52:58.349Z_

<details open><summary>🔧 Tool call — Read · `toolu_015GwsZuBtMNRxToyehSiKVe`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section3_method_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "39ef5367-778d-4745-8903-645250987d51",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSZNNs45RSopp8cXLS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e3900287-4512-4052-95bf-b6ee97656475",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VDwPV82hKw3TdpMtUxAG9G",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2759,
      "cache_read_input_tokens": 52585,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2759,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 69,
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

_source line 37 · 2026-05-16T02:52:58.354Z_

<details><summary>↩ Tool result · `toolu_015GwsZuBtMNRxToyehSiKVe`</summary>

```text
1	% Section 3 — Method (Draft)
2	% OntoCoDec: Type-Valid Information Extraction
3	% via Compiled Ontology Constraints
4	
5	\section{Method}
6	\label{sec:method}
7	
8	We present OntoCoDec, a two-layer constrained decoding framework that compiles ontology schemas into token-level masks enforced during autoregressive generation.
9	The grammar layer (\S\ref{sec:grammar}) guarantees structural validity—well-formed JSON with ontology-vocabulary membership—while the semantic layer (\S\ref{sec:semantic}) enforces domain/range type constraints via a stateful entity registry.
10	We describe the problem formulation (\S\ref{sec:formulation}), each layer, and two decoding strategies (\S\ref{sec:strategies}).
11	Formal analysis of constraint composition is deferred to Section~\ref{sec:composition}.
12	
13	
14	\subsection{Problem Formulation}
15	\label{sec:formulation}
16	
17	\paragraph{IE as structured generation.}
18	Given an input text $x$, a language model generates a structured JSON output $y$:
19	%
20	\begin{equation}\label{eq:output-schema}
21	\resizebox{.88\columnwidth}{!}{$\displaystyle
22	  y = \bigl\{\texttt{entities}: [\{n_i, \tau_i\}],\; \texttt{relations}: [\{h_j, t_j, r_j, \tau^h_j, \tau^t_j\}]\bigr\}
23	$}
24	\end{equation}
25	%
26	where each entity has a name $n_i$ and type $\tau_i \in \mathcal{E}$, and each relation specifies head $h_j$, tail $t_j$, relation type $r_j \in \mathcal{R}$, and head/tail entity types $\tau^h_j, \tau^t_j$.
27	
28	\paragraph{Ontology compliance.}
29	Using the ontology $\mathcal{O} = (\mathcal{E}, \mathcal{R}, \sigma)$ defined in \S\ref{sec:background}, we write $\operatorname{dom}(r) = \{\tau^h : \exists \tau^t,\, (\tau^h, \tau^t) \in \sigma(r)\}$ for domain-valid head types and $\operatorname{range}(r, \tau^h) = \{\tau^t : (\tau^h, \tau^t) \in \sigma(r)\}$ for the conditional range given head type $\tau^h$.
30	Our enforcement target is \emph{pair-based} type validity: $(\tau^h, \tau^t) \in \sigma(r)$ for every triple.
31	The decoder enforces this sequentially---$\tau^h \in \operatorname{dom}(r)$ at head position, then $\tau^t \in \operatorname{range}(r, \tau^h)$ at tail position---which is equivalent to the full pair check and strictly stronger than independent domain/range enforcement, because most relations have non-rectangular type signatures ($\sigma(r) \subsetneq \operatorname{dom}(r) \times \operatorname{range}(r)$ for all 7 SciERC and 73/96 DocRED relations; see \S\ref{sec:rectangularity}).\footnote{An independent check ($\tau^h \in \operatorname{dom}(r) \wedge \tau^t \in \operatorname{range}(r)$) would over-permit type pairs by $1.50\times$ on SciERC and $1.58\times$ on DocRED, corresponding to 33.3\% and 36.8\% spurious type pairs.}
32	Our goal is maximizing $P(y \mid x)$ subject to all triples being type-valid and $y$ being well-formed JSON conforming to Eq.~\eqref{eq:output-schema}.
33	
34	
35	\subsection{Grammar Layer}
36	\label{sec:grammar}
37	
38	The grammar layer compiles $\mathcal{O}$ into a context-free grammar (CFG) enforced at every decoding step via logit masking.
39	This compilation proceeds in two stages.
40	
41	\paragraph{Schema-to-grammar compilation.}
42	We generate a JSON Schema encoding the structure in Eq.~\eqref{eq:output-schema} with \texttt{enum} constraints restricting entity types to $\mathcal{E}$ and relation types to $\mathcal{R}$.
43	This schema is compiled into an EBNF grammar via XGrammar~\cite{dong2025xgrammar}, producing a pushdown automaton tracking JSON structure and enum membership.
44	
45	\paragraph{Logit masking.}
46	At step $t$, the automaton computes grammar-valid tokens $G(t) \subseteq V$; all others receive logits $-\infty$.
47	This simultaneously enforces: (i)~structural validity (well-formed JSON), (ii)~relation vocabulary membership ($r_j \in \mathcal{R}$), and (iii)~entity type membership ($\tau_i \in \mathcal{E}$).
48	Domain/range constraints are \emph{not} enforced, as they depend on entity types within each triple—the gap filled by the semantic layer.
49	
50	\paragraph{Empirical profile.}
51	On SciERC, grammar constraints eliminate relation vocabulary violations entirely (1.39\%\,$\to$\,0\%) and entity type violations entirely (0.40\%\,$\to$\,0\%), with no measurable F1 impact.
52	Domain/range violations remain effectively unchanged (15.37\%\,$\to$\,14.84\%), confirming that grammar constraints enforce structural but not semantic validity.
53	
54	
55	\subsection{Semantic Layer}
56	\label{sec:semantic}
57	
58	The semantic layer enforces domain/range constraints through a stateful logits processor maintaining an entity registry during generation.
59	
60	\subsubsection{Entity Registry}
61	\label{sec:entity-registry}
62	
63	As the model generates the entity list, the semantic layer builds a registry $\mathcal{D}: \text{name} \to \text{type}$ mapping each entity to its declared type.
64	This registry is populated incrementally: when the model completes an entry $\{n_i, \tau_i\}$, the pair $(n_i, \tau_i)$ is added to $\mathcal{D}$.
65	The registry is then consulted during relation generation to look up the declared types of head and tail entities.
66	
67	\subsubsection{Position Detection}
68	\label{sec:position-detection}
69	
70	At each step $t$, the processor determines which field is currently being generated by pattern-matching on the decoded prefix.
71	We define five field positions---\textsc{EntityType}, \textsc{RelationType}, \textsc{HeadType}, \textsc{TailType}, and \textsc{FreeText}---identified via JSON key patterns (e.g., tokens following \texttt{"head\_type":} indicate \textsc{HeadType}).
72	Semantic masks activate only at type-bearing positions (\textsc{HeadType}, \textsc{TailType}).
73	
74	\subsubsection{Dynamic Masking}
75	\label{sec:dynamic-masking}
76	
77	At type-bearing positions, the processor computes a semantic mask $S(t) \subseteq V$ restricting generation to type-valid tokens.
78	
79	\paragraph{Head type masking.}
80	At a \textsc{HeadType} position, the processor considers the entity registry $\mathcal{D}$ and the current relation type $r_j$ (if already generated).
81	If $h_j \in \mathcal{D}$ and $\mathcal{D}[h_j] \in \operatorname{dom}(r_j)$, the mask allows only that registered type: $S(t) = \{\operatorname{tok}(\mathcal{D}[h_j])\}$, ensuring consistency with both the entity list and domain constraints.
82	Otherwise, if $r_j$ is known, the mask falls back to all domain-valid types: $S(t) = \{\operatorname{tok}(\tau) : \tau \in \operatorname{dom}(r_j)\}$.
83	If $r_j$ is unavailable, no semantic mask is applied.
84	
85	\paragraph{Tail type masking.}
86	At a \textsc{TailType} position, the head type $\tau^h_j$ is already determined from the decoded prefix.
87	The processor computes $\operatorname{range}(r_j, \tau^h_j)$---the valid tail types conditioned on the generated head type (\S\ref{sec:formulation}).
88	If $t_j \in \mathcal{D}$, the mask further restricts to the registered type when it belongs to this set.
89	This sequential check ($\tau^h \in \operatorname{dom}(r)$, then $\tau^t \in \operatorname{range}(r, \tau^h)$) achieves exact pair-based enforcement, strictly tighter than an independent range check $\tau^t \in \operatorname{range}(r)$.
90	
91	\paragraph{Implementation.}
92	Each $\tau \in \mathcal{E}$ is mapped to the token ID of its first subword token; we pre-verify uniqueness across all entity types, which holds for both SciERC (6 entity types) and DocRED (6 entity types, disjoint from SciERC's) with both the Qwen3-8B and Llama-3.1-8B tokenizers.
93	The semantic mask is applied by setting logits of disallowed first-token IDs to $-\infty$.
94	
95	\subsubsection{Grammar-Semantic Interaction}
96	\label{sec:interaction}
97	
98	The final mask is the conjunction of $G(t)$ and $S(t)$, permitting only tokens satisfying both layers (formalized in \S\ref{sec:composition}).
99	This embodies an \emph{enabling dependency}: semantic lookup requires relation types to be valid members of $\mathcal{R}$, guaranteed only by the grammar layer.
100	Without grammar enforcement, the model may generate out-of-vocabulary relation types for which no $\sigma(r)$ rules exist.
101	Empirically, semantic-only constraints reduce DR by only 24\% (15.37\%\,$\to$\,11.65\%) while failing to eliminate vocabulary violations; the full combination achieves 94\% DR reduction.
102	When $S(t) \cap G(t) = \emptyset$---the semantic layer would mask out all grammar-valid tokens---the system falls back to grammar-only control, preserving structural validity at the cost of a potential type violation.
103	This \emph{grammar-first invariant} reflects a deliberate priority ordering: structural integrity is a hard constraint, while type violations are soft errors detectable by downstream validation.
104	
105	
106	\subsection{Decoding Strategies}
107	\label{sec:strategies}
108	
109	\paragraph{S1: Single-pass decoding.}
110	Both constraint layers are active throughout a single generation pass.
111	The entity registry is populated as entities are generated and immediately available for relation-level type checking.
112	This is the simpler and recommended strategy, achieving strong constraint enforcement with higher relation F1 than the two-pass alternative.
113	
114	\paragraph{S2: Two-pass decoding.}\label{sec:s2}
115	The first pass generates only entities under grammar constraints; the extracted entities compile an input-dependent grammar that additionally constrains head and tail names to match declared entities.
116	The second pass generates relations under this tighter grammar plus semantic constraints.
117	Detailed comparison is provided in the appendix.
118	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e3900287-4512-4052-95bf-b6ee97656475",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "2bf98374-ac22-4518-bcb7-951b1f161fad",
  "sourceToolAssistantUUID": "e3900287-4512-4052-95bf-b6ee97656475",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-16T02:52:58.686Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LZKwaHsUGxTJ98xtefCBsR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section4_composition_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2bf98374-ac22-4518-bcb7-951b1f161fad",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSZNNs45RSopp8cXLS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f59aea24-d9d5-476c-8ffb-16324b280df6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VDwPV82hKw3TdpMtUxAG9G",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2759,
      "cache_read_input_tokens": 52585,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2759
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 177,
          "cache_read_input_tokens": 52585,
          "cache_creation_input_tokens": 2759,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2759,
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

_source line 39 · 2026-05-16T02:52:58.691Z_

<details><summary>↩ Tool result · `toolu_01LZKwaHsUGxTJ98xtefCBsR`</summary>

```text
1	% Section: Constraint Composition (compressed, 787→~500 words)
2	
3	At each decoding step $t$, let $G(t) \subseteq V$ and $S(t) \subseteq V$ denote the tokens permitted by the grammar and semantic layers, respectively.
4	The final mask is their conjunction:
5	%
6	\begin{equation}\label{eq:composition}
7	  M_{\text{final}}(t) = M_{\text{grammar}}(t) \;\wedge\; M_{\text{semantic}}(t),
8	\end{equation}
9	%
10	so a token is allowed only if it satisfies \emph{both} structural and type-level constraints.
11	The conjunction is asymmetric: $S(t)$ is defined only over $G(t)$, reflecting the enabling dependency (\S\ref{sec:method})---the semantic layer requires the relation type to belong to $\mathcal{R}$, a property guaranteed only by the grammar layer.
12	
13	\paragraph{Grammar-First Fallback.}
14	When $S(t) \cap G(t) = \emptyset$---tight constraints leave no token that is both grammar-valid and semantically valid---na\"{\i}ve masking would force selection of a grammar-invalid token, breaking JSON structure.
15	We enforce a \emph{grammar-first fallback}: if no semantically valid token survives grammar filtering, semantic masking is skipped and the grammar layer alone controls selection.
16	Structural integrity is a hard constraint; a type violation is a soft error detectable by downstream validation.
17	
18	\paragraph{Constraint Tightness.}
19	We define the tightness of relation $r$ as:
20	%
21	\begin{equation}\label{eq:tightness}
22	  \tau(r) = 1 - \frac{|\mathcal{V}(r)|}{|\mathcal{T}|^2},
23	\end{equation}
24	%
25	where $\mathcal{V}(r)$ is the set of valid type pairs and $\mathcal{T}$ the entity type vocabulary.
26	The mean tightness $\bar{\tau} = \frac{1}{|\mathcal{R}|}\sum_{r} \tau(r)$ characterizes ontology restrictiveness.
27	Tighter constraints eliminate more grammar-valid tokens at type-bearing positions, increasing fallback frequency and residual DR.
28	This dual-factor pattern---tightness $\times$ baseline model violation rate---is consistent with the cross-dataset results: SciERC ($\bar{\tau}{=}0.333$, 24 valid pairs/relation) achieves 94--99\% DR reduction, while DocRED ($\bar{\tau}{=}0.842$, 5.68 pairs) achieves 45--90\%, with the residual modulated by model-specific baselines (\S\ref{sec:cross-model}; quantitative analysis in Appendix~\ref{app:dual-factor}).
29	
30	\paragraph{Non-Rectangularity and Sequential Masking.}
31	\label{sec:rectangularity}
32	% Data source: artifacts/rebuttal/w2_rectangularity_report.md
33	The sequential masking strategy---$\tau^h \in \operatorname{dom}(r)$, then $\tau^t \in \operatorname{range}(r, \tau^h)$---is necessary because real ontology type signatures are overwhelmingly non-rectangular: 0/7 SciERC and only 23/96 DocRED relations satisfy $\sigma(r) = \operatorname{dom}(r) \times \operatorname{range}(r)$.
34	Independent enforcement ($\tau^h \in \operatorname{dom}(r) \wedge \tau^t \in \operatorname{range}(r)$) would admit 33.3\% (SciERC) and 36.8\% (DocRED) spurious type pairs---on SciERC, 100\% of residual DR violations under full S1 are pairs that pass independent checks but violate $\sigma(r)$.
35	OntoCoDec's sequential approach achieves exact pair-based enforcement without explicit enumeration of $\sigma(r)$ at each step, exploiting the autoregressive left-to-right generation order.
36	
37	\paragraph{Decidability Taxonomy.}
38	We classify ontology constraints by when sufficient information becomes available:
39	%
40	\begin{enumerate}[leftmargin=*,nosep]
41	  \item \textbf{Local}: require only the current token (entity/relation vocabulary membership). Handled by the grammar layer.
42	  \item \textbf{Prefix-decidable}: require the decoded prefix (domain/range constraints). Handled by the semantic layer via the entity registry.
43	  \item \textbf{Non-local}: require information not yet generated (forward coreference). Outside the scope of single-pass decoding; partially addressed by the two-pass strategy (S2, \S\ref{sec:s2}).
44	\end{enumerate}
45	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f59aea24-d9d5-476c-8ffb-16324b280df6",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "5ef0821b-498e-4b0a-96d9-04298651185b",
  "sourceToolAssistantUUID": "f59aea24-d9d5-476c-8ffb-16324b280df6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 40 · 2026-05-16T02:53:01.641Z_

Now let me read the experimental sections and the fine-tuning results.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5ef0821b-498e-4b0a-96d9-04298651185b",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSq9f6BvfJev6xXmxe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d66e56b7-68f7-486e-8e53-787e4e327f1d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PwL56No7iGa1g7xQCPvZiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 55344,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4675,
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

_source line 41 · 2026-05-16T02:53:03.545Z_

<details open><summary>🔧 Tool call — Read · `toolu_016G3EeY6s9EKbZfMPLxQpJz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section5_scierc_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d66e56b7-68f7-486e-8e53-787e4e327f1d",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSq9f6BvfJev6xXmxe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d04b9caa-b902-460d-bdb7-b6a491f7f906",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PwL56No7iGa1g7xQCPvZiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 55344,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4675,
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

_source line 42 · 2026-05-16T02:53:03.551Z_

<details><summary>↩ Tool result · `toolu_016G3EeY6s9EKbZfMPLxQpJz`</summary>

```text
1	% Section 5 — SciERC Results (Draft)
2	% Data source: Phase 2 SciERC registry experiments
3	% exp_ids: phase2_scierc_unconstrained, phase2_scierc_grammar_only,
4	%          phase2_scierc_semantic_only, phase2_scierc_full_s1, phase2_scierc_full_s2
5	% All numbers verified against registry 2026-05-14.
6	
7	\subsection{Results on SciERC}
8	\label{sec:scierc-results}
9	
10	Table~\ref{tab:scierc-ablation} presents the five-way ablation on SciERC,
11	evaluating each constraint layer independently and in combination.
12	All experiments use Qwen3-8B in a zero-shot setting on 551 test documents
13	with identical prompts and decoding parameters;
14	only the active constraint layers differ.
15	
16	% ──────────────────────────────────────────
17	%  Table: SciERC five-way ablation
18	% ──────────────────────────────────────────
19	\begin{table}[t]
20	\centering
21	\small
22	\setlength{\tabcolsep}{3.6pt}
23	\resizebox{\columnwidth}{!}{%
24	\begin{tabular}{@{}l rrrrr rr@{}}
25	\toprule
26	& \multicolumn{5}{c}{\textbf{Violation Rates (\%)}}
27	& \multicolumn{2}{c}{\textbf{F1}} \\
28	\cmidrule(lr){2-6} \cmidrule(l){7-8}
29	\textbf{Mode}
30	  & DR\,$\downarrow$ & $\Delta$DR
31	  & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
32	  & Rel.\,$\uparrow$ & Ent.\,$\uparrow$ \\
33	\midrule
34	Unconstrained
35	  & 15.37 & ---
36	  & 1.39  & 0.40
37	  & 0.08
38	  & 8.23  & 31.01 \\
39	Grammar
40	  & 14.84 & $\downarrow$3\%
41	  & \textbf{0} & \textbf{0}
42	  & 0.08
43	  & 8.23  & 30.98 \\
44	Semantic
45	  & 11.65 & $\downarrow$24\%
46	  & 1.51  & 0.40
47	  & 2.71
48	  & 8.15  & 31.01 \\
49	Full (S1)
50	  & \textbf{0.93} & $\downarrow$\textbf{94\%}
51	  & \textbf{0} & \textbf{0}
52	  & 9.90
53	  & \textbf{8.36} & 30.98 \\
54	Full (S2)
55	  & 0.97  & $\downarrow$94\%
56	  & \textbf{0} & \textbf{0}
57	  & 8.03
58	  & 8.03  & \textbf{31.90} \\
59	\bottomrule
60	\end{tabular}}%
61	\caption{Five-way ablation on SciERC (551 documents, Qwen3-8B, zero-shot).
62	DR: domain/range violation rate;
63	RV: relation vocabulary violation rate;
64	ET: entity type violation rate;
65	CF: cross-field consistency violation rate.
66	$\Delta$DR: relative DR reduction vs.\ the unconstrained baseline.
67	$\downarrow$\,/\,$\uparrow$: lower\,/\,higher is better.
68	Best per column in \textbf{bold} (CF excluded---see text).
69	F1 scores are multiplied by 100.
70	Statistical significance assessed via bootstrap resampling (10{,}000 iterations).}
71	\label{tab:scierc-ablation}
72	\end{table}
73	
74	% ──────────────────────────────────────────
75	%  (a) Core result
76	% ──────────────────────────────────────────
77	\paragraph{Core result: DR elimination at zero F1 cost.}
78	The full two-layer constraint configuration (S1) reduces domain/range
79	violations from 15.37\% to 0.93\%, a 94\% relative reduction,
80	% phase2_scierc_unconstrained: DR=0.1537; phase2_scierc_full_s1: DR=0.0093
81	while relation F1 moves from 8.23 to 8.36 ($+$0.13\,pp; bootstrap 95\% CI [$-$0.24, $+$0.58]\,pp, $p = 0.58$, 10{,}000 iterations).
82	% phase2_scierc_unconstrained: R-F1=0.0823; phase2_scierc_full_s1: R-F1=0.0836
83	% bootstrap: delta=+0.13pp, CI=[-0.24,+0.58], p=0.5824
84	The difference is not statistically significant ($p = 0.58$), confirming
85	that constraint enforcement is F1-neutral on this dataset.
86	At the per-relation level, violations drop from 42.42\% to 2.82\% on
87	\textsc{Compare}, from 33.54\% to 1.21\% on \textsc{Feature-of}, and
88	reach 0\% on four of seven relation types
89	(\textsc{Conjunction}, \textsc{Hyponym-of}, \textsc{Part-of},
90	\textsc{Used-for}).
91	% phase2_scierc_full_s1 per_relation_dr: Compare=0.0282,
92	%   Feature-of=0.0121, Hyponym-of=0, Part-of=0, Used-for=0, Conjunction=0
93	However, full constraint enforcement elevates cross-field consistency
94	violations from 0.08\% to 9.90\%;
95	% phase2_scierc_unconstrained: CF=0.0008; phase2_scierc_full_s1: CF=0.099
96	we analyze this trade-off in Section~\ref{sec:discussion}.
97	
98	% ──────────────────────────────────────────
99	%  (b) Grammar layer
100	% ──────────────────────────────────────────
101	\paragraph{Grammar layer: cost-free structural guarantees.}
102	Grammar-only constraints eliminate RV (1.39\%\,$\to$\,0\%) and ET (0.40\%\,$\to$\,0\%) with no F1 impact, while DR remains unchanged (15.37\%\,$\to$\,14.84\%), confirming that grammar constraints enforce structural validity but not semantic constraints.
103	% phase2_scierc_grammar_only: RV=0, ET=0, DR=0.1484, R-F1=0.0823
104	
105	% ──────────────────────────────────────────
106	%  (c) Enabling dependency
107	% ──────────────────────────────────────────
108	\paragraph{Enabling dependency.}
109	Semantic-only constraints reduce DR by only 24\% (15.37\%\,$\to$\,11.65\%) and cannot eliminate RV (1.51\%) or ET (0.40\%).
110	% phase2_scierc_semantic_only: DR=0.1165, RV=0.0151, ET=0.004
111	Adding the grammar layer yields a further 92\% relative reduction (11.65\%\,$\to$\,0.93\%), demonstrating an \emph{enabling dependency}: without grammar-enforced vocabulary, the semantic layer encounters OOV relation types with no domain/range rules.
112	% phase2_scierc_full_s1: DR=0.0093
113	
114	% ──────────────────────────────────────────
115	%  (d) S1 vs S2
116	% ──────────────────────────────────────────
117	\paragraph{S1 vs.\ S2.}
118	S2 achieves comparable DR (0.97\%) but lower R-F1 (8.03 vs.\ 8.36) with fewer triples (1{,}644 vs.\ 1{,}729) and does not resolve the CF trade-off (8.03\% vs.\ 9.90\%); we adopt S1 as the primary configuration.
119	% phase2_scierc_full_s2: DR=0.0097, R-F1=0.0803, CF=0.0803, triples=1644
120	
121	% ──────────────────────────────────────────
122	%  (e) Composability with Fine-Tuning
123	%  exp_ids: lora_scierc_unconstrained, lora_scierc_full_s1
124	% ──────────────────────────────────────────
125	\paragraph{Composability with fine-tuning.}
126	\label{sec:composability}
127	Table~\ref{tab:composability} presents the composability matrix on SciERC for both Qwen3-8B and Llama-3.1-8B (zero-shot vs.\ LoRA fine-tuned $\times$ unconstrained vs.\ full S1), testing whether OntoCoDec composes with task-specific fine-tuning across model families.
128	% exp_ids: phase2_scierc_unconstrained, phase2_scierc_full_s1,
129	%          w5_lora_scierc_unconstrained_eval, w5_lora_scierc_constrained_eval,
130	%          llama_scierc_unconstrained, llama_scierc_full_s1,
131	%          w5_llama_lora_scierc_unconstrained_eval, w5_llama_lora_scierc_constrained_eval
132	
133	For Qwen3-8B, fine-tuning alone raises R-F1 from 8.23 to 43.86 ($+$35.63\,pp) and E-F1 from 31.01 to 67.05 ($+$36.04\,pp), while reducing DR from 15.37\% to 1.95\% (87\% relative reduction).
134	% w5_lora_scierc_unconstrained_eval: DR=0.0195, R-F1=0.4386, E-F1=0.6705
135	The residual 1.95\% DR concentrates on tight-constraint relations: \textsc{Evaluate-for} (13.13\%), \textsc{Part-of} (5.77\%), and \textsc{Compare} (5.00\%) (per-relation breakdown in Appendix~\ref{app:lora-per-relation}).
136	Adding OntoCoDec eliminates the remaining DR entirely (1.95\%\,$\to$\,0\%) with R-F1 cost of $-$0.09\,pp (43.86\,$\to$\,43.77) and unchanged E-F1 (67.05).
137	% w5_lora_scierc_constrained_eval: DR=0, R-F1=0.4377, E-F1=0.6705, CF=0.0118
138	
139	Llama-3.1-8B exhibits the same pattern.
140	Fine-tuning raises R-F1 from 2.68 to 45.45 ($+$42.77\,pp) and E-F1 from 23.56 to 67.76 ($+$44.20\,pp), while reducing DR from 13.34\% to 1.11\%.
141	% w5_llama_lora_scierc_unconstrained_eval: DR=0.0111, R-F1=0.4545, E-F1=0.6776
142	Adding OntoCoDec reduces DR by 92\% (1.11\%\,$\to$\,0.09\%) with R-F1 change of $+$0.02\,pp (45.45\,$\to$\,45.47) and unchanged E-F1 (67.76).
143	% w5_llama_lora_scierc_constrained_eval: DR=0.0009, R-F1=0.4547, E-F1=0.6776, CF=0.0046
144	
145	Across both models, fine-tuned + S1 yields DR\,$\leq$\,0.09\% with R-F1 change within $\pm$0.1\,pp, consistently validating Claim~3 on SciERC across two model families: fine-tuning and OntoCoDec compose along orthogonal axes---fine-tuning improves extraction quality, OntoCoDec guarantees ontological compliance.
146	We evaluate on one dataset and one fine-tuning method (LoRA), so we do not claim composability holds universally.
147	
148	Two secondary observations support this interpretation.
149	First, CF interference drops substantially under fine-tuning for both models: Qwen from $+$9.82\,pp to $+$1.18\,pp, Llama from $+$6.32\,pp to $+$0.46\,pp,
150	% Qwen: ZS CF delta = 9.90-0.08 = 9.82pp, FT CF delta = 1.18-0 = 1.18pp
151	% Llama: ZS CF delta = 6.56-0.24 = 6.32pp, FT CF delta = 0.46-0 = 0.46pp
152	because fine-tuned per-slot type predictions are more consistent with the entity registry;
153	for Qwen, the residual 1.18\% traces to \textsc{Generic}$\leftrightarrow$X schema-level ambiguity (Appendix~\ref{app:cf-distribution}) rather than enforcement failure.
154	Second, in the zero-shot setting, S1 R-F1 impact is negligible for both models (Qwen $+$0.13\,pp, Llama $-$0.14\,pp),
155	% phase2_scierc_unconstrained: R-F1=0.0823; phase2_scierc_full_s1: R-F1=0.0836
156	% llama_scierc_unconstrained: R-F1=0.0268; llama_scierc_full_s1: R-F1=0.0254
157	confirming that constraint enforcement is F1-neutral regardless of base model quality.
158	
159	\begin{table}[t]
160	\centering
161	\small
162	\setlength{\tabcolsep}{3pt}
163	\resizebox{\columnwidth}{!}{%
164	\begin{tabular}{@{}lll rrrr r@{}}
165	\toprule
166	\textbf{Model} & \textbf{Setting} & \textbf{Mode}
167	  & \textbf{DR\,$\downarrow$} & \textbf{CF}
168	  & \textbf{R-F1\,$\uparrow$} & \textbf{E-F1\,$\uparrow$}
169	  & \textbf{$\Delta$DR} \\
170	\midrule
171	\multirow{4}{*}{Qwen3-8B}
172	  & \multirow{2}{*}{Zero-shot}
173	    & Unconstr.\ & 15.37 & 0.08 & 8.23  & 31.01 & --- \\
174	  & & Full S1    &  0.93 & 9.90 & 8.36  & 30.98 & $\downarrow$94\% \\
175	\cmidrule(l){2-8}
176	  & \multirow{2}{*}{LoRA}
177	    & Unconstr.\ &  1.95 & 0    & 43.86 & 67.05 & --- \\
178	  & & Full S1    & \textbf{0} & 1.18 & 43.77 & 67.05 & $\downarrow$100\% \\
179	\midrule
180	\multirow{4}{*}{Llama-3.1-8B}
181	  & \multirow{2}{*}{Zero-shot}
182	    & Unconstr.\ & 13.34 & 0.24 & 2.68  & 23.56 & --- \\
183	  & & Full S1    &  0.08 & 6.56 & 2.54  & 23.49 & $\downarrow$99\% \\
184	\cmidrule(l){2-8}
185	  & \multirow{2}{*}{LoRA}
186	    & Unconstr.\ &  1.11 & 0    & 45.45 & 67.76 & --- \\
187	  & & Full S1    &  0.09 & 0.46 & 45.47 & 67.76 & $\downarrow$92\% \\
188	\bottomrule
189	\end{tabular}}%
190	\caption{Composability matrix on SciERC (551 documents):
191	zero-shot vs.\ LoRA fine-tuned $\times$ unconstrained vs.\ full S1
192	for Qwen3-8B and Llama-3.1-8B.
193	$\Delta$DR: relative DR reduction vs.\ the same-row unconstrained baseline.
194	For both models, fine-tuning alone leaves residual DR (1--2\%);
195	adding S1 reduces it to $\leq$\,0.09\% with R-F1 change within $\pm$0.1\,pp.
196	F1\,$\times$100.
197	Evaluation is limited to one dataset and one fine-tuning method (LoRA).}
198	\label{tab:composability}
199	\end{table}
200	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d04b9caa-b902-460d-bdb7-b6a491f7f906",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "d4c1b28e-17e5-403a-a1ce-9087da98259e",
  "sourceToolAssistantUUID": "d04b9caa-b902-460d-bdb7-b6a491f7f906",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-16T02:53:03.939Z_

<details open><summary>🔧 Tool call — Read · `toolu_018JmZnXWXzHozb4tEzTZLgb`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section5_docred_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d4c1b28e-17e5-403a-a1ce-9087da98259e",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSq9f6BvfJev6xXmxe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3a5ed246-d19a-4327-ba71-debdd2690eec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PwL56No7iGa1g7xQCPvZiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 55344,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4675,
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

_source line 44 · 2026-05-16T02:53:03.943Z_

<details><summary>↩ Tool result · `toolu_018JmZnXWXzHozb4tEzTZLgb`</summary>

```text
1	% Section 5 — DocRED Results (compressed, 1450→~600 words)
2	% exp_ids: phase2_docred_unconstrained, phase2_docred_grammar_only,
3	%          phase2_docred_semantic_only, phase2_docred_full_s1
4	% All numbers verified against registry 2026-05-14.
5	
6	\subsection{Cross-Dataset Validation on DocRED}
7	\label{sec:docred-results}
8	
9	Table~\ref{tab:docred-ablation} presents the four-way ablation on DocRED, a document-level RE benchmark with 96 Wikidata relation types---14$\times$ the ontology size of SciERC.
10	All experiments use Qwen3-8B zero-shot on 998 documents.
11	
12	% ──────────────────────────────────────────
13	%  Table: DocRED four-way ablation
14	% ──────────────────────────────────────────
15	\begin{table}[t]
16	\centering
17	\small
18	\setlength{\tabcolsep}{3.6pt}
19	\resizebox{\columnwidth}{!}{%
20	\begin{tabular}{@{}l rrrrr rr@{}}
21	\toprule
22	& \multicolumn{5}{c}{\textbf{Violation Rates (\%)}}
23	& \multicolumn{2}{c}{\textbf{F1}} \\
24	\cmidrule(lr){2-6} \cmidrule(l){7-8}
25	\textbf{Mode}
26	  & DR\,$\downarrow$ & $\Delta$DR
27	  & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
28	  & Rel.\,$\uparrow$ & Ent.\,$\uparrow$ \\
29	\midrule
30	Unconstrained
31	  & 18.46 & ---
32	  & 29.66 & 2.48
33	  & 0.10
34	  & 7.74  & 58.15 \\
35	Grammar
36	  & 26.17 & $\uparrow$42\%
37	  & \textbf{0.03} & \textbf{0}
38	  & 0.07
39	  & \textbf{8.31}  & \textbf{59.38} \\
40	Semantic
41	  & 13.84 & $\downarrow$25\%
42	  & 29.87 & 4.22
43	  & 1.05
44	  & 7.70  & 57.81 \\
45	Full (S1)
46	  & \textbf{10.21} & $\downarrow$\textbf{45\%}
47	  & \textbf{0.03} & \textbf{0}
48	  & 2.57
49	  & 8.23  & 59.37 \\
50	\bottomrule
51	\end{tabular}}%
52	\caption{Four-way ablation on DocRED (998 documents, Qwen3-8B, zero-shot).
53	$\Delta$DR: relative change vs.\ unconstrained.
54	Best per column in \textbf{bold} (CF excluded).
55	F1 $\times$100. Bootstrap significance: R-F1 $+$0.50\,pp ($p < 0.001$).}
56	\label{tab:docred-ablation}
57	\end{table}
58	
59	% exp_ids: phase2_docred_unconstrained, phase2_docred_full_s1
60	\paragraph{Core result.}
61	Full S1 reduces DR from 18.46\% to 10.21\% ($\downarrow$45\%), eliminates ET (2.48\%\,$\to$\,0\%), and near-eliminates RV (29.66\%\,$\to$\,0.03\%).
62	Relation F1 improves from 7.74 to 8.23 ($+$0.50\,pp; bootstrap 95\% CI [$+$0.23, $+$0.81], $p < 0.001$), attributable to grammar-layer elimination of 5{,}189 OOV relation predictions counted as false positives.
63	CF increases modestly (0.10\%\,$\to$\,2.57\%), lower than SciERC's 9.90\%.
64	
65	% exp_ids: phase2_docred_grammar_only
66	\paragraph{Grammar layer surfaces latent violations.}
67	Grammar-only constraints eliminate RV and ET but \emph{increase} DR from 18.46\% to 26.17\% ($+$42\%).
68	This counter-intuitive result has a structural explanation: the unconstrained baseline's 29.66\% OOV relation triples cannot be evaluated for DR (no schema entry exists); grammar enforcement assigns these triples valid relation names whose domain/range rules the associated entity types frequently violate.
69	The grammar layer thus \emph{reveals} latent type incompatibilities, directly motivating the semantic layer.
70	
71	% exp_ids: phase2_docred_semantic_only, phase2_docred_full_s1
72	\paragraph{Enabling dependency.}
73	Semantic-only constraints reduce DR by only 25\% (18.46\%\,$\to$\,13.84\%) while failing to eliminate RV (29.87\%) or ET (4.22\%).
74	Full S1 achieves a further 26\% relative reduction over semantic-only (13.84\%\,$\to$\,10.21\%), replicating the enabling dependency from SciERC: without grammar-enforced vocabulary, the semantic layer encounters OOV relation types for which no domain/range rules exist.
75	
76	% exp_ids: phase2_docred_full_s1, llama_docred_full_s1
77	\paragraph{Constraint tightness governs enforcement ceiling.}
78	The residual DR on DocRED (10.21\%) exceeds SciERC (0.93\%) due to per-relation \emph{constraint tightness}: DocRED relations average 5.68 valid type pairs ($\bar{\tau}{=}0.842$) vs.\ 24 on SciERC ($\bar{\tau}{=}0.333$).
79	Tighter constraints produce narrower grammar$\cap$semantic mask intersections, increasing fallback frequency---the aggregate fallback rate (10.2\%; 1{,}770/17{,}341 triples) closely tracks residual DR (10.21\%), confirming a near-bijection between fallback events and residual violations.
80	Crucially, tightness interacts with the model's baseline violation profile: Qwen's high RV (29.66\%) causes grammar enforcement to surface many latent DR violations, yielding 10.21\% residual DR; Llama's lower RV (16.03\%) limits this surfacing, achieving 2.55\% residual ($\downarrow$90.2\%) on the same ontology (\S\ref{sec:cross-model}).
81	This dual-factor pattern---tightness $\times$ baseline RV---is consistent with cross-dataset and cross-model DR reduction differences.
82	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3a5ed246-d19a-4327-ba71-debdd2690eec",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "ec24274f-26aa-4bb1-a072-762a406ac047",
  "sourceToolAssistantUUID": "3a5ed246-d19a-4327-ba71-debdd2690eec",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-16T02:53:04.663Z_

<details open><summary>🔧 Tool call — Read · `toolu_01JvR6W7yZt7hFmoZW89Pb65`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section5_crossmodel_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ec24274f-26aa-4bb1-a072-762a406ac047",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VSq9f6BvfJev6xXmxe",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "124a6b08-dc9f-48b4-b294-a28e074710ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PwL56No7iGa1g7xQCPvZiN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4675,
      "cache_read_input_tokens": 55344,
      "output_tokens": 277,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4675
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 277,
          "cache_read_input_tokens": 55344,
          "cache_creation_input_tokens": 4675,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4675,
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

_source line 46 · 2026-05-16T02:53:04.669Z_

<details><summary>↩ Tool result · `toolu_01JvR6W7yZt7hFmoZW89Pb65`</summary>

```text
1	% Section 5 — Cross-Model Validation (compressed, 830→~400 words)
2	% exp_ids: phase2_scierc_unconstrained, phase2_scierc_full_s1,
3	%          phase2_docred_unconstrained, phase2_docred_full_s1,
4	%          llama_scierc_unconstrained, llama_scierc_full_s1,
5	%          llama_docred_unconstrained, llama_docred_full_s1
6	
7	\subsection{Cross-Model Validation}
8	\label{sec:cross-model}
9	
10	We replicate the full S1 configuration with Llama-3.1-8B-Instruct under identical prompts, decoding parameters, and evaluation.
11	Table~\ref{tab:cross-model} summarizes results alongside Qwen3-8B.
12	
13	\begin{table}[t]
14	\centering
15	\small
16	\setlength{\tabcolsep}{3.4pt}
17	\resizebox{\columnwidth}{!}{%
18	\begin{tabular}{@{}ll rrrr rr@{}}
19	\toprule
20	& & \multicolumn{4}{c}{\textbf{Violation Rates (\%)}}
21	& \multicolumn{2}{c}{\textbf{F1}} \\
22	\cmidrule(lr){3-6} \cmidrule(l){7-8}
23	\textbf{Dataset} & \textbf{Model}
24	  & DR\,$\downarrow$ & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
25	  & Rel. & Ent. \\
26	\midrule
27	\multirow{4}{*}{SciERC}
28	  & Qwen (U)  & 15.37 & 1.39 & 0.40 & 0.08 & 8.23 & 31.01 \\
29	  & Qwen (S1) &  0.93 & 0    & 0    & 9.90 & 8.36 & 30.98 \\
30	  \cmidrule(l){2-8}
31	  & Llama (U)  & 13.34 & 0.55 & 0    & 0.24 & 2.68 & 23.56 \\
32	  & Llama (S1) &  0.08 & 0    & 0    & 6.56 & 2.54 & 23.49 \\
33	\midrule
34	\multirow{4}{*}{DocRED}
35	  & Qwen (U)  & 18.46 & 29.66 & 2.48 & 0.10 & 7.74 & 58.15 \\
36	  & Qwen (S1) & 10.21 &  0.03 & 0    & 2.57 & 8.23 & 59.37 \\
37	  \cmidrule(l){2-8}
38	  & Llama (U)  & 26.07 & 16.03 & 0.13 & 0.17 & 5.98 & 55.65 \\
39	  & Llama (S1) &  2.55 &  0    & 0    & 12.02 & 6.27 & 55.01 \\
40	\bottomrule
41	\end{tabular}}%
42	\caption{Cross-model validation. U: unconstrained; S1: full two-layer.
43	Parse failures (U$\to$S1): Qwen DocRED 12$\to$11, Llama DocRED 68$\to$91; others $\leq$1.
44	F1 $\times$100.}
45	\label{tab:cross-model}
46	\end{table}
47	
48	\paragraph{Model-agnostic structural guarantees.}
49	RV and ET violations are eliminated ($\leq$0.03\%) for both models on both datasets, confirming that grammar-layer enforcement depends on the decoding mechanism, not model-specific generation patterns.
50	
51	% exp_ids: phase2_scierc_full_s1, llama_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1
52	\paragraph{DR reduction generalizes but varies by model.}
53	SciERC DR drops 94\% for Qwen (15.37\%\,$\to$\,0.93\%) and 99.4\% for Llama (13.34\%\,$\to$\,0.08\%); DocRED DR drops 45\% for Qwen and 90.2\% for Llama.
54	R-F1 is preserved or improves in three of four settings
55	(Qwen: $+$0.13/$+$0.50\,pp; Llama: $-$0.14/$+$0.29\,pp).
56	On DocRED, R-F1 gains are statistically significant for both models
57	(Qwen $+$0.50\,pp, $p{<}0.001$; Llama $+$0.29\,pp, $p{=}0.013$;
58	bootstrap 10{,}000 iterations).
59	The sole R-F1 decline (Llama SciERC, $-$0.14\,pp)
60	is practically negligible on a 2.68\% baseline.
61	On SciERC, Qwen's R-F1 change is not significant ($p{=}0.58$).
62	% All bootstrap CIs registry-aligned (≤0.05pp tolerance)
63	Entity F1 impact is model-dependent: Qwen DocRED improves ($+$1.22\,pp, $p{<}0.001$), while Llama DocRED shows a modest decline ($-$0.64\,pp, $p{=}0.022$), partially attributable to Llama's higher parse failure rate under constraints (91 vs.\ 68 documents); other entity F1 changes are not significant.
64	
65	\paragraph{Tightness $\times$ RV interaction is consistent with cross-model asymmetry.}
66	Llama's relative DR reduction exceeds Qwen's on both datasets.
67	This asymmetry reflects the interaction between constraint tightness and model-specific violation profiles (\S\ref{sec:docred-results}): Qwen's higher baseline RV (29.66\% vs.\ 16.03\% on DocRED) causes grammar enforcement to surface more latent DR violations---triples whose OOV relation names masked underlying type incompatibilities.
68	With Llama's lower RV, fewer triples undergo this surfacing, yielding residual DR of 2.55\% vs.\ Qwen's 10.21\% on the same ontology ($\bar{\tau}{=}0.842$).
69	This is consistent with the dual-factor pattern: constraint tightness sets the enforcement difficulty ceiling, while baseline RV modulates the realized residual DR.
70	Notably, Llama's per-relation residual DR shows no correlation with tightness (Spearman $\rho{=}0.069$, $p{=}0.52$), indicating that the constraint system is uniformly effective across relations of varying tightness once baseline RV is low (per-relation breakdown in Appendix~\ref{app:llama-per-relation}).
71	
72	\paragraph{CF trade-off.}
73	CF violations increase under S1 for both models (Qwen: 0.08\%\,$\to$\,9.90\% SciERC, 0.10\%\,$\to$\,2.57\% DocRED; Llama: 0.24\%\,$\to$\,6.56\% SciERC, 0.17\%\,$\to$\,12.02\% DocRED), confirming CF elevation as a systematic property of per-relation independent enforcement (\S\ref{sec:discussion}).
74	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "124a6b08-dc9f-48b4-b294-a28e074710ea",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "f13157ab-00ae-4c94-a1a3-a3e7685c99eb",
  "sourceToolAssistantUUID": "124a6b08-dc9f-48b4-b294-a28e074710ea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-16T02:53:09.576Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BzHFu23patZnRJHBzjwEY6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section7_conclusion_compressed.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f13157ab-00ae-4c94-a1a3-a3e7685c99eb",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTGoWCaUX66atUDAtz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7898aa9f-0062-4171-a9bb-7692982bd164",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RkQpi3oHvRjkryAfy34M77",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9178,
      "cache_read_input_tokens": 60019,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9178,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 39,
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

_source line 48 · 2026-05-16T02:53:09.596Z_

<details><summary>↩ Tool result · `toolu_01BzHFu23patZnRJHBzjwEY6`</summary>

```text
1	% Section 7 — Discussion and Conclusion (compressed)
2	% Full discussion paragraphs moved to Appendix B.
3	
4	\paragraph{CF Severity.}
5	% exp_ids: phase2_scierc_full_s1 (CF=9.90%), phase2_scierc_grammar_only (CF=0.08%),
6	%          phase2_docred_full_s1 (CF=2.57%), llama_docred_full_s1 (CF=12.02%)
7	Unlike DR violations (ontologically invalid triples), CF violations are qualitatively milder: each triple remains type-valid per its own relation; only cross-triple consistency is broken.
8	The dominant pattern---\emph{Generic}$\leftrightarrow$\emph{OtherScientificTerm} (85/245 on SciERC; Table~\ref{tab:cf-distribution})---reflects genuine type-system ambiguity, with \textsc{Generic} involved in 63.3\% of all CF violations.
9	Ablation attributes CF to the semantic layer's two mechanisms---registry override and grammar-first fallback---with model-dependent profiles (Appendix~\ref{app:discussion}).
10	% exp_ids: phase2_scierc_grammar_only, phase2_docred_full_s1, llama_docred_full_s1
11	CF fallback ablation confirms a CF$\leftrightarrow$DR tension: eliminating CF re-routes violations to DR ($+$13.85\,pp), confirming the current S1 configuration as near-optimal (Appendix~\ref{app:cf-dr-tradeoff}).
12	% exp_ids: cf_fallback_ablation_scierc
13	Fine-tuning reduces CF by 88\% ($+$9.82\,pp\,$\to$\,$+$1.18\,pp; \S\ref{sec:composability}); the residual traces to schema-level \textsc{Generic}$\leftrightarrow$X ambiguity.
14	R-F1 gains are significant on DocRED ($+$0.50\,pp, $p{<}0.001$) but not SciERC ($+$0.13\,pp, $p{=}0.58$), proportional to baseline OOV rate (Appendix~\ref{app:discussion}).
15	% exp_ids: lora_scierc_full_s1, d012_bootstrap_ci
16	
17	% Limitations and Future Work moved to \section*{Limitations} in main.tex (ARR requirement)
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7898aa9f-0062-4171-a9bb-7692982bd164",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "66e4f259-54f3-43a2-9be8-7b4ac0f9449f",
  "sourceToolAssistantUUID": "7898aa9f-0062-4171-a9bb-7692982bd164",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-16T02:53:10.109Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DBaF8tR75f2ad1vPdyjMHX`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "66e4f259-54f3-43a2-9be8-7b4ac0f9449f",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTGoWCaUX66atUDAtz",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a9ac4cd5-eade-4662-85dd-4f68336b9462",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RkQpi3oHvRjkryAfy34M77",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9178,
      "cache_read_input_tokens": 60019,
      "output_tokens": 177,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 9178
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 177,
          "cache_read_input_tokens": 60019,
          "cache_creation_input_tokens": 9178,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 9178,
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

_source line 50 · 2026-05-16T02:53:10.122Z_

<details><summary>↩ Tool result · `toolu_01DBaF8tR75f2ad1vPdyjMHX`</summary>

```text
1	\section{Extended Related Work}
2	\label{app:related_work}
3	
4	% ===========================================================================
5	% Paradigm 1: Grammar-Constrained Decoding
6	% ===========================================================================
7	\paragraph{Grammar-Constrained Decoding.}
8	Recent work has established efficient algorithms for restricting LLM outputs to conform to context-free grammars, making grammar-constrained decoding the de facto standard for obtaining structured output from language models.
9	XGrammar~\cite{dong2025xgrammar} partitions the vocabulary into context-independent and context-dependent tokens and maintains persistent pushdown automata across decoding steps, achieving up to 100$\times$ speedup over prior CFG-constrained decoding methods.
10	Outlines~\cite{willard2023outlines} reformulates constrained generation as finite-state machine transitions with offline vocabulary indexing, enabling efficient enforcement of regular-expression and JSON-schema constraints without runtime overhead per token.
11	LMQL~\cite{beurer-kellner2023lmql} introduces a declarative query language that compiles type, length, and regex constraints into token-level masks, providing a programmable interface for specifying multi-variable output structures.
12	These systems ensure that every generated token belongs to a grammar-valid continuation, but they do not address the \emph{distribution distortion} introduced by naive token masking.
13	A parallel line of work tackles this problem directly: DOMINO~\cite{beurer-kellner2024domino} minimizes distributional divergence during CFG enforcement by formulating mask selection as an optimization problem, and ASAp~\cite{park2024grammar} provides a provably unbiased sampling algorithm that preserves the original LM distribution under grammar constraints.
14	Together, these advances have made grammar-constrained decoding both fast and statistically principled, establishing a robust foundation for structured generation.
15	However, all of these methods operate exclusively at the syntactic level---they ensure format validity (e.g., well-formed JSON, valid enum values) but cannot enforce cross-field semantic constraints such as ontology domain/range rules that depend on previously generated content.
16	This syntactic-only limitation motivates OntoCoDec's semantic extension: our grammar layer builds on XGrammar for structural (JSON schema and enum) constraints, while a second semantic layer enforces relational type constraints that are inherently beyond the expressive power of context-free grammars.
17	
18	% ===========================================================================
19	% Paradigm 1.5: Semantic Constrained Decoding for Code
20	% ===========================================================================
21	\paragraph{Semantic Constrained Decoding for Code.}
22	In programming-language generation, constrained decoding has been extended beyond syntax to enforce semantic properties such as type correctness, demonstrating that richer-than-CFG constraints can be compiled into token-level filtering.
23	In the text-to-SQL domain, PICARD~\cite{scholak2021picard} maintains an incremental SQL parsing state that rejects tokens violating syntax or referencing non-existent database columns at each decoding step, achieving state-of-the-art results on Spider and CoSQL without modifying model weights.
24	While mechanistically similar to OntoCoDec's token-level filtering, PICARD operates over a \emph{fixed, fully enumerated} schema---database table and column names known before decoding begins.
25	In contrast, OntoCoDec's entity registry is populated \emph{during} generation as entity spans are extracted from free text, requiring constraint sets that evolve with the decoding prefix---a fundamental distinction between querying a known schema and extracting from unstructured text.
26	Synchromesh~\cite{synchromesh_iclr2022} pioneers Constrained Semantic Decoding (CSD), which enforces syntax, type, and scope constraints simultaneously during code generation from pre-trained LMs without fine-tuning, establishing that semantic constraints can be expressed as dynamic token masks conditioned on the generation prefix.
27	MGD~\cite{mgd_neurips2023} uses static-analysis monitors to perform incremental type checking at decode time, enabling SantaCoder-1.1B to outperform text-davinci-003 on repository-level code completion by ensuring that every generated identifier is type-correct with respect to the surrounding code context.
28	Most recently, \citet{pldi2025_type_constrained_codegen} compile full type systems---including generic types and subtyping---into prefix automata for token-level logits masking, reducing compilation errors by over 50\%.
29	This last system is the closest mechanistic analog to OntoCoDec, applying the same ``type system $\to$ automaton $\to$ logits mask'' pipeline, though in a fundamentally different domain.
30	The key technical difference lies in the constraint structure: programming-language type systems feature deep subtyping hierarchies and parametric polymorphism, whereas IE ontology axioms specify flat domain/range sets---a relation $R$ accepts head entities from set $\mathcal{D}(R)$ and tail entities from set $\mathcal{R}(R)$, with no subtype chains.
31	Conversely, IE introduces a challenge absent in code generation: the constraint target (entity type) must be inferred from free-text spans rather than read from declared type annotations, requiring a stateful entity registry that tracks extracted types during autoregressive generation.
32	These methods collectively demonstrate that semantic (type) constraints at decode time are both feasible and highly effective, but exclusively in the code domain where type systems are formally specified.
33	OntoCoDec is the first to \emph{automatically compile} IE ontology axioms---including domain/range constraints---into token-level decoding masks for information extraction, migrating the type-constrained decoding paradigm from code generation to IE.
34	
35	% ===========================================================================
36	% Paradigm 2: Vocabulary/Type-Constrained Generation
37	% ===========================================================================
38	\paragraph{Vocabulary and Type-Constrained Generation.}
39	The idea of enforcing entity-type compatibility constraints for information extraction dates back to pre-neural methods.
40	\citet{roth_yih_2004} formulate joint entity and relation identification as an integer linear program (ILP) that enforces type constraints---e.g., \textsc{Emp-Org} only between \textsc{Per} and \textsc{Org} entities---establishing the foundational principle that relational type compatibility should be a hard constraint, not a soft preference learned from data.
41	In the autoregressive era, GENRE~\cite{decao2021genre} pioneers trie-based constrained beam search for autoregressive entity retrieval, restricting each decoding step to tokens consistent with valid entity names from a predefined catalog.
42	GenIE~\cite{josifoski2022genie} extends this approach to end-to-end information extraction with state-based constraints that enforce valid triple structures, achieving strong performance on closed-world knowledge base population, though it requires task-specific fine-tuning on the target schema.
43	AdaKGC~\cite{adakgc_emnlp2023} introduces schema-constrained dynamic decoding with trie-based prefix trees that adapt to the target schema, enforcing that generated entity and relation names belong to a predefined inventory---a vocabulary-level constraint that ensures name validity but does not verify type compatibility between a relation and its arguments.
44	GCD~\cite{geng2023gcd} provides a unified grammar-constrained decoding framework for structured NLP tasks including IE, introducing input-dependent grammars that adapt constraints based on the source text---the closest precursor to OntoCoDec in applying logits masking to IE, though limited to syntactic constraints.
45	NeuroLogic Decoding~\cite{lu2021neurologic} expresses lexical inclusion and exclusion constraints as predicate logic formulas enforced during beam search, offering a general mechanism for token-level control that can encode vocabulary membership but not relational type rules.
46	These approaches constrain \emph{which tokens} can appear (vocabulary membership) but not \emph{which type combinations} are valid for a given relation.
47	OntoCoDec's semantic layer enforces relational constraints---e.g., that the head entity of relation $R$ must belong to type set $\mathcal{D}(R)$---which cannot be expressed as static vocabulary restrictions because the valid set depends on the relation type generated earlier in the same sequence.
48	While Roth \& Yih's ILP formulation shares the same type-compatibility motivation, it operates as a post-hoc reranker over discrete candidates; OntoCoDec integrates enforcement directly into autoregressive decoding, preventing violations rather than filtering them.
49	
50	% ===========================================================================
51	% Paradigm 3: Structural Constraints for IE
52	% ===========================================================================
53	\paragraph{Structural Constraints via Training and Prompting.}
54	An orthogonal approach encodes IE output structure through model training or prompt design rather than decoding-time enforcement, relying on learned representations to produce schema-compliant outputs.
55	UIE~\cite{lu2022uie} defines a Structured Extraction Language and trains a unified text-to-structure model across 13 IE datasets, relying on large-scale pre-training to internalize output format constraints.
56	GoLLIE~\cite{sainz2024gollie} expresses annotation guidelines as Python dataclass definitions and fine-tunes Code-LLaMA to generate typed code, achieving strong zero-shot transfer to unseen IE schemas by leveraging the implicit type structure of programming languages.
57	KnowCoder~\cite{knowcoder_acl2024} takes this further by encoding 29K entity types from Wikidata as a Python class hierarchy, training a Code-LLM to generate structured extraction code that implicitly respects type inheritance---the most comprehensive schema-as-code approach to date.
58	CodeIE~\cite{li2023codeie} similarly reformulates IE as code generation, leveraging the structural regularity of programming languages to reduce output format errors.
59	ADELIE~\cite{qi2024adelie} uses SFT and DPO to align LLMs on IE tasks, achieving state-of-the-art results among open-source models while preserving general capabilities, though compliance with ontological constraints remains a learned soft preference rather than a guarantee.
60	In the supervised setting, joint entity-relation architectures such as SpERT~\cite{eberts2020spert} and PFN~\cite{yan2021pfn} enforce type consistency implicitly through shared representations: SpERT classifies entity spans and relation pairs in a single BERT pass with span-level negative sampling, while PFN decomposes feature encoding into entity-specific, relation-specific, and shared partitions via gating mechanisms.
61	These models achieve strong performance but are limited to fixed, predefined schemas and cannot generalize to unseen ontologies without retraining---precisely the zero-shot, ontology-portable scenario that OntoCoDec targets.
62	EnriCo~\cite{zaratiana2024enrico} applies Answer Set Programming (ASP) constraints during decoding of joint entity-relation extraction models, enforcing structural type compatibility at generation time---a decoding-time approach, though with model-specific, manually authored constraints rather than ontology-driven compilation.
63	Training-based methods provide \emph{soft} structural guidance---the model learns to prefer valid outputs but cannot guarantee compliance at inference time, as demonstrated by non-trivial violation rates even in fine-tuned systems.
64	Importantly, training-based and decoding-time approaches are complementary rather than competing: a system like GoLLIE could be combined with OntoCoDec's constraint layers, using fine-tuning to maximize the probability of valid outputs while decoding-time enforcement eliminates residual violations.
65	OntoCoDec provides \emph{hard} decoding-time enforcement that is training-free, automatically compiled from ontology schemas, and composable with any of these training-based approaches.
66	
67	% ===========================================================================
68	% Paradigm 4: Type-Checking / Ontology Validation
69	% ===========================================================================
70	\paragraph{Post-hoc Ontology Validation.}
71	Rather than constraining generation, several methods validate LLM outputs against ontological rules after generation, applying a detect-then-fix paradigm.
72	ODKE+~\cite{khorshidi2025odke} dynamically generates ontology snippets containing domain/range constraints as prompt context, achieving 98.8\% precision across 195 predicates at web scale---but constraint adherence relies on prompt-level guidance, not enforcement, leaving residual violations unaddressed.
73	SPIRES/OntoGPT~\cite{spires_2024} provides an ontology-based extraction framework that grounds LLM outputs against OBO ontologies post-generation, validating extracted entities and relations through ontology lookup and correcting mismatches in a second pass---representing the prompt-then-validate paradigm in the biomedical domain.
74	OntoLogX~\cite{ontologx_2025} applies SHACL validation to LLM-generated knowledge graphs, iteratively re-prompting the LLM to correct constraint violations and reducing them by approximately 10$\times$ across multiple correction rounds---demonstrating the detect-then-fix paradigm's effectiveness but also its inherent multi-pass cost.
75	\citet{upadhyay2023openie} inject entity-type knowledge as constraints into Open IE via both constrained inference and constraint-aware training, improving F1 by 29\% on CaRB, though their constrained inference operates over a discrete candidate set rather than during autoregressive generation.
76	\citet{regino2025kgcurator} propose a multi-stage LLM pipeline for validating RDF triple insertions against RDFS domain/range constraints, where each validation step requires a separate LLM call---effective but computationally expensive at scale.
77	RELATE~\cite{olasunkanmi2025relate} addresses the alignment gap between LLM-extracted biomedical relations and standardized ontology predicates through a three-stage pipeline: ontology preprocessing with predicate embeddings, similarity-based retrieval via SapBERT, and LLM-based reranking with negation handling, achieving 94\% accuracy@10 on ChemProt.
78	While RELATE demonstrates effective ontology grounding for relation extraction, its constraints are applied \emph{post-extraction} through retrieval and reranking rather than during generation, and it requires domain-specific embedding models trained on biomedical corpora.
79	OntoCoDec enforces ontology constraints \emph{during} autoregressive decoding and requires no additional trained components beyond the base LLM.
80	Concurrently, \citet{zhou2026ontologytools} compile OWL ontologies into executable tool interfaces within The World Avatar framework, requiring LLM agents to invoke ontology-aware tools that enforce semantic constraints during knowledge graph construction from scientific text.
81	This ``ontology-to-tools'' approach shares OntoCoDec's philosophy of compiling formal ontological knowledge into runtime enforcement mechanisms, but operates at the tool-call level (constraining which API functions the agent invokes) rather than at the token level (constraining which tokens the decoder produces), and requires an agentic multi-step workflow rather than single-pass autoregressive generation.
82	\citet{ekaw2024_ontology_beam} introduce ontology-constrained beam scoring for clinical summarization, applying soft biases (not hard masks) during beam search to steer outputs toward ontology-compliant terms---a middle ground between unconstrained generation and hard enforcement that reduces but cannot eliminate violations.
83	Post-hoc validation detects violations after generation, requiring rejection or correction cycles that waste compute---in our setting, 15.37\% of generated triples contain domain/range violations under unconstrained decoding, representing substantial wasted generation effort.
84	OntoCoDec \emph{prevents} violations during decoding, redirecting probability mass to valid alternatives rather than discarding invalid outputs, with only marginal overhead from logits masking compared to the cost of regenerating or correcting violated triples.
85	Soft-constraint approaches such as ontology-weighted beam scoring reduce violation frequency but cannot eliminate it, whereas OntoCoDec substantially reduces violations (DR$\downarrow$94\% on SciERC, $\downarrow$45--90\% on DocRED depending on model).
86	
87	% ===========================================================================
88	% Paradigm 5: Constrained Decoding Quality Concerns
89	% ===========================================================================
90	\paragraph{Quality Impact of Constrained Decoding.}
91	A growing body of work raises concerns that constrained decoding degrades LLM generation quality, particularly for reasoning-intensive tasks where format enforcement interferes with chain-of-thought processes.
92	\citet{tam2024letmespeak} conduct a comprehensive evaluation showing that rigid format constraints (JSON, XML) harm performance on math and multi-hop QA benchmarks but \emph{benefit} classification-style tasks such as slot filling---a distinction directly relevant to IE, which is fundamentally an extraction (classification-like) task rather than a reasoning task.
93	CRANE~\cite{banerjee2025crane} provides theoretical analysis of why restricting outputs to narrow grammars suppresses chain-of-thought reasoning by eliminating intermediate reasoning tokens, and proposes an alternating strategy between unconstrained reasoning phases and constrained output phases to mitigate this effect.
94	\citet{schall2025hiddencost} conduct a systematic study across 11 models and multiple benchmarks, finding 10--30\% semantic correctness degradation on reasoning tasks under structural constraints, with larger models showing greater absolute degradation.
95	\citet{zhou2026snowballing} identify ``structure snowballing''---a failure mode where format compliance cognitive load traps models in repetitive structural patterns rather than improving reasoning during self-correction iterations.
96	These findings establish a legitimate concern for constrained decoding in reasoning-heavy applications.
97	However, information extraction occupies a fundamentally different regime: the model extracts entities and relations from input text rather than generating novel reasoning chains, and \citet{tam2024letmespeak}'s own results show that extraction-style tasks are robust to---or even benefit from---format constraints.
98	OntoCoDec addresses this concern empirically: domain/range violations decrease by 94\% on SciERC (15.37\%$\to$0.93\%) and 45--90\% on DocRED across two models, with F1-neutral impact on SciERC ($+$0.13pp, $p{=}0.58$) and significant R-F1 gains on DocRED ($p \leq 0.013$).
99	Critically, OntoCoDec's constraints target only type tokens (entity types, relation labels), leaving free-text spans---entity surface forms and their boundaries---entirely unconstrained, which minimizes the distribution distortion that causes quality degradation in reasoning tasks.
100	A two-pass variant (S2), explored in ablation (Section~5), separates extraction and constraint enforcement into distinct passes, analogous to CRANE's alternating strategy; however, our primary single-pass approach already avoids reasoning interference by constraining only type tokens while leaving free-text spans unconstrained.
101	
102	% ===========================================================================
103	% Our Approach
104	% ===========================================================================
105	\paragraph{Our Approach.}
106	OntoCoDec occupies a unique position in this landscape: it is the first system to \emph{automatically compile} IE ontology schemas---including domain/range axioms---into token-level semantic masks, extending grammar-constrained decoding from syntactic to semantic enforcement without manually authored rules.
107	Unlike vocabulary-constrained methods that restrict individual tokens to a fixed set, OntoCoDec enforces \emph{cross-field relational constraints} through a stateful entity registry that tracks extracted types during autoregressive generation, enabling dynamic constraint evaluation that depends on previously decoded content.
108	This approach is orthogonal to supervised IE methods and applicable to any autoregressive LM without model modification or additional training.
109	Unlike training-based IE systems, OntoCoDec is training-free and substantially reduces type violations at inference time (DR$\downarrow$94\% on SciERC, $\downarrow$45--90\% on DocRED); unlike post-hoc validation, it prevents violations rather than detecting them, redirecting probability mass to valid alternatives with significant R-F1 gains on DocRED ($p \leq 0.013$) and F1-neutral impact on SciERC.
110	The two constraint layers---grammar (structural) and semantic (relational)---compose via bitwise AND with an enabling dependency: the grammar layer ensures every generated type token belongs to the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type.
111	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a9ac4cd5-eade-4662-85dd-4f68336b9462",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "b02363a5-3247-42a0-8542-7552e317f27c",
  "sourceToolAssistantUUID": "a9ac4cd5-eade-4662-85dd-4f68336b9462",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 51 · 2026-05-16T02:53:12.739Z_

Now let me read the remaining sections to complete my understanding.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b02363a5-3247-42a0-8542-7552e317f27c",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTg6E4FmhVSBXQAN52",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7cd9f251-af7a-4e79-a2c7-53d9d2b75043",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcBsnWnRsrcSn346agujK1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5828,
      "cache_read_input_tokens": 69197,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5828,
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

_source line 52 · 2026-05-16T02:53:14.728Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FCfjJDPez6xgCRij8F81s9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section2_background.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7cd9f251-af7a-4e79-a2c7-53d9d2b75043",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTg6E4FmhVSBXQAN52",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "59d87c2a-7403-4f96-b5d9-2b2ced93cd09",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcBsnWnRsrcSn346agujK1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5828,
      "cache_read_input_tokens": 69197,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5828,
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

_source line 53 · 2026-05-16T02:53:14.733Z_

<details><summary>↩ Tool result · `toolu_01FCfjJDPez6xgCRij8F81s9`</summary>

```text
1	% Section 2: Background (compressed)
2	
3	\section{Background}
4	\label{sec:background}
5	
6	\paragraph{IE Ontology Structure.}
7	\label{sec:bg:ontology}
8	An IE ontology $\mathcal{O} = (\mathcal{E}, \mathcal{R}, \sigma)$ defines entity types $\mathcal{E}$, relation types $\mathcal{R}$, and a mapping $\sigma: \mathcal{R} \to \mathcal{P}(\mathcal{E} \times \mathcal{E})$ specifying valid (head type, tail type) pairs per relation.
9	A triple $(h, r, t)$ is \emph{type-valid} if $(\mathrm{type}(h), \mathrm{type}(t)) \in \sigma(r)$.
10	We define the \emph{constraint tightness} of $r$ as $1 - |\sigma(r)| / |\mathcal{T}|^2$ where $\mathcal{T} = \mathcal{E}$ is the entity type vocabulary: tighter constraints leave fewer valid options, increasing violation likelihood.
11	
12	\paragraph{Grammar-Constrained Decoding.}
13	\label{sec:bg:gcd}
14	Grammar-constrained decoding restricts each token $y_t$ to a mask $M_g \in \{0, 1\}^{|V|}$ derived from a target grammar.
15	XGrammar~\citep{dong2025xgrammar} compiles JSON Schemas into pushdown automata for efficient enforcement of structural constraints; Outlines~\citep{willard2023outlines} and SGLang~\citep{zheng2024sglang} offer similar capabilities.
16	However, these methods are limited to context-free constraints and cannot enforce cross-field semantic rules---e.g., ``if $r$ = \textsc{Feature-of}, then $\mathrm{type}(h) \in \{\textsc{Method}, \textsc{OtherScientificTerm}\}$''---which depend on previously generated field values.
17	
18	\paragraph{Problem Statement.}
19	\label{sec:bg:problem}
20	Given $\mathcal{O}$ and an autoregressive LM $\mathcal{M}$, we seek constraints $\mathcal{C}$ ensuring: (a)~\textbf{structural validity}---well-formed JSON with $\mathcal{E}$/$\mathcal{R}$ membership; and (b)~\textbf{type validity}---$(\mathrm{type}(h), \mathrm{type}(t)) \in \sigma(r)$ for every triple.
21	Condition (a) is context-free; (b) is context-sensitive but \emph{prefix-decidable}---at the point where a type token is generated, all information needed (relation type, entity registry) is available in the decoded prefix.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "59d87c2a-7403-4f96-b5d9-2b2ced93cd09",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "e496b9f7-4131-469a-aca3-be77738d4ca0",
  "sourceToolAssistantUUID": "59d87c2a-7403-4f96-b5d9-2b2ced93cd09",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 54 · 2026-05-16T02:53:15.719Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LrDD3h1MtiBs6FYo5AGZoq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section3_violation_landscape.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e496b9f7-4131-469a-aca3-be77738d4ca0",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTg6E4FmhVSBXQAN52",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a2c37f09-9432-4d7b-809a-dc3f031a169b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcBsnWnRsrcSn346agujK1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5828,
      "cache_read_input_tokens": 69197,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5828,
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

_source line 55 · 2026-05-16T02:53:15.729Z_

<details><summary>↩ Tool result · `toolu_01LrDD3h1MtiBs6FYo5AGZoq`</summary>

```text
1	% §5.1 Experimental Setup and Violation Landscape
2	% Compressed from standalone section. main.tex provides \subsection header.
3	% exp_ids: mvp_phase0_violation_rate, mvp_phase0_scierc_schema,
4	%          mvp_phase0_violation_rate_docred, mvp_phase0_docred_schema
5	
6	\label{sec:violation_landscape}
7	
8	\paragraph{Setup.}
9	We evaluate Qwen3-8B~\cite{qwen2025qwen3} under zero-shot greedy decoding on two IE benchmarks:
10	\textbf{SciERC}~\cite{luan2018scierc} (551 test sentences, 7 relations, avg.\ 26.1 valid type pairs per relation) and \textbf{DocRED}~\cite{yao2019docred} (998 dev documents,\footnote{DocRED test set annotations are not publicly available; following prior work, we evaluate on the development set (998 documents).} 96 relations, avg.\ 5.68 valid pairs).
11	We measure four violation categories: \textbf{Domain/Range (DR)} violations where $(\mathrm{type}(h), \mathrm{type}(t)) \notin \sigma(r)$; \textbf{Relation Vocabulary (RV)} where $r \notin \mathcal{R}$; \textbf{Entity Type (ET)} where $e \notin \mathcal{E}$; and \textbf{Cross-Field Consistency (CF)} where the same entity receives different types across triples.
12	Cross-model validation with Llama-3.1-8B-Instruct is reported in \S\ref{sec:cross-model}.
13	
14	\paragraph{Violation distribution.}
15	Table~\ref{tab:prompt_comparison} reports violation rates.
16	DR violations affect 15.37\% of triples on SciERC and 18.46\% on DocRED---comparable rates despite a 14$\times$ difference in ontology size---indicating that violation severity is driven by \emph{constraint tightness} rather than ontology scale.
17	RV violations on DocRED are dramatically higher (29.66\% vs.\ 1.39\%), indicating that 96 relation types exceed the model's capacity to reproduce a target vocabulary from a single prompt.
18	Per-relation rates (Figure~\ref{fig:per_relation_dr}) vary by over 40 percentage points: \textsc{Compare} at 42.4\% vs.\ \textsc{Used-for} at 0.76\%, correlating with tightness---tight constraints (few valid type pairs) produce systematic failures.
19	
20	\begin{table}[t]
21	\centering
22	\caption{Violation rates (\%) under unconstrained and schema-informed prompting (Qwen3-8B, zero-shot).}
23	\label{tab:prompt_comparison}
24	\resizebox{\columnwidth}{!}{%
25	\begin{tabular}{ll cccc}
26	\toprule
27	Dataset & Prompt & DR$\downarrow$ & RV$\downarrow$ & ET$\downarrow$ & CF$\downarrow$ \\
28	\midrule
29	\multirow{2}{*}{SciERC} & Unconstrained & 15.4 & 1.4 & 0.4 & 0.1 \\
30	 & Schema-informed & 5.8 & 0.3 & \textbf{0.0} & --- \\
31	\midrule
32	\multirow{2}{*}{DocRED} & Unconstrained & 18.5 & 29.7 & 2.5 & 0.1 \\
33	 & Schema-informed & 12.8 & 18.4 & 0.2 & 0.2 \\
34	\bottomrule
35	\end{tabular}%
36	}
37	\end{table}
38	
39	\begin{figure}[t]
40	\centering
41	\includegraphics[width=\columnwidth]{figures/fig2_per_relation_dr.pdf}
42	\caption{Per-relation DR violation rates on SciERC. Rates correlate with constraint tightness.}
43	\label{fig:per_relation_dr}
44	\end{figure}
45	
46	\paragraph{Prompt insufficiency.}
47	Schema-informed prompting---augmenting the prompt with valid type pairs---reduces DR by 62.4\% on SciERC but only 30.4\% on DocRED (Table~\ref{tab:prompt_comparison}), and is unreliable per-relation: DR for \textsc{Evaluate-for} \emph{increases} by 5.8\,pp.
48	These limitations motivate decoding-time enforcement (\S\ref{sec:method}).
49	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a2c37f09-9432-4d7b-809a-dc3f031a169b",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "8b918d58-3d4f-4671-bd6c-99ff6d0227fe",
  "sourceToolAssistantUUID": "a2c37f09-9432-4d7b-809a-dc3f031a169b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 56 · 2026-05-16T02:53:15.874Z_

<details open><summary>🔧 Tool call — Read · `toolu_015KrbxYuDTWuS7AM41jyxcH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section5_runtime.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8b918d58-3d4f-4671-bd6c-99ff6d0227fe",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VTg6E4FmhVSBXQAN52",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "02f38ad2-48fd-4949-a653-24b808830c3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UcBsnWnRsrcSn346agujK1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5828,
      "cache_read_input_tokens": 69197,
      "output_tokens": 266,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5828
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 266,
          "cache_read_input_tokens": 69197,
          "cache_creation_input_tokens": 5828,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5828,
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

_source line 57 · 2026-05-16T02:53:15.884Z_

<details><summary>↩ Tool result · `toolu_015KrbxYuDTWuS7AM41jyxcH`</summary>

```text
1	% Section 5 — Runtime Analysis
2	% Data source: artifacts/rebuttal/w3_runtime_report.md
3	% Per-document inference times from JSONL outputs (inference_time_seconds field).
4	% All runs on same single-GPU server (westd-16980), same vLLM/transformers stack.
5	
6	\subsection{Runtime Overhead}
7	\label{sec:runtime}
8	
9	Table~\ref{tab:runtime} reports per-document inference time for each configuration.
10	
11	\begin{table}[t]
12	\centering
13	\small
14	\setlength{\tabcolsep}{4pt}
15	\begin{tabular}{@{}lll rr@{}}
16	\toprule
17	\textbf{Model} & \textbf{Dataset} & \textbf{Mode} & \textbf{Avg (s)} & \textbf{Overhead} \\
18	\midrule
19	\multirow{3}{*}{Qwen}
20	  & \multirow{3}{*}{SciERC}
21	    & Unconstrained & 8.69 & --- \\
22	  & & Grammar       & 8.82 & $+$1.4\% \\
23	  & & Full (S1)     & 6.76 & $-$22.2\% \\
24	\cmidrule(l){2-5}
25	\multirow{2}{*}{}
26	  & \multirow{2}{*}{DocRED}
27	    & Unconstrained & 19.76 & --- \\
28	  & & Full (S1)     & 20.40 & $+$3.2\% \\
29	\midrule
30	\multirow{2}{*}{Llama}
31	  & SciERC
32	    & Unconstrained & 2.81 & --- \\
33	  & & Full (S1)     & 4.33 & $+$53.8\% \\
34	\cmidrule(l){2-5}
35	  & \multirow{2}{*}{DocRED}
36	    & Unconstrained & 18.16 & --- \\
37	  & & Full (S1)     & 20.52 & $+$13.0\% \\
38	\bottomrule
39	\end{tabular}
40	\caption{Per-document inference time (wall-clock seconds, same GPU).
41	Grammar-only overhead is $\leq$4.2\% (Qwen; Llama grammar-only not separately measured).
42	Post-hoc filtering is an $O(n)$ pass over predicted triples and adds negligible time.}
43	\label{tab:runtime}
44	\end{table}
45	
46	Overhead ranges from $-$22\% to $+$54\%, with three of four cells at $\leq$13\%; the outlier (Llama-SciERC, $+$53.8\%) is only $+$1.5\,s absolute.
47	Qwen-SciERC exhibits a \emph{speedup} ($-$22.2\%) because constrained decoding produces tighter outputs, avoiding long noisy continuations before EOS.
48	Grammar-only overhead is $\leq$4.2\% (Qwen), indicating the semantic layer's logit masking accounts for most incremental cost.
49	Llama grammar-only was not separately measured; because the grammar layer uses identical DFA construction across models, Qwen's $\leq$4.2\% provides a reasonable proxy.
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "02f38ad2-48fd-4949-a653-24b808830c3f",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "4228b00d-c5e8-45ca-ba46-e646129fc926",
  "sourceToolAssistantUUID": "02f38ad2-48fd-4949-a653-24b808830c3f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 58 · 2026-05-16T02:53:19.531Z_

Let me also check the bibliography and the dream review reports for context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4228b00d-c5e8-45ca-ba46-e646129fc926",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VU6mHY8je3siKzCw4k",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a4d998c9-a63c-44ea-acbf-5b5d364ffa0d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KYRnkps9RM3TgqvThYNy5F",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3401,
      "cache_read_input_tokens": 75025,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3401,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 59 · 2026-05-16T02:53:20.076Z_

<details open><summary>🔧 Tool call — Read · `toolu_01K2EtKQX7ao4yXjKjKTuiXJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/relwork_new_entries.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a4d998c9-a63c-44ea-acbf-5b5d364ffa0d",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VU6mHY8je3siKzCw4k",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "24bb59f5-c74e-4f4e-8ce1-bfb77746a342",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KYRnkps9RM3TgqvThYNy5F",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3401,
      "cache_read_input_tokens": 75025,
      "output_tokens": 113,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 3401
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 113,
          "cache_read_input_tokens": 75025,
          "cache_creation_input_tokens": 3401,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 3401,
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

_source line 60 · 2026-05-16T02:53:20.088Z_

<details><summary>↩ Tool result · `toolu_01K2EtKQX7ao4yXjKjKTuiXJ`</summary>

```text
1	% ============================================================
2	% Merged authoritative BibTeX references (9 entries)
3	% Merged 2026-05-14 from relwork_new_entries.bib + new_references.bib
4	% ============================================================
5	
6	% Confirmed via: Semantic Scholar, arXiv:2201.11227, OpenReview
7	% Venue: ICLR 2022 (cite key corrected from synchromesh_neurips2022)
8	@inproceedings{synchromesh_iclr2022,
9	  title     = {Synchromesh: Reliable Code Generation from Pre-trained Language Models},
10	  author    = {Poesia, Gabriel and Polozov, Oleksandr and Le, Vu and Tiwari, Ashish and Soares, Gustavo and Meek, Christopher and Gulwani, Sumit},
11	  booktitle = {International Conference on Learning Representations},
12	  year      = {2022},
13	  url       = {https://openreview.net/forum?id=KmtVD97J43e}
14	}
15	
16	% Confirmed via: NeurIPS 2023 proceedings, microsoft/monitors4codegen GitHub
17	@inproceedings{mgd_neurips2023,
18	  title     = {Monitor-Guided Decoding of Code {LMs} with Static Analysis of Repository Context},
19	  author    = {Agrawal, Lakshya A. and Kanade, Aditya and Goyal, Navin and Lahiri, Shuvendu K. and Rajamani, Sriram K.},
20	  booktitle = {Advances in Neural Information Processing Systems},
21	  volume    = {36},
22	  year      = {2023},
23	  url       = {https://proceedings.neurips.cc/paper_files/paper/2023/hash/662b1774ba8845fc1fa3d1fc0177ceeb-Abstract-Conference.html}
24	}
25	
26	% Confirmed via: ACM DL doi:10.1145/3729274, arXiv:2504.09246, SRI Lab ETH
27	@article{pldi2025_type_constrained_codegen,
28	  title     = {Type-Constrained Code Generation with Language Models},
29	  author    = {M\"{u}ndler, Niels and He, Jingxuan and Wang, Hao and Sen, Koushik and Song, Dawn and Vechev, Martin},
30	  journal   = {Proceedings of the ACM on Programming Languages},
31	  volume    = {9},
32	  number    = {PLDI},
33	  year      = {2025},
34	  doi       = {10.1145/3729274},
35	  url       = {https://dl.acm.org/doi/10.1145/3729274}
36	}
37	
38	% Confirmed via: ACL Anthology W04-2401, scottyih.org
39	% WARNING: cite key suggests AAAI 2004, but actual venue is CoNLL 2004 at HLT-NAACL
40	@inproceedings{roth_yih_2004,
41	  title     = {A Linear Programming Formulation for Global Inference in Natural Language Tasks},
42	  author    = {Roth, Dan and Yih, Wen-tau},
43	  booktitle = {Proceedings of the Eighth Conference on Computational Natural Language Learning ({CoNLL}-2004) at {HLT}-{NAACL} 2004},
44	  pages     = {1--8},
45	  year      = {2004},
46	  address   = {Boston, Massachusetts, USA},
47	  url       = {https://aclanthology.org/W04-2401/}
48	}
49	
50	% Confirmed via: ACL Anthology 2023.findings-emnlp.425, zjunlp/AdaKGC GitHub
51	@inproceedings{adakgc_emnlp2023,
52	  title     = {Schema-adaptable Knowledge Graph Construction},
53	  author    = {Ye, Hongbin and Gui, Honghao and Xu, Xin and Chen, Xi and Chen, Huajun and Zhang, Ningyu},
54	  booktitle = {Findings of the Association for Computational Linguistics: {EMNLP} 2023},
55	  pages     = {6408--6431},
56	  year      = {2023},
57	  url       = {https://aclanthology.org/2023.findings-emnlp.425/}
58	}
59	
60	% Confirmed via: ACL Anthology 2024.acl-long.475, arXiv:2403.07969
61	@inproceedings{knowcoder_acl2024,
62	  title     = {{KnowCoder}: Coding Structured Knowledge into {LLMs} for Universal Information Extraction},
63	  author    = {Li, Zixuan and Zeng, Yutao and Zuo, Yuxin and Ren, Weicheng and Liu, Wenxuan and Su, Miao and Guo, Yucan and Liu, Yantao and Li, Xiang and Hu, Zhilei and Bai, Long and Li, Wei and Liu, Yidan and Yang, Pan and Jin, Xiaolong and Guo, Jiafeng and Cheng, Xueqi},
64	  booktitle = {Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
65	  pages     = {8758--8779},
66	  year      = {2024},
67	  address   = {Bangkok, Thailand},
68	  url       = {https://aclanthology.org/2024.acl-long.475/}
69	}
70	
71	% Confirmed via: Oxford Academic Bioinformatics btae104, PubMed 38383067
72	@article{spires_2024,
73	  title     = {Structured Prompt Interrogation and Recursive Extraction of Semantics ({SPIRES}): A Method for Populating Knowledge Bases Using Zero-shot Learning},
74	  author    = {Caufield, J. Harry and Hegde, Harshad and Emonet, Vincent and Harris, Nomi L. and Joachimiak, Marcin P. and Matentzoglu, Nicolas and Kim, HyeongSik and Moxon, Sierra and Reese, Justin T. and Haendel, Melissa A. and Robinson, Peter N. and Mungall, Christopher J.},
75	  journal   = {Bioinformatics},
76	  volume    = {40},
77	  number    = {3},
78	  pages     = {btae104},
79	  year      = {2024},
80	  doi       = {10.1093/bioinformatics/btae104},
81	  url       = {https://academic.oup.com/bioinformatics/article/40/3/btae104/7612230}
82	}
83	
84	% Confirmed via: arXiv:2510.01409, Wiley Advanced Intelligent Systems doi:10.1002/aisy.202501381
85	@misc{ontologx_2025,
86	  title         = {{OntoLogX}: Ontology-Guided Knowledge Graph Extraction from Cybersecurity Logs with Large Language Models},
87	  author        = {Cotti, Luca and Drago, Idilio and Rula, Anisa and Bianchini, Devis and Cerutti, Federico},
88	  year          = {2025},
89	  eprint        = {2510.01409},
90	  archiveprefix = {arXiv},
91	  primaryclass  = {cs.AI},
92	  url           = {https://arxiv.org/abs/2510.01409}
93	}
94	
95	% Confirmed via: Springer LNCS 15370, arXiv:2411.15666, Lama-West GitHub
96	@inproceedings{ekaw2024_ontology_beam,
97	  title     = {Ontology-Constrained Generation of Domain-Specific Clinical Summaries},
98	  author    = {Mehenni, Gaya and Zouaq, Amal},
99	  booktitle = {Knowledge Engineering and Knowledge Management ({EKAW} 2024)},
100	  series    = {Lecture Notes in Computer Science},
101	  volume    = {15370},
102	  pages     = {382--398},
103	  year      = {2024},
104	  publisher = {Springer},
105	  doi       = {10.1007/978-3-031-77792-9_23}
106	}
107	
108	% ============================================================
109	% New entries added 2026-05-14 for §6 related work expansion
110	% ============================================================
111	
112	% Confirmed via: ACL Anthology 2021.emnlp-main.779, arXiv:2109.05093, GitHub ServiceNow/picard
113	@inproceedings{scholak2021picard,
114	  title     = {{PICARD}: Parsing Incrementally for Constrained Auto-Regressive Decoding from Language Models},
115	  author    = {Scholak, Torsten and Schucher, Nathan and Bahdanau, Dzmitry},
116	  booktitle = {Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing},
117	  year      = {2021},
118	  url       = {https://aclanthology.org/2021.emnlp-main.779/}
119	}
120	
121	% Confirmed via: arXiv:2509.19057, ResearchGate, OpenReview gcG8dmAUNh
122	@article{olasunkanmi2025relate,
123	  title   = {{RELATE}: Relation Extraction in Biomedical Abstracts with {LLMs} and Ontology Constraints},
124	  author  = {Olasunkanmi, Olawumi and Satusky, Mathew and Yi, Hong and Bizon, Chris and Lee, Harlin and Ahalt, Stanley},
125	  journal = {arXiv preprint arXiv:2509.19057},
126	  year    = {2025},
127	  url     = {https://arxiv.org/abs/2509.19057}
128	}
129	
130	% Confirmed via: arXiv:2602.03439, University of Cambridge / The World Avatar project
131	@article{zhou2026ontologytools,
132	  title   = {Ontology-to-tools compilation for executable semantic constraint enforcement in {LLM} agents},
133	  author  = {Zhou, Xiaochi and Bulter, Patrick and Yang, Changxuan and Rihm, Simon D. and Angkanaporn, Thitikarn and Akroyd, Jethro and Mosbach, Sebastian and Kraft, Markus},
134	  journal = {arXiv preprint arXiv:2602.03439},
135	  year    = {2026},
136	  url     = {https://arxiv.org/abs/2602.03439}
137	}
138	
139	% Confirmed via: IOS Press ECAI 2020 FAIA vol.325, arXiv:1909.07755, GitHub lavis-nlp/spert
140	@inproceedings{eberts2020spert,
141	  title     = {Span-based Joint Entity and Relation Extraction with Transformer Pre-training},
142	  author    = {Eberts, Markus and Ulges, Adrian},
143	  booktitle = {Proceedings of the 24th European Conference on Artificial Intelligence ({ECAI} 2020)},
144	  series    = {Frontiers in Artificial Intelligence and Applications},
145	  volume    = {325},
146	  pages     = {2006--2013},
147	  year      = {2020},
148	  doi       = {10.3233/FAIA200321}
149	}
150	
151	% Confirmed via: ACL Anthology 2021.emnlp-main.17, arXiv:2108.12202
152	% NOTE: venue is EMNLP 2021 (NOT AAAI 2021)
153	@inproceedings{yan2021pfn,
154	  title     = {A Partition Filter Network for Joint Entity and Relation Extraction},
155	  author    = {Yan, Zhiheng and Zhang, Chong and Fu, Jinlan and Zhang, Qi and Wei, Zhongyu},
156	  booktitle = {Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing},
157	  pages     = {185--197},
158	  year      = {2021},
159	  url       = {https://aclanthology.org/2021.emnlp-main.17/}
160	}
161	
162	% Confirmed via: ACL Anthology 2021.naacl-main.5, GitHub princeton-nlp/PURE
163	@inproceedings{zhong2021frustratingly,
164	  title     = {A Frustratingly Easy Approach for Entity and Relation Extraction},
165	  author    = {Zhong, Zexuan and Chen, Danqi},
166	  booktitle = {Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},
167	  pages     = {50--61},
168	  year      = {2021},
169	  address   = {Online},
170	  publisher = {Association for Computational Linguistics},
171	  url       = {https://aclanthology.org/2021.naacl-main.5}
172	}
173	
174	% Confirmed via: ACL Anthology 2022.acl-long.337, GitHub thunlp/PL-Marker
175	@inproceedings{ye2022packed,
176	  title     = {Packed Levitated Marker for Entity and Relation Extraction},
177	  author    = {Ye, Deming and Lin, Yankai and Li, Peng and Sun, Maosong},
178	  booktitle = {Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
179	  pages     = {4904--4917},
180	  year      = {2022},
181	  address   = {Dublin, Ireland},
182	  publisher = {Association for Computational Linguistics},
183	  url       = {https://aclanthology.org/2022.acl-long.337}
184	}
185	
186	% Confirmed via: arXiv:2604.06066 (previously PENDING AUDIT — now verified)
187	@article{zhou2026snowballing,
188	  title   = {From Hallucination to Structure Snowballing: The Alignment Tax of Constrained Decoding in {LLM} Reflection},
189	  author  = {Zhou, Hongxu},
190	  journal = {arXiv preprint arXiv:2604.06066},
191	  year    = {2026},
192	  url     = {https://arxiv.org/abs/2604.06066}
193	}
194	
195	% ============================================================
196	% Batch 1: Constrained decoding + IE foundations (10 entries)
197	% ============================================================
198	
199	% Confirmed via: arXiv 2411.15100, MLSys 2025 proceedings
200	@inproceedings{dong2025xgrammar,
201	  title     = {{XGrammar}: Flexible and Efficient Structured Generation Engine for Large Language Models},
202	  author    = {Dong, Yixin and Ruan, Charlie F. and Cai, Yaxing and Lai, Ruihang and Xu, Ziyi and Zhao, Yilong and Chen, Tianqi},
203	  booktitle = {Proceedings of Machine Learning and Systems (MLSys)},
204	  year      = {2025},
205	  url       = {https://arxiv.org/abs/2411.15100}
206	}
207	
208	% Confirmed via: arXiv 2307.09702
209	@article{willard2023outlines,
210	  title   = {Efficient Guided Generation for Large Language Models},
211	  author  = {Willard, Brandon T. and Louf, R{\'e}mi},
212	  journal = {arXiv preprint arXiv:2307.09702},
213	  year    = {2023},
214	  url     = {https://arxiv.org/abs/2307.09702}
215	}
216	
217	% Confirmed via: ACM DL 10.1145/3591300, PLDI 2023
218	@inproceedings{beurer-kellner2023lmql,
219	  title     = {Prompting Is Programming: A Query Language for Large Language Models},
220	  author    = {Beurer-Kellner, Luca and Fischer, Marc and Vechev, Martin},
221	  booktitle = {Proceedings of the ACM SIGPLAN Conference on Programming Language Design and Implementation (PLDI)},
222	  year      = {2023},
223	  url       = {https://doi.org/10.1145/3591300}
224	}
225	
226	% Confirmed via: PMLR v235, ICML 2024
227	@inproceedings{beurer-kellner2024domino,
228	  title     = {Guiding {LLMs} The Right Way: Fast, Non-Invasive Constrained Generation},
229	  author    = {Beurer-Kellner, Luca and Fischer, Marc and Vechev, Martin},
230	  booktitle = {Proceedings of the 41st International Conference on Machine Learning (ICML)},
231	  pages     = {3658--3673},
232	  year      = {2024},
233	  series    = {PMLR},
234	  volume    = {235},
235	  url       = {https://proceedings.mlr.press/v235/beurer-kellner24a.html}
236	}
237	
238	% Confirmed via: NeurIPS 2024 proceedings, OpenReview
239	@inproceedings{park2024grammar,
240	  title     = {Grammar-Aligned Decoding},
241	  author    = {Park, Kanghee and Wang, Jiayu and Berg-Kirkpatrick, Taylor and Polikarpova, Nadia and D'Antoni, Loris},
242	  booktitle = {Advances in Neural Information Processing Systems (NeurIPS)},
243	  year      = {2024},
244	  url       = {https://arxiv.org/abs/2405.21047}
245	}
246	
247	% Confirmed via: OpenReview, ICLR 2021
248	@inproceedings{decao2021genre,
249	  title     = {Autoregressive Entity Retrieval},
250	  author    = {De Cao, Nicola and Izacard, Gautier and Riedel, Sebastian and Petroni, Fabio},
251	  booktitle = {International Conference on Learning Representations (ICLR)},
252	  year      = {2021},
253	  url       = {https://openreview.net/forum?id=5k8F6UU39V}
254	}
255	
256	% Confirmed via: ACL Anthology 2022.naacl-main.342
257	@inproceedings{josifoski2022genie,
258	  title     = {{GenIE}: Generative Information Extraction},
259	  author    = {Josifoski, Martin and De Cao, Nicola and Peyrard, Maxime and Petroni, Fabio and West, Robert},
260	  booktitle = {Proceedings of the 2022 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (NAACL)},
261	  pages     = {4626--4643},
262	  year      = {2022},
263	  url       = {https://aclanthology.org/2022.naacl-main.342/}
264	}
265	
266	% Confirmed via: ACL Anthology 2023.emnlp-main.674
267	@inproceedings{geng2023gcd,
268	  title     = {Grammar-Constrained Decoding for Structured {NLP} Tasks without Finetuning},
269	  author    = {Geng, Saibo and Josifoski, Martin and Peyrard, Maxime and West, Robert},
270	  booktitle = {Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
271	  year      = {2023},
272	  url       = {https://aclanthology.org/2023.emnlp-main.674/}
273	}
274	
275	% Confirmed via: ACL Anthology 2021.naacl-main.339
276	@inproceedings{lu2021neurologic,
277	  title     = {{NeuroLogic} Decoding: (Un)supervised Neural Text Generation with Predicate Logic Constraints},
278	  author    = {Lu, Ximing and West, Peter and Zellers, Rowan and Le Bras, Ronan and Bhagavatula, Chandra and Choi, Yejin},
279	  booktitle = {Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (NAACL)},
280	  pages     = {4288--4299},
281	  year      = {2021},
282	  url       = {https://aclanthology.org/2021.naacl-main.339/}
283	}
284	
285	% Confirmed via: ACL Anthology 2022.acl-long.395
286	@inproceedings{lu2022uie,
287	  title     = {Unified Structure Generation for Universal Information Extraction},
288	  author    = {Lu, Yaojie and Liu, Qing and Dai, Dai and Xiao, Xinyan and Lin, Hongyu and Han, Xianpei and Sun, Le and Wu, Hua},
289	  booktitle = {Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},
290	  pages     = {5755--5772},
291	  year      = {2022},
292	  url       = {https://aclanthology.org/2022.acl-long.395/}
293	}
294	
295	% ============================================================
296	% Batch 2: 10 entries added 2026-05-14
297	% ============================================================
298	
299	% Confirmed via: ICLR 2024 proceedings, OpenReview Y3wpuxd7u9, arXiv:2310.03668
300	@inproceedings{sainz2024gollie,
301	  title     = {{GoLLIE}: Annotation Guidelines improve Zero-Shot Information-Extraction Modeling},
302	  author    = {Sainz, Oscar and Garc{\'\i}a-Ferrero, Iker and Agerri, Rodrigo and Lopez de Lacalle, Oier and Rigau, German and Agirre, Eneko},
303	  booktitle = {The Twelfth International Conference on Learning Representations},
304	  year      = {2024},
305	  url       = {https://openreview.net/forum?id=Y3wpuxd7u9}
306	}
307	
308	% Confirmed via: ACL Anthology 2023.acl-long.855, arXiv:2305.05711
309	@inproceedings{li2023codeie,
310	  title     = {{CodeIE}: Large Code Generation Models are Better Few-Shot Information Extractors},
311	  author    = {Li, Peng and Sun, Tianxiang and Tang, Qiong and Yan, Hang and Wu, Yuanbin and Huang, Xuanjing and Qiu, Xipeng},
312	  booktitle = {Proceedings of the 61st Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers)},
313	  pages     = {15339--15353},
314	  year      = {2023},
315	  address   = {Toronto, Canada},
316	  url       = {https://aclanthology.org/2023.acl-long.855/}
317	}
318	
319	% Confirmed via: ACL Anthology 2024.emnlp-main.419, arXiv:2405.05008, GitHub THU-KEG/ADELIE
320	@inproceedings{qi2024adelie,
321	  title     = {{ADELIE}: Aligning Large Language Models on Information Extraction},
322	  author    = {Qi, Yunjia and Peng, Hao and Wang, Xiaozhi and Xu, Bin and Hou, Lei and Li, Juanzi},
323	  booktitle = {Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing},
324	  year      = {2024},
325	  address   = {Miami, Florida, USA},
326	  url       = {https://aclanthology.org/2024.emnlp-main.419/}
327	}
328	
329	% Confirmed via: arXiv:2404.12493, GitHub urchade/EnriCo
330	% NOTE: arXiv preprint; no conference publication found
331	@article{zaratiana2024enrico,
332	  title   = {{EnriCo}: Enriched Representation and Globally Constrained Inference for Entity and Relation Extraction},
333	  author  = {Zaratiana, Urchade and Tomeh, Nadi and Dauxais, Yann and Holat, Pierre and Charnois, Thierry},
334	  journal = {arXiv preprint arXiv:2404.12493},
335	  year    = {2024},
336	  url     = {https://arxiv.org/abs/2404.12493}
337	}
338	
339	% Confirmed via: arXiv:2509.04696, Apple ML Research machinelearning.apple.com/research/odke
340	% NOTE: cite key uses "odke"; actual paper title is "ODKE+"
341	@article{khorshidi2025odke,
342	  title   = {{ODKE+}: Ontology-Guided Open-Domain Knowledge Extraction with {LLMs}},
343	  author  = {Khorshidi, Samira and Nikfarjam, Azadeh and Shankar, Suprita and Sang, Yisi and Govind, Yash and Jang, Hyun and Kasgari, Ali and McClimans, Alexis and Soliman, Mohamed and Konda, Vishnu and Fakhry, Ahmed and Qi, Xiaoguang},
344	  journal = {arXiv preprint arXiv:2509.04696},
345	  year    = {2025},
346	  url     = {https://arxiv.org/abs/2509.04696}
347	}
348	
349	% Confirmed via: ACL Anthology 2023.findings-eacl.95
350	@inproceedings{upadhyay2023openie,
351	  title     = {Open Information Extraction with Entity Focused Constraints},
352	  author    = {Upadhyay, Prajna and Balalau, Oana and Manolescu, Ioana},
353	  booktitle = {Findings of the Association for Computational Linguistics: {EACL} 2023},
354	  year      = {2023},
355	  url       = {https://aclanthology.org/2023.findings-eacl.95/}
356	}
357	
358	% Confirmed via: ACL Anthology 2025.genaik-1.10, GenAIK Workshop at COLING 2025
359	@inproceedings{regino2025kgcurator,
360	  title     = {Can {LLMs} be Knowledge Graph Curators for Validating Triple Insertions?},
361	  author    = {Regino, Andr{\'e} Gomes and dos Reis, Julio Cesar},
362	  booktitle = {Proceedings of the Workshop on Generative {AI} and Knowledge Graphs ({GenAIK})},
363	  pages     = {87--99},
364	  year      = {2025},
365	  address   = {Abu Dhabi, UAE},
366	  url       = {https://aclanthology.org/2025.genaik-1.10/}
367	}
368	
369	% Confirmed via: ACL Anthology 2024.emnlp-industry.91, arXiv:2408.02442
370	@inproceedings{tam2024letmespeak,
371	  title     = {Let Me Speak Freely? {A} Study on the Impact of Format Restrictions on Performance of Large Language Models},
372	  author    = {Tam, Zhi Rui and Wu, Cheng-Kuang and Tsai, Yi-Lin and Lin, Chieh-Yen and Lee, Hung-yi and Chen, Yun-Nung},
373	  booktitle = {Proceedings of the 2024 Conference on Empirical Methods in Natural Language Processing: Industry Track},
374	  pages     = {1218--1236},
375	  year      = {2024},
376	  address   = {Miami, Florida, US},
377	  url       = {https://aclanthology.org/2024.emnlp-industry.91/}
378	}
379	
380	% Confirmed via: PMLR v267/banerjee25a, ICML 2025, arXiv:2502.09061
381	@inproceedings{banerjee2025crane,
382	  title     = {{CRANE}: Reasoning with Constrained {LLM} Generation},
383	  author    = {Banerjee, Debangshu and Suresh, Tarun and Ugare, Shubham and Misailovic, Sasa and Singh, Gagandeep},
384	  booktitle = {Proceedings of the 42nd International Conference on Machine Learning},
385	  pages     = {2836--2857},
386	  year      = {2025},
387	  url       = {https://proceedings.mlr.press/v267/banerjee25a.html}
388	}
389	
390	% Confirmed via: ACL Anthology 2025.ranlp-1.124
391	@inproceedings{schall2025hiddencost,
392	  title     = {The Hidden Cost of Structure: How Constrained Decoding Affects Language Model Performance},
393	  author    = {Schall, Maximilian and de Melo, Gerard},
394	  booktitle = {Proceedings of the 15th International Conference on Recent Advances in Natural Language Processing ({RANLP} 2025)},
395	  year      = {2025},
396	  address   = {Varna, Bulgaria},
397	  url       = {https://aclanthology.org/2025.ranlp-1.124/}
398	}
399	
400	% ============================================================
401	% D015 reviewer-requested references (5 entries)
402	% ============================================================
403	
404	% Confirmed via: GitHub guidance-ai/guidance, Microsoft Research project page
405	@misc{guidance2023,
406	  title        = {Guidance: A Guidance Language for Controlling Large Language Models},
407	  author       = {Lundberg, Scott and Ribeiro, Marco Tulio},
408	  year         = {2023},
409	  url          = {https://github.com/guidance-ai/guidance},
410	  note         = {Microsoft Research}
411	}
412	
413	% Confirmed via: OpenReview US-TP-xnXI, arXiv:2101.05779, Amazon Science
414	@inproceedings{paolini2021tanl,
415	  title     = {Structured Prediction as Translation between Augmented Natural Languages},
416	  author    = {Paolini, Giovanni and Athiwaratkun, Ben and Krone, Jason and Ma, Jie and Achille, Alessandro and Anubhai, Rishita and dos Santos, Cicero Nogueira and Xiang, Bing and Soatto, Stefano},
417	  booktitle = {International Conference on Learning Representations},
418	  year      = {2021},
419	  url       = {https://openreview.net/forum?id=US-TP-xnXI}
420	}
421	
422	% Confirmed via: ACL Anthology 2021.findings-emnlp.204, GitHub Babelscape/rebel
423	@inproceedings{cabot2021rebel,
424	  title     = {{REBEL}: Relation Extraction By End-to-end Language Generation},
425	  author    = {Huguet Cabot, Pere-Llu{\'\i}s and Navigli, Roberto},
426	  booktitle = {Findings of the Association for Computational Linguistics: {EMNLP} 2021},
427	  pages     = {2370--2381},
428	  year      = {2021},
429	  url       = {https://aclanthology.org/2021.findings-emnlp.204/}
430	}
431	
432	% Confirmed via: IJCAI 2016 Proceedings/16/Papers/421, GitHub thunlp/TKRL
433	@inproceedings{xie2016tkrl,
434	  title     = {Representation Learning of Knowledge Graphs with Hierarchical Types},
435	  author    = {Xie, Ruobing and Liu, Zhiyuan and Sun, Maosong},
436	  booktitle = {Proceedings of the 25th International Joint Conference on Artificial Intelligence ({IJCAI})},
437	  pages     = {2965--2971},
438	  year      = {2016},
439	  url       = {https://www.ijcai.org/Proceedings/16/Papers/421.pdf}
440	}
441	
442	% ============================================================
443	% Dataset & model references (5 entries)
444	% ============================================================
445	
446	% Confirmed via: ACL Anthology D18-1360, arXiv:1808.09602
447	@inproceedings{luan2018scierc,
448	  title     = {Multi-Task Identification of Entities, Relations, and Coreference for Scientific Knowledge Graph Construction},
449	  author    = {Luan, Yi and He, Luheng and Ostendorf, Mari and Hajishirzi, Hannaneh},
450	  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},
451	  pages     = {3219--3232},
452	  year      = {2018},
453	  address   = {Brussels, Belgium},
454	  url       = {https://aclanthology.org/D18-1360/}
455	}
456	
457	% Confirmed via: ACL Anthology P19-1074, arXiv:1906.06127
458	@inproceedings{yao2019docred,
459	  title     = {{DocRED}: A Large-Scale Document-Level Relation Extraction Dataset},
460	  author    = {Yao, Yuan and Ye, Deming and Li, Peng and Han, Xu and Lin, Yankai and Liu, Zhenghao and Liu, Zhiyuan and Huang, Lixin and Zhou, Jie and Sun, Maosong},
461	  booktitle = {Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
462	  pages     = {764--777},
463	  year      = {2019},
464	  address   = {Florence, Italy},
465	  url       = {https://aclanthology.org/P19-1074/}
466	}
467	
468	% Confirmed via: arXiv:2302.10205, Semantic Scholar
469	@article{wei2023zeroshot,
470	  title   = {{ChatIE}: Zero-Shot Information Extraction via Chatting with {ChatGPT}},
471	  author  = {Wei, Xiang and Cui, Xingyu and Cheng, Ning and Wang, Xiaobin and Zhang, Xin and Huang, Shen and Xie, Pengjun and Xu, Jinan and Chen, Yufeng and Zhang, Meishan and Jiang, Yong and Han, Wenjuan},
472	  journal = {arXiv preprint arXiv:2302.10205},
473	  year    = {2023},
474	  url     = {https://arxiv.org/abs/2302.10205}
475	}
476	
477	% Confirmed via: arXiv:2505.09388, Hugging Face model cards
478	@article{qwen2025qwen3,
479	  title   = {Qwen3 Technical Report},
480	  author  = {{Qwen Team}},
481	  journal = {arXiv preprint arXiv:2505.09388},
482	  year    = {2025},
483	  url     = {https://arxiv.org/abs/2505.09388}
484	}
485	
486	% Confirmed via: NeurIPS 2024 proceedings, arXiv:2312.07104
487	@inproceedings{zheng2024sglang,
488	  title     = {{SGLang}: Efficient Execution of Structured Language Model Programs},
489	  author    = {Zheng, Lianmin and Yin, Liangsheng and Xie, Zhiqiang and Sun, Chuyue and Huang, Jeff and Yu, Cody Hao and Cao, Shiyi and Kozyrakis, Christos and Stoica, Ion and Gonzalez, Joseph E. and Barrett, Clark and Sheng, Ying},
490	  booktitle = {Advances in Neural Information Processing Systems},
491	  volume    = {37},
492	  year      = {2024},
493	  url       = {https://arxiv.org/abs/2312.07104}
494	}
495	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "24bb59f5-c74e-4f4e-8ce1-bfb77746a342",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "75350d61-8042-4544-a2bf-6f3701b298ae",
  "sourceToolAssistantUUID": "24bb59f5-c74e-4f4e-8ce1-bfb77746a342",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 61 · 2026-05-16T02:53:23.406Z_

Now let me check if there are any dream review reports that provide additional context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "75350d61-8042-4544-a2bf-6f3701b298ae",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VUQdL426mLeU642U2M",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2ce59025-7ddd-4fcf-a9ab-0c510466ca04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WraTT6rQ8WUAfGnvvvodRY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10060,
      "cache_read_input_tokens": 78426,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 10060,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 2,
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

_source line 62 · 2026-05-16T02:53:25.218Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01KqKB17XrsuQQtenkjjCVWq`</summary>

```json
{
  "pattern": "**/dream_reports/**/review_report.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2ce59025-7ddd-4fcf-a9ab-0c510466ca04",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VUQdL426mLeU642U2M",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "dfe9ae9f-2c1b-440d-9163-345314a4c963",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WraTT6rQ8WUAfGnvvvodRY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 10060,
      "cache_read_input_tokens": 78426,
      "output_tokens": 128,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 10060
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 128,
          "cache_read_input_tokens": 78426,
          "cache_creation_input_tokens": 10060,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 10060,
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

_source line 63 · 2026-05-16T02:53:25.235Z_

<details><summary>↩ Tool result · `toolu_01KqKB17XrsuQQtenkjjCVWq`</summary>

```text
artifacts/dream_reports/dream_20260514T094226/median/review_report.md
artifacts/dream_reports/dream_20260514T094226/best/review_report.md
artifacts/dream_reports/dream_20260514T094226/worst/review_report.md
artifacts/dream_reports/dream_20260514T205155/best/review_report.md
artifacts/dream_reports/dream_20260514T205155/median/review_report.md
artifacts/dream_reports/dream_20260514T205155/worst/review_report.md
artifacts/dream_reports/dream_20260516T021434/best/review_report.md
artifacts/dream_reports/dream_20260516T021434/median/review_report.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dfe9ae9f-2c1b-440d-9163-345314a4c963",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "47b1478a-14d9-4616-b015-700d7f016a69",
  "sourceToolAssistantUUID": "dfe9ae9f-2c1b-440d-9163-345314a4c963",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 64 · 2026-05-16T02:53:28.494Z_

<details open><summary>🔧 Tool call — Read · `toolu_015FawYad1tMhj2PWcH9PUDr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/dream_reports/dream_20260516T021434/median/review_report.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "47b1478a-14d9-4616-b015-700d7f016a69",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VUnePzN8CrrYNDveEZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2b2d42e9-0e68-4c55-8ebd-0798673a3c47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MRVZVxp2xJEqjvrX5kmuBu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 323,
      "cache_read_input_tokens": 88486,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 323,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 72,
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

_source line 65 · 2026-05-16T02:53:28.500Z_

<details><summary>↩ Tool result · `toolu_015FawYad1tMhj2PWcH9PUDr`</summary>

```text
1	---
2	dream_id: dream_20260516T021434
3	tier: median
4	overall_score: borderline accept
5	timestamp: 2026-05-16T02:51:02.287617+00:00
6	---
7	
8	# Dream Review Report: OntoCoDec
9	
10	**Paper:** OntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints
11	**Review Mode:** Full (2 Reviewers, 4-step roundtable)
12	**Date:** 2026-05-16
13	
14	---
15	
16	## Consolidated Assessment
17	
18	**Overall Score: 4/6 (Borderline Accept)**
19	**Consensus Confidence: 4/5**
20	
21	Both reviewers independently scored the paper 4/6 (Borderline Accept) with high confidence (4/5). The convergence was strong across nearly all dimensions. The paper makes a genuine empirical contribution (violation landscape study) and provides a competent, thoroughly evaluated system for a real problem. However, technical novelty is limited, scope is narrow, and the CF trade-off partially undermines the core contribution.
22	
23	---
24	
25	## R1 Review: Methods and Experiments (Score: 4/6, Confidence: 4/5)
26	
27	### Summary
28	OntoCoDec proposes a two-layer constrained decoding framework compiling IE ontology schemas into grammar (CFG-based) and semantic (stateful entity registry + dynamic logit masking) constraint layers. The paper provides a systematic violation landscape study, extensive ablations on SciERC and DocRED with two 8B models, bootstrap CIs, post-hoc filtering comparison, and fine-tuning composability experiments. Methodology is generally sound with careful ablation design and honest reporting of trade-offs.
29	
30	### Strengths
31	1. **Comprehensive ablation design.** The five-way ablation (unconstrained, grammar-only, semantic-only, full S1, full S2) cleanly isolates each layer's contribution. The enabling dependency finding — semantic-only achieves only 24% DR reduction while full combination achieves 94% — is well-demonstrated. Grammar-only CF=0.08% vs full S1 CF=9.90% cleanly attributes CF entirely to the semantic layer.
32	
33	2. **Honest framing of limitations.** The CF-DR Pareto analysis (CF fallback pilot: CF 9.90%→0.04% but DR 0.93%→14.78%, total violations +3.99pp) is a rare example of authors conducting experiments that make their method look worse to demonstrate a fundamental tension. The dual-factor explanation (tightness × RV baseline) for the Qwen 44.7% vs Llama 90.2% DR reduction gap is convincing.
34	
35	3. **Statistical methodology is appropriate.** Bootstrap resampling with 10K iterations, per-dataset significance reporting rather than cherry-picking. SciERC F1 reported as "not significant" (p=0.58) while DocRED reported as significant (p<0.001) — methodologically honest.
36	
37	4. **Fine-tuning composability is the strongest experimental contribution.** The 2×2 matrices (ZS/FT × unconstrained/constrained) on both DocRED datasets provide compelling evidence: FT reduces DR from 18–26% to ~0.5–0.8%, OntoCoDec eliminates residual to 0.15–0.32%, with R-F1 loss ≤0.51pp. Per-relation breakdown showing high-tightness relations (P31_instance_of τ=0.98) retaining residual DR post-FT demonstrates "learning-resistant" constraints needing decoding-time enforcement.
38	
39	5. **Cross-model generalization without code modification.** Testing on both Qwen3-8B and Llama-3.1-8B with zero code changes. Different violation profiles (Qwen high-RV/lower-DR vs Llama low-RV/higher-DR) and explanation via orthogonal failure modes adds genuine insight.
40	
41	6. **Non-rectangularity analysis.** Finding that 73/96 DocRED relations have non-rectangular type signatures, and independent enforcement would over-permit 33–37% spurious type pairs, provides principled justification for sequential head→tail masking.
42	
43	### Weaknesses
44	1. **CF trade-off remains the dominant concern (severity: high).** CF violations increase from near-zero to 9.90% on SciERC and up to 12.02% on Llama-DocRED zero-shot. While argued as "softer" than DR, this claim lacks downstream validation. The 245 CF entities on SciERC (7.34% of entity mentions typed inconsistently) would propagate errors in knowledge graph construction. FT regime reduces CF to 0.46–2.00%, which is reassuring, but zero-shot CF is a significant practical limitation.
45	
46	2. **Only two datasets with narrow ontological scope (severity: medium).** Both datasets have exactly 6 entity types — the simplest case for first-token masking. The single-token uniqueness assumption would not hold for ontologies with dozens of entity types or multi-word type names. Two datasets from academic text (SciERC) and Wikipedia (DocRED) do not span critical IE domains (biomedical, legal, financial).
47	
48	3. **Only 8B-class models tested (severity: medium).** Scaling behavior is unknown. Larger models may have fewer baseline violations (reducing OntoCoDec's marginal value). The dual-factor fit (R²=0.886) is based on n=4 data points with 2 parameters — effectively zero degrees of freedom for validation.
49	
50	4. **Zero-shot F1 of ~8% raises practical relevance concerns (severity: medium).** At 8% R-F1, ensuring triples are "type-valid incorrect triples" has questionable real-world value. FT experiments (R-F1 40–45%) address this substantially.
51	
52	5. **Post-hoc filtering comparison is not entirely fair (severity: low-medium).** Post-hoc achieves higher F1 than OntoCoDec on both datasets (DocRED 9.61 vs 8.23). The 48.1% triple rejection rate partly reflects the unconstrained model generating many invalid triples that should be rejected. The trade-off framing is reasonable but application-dependent.
53	
54	6. **Missing Llama SciERC R-F1/E-F1 values in Table 2 (severity: low).** Marked as "—" but appear elsewhere, suggesting incomplete integration.
55	
56	### Questions for Authors
57	1. What is the per-token fallback rate at type-bearing positions on DocRED-Qwen (the worst case)?
58	2. The entity registry assumes entities appear in the entity list before relations. What happens if a relation references an unregistered entity?
59	3. Can you provide more data points for the dual-factor regression beyond n=4?
60	4. Compute cost of the full pipeline (LoRA FT GPU-hours)?
61	
62	---
63	
64	## R2 Review: Novelty and Related Work (Score: 4/6, Confidence: 4/5)
65	
66	### Summary
67	The paper's novelty profile is uneven. The violation landscape study is a genuine first-of-its-kind empirical contribution. The technical approach — grammar-constrained decoding (standard) + semantic logit masking (straightforward hash-map entity registry) — is competent engineering rather than algorithmic innovation. The evaluation thoroughness partially compensates for limited technical depth.
68	
69	### Strengths
70	1. **Well-motivated problem formulation with novel empirical contribution.** The violation landscape study is genuinely the first systematic measurement of ontology type constraint violations in LLM-based IE. Finding that violations are driven by constraint tightness rather than ontology size is non-obvious and practically useful. Counter-intuitive result that schema-informed prompting can *increase* violations for specific relations (Evaluate-for +5.8pp) strengthens the motivation.
71	
72	2. **Extensive and honest related work (in appendix).** Coverage of five paradigms (grammar-constrained decoding, semantic constrained decoding for code, vocabulary/type-constrained generation, post-hoc ontology validation, quality impact of constrained decoding). Differentiation from code generation constrained decoding literature is well-articulated: IE requires a dynamically populated entity registry during generation rather than a fixed schema.
73	
74	3. **Non-trivial layer interaction revealed through ablation.** The enabling dependency is not just claimed but demonstrated: semantic-only achieves only 24% DR reduction. The finding that grammar-only on DocRED *increases* DR (18.46%→26.17%) because grammar forces OOV relations to valid names whose constraints are then violated is a genuinely insightful observation.
75	
76	4. **Composability with fine-tuning.** Demonstrating DR→0% when composed with LoRA on SciERC at effectively zero F1 cost, with CF collapsing from 9.90% to 1.18%, addresses the most natural practical objection ("just fine-tune instead").
77	
78	5. **Pair-based sequential enforcement is technically precise.** Non-rectangularity analysis (73/96 DocRED relations) justifies sequential head→tail masking as genuinely tighter than naive independent enforcement.
79	
80	### Weaknesses
81	1. **Limited technical novelty (severity: high).** The grammar layer is standard XGrammar applied to IE. The semantic layer's core mechanism is a hash map consulted to construct logit masks. The composition (bitwise AND) is straightforward. Novelty rests on the *combination* and *IE-specific application*, placing this in the "well-executed systems paper" category rather than "technical novelty."
82	
83	2. **Decidability taxonomy is superficial (severity: medium).** The three-level classification (local, prefix-decidable, non-local) restates known formal language theory concepts applied to IE constraints. No formal proofs, complexity analysis, or surprising categorizations. These observations would be apparent to anyone with basic formal language theory background.
84	
85	3. **Constraint tightness metric is obvious once stated (severity: low-medium).** τ_r = 1 − |valid_pairs| / |E|² is a natural normalized measure. While usefully predictive, it is not a methodological contribution in itself.
86	
87	4. **Missing critical related work (severity: high).**
88	   - **BoostCD/BoostIE (Zhang et al., EMNLP 2025)**: Combines constrained and unconstrained decoding for closed IE via learned boosting. Directly addresses error complementarity between constrained and unconstrained IE decoding — a finding central to this paper's own analysis.
89	   - **SynCode (Ugare et al., ICML 2024)**: Uses attribute grammars with semantic augmentation for constrained generation. Mechanistically very close to OntoCoDec's grammar + semantic state approach.
90	   - **IterGen (Ugare et al., ICLR 2025)**: Grammar-guided generation with semantic backtracking via KV cache restoration. Provides a more sophisticated alternative to OntoCoDec's graceful degradation (fallback to grammar-only).
91	   - **Classical constrained structured prediction**: CRFs with hard constraints, ILP-based joint NER+RE inference (Roth & Yih 2004 cited but broader tradition inadequately covered).
92	   - **Schema-guided dialogue** (Rastogi et al., AAAI 2020): Constraining generation to schema-valid slot values is a closely related paradigm.
93	
94	5. **Code-to-IE "migration" is simplification, not extension (severity: medium).** Code type systems involve subtyping hierarchies, parametric polymorphism, scope rules. IE ontologies have flat domain/range sets with no inheritance. The paper acknowledges this but should be more explicit that the IE instantiation is significantly less technically challenging than code-domain inspirations.
95	
96	6. **Narrow scope undermines generality claims (severity: medium).** Two datasets with 6 entity types each. First-subword-token uniqueness assumption verified only for these ontologies. For ontologies with dozens/hundreds of entity types, this assumption fails, requiring prefix-tree masking that is "not implemented" (Limitations section).
97	
98	### Questions for Authors
99	1. How does the system handle ontologies with non-unique first subword tokens across entity types?
100	2. Why is BoostCD/BoostIE (EMNLP 2025) not discussed? It directly addresses constrained decoding trade-offs for IE.
101	3. How does OntoCoDec differentiate from SynCode's attribute grammar approach and IterGen's semantic backtracking?
102	4. The net violation count: DR+CF under OntoCoDec S1 on SciERC is ~10.83% vs ~15.45% unconstrained. Given CF is described as "milder," is the 30% relative total-violation improvement the right way to frame the contribution?
103	
104	---
105	
106	## Roundtable Synthesis
107	
108	### Step 2: Cross-Sharing Summary
109	Both reviewers independently arrived at identical scores (4/6) with identical confidence (4/5). Key alignment areas:
110	- Violation landscape study is the strongest novel contribution
111	- FT composability is the most practically significant result
112	- CF trade-off is the dominant concern
113	- Scope is narrow (2 datasets, 6 entity types, 8B models)
114	- Technical novelty is moderate — competent engineering, not algorithmic innovation
115	- Evaluation thoroughness and honest reporting are commendable
116	
117	### Step 3: Convergence
118	
119	**Agreements:**
120	- The paper is above-average in empirical rigor and below-average in technical novelty for a top venue
121	- The violation landscape study fills a genuine gap
122	- The CF-DR trade-off is the most attackable weakness but is honestly disclosed
123	- FT composability is the paper's strongest card for practical significance
124	- Narrow scope (6 entity types, 8B models) limits generalizability claims
125	- The decidability taxonomy adds little value
126	- The constraint tightness metric is useful but not deep
127	
128	**Key Differences:**
129	- R2 provides substantially more detailed missing related work analysis (BoostCD/BoostIE, SynCode, IterGen) — this is a significant gap the paper must address
130	- R1 focuses more on experimental completeness and statistical rigor
131	- R2 is more critical of technical novelty depth ("logit mask with a hash map")
132	
133	### Step 4: Consolidated Recommendation
134	
135	**Score: 4/6 (Borderline Accept)**
136	
137	**Justification:** The paper addresses a real and underexplored problem (ontology type violations in LLM-based IE) with a well-engineered solution backed by thorough evaluation. The violation landscape study is a first-of-its-kind empirical contribution. The FT composability results — demonstrating that OntoCoDec provides a residual compliance guarantee that fine-tuning alone cannot achieve, at negligible F1 cost — represent a genuinely useful practical finding. The paper's honest treatment of the CF trade-off and its limitations is commendable.
138	
139	However, the technical novelty is limited: the individual components (grammar-constrained decoding, logit masking with entity registry) are standard, and the composition is straightforward. The decidability taxonomy adds little. Several important related works are missing (BoostCD/BoostIE, SynCode, IterGen). The scope is narrow — two datasets with only 6 entity types each, and only 8B-class models — which limits the generality of claims about "automatic ontology-to-constraint compilation." The first-token uniqueness assumption is a practical scalability bottleneck.
140	
141	**For acceptance, the paper would need to:**
142	1. Address missing related work (BoostCD/BoostIE, SynCode, IterGen) and clearly differentiate
143	2. Provide downstream validation of the CF-vs-DR severity distinction
144	3. Test on at least one ontology with >10 entity types to validate scalability
145	4. Tone down the decidability taxonomy as a contribution — it's pedagogical, not technical
146	
147	**The paper's strongest path to acceptance** is to foreground the violation landscape study + FT composability as the dual contributions, and position the technical framework as a well-executed instantiation rather than claiming algorithmic novelty.
148	
149	---
150	
151	## Experiment Coverage Assessment
152	
153	All 4 planned experiments from the review context are present in the paper:
154	| Experiment | Paper Location | Status |
155	|---|---|---|
156	| Qwen DocRED FT + OntoCoDec constrained | Table 4, §5.4.1 | ✓ Complete |
157	| Llama DocRED FT + OntoCoDec constrained | Table 6, §5.4.2 | ✓ Complete |
158	| Cross-model composability analysis | Table 8, §5.4.3 | ✓ Complete |
159	| Bootstrap CI for FT composability | Table 9, §5.5 | ✓ Complete |
160	
161	Results align closely with expected values from the experiment design (DR, R-F1, bootstrap CIs all within expected ranges).
162	
163	---
164	
165	## Key Metrics Summary
166	
167	| Config | DR% | R-F1 | CF% | Notes |
168	|---|---|---|---|---|
169	| Qwen SciERC ZS unconstrained | 15.40 | 8.10 | 0.04 | Baseline |
170	| Qwen SciERC ZS + OntoCoDec | 0.93 | 8.23 | 9.90 | ↓94% DR, CF↑ |
171	| Qwen DocRED ZS + OntoCoDec | 10.21 | 8.23 | 2.57 | ↓45% DR |
172	| Llama DocRED ZS + OntoCoDec | 2.55 | 6.27 | 12.02 | ↓90% DR |
173	| Qwen DocRED FT + OntoCoDec | 0.32 | 40.35 | 1.50 | ↓98.3% total DR |
174	| Llama DocRED FT + OntoCoDec | 0.15 | 43.42 | 2.00 | ↓99.4% total DR |
175	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2b2d42e9-0e68-4c55-8ebd-0798673a3c47",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "eeab8aa4-0dba-4e84-b742-13e019394b58",
  "sourceToolAssistantUUID": "2b2d42e9-0e68-4c55-8ebd-0798673a3c47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 66 · 2026-05-16T02:53:29.031Z_

<details open><summary>🔧 Tool call — Read · `toolu_015Yk3QqPdPLhtyySovqFbR2`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/dream_reports/dream_20260516T021434/best/review_report.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "eeab8aa4-0dba-4e84-b742-13e019394b58",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VUnePzN8CrrYNDveEZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a4ee7fff-aaf6-484f-9358-1914b5c9f5e4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MRVZVxp2xJEqjvrX5kmuBu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 323,
      "cache_read_input_tokens": 88486,
      "output_tokens": 193,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 323
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 193,
          "cache_read_input_tokens": 88486,
          "cache_creation_input_tokens": 323,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 323,
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

_source line 67 · 2026-05-16T02:53:29.037Z_

<details><summary>↩ Tool result · `toolu_015Yk3QqPdPLhtyySovqFbR2`</summary>

```text
1	# [Dream Review — best]
2	
3	Status: subprocess exited but no report was submitted
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a4ee7fff-aaf6-484f-9358-1914b5c9f5e4",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "997881c9-c5b9-418f-bfdf-cfbc1bfe3bf3",
  "sourceToolAssistantUUID": "a4ee7fff-aaf6-484f-9358-1914b5c9f5e4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 68 · 2026-05-16T02:53:32.431Z_

Now let me check the appendix discussion for the full picture.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "997881c9-c5b9-418f-bfdf-cfbc1bfe3bf3",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VV4uh9tGM4FQuFQZUm",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4c1fe42a-ca5d-4b61-a62e-a0639ce51a46",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S1aLBViSV28iuEENydh3y1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4926,
      "cache_read_input_tokens": 88809,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4926,
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

_source line 69 · 2026-05-16T02:53:34.046Z_

<details open><summary>🔧 Tool call — Read · `toolu_012Se57mHF9h6rNrQibDG9W2`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4c1fe42a-ca5d-4b61-a62e-a0639ce51a46",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VV4uh9tGM4FQuFQZUm",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "741455e8-c2e8-44ff-a582-7275298be4d5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01S1aLBViSV28iuEENydh3y1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4926,
      "cache_read_input_tokens": 88809,
      "output_tokens": 109,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4926
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 109,
          "cache_read_input_tokens": 88809,
          "cache_creation_input_tokens": 4926,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4926,
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

_source line 70 · 2026-05-16T02:53:34.051Z_

<details><summary>↩ Tool result · `toolu_012Se57mHF9h6rNrQibDG9W2`</summary>

```text
1	% Appendix B — Extended Discussion
2	% Contains discussion paragraphs moved from the main text during compression.
3	
4	\section{Extended Discussion}\label{app:discussion}
5	
6	%%% CF Dual Mechanism %%%
7	% exp_ids: phase2_scierc_full_s1, llama_scierc_full_s1, llama_docred_full_s1
8	
9	\paragraph{CF Dual Mechanism.}
10	CF violations arise from two distinct mechanisms:
11	(1)~\emph{Registry override}: the semantic constraint forces a domain-compatible type that conflicts with the entity's previously registered type.
12	The entity appears in multiple relations with different type requirements, and the per-relation mask selects the locally valid type without consulting prior assignments.
13	(2)~\emph{Grammar-first fallback} (\S\ref{sec:interaction}): when the semantic mask conflicts with all grammar-valid tokens, the semantic layer is dropped entirely, allowing the grammar layer to generate any structurally valid type---which may differ from the entity's registered type.
14	
15	These mechanisms have sharply different model profiles.
16	Qwen3-8B triggers zero grammar-first fallbacks across all experiments, attributing 100\% of its CF violations to registry override.
17	Llama-3.1-8B, by contrast, triggers 5{,}882 fallbacks on SciERC (10.7 per document) and 57{,}825 on DocRED (63.8 per document), making grammar-first fallback the dominant CF source.
18	This asymmetry is consistent with the cross-model CF gap: Qwen achieves CF\,=\,2.57\% on DocRED vs.\ Llama's 12.02\%, despite both using identical constraint configurations.
19	The difference traces to Llama's less calibrated type predictions, which more frequently conflict with the semantic mask's valid set, triggering fallback.
20	
21	%%% Fallback Behavior and Effective Coverage %%%
22	% exp_ids: cf_fallback_ablation_scierc (final data)
23	
24	\paragraph{Fallback Behavior and Effective Coverage.}
25	\label{app:fallback-coverage}
26	The two-layer architecture produces two distinct fallback mechanisms with different semantic consequences.
27	\emph{Grammar-first fallback} (36.6\% of type-bearing positions on SciERC) occurs when $S(t) \cap G(t) = \emptyset$: the semantic layer deactivates as a safety valve, preserving structural validity at the cost of potential type violations---these events account for the residual DR that persists after constraint enforcement.
28	\emph{Registry-consistent fallback} (4.5\%) occurs when the entity's registered type conflicts with domain/range constraints; the system defaults to the registered type for cross-triple consistency.
29	Together, these mechanisms produce the characteristic profile of composable constraint systems: residual DR traces to grammar-first fallback events, while CF violations arise from registry override events where per-relation enforcement assigns conflicting types.
30	
31	We define \emph{effective semantic constraint coverage} as $1 - f_{\text{gf}}$, where $f_{\text{gf}}$ is the grammar-first fallback rate.
32	On SciERC, this yields 63.4\% coverage---at 63.4\% of type-bearing positions, the semantic layer actively constrains generation.
33	This metric directly quantifies the enabling dependency (\S\ref{sec:interaction}): it measures the fraction of decoding steps where both constraint layers are jointly active, providing a fine-grained view beyond aggregate violation rates.
34	Qwen3-8B, with zero grammar-first fallbacks, achieves 100\% effective coverage on SciERC, consistent with its lower residual DR (0.93\% vs.\ Llama's 0.08\%).
35	
36	%%% CF-DR Trade-off Analysis %%%
37	% exp_ids: cf_fallback_ablation_scierc (CF fallback vs full_s1 baseline)
38	
39	\paragraph{CF-DR Trade-off Analysis.}
40	\label{app:cf-dr-tradeoff}
41	
42	CF violations are the most prominent residual limitation of OntoCoDec under zero-shot decoding (9.90\% on SciERC, up to 12.02\% on Llama DocRED).
43	We treat this honestly: per-relation independent enforcement cannot eliminate CF without trading it against DR.
44	Table~\ref{tab:cf-dr-tradeoff} reports a pilot ablation in which we replace the grammar-first fallback with a CF-priority fallback that forces the entity's registered type when it conflicts with $\sigma(r)$.
45	
46	\begin{table}[t]
47	\centering
48	\small
49	\begin{tabular}{@{}l rrrr@{}}
50	\toprule
51	\textbf{Configuration} & \textbf{DR\,(\%)} & \textbf{CF\,(\%)} & \textbf{DR+CF} & \textbf{$f_{\text{gf}}$\,(\%)} \\
52	\midrule
53	Full S1 (baseline) & 0.93 & 9.90 & 10.83 & --- \\
54	CF fallback        & 14.78 & 0.04 & 14.82 & 36.64 \\
55	\midrule
56	$\Delta$ & $+$13.85 & $-$9.86 & $+$3.99 & --- \\
57	\bottomrule
58	\end{tabular}
59	\caption{CF-DR trade-off pilot on SciERC (Qwen3-8B, 551 documents; \texttt{w1\_cf\_fallback\_scierc\_pilot}). CF fallback eliminates CF but re-routes violations to DR, increasing total violations (DR+CF) by 3.99\,pp. $f_{\text{gf}}$: grammar-first fallback rate at type-bearing positions.}
60	\label{tab:cf-dr-tradeoff}
61	\end{table}
62	
63	The CF fallback variant nearly eliminates CF (9.90\%\,$\to$\,0.04\%, $-$9.86\,pp) but at the cost of a 15.9$\times$ increase in DR (0.93\%\,$\to$\,14.78\%, $+$13.85\,pp).
64	% exp_id: w1_cf_fallback_scierc_pilot: DR=0.1478, CF=0.0004, f_gf=0.3664
65	This is not a net improvement: total violations (DR+CF) rise from 10.83\% to 14.82\% ($+$3.99\,pp), so the change \emph{re-routes} violations rather than reducing them.
66	The mechanism is mechanical: each token position with conflicting masks must commit to one violation type; when the CF fallback forces the system to emit the entity's registered type even though it lies outside $\sigma(r)$, the resulting triple satisfies cross-entity consistency but violates domain/range.
67	The grammar-first fallback is triggered at 36.64\% of type-bearing positions, indicating that this conflict is structural, not a tunable hyperparameter.
68	
69	We interpret this as a fundamental tension in composable constraint systems with \emph{per-relation independent} enforcement: enforcement priority can be allocated between DR and CF but cannot independently minimize both.
70	Within this design, the current full S1 configuration sits near the Pareto frontier of the trade-off, achieving 0.93\% DR at the cost of 9.90\% CF.
71	The CF residual is concentrated in schema ambiguity rather than enforcement failure: 63.3\% of CF violations on SciERC involve the catch-all \textsc{Generic} type (Table~\ref{tab:cf-distribution}), which competes with every content type depending on anaphoric vs.\ referential use---a distinction the per-slot decoder cannot resolve without document-level coreference.
72	
73	Two complementary paths can lower CF without re-routing it to DR.
74	(i)~\emph{Reduce the baseline conflict rate.} Composing OntoCoDec with LoRA fine-tuning on SciERC reduces CF by 88\% relative to the zero-shot setting (9.90\%\,$\to$\,1.18\%; Table~\ref{tab:composability}), because the fine-tuned model's per-slot type predictions agree more often with the entity registry, so the per-relation mask and the registry intersect more frequently.
75	% exp_id: w5_lora_scierc_constrained_eval: CF=0.0118
76	The remaining 1.18\% still traces to \textsc{Generic}$\leftrightarrow$X schema ambiguity, so this path is empirically validated on one dataset and one fine-tuning method but does not generalize without further evidence.
77	(ii)~\emph{Replace per-relation enforcement with global entity-level type consensus during decoding.} This is outside the scope of OntoCoDec's forward-only autoregressive design and is left to future work.
78	
79	%%% Dual-Factor Quantitative Analysis %%%
80	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1,
81	%          llama_scierc_full_s1, llama_docred_full_s1
82	
83	\paragraph{Dual-Factor Quantitative Analysis.}
84	\label{app:dual-factor}
85	
86	Figure~\ref{fig:dual-factor-scatter} plots residual DR against the product $\bar{\tau} \times \text{RV}_{\text{baseline}}$ for all four model$\times$dataset configurations.
87	A linear fit yields $y = 0.366x - 0.138$ with $R^2 = 0.886$ ($n{=}4$; we do not report a $p$-value given the small sample size).
88	The strong fit is consistent with the dual-factor pattern described in \S\ref{sec:composition}: configurations with higher tightness and higher baseline violation rate exhibit proportionally higher residual DR after constraint enforcement.
89	The two DocRED points (high $\bar{\tau}{=}0.842$) separate cleanly from the two SciERC points (low $\bar{\tau}{=}0.333$), and within each dataset the model with higher baseline RV shows higher residual DR.
90	
91	\begin{figure}[t]
92	\centering
93	\includegraphics[width=0.75\columnwidth]{figures/dual_factor_scatter.pdf}
94	\caption{Residual DR vs.\ $\bar{\tau} \times \text{RV}_{\text{baseline}}$ across four model$\times$dataset configurations.
95	Linear fit: $y = 0.366x - 0.138$, $R^2 = 0.886$.}
96	\label{fig:dual-factor-scatter}
97	\end{figure}
98	
99	%%% Dataset-Dependent F1 Impact (moved from §7) %%%
100	% exp_ids: d012_bootstrap_ci (DocRED +0.50pp p<0.001, SciERC +0.13pp p=0.58),
101	%          phase0_docred_unconstrained (RV=29.66%), phase0_scierc_unconstrained (RV=1.39%)
102	
103	\paragraph{Dataset-Dependent F1 Impact.}
104	The divergence in F1 significance between DocRED ($+$0.50\,pp, $p < 0.001$) and SciERC ($+$0.13\,pp, $p = 0.58$) traces to a single mechanism: grammar-layer elimination of out-of-vocabulary relation names.
105	DocRED's baseline RV of 29.66\% produces 5{,}189 OOV predictions counted as false positives; eliminating them yields a significant precision gain.
106	SciERC's baseline RV is only 1.39\% (24 OOV predictions), too few to produce a detectable F1 effect.
107	Llama-3.1-8B's lower baseline RV (16.03\%) yields a smaller but directionally consistent improvement ($+$0.29\,pp vs.\ $+$0.50\,pp), confirming that F1 gain magnitude is proportional to baseline OOV rate.
108	% exp_ids: phase0_docred_unconstrained, phase0_scierc_unconstrained
109	% exp_ids: llama_docred_unconstrained (RV=16.03%), llama_docred_full_s1 (R-F1 delta=+0.29pp)
110	
111	%%% Paragraph 1: Low F1 Practical Significance %%%
112	% exp_ids: phase2_scierc_full_s1 (R-F1=8.36%), phase2_docred_full_s1 (R-F1=8.23%),
113	%          phase0_scierc_unconstrained (DR=15.37%), phase2_docred_unconstrained (DR=18.46%)
114	
115	\paragraph{Practical Significance of Zero-Shot F1.}
116	Our reported relation F1 of approximately 8\% on both SciERC and DocRED reflects the inherent difficulty of zero-shot closed IE, where the model receives no task-specific training examples.
117	For reference, supervised state-of-the-art systems on SciERC achieve approximately 49--53\% relation F1 with full training data~\citep{zhong2021frustratingly,ye2022packed}.
118	Constraint enforcement operates largely independently of the extraction model's intrinsic capability: it restricts the output space to ontologically valid triples regardless of the underlying model's accuracy.
119	When applied to fine-tuned models that reach competitive F1 levels, the same constraints remain necessary---Phase~0 analysis confirms that even well-prompted models exhibit non-trivial violation rates (15.37\% DR on SciERC, 18.46\% on DocRED).
120	% exp_ids: phase0_scierc_unconstrained, phase2_docred_unconstrained
121	In our evaluation, F1 serves as a \emph{control variable} verifying that constraint enforcement does not degrade extraction quality, not as an optimization target.
122	The contribution of this work is the constraint enforcement method itself; the zero-shot setting isolates its effect from confounds introduced by task-specific fine-tuning.
123	
124	%%% Paragraph 4: Decoding-Time vs. Post-Hoc Enforcement %%%
125	% exp_ids: posthoc_filtering_baseline, phase2_scierc_full_s1 (R-F1=8.36%),
126	%          phase2_docred_full_s1 (R-F1=8.23%, ET=0%)
127	
128	\paragraph{Decoding-Time vs.\ Post-Hoc Enforcement.}
129	Post-hoc filtering---generating triples without constraints, then removing schema-violating predictions---yields higher precision and consequently higher F1 than OntoCoDec on both datasets (SciERC 8.63 vs.\ 8.36; DocRED 9.61 vs.\ 8.23).
130	% posthoc: SciERC F1=8.63, DocRED F1=9.61; OntoCoDec: SciERC R-F1=8.36, DocRED R-F1=8.23
131	However, this precision gain comes at substantial cost.
132	On DocRED, post-hoc filtering discards 48.1\% of all predicted triples, including 127 true positives (11.2\% of correct predictions), reducing recall from 9.46\% to 8.40\%.
133	% posthoc_docred: rejection=48.1%, tp_lost=127/1137, R: 9.46→8.40
134	Entity type violations remain unresolved (ET\,=\,2.47\% vs.\ OntoCoDec's 0\%), as filtering targets only domain/range and vocabulary violations.
135	% posthoc_docred: ET_residual=2.47%; phase2_docred_full_s1: ET=0%
136	OntoCoDec's decoding-time approach avoids this information loss by guiding generation toward compliant outputs rather than discarding non-compliant ones, preserving both recall and entity type validity.
137	The two strategies are complementary: post-hoc filtering can serve as an additional safety net for residual violations that decoding-time enforcement does not fully resolve.
138	
139	%%% CF Violation Distribution %%%
140	% exp_ids: phase2_scierc_full_s1 (CF=245), llama_scierc_full_s1 (CF=162),
141	%          phase2_docred_full_s1 (CF=2670), llama_docred_full_s1 (CF=3824)
142	
143	\paragraph{Cross-Field Violation Distribution.}
144	\label{app:cf-distribution}
145	
146	Table~\ref{tab:cf-distribution} reports the complete distribution of conflicting-type pairs for SciERC full S1 (245 CF violations, all pairwise---no mention triggered $\geq$3 types).
147	Conflicts involving the \textsc{Generic} type account for 63.3\% (155/245) of all violations.
148	\textsc{Generic} is SciERC's anaphoric/placeholder label (``this approach'', ``the method''), which competes with every content type depending on whether the mention is used anaphorically or referentially---a distinction the per-slot constrained decoder cannot resolve without document-level coreference.
149	
150	The pattern generalizes across models and datasets: on Llama-3.1-8B SciERC, \textsc{Generic}$\leftrightarrow$\textsc{OtherScientificTerm} remains the top pair (53/162, 32.7\%); on DocRED, the analogous catch-all type \textsc{MISC} drives 76.6\% of Qwen's CF violations.
151	Under unconstrained decoding, CF rates collapse to $\leq$1\% on both datasets, confirming that CF violations are a side-effect of per-slot type commitment rather than a model deficiency.
152	
153	\begin{table}[t]
154	\centering
155	\small
156	\begin{tabular}{@{}lr r@{}}
157	\toprule
158	\textbf{Conflicting Type Pair} & \textbf{Count} & \textbf{\%} \\
159	\midrule
160	Generic $\leftrightarrow$ OtherScientificTerm & 85 & 34.7 \\
161	Generic $\leftrightarrow$ Material & 35 & 14.3 \\
162	Generic $\leftrightarrow$ Metric & 30 & 12.2 \\
163	Method $\leftrightarrow$ Task & 20 & 8.2 \\
164	Material $\leftrightarrow$ Method & 17 & 6.9 \\
165	OtherScientificTerm $\leftrightarrow$ Task & 12 & 4.9 \\
166	\midrule
167	10 further pairs (each $\leq$3.3\%) & 46 & 18.8 \\
168	\midrule
169	\textbf{Total} & \textbf{245} & 100.0 \\
170	\bottomrule
171	\end{tabular}
172	\caption{CF violation distribution on SciERC full S1 (Qwen3-8B, 551 documents).
173	All 245 violations are pairwise conflicts.
174	Conflicts involving \textsc{Generic} account for 63.3\%.}
175	\label{tab:cf-distribution}
176	\end{table}
177	
178	%%% Per-Relation DR Elimination under Fine-Tuning %%%
179	% exp_ids: lora_scierc_unconstrained, lora_scierc_full_s1
180	
181	\paragraph{Per-Relation DR Elimination under Fine-Tuning.}
182	\label{app:lora-per-relation}
183	
184	Table~\ref{tab:lora-per-relation} presents the per-relation breakdown of DR elimination when OntoCoDec is composed with LoRA fine-tuning on SciERC.
185	Fine-tuning alone eliminates DR on four of seven relations but leaves non-zero violations on the three tightest-constraint relations: \textsc{Evaluate-for} ($\tau{=}0.361$, 13.13\%), \textsc{Part-of} ($\tau{=}0.417$, 5.77\%), and \textsc{Compare} ($\tau{=}0.528$, 5.00\%).
186	Adding OntoCoDec constraints eliminates all remaining violations across all relations.
187	One \textsc{Evaluate-for} triple (99\,$\to$\,98) is redirected to \textsc{Used-for} (634\,$\to$\,635) by token-level masking: the head entity's registered type falls outside \textsc{Evaluate-for}'s domain, and the semantic mask steers generation to the nearest valid relation.
188	
189	\begin{table}[t]
190	\centering
191	\small
192	\begin{tabular}{@{}l r rr rr@{}}
193	\toprule
194	& & \multicolumn{2}{c}{\textbf{LoRA Unconstr.}} & \multicolumn{2}{c}{\textbf{LoRA + S1}} \\
195	\cmidrule(lr){3-4} \cmidrule(l){5-6}
196	\textbf{Relation} & $\tau$ & DR\,(\%) & $n$ & DR\,(\%) & $n$ \\
197	\midrule
198	Evaluate-for & 0.361 & 13.13 & 99 & \textbf{0} & 98 \\
199	Part-of      & 0.417 & 5.77  & 52 & \textbf{0} & 52 \\
200	Compare      & 0.528 & 5.00  & 40 & \textbf{0} & 40 \\
201	Conjunction  & 0.306 & 1.31  & 153 & \textbf{0} & 153 \\
202	Feature-of   & 0.278 & 1.35  & 74 & \textbf{0} & 74 \\
203	Used-for     & 0.028 & 0.16  & 634 & \textbf{0} & 635 \\
204	Hyponym-of   & 0.417 & 0     & --- & \textbf{0} & --- \\
205	\bottomrule
206	\end{tabular}
207	\caption{Per-relation DR elimination on SciERC with LoRA fine-tuning (Qwen3-8B).
208	$\tau$: constraint tightness; $n$: predicted triple count.
209	Used-for gains one triple from Evaluate-for redirection.}
210	\label{tab:lora-per-relation}
211	\end{table}
212	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "741455e8-c2e8-44ff-a582-7275298be4d5",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "3feb49d5-af65-45b6-ae64-d3bcaabd0507",
  "sourceToolAssistantUUID": "741455e8-c2e8-44ff-a582-7275298be4d5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 71 · 2026-05-16T02:53:38.148Z_

I now have a comprehensive understanding of the paper. Let me also check if there's a "Constraint ROI" metric mentioned in the paper (referenced in the review prompt).

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3feb49d5-af65-45b6-ae64-d3bcaabd0507",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VVSTVPJvERTzPN6Syt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c77f797e-7fe9-4343-87f6-3cfa27562b04",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EwxSmxHpCyo1ywTtwWMkPK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6094,
      "cache_read_input_tokens": 93735,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6094,
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

_source line 72 · 2026-05-16T02:53:41.855Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01Lq4uyMVxRevrYgLLAWPjNJ`</summary>

```json
{
  "pattern": "ROI|constraint ROI|Constraint ROI",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c77f797e-7fe9-4343-87f6-3cfa27562b04",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VVSTVPJvERTzPN6Syt",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4cca8d14-00a6-435d-a0cd-da10a32f8e92",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EwxSmxHpCyo1ywTtwWMkPK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6094,
      "cache_read_input_tokens": 93735,
      "output_tokens": 170,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6094
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 170,
          "cache_read_input_tokens": 93735,
          "cache_creation_input_tokens": 6094,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6094,
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

_source line 73 · 2026-05-16T02:53:41.877Z_

<details><summary>↩ Tool result · `toolu_01Lq4uyMVxRevrYgLLAWPjNJ`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4cca8d14-00a6-435d-a0cd-da10a32f8e92",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "9ed5e1ae-f426-4a03-af82-168d6b44e316",
  "sourceToolAssistantUUID": "4cca8d14-00a6-435d-a0cd-da10a32f8e92",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 74 · 2026-05-16T02:53:46.228Z_

The "Constraint ROI" metric mentioned in the review prompt does not appear in the actual paper. Let me now prepare the review. Let me also verify one more thing -- the paper's claim of being "first to compile ontology constraints into decoding masks."

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9ed5e1ae-f426-4a03-af82-168d6b44e316",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VW1hVS8k3yt3nFcfXa",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9ddfb0aa-9176-4a51-98e8-42dd3b570238",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011bYfCgyg3SR6ah46PropcD",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 288,
      "cache_read_input_tokens": 99829,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 288,
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

_source line 75 · 2026-05-16T02:53:47.477Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01UPqCNAojB9WYdHCBncaJsA`</summary>

```json
{
  "pattern": "first to|first system|first work|novel|novelty",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper",
  "output_mode": "content",
  "-i": true,
  "head_limit": 30
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9ddfb0aa-9176-4a51-98e8-42dd3b570238",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VW1hVS8k3yt3nFcfXa",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7e01e4e4-cc8a-4883-85d6-af324600d8ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011bYfCgyg3SR6ah46PropcD",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 288,
      "cache_read_input_tokens": 99829,
      "output_tokens": 227,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 288
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 227,
          "cache_read_input_tokens": 99829,
          "cache_creation_input_tokens": 288,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 288,
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

_source line 76 · 2026-05-16T02:53:47.498Z_

<details><summary>↩ Tool result · `toolu_01UPqCNAojB9WYdHCBncaJsA`</summary>

```text
artifacts/_project/paper/section1_introduction_draft.tex:25:    \item The first systematic study of ontological constraint violations in LLM-based IE (spanning per-relation tightness analysis, dual-factor characterization, and post-hoc baseline comparison), showing that violation rates are driven by constraint tightness rather than ontology size, and that prompt-level intervention is per-relation unreliable.
artifacts/_project/paper/section1_introduction_draft.tex:26:    \item OntoCoDec, a two-layer compiled constraint framework that enforces cross-field type validity during autoregressive IE---the first to automatically compile IE ontology domain/range constraints into token-level semantic masks.
artifacts/_project/paper/appendix_related_work.tex:33:OntoCoDec is the first to \emph{automatically compile} IE ontology axioms---including domain/range constraints---into token-level decoding masks for information extraction, migrating the type-constrained decoding paradigm from code generation to IE.
artifacts/_project/paper/appendix_related_work.tex:97:However, information extraction occupies a fundamentally different regime: the model extracts entities and relations from input text rather than generating novel reasoning chains, and \citet{tam2024letmespeak}'s own results show that extraction-style tasks are robust to---or even benefit from---format constraints.
artifacts/_project/paper/appendix_related_work.tex:106:OntoCoDec occupies a unique position in this landscape: it is the first system to \emph{automatically compile} IE ontology schemas---including domain/range axioms---into token-level semantic masks, extending grammar-constrained decoding from syntactic to semantic enforcement without manually authored rules.
artifacts/_project/paper/section6_relwork_outline.tex:34:\textbf{Distinction:} These methods demonstrate that semantic (type) constraints at decode time are both feasible and highly effective---but exclusively in the code domain, where type systems are formally specified. OntoCoDec is the first to migrate this paradigm to information extraction, compiling IE ontology axioms (domain/range constraints) into an analogous decoding-time enforcement mechanism.
artifacts/_project/paper/section6_relwork_outline.tex:131:OntoCoDec occupies a unique position in this landscape: it is the first system to automatically compile IE ontology schemas---including domain/range axioms---into decoding-time semantic constraints, extending grammar-constrained decoding from syntactic to semantic enforcement.
artifacts/_project/paper/section7_conclusion_550cbf.tex:10:First, we conducted the first systematic study of ontological constraint violations in LLM-based IE (\S\ref{sec:violation_landscape}).
artifacts/_project/paper/section7_conclusion.tex:10:First, we conducted the first systematic study of ontological constraint violations in LLM-based IE (\S\ref{sec:violation_landscape}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7e01e4e4-cc8a-4883-85d6-af324600d8ca",
  "isSidechain": true,
  "promptId": "75113fbb-880f-4c1a-9f36-91734fa9d04b",
  "agentId": "a77dd280799b6b550",
  "type": "user",
  "uuid": "c2ec43ab-28dc-4c2c-91a3-57046908f279",
  "sourceToolAssistantUUID": "7e01e4e4-cc8a-4883-85d6-af324600d8ca",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 77 · 2026-05-16T02:55:23.778Z_

Now I have all the information needed. Let me now submit the review via the dream review report tool, as this is a review task.

Looking at the task description again, this is a direct review request, not a dream review submission. Let me provide the review directly.

---

## R2 Review: Novelty and Related Work

**Paper:** OntoCoDec: Type-Constrained Information Extraction via Compiled Ontology Constraints

---

### 1. Summary

OntoCoDec compiles IE ontology schemas into two composable decoding constraint layers -- a grammar layer (XGrammar-based CFG) enforcing JSON structure and vocabulary membership, and a semantic layer using a stateful entity registry with dynamic logit masking to enforce domain/range type constraints. The paper provides a systematic violation landscape study showing 15-19% domain/range violation rates in LLM-based IE, then demonstrates 45-99% DR reduction across 2 models x 2 datasets with F1-neutral or positive impact, and shows composability with LoRA fine-tuning on SciERC (DR to 0% at negligible F1 cost). A CF violation trade-off (up to 12%) is honestly disclosed as a systematic limitation.

---

### 2. Strengths

- **Genuine empirical contribution in the violation landscape study.** The systematic measurement of ontology type constraint violations in LLM-based IE is, to my knowledge, novel. The finding that violation rates correlate with constraint tightness rather than ontology size is non-obvious and practically useful. The counter-intuitive observation that schema-informed prompting *increases* violations on Evaluate-for (+5.8pp) provides strong motivation for decoding-time enforcement.

- **Well-articulated differentiation from code-domain constrained decoding.** The paper correctly identifies that the key technical difference from PICARD/Synchromesh/PLDI'25 type-constrained codegen is that IE requires a *dynamically populated* entity registry during generation (entities extracted from free text) rather than querying a fixed, pre-declared schema. This is a genuine and important distinction.

- **Thorough related work in the appendix.** The extended related work covers five distinct paradigms with 42+ references, including recent work (CRANE ICML 2025, PLDI'25 type-constrained codegen, OntoLogX 2025). The differentiation is generally clear and well-argued.

- **Non-rectangularity analysis provides principled justification.** Finding that 0/7 SciERC and 73/96 DocRED relations have non-rectangular type signatures, with independent enforcement over-permitting 33-37% spurious type pairs, gives principled motivation for the sequential head-then-tail masking strategy. This is a small but solid technical contribution.

- **FT composability is the strongest finding.** The 2x2 matrices (ZS/FT x unconstrained/constrained) on SciERC with two models demonstrate that fine-tuning and constrained decoding address orthogonal failure modes: fine-tuning eliminates most violations but leaves learning-resistant tight-constraint relations (Evaluate-for retains 13.13% DR); OntoCoDec eliminates the residual. CF drops from ~10% to ~1%. This is the most convincing argument for the method's practical value.

- **Honest disclosure of trade-offs.** The CF-DR Pareto analysis, the R^2=0.886 regression on n=4 points without claiming statistical significance, and the per-relation Evaluate-for counterexample are examples of unusually honest scientific reporting.

---

### 3. Weaknesses

- **Limited technical novelty (high severity).** The grammar layer is a direct application of XGrammar to IE -- no algorithmic contribution. The semantic layer's core mechanism is a hash-map entity registry consulted to construct logit masks -- a straightforward engineering decision. The composition (bitwise AND with fallback) is simple. The decidability taxonomy (local / prefix-decidable / non-local) restates basic formal language theory concepts without proofs, complexity analysis, or surprising categorizations. The paper's novelty rests on the combination and IE-specific application, placing it in the "well-executed systems paper" category. For a top venue like EMNLP, this is a concern.

- **The "first to compile IE ontology constraints into decoding masks" claim is overclaimed (high severity).** Several closely related systems deserve discussion:
  - **SynCode (Ugare et al., ICML 2024)** uses attribute grammars with semantic augmentation for constrained generation -- mechanistically very close to OntoCoDec's grammar + semantic state approach. The paper does not cite or differentiate from it.
  - **IterGen (Ugare et al., ICLR 2025)** provides grammar-guided generation with semantic backtracking via KV cache restoration -- a more sophisticated approach to the same fallback problem OntoCoDec addresses with grammar-first degradation.
  - **EnriCo (cited but insufficiently discussed)** applies ASP constraints during joint entity-relation decoding, enforcing structural type compatibility at generation time. The paper dismisses it as "model-specific, manually authored" but does not adequately compare the enforcement mechanisms.
  - **GCD (Geng et al., EMNLP 2023, cited)** already applies grammar-constrained decoding to IE with input-dependent grammars. The paper's claim of being "first" to compile ontology constraints into decoding masks needs more careful qualification relative to GCD.
  - **GenIE (Josifoski et al., NAACL 2022, cited)** implements state-based constraints for end-to-end IE that enforce valid triple structures. While it requires fine-tuning, the constrained decoding mechanism shares significant overlap.
  - The paper does not discuss **Schema-Guided Dialogue** (Rastogi et al., AAAI 2020), where constraining generation to schema-valid slot values is a closely related paradigm.

- **Constraint tightness metric is trivial (medium severity).** The metric tau(r) = 1 - |valid_pairs| / |E|^2 is the most obvious normalization one could write. While usefully predictive, calling it a "contribution" is a stretch. The dual-factor regression (R^2=0.886 on n=4 points with 2 parameters) has effectively zero degrees of freedom for validation -- it is a line fit through 4 points with 2 free parameters, which will always fit well. The paper is honest about not reporting a p-value, but this still weakens the "predictive" framing.

- **Narrow ontological scope undermines generality claims (medium severity).** Both ontologies have exactly 6 entity types. The single-first-subword-token uniqueness assumption is verified only for these tiny type vocabularies. The Limitations section acknowledges that "prefix-tree masking" would be needed for ontologies with many types or multi-token type names but states it is "not implemented." For a paper claiming to provide "automatic ontology-to-constraint compilation," this is a significant scope limitation. Biomedical ontologies (hundreds of entity types), legal ontologies, etc. are the domains where such constraints are most needed -- and precisely where the current implementation would not work.

- **The "Constraint ROI" metric mentioned in the framing documents does not appear in the paper.** This was apparently dropped, which is fine, but it means the paper's analytical toolkit (tightness, dual-factor) is thin.

- **The paper's identity is ambiguous (medium severity).** Is this a method paper or an analysis paper? The violation landscape study and the dual-factor characterization are empirical analysis contributions. The OntoCoDec framework is a systems/engineering contribution. The composability finding is an experimental insight. The paper tries to be all three, which dilutes the novelty claim for each. If positioned primarily as an empirical analysis paper ("what happens when you enforce ontology constraints during IE decoding, and why?"), the novelty bar would be easier to clear. If positioned as a method paper, the technical contribution is insufficient for a top venue.

- **Code-to-IE migration is a simplification, not an extension (low-medium severity).** The paper acknowledges that code type systems involve "deep subtyping hierarchies and parametric polymorphism" while IE ontologies have "flat domain/range sets." This means OntoCoDec's type system is strictly simpler than what PLDI'25 handles. The paper frames this as "migrating the paradigm to IE," but a more accurate framing would be "applying a simplified version of known techniques to a new domain." The genuinely novel aspect -- the dynamically populated entity registry -- is the one element that goes beyond the code analogs, and it deserves more technical depth.

---

### 4. Questions for Authors

1. How does OntoCoDec differentiate from SynCode's attribute grammar approach? SynCode also augments grammar constraints with semantic state -- why is it not cited?

2. How would the system handle an ontology with 50+ entity types where multiple types share the same first subword token? The paper acknowledges this limitation but does not quantify how common this scenario is across standard IE ontologies.

3. The dual-factor regression has n=4 data points and 2 parameters. Can you provide additional data points (e.g., from per-relation analysis, or from subsets of DocRED with different tightness profiles) to validate the relationship with more statistical power?

4. The enabling dependency finding (semantic-only achieves only 24% DR reduction) -- is this because the semantic layer genuinely cannot function without grammar-enforced vocabulary, or because the semantic-only implementation simply does not handle OOV relation names gracefully? If the latter, a more robust semantic-only implementation could potentially achieve higher DR reduction independently.

5. What is the total inference-time computational overhead of the full pipeline (grammar + semantic) compared to unconstrained generation, measured in tokens/second rather than wall-clock time per document?

6. The CF-DR Pareto analysis shows the current S1 is near-optimal under the per-relation independent enforcement design. Have you considered any relaxation of this independence assumption short of full global entity consensus (e.g., a sliding window of N most recent entity assignments)?

---

### 5. Novelty Assessment

**(a) Grammar + semantic layer composition:** Low novelty. Combining grammar-constrained decoding with an additional semantic filtering layer via bitwise AND is a straightforward extension. The enabling dependency finding (semantic needs grammar) is an interesting empirical observation but not a technical contribution. SynCode and IterGen already explore similar grammar+semantic compositions in other domains.

**(b) Constraint tightness metric:** Minimal novelty. It is the most obvious normalization. Useful as descriptive shorthand but not a methodological contribution.

**(c) Regime-dependent composability analysis (ZS vs. FT):** Moderate novelty. This is the paper's strongest novelty claim. The finding that fine-tuning eliminates most violations but leaves a learning-resistant tail of tight-constraint relations, which constrained decoding can precisely target, is a genuinely useful and non-obvious insight. The 2x2 matrices across two models provide convincing evidence.

**(d) Dual-factor pattern (tightness x RV baseline):** Low-to-moderate novelty. The observation is sensible but based on n=4 points. Without more data, it is a hypothesis rather than a validated finding.

**Overall:** The paper is incremental over XGrammar + standard constrained decoding practices. The main novelty lies in (i) the violation landscape study and (ii) the composability analysis, not in the technical framework itself. The semantic layer's entity registry is the one technically novel element, but its implementation (hash map + logit masking) is straightforward.

---

### 6. Related Work Assessment

**Coverage:** Generally good in the appendix, but with critical gaps:

- **SynCode (Ugare et al., ICML 2024):** Major omission. Attribute grammars with semantic augmentation for constrained generation is mechanistically the closest analog in the general constrained decoding literature.
- **IterGen (Ugare et al., ICLR 2025):** Major omission. Grammar-guided generation with semantic backtracking provides a more principled alternative to OntoCoDec's grammar-first fallback.
- **Schema-Guided Dialogue (Rastogi et al., AAAI 2020):** Minor omission. Schema-constrained slot filling in dialogue is a related paradigm.
- **Classical constraint satisfaction / constraint propagation literature:** The paper frames the problem purely in NLP terms. A brief connection to the constraint programming literature (arc consistency, constraint propagation) would strengthen the theoretical framing -- the sequential head-then-tail masking is essentially a form of forward-checking in constraint satisfaction.

**Differentiation quality:** The differentiation from code-domain constrained decoding (PICARD, Synchromesh, MGD, PLDI'25) is well-executed. The differentiation from vocabulary-constrained IE (GENRE, AdaKGC, GCD, GoLLIE) is adequate. The differentiation from post-hoc validation (ODKE+, OntoGPT, OntoLogX) is clear and well-argued.

**"First to compile" claim:** Needs qualification. GCD already applies grammar-constrained decoding to IE. GenIE uses state-based constraints for triple validity. OntoCoDec's specific contribution is automatically compiling *domain/range type constraints* into *semantic logit masks* -- a more narrow claim than "first to compile ontology constraints into decoding masks." The paper should state this more precisely.

---

### 7. Score and Confidence

**Score: 3 (Weak Reject)**

**Confidence: 4/5**

**Rationale:** The paper addresses a real problem with a competent solution backed by thorough evaluation. The violation landscape study and the FT composability analysis are genuine contributions. However, the technical novelty of the framework itself is limited -- it is well-executed engineering applying known techniques (grammar-constrained decoding, logit masking with hash-map state) to a new domain. The "first to compile" claim needs stronger qualification given SynCode, IterGen, GCD, and GenIE. The narrow ontological scope (6 entity types, single-token assumption) limits the generality of the "automatic compilation" framing. For EMNLP, the balance tips slightly toward rejection: the evaluation thoroughness is above the accept bar, but the technical novelty and scope of contribution are below it.

---

### 8. Key Concerns That Would Change My Score

**Would raise to 4 (Weak Accept):**
- Citing and clearly differentiating from SynCode and IterGen
- Demonstrating the framework on at least one ontology with >10 entity types (validating the "automatic compilation" claim beyond the toy 6-type case)
- Reframing the paper primarily as an empirical analysis paper with a systems contribution, rather than claiming methodological novelty

**Would raise to 5 (Accept):**
- All of the above, plus:
- Additional data points for the dual-factor regression (e.g., 2+ additional ontologies or models)
- A principled approach to the CF-DR trade-off beyond the current Pareto observation (even a lightweight global consistency mechanism)
- Demonstration on a practical domain (biomedical IE with an established ontology)

**Would lower to 2 (Reject):**
- If the "first to compile" claim is shown to be incorrect (i.e., if a published system already compiles IE ontology domain/range constraints into decoding masks)
- If the CF trade-off is found to cause significant downstream degradation in a knowledge graph construction pipeline

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c2ec43ab-28dc-4c2c-91a3-57046908f279",
  "isSidechain": true,
  "agentId": "a77dd280799b6b550",
  "requestId": "req_011Cb5VWS2DhTZMxaP8137ZU",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1c885589-c4bf-4d1a-9bd5-006ca34b9d11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "a8f7b9b0-e3ba-485f-a37e-4e472b218b82",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PaXvvD7agnkgggDs77QgBw",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 911,
      "cache_read_input_tokens": 100117,
      "output_tokens": 3661,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 911
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3661,
          "cache_read_input_tokens": 100117,
          "cache_creation_input_tokens": 911,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 911,
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
