# Research conversation: You are Reviewer 2 (R2) for an EMNLP 2026 submission. Your focus area is **Novelty and Related Work**. ## Venue: EMNLP 2

**OntoCoDec: Type-Constrained Information Extraction via Compiled Schema Constraints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 61
- **Recorded user turns:** 1
- **Tool calls:** 26
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-aaaf91bd2cb668cad.jsonl`
- **Structured JSON:** [`41177ce76d886434ea41.json`](../../sessions/41/41177ce76d886434ea41.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

61 recorded events

### User

_source line 1 · 2026-05-14T21:43:04.581Z_

You are Reviewer 2 (R2) for an EMNLP 2026 submission. Your focus area is **Novelty and Related Work**.

## Venue: EMNLP 2026 (via ACL Rolling Review)

**Scoring scale (1–5, half-point increments):**
- 5 = Award-worthy (top 2.5%)
- 4 = Largely complete, minor revisions
- 3 = Major revisions needed
- 2 = Significant revisions / resubmit
- 1.5 = Resubmit after next cycle
- 1 = Not publishable at *ACL

**Three dimensions:** Soundness (same 1–5), Excitement (same 1–5), Overall Assessment.

## Paper Summary

**Title:** "OntoCoDec: Near-Complete Type-Valid Information Extraction via Compiled Ontology Constraints"

The paper addresses ontology constraint violations in LLM-based zero-shot information extraction. It:
1. Conducts a **violation landscape study** measuring domain/range (DR), relation vocabulary (RV), entity type (ET), and cross-field consistency (CF) violations on SciERC (7 relations) and DocRED (96 relations) with Qwen3-8B under zero-shot prompting.
2. Proposes **OntoCoDec**, a framework that compiles IE ontology schemas into two composable constrained-decoding layers:
   - Grammar layer (CFG via XGrammar): enforces JSON structure, relation vocabulary, entity-type vocabulary → this is essentially applying existing XGrammar to IE
   - Semantic layer (TypeConstraintProcessor): stateful entity registry + dynamic logit masking for domain/range constraints → this is logit masking conditioned on a constraint table
3. Layers compose via bitwise AND of token masks; fallback to grammar-only when intersection is empty.
4. Two decoding strategies: S1 (single-pass) and S2 (two-pass).

## Key Claims
- C1: First systematic measurement of ontology constraint violations in LLM-based IE (violation landscape)
- C2: OntoCoDec framework for compiled ontology constraints
- C3: "Near-complete" type validity (94% DR reduction on SciERC)
- C4: Tightness hypothesis (violation rates driven by constraint tightness, not ontology size)
- C5: CF trade-off analysis as inherent limitation of per-relation enforcement

## Key Results

**SciERC (Qwen3-8B):** DR 15.4%→0.9% (↓94%), but CF 0.1%→9.9%. R-F1 8.23→8.36 (p=0.58, not significant).

**DocRED (Qwen3-8B):** DR 18.5%→10.2% (↓45%), CF 0.1%→2.6%. Grammar-only INCREASES DR to 26.2%.

**Cross-model (Llama-3.1-8B):**
- SciERC: DR 13.3%→0.1% (↓99.4%), CF=6.6%
- DocRED: DR 26.1%→2.6% (↓90.2%), CF=12.0%, parse failures increase 33.8%

**Post-hoc baseline outperforms on F1:** SciERC 8.63 vs 8.36; DocRED 9.61 vs 8.23.

**S2 two-pass designed to mitigate CF:** only 1.9pp reduction, not significant.

## Related Work Section (from paper)
The paper's related work section covers:
- Grammar-Constrained Decoding (XGrammar, code generation, JSON)
- Constrained Decoding for NLP (lexical, length, structural constraints)
- Schema-Guided IE
- Post-Hoc Validation

References are placeholder only ("[placeholder] References omitted for draft review").

## Your Task

Write a **detailed review** covering:

1. **Summary** (2–3 sentences)
2. **Strengths** (focus on novelty of contributions, positioning, framing)
3. **Weaknesses** (focus on novelty assessment, related work gaps, contribution framing)
4. **Questions for Authors**
5. **Preliminary Scores:**
   - Soundness (1–5)
   - Excitement (1–5)
   - Overall Assessment (1–5)
   - Confidence (1–5)

Be thorough and critical. Specifically assess:
- Whether the grammar layer (XGrammar application) constitutes genuine novelty or engineering combination
- Whether the semantic layer (logit masking with a constraint table) is sufficiently novel
- Whether the violation landscape study (C1) is an independent contribution or an incremental observation
- Whether "near-complete" in the title is justified given DocRED results (45% reduction, 10.2% residual)
- Missing related work: constrained decoding (NeuroLogic, FLAN-T5 structured generation, Guidance/Outlines libraries), ontology-aware IE (DeepKE, UIE, InstructUIE), type-constrained KG completion
- Whether the paper adequately distinguishes itself from applying existing constrained decoding tools (XGrammar, Outlines, etc.) to IE
- The CF trade-off: does introducing 9.9% CF while reducing 15.4% DR represent a net benefit?

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "d58d400e-54b8-4a08-882a-10d61203546e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-14T21:43:04.583Z_

```json
{
  "parentUuid": "d58d400e-54b8-4a08-882a-10d61203546e",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
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
  "uuid": "5e163447-b7e7-473f-ba4c-389c631d0c4c",
  "timestamp": "2026-05-14T21:43:04.583Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 3 · 2026-05-14T21:43:07.552Z_



I'll start by reading the paper and related project files to give a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5e163447-b7e7-473f-ba4c-389c631d0c4c",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1G4tYskHBJftUC2T3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8f3a09b1-fce2-4d6f-8079-744b6e507a63",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KgksFHCT6zDqAR2D8JNDwS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7137,
      "cache_read_input_tokens": 8252,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7137,
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

_source line 4 · 2026-05-14T21:43:07.973Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01SCaiy1YFW1mzzRNwZWD8h6`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__director_get_project_overview",
  "max_results": 2
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8f3a09b1-fce2-4d6f-8079-744b6e507a63",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1G4tYskHBJftUC2T3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f08fe599-bd98-4693-99a9-0c6eb4407c0c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KgksFHCT6zDqAR2D8JNDwS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7137,
      "cache_read_input_tokens": 8252,
      "output_tokens": 124,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7137
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 124,
          "cache_read_input_tokens": 8252,
          "cache_creation_input_tokens": 7137,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7137,
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

_source line 5 · 2026-05-14T21:43:07.977Z_

<details><summary>↩ Tool result · `toolu_01SCaiy1YFW1mzzRNwZWD8h6`</summary>

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
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f08fe599-bd98-4693-99a9-0c6eb4407c0c",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "24cf8a66-3083-4e58-9bb3-e7d7341ede46",
  "sourceToolAssistantUUID": "f08fe599-bd98-4693-99a9-0c6eb4407c0c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 6 · 2026-05-14T21:43:10.550Z_



Let me read the paper and project files to conduct a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "24cf8a66-3083-4e58-9bb3-e7d7341ede46",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1Ws8inqv8xJJrBsrZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e1626092-76db-4bf3-8aa6-ba28417d0378",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R5zKhWitQxJ5ScK9TgRDHG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 15389,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

_source line 7 · 2026-05-14T21:43:11.552Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_013xjHwrfhHwHKbqKNEsh8ym`</summary>

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
  "parentUuid": "e1626092-76db-4bf3-8aa6-ba28417d0378",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1Ws8inqv8xJJrBsrZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9c20a3fa-a22b-4680-84de-1a410e688613",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R5zKhWitQxJ5ScK9TgRDHG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 15389,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

_source line 8 · 2026-05-14T21:43:11.565Z_

<details><summary>↩ Tool result · `toolu_013xjHwrfhHwHKbqKNEsh8ym`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/report.md\", \"content\": \"# Handover — 2026-05-14\\n\\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\\n\\n## 运行中\\n（无）\\n\\n## 待处理\\n（无）\\n\\n## 近期结论\\n- **llama_docred_full_s1** (success): Llama-3.1-8B-Instruct + Grammar+Semantic 双层约束 (S1) 在 DocRED (96 relations) 上的效果。与 Qwen3-8B DocRED full_s1 (DR 10.19%) 对比，验证约束解码在不同模型+复杂 schema 上的泛化性。\\n  [llama_docred_full_s1_analysis](/api/workspace-files/projects/schema_semantic_constrained_ie/artifacts/llama_docred_full_s1/report/llama_docred_full_s1_analysis.md)\\n- **llama_docred_unconstrained** (success): Llama-3.1-8B-Instruct 在 DocRED unconstrained baseline。与 Qwen3-8B DocRED unconstrained 对比 violation 分布。验证不同模型在复杂 schema (96 relations) 上的 violation 模式差异。\\n- **phase2_docred_grammar_only** (success): Grammar-only constrained decoding 在 DocRED (96 relation types) 上能否消除 RV violations (28.9%) 和 ET violations (7.5%)？与 SciERC grammar_only (RV 1.4%→0%, ET 0.4%→0%) 对比，验证 grammar 层在复杂 schema 上的泛化性。\\n\\n## 趋势\\n成功 19 / 负向 0 / 失败 0 / 共 20\\n\\n## 下一步\\n（无活跃 idea，请通过 ideas.md 添加）\\n\\n## 资源状态\\nwestd-16980: 无 GPU 信息\\n\\n## 告警\\n- mvp_phase0_docred_schema_r2: 已被终止 — unknown\\n\", \"total_chars\": 1036, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9c20a3fa-a22b-4680-84de-1a410e688613",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "6fab0d57-eba0-4276-b832-9687ee0b7a94",
  "sourceToolAssistantUUID": "9c20a3fa-a22b-4680-84de-1a410e688613",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-14T21:43:12.457Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01Lgv48QphewbahSPCCmhSWq`</summary>

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
  "parentUuid": "6fab0d57-eba0-4276-b832-9687ee0b7a94",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1Ws8inqv8xJJrBsrZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "569ef11f-0912-4fe1-b91c-43e31c6c4ace",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R5zKhWitQxJ5ScK9TgRDHG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 15389,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

_source line 10 · 2026-05-14T21:43:12.467Z_

<details><summary>↩ Tool result · `toolu_01Lgv48QphewbahSPCCmhSWq`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No ideas.md found for 'schema_semantic_constrained_ie'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "569ef11f-0912-4fe1-b91c-43e31c6c4ace",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "65fd7704-f0ce-4e23-810d-2b40c9548372",
  "sourceToolAssistantUUID": "569ef11f-0912-4fe1-b91c-43e31c6c4ace",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-14T21:43:12.786Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01WRmF6kFm2hkCECVXKEpA3H`</summary>

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
  "parentUuid": "65fd7704-f0ce-4e23-810d-2b40c9548372",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1Ws8inqv8xJJrBsrZ",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9251268c-d28c-43bd-825b-df942c0c6ef8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R5zKhWitQxJ5ScK9TgRDHG",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 15389,
      "output_tokens": 312,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1447
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 312,
          "cache_read_input_tokens": 15389,
          "cache_creation_input_tokens": 1447,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1447,
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

_source line 12 · 2026-05-14T21:43:12.795Z_

<details><summary>↩ Tool result · `toolu_01WRmF6kFm2hkCECVXKEpA3H`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No literature_map.yaml found for 'schema_semantic_constrained_ie'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9251268c-d28c-43bd-825b-df942c0c6ef8",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "a3a27e90-6e9b-434d-957f-3d72a8a1bfc8",
  "sourceToolAssistantUUID": "9251268c-d28c-43bd-825b-df942c0c6ef8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-14T21:43:15.825Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01R37gV8FZnTg36owFdodsL4`</summary>

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
  "parentUuid": "a3a27e90-6e9b-434d-957f-3d72a8a1bfc8",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1sMgBcEzzozbd9ah6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8d67dd12-8913-4906-acf2-18f74f9c1d48",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XjXJcC9nMfRFpK6qrsbSzQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1220,
      "cache_read_input_tokens": 16836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1220,
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

_source line 14 · 2026-05-14T21:43:15.836Z_

<details><summary>↩ Tool result · `toolu_01R37gV8FZnTg36owFdodsL4`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/paper_framing.md\", \"content\": \"# OntoCoDec — Paper Framing\\n\\n## Target Venue\\nEMNLP 2026 (ARR submission May 25, 2026)\\n\\n## Title\\nOntoCoDec: Near-Complete Type-Valid Information Extraction via Compiled Ontology Constraints\\n(Note: \\\"Guaranteed\\\" dropped per Reviewer — S1 DR=0.93%, S2 DR=0.97%, neither achieves 0%. \\\"Near-Complete\\\" is honest and defensible.)\\n\\n## Core Insight\\nLLM-based IE systems produce systematic ontology constraint violations concentrated in specific relation types. Prompt-level intervention (schema-informed prompting) reduces violations by ~62% but cannot eliminate them — certain relation types retain 25-30% violation rates even with explicit constraint descriptions. OntoCoDec provides **near-complete elimination (DR 15.4%→0.93%, ↓94%) at zero or positive F1 impact** through automatic ontology-to-decoder constraint compilation with two complementary layers.\\n\\n**Phase 2 confirmed (D012 bootstrap CI, v2 fix)**: Grammar+Semantic dual-layer constrained decoding reduces domain/range violations by 94%, eliminates entity-type and relation-vocabulary violations entirely (→0%). F1 impact is **dataset-dependent**:\\n- SciERC: Rel F1 neutral (+0.13pp, p=0.58), Ent F1 neutral (-0.03pp, p=0.53)\\n- DocRED: Rel F1 **significantly improved** (+0.50pp, p<0.001, 95% CI [+0.23, +0.81]); Ent F1 **significantly improved** (+1.23pp, p<0.001, 95% CI [+0.94, +1.55])\\n- Mechanism: grammar 消除 OOV relation names (DocRED RV 29.66%→0.03%) + 非标 entity types (ET 2.48%→0%)。all_set F1 方法下 OOV=FP → fewer FP → higher precision/F1。SciERC baseline RV/ET 已很低，效果不显著。\\n- **Grammar 层是 F1 提升的唯一来源**: grammar_only Ent F1=59.38% ≈ full_s1 59.37% (Δ+0.01pp, p=0.66)。Semantic 层对 F1 无额外贡献，专注 DR reduction。\\n\\n## Core Claims\\n\\n### Claim 1 (Empirical): Violation Landscape\\nLLM-based IE systems violate ontology type constraints at non-trivial rates (15.4% per-triple on SciERC, 18.7% on DocRED). Violations are **not uniformly distributed** — they concentrate on relation types with tight domain/range constraints (Feature-of 33.5%, Compare 42.4%) while loose-constraint relations show near-zero violation (Used-for 0.8%).\\n\\n**Key insight**: Violation rate is driven by **constraint tightness**, not ontology size. A small ontology with tight constraints can produce more violations than a large ontology with loose constraints.\\n\\n**D014 修订**: DR reduction ceiling 由 **tightness × model RV baseline** 共同决定，非 tightness 单因素。Llama DocRED DR↓90.2% vs Qwen DR↓44.7%（同一 ontology τ̄=0.842）。机制：Qwen RV=29.66% >> Llama RV=16.03% → grammar 层将 OOV triples 强制匹配有效关系名 → 揭露大量 latent DR violations → 残余 DR 更高。这是比单一 tightness 更深的 insight。\\n\\n**Evidence**: SciERC (7 relations) 15.4%; DocRED (96 relations) 18.7% — comparable rates despite 14× ontology size difference. Schema-informed prompt on DocRED only achieves DR↓32% (vs SciERC ↓62%), confirming **prompt-level intervention scales poorly with ontology complexity**.\\n\\n### Claim 2 (Empirical): Prompt Insufficiency\\nSchema-informed prompting (explicitly describing domain/range constraints in the prompt) reduces but does not eliminate violations:\\n- Overall: 15.4% → 5.78% (-62.4%), still above 5%\\n- Per-relation: Compare 42.4% → 27.6%, Evaluate-for 24.1% → 29.9% (**worse**)\\n- Prompt intervention is unreliable at the per-relation level — some relations improve, one regresses\\n\\n**Narrative**: This is NOT about \\\"5.78% barely above 5%\\\". The story is: **prompt-level intervention is fundamentally unreliable as a guarantee mechanism**. It works statistically but cannot provide per-instance compliance. Three specific relation types retain >10% violation rates with schema-informed prompts. For safety-critical IE (biomedical, legal, regulatory), statistical reduction is insufficient — guaranteed compliance is required.\\n\\n### Claim 3 (Methodological): Composable Constraint Framework\\nOntoCoDec automatically compiles IE ontology schemas into two composable constraint layers:\\n1. **Grammar layer** (XGrammar): JSON structure + type vocabulary constraints (CFG-expressible)\\n2. **Semantic layer** (TypeConstraintProcessor): Cross-field domain/range constraints via stateful entity registry + dynamic logit masking\\n\\nThe two layers are **complementary with enabling dependency**: grammar ensures every generated relation type is in the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type. Without grammar, the semantic layer encounters unknown relation types and cannot enforce constraints (explaining why semantic_only achieves only ↓24% vs full_s1 ↓94%). This is NOT \\\"synergistic\\\" (mutual amplification) — grammar is a prerequisite for semantic, not vice versa.\\n\\nThe two layers compose via bitwise AND of token masks. Recommended framing: \\\"Grammar and semantic constraints compose via bitwise AND with an enabling dependency: grammar ensures structural validity, enabling semantic constraints to enforce domain/range rules. When constraint tightness creates empty intersection between layers, the system degrades gracefully to grammar-only constraints, maintaining structural validity as a guaranteed floor.\\\"\\n\\n**Graceful degradation + Fallback 频率量化** (D008 + Reviewer 发现):\\nWhen $M_{semantic} \\\\cap M_{grammar} = \\\\emptyset$, the system falls back to grammar-only control.\\n\\n**关键量化数据（Reviewer 从日志挖掘）**:\\n- Llama DocRED full_s1: **32,921 次 fallback / 577 docs = ~57 次/doc**\\n- Llama SciERC full_s1: **5,882 次 fallback / 550 docs = ~10.7 次/doc**\\n- DocRED fallback 频率是 SciERC 的 **5.3×**\\n- Qwen DocRED fallback 率未知（日志当时无 fallback logging，需估算）\\n\\n**这直接解释了 DocRED DR 残余 10.19% vs SciERC 0.93%**: 更多 token 位置退化为 grammar-only → grammar-only 的 DR 已知为 26.17% → 高 fallback = 高残余 DR。\\n\\n**论文建议**: 在 §5 tightness 段报告 fallback 率，定义 \\\"Constraint Coverage\\\" 指标（semantic masking 实际生效的 token 比例）。这把 \\\"10.19% DR 残余\\\" 从弱点变成可量化分析的 finding。Frame as \\\"engineering robustness\\\" in §4; fallback 频率 + tightness 作为 §5 定量分析。\\n\\n**Decidability taxonomy**: Constraints classified by prefix-decidability:\\n- (a) Purely local: entity type ∈ vocabulary (grammar layer)\\n- (b) Prefix-decidable with state: relation argument types compatible with domain/range (semantic layer, requires entity registry)\\n- (c) Truly non-local: forward coreference — out of scope for forward-only decoding\\n\\n### Claim 4 (Methodological): S1 vs S2 Decoding Strategies — Architectural Ablation\\n- S1 (single-pass): Both layers applied throughout generation. **Recommended primary strategy** — simpler, slightly better metrics across the board.\\n- S2 (two-pass): Pass 1 extracts entities (grammar-only), Pass 2 generates relations with input-dependent grammar compiled from Pass 1 entities.\\n\\n**S2 full results (551/551 SciERC)**: DR 0.97% (vs S1 0.93%), CF 8.03% (vs S1 9.9%), R-F1 8.03% (vs S1 8.36%). S2 does NOT solve CF — the 1.87pp reduction is not significant. S2 also slightly worse on DR and F1. **S2 is an architectural variant demonstrating framework flexibility, not a CF solution.** Position in paper as ablation (Section 5 or Appendix), not as a core contribution.\\n\\n⚠️ **Do NOT cite pilot50 DR=0% as S2 evidence** — small-sample artifact; full run shows DR=0.97%. Per-relation S2 DR is worse than S1 on Compare (4.6% vs 2.82%), Part-of (1.25% vs 0%), Used-for (0.12% vs 0%).\\n\\n## Anticipated Reviewer Concerns\\n\\n### C1: \\\"5.78% is barely above 5% — threshold is arbitrary\\\"\\n**Response**: Don't argue about the threshold. Argue about per-relation distribution: Compare (27.6%), Evaluate-for (29.9%), Feature-of (11.3%) have double-digit violation rates with schema-informed prompt. The value proposition is per-relation guaranteed compliance, not overall statistical rate.\\n\\n### C2: \\\"Why not just post-hoc filter?\\\"\\n**Response (D013, 实验结果已出)**:\\n\\nPost-hoc filtering 实验结果：post-hoc F1 > OntoCoDec F1（SciERC 8.63 vs 8.36, DocRED 9.61 vs 8.24）——因 low F1 regime 下移除 FP 大幅提升 precision。\\n\\n**论文 framing（不以 F1 论高低，多维对比）**:\\n1. **Recall 维度（核心论点）**: OntoCoDec recall 上升 (SciERC +0.20pp, DocRED +0.56pp) = 概率质量重分配到合法 token 生效。Post-hoc recall 下降 (SciERC -0.72pp, DocRED -1.06pp) = 正确 triple 被误删。\\n2. **Information coverage**: DocRED post-hoc 丢弃 **48.1%** triples（近半数信息丢失），SciERC 16.8%。OntoCoDec 保留全部 triple slots。\\n3. **Operational**: OntoCoDec 产出即合规、无需后处理、支持流式。Post-hoc 需额外管线、不适用实时场景。\\n4. **Precision trade-off（诚实承认）**: \\\"Post-hoc achieves higher precision by removing a large fraction of triples, many of which are incorrect. This trades information coverage for precision — valid when FP are costly, but inadequate when completeness matters.\\\"\\n\\n数据表：SciERC post-hoc rejection 16.8%, OntoCoDec recall 11.60 vs post-hoc 10.68; DocRED post-hoc rejection 48.1%, OntoCoDec recall 10.02 vs post-hoc 8.40。\\n\\n**Reviewer 补充发现（D013 后）**:\\n5. **ET 残余**：post-hoc 只删 triples 不改 entity list，残余 ET=0.4% (SciERC) / 2.47% (DocRED)。OntoCoDec ET=0%。Post-hoc 无法解决 entity type 违规。\\n6. **127 个被删 TP (DocRED)**：过滤前 TP=1137，过滤后 TP=1010。丢失的 127 个 TP（11.2%）是正确提取但 entity type 违规的 triple。OntoCoDec 通过生成时强制合法 type 保留这些 TP——\\\"prevent vs detect\\\" 核心论据的具体数据。\\n7. **OntoCoDec+post-hoc 组合**（future work idea）：先 constrain 再 filter 残余 DR。低优先级，May 19 前不做。\\n\\n### C3: \\\"Bitwise AND of two masks is not novel\\\"\\n**Response**: The novelty is not the AND operation — it's (a) the automatic compilation from ontology definitions (zero-code schema compliance), (b) the stateful entity registry enabling cross-field constraints during autoregressive generation, (c) the decidability taxonomy providing theoretical guidance, and (d) the systematic violation landscape measurement motivating the approach.\\n\\n### C4: \\\"Evaluate-for violation rate increases with schema-informed prompt\\\"\\n**Response (prior-constraint conflict framework)**: Evaluate-for has 23/36 valid pairs; Method→Task is invalid for Evaluate-for but natural in the LLM's distributional prior (\\\"Method X evaluates for Task Y\\\" is semantically plausible). Schema-informed prompting creates a **prior-constraint conflict**: the model learns to avoid Method→Task for Evaluate-for (reducing count 133→87, -34.6%), but the remaining instances are harder boundary cases where the model's type assignment strategy becomes less stable. This is not just \\\"harder instances\\\" — it's an active interference between prompt-level constraint signals and the model's learned type associations.\\n\\n**This strengthens the paper's claim**: prompt-level intervention is not merely insufficient but potentially **counterproductive** for specific constraint configurations. Decoding-time enforcement avoids this issue entirely — it operates on logits, not on the model's reasoning process, so there is no prior-constraint conflict.\\n\\n### C5: \\\"Only tested on one model (Qwen3-8B)\\\"\\n**Response**: Cross-model validation DONE. Llama-3.1-8B 零代码修改：\\n- SciERC: DR 13.34%→0.08% (↓99.4%), F1-neutral (-0.14pp)\\n- DocRED unconstrained: DR 26.15%, RV 16.03%, R-F1 5.98% (parse failures 6.8% vs Qwen 1.2%)\\n- DocRED full_s1: 🔄 ETA ~20:19 UTC\\n\\n**Cross-model claim 指导（Reviewer 专项评估）**:\\n- ✅ 可声明：\\\"OntoCoDec generalizes across model families without code modification\\\"（程序性事实，铁证）\\n- ❌ 不可声明：\\\"consistently achieves the same reduction rate\\\"（仅 2 模型，不足以量化声明）\\n- **RV↓DR↑ 正交性 finding**: Llama RV baseline 低(16%) 但 DR baseline 高(26%)，反向于 Qwen。证明两层约束解决正交 failure modes——vocabulary compliance ≠ semantic compliance。应作为 §5 cross-model 独立 finding 展开。\\n- **Parse failure 偏差**: checker skip parse failures (不计入 F1)，Llama 68/998=6.8% vs Qwen 12/998=1.2%。偏差方向保守（不利于 constrained），不威胁 claim。但需 footnote 披露 + cross-model 表增加 parse failure rate 行。\\n- **Llama SciERC CF=6.56%**: 比 Qwen 同量级更高，non-local constraint 问题在 Llama 上更突出，limitations 提及。\\n- 等 llama_docred_full_s1 出来后定最终 claim 措辞。\\n\\n### C6: \\\"Constrained decoding degrades generation quality (CRANE, Structure Snowballing)\\\"\\n**Response**: OntoCoDec's semantic constraints are narrower than full grammar constraints — only type tokens are masked, free text is unconstrained. **D012 Bootstrap CI (10000×, v2 fix) 结果**:\\n- SciERC: Rel F1 +0.13pp (p=0.58), Ent F1 -0.03pp (p=0.53) → **F1-neutral**\\n- DocRED: Rel F1 +0.50pp (p<0.001, CI [+0.23, +0.81]), Ent F1 +1.23pp (p<0.001, CI [+0.94, +1.55]) → **双双显著提升**\\n- 机制：grammar 消除 OOV relation names + 非标 entity types → all_set 方法下减少 FP → precision 提升。Grammar 是 F1 提升的唯一来源（grammar_only Ent F1=59.38% ≈ full_s1 59.37%, Δ=0.01pp, p=0.66）。Semantic 层对 F1 无额外贡献。\\n- Frame as: \\\"Constraint enforcement preserves or improves extraction quality: F1-neutral on SciERC; statistically significant Rel F1 and Entity F1 improvement on DocRED (p<0.001).\\\"\\n- 不升级为 core claim，但如实报告 significance + 机制归因。Note: S2 shows marginally lower F1 and fewer triples (1644 vs 1729) — two-pass does not improve quality.\\n\\n### C7: \\\"Your method trades DR violations for CF violations (cross-field consistency)\\\"\\n**Response**: Both S1 and S2 show elevated CF (per-triple rate ~8-10%). This is an inherent limitation of per-relation independent type enforcement. Must be proactively reported as a limitation. Defense:\\n\\n**CF 子类型分析（根因已确认）**：\\n- **EVR（entity-vs-relation type drift）**: 占 CF 的 >90%。同一 entity 在 entity list 和 relation triple 中被赋予不同 type。S1: 245 entities (7.34%), S2: 178 entities (5.54%, -27%)\\n- **Within-rel（同 entity 跨 relation type 不一致）**: S1: 10 (0.36%), S2: 18 (0.72%)\\n- S2 减少 EVR 但增加 within-rel——trade-off 更复杂，不是单纯好/差\\n\\n**Top 冲突模式**: Generic↔OtherScientificTerm (60次), Material↔OtherScientificTerm (28次), Material↔Method (20次)。**这些是 SciERC type system 固有的语义边界模糊区**——同一术语在不同学术语境下确实可以被合理归类为不同 type。CF 在相当程度上是 type system 模糊性的体现，非纯粹的方法缺陷。\\n\\n**论证层次**：\\n1. DR violations = structurally invalid triples（下游系统不可用）→ hard constraint\\n2. CF violations = same entity gets different types across relations → individual triples remain type-valid, only cross-triple consistency broken → soft preference\\n3. CF 的根因是 type system 语义边界模糊 + per-relation 独立 enforcement，非 bug\\n4. Future work: cross-relation global consistency pass (entity-level type consensus before relation-specific enforcement)\\n\\n**机制归因（口径对账确认）**：grammar_only CF=0.08%（与 unconstrained 持平），full_s1 CF=9.90%，full_s2 CF=8.03%。**CF 100% 由 semantic 层引入，grammar 层无贡献。** 这为 \\\"CF 是 semantic type enforcement 的系统性副作用\\\" 提供干净的消融证据。\\n\\n**论文数字口径**：CF rate 用 violation_checker 口径（denominator=total_entities，与 DR/RV/ET 一致）。分析段落额外给 entity-level EVR 率 + 受影响样本比例。注意：analyze_cf 脚本的 EVR/WR 两维度不是独立的（WR⊂EVR），论文中不要作为两个独立维度报告。\\n\\n**Do NOT hide this data.** Proactive disclosure + severity distinction + root cause analysis + type ambiguity evidence + 消融归因 = 最强防御策略。\\n\\n### C8: \\\"Absolute F1 is too low (~8%) — results are not meaningful\\\"\\n**Response**: This is a zero-shot extraction setting (no training data, no fine-tuning). Low F1 is expected — supervised SOTA on SciERC relation F1 is ~40-50%. Our contribution is the constraint enforcement method, not extraction quality. F1 is a control variable verifying constraints don't degrade quality, not an optimization target. Recommended framing: \\\"We evaluate in a zero-shot setting to demonstrate that our constraint enforcement method works without task-specific training. F1 is reported to verify that constraint enforcement does not degrade extraction quality, not as a claim of state-of-the-art performance.\\\"\\n\\n## Paper Structure (Draft)\\n1. Introduction: Violation landscape motivation + composable constraint framework overview\\n2. Background: Grammar-constrained decoding (XGrammar) + IE ontology structure\\n3. Violation Landscape Study (Phase 0 empirics — independent contribution)\\n4. OntoCoDec Framework: Compiler + TypeConstraintProcessor + S1/S2 strategies\\n5. Experiments: Constrained vs unconstrained vs post-hoc vs prompt-based\\n6. Related Work: 5 constraint paradigms (grammar, vocabulary, structural, type-checking, ontology)\\n7. Conclusion\\n\\n## Claim Calibration (per Reviewer assessment)\\n\\n**Safe to claim (sufficient evidence from Phase 2)**:\\n- \\\"First systematic study of ontology constraint violations in LLM-based IE\\\"\\n- \\\"Violation rate correlates with constraint tightness, not ontology size\\\" (D014: DR reduction ceiling 由 tightness × model RV baseline 共同决定)\\n- \\\"Grammar+semantic constrained decoding eliminates 94% of DR violations at zero F1 cost\\\" ✅ Phase 2 confirmed\\n- \\\"Two-layer architecture provides complementary coverage — grammar enables semantic\\\" ✅ Ablation confirmed\\n- \\\"Prompt-level intervention scales poorly with ontology complexity\\\" ✅ SciERC ↓62% vs DocRED ↓32%\\n\\n**Claim with caution**:\\n- \\\"Near-complete type-valid IE\\\" — S1 0.93%, S2 0.97% residual, not truly 0%. Title updated to \\\"Near-Complete\\\"\\n- \\\"Principled framework applicable to arbitrary IE ontologies\\\" — validated on 2 datasets + 1 model only\\n- \\\"F1 improvement\\\" — SciERC: not significant (p=0.58), frame as F1-neutral; DocRED: significant (+0.50pp, p<0.001), 可报告但不升级为 core claim，归因于 OOV elimination 而非约束解码本身的提升\\n- \\\"CF reveals type system ambiguity\\\" — 可在 §5.3 作为 analysis finding 展开（Generic↔OtherScientificTerm 等模式有独立 insight 价值），但 §7 必须同时保留 CF 作为 limitation + future work。**两处都要有，缺一不可。** 不能暗示\\\"因为是 type ambiguity 所以 CF 可接受\\\"\\n\\n**Do NOT claim**:\\n- \\\"General infrastructure for IE\\\" — only zero-shot extraction validated\\n- \\\"State-of-the-art\\\" — F1 is control variable, not optimization target (see C8)\\n- \\\"Synergistic effect\\\" — mechanism is enabling dependency, not mutual amplification (see Claim 3)\\n- \\\"S2 solves CF\\\" or \\\"S2 mitigates Structure Snowballing\\\" — data shows S2 ≈ S1 on all metrics; position as architectural variant only\\n- \\\"Pilot50 DR=0%\\\" — small-sample artifact, full S2 has DR=0.97%\\n- \\\"Grammar-first invariant\\\" 作为独立 claim — 证据不足（仅 1 次崩溃触发，实现是 fallback 非形式化保证）。写入 §4 方法论设计原则（1-2 句），不升级为 claim\\n- \\\"Robust dual-layer composition across schema complexities\\\" — 等 DocRED 完成。最终如 fallback ≤5/998，可写经验性陈述，不做泛化 claim\\n\\n## Risk Ranking (ordered by reject probability)\\n\\n1. **CF violation trade-off under-addressed** (MEDIUM-HIGH): S1 9.9%, S2 8.03% — both elevated. **S2 confirmed: does NOT solve CF.** This is the #1 attack surface. Mitigated by proactive disclosure + severity distinction + root cause analysis (C7). Must be reported as explicit limitation with future work direction (global entity-type consensus).\\n2. ~~**Single model limitation**~~ (RESOLVED): Llama-3.1-8B SciERC ✅ (DR↓99.4%) + DocRED ✅ (DR↓90.2%). 2 模型 × 2 数据集全矩阵完成。\\n3. **Novelty perception** (MEDIUM): \\\"PLDI'25 for code → OntoCoDec for IE\\\" attack line. Must argue IE constraint structure differs fundamentally.\\n4. ~~**DocRED Phase 2 weak**~~ (RESOLVED → reframed as D014): Qwen DR↓44.7%, Llama DR↓90.2% — both substantial. Weaker Qwen reduction explained by RV baseline interaction (D014), not method failure.\\n5. ~~**Phase 2 F1 drop**~~ (RESOLVED): F1 confirmed neutral (SciERC) or positive (DocRED, p<0.001). Bootstrap CI D012 confirms. No longer a risk.\\n\\n## Critical Path to EMNLP Submission (May 25)\\n\\n- **May 13-14**: Phase 0 + Phase 1 + Phase 2 SciERC ✅\\n- **May 14**: Phase 2 DocRED 4-way ablation ✅ + Llama SciERC cross-model ✅ + Dream 完成 (3/6)\\n- **May 14-15**: Llama DocRED 2 组实验 ✅ + Checker 修正 ✅ + post-hoc baseline ✅ + bootstrap CI ✅ + related work ✅\\n- **May 14-15**: D014 tightness claim 修订 + §5 cross-model subsection + abstract/conclusion 修正 (Agent 执行中)\\n- **May 15-17**: 全文校对 + Discussion 整合 + 最终数字确认\\n- **May 19**: 内部稿 → submit_paper_to_review\\n- **May 19-24**: Review 修改 + 最终提交\\n\\n**当前瓶颈**: D014 论文修订（tightness claim + cross-model subsection + E-F1 claim limitation）\\n\\n## Status\\n- Phase 0 SciERC: ✅ Complete (minimal + schema-informed)\\n- Phase 0 DocRED: ✅ Complete (minimal 18.7% DR + schema-informed 12.8% DR)\\n- Phase 1 Compiler: ✅ Complete (grammar + semantic layers integrated)\\n- Phase 2 SciERC (5 configs): ✅ Complete (S1 DR↓94% F1-neutral, S2 降级为 ablation)\\n- Phase 2 DocRED (4 configs): ✅ Complete (full_s1 DR↓45%, grammar ET/RV→0%)\\n- Llama SciERC cross-model: ✅ Complete (DR↓99.4%, F1-neutral, 零代码修改)\\n- Llama DocRED cross-model: ✅ Complete (full_s1 DR↓90.2%, unconstrained DR=26.07%)\\n- Checker v2 (D011): ✅ Fixed (ET triple-counting → unique entity dedup)\\n- Bootstrap CI (D012): ✅ Fixed + confirmed (entity filter bug resolved)\\n- Post-hoc baseline (D013): ✅ Complete (multi-dimensional framing)\\n- Related work: ✅ 42 bib entries, 4 additions merged\\n- Dream 6/6 actions: ✅ All complete\\n- CF violation analysis: ✅ Confirmed inherent limitation (S1 9.9% SciERC / 2.57% DocRED / 12.02% Llama DocRED)\\n- D014 tightness revision: 🔄 Agent executing (tightness × RV baseline dual-factor)\\n\", \"total_chars\": 20047, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8d67dd12-8913-4906-acf2-18f74f9c1d48",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "84a72cee-a112-40fa-bdf0-18f742328eab",
  "sourceToolAssistantUUID": "8d67dd12-8913-4906-acf2-18f74f9c1d48",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-14T21:43:16.794Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01YTbDwgJvDNnHFE4G9XuQN7`</summary>

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
  "parentUuid": "84a72cee-a112-40fa-bdf0-18f742328eab",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1sMgBcEzzozbd9ah6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bed4e7d7-fcb2-47b6-9e45-f77ea5359325",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XjXJcC9nMfRFpK6qrsbSzQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1220,
      "cache_read_input_tokens": 16836,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1220,
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

_source line 16 · 2026-05-14T21:43:16.810Z_

<details><summary>↩ Tool result · `toolu_01YTbDwgJvDNnHFE4G9XuQN7`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/ROADMAP.md\", \"content\": \"# OntoCoDec — Research Dashboard\\n\\n> 最后更新: 2026-05-14 20:43 UTC | 更新原因: 修正 Llama unconstrained DR 数据错误 (18.36%→26.07%) + 核心方向描述加 model-dependent + 补全近期任务\\n\\n## 核心方向\\n两层约束解码（grammar + semantic）近完全消除 LLM-based IE 的本体类型违规，F1 impact model-dependent: neutral (SciERC) to positive (DocRED Qwen, +0.50pp p<0.001)。详见 paper_framing.md。\\n\\n## 当前阶段\\nResearch — **全部 20 个实验完成**（19 success, 1 killed）。进入论文修订收尾。目标 May 19 内部稿 → May 25 EMNLP ARR。\\n\\n## 实验完成度\\n- 总计: 20 个实验，19 success，1 killed，0 RUNNING\\n- SciERC 5-way ablation (Qwen): ✅\\n- DocRED 4-way ablation (Qwen): ✅\\n- Llama SciERC cross-model: ✅ (DR↓99.4%)\\n- Llama DocRED cross-model: ✅ (unconstrained DR=26.07%, full_s1 DR=2.55%, DR↓90.2%)\\n- Phase 0 violation landscape: ✅ SciERC + DocRED\\n- Post-hoc baseline: ✅ (D013 multi-dimensional framing)\\n- Bootstrap CI (D012): ✅ (entity filter bug fixed + re-verified)\\n- D011 ET fix (v2 checker): ✅ 全量重跑完成\\n\\n## 关键决策摘要\\n- D014: Tightness scaling → 双因素 (tightness × model RV baseline)\\n- D013: Post-hoc framing → 不争 F1，多维对比 (recall + coverage + operational)\\n- D012: Bootstrap CI → SciERC neutral (p=0.58), DocRED significant (+0.50pp, p<0.001)\\n\\n## 活跃工作流 (May 14 ~21:30 UTC)\\n\\n### GPU 实验\\n（无 — 全部完成）\\n\\n### Agent 工作\\n- D014 修订指令在队列中等待执行（§5 tightness rewrite + cross-model subsection + abstract/conclusion + limitations + placeholders）\\n- 前置 worker callbacks 处理中\\n\\n## 近期任务\\n- [ ] D014 §5 tightness claim 修订（tightness × RV baseline 双因素）— Agent 队列中\\n- [ ] Abstract/Conclusion E-F1 claim limitation（Qwen-specific）— Agent 队列中\\n- [ ] §5 Cross-model subsection（2×2 matrix table + narrative）— Agent 队列中\\n- [ ] Limitations expansion（CF 12.02% + parse failures 6.8%→9.1% + scope）— Agent 队列中\\n- [ ] [LLAMA-DOCRED-TBD] placeholder filling — Agent 队列中\\n- [ ] Discussion 段落更新（加入 Llama DocRED 数据）\\n- [ ] Bibliography 最终编译检查\\n- [ ] main.tex 集成 + 全文数字一致性终审\\n- [ ] May 19: 内部稿 → submit_paper_to_review\\n\\n## GPU 预算\\nwestd-16980: cuda:0 + cuda:1 分配给本项目。当前空闲（全部实验已完成）。\\n\\n## Dream 后行动完成度 (6/6 ✅)\\n1. Post-hoc baseline — ✅ D013\\n2. Bootstrap CI — ✅ D012 (entity filter fix verified)\\n3. Related work 20+ refs — ✅ 42 entries merged\\n4. PICARD detailed comparison — ✅\\n5. CF/F1 discussion — ✅ discussion_paragraphs.tex\\n6. Variance estimates — ✅ bootstrap CI\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D014 | 2026-05-14 | Tightness scaling claim 修订：从单因素(tightness)改为双因素(ti | llama_docred_full_s1, llama_docred_unconstrained, phase2_docred_full_s1 |\\n| D013 | 2026-05-14 | Post-hoc baseline framing: 不以 F1 论高低，多维对比 (recall  | phase2_scierc_unconstrained, phase2_scierc_full_s1, phase2_docred_unconstrained, phase2_docred_full_s1 |\\n| D012 | 2026-05-14 | Bootstrap CI framing: 选 (B) 逐数据集报告 F1 significance | phase2_docred_full_s1, phase2_scierc_full_s1 |\\n| D011 | 2026-05-14 | 推翻之前 ET 计数口径决定——修正 ET triple-counting，每个 entity 只计 | phase2_docred_unconstrained, phase2_docred_semantic_only |\\n| D010 | 2026-05-14 | Dream 三档 Weak Reject (3/6) → 制定 6 项结构性补强计划：post-ho | llama_docred_full_s1, llama_docred_unconstrained, llama_scierc_full_s1 |\\n| D009 | 2026-05-14 | Llama-3.1-8B cross-model 验证升级为 should-have，SciERC- | phase2_scierc_full_s1, phase2_scierc_unconstrained |\\n| D008 | 2026-05-14 | 补跑 DocRED semantic_only 完成跨数据集全消融；论文写作提前至 DocRED 分 | phase2_docred_grammar_only, phase2_docred_full_s1, phase2_scierc_semantic_only |\\n| D007 | 2026-05-14 | S2 降级为架构 ablation，S1 为主推策略；标题去掉 \\\"Guaranteed\\\" 改 \\\"Ne | phase2_scierc_full_s2, phase2_scierc_full_s1 |\\n| D006 | 2026-05-14 | Phase 2 SciERC 核心结果确认：Full S1 DR -94% 且 F1 无损，CF v | phase2_scierc_unconstrained, phase2_scierc_grammar_only, phase2_scierc_semantic_only, phase2_scierc_full_s1, mvp_phase0_docred_schema |\\n| D005 | 2026-05-14 | Phase 2 SciERC 核心结果确认：Full S1 DR↓94% F1无损，CF viola | phase2_scierc_unconstrained, phase2_scierc_grammar_only, phase2_scierc_semantic_only, phase2_scierc_full_s1 |\\n\\n\\n\\n\", \"total_chars\": 3780, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bed4e7d7-fcb2-47b6-9e45-f77ea5359325",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "35522d28-d808-4834-a3f3-bda8315234a8",
  "sourceToolAssistantUUID": "bed4e7d7-fcb2-47b6-9e45-f77ea5359325",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-14T21:43:17.267Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_014A3HZYxsT7E8sS3puCyyqX`</summary>

```json
{
  "project": "schema_semantic_constrained_ie",
  "file": "memory.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "35522d28-d808-4834-a3f3-bda8315234a8",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C1sMgBcEzzozbd9ah6",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6d0d0499-15a5-4d94-82fe-2a890a905af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XjXJcC9nMfRFpK6qrsbSzQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1220,
      "cache_read_input_tokens": 16836,
      "output_tokens": 298,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1220
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 298,
          "cache_read_input_tokens": 16836,
          "cache_creation_input_tokens": 1220,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1220,
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

_source line 18 · 2026-05-14T21:43:17.282Z_

<details><summary>↩ Tool result · `toolu_014A3HZYxsT7E8sS3puCyyqX`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/memory.md\", \"content\": \"# Memory — schema_semantic_constrained_ie\\n\\n## 文献调研 (2026-05-13)\\n\\n### 核心结论: OntoCoDec 的 novelty 成立\\n**没有人做过 \\\"compile IE ontology domain/range → decoding-time logits masking\\\" 的完整 pipeline。**\\n\\nGap 结构：\\n- Syntactic constrained decoding for IE: well-explored (GCD, XGrammar, Outlines)\\n- Vocabulary-level: exists (GENRE, iNERD, AdaKGC)\\n- **Semantic (domain/range) decoding for IE: OPEN GAP** ← OntoCoDec\\n- Semantic type checking at decode time: only for code gen (MGD NeurIPS'23, PLDI'25)\\n- Ontology compliance for IE: only post-processing (ODKE+ Apple'25, OntoLogX'25)\\n\\n最近竞争者：PLDI'25 Type-Constrained Code Gen（同机制但领域是代码生成，必须引用并区分）\\n\\n风险：CRANE (ICML'25) 严格约束可能降低推理质量；Grammar-Aligned Decoding (NeurIPS'24) naive masking 扭曲分布\\n\\nNovelty 定位：\\\"OntoCoDec 将 type-constrained generation 引入信息抽取，编译 IE ontology axioms 为解码时语义约束，预防而非检测 type violations。\\\"\\n\\n详细报告: `artifacts/literature_map.yaml`, `artifacts/literature_survey_*.md`\\n\\n## 实验发现\\n\\n### SciERC Phase 0 — Minimal (2026-05-13)\\n- **go_nogo_metric = 15.4%** (domain_range_violation_rate), 3× 超过 5% 阈值 → GO\\n- Violation 分布极不均匀: Used-for 0.76% vs Compare 42.4% vs Feature-of 33.5%\\n- Feature-of + Compare 贡献 72% 的 domain/range violations\\n- Relation vocabulary violations 仅 1.4%\\n- 关键 insight: OntoCoDec 的价值在于精确靶向高违规 relation types\\n\\n### SciERC Phase 0 — Schema-informed (2026-05-13)\\n- **domain_range_violation_rate = 5.78%**（vs minimal 15.37%, -62.4%）\\n- 仍高于 5% 阈值 → prompt 级干预不足以替代 decoding-time enforcement\\n- Entity type violations 降到 0%，relation vocabulary 降到 0.30%\\n- Per-relation: Feature-of -22.3pp, Part-of -22.5pp, Compare -14.8pp\\n- ⚠️ Evaluate-for 反而退步 +5.8pp — prompt 复杂度反而干扰\\n- McNemar 四类全显著 p<0.01\\n- **论文 story**: LLM 能理解约束（-62%）但执行不完美（仍>5%），需要 hard constraint\\n\\n### DocRED Phase 0 — Minimal (2026-05-13)\\n- **domain_range_violation_rate = 18.7%** (16,540 triples, 998 docs)\\n- Relation vocabulary violation = 28.9% (4,775 triples) — 远高于 SciERC 1.4%\\n- Entity type violation = 7.5% (vs SciERC 0.4%)\\n- JSON parse rate = 96.4% (36 docs 解析失败)\\n- Top violators: P31 instance_of (60.4%, 322/533), P1001 applies_to_jurisdiction (44.4%)\\n- 约束更紧(avg 5.68 pairs)确实导致更高违规(18.7% vs 15.4%)\\n\\n### SciERC vs DocRED 对比 (2026-05-13)\\n| 指标 | SciERC (7 rels) | DocRED (96 rels) |\\n|------|----------------|-----------------|\\n| D/R violation | 15.4% | 18.7% (+3.3pp) |\\n| Relation vocab | 1.4% | 28.9% (+27.5pp) |\\n| Entity type | 0.4% | 7.5% (+7.1pp) |\\n| Avg valid pairs | 26.1 | 5.68 |\\n两个数据集都远超 5% 阈值 → 强 GO 信号。Vocabulary layer 在复杂 schema 上尤为关键。\\n\\n### SciERC Phase 2 — Grammar-only (2026-05-13)\\n- **Grammar 层约束是\\\"免费\\\"的**：零 F1 代价完全消除 rv (1.4%→0%) 和 et (0.4%→0%) violations\\n- entity_f1 delta = -0.03pp ≈ 0，relation_f1 delta = 0\\n- **论文 claim**: \\\"Structural constraints can be enforced at zero quality cost\\\"\\n- DR violation 基本不变 (15.37%→14.84%, -0.53pp) — 符合预期，grammar 不含 D/R 约束\\n- DR 热点: Compare 40.85%, Feature-of 31.98%, Part-of 23.38% — 这些是 semantic 层的目标\\n- **决策依据**: grammar 层可以 always-on，无需 ablation 它的\\\"代价\\\"。论文只需关注 semantic 层的 F1 trade-off。\\n\\n### SciERC Phase 2 — 全量最终结果 (2026-05-14, _v2 干净数据)\\n\\n| Mode | R-F1 | E-F1 | DR% | RV% | ET% | ΔDR |\\n|------|------|------|-----|-----|-----|-----|\\n| unconstrained | 0.0823 | 0.3101 | 15.37% | 1.39% | 0.4% | — |\\n| grammar_only | 0.0823 | 0.3098 | 14.84% | 0% | 0% | -0.53pp |\\n| semantic_only | 0.0815 | 0.3101 | 11.65% | 1.51% | 0.4% | -3.72pp |\\n| **full_s1** | **0.0836** | **0.3098** | **0.93%** | **0%** | **0%** | **-14.44pp (↓94%)** |\\n\\n**核心发现**:\\n- **full_s1 是论文核心结果**: DR 15.37%→0.93% (消除 94%), F1 反而微升 +0.0013, 零质量代价\\n- **semantic_only 有效但不够**: DR -3.72pp (↓24%), 但 RV/ET 未消除（需 grammar 层配合）\\n- 早期污染数据 (108样本) 显示 semantic_only DR=16.43%（误导），干净数据实际 11.65%\\n- **Ablation story**: grammar 处理结构约束 (RV, ET), semantic 处理类型约束 (DR), 合并达最佳效果\\n\\n**Per-relation DR (full_s1)**: Used-for/Hyponym-of/Part-of/Conjunction = 0%, Feature-of 1.21%, Compare 2.82%, Evaluate-for 5.76% (残留最多)\\n\\n### SciERC Phase 2 — S2 全量结果 (2026-05-14)\\n| Mode | R-F1 | E-F1 | DR% | CF% |\\n|------|------|------|-----|-----|\\n| full_s1 | 0.0836 | 0.3098 | 0.93% | 9.90% |\\n| full_s2 | 0.0803 | 0.3190 | 0.97% | 8.03% |\\nS1 全面略优 (R-F1 +0.33pp, DR 持平)，S2 降级为 ablation。\\n\\n### DocRED Phase 2 — 全量最终结果 (2026-05-14, all_set 方法, Reviewer 确认) ⚠️ ET 待 D011 v2 checker 修正\\n\\n| Mode | R-F1 | E-F1 | DR% | RV% | ET% | CF% | Triples |\\n|------|------|------|-----|-----|-----|-----|---------|\\n| **unconstrained** | **7.74%** | **58.15%** | **18.46%** | **29.66%** | **8.18%** | 0.10% | 17,497 |\\n| grammar_only | 8.31% | — | 26.17% | 0.03% | 0% | — | 17,341 |\\n| **full_s1** | **8.23%** | **59.37%** | **10.19%** | **0.03%** | **0%** | 2.57% | 17,372 |\\n| semantic_only | 7.70% | 57.81% | 13.84% | 29.87% | 10.44% | 1.05% | 17,571 |\\n\\n**核心发现**:\\n1. ✅ Grammar 层在 DocRED 完美泛化: ET/RV→0%（与 SciERC 一致）\\n2. ⚠️ **DR 降幅 scaling gap**: SciERC ↓94% (15.37→0.93%) vs DocRED ↓45% (18.46→10.19%)\\n3. ✅ **R-F1 不降反升**: 7.74%→8.23% (+0.49pp)，E-F1 58.15%→59.37% (+1.22pp)\\n4. **论文可 claim：两个数据集上 constrained decoding 均不损失 R-F1**（Reviewer 2026-05-14 确认）\\n5. Grammar-only DR 上升 (18.46→26.17%) 是审稿必问点：grammar 强制 valid relation name 后 entity type 与新 relation 的 domain/range 不匹配加剧，恰好证明 semantic 层必要性\\n6. 残余 DR 集中在特定关系: P190_sister_city 58%, P582_end_time 43.5%, P205_basin_country 37%\\n7. Semantic 层在 grammar 基础上额外贡献: DR 26.17→10.19% (↓61%)\\n\\n### Semantic Fallback 频率分析 (2026-05-14) ⚠️ 论文 §5 + Discussion 关键数据\\n\\n| Model | Dataset | Fallback Rate | Avg/doc | Source | Unit |\\n|-------|---------|--------------|---------|--------|------|\\n| Qwen | SciERC | 0.9% (16/1,729) | 0.03 | post-hoc | triple-level |\\n| Qwen | DocRED | 10.2% (1,770/17,341) | 1.77 | post-hoc | triple-level |\\n| Llama | SciERC | — | ~10.7 | 日志 | token-level |\\n| Llama | DocRED | — | ~57 | 日志 | token-level |\\n\\n**关键发现**:\\n- Qwen DocRED 10.2% triple-level fallback ≈ DR 残余 10.19% — **fallback 精确解释了 DR 残余**\\n- Qwen SciERC 0.9% ≈ DR 残余 0.93% — 同样精确匹配\\n- DocRED >> SciERC 趋势跨模型一致（Llama 也是 ~5.3× 差异）\\n- **⚠️ 单位不可比**: Llama 是 token-level 事件计数（每步 mask 检查），Qwen 是 triple-level DR violation（fallback 下界）。论文中不能直接对比绝对值，只能说趋势一致\\n- 高频 fallback 关系 (Qwen DocRED): parent_taxon 77.8%, unemployment_rate 83.3%, territory_claimed_by 45%\\n- **论文定位**: \\\"Constraint coverage\\\"——semantic masking 实际生效的比例，与 constraint tightness 反相关\\n\\n### Constraint Tightness ↔ DR Violation Scaling (2026-05-14) ⚠️ 论文核心 insight\\n**根因分析确认：DR 差异由约束紧度驱动，非 semantic 层失效。**\\n\\n| Tightness 区间 | Valid pairs | DocRED 聚合 DR | SciERC 对应 |\\n|---------------|-------------|---------------|------------|\\n| ≥ 0.95 (极紧) | 1-2 pairs | 30.6% | 无此类 relation |\\n| 0.90-0.94 | 3-4 pairs | 19.3% | 无此类 relation |\\n| < 0.70 (宽松) | 11+ pairs | 0.7% | SciERC 全部在此区间 |\\n\\n- DocRED avg tightness = 0.842 vs SciERC = 0.333\\n- DocRED 中位数仅允许 5/36 type pairs，SciERC 中位数 23/36\\n- 高 tightness 下 semantic∩grammar=∅ 概率高 → fallback 到 grammar-only → DR 未被约束\\n- SciERC DR 低是因为约束本身宽松，LLM 几乎不可能违规\\n- **论文定位**：effectiveness scales inversely with constraint tightness，这是 **contribution** 而非 weakness（首个 constraint scaling 实证，无文献可比）\\n- **文献确认**：无任何论文在 DocRED 上报告 constrained decoding violation rate，我们是首个 benchmark\\n\\n### CF Violation 根因分析 (2026-05-14)\\n- **CF = 跨字段一致性违规**：同一 entity mention 在 entity list 和 relation head/tail 中被标注为不同类型\\n- 根因: semantic constraint 按 per-relation 独立强制 type，导致 entity-vs-relation type drift\\n- 主要冲突: Generic ↔ OtherScientificTerm (60 次, 占比最高)\\n- grammar_only CF=0.08% → S1 CF=9.90% → **CF 100% 来自 semantic 层**\\n- **论文 limitation**: per-relation 独立 type enforcement 的固有副作用，需 future work 做跨 relation entity type 一致性约束\\n\\n### CF 指标口径澄清 (2026-05-14)\\n- violation_checker: 合并所有 type 来源 (entity list + relation head/tail)，denominator = total_entities (2474)\\n- analyze_cf: 分 WR (Within-Relations) + EVR (Entity-vs-Relation) 两维度，denominator 不同 (checked_slots=3380)\\n- **分子一致**: S1=245=245, S2=178 vs 179 (差 1 due to analyze_cf entity_type_map overwrite bug)\\n- **论文统一用 violation_checker 口径**: S1=9.90%, S2=8.03%\\n\\n### S2 Pilot 调查 (2026-05-13)\\n- **原报告 relation_f1=0 是误读**：数据来自 10 样本 dryrun 的 violation_report，非 pilot50 评估\\n- pilot50 实际 relation_f1=0.1008 (13 TP / 146 pred / 112 gold)，与 unconstrained 0.0823 持平\\n- S2 架构可行，DR violation=0% 达标，F1 瓶颈在 entity span 质量（zero-shot entity F1≈0.29）\\n- FP 根因: 52.6% head+tail 都不匹配 gold（entity span 提取错误以平方级放大到 relation）\\n\\n## 技术路线决策\\n\\n### Phase 1 Compiler 完成 (2026-05-13)\\n**HF transformers + XGrammar (standalone)**，代码在 `/root/schema_semantic_constrained_ie/compiler/`：\\n- `ontology_compiler.py`: compile_type_constraints() + build_processor()\\n- `type_mask_processor.py`: _build_first_token_map(), _mask_entity_type/head/tail_type(), _detect_position()\\n- 24 单元测试 + 12 e2e 测试全部通过\\n- SGLang 作为后续性能优化路径，vLLM 暂不可用\\n\\n### Phase 2 脚本完成 (2026-05-13)\\n`run_constrained_extraction.py` (652 行) 支持 5 模式：unconstrained/grammar_only/semantic_only/full_s1/full_s2\\n- 所有模式 dry-run 通过 + violation_checker 兼容\\n\\n### DocRED constrained decoding 就绪 (2026-05-14)\\n`run_constrained_extraction.py --dataset docred` 零代码修改即可运行 grammar_only / full_s1 模式。\\n约束文件: `data/docred/ontology_constraints_docred.json` (6 entity types, 96 relations)\\n建议命令加 `--max_new_tokens 4096`（文档级比句子级长得多）\\n\\n### Grammar-Semantic 交互 Bug 修复 (2026-05-14)\\n**根因**: `compiler/type_mask_processor.py` → `_apply_type_mask`。full_s1 模式下 XGrammar 将 grammar-invalid tokens 设为有限负值 (-1e10)，TypeConstraintProcessor 将 semantically-disallowed types 设为 -inf。当 `allowed_types` 与 grammar-valid tokens 无交集时，所有 grammar-valid tokens 变为 -inf，而 grammar-invalid tokens 仍为 -1e10 (> -inf) → argmax 选中 grammar-invalid token → XGrammar assertion failure。\\n**修复**: `_apply_type_mask` 增加 `_GRAMMAR_MASK_THRESHOLD = -1e8` 安全检查：应用 semantic mask 前验证至少一个 semantically-allowed type 有非 grammar-masked logit；若无交集则跳过 semantic masking，交由 grammar 控制。\\n**论文意义**: 此 invariant（semantic mask ⊆ grammar allowed set）是双层约束架构的关键设计约束，应在 Method section 明确描述。在 SciERC 上未触发是因为约束更松 (avg 26.1 valid pairs vs DocRED 5.68)。\\n\\n### Llama-3.1-8B 兼容性验证 (2026-05-14)\\n- 模型已在服务器: `/root/autodl-tmp/models/LLM-Research/Meta-Llama-3.1-8B-Instruct`\\n- 零代码修改：AutoTokenizer/AutoModelForCausalLM 模型无关，chat_template 自动适配\\n- XGrammar + TypeConstraintProcessor first-token 唯一性验证通过（SciERC 6 types + DocRED 6 types）\\n- pad_token=None 已有处理逻辑\\n\\n### First-token masking 验证 (2026-05-13)\\n简单 first-token masking 安全可用，不需要 trie-based 方案。\\nSciERC: Task=6262, Method=3523, Material=13415, Metric=54310, OtherScientificTerm=11409, Generic=19964\\nDocRED: PER=9654, ORG=44927, LOC=12052, TIME=18129, NUM=17488, MISC=44\\n上下文无关性已验证。\\n\\n## 方法论决策\\n\\n### R-F1 评估方法 — ✅ 定稿 (2026-05-14, Reviewer 独立确认)\\n- **all_set 方法正确**：OOV predictions 计为 FP，包含在分母中\\n- recognized_set 方法有误：过滤 5189 个 OOV predictions 人为抬高 precision\\n- **定稿 R-F1 数字**：\\n  | 数据集 | Unconstrained | Full S1 | Delta |\\n  |--------|:---:|:---:|:---:|\\n  | SciERC | 8.23% | 8.36% | +0.13pp |\\n  | DocRED | 7.74% | 8.23% | +0.49pp |\\n- **论文可 claim：两个数据集上 constrained decoding 均不损失 R-F1**\\n- §5 评估方法段必须明确描述：DocRED name→PID 归一化流程 + OOV 计为 FP 的处理（审稿必问）\\n\\n### Violation 分类体系 (2026-05-13)\\n4 类独立计数：entity_type / relation_vocabulary / domain_range / cross_field_consistency\\ngo/no-go 阈值 (5%) 基于 domain_range_violation_rate\\n\\n### Fuzzy Matching (2026-05-13)\\nDocRED: token overlap >80% 或 Levenshtein ≤2\\n\\n## §5 写作备忘 (2026-05-14)\\n\\n### Grammar-only DR 上升是审稿必问点\\n- DocRED grammar_only DR=26.17% > unconstrained DR=18.46%\\n- 原因：grammar 强制 valid relation name 后，原来因 RV violation 被过滤的 triples 现在保留，但这些 triples 的 entity type 与新 relation 的 domain/range 可能不匹配\\n- **论文定位**：恰好证明 semantic 层必要性——grammar alone 不仅不够，反而加剧 DR；需要 semantic 层配合\\n- 预写 rebuttal 要点：grammar + semantic 合并后 DR 从 26.17% 降到 10.19% (↓61%)\\n\\n### DocRED 评估方法段写作要点（审稿必问）\\n- 必须明确描述 name→PID 归一化流程（如何匹配模型输出的自然语言 relation name 到 Wikidata PID）\\n- 必须说明 OOV predictions（模型输出的 relation name 无法匹配任何 PID）计为 FP 的处理逻辑\\n- 这两点是审稿人必然攻击面，主动说清楚比被动辩解好\\n\\n### ET 归因修正 (2026-05-14, Reviewer 补充 1)\\n- ❌ 错误归因：\\\"leading spaces in entity type tokens\\\"（strip 已修复 space 问题）\\n- ✅ 正确归因：\\\"trajectory perturbation — constrained logit masking shifts generation distribution, producing non-standard entity types (WORK 823, EVENT 743, ETHNIC_GROUP 137)\\\"\\n- 已修正 section5_docred_draft.tex\\n\\n## 踩坑记录\\n\\n### submit_training_job 必须 bash -c 包裹 (2026-05-13)\\n- tmux session 默认用 `sh` 执行命令，`source` 和 `conda activate` 是 bash built-in\\n- **直接写 `python3 ...` 会 EXIT_CODE=127 (command not found)**\\n- **正确写法**: `bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python3 ...\\\"`\\n\\n### 孤儿进程清理误杀活跃实验 (2026-05-14)\\n- Worker 执行孤儿进程清理时，白名单未包含所有活跃实验 PID → SIGTERM 杀掉了 mvp_phase0_docred_schema 和 semantic_only/full_s1\\n- **防护措施**: 清理前必须查 registry 所有 RUNNING 实验的 PID 全部加入白名单; Kill 前检查输出文件行数是否已达 expected count; 只 kill 具体的孤儿 PID\\n- **恢复方式**: JSONL 逐行追加，用 --resume 从断点恢复\\n\\n### 重提交实验前必须清理旧 tmux session (2026-05-13)\\n- retry 未 kill 旧 tmux → 两进程同时写同一 JSONL → null bytes 污染\\n- **规则**: 重提交前先 `tmux kill-session -t &lt;exp_id>`\\n\\n### tmux kill-session 不保证杀死子进程 (2026-05-14) ⚠️ 新教训\\n- allocate_and_submit 首次返回 \\\"duplicate session\\\" 错误，但底层 python3 子进程 (PID 190246) 已启动且脱离 tmux 控制\\n- 清理 Worker 只杀了 tmux session，未检查子进程是否已死\\n- 第二次 allocate_and_submit 成功，新进程 (PID 190653) 与旧进程同时写同一输出文件 → 数据损坏\\n- **防护措施**: 清理 tmux session 后，必须额外执行 `ps aux | grep &lt;exp_name>` 或 `nvidia-smi | grep python` 确认无残留进程。如有残留，显式 `kill &lt;PID>` 后再提交新实验\\n\\n### 禁止在 allocate_and_submit 命令内放 tmux kill-session (2026-05-14)\\n- allocate_and_submit 在 tmux session 内执行命令，`tmux kill-session -t <同名session>` 导致 session 自杀\\n- cron 追踪死 session → 5× miss → 误判 DONE(failed)\\n- **正确做法**: 单独派 Worker 先清理旧 session，确认后再 allocate_and_submit\\n\\n### Cron PID 追踪不可靠 (2026-05-14)\\n- cron 系统导致 4 次假失败（grammar_only / semantic_only / full_s1 / full_s2），每次假失败触发 cleanup worker 又误杀合法进程，恶性循环\\n- **决策**: 对长期运行实验改用手动 `wc -l` 检查输出文件行数判断完成，不依赖 PID/tmux 存活\\n- 完成判断标准: 输出文件行数 = 目标样本数\\n\\n### Violation report 基于错误文件的风险 (2026-05-14)\\n- phase2_docred_unconstrained 的 violation report 最初基于 Phase 0 的 raw_outputs_docred.jsonl，所有数字与 Phase 0 完全一致\\n- **检测方法**: 对比 report 生成时间 vs 实验完成时间，检查 parse failures 数差异（Phase 0: 36, Phase 2: 12）\\n- **防护**: 完成后必须确认 violation checker 输入的文件路径与实验输出路径一致\\n\\n## 环境信息\\n\\n### westd-16980 (2026-05-13)\\n- GPU: 2× NVIDIA RTX PRO 6000 Blackwell (94GB each)\\n- CUDA 12.8, Python 3.12.3 (conda base)\\n- torch 2.10.0+cu128, transformers 4.57.6\\n- 环境激活: `source /root/miniconda3/etc/profile.d/conda.sh && conda activate base`\\n- 模型路径: `/root/autodl-tmp/models/Qwen3-8B-ms/Qwen/Qwen3-8B`\\n- Llama 模型路径: `/root/autodl-tmp/models/LLM-Research/Meta-Llama-3.1-8B-Instruct`\\n- XGrammar v2 已安装\\n\\n## 数据信息\\n\\n### SciERC\\n- HuggingFace `zj88zj/SCIERC`, 551 sentences, 7 relation types, 17-35 valid pairs each（约束松散）\\n\\n### DocRED\\n- HuggingFace Hub .gz, 998 docs, 96 relation types, avg 5.68 valid pairs/relation (约束紧)\\n\\n## 分析工具 (2026-05-13)\\n- `compare_prompts.py`: minimal vs schema-informed 对比 + McNemar 检验\\n- `violation_checker.py` / `violation_checker_docred.py`: 4 类 violation 分析\\n- ⚠️ Checker 正在做 D011 修复 (ET unique counting)，版本将升级到 `fixed_20260514_v2`\\n\", \"total_chars\": 14556, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6d0d0499-15a5-4d94-82fe-2a890a905af8",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "959fc9dd-f46d-4e65-94fd-1496bbeffa97",
  "sourceToolAssistantUUID": "6d0d0499-15a5-4d94-82fe-2a890a905af8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 19 · 2026-05-14T21:43:22.738Z_

Now let me look at the actual paper draft and related work section.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "959fc9dd-f46d-4e65-94fd-1496bbeffa97",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2CcJjcZmmThnDuDQN",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "571b08b5-97ff-4a80-a185-13b80cb84640",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UtXtrNLvUmVUWqMsZgZCYT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 18056,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18678,
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

_source line 20 · 2026-05-14T21:43:24.117Z_

<details open><summary>🔧 Tool call — Glob · `toolu_011YWTCQcpe9ZBsNdCBshFZw`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "571b08b5-97ff-4a80-a185-13b80cb84640",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2CcJjcZmmThnDuDQN",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a05434cc-fa4b-4553-9f70-117935e1d57f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UtXtrNLvUmVUWqMsZgZCYT",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 18056,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18678,
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

_source line 21 · 2026-05-14T21:43:24.146Z_

<details><summary>↩ Tool result · `toolu_011YWTCQcpe9ZBsNdCBshFZw`</summary>

```text
artifacts/_project/paper/paper_tables_draft.tex
artifacts/_project/paper/section5_scierc_draft_4796e8.tex
artifacts/_project/paper/abstract_fd4b26.tex
artifacts/_project/paper/abstract_d3264e.tex
artifacts/_project/paper/section7_conclusion_550cbf.tex
artifacts/dream_reports/dream_20260514T094226/best/paper.tex
artifacts/dream_reports/dream_20260514T094226/median/paper.tex
artifacts/dream_reports/dream_20260514T094226/worst/paper.tex
artifacts/_project/paper/section5_docred_draft_9b84f1.tex
artifacts/_project/paper/discussion_paragraphs_cf83d1.tex
artifacts/_project/paper/section5_scierc_draft.tex
artifacts/_project/paper/section6_relwork_outline.tex
artifacts/_project/paper/section6_relwork_additions.tex
artifacts/_project/paper/discussion_paragraphs.tex
artifacts/dream_reports/dream_20260514T205155/best/paper.tex
artifacts/_project/paper/section7_conclusion.tex
artifacts/dream_reports/dream_20260514T205155/median/paper.tex
artifacts/dream_reports/dream_20260514T205155/worst/paper.tex
artifacts/_project/paper/section6_related_work.tex
artifacts/_project/paper/section7_conclusion_compressed.tex
artifacts/_project/paper/appendix_discussion.tex
artifacts/_project/paper/section3_violation_landscape.tex
artifacts/_project/paper/section2_background.tex
artifacts/_project/paper/section1_introduction_draft.tex
artifacts/_project/paper/section4_composition_draft.tex
artifacts/_project/paper/section5_docred_draft.tex
artifacts/_project/paper/section5_crossmodel_draft.tex
artifacts/_project/paper/main.tex
artifacts/_project/paper/appendix_related_work.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/section3_method_draft.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a05434cc-fa4b-4553-9f70-117935e1d57f",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "f13d3495-669f-4f76-acae-6399a884bdd5",
  "sourceToolAssistantUUID": "a05434cc-fa4b-4553-9f70-117935e1d57f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-14T21:43:24.652Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01MMCZD2Y6iqJeHYZxSc8BKJ`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f13d3495-669f-4f76-acae-6399a884bdd5",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2CcJjcZmmThnDuDQN",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "84148712-abb2-4c17-92f5-f5d0200be6f7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UtXtrNLvUmVUWqMsZgZCYT",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18678,
      "cache_read_input_tokens": 18056,
      "output_tokens": 199,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 18678
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 199,
          "cache_read_input_tokens": 18056,
          "cache_creation_input_tokens": 18678,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 18678,
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

_source line 23 · 2026-05-14T21:43:24.669Z_

<details><summary>↩ Tool result · `toolu_01MMCZD2Y6iqJeHYZxSc8BKJ`</summary>

```text
artifacts/dream_reports/dream_20260514T094226/median/references.bib
artifacts/_project/paper/relwork_new_entries.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "84148712-abb2-4c17-92f5-f5d0200be6f7",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "a68c15d4-e668-4520-95bc-010892fcd1b6",
  "sourceToolAssistantUUID": "84148712-abb2-4c17-92f5-f5d0200be6f7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-14T21:43:27.309Z_

<details open><summary>🔧 Tool call — Read · `toolu_01EytsHy8t8QkDxXmZV4gR9d`</summary>

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
  "parentUuid": "a68c15d4-e668-4520-95bc-010892fcd1b6",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2k8stb418XZr87gSM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "00e7f6f9-8335-4b74-baf5-05ddf1e7a8fc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EkHfmjmE2UQq7HoEi6F8GA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 805,
      "cache_read_input_tokens": 36734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 805,
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

_source line 25 · 2026-05-14T21:43:27.315Z_

<details><summary>↩ Tool result · `toolu_01EytsHy8t8QkDxXmZV4gR9d`</summary>

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
18	\title{OntoCoDec: Near-Complete Type-Valid Information Extraction\\via Compiled Ontology Constraints}
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
52	
53	% === §6 Related Work ===
54	\input{section6_related_work}
55	
56	% === §7 Discussion and Conclusion ===
57	\section{Discussion and Conclusion}
58	\label{sec:discussion}
59	\input{section7_conclusion_compressed}
60	
61	% === Bibliography ===
62	\bibliography{relwork_new_entries}
63	
64	% === Appendix ===
65	\appendix
66	
67	\input{appendix_related_work}
68	\input{appendix_discussion}
69	
70	\end{document}
71	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "00e7f6f9-8335-4b74-baf5-05ddf1e7a8fc",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "f46b880a-af1d-4ca9-bf5e-bd5430c5f7b2",
  "sourceToolAssistantUUID": "00e7f6f9-8335-4b74-baf5-05ddf1e7a8fc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-14T21:43:27.754Z_

<details open><summary>🔧 Tool call — Read · `toolu_01F3Y5zQLRPy5vLn9PhaFehE`</summary>

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
  "parentUuid": "f46b880a-af1d-4ca9-bf5e-bd5430c5f7b2",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2k8stb418XZr87gSM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4d15c64a-ca8b-4c37-96b3-6d4ea0ffe8e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EkHfmjmE2UQq7HoEi6F8GA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 805,
      "cache_read_input_tokens": 36734,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 805,
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

_source line 27 · 2026-05-14T21:43:27.758Z_

<details><summary>↩ Tool result · `toolu_01F3Y5zQLRPy5vLn9PhaFehE`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Grammar-Constrained Decoding.}
5	XGrammar~\cite{dong2025xgrammar}, Outlines~\cite{willard2023outlines}, and LMQL~\cite{beurer-kellner2023lmql} have made grammar-constrained decoding the standard for structured LLM output, ensuring every token belongs to a grammar-valid continuation.
6	DOMINO~\cite{beurer-kellner2024domino} and ASAp~\cite{park2024grammar} further address distribution distortion, making grammar enforcement statistically principled.
7	However, these methods operate at the syntactic level---they ensure format validity but cannot enforce cross-field semantic constraints such as ontology domain/range rules.
8	
9	\paragraph{Semantic Constrained Decoding for Code.}
10	In code generation, constrained decoding has been extended to enforce semantic properties: Synchromesh~\cite{synchromesh_iclr2022} enforces type and scope constraints via dynamic token masks; PICARD~\cite{scholak2021picard} performs incremental SQL parsing to reject type-invalid tokens; MGD~\cite{mgd_neurips2023} applies static-analysis monitors for type checking at decode time; and \citet{pldi2025_type_constrained_codegen} compile full type systems into prefix automata for logits masking.
11	These demonstrate that richer-than-CFG constraints are feasible at decode time, but exclusively in the code domain---OntoCoDec migrates this paradigm to information extraction.
12	
13	\paragraph{Vocabulary and Type-Constrained Generation.}
14	\citet{roth_yih_2004} establish that relational type compatibility should be a hard constraint via integer linear programming, though applied post-hoc.
15	GENRE~\cite{decao2021genre}, AdaKGC~\cite{adakgc_emnlp2023}, GCD~\cite{geng2023gcd}, and GoLLIE~\cite{sainz2024gollie} constrain \emph{which tokens} can appear (vocabulary membership) but not \emph{which type combinations} are valid for a given relation---OntoCoDec enforces relational constraints where the valid set depends on the relation type generated earlier in the same sequence.
16	
17	\paragraph{Structural Constraints via Training.}
18	UIE~\cite{lu2022uie}, GoLLIE~\cite{sainz2024gollie}, KnowCoder~\cite{knowcoder_acl2024}, and CodeIE~\cite{li2023codeie} encode IE structure through training or schema-as-code prompting.
19	These provide \emph{soft} guidance---the model learns to prefer valid outputs but cannot guarantee compliance, as shown by non-trivial violation rates even in fine-tuned systems.
20	OntoCoDec provides complementary \emph{hard} enforcement that is training-free and composable with these methods.
21	
22	\paragraph{Post-hoc Ontology Validation.}
23	ODKE+~\cite{khorshidi2025odke} uses ontology snippets as prompt context; OntoGPT~\cite{spires_2024} validates outputs against ontologies in a second pass; OntoLogX~\cite{ontologx_2025} applies SHACL validation with iterative re-prompting, reducing violations by ${\sim}10\times$ across correction rounds.
24	These detect-then-fix approaches waste compute on violated outputs, whereas OntoCoDec \emph{prevents} violations during decoding by redirecting probability mass to valid alternatives.
25	
26	\paragraph{Quality Impact of Constrained Decoding.}
27	CRANE~\cite{banerjee2025crane} shows grammar restrictions suppress chain-of-thought reasoning, \citet{schall2025hiddencost} find 10--30\% degradation on reasoning tasks, and \citet{tam2024letmespeak} demonstrate that format constraints harm reasoning benchmarks.
28	However, \citet{tam2024letmespeak}'s results also show extraction-style tasks are robust to---or benefit from---constraints, and IE is fundamentally extraction rather than reasoning.
29	OntoCoDec confirms this: violations decrease by 94\% on SciERC with zero F1 degradation, as constraints target only type tokens while leaving entity spans unconstrained.
30	
31	\medskip
32	\noindent
33	OntoCoDec is the first system to automatically compile IE ontology domain/range constraints into token-level semantic masks, extending grammar-constrained decoding from syntactic to semantic enforcement for information extraction.
34	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4d15c64a-ca8b-4c37-96b3-6d4ea0ffe8e0",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "38fd1d26-19ec-4fe3-a913-504fc63c3138",
  "sourceToolAssistantUUID": "4d15c64a-ca8b-4c37-96b3-6d4ea0ffe8e0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-14T21:43:28.264Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SNwXLCG6CefC4XHPH4BEbk`</summary>

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
  "parentUuid": "38fd1d26-19ec-4fe3-a913-504fc63c3138",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C2k8stb418XZr87gSM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9e55ea8b-7942-47f8-89b3-53c1a3e117df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EkHfmjmE2UQq7HoEi6F8GA",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 805,
      "cache_read_input_tokens": 36734,
      "output_tokens": 252,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 805
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 252,
          "cache_read_input_tokens": 36734,
          "cache_creation_input_tokens": 805,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 805,
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

_source line 29 · 2026-05-14T21:43:28.270Z_

<details><summary>↩ Tool result · `toolu_01SNwXLCG6CefC4XHPH4BEbk`</summary>

```text
1	% Section 1: Introduction (compressed, 669→~550 words)
2	
3	\section{Introduction}
4	\label{sec:introduction}
5	
6	Large language models are increasingly deployed for zero-shot information extraction~\cite{li2023codeie,sainz2024gollie,wei2023zeroshot}, but when generating relation triples $(h, r, t)$, neither entity is guaranteed to carry a type consistent with the ontology's domain/range constraints for $r$.
7	We call such outputs \emph{domain/range violations}---structurally valid triples that are ontologically invalid.
8	In a systematic study, we find violations are pervasive: 15.4\% of triples on SciERC~\cite{luan2018scierc} and 18.7\% on DocRED~\cite{yao2019docred}, driven by \emph{constraint tightness} (few valid type pairs per relation) rather than ontology scale.
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
25	    \item The first systematic study of ontological constraint violations in LLM-based IE, showing that violation rates are driven by constraint tightness rather than ontology size, and that prompt-level intervention is per-relation unreliable.
26	    \item OntoCoDec, a two-layer compiled constraint framework that enforces cross-field type validity during autoregressive IE---the first to extend grammar-constrained decoding with semantic ontology constraints.
27	    \item Empirical validation on 2 models $\times$ 2 datasets: DR $\downarrow$94\% on SciERC and $\downarrow$45--90\% on DocRED at zero F1 cost, with model-agnostic generalization.
28	\end{enumerate}
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "9e55ea8b-7942-47f8-89b3-53c1a3e117df",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "cb0a8299-4998-4d68-bb6e-32a5640525e5",
  "sourceToolAssistantUUID": "9e55ea8b-7942-47f8-89b3-53c1a3e117df",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-14T21:43:31.354Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CV7tSKFpkUdv3rC9WzfH7k`</summary>

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
  "parentUuid": "cb0a8299-4998-4d68-bb6e-32a5640525e5",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C31cnnooonSyXzFEE3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "5c222d9b-d0bc-48c1-9072-32c06d897d18",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012nc6psebqp7fo6MKtWAJkd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3066,
      "cache_read_input_tokens": 37539,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3066,
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

_source line 31 · 2026-05-14T21:43:31.359Z_

<details><summary>↩ Tool result · `toolu_01CV7tSKFpkUdv3rC9WzfH7k`</summary>

```text
1	\begin{abstract}
2	LLM-based information extraction systems produce systematic ontology constraint violations during autoregressive generation.
3	On SciERC (7 relation types), 15.37\% of extracted triples violate domain/range type constraints; on DocRED (96 relation types), 18.46\%---comparable rates governed by \emph{constraint tightness} rather than ontology scale.
4	%
5	We present \textsc{OntoCoDec}, which compiles IE ontology schemas into two composable decoding constraint layers:
6	(1)~a \emph{grammar layer} (XGrammar CFG) enforcing JSON structural validity and restricting entity/relation vocabularies to schema-defined values (ET, RV\,$\to$\,0\%); and
7	(2)~a \emph{semantic layer} enforcing domain/range constraints via a stateful entity registry and dynamic logit masking.
8	The grammar layer is an enabling prerequisite; the two compose via bitwise AND on token-level masks.
9	%
10	On SciERC, \textsc{OntoCoDec} reduces domain/range violations by 94\% (15.37\%\,$\to$\,0.93\%) while maintaining extraction F1 ({+}0.13pp, $p{=}0.58$).
11	On DocRED, violations decrease by 45--90\% depending on the model, with significant F1 gains for Qwen3-8B ({+}0.50pp, $p{<}0.001$) and F1-neutral impact for Llama-3.1-8B (DR$\downarrow$90.2\%).
12	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1
13	The dual-factor mechanism---tightness $\times$ baseline violation rate---explains cross-dataset and cross-model DR reduction differences.
14	\end{abstract}
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5c222d9b-d0bc-48c1-9072-32c06d897d18",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "c64587c5-44de-4523-9a83-c3b8fc8251c5",
  "sourceToolAssistantUUID": "5c222d9b-d0bc-48c1-9072-32c06d897d18",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-14T21:43:31.825Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TUkUHdCQYtsSkmRi1vYhDS`</summary>

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
  "parentUuid": "c64587c5-44de-4523-9a83-c3b8fc8251c5",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C31cnnooonSyXzFEE3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "41980335-ce0e-40f9-9251-de4732e22b1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012nc6psebqp7fo6MKtWAJkd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3066,
      "cache_read_input_tokens": 37539,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3066,
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

_source line 33 · 2026-05-14T21:43:31.832Z_

<details><summary>↩ Tool result · `toolu_01TUkUHdCQYtsSkmRi1vYhDS`</summary>

```text
1	% Section 3 — Method (Draft)
2	% OntoCoDec: Near-Complete Type-Valid Information Extraction
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
28	\paragraph{Ontology schema.}
29	An ontology $\mathcal{O} = (\mathcal{E}, \mathcal{R}, \operatorname{dom}, \operatorname{range})$ defines entity types $\mathcal{E}$, relation types $\mathcal{R}$, and functions $\operatorname{dom}, \operatorname{range}: \mathcal{R} \to 2^{\mathcal{E}}$ specifying permitted head and tail types for each relation.
30	
31	\paragraph{Ontology compliance.}
32	A triple $(h, r, t)$ with $\operatorname{type}(h) = \tau^h$, $\operatorname{type}(t) = \tau^t$ is \emph{type-valid} w.r.t.\ $\mathcal{O}$ iff:
33	%
34	\begin{equation}\label{eq:type-valid}
35	  \tau^h \in \operatorname{dom}(r) \;\wedge\; \tau^t \in \operatorname{range}(r).
36	\end{equation}
37	%
38	Our goal is a decoding strategy maximizing $P(y \mid x)$ subject to ontology compliance: all triples must be type-valid under $\mathcal{O}$, and $y$ must be well-formed JSON conforming to Eq.~\eqref{eq:output-schema}.
39	
40	\paragraph{Constraint decidability.}
41	Not all ontology constraints are enforceable at every point during left-to-right generation.
42	We distinguish three classes by \emph{prefix-decidability}:
43	%
44	\begin{enumerate}[leftmargin=*,nosep]
45	  \item \textbf{Local constraints} depend only on the current token position.
46	    Entity-type membership ($\tau_i \in \mathcal{E}$) and relation-vocabulary membership ($r_j \in \mathcal{R}$) are local.
47	  \item \textbf{Prefix-decidable constraints} depend on previously generated context.
48	    Domain/range constraints are prefix-decidable: once head type and relation type are generated, valid tail types are fully determined.
49	  \item \textbf{Non-local constraints} depend on information not yet generated (e.g., forward coreference) and fall outside single-pass decoding.
50	\end{enumerate}
51	%
52	The grammar layer handles class~(1); the semantic layer handles class~(2).
53	
54	
55	\subsection{Grammar Layer}
56	\label{sec:grammar}
57	
58	The grammar layer compiles $\mathcal{O}$ into a context-free grammar (CFG) enforced at every decoding step via logit masking.
59	This compilation proceeds in two stages.
60	
61	\paragraph{Schema-to-grammar compilation.}
62	We generate a JSON Schema encoding the structure in Eq.~\eqref{eq:output-schema} with \texttt{enum} constraints restricting entity types to $\mathcal{E}$ and relation types to $\mathcal{R}$.
63	This schema is compiled into an EBNF grammar via XGrammar~\cite{dong2025xgrammar}, producing a pushdown automaton tracking JSON structure and enum membership.
64	
65	\paragraph{Logit masking.}
66	At step $t$, the automaton computes grammar-valid tokens $G(t) \subseteq V$; all others receive logits $-\infty$.
67	This simultaneously enforces: (i)~structural validity (well-formed JSON), (ii)~relation vocabulary membership ($r_j \in \mathcal{R}$), and (iii)~entity type membership ($\tau_i \in \mathcal{E}$).
68	Domain/range constraints are \emph{not} enforced, as they depend on entity types within each triple—the gap filled by the semantic layer.
69	
70	\paragraph{Empirical profile.}
71	On SciERC, grammar constraints eliminate relation vocabulary violations entirely (1.39\%\,$\to$\,0\%) and entity type violations entirely (0.40\%\,$\to$\,0\%), with no measurable F1 impact.
72	Domain/range violations remain effectively unchanged (15.37\%\,$\to$\,14.84\%), confirming that grammar constraints enforce structural but not semantic validity.
73	
74	
75	\subsection{Semantic Layer}
76	\label{sec:semantic}
77	
78	The semantic layer enforces domain/range constraints through a stateful logits processor maintaining an entity registry during generation.
79	
80	\subsubsection{Entity Registry}
81	\label{sec:entity-registry}
82	
83	As the model generates the entity list, the semantic layer builds a registry $\mathcal{D}: \text{name} \to \text{type}$ mapping each entity to its declared type.
84	This registry is populated incrementally: when the model completes an entry $\{n_i, \tau_i\}$, the pair $(n_i, \tau_i)$ is added to $\mathcal{D}$.
85	The registry is then consulted during relation generation to look up the declared types of head and tail entities.
86	
87	\subsubsection{Position Detection}
88	\label{sec:position-detection}
89	
90	At each step $t$, the processor determines which field is currently being generated by pattern-matching on the decoded prefix.
91	We define five field positions---\textsc{EntityType}, \textsc{RelationType}, \textsc{HeadType}, \textsc{TailType}, and \textsc{FreeText}---identified via JSON key patterns (e.g., tokens following \texttt{"head\_type":} indicate \textsc{HeadType}).
92	Semantic masks activate only at type-bearing positions (\textsc{HeadType}, \textsc{TailType}).
93	
94	\subsubsection{Dynamic Masking}
95	\label{sec:dynamic-masking}
96	
97	At type-bearing positions, the processor computes a semantic mask $S(t) \subseteq V$ restricting generation to type-valid tokens.
98	
99	\paragraph{Head type masking.}
100	At a \textsc{HeadType} position, the processor considers the entity registry $\mathcal{D}$ and the current relation type $r_j$ (if already generated).
101	If $h_j \in \mathcal{D}$ and $\mathcal{D}[h_j] \in \operatorname{dom}(r_j)$, the mask allows only that registered type: $S(t) = \{\operatorname{tok}(\mathcal{D}[h_j])\}$, ensuring consistency with both the entity list and domain constraints.
102	Otherwise, if $r_j$ is known, the mask falls back to all domain-valid types: $S(t) = \{\operatorname{tok}(\tau) : \tau \in \operatorname{dom}(r_j)\}$.
103	If $r_j$ is unavailable, no semantic mask is applied.
104	
105	\paragraph{Tail type masking.}
106	At a \textsc{TailType} position, valid tail types are computed from $\operatorname{range}(r_j)$; if $t_j \in \mathcal{D}$, the mask further restricts to the registered type when range-valid.
107	This implements the core prefix-decidable constraint: once $(h_j, r_j, \tau^h_j)$ are known, valid $\tau^t_j$ values are fully determined by $\operatorname{range}(r_j)$.
108	
109	\paragraph{Implementation.}
110	Each $\tau \in \mathcal{E}$ is mapped to the token ID of its first subword token; we pre-verify uniqueness across all entity types, which holds for both SciERC and DocRED (6 types each) with the Qwen3-8B tokenizer.
111	The semantic mask is applied by setting logits of disallowed first-token IDs to $-\infty$.
112	
113	\subsubsection{Grammar-Semantic Interaction}
114	\label{sec:interaction}
115	
116	The final mask is the conjunction of $G(t)$ and $S(t)$, permitting only tokens satisfying both layers (formalized in \S\ref{sec:composition}).
117	This embodies an \emph{enabling dependency}: semantic lookup requires relation types to be valid members of $\mathcal{R}$, guaranteed only by the grammar layer.
118	Without grammar enforcement, the model may generate out-of-vocabulary relation types for which no $\operatorname{dom}$/$\operatorname{range}$ rules exist.
119	Empirically, semantic-only constraints reduce DR by only 24\% (15.37\%\,$\to$\,11.65\%) while failing to eliminate vocabulary violations; the full combination achieves 94\% DR reduction.
120	When $S(t) \cap G(t) = \emptyset$---the semantic layer would mask out all grammar-valid tokens---the system falls back to grammar-only control, preserving structural validity at the cost of a potential type violation.
121	This \emph{grammar-first invariant} reflects a deliberate priority ordering: structural integrity is a hard constraint, while type violations are soft errors detectable by downstream validation.
122	
123	
124	\subsection{Decoding Strategies}
125	\label{sec:strategies}
126	
127	\paragraph{S1: Single-pass decoding.}
128	Both constraint layers are active throughout a single generation pass.
129	The entity registry is populated as entities are generated and immediately available for relation-level type checking.
130	This is the simpler and recommended strategy, achieving strong constraint enforcement with higher relation F1 than the two-pass alternative.
131	
132	\paragraph{S2: Two-pass decoding.}\label{sec:s2}
133	The first pass generates only entities under grammar constraints; the extracted entities compile an input-dependent grammar that additionally constrains head and tail names to match declared entities.
134	The second pass generates relations under this tighter grammar plus semantic constraints.
135	Detailed comparison is provided in the appendix.
136	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "41980335-ce0e-40f9-9251-de4732e22b1f",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "30c37d55-b031-4144-93b2-da34c61ed32c",
  "sourceToolAssistantUUID": "41980335-ce0e-40f9-9251-de4732e22b1f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-14T21:43:32.275Z_

<details open><summary>🔧 Tool call — Read · `toolu_01G2awU3wPTM4XFSMyMDCqDc`</summary>

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
  "parentUuid": "30c37d55-b031-4144-93b2-da34c61ed32c",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C31cnnooonSyXzFEE3",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "cc9775dc-86c1-4d02-8c22-a3fb10c4bef0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012nc6psebqp7fo6MKtWAJkd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3066,
      "cache_read_input_tokens": 37539,
      "output_tokens": 252,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 3066
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 252,
          "cache_read_input_tokens": 37539,
          "cache_creation_input_tokens": 3066,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 3066,
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

_source line 35 · 2026-05-14T21:43:32.282Z_

<details><summary>↩ Tool result · `toolu_01G2awU3wPTM4XFSMyMDCqDc`</summary>

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
28	This dual-factor mechanism---tightness $\times$ baseline model violation rate---explains the cross-dataset pattern: SciERC ($\bar{\tau}{=}0.333$, 24 valid pairs/relation) achieves 94--99\% DR reduction, while DocRED ($\bar{\tau}{=}0.842$, 5.68 pairs) achieves 45--90\%, with the residual modulated by model-specific baselines (\S\ref{sec:cross-model}).
29	
30	\paragraph{Decidability Taxonomy.}
31	We classify ontology constraints by when sufficient information becomes available:
32	%
33	\begin{enumerate}[leftmargin=*,nosep]
34	  \item \textbf{Local}: require only the current token (entity/relation vocabulary membership). Handled by the grammar layer.
35	  \item \textbf{Prefix-decidable}: require the decoded prefix (domain/range constraints). Handled by the semantic layer via the entity registry.
36	  \item \textbf{Non-local}: require information not yet generated (forward coreference). Outside the scope of single-pass decoding; partially addressed by the two-pass strategy (S2, \S\ref{sec:s2}).
37	\end{enumerate}
38	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "cc9775dc-86c1-4d02-8c22-a3fb10c4bef0",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "6341edc5-6e40-48b4-af47-b878b12597bb",
  "sourceToolAssistantUUID": "cc9775dc-86c1-4d02-8c22-a3fb10c4bef0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-14T21:43:40.161Z_

<details open><summary>🔧 Tool call — Read · `toolu_01S7Gb9Kt8XzG8jLW9QogTmx`</summary>

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
  "parentUuid": "6341edc5-6e40-48b4-af47-b878b12597bb",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3JnuZoD9K79ZDD9cf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8b44b5fe-73fb-4a90-840b-9d9668202bde",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RgS67tf8zYsyD2rb2i36E8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4848,
      "cache_read_input_tokens": 40605,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4848,
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

_source line 37 · 2026-05-14T21:43:40.175Z_

<details><summary>↩ Tool result · `toolu_01S7Gb9Kt8XzG8jLW9QogTmx`</summary>

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
10	\textbf{SciERC}~\cite{luan2018scierc} (551 test sentences, 7 relations, avg.\ 26.1 valid type pairs per relation) and \textbf{DocRED}~\cite{yao2019docred} (998 dev documents, 96 relations, avg.\ 5.68 valid pairs).
11	We measure four violation categories: \textbf{Domain/Range (DR)} violations where $(\mathrm{type}(h), \mathrm{type}(t)) \notin \sigma(r)$; \textbf{Relation Vocabulary (RV)} where $r \notin \mathcal{R}$; \textbf{Entity Type (ET)} where $e \notin \mathcal{E}$; and \textbf{Cross-Field Consistency (CF)} where the same entity receives different types across triples.
12	Cross-model validation with Llama-3.1-8B-Instruct is reported in \S\ref{sec:cross-model}.
13	
14	\paragraph{Violation distribution.}
15	Table~\ref{tab:prompt_comparison} reports violation rates.
16	DR violations affect 15.37\% of triples on SciERC and 18.70\% on DocRED---comparable rates despite a 14$\times$ difference in ontology size---indicating that violation severity is driven by \emph{constraint tightness} rather than ontology scale.
17	RV violations on DocRED are dramatically higher (28.90\% vs.\ 1.39\%), indicating that 96 relation types exceed the model's capacity to reproduce a target vocabulary from a single prompt.
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
32	\multirow{2}{*}{DocRED} & Unconstrained & 18.7 & 28.9 & 7.5 & 0.1 \\
33	 & Schema-informed & 12.8 & 18.4 & 0.6 & 0.2 \\
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
47	Schema-informed prompting---augmenting the prompt with valid type pairs---reduces DR by 62.4\% on SciERC but only 31.3\% on DocRED (Table~\ref{tab:prompt_comparison}), and is unreliable per-relation: DR for \textsc{Evaluate-for} \emph{increases} by 5.8\,pp.
48	These limitations motivate decoding-time enforcement (\S\ref{sec:method}).
49	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8b44b5fe-73fb-4a90-840b-9d9668202bde",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "b191edf9-ea79-454e-b822-63c2088a2979",
  "sourceToolAssistantUUID": "8b44b5fe-73fb-4a90-840b-9d9668202bde",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-14T21:43:40.468Z_

<details open><summary>🔧 Tool call — Read · `toolu_012AtpKc7h2x3iPDxFXvxWuR`</summary>

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
  "parentUuid": "b191edf9-ea79-454e-b822-63c2088a2979",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3JnuZoD9K79ZDD9cf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d798d773-10ad-4570-9a97-53c64177b725",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RgS67tf8zYsyD2rb2i36E8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4848,
      "cache_read_input_tokens": 40605,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4848,
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

_source line 39 · 2026-05-14T21:43:40.480Z_

<details><summary>↩ Tool result · `toolu_012AtpKc7h2x3iPDxFXvxWuR`</summary>

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
23	\begin{tabular}{@{}l rrrrr rr@{}}
24	\toprule
25	& \multicolumn{5}{c}{\textbf{Violation Rates (\%)}}
26	& \multicolumn{2}{c}{\textbf{F1}} \\
27	\cmidrule(lr){2-6} \cmidrule(l){7-8}
28	\textbf{Mode}
29	  & DR\,$\downarrow$ & $\Delta$DR
30	  & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
31	  & Rel.\,$\uparrow$ & Ent.\,$\uparrow$ \\
32	\midrule
33	Unconstrained
34	  & 15.37 & ---
35	  & 1.39  & 0.40
36	  & 0.08
37	  & 8.23  & 31.01 \\
38	Grammar
39	  & 14.84 & $\downarrow$3\%
40	  & \textbf{0} & \textbf{0}
41	  & 0.08
42	  & 8.23  & 30.98 \\
43	Semantic
44	  & 11.65 & $\downarrow$24\%
45	  & 1.51  & 0.40
46	  & 2.71
47	  & 8.15  & 31.01 \\
48	Full (S1)
49	  & \textbf{0.93} & $\downarrow$\textbf{94\%}
50	  & \textbf{0} & \textbf{0}
51	  & 9.90
52	  & \textbf{8.36} & 30.98 \\
53	Full (S2)
54	  & 0.97  & $\downarrow$94\%
55	  & \textbf{0} & \textbf{0}
56	  & 8.03
57	  & 8.03  & \textbf{31.90} \\
58	\bottomrule
59	\end{tabular}
60	\caption{Five-way ablation on SciERC (551 documents, Qwen3-8B, zero-shot).
61	DR: domain/range violation rate;
62	RV: relation vocabulary violation rate;
63	ET: entity type violation rate;
64	CF: cross-field consistency violation rate.
65	$\Delta$DR: relative DR reduction vs.\ the unconstrained baseline.
66	$\downarrow$\,/\,$\uparrow$: lower\,/\,higher is better.
67	Best per column in \textbf{bold} (CF excluded---see text).
68	F1 scores are multiplied by 100.
69	Statistical significance assessed via bootstrap resampling (10{,}000 iterations).}
70	\label{tab:scierc-ablation}
71	\end{table}
72	
73	% ──────────────────────────────────────────
74	%  (a) Core result
75	% ──────────────────────────────────────────
76	\paragraph{Core result: near-complete DR elimination at zero F1 cost.}
77	The full two-layer constraint configuration (S1) reduces domain/range
78	violations from 15.37\% to 0.93\%, a 94\% relative reduction,
79	% phase2_scierc_unconstrained: DR=0.1537; phase2_scierc_full_s1: DR=0.0093
80	while relation F1 moves from 8.23 to 8.36 ($+$0.13\,pp; bootstrap 95\% CI [$-$0.24, $+$0.58]\,pp, $p = 0.58$, 10{,}000 iterations).
81	% phase2_scierc_unconstrained: R-F1=0.0823; phase2_scierc_full_s1: R-F1=0.0836
82	% bootstrap: delta=+0.13pp, CI=[-0.24,+0.58], p=0.5824
83	The difference is not statistically significant ($p = 0.58$), confirming
84	that constraint enforcement is F1-neutral on this dataset.
85	At the per-relation level, violations drop from 42.42\% to 2.82\% on
86	\textsc{Compare}, from 33.54\% to 1.21\% on \textsc{Feature-of}, and
87	reach 0\% on four of seven relation types
88	(\textsc{Conjunction}, \textsc{Hyponym-of}, \textsc{Part-of},
89	\textsc{Used-for}).
90	% phase2_scierc_full_s1 per_relation_dr: Compare=0.0282,
91	%   Feature-of=0.0121, Hyponym-of=0, Part-of=0, Used-for=0, Conjunction=0
92	However, full constraint enforcement elevates cross-field consistency
93	violations from 0.08\% to 9.90\%;
94	% phase2_scierc_unconstrained: CF=0.0008; phase2_scierc_full_s1: CF=0.099
95	we analyze this trade-off in Section~\ref{sec:discussion}.
96	
97	% ──────────────────────────────────────────
98	%  (b) Grammar layer
99	% ──────────────────────────────────────────
100	\paragraph{Grammar layer: cost-free structural guarantees.}
101	Grammar-only constraints completely eliminate both relation vocabulary
102	violations (1.39\%\,$\to$\,0\%) and entity type violations
103	(0.40\%\,$\to$\,0\%), with no measurable impact on F1
104	(R-F1 8.23, E-F1 30.98).
105	% phase2_scierc_grammar_only: RV=0, ET=0, R-F1=0.0823, E-F1=0.3098
106	Domain/range violations remain effectively unchanged
107	(15.37\%\,$\to$\,14.84\%, $-$0.53\,pp), confirming that grammar
108	constraints enforce output structure---valid JSON, correct relation
109	vocabulary, valid entity types---but do not address cross-field
110	semantic constraints.
111	% phase2_scierc_grammar_only: DR=0.1484
112	The grammar layer thus provides two categories of violation elimination
113	at zero cost, establishing the structural preconditions on which the
114	semantic layer depends.
115	
116	% ──────────────────────────────────────────
117	%  (c) Enabling dependency
118	% ──────────────────────────────────────────
119	\paragraph{Enabling dependency: grammar enables semantic enforcement.}
120	Applying semantic constraints alone reduces DR by only 24\%
121	(15.37\%\,$\to$\,11.65\%) and, critically, cannot eliminate
122	relation vocabulary violations (RV\,=\,1.51\%) or entity type
123	violations (ET\,=\,0.40\%).
124	% phase2_scierc_semantic_only: DR=0.1165, RV=0.0151, ET=0.004
125	When the grammar layer is added (Full S1), DR drops a further 92\%
126	relative to the semantic-only configuration
127	(11.65\%\,$\to$\,0.93\%).
128	% phase2_scierc_full_s1: DR=0.0093; delta=(11.65-0.93)/11.65=0.920
129	This demonstrates an \emph{enabling dependency} rather than mere
130	additivity: without grammar-enforced vocabulary constraints, the
131	semantic layer encounters out-of-vocabulary relation types for which
132	no domain/range rules exist, rendering its type checking ineffective.
133	The two layers are therefore complementary with a prerequisite
134	structure---grammar must be active for semantic constraints to reach
135	their full enforcement capacity.
136	
137	% ──────────────────────────────────────────
138	%  (d) S1 vs S2
139	% ──────────────────────────────────────────
140	\paragraph{S1 vs.\ S2: single-pass suffices.}
141	The two-pass strategy (S2) achieves comparable DR
142	(0.97\% vs.\ 0.93\%) but lower relation F1
143	(8.03 vs.\ 8.36, $-$0.33\,pp) and generates fewer relation triples
144	(1{,}644 vs.\ 1{,}729).
145	% phase2_scierc_full_s2: DR=0.0097, R-F1=0.0803, triples=1644
146	% phase2_scierc_full_s1: DR=0.0093, R-F1=0.0836, triples=1729
147	S2 shows a modestly lower CF rate (8.03\% vs.\ 9.90\%), but both
148	configurations exhibit substantially elevated CF relative to the
149	unconstrained baseline (0.08\%), indicating that two-pass decoding
150	does not resolve the cross-field consistency trade-off
151	(Section~\ref{sec:discussion}).
152	% phase2_scierc_full_s2: CF=0.0803; phase2_scierc_full_s1: CF=0.099
153	The two-pass separation offers no clear advantage over single-pass
154	enforcement; we adopt S1 as the primary configuration for its
155	simplicity and marginally stronger extraction performance.
156	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d798d773-10ad-4570-9a97-53c64177b725",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "1765f1c2-36bc-4008-bf9c-61779e127737",
  "sourceToolAssistantUUID": "d798d773-10ad-4570-9a97-53c64177b725",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-14T21:43:40.637Z_

<details open><summary>🔧 Tool call — Read · `toolu_014Df2qopa5nQ3NCgZyafaAp`</summary>

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
  "parentUuid": "1765f1c2-36bc-4008-bf9c-61779e127737",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3JnuZoD9K79ZDD9cf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ed93342e-abf5-435b-a35c-851390463bf4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01RgS67tf8zYsyD2rb2i36E8",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4848,
      "cache_read_input_tokens": 40605,
      "output_tokens": 260,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4848
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 260,
          "cache_read_input_tokens": 40605,
          "cache_creation_input_tokens": 4848,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4848,
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

_source line 41 · 2026-05-14T21:43:40.642Z_

<details><summary>↩ Tool result · `toolu_014Df2qopa5nQ3NCgZyafaAp`</summary>

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
19	\begin{tabular}{@{}l rrrrr rr@{}}
20	\toprule
21	& \multicolumn{5}{c}{\textbf{Violation Rates (\%)}}
22	& \multicolumn{2}{c}{\textbf{F1}} \\
23	\cmidrule(lr){2-6} \cmidrule(l){7-8}
24	\textbf{Mode}
25	  & DR\,$\downarrow$ & $\Delta$DR
26	  & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
27	  & Rel.\,$\uparrow$ & Ent.\,$\uparrow$ \\
28	\midrule
29	Unconstrained
30	  & 18.46 & ---
31	  & 29.66 & 2.48
32	  & 0.10
33	  & 7.74  & 58.15 \\
34	Grammar
35	  & 26.17 & $\uparrow$42\%
36	  & \textbf{0.03} & \textbf{0}
37	  & 0.07
38	  & \textbf{8.31}  & \textbf{59.38} \\
39	Semantic
40	  & 13.84 & $\downarrow$25\%
41	  & 29.87 & 4.22
42	  & 1.05
43	  & 7.70  & 57.81 \\
44	Full (S1)
45	  & \textbf{10.21} & $\downarrow$\textbf{45\%}
46	  & \textbf{0.03} & \textbf{0}
47	  & 2.57
48	  & 8.23  & 59.37 \\
49	\bottomrule
50	\end{tabular}
51	\caption{Four-way ablation on DocRED (998 documents, Qwen3-8B, zero-shot).
52	$\Delta$DR: relative change vs.\ unconstrained.
53	Best per column in \textbf{bold} (CF excluded).
54	F1 $\times$100. Bootstrap significance: R-F1 $+$0.50\,pp ($p < 0.001$).}
55	\label{tab:docred-ablation}
56	\end{table}
57	
58	% exp_ids: phase2_docred_unconstrained, phase2_docred_full_s1
59	\paragraph{Core result.}
60	Full S1 reduces DR from 18.46\% to 10.21\% ($\downarrow$45\%), eliminates ET (2.48\%\,$\to$\,0\%), and near-eliminates RV (29.66\%\,$\to$\,0.03\%).
61	Relation F1 improves from 7.74 to 8.23 ($+$0.50\,pp; bootstrap 95\% CI [$+$0.23, $+$0.81], $p < 0.001$), attributable to grammar-layer elimination of 5{,}189 OOV relation predictions counted as false positives.
62	CF increases modestly (0.10\%\,$\to$\,2.57\%), lower than SciERC's 9.90\%.
63	
64	% exp_ids: phase2_docred_grammar_only
65	\paragraph{Grammar layer surfaces latent violations.}
66	Grammar-only constraints eliminate RV and ET but \emph{increase} DR from 18.46\% to 26.17\% ($+$42\%).
67	This counter-intuitive result has a structural explanation: the unconstrained baseline's 29.66\% OOV relation triples cannot be evaluated for DR (no schema entry exists); grammar enforcement assigns these triples valid relation names whose domain/range rules the associated entity types frequently violate.
68	The grammar layer thus \emph{reveals} latent type incompatibilities, directly motivating the semantic layer.
69	
70	% exp_ids: phase2_docred_semantic_only, phase2_docred_full_s1
71	\paragraph{Enabling dependency.}
72	Semantic-only constraints reduce DR by only 25\% (18.46\%\,$\to$\,13.84\%) while failing to eliminate RV (29.87\%) or ET (4.22\%).
73	Full S1 achieves a further 26\% relative reduction over semantic-only (13.84\%\,$\to$\,10.21\%), replicating the enabling dependency from SciERC: without grammar-enforced vocabulary, the semantic layer encounters OOV relation types for which no domain/range rules exist.
74	
75	% exp_ids: phase2_docred_full_s1, llama_docred_full_s1
76	\paragraph{Constraint tightness governs enforcement ceiling.}
77	The residual DR on DocRED (10.21\%) exceeds SciERC (0.93\%) due to per-relation \emph{constraint tightness}: DocRED relations average 5.68 valid type pairs ($\bar{\tau}{=}0.842$) vs.\ 24 on SciERC ($\bar{\tau}{=}0.333$).
78	Tighter constraints produce narrower grammar$\cap$semantic mask intersections, increasing fallback frequency---the aggregate fallback rate (10.2\%; 1{,}770/17{,}341 triples) closely tracks residual DR (10.21\%), confirming a near-bijection between fallback events and residual violations.
79	Crucially, tightness interacts with the model's baseline violation profile: Qwen's high RV (29.66\%) causes grammar enforcement to surface many latent DR violations, yielding 10.21\% residual DR; Llama's lower RV (16.03\%) limits this surfacing, achieving 2.55\% residual ($\downarrow$90.2\%) on the same ontology (\S\ref{sec:cross-model}).
80	This dual-factor mechanism---tightness $\times$ baseline RV---explains cross-dataset and cross-model DR reduction differences.
81	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ed93342e-abf5-435b-a35c-851390463bf4",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "499d5f89-c2ca-4923-9510-90aa1ae9e4d9",
  "sourceToolAssistantUUID": "ed93342e-abf5-435b-a35c-851390463bf4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 42 · 2026-05-14T21:43:44.937Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GTesFYAVpJPW8WJgYtuiCm`</summary>

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
  "parentUuid": "499d5f89-c2ca-4923-9510-90aa1ae9e4d9",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3vax7cE573SoEguvv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "90292658-c9ee-4d80-890d-88d0a0420c0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FuBXTDSfveWXBprPBEG9vy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6290,
      "cache_read_input_tokens": 45453,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6290,
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

_source line 43 · 2026-05-14T21:43:44.942Z_

<details><summary>↩ Tool result · `toolu_01GTesFYAVpJPW8WJgYtuiCm`</summary>

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
17	\begin{tabular}{@{}ll rrrr rr@{}}
18	\toprule
19	& & \multicolumn{4}{c}{\textbf{Violation Rates (\%)}}
20	& \multicolumn{2}{c}{\textbf{F1}} \\
21	\cmidrule(lr){3-6} \cmidrule(l){7-8}
22	\textbf{Dataset} & \textbf{Model}
23	  & DR\,$\downarrow$ & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
24	  & Rel. & Ent. \\
25	\midrule
26	\multirow{4}{*}{SciERC}
27	  & Qwen (U)  & 15.37 & 1.39 & 0.40 & 0.08 & 8.23 & 31.01 \\
28	  & Qwen (S1) &  0.93 & 0    & 0    & 9.90 & 8.36 & 30.98 \\
29	  \cmidrule(l){2-8}
30	  & Llama (U)  & 13.34 & 0.55 & 0    & 0.24 & 2.68 & 23.56 \\
31	  & Llama (S1) &  0.08 & 0    & 0    & 6.56 & 2.54 & 23.49 \\
32	\midrule
33	\multirow{4}{*}{DocRED}
34	  & Qwen (U)  & 18.46 & 29.66 & 2.48 & 0.10 & 7.74 & 58.15 \\
35	  & Qwen (S1) & 10.21 &  0.03 & 0    & 2.57 & 8.23 & 59.37 \\
36	  \cmidrule(l){2-8}
37	  & Llama (U)  & 26.07 & 16.03 & 0.13 & 0.17 & 5.98 & 55.65 \\
38	  & Llama (S1) &  2.55 &  0    & 0    & 12.02 & 6.27 & 55.01 \\
39	\bottomrule
40	\end{tabular}
41	\caption{Cross-model validation. U: unconstrained; S1: full two-layer.
42	Parse failures (U$\to$S1): Qwen DocRED 12$\to$11, Llama DocRED 68$\to$91; others $\leq$1.
43	F1 $\times$100.}
44	\label{tab:cross-model}
45	\end{table}
46	
47	\paragraph{Model-agnostic structural guarantees.}
48	RV and ET violations are eliminated ($\leq$0.03\%) for both models on both datasets, confirming that grammar-layer enforcement depends on the decoding mechanism, not model-specific generation patterns.
49	
50	% exp_ids: phase2_scierc_full_s1, llama_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1
51	\paragraph{DR reduction generalizes but varies by model.}
52	SciERC DR drops 94\% for Qwen (15.37\%\,$\to$\,0.93\%) and 99.4\% for Llama (13.34\%\,$\to$\,0.08\%); DocRED DR drops 45\% for Qwen and 90.2\% for Llama.
53	R-F1 is preserved or improves in all cases (Qwen: $+$0.13/$+$0.50\,pp; Llama: $-$0.14/$+$0.29\,pp).
54	
55	\paragraph{Tightness $\times$ RV interaction explains cross-model asymmetry.}
56	Llama's relative DR reduction exceeds Qwen's on both datasets.
57	This asymmetry reflects the interaction between constraint tightness and model-specific violation profiles (\S\ref{sec:docred-results}): Qwen's higher baseline RV (29.66\% vs.\ 16.03\% on DocRED) causes grammar enforcement to surface more latent DR violations---triples whose OOV relation names masked underlying type incompatibilities.
58	With Llama's lower RV, fewer triples undergo this surfacing, yielding residual DR of 2.55\% vs.\ Qwen's 10.21\% on the same ontology ($\bar{\tau}{=}0.842$).
59	This confirms the dual-factor model: constraint tightness sets the enforcement difficulty ceiling, while baseline RV modulates the realized residual DR.
60	
61	\paragraph{CF trade-off.}
62	CF violations increase under S1 for both models (Qwen: 0.08\%\,$\to$\,9.90\% SciERC, 0.10\%\,$\to$\,2.57\% DocRED; Llama: 0.24\%\,$\to$\,6.56\% SciERC, 0.17\%\,$\to$\,12.02\% DocRED), confirming CF elevation as a systematic property of per-relation independent enforcement (\S\ref{sec:discussion}).
63	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "90292658-c9ee-4d80-890d-88d0a0420c0f",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "e8b3ea8d-f90c-433b-9e2d-dd17926a0be9",
  "sourceToolAssistantUUID": "90292658-c9ee-4d80-890d-88d0a0420c0f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 44 · 2026-05-14T21:43:45.897Z_

<details open><summary>🔧 Tool call — Read · `toolu_01L2korTRu3eBDS2ALcLNB1V`</summary>

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
  "parentUuid": "e8b3ea8d-f90c-433b-9e2d-dd17926a0be9",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3vax7cE573SoEguvv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "5dbba274-d159-4477-bd67-19e6ab90fab5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FuBXTDSfveWXBprPBEG9vy",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6290,
      "cache_read_input_tokens": 45453,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6290,
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

_source line 45 · 2026-05-14T21:43:45.901Z_

<details><summary>↩ Tool result · `toolu_01L2korTRu3eBDS2ALcLNB1V`</summary>

```text
1	% Section 7 — Discussion and Conclusion (compressed)
2	% Full discussion paragraphs moved to Appendix B.
3	
4	\paragraph{Discussion.}
5	% exp_ids: phase2_scierc_full_s1 (CF=9.90%), phase2_scierc_grammar_only (CF=0.08%),
6	%          phase2_docred_full_s1 (CF=2.57%), llama_docred_full_s1 (CF=12.02%)
7	Cross-field consistency (CF) violations are qualitatively different from DR violations: each triple remains individually type-valid, but the same entity may receive different types across relations.
8	Ablation cleanly attributes CF to the semantic layer (grammar-only: CF\,=\,0.08\%; full S1: 9.90\% SciERC, 2.57\% DocRED for Qwen3-8B; 12.02\% DocRED for Llama-3.1-8B), arising from per-relation independent enforcement.
9	% exp_ids: phase2_scierc_grammar_only, phase2_docred_full_s1, llama_docred_full_s1
10	The F1 significance divergence between DocRED ($+$0.50\,pp, $p < 0.001$) and SciERC ($+$0.13\,pp, $p = 0.58$) traces to grammar-layer elimination of OOV relation names: DocRED's baseline RV of 29.66\% (5{,}189 false-positive predictions) vs.\ SciERC's 1.39\%.
11	% exp_ids: phase0_docred_unconstrained, phase0_scierc_unconstrained
12	
13	\paragraph{Contributions.}
14	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1
15	We presented OntoCoDec, a framework compiling IE ontology schemas into token-level decoding constraints.
16	We conducted the first systematic study of ontological constraint violations in LLM-based IE, finding that violation severity is driven by constraint tightness $\bar{\tau}$ rather than ontology scale.
17	Our two-layer architecture---grammar (RV, ET\,$\to$\,0\%) plus semantic (domain/range enforcement)---achieves 45--99\% DR reduction across two models and two datasets while preserving extraction quality.
18	
19	\paragraph{Limitations.}
20	% exp_ids: phase2_scierc_full_s1, llama_docred_full_s1
21	The semantic layer introduces CF violations (up to 12.02\%), a systematic consequence of per-relation independent enforcement that remains an open challenge.
22	Constrained decoding increases parse failures for some configurations (Llama-3.1-8B DocRED: 9.1\% vs.\ 6.8\% unconstrained).
23	Results cover two 8B-class models under zero-shot prompting; integration with fine-tuned models has not been explored.
24	
25	\paragraph{Future Work.}
26	Global entity-level type consensus during decoding offers the most direct path to resolving CF violations.
27	Validation with fine-tuned models, larger scales, and non-English ontologies remains to be explored.
28	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "5dbba274-d159-4477-bd67-19e6ab90fab5",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "ce5fca3b-c0a3-4009-aa5c-934867c3e8bb",
  "sourceToolAssistantUUID": "5dbba274-d159-4477-bd67-19e6ab90fab5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 46 · 2026-05-14T21:43:46.123Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SjFZ1y1usf9VY5ZaRrfUG3`</summary>

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
  "parentUuid": "ce5fca3b-c0a3-4009-aa5c-934867c3e8bb",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C3vax7cE573SoEguvv",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "19e3d8be-d20c-42e3-b860-ee4b1a61f8f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FuBXTDSfveWXBprPBEG9vy",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6290,
      "cache_read_input_tokens": 45453,
      "output_tokens": 256,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6290
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 256,
          "cache_read_input_tokens": 45453,
          "cache_creation_input_tokens": 6290,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6290,
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

_source line 47 · 2026-05-14T21:43:46.128Z_

<details><summary>↩ Tool result · `toolu_01SjFZ1y1usf9VY5ZaRrfUG3`</summary>

```text
1	% Appendix B — Extended Discussion
2	% Contains discussion paragraphs moved from the main text during compression.
3	
4	\section{Extended Discussion}\label{app:discussion}
5	
6	%%% Paragraph 1: Low F1 Practical Significance %%%
7	% exp_ids: phase2_scierc_full_s1 (R-F1=8.36%), phase2_docred_full_s1 (R-F1=8.23%),
8	%          phase0_scierc_unconstrained (DR=15.37%), phase2_docred_unconstrained (DR=18.46%)
9	
10	\paragraph{Practical Significance of Zero-Shot F1.}
11	Our reported relation F1 of approximately 8\% on both SciERC and DocRED reflects the inherent difficulty of zero-shot closed IE, where the model receives no task-specific training examples.
12	For reference, supervised state-of-the-art systems on SciERC achieve approximately 49--53\% relation F1 with full training data~\citep{zhong2021frustratingly,ye2022packed}.
13	Constraint enforcement operates largely independently of the extraction model's intrinsic capability: it restricts the output space to ontologically valid triples regardless of the underlying model's accuracy.
14	When applied to fine-tuned models that reach competitive F1 levels, the same constraints remain necessary---Phase~0 analysis confirms that even well-prompted models exhibit non-trivial violation rates (15.37\% DR on SciERC, 18.46\% on DocRED).
15	% exp_ids: phase0_scierc_unconstrained, phase2_docred_unconstrained
16	In our evaluation, F1 serves as a \emph{control variable} verifying that constraint enforcement does not degrade extraction quality, not as an optimization target.
17	The contribution of this work is the constraint enforcement method itself; the zero-shot setting isolates its effect from confounds introduced by task-specific fine-tuning.
18	
19	%%% Paragraph 4: Decoding-Time vs. Post-Hoc Enforcement %%%
20	% exp_ids: posthoc_filtering_baseline, phase2_scierc_full_s1 (R-F1=8.36%),
21	%          phase2_docred_full_s1 (R-F1=8.23%, ET=0%)
22	
23	\paragraph{Decoding-Time vs.\ Post-Hoc Enforcement.}
24	Post-hoc filtering---generating triples without constraints, then removing schema-violating predictions---yields higher precision and consequently higher F1 than OntoCoDec on both datasets (SciERC 8.63 vs.\ 8.36; DocRED 9.61 vs.\ 8.23).
25	% posthoc: SciERC F1=8.63, DocRED F1=9.61; OntoCoDec: SciERC R-F1=8.36, DocRED R-F1=8.23
26	However, this precision gain comes at substantial cost.
27	On DocRED, post-hoc filtering discards 48.1\% of all predicted triples, including 127 true positives (11.2\% of correct predictions), reducing recall from 9.46\% to 8.40\%.
28	% posthoc_docred: rejection=48.1%, tp_lost=127/1137, R: 9.46→8.40
29	Entity type violations remain unresolved (ET\,=\,2.47\% vs.\ OntoCoDec's 0\%), as filtering targets only domain/range and vocabulary violations.
30	% posthoc_docred: ET_residual=2.47%; phase2_docred_full_s1: ET=0%
31	OntoCoDec's decoding-time approach avoids this information loss by guiding generation toward compliant outputs rather than discarding non-compliant ones, preserving both recall and entity type validity.
32	The two strategies are complementary: post-hoc filtering can serve as an additional safety net for residual violations that decoding-time enforcement does not fully resolve.
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "19e3d8be-d20c-42e3-b860-ee4b1a61f8f1",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "1a8059c0-16fe-4c7c-baf6-46cc279bd057",
  "sourceToolAssistantUUID": "19e3d8be-d20c-42e3-b860-ee4b1a61f8f1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 48 · 2026-05-14T21:43:48.985Z_

Now let me check the related work section and the dream review reports for additional context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1a8059c0-16fe-4c7c-baf6-46cc279bd057",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C4KwtGoYhs7vpFRcAX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d0eaf627-2957-44aa-890e-24a0854e5deb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Na1G7hdrycteodewrnSae6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3907,
      "cache_read_input_tokens": 51743,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3907,
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

_source line 49 · 2026-05-14T21:43:49.471Z_

<details open><summary>🔧 Tool call — Read · `toolu_01TP8aGhdpmAQat6vWFRsvHz`</summary>

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
  "parentUuid": "d0eaf627-2957-44aa-890e-24a0854e5deb",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C4KwtGoYhs7vpFRcAX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7b6f058f-4ebc-4f31-bbd7-09ece6ac53ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Na1G7hdrycteodewrnSae6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3907,
      "cache_read_input_tokens": 51743,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3907,
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

_source line 50 · 2026-05-14T21:43:49.476Z_

<details><summary>↩ Tool result · `toolu_01TP8aGhdpmAQat6vWFRsvHz`</summary>

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
85	Soft-constraint approaches such as ontology-weighted beam scoring reduce violation frequency but cannot eliminate it, whereas OntoCoDec achieves near-complete to substantial elimination (DR$\downarrow$94\% on SciERC, $\downarrow$45\% on DocRED).
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
98	OntoCoDec addresses this concern empirically: domain/range violations decrease by 94\% on SciERC (15.37\%$\to$0.93\%) and 45\% on DocRED, with \emph{zero} F1 degradation on SciERC (R-F1 8.36\% vs.\ 8.23\% unconstrained, $+$0.13pp, not statistically significant).
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
109	Unlike training-based IE systems, OntoCoDec is training-free and achieves near-complete to substantial elimination of type violations at inference time (DR$\downarrow$94\% on SciERC, $\downarrow$45\% on DocRED); unlike post-hoc validation, it prevents violations rather than detecting them, redirecting probability mass to valid alternatives with zero quality cost on SciERC (R-F1 8.36\% vs.\ 8.23\% unconstrained).
110	The two constraint layers---grammar (structural) and semantic (relational)---compose via bitwise AND with an enabling dependency: the grammar layer ensures every generated type token belongs to the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type.
111	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7b6f058f-4ebc-4f31-bbd7-09ece6ac53ac",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "3291268e-a2c0-481c-bb3d-264867db0f7f",
  "sourceToolAssistantUUID": "7b6f058f-4ebc-4f31-bbd7-09ece6ac53ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 51 · 2026-05-14T21:43:50.741Z_

<details open><summary>🔧 Tool call — Read · `toolu_01HHeEVWN8kKDg1CsRnZwcui`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/dream_reports/dream_20260514T205155/best/paper.tex",
  "limit": 100
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3291268e-a2c0-481c-bb3d-264867db0f7f",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C4KwtGoYhs7vpFRcAX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a409a9e7-a838-4b86-84cf-458fad10705b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Na1G7hdrycteodewrnSae6",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3907,
      "cache_read_input_tokens": 51743,
      "output_tokens": 218,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 3907
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 218,
          "cache_read_input_tokens": 51743,
          "cache_creation_input_tokens": 3907,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 3907,
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

_source line 52 · 2026-05-14T21:43:50.750Z_

<details><summary>↩ Tool result · `toolu_01HHeEVWN8kKDg1CsRnZwcui`</summary>

```text
1	\documentclass[11pt,a4paper]{article}
2	\usepackage[utf8]{inputenc}
3	\usepackage[T1]{fontenc}
4	\usepackage{times}
5	\usepackage{graphicx}
6	\usepackage{amsmath,amssymb}
7	\usepackage{booktabs}
8	\usepackage{multirow}
9	\usepackage{xcolor}
10	\usepackage{url}
11	\usepackage[margin=2.5cm]{geometry}
12	\usepackage{hyperref}
13	\usepackage{natbib}
14	\usepackage{array}
15	\usepackage{tabularx}
16	
17	\newcommand{\sys}{OntoCoDec}
18	\newcommand{\dr}{domain/range}
19	\newcommand{\rv}{relation vocabulary}
20	\newcommand{\et}{entity type}
21	\newcommand{\cf}{cross-field consistency}
22	
23	\title{\sys{}: Near-Complete Type-Valid Information Extraction\\via Compiled Ontology Constraints}
24	
25	\author{
26	  Anonymous EMNLP Submission
27	}
28	\date{}
29	
30	\begin{document}
31	\maketitle
32	
33	% ============================================================
34	\begin{abstract}
35	Large language models (LLMs) applied to information extraction (IE) produce systematic ontology constraint violations---15.4\% of extracted triples violate domain/range type constraints on SciERC and 18.7\% on DocRED. We show that these violations concentrate on relation types with tight type constraints (e.g., Compare: 42.4\%) rather than scaling with ontology size, and that prompt-level intervention, while reducing overall violations by 62\%, remains unreliable at the per-relation level, with one relation type exhibiting \emph{increased} violations.
36	
37	We present \sys{}, a framework that automatically compiles IE ontology schemas into two composable constraint layers for LLM decoding: (1) a \emph{grammar layer} enforcing JSON structure and type/relation vocabulary via context-free grammars, and (2) a \emph{semantic layer} enforcing cross-field domain/range constraints through a stateful entity registry with dynamic logit masking. The two layers compose via bitwise AND with an enabling dependency: grammar ensures vocabulary validity, enabling the semantic layer to look up and enforce domain/range rules.
38	
39	Evaluated on SciERC (7 relations) and DocRED (96 relations) with Qwen3-8B and Llama-3.1-8B, \sys{} reduces domain/range violations by 94\% on SciERC (15.4\%$\to$0.93\%) and 44.7--90.2\% on DocRED, while eliminating entity-type and relation-vocabulary violations entirely. F1 impact is neutral on SciERC ($p{=}0.58$) and significantly positive on DocRED ($+0.50$pp relation F1, $p{<}0.001$). We provide a decidability taxonomy classifying constraint types by their amenability to autoregressive enforcement and identify cross-field consistency as an inherent limitation of per-relation independent enforcement.
40	\end{abstract}
41	
42	% ============================================================
43	\section{Introduction}
44	\label{sec:intro}
45	
46	Information extraction (IE) systems built on large language models achieve impressive zero-shot performance by framing extraction as structured generation. However, when an ontology defines type constraints on relations---e.g., that \textsc{Used-for} requires a \textsc{Method} head and a \textsc{Task} tail---LLMs routinely violate these constraints in their output.
47	
48	We conduct the first systematic study of ontology constraint violations in LLM-based IE. Our violation landscape analysis across two datasets (SciERC with 7 relations, DocRED with 96) reveals two key findings: (1) domain/range violations are non-trivial (15.4\% and 18.7\% respectively) and concentrate on relation types with tight constraints rather than scaling with ontology size; (2) schema-informed prompting reduces violations by 62\% overall but is unreliable at the per-relation level---Evaluate-for violations \emph{increase} by 5.8 percentage points even when constraints are explicitly described in the prompt.
49	
50	These findings motivate \sys{}, a framework that compiles ontology schemas into decoder constraints operating at two complementary layers. The \textbf{grammar layer} uses context-free grammars (via XGrammar) to enforce JSON structure, entity type vocabulary, and relation name vocabulary---constraints that are decidable from the token prefix alone. The \textbf{semantic layer} maintains a stateful entity registry during generation and applies dynamic logit masking to enforce domain/range constraints---which require cross-field state but remain prefix-decidable given the registry.
51	
52	The two layers exhibit an \emph{enabling dependency}: grammar ensures every generated relation name belongs to the valid vocabulary, which is a prerequisite for the semantic layer to look up the corresponding domain/range rules. Without grammar, the semantic layer encounters out-of-vocabulary relation names and cannot enforce constraints (semantic-only achieves 24\% DR reduction vs.\ full system 94\%).
53	
54	We classify constraints into a decidability taxonomy: (a) purely local constraints (entity type $\in$ vocabulary), enforceable by grammar alone; (b) prefix-decidable with state (domain/range compatibility), requiring the semantic layer's entity registry; and (c) truly non-local constraints (forward coreference), which are out of scope for forward-only autoregressive decoding.
55	
56	Our contributions:
57	\begin{enumerate}
58	\item A systematic violation landscape study establishing that LLM-based IE produces non-trivial, tightness-driven ontology violations, and that prompt-level intervention is insufficient (\S\ref{sec:landscape}).
59	\item A composable two-layer constraint framework with principled decidability taxonomy, compiling ontology schemas into grammar and semantic decoder constraints (\S\ref{sec:method}).
60	\item Comprehensive experiments on 2 datasets $\times$ 2 models showing 94\% DR elimination on SciERC at zero F1 cost, with honest analysis of the cross-field consistency trade-off (\S\ref{sec:experiments}).
61	\item A cross-model generalization study demonstrating zero-code-modification transfer across model families, with a dual-factor analysis explaining DR reduction variance (\S\ref{sec:experiments}).
62	\end{enumerate}
63	
64	% ============================================================
65	\section{Background}
66	\label{sec:background}
67	
68	\paragraph{IE as Structured Generation.} Modern LLM-based IE frames extraction as generating JSON-structured output containing entity lists and relation triples. Each triple $(h, r, t)$ associates a head entity $h$ with type $\tau_h$, a relation $r$, and a tail entity $t$ with type $\tau_t$. An ontology schema $\mathcal{O}$ defines the valid entity types $\mathcal{T}$, relation types $\mathcal{R}$, and for each $r \in \mathcal{R}$, the domain $\text{dom}(r) \subseteq \mathcal{T}$ and range $\text{ran}(r) \subseteq \mathcal{T}$.
69	
70	\paragraph{Constraint Violations.} We define four violation types:
71	\begin{itemize}
72	\item \textbf{Entity type (ET)}: $\tau_h \notin \mathcal{T}$ or $\tau_t \notin \mathcal{T}$
73	\item \textbf{Relation vocabulary (RV)}: $r \notin \mathcal{R}$
74	\item \textbf{Domain/range (DR)}: $\tau_h \notin \text{dom}(r)$ or $\tau_t \notin \text{ran}(r)$
75	\item \textbf{Cross-field consistency (CF)}: same entity assigned different types across relations
76	\end{itemize}
77	
78	\paragraph{Grammar-Constrained Decoding.} Recent work on grammar-constrained decoding (e.g., XGrammar) enforces context-free grammar constraints during autoregressive generation by masking logits at each decoding step. This guarantees structural validity (e.g., valid JSON) but cannot enforce cross-field semantic constraints that depend on previously generated content.
79	
80	\paragraph{Constraint Tightness.} We define the \emph{constraint tightness} $\tau_r$ of a relation $r$ as:
81	\begin{equation}
82	\bar{\tau}_r = 1 - \frac{|\text{dom}(r)| \times |\text{ran}(r)|}{|\mathcal{T}|^2}
83	\end{equation}
84	Higher tightness means fewer valid type combinations, predicting higher violation rates.
85	
86	% ============================================================
87	\section{Violation Landscape Study}
88	\label{sec:landscape}
89	
90	We conduct a systematic study of ontology constraint violations in zero-shot LLM-based IE using Qwen3-8B on SciERC (551 abstracts, 7 relations) and DocRED (998 documents, 96 relations).
91	
92	% --- Experiment 1: SciERC minimal prompt ---
93	\subsection{SciERC Violation Profile}
94	\label{sec:scierc-violations}
95	
96	Table~\ref{tab:per-relation-dr} presents per-relation domain/range violation rates under a minimal prompt (relation list only, no constraint descriptions). The overall DR violation rate is 15.4\% (265 of 1,724 triples), but the distribution is highly non-uniform: Compare exhibits 42.4\% violations while Used-for shows only 0.8\%.
97	
98	\begin{table}[t]
99	\centering
100	\small
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a409a9e7-a838-4b86-84cf-458fad10705b",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "d8c6a3fb-8405-4126-9e00-55fd912d6e28",
  "sourceToolAssistantUUID": "a409a9e7-a838-4b86-84cf-458fad10705b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 53 · 2026-05-14T21:43:53.999Z_

Now let me also look at the bibliography entries.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d8c6a3fb-8405-4126-9e00-55fd912d6e28",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C4fkm2D3UHx67Ttipf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f28516db-0e80-4051-8f52-c3234c0422e2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01McTrf444LKDwdibBd1NxBF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7742,
      "cache_read_input_tokens": 55650,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7742,
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

_source line 54 · 2026-05-14T21:43:56.331Z_

<details open><summary>🔧 Tool call — Read · `toolu_019PLoJwTst8ob96AVFtTaWm`</summary>

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
  "parentUuid": "f28516db-0e80-4051-8f52-c3234c0422e2",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C4fkm2D3UHx67Ttipf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4f0c423c-9cec-4ad8-a1b9-fda80554d30e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01McTrf444LKDwdibBd1NxBF",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7742,
      "cache_read_input_tokens": 55650,
      "output_tokens": 109,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7742
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 109,
          "cache_read_input_tokens": 55650,
          "cache_creation_input_tokens": 7742,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7742,
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

_source line 55 · 2026-05-14T21:43:56.344Z_

<details><summary>↩ Tool result · `toolu_019PLoJwTst8ob96AVFtTaWm`</summary>

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
401	% Dataset & model references (5 entries)
402	% ============================================================
403	
404	% Confirmed via: ACL Anthology D18-1360, arXiv:1808.09602
405	@inproceedings{luan2018scierc,
406	  title     = {Multi-Task Identification of Entities, Relations, and Coreference for Scientific Knowledge Graph Construction},
407	  author    = {Luan, Yi and He, Luheng and Ostendorf, Mari and Hajishirzi, Hannaneh},
408	  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},
409	  pages     = {3219--3232},
410	  year      = {2018},
411	  address   = {Brussels, Belgium},
412	  url       = {https://aclanthology.org/D18-1360/}
413	}
414	
415	% Confirmed via: ACL Anthology P19-1074, arXiv:1906.06127
416	@inproceedings{yao2019docred,
417	  title     = {{DocRED}: A Large-Scale Document-Level Relation Extraction Dataset},
418	  author    = {Yao, Yuan and Ye, Deming and Li, Peng and Han, Xu and Lin, Yankai and Liu, Zhenghao and Liu, Zhiyuan and Huang, Lixin and Zhou, Jie and Sun, Maosong},
419	  booktitle = {Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
420	  pages     = {764--777},
421	  year      = {2019},
422	  address   = {Florence, Italy},
423	  url       = {https://aclanthology.org/P19-1074/}
424	}
425	
426	% Confirmed via: arXiv:2302.10205, Semantic Scholar
427	@article{wei2023zeroshot,
428	  title   = {{ChatIE}: Zero-Shot Information Extraction via Chatting with {ChatGPT}},
429	  author  = {Wei, Xiang and Cui, Xingyu and Cheng, Ning and Wang, Xiaobin and Zhang, Xin and Huang, Shen and Xie, Pengjun and Xu, Jinan and Chen, Yufeng and Zhang, Meishan and Jiang, Yong and Han, Wenjuan},
430	  journal = {arXiv preprint arXiv:2302.10205},
431	  year    = {2023},
432	  url     = {https://arxiv.org/abs/2302.10205}
433	}
434	
435	% Confirmed via: arXiv:2505.09388, Hugging Face model cards
436	@article{qwen2025qwen3,
437	  title   = {Qwen3 Technical Report},
438	  author  = {{Qwen Team}},
439	  journal = {arXiv preprint arXiv:2505.09388},
440	  year    = {2025},
441	  url     = {https://arxiv.org/abs/2505.09388}
442	}
443	
444	% Confirmed via: NeurIPS 2024 proceedings, arXiv:2312.07104
445	@inproceedings{zheng2024sglang,
446	  title     = {{SGLang}: Efficient Execution of Structured Language Model Programs},
447	  author    = {Zheng, Lianmin and Yin, Liangsheng and Xie, Zhiqiang and Sun, Chuyue and Huang, Jeff and Yu, Cody Hao and Cao, Shiyi and Kozyrakis, Christos and Stoica, Ion and Gonzalez, Joseph E. and Barrett, Clark and Sheng, Ying},
448	  booktitle = {Advances in Neural Information Processing Systems},
449	  volume    = {37},
450	  year      = {2024},
451	  url       = {https://arxiv.org/abs/2312.07104}
452	}
453	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4f0c423c-9cec-4ad8-a1b9-fda80554d30e",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "b7e3485a-11e5-44f2-89e7-e6a3b230597e",
  "sourceToolAssistantUUID": "4f0c423c-9cec-4ad8-a1b9-fda80554d30e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 56 · 2026-05-14T21:44:00.641Z_

I now have a thorough understanding of the paper. Let me also check the literature survey artifacts for completeness.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b7e3485a-11e5-44f2-89e7-e6a3b230597e",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C55ZyhqZ5q1ixX3eaq",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "298c5092-9d65-4872-b33b-f0e1de457fd9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UpWYYzAnseDqKbAsZuY5zj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9296,
      "cache_read_input_tokens": 63392,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9296,
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

_source line 57 · 2026-05-14T21:44:02.335Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01RBSxcnHXGgSKiLr8fKnjG4`</summary>

```json
{
  "pattern": "**/literature_survey*.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "298c5092-9d65-4872-b33b-f0e1de457fd9",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C55ZyhqZ5q1ixX3eaq",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2acda5da-ab56-4af6-ab49-3181d98a8acd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UpWYYzAnseDqKbAsZuY5zj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9296,
      "cache_read_input_tokens": 63392,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9296,
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

_source line 58 · 2026-05-14T21:44:02.351Z_

<details><summary>↩ Tool result · `toolu_01RBSxcnHXGgSKiLr8fKnjG4`</summary>

```text
artifacts/literature_survey_constrained_decoding_ie.md
artifacts/literature_survey_ontology_constrained_ie.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2acda5da-ab56-4af6-ab49-3181d98a8acd",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "2bb1f401-4443-4c76-81aa-63accee4eca0",
  "sourceToolAssistantUUID": "2acda5da-ab56-4af6-ab49-3181d98a8acd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 59 · 2026-05-14T21:44:05.994Z_

<details open><summary>🔧 Tool call — Read · `toolu_011dvnFPaHmk7t5xGyf1jqar`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/literature_survey_constrained_decoding_ie.md",
  "limit": 80
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2bb1f401-4443-4c76-81aa-63accee4eca0",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C5YyVsJy1SrawDyfdH",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "836815d1-ab1d-4110-a7fe-091e8cdceb47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FVKv4eVSv2v3CivMRQ6URC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 173,
      "cache_read_input_tokens": 72688,
      "output_tokens": 115,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 173
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 115,
          "cache_read_input_tokens": 72688,
          "cache_creation_input_tokens": 173,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 173,
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

_source line 60 · 2026-05-14T21:44:06.009Z_

<details><summary>↩ Tool result · `toolu_011dvnFPaHmk7t5xGyf1jqar`</summary>

```text
1	# Literature Survey: Constrained Decoding for Information Extraction (2022-2026)
2	
3	Survey date: 2026-05-13
4	
5	---
6	
7	## Category A: Grammar-Constrained Decoding Directly Applied to IE Tasks
8	
9	### A1. Grammar-Constrained Decoding for Structured NLP Tasks without Finetuning
10	- **Authors**: Saibo Geng, Martin Josifoski, Maxime Peyrard, Robert West
11	- **Venue**: EMNLP 2023
12	- **ArXiv**: 2305.13971
13	- **Core method**: Uses context-free grammars (via Grammatical Framework) to constrain LLM decoding for structured NLP tasks. Introduces **input-dependent grammars** that adapt the grammar to each input.
14	- **IE tasks**: NER, relation extraction, entity disambiguation, constituency parsing
15	- **Semantic constraints**: No. Purely syntactic (CFG-level). Ensures valid output structure but not ontological validity of extracted content.
16	- **Key result**: GCD-enhanced LLMs substantially outperform unconstrained LLMs and even beat task-specific finetuned models.
17	- **Relevance**: **HIGH** — Most direct precursor. Demonstrates GCD for IE but stops at syntactic validity. Our work extends to semantic (type) constraints.
18	- **Code**: https://github.com/epfl-dlab/GCD
19	
20	### A2. iNERD: Informed Named Entity Recognition Decoding for Generative Language Models
21	- **Authors**: Deussel, Hillebrand, et al.
22	- **Venue**: IEEE SLT 2024 (arXiv 2308.07791, Aug 2023)
23	- **Core method**: Treats NER as generative process; uses informed decoding that masks impossible tokens based on NER structure constraints during prediction.
24	- **IE tasks**: NER only
25	- **Semantic constraints**: Partial — masks tokens that are structurally impossible for NER (e.g., entity type vocabulary), but does not enforce ontological constraints like domain/range.
26	- **Key result**: Eliminates hallucinated entity types, improves NER performance across 5 LLMs on 8 datasets.
27	- **Relevance**: **HIGH** — Shows token masking for IE-specific constraints works. But constraints are NER-structural, not ontology-semantic.
28	
29	### A3. Grammar-Constrained Decoding for Structured IE with Fine-tuned Models (Clinical Trial Abstracts)
30	- **Authors**: (Frontiers in AI, 2024)
31	- **Venue**: Frontiers in Artificial Intelligence, Jan 2025 (published online)
32	- **Core method**: Investigates grammar-constrained decoding impact on fine-tuned generative models for structured information extraction from clinical trial abstracts.
33	- **IE tasks**: Structured extraction from clinical text (PICO elements)
34	- **Semantic constraints**: No. Focuses on ensuring well-formedness of output structure via grammar rules.
35	- **Key result**: Grammar constraints ensure valid output format even in low-resource settings; investigates trade-off between format compliance and extraction accuracy.
36	- **Relevance**: MEDIUM — Domain-specific application of GCD to IE, but no semantic constraints.
37	
38	### A4. Generative Biomedical Event Extraction with Constrained Decoding Strategy
39	- **Authors**: (IEEE/ACM Trans. Comp. Bio. Bioinformatics, 2024)
40	- **Venue**: IEEE/ACM TCBB, 2024
41	- **Core method**: T5-based seq2seq model with trie-based constrained decoding for biomedical event extraction. Uses curriculum learning.
42	- **IE tasks**: Biomedical event extraction (Genia 2011, Genia 2013)
43	- **Semantic constraints**: Partial — the trie constrains argument roles to valid options, which is a form of schema-level constraint beyond pure syntax.
44	- **Key result**: Outperforms extraction-based approaches; avoids cascading errors of pipeline systems.
45	- **Relevance**: MEDIUM-HIGH — Trie-constrained decoding for event extraction with role constraints is conceptually related to our type constraints.
46	
47	### A5. An Autoregressive Text-to-Graph Framework for Joint Entity and Relation Extraction (ATG)
48	- **Authors**: Zaratiana, Tomeh, et al.
49	- **Venue**: AAAI 2024
50	- **ArXiv**: 2401.01326
51	- **Core method**: Encoder-decoder with pointing mechanism on dynamic vocabulary of spans and relation types. Decoder transitions through states with constraints (no relation before entities, no repeated spans, head != tail).
52	- **IE tasks**: Joint entity and relation extraction (CoNLL04, SciERC, ACE05)
53	- **Semantic constraints**: Minimal — structural constraints on generation order, but no type-compatibility checking.
54	- **Relevance**: MEDIUM — Constrained generation for RE but constraints are structural/ordering, not ontological.
55	
56	### A6. CodeIE: Large Code Generation Models are Better Few-Shot Information Extractors
57	- **Authors**: Peng Li, Tianxiang Sun, et al.
58	- **Venue**: ACL 2023
59	- **ArXiv**: 2305.05711
60	- **Core method**: Recasts IE structured output as Python code (dicts, lists); uses Code-LLMs (Codex) with code-style prompts.
61	- **IE tasks**: NER, relation extraction (7 benchmarks)
62	- **Semantic constraints**: No. Code structure provides implicit constraints but no ontology-level enforcement during decoding.
63	- **Relevance**: MEDIUM — Alternative approach to structured IE output; Python type hints could potentially encode ontological constraints but this is not explored.
64	
65	### A7. GoLLIE: Annotation Guidelines improve Zero-Shot Information Extraction
66	- **Authors**: Sainz et al. (HiTZ Center)
67	- **Venue**: ICLR 2024
68	- **ArXiv**: 2310.03668
69	- **Core method**: Fine-tunes Code-LLama to follow annotation guidelines defined as Python classes. Type constraints (str, list, Optional) defined in schema.
70	- **IE tasks**: NER, RE, event extraction (zero-shot generalization)
71	- **Semantic constraints**: Partial — Python type annotations serve as soft constraints during generation. However, these are format-level types (str, list), not ontological types (e.g., Person can only be head of "born_in" → Location).
72	- **Relevance**: MEDIUM-HIGH — Schema-as-code approach. Close in spirit but constraints are format-level, not ontology-level.
73	
74	---
75	
76	## Category B: Constrained Decoding Frameworks/Engines (Tooling Layer)
77	
78	### B1. XGrammar: Flexible and Efficient Structured Generation Engine
79	- **Authors**: Dong, Ruan, et al. (MLC-AI)
80	- **Venue**: Preprint, Nov 2024 (arXiv 2411.15100)
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "836815d1-ab1d-4110-a7fe-091e8cdceb47",
  "isSidechain": true,
  "promptId": "b1954f54-c1c1-49c9-a9f9-06737f8d4e86",
  "agentId": "aaaf91bd2cb668cad",
  "type": "user",
  "uuid": "b58f01a4-6973-4c9a-b3df-69ef32a387a2",
  "sourceToolAssistantUUID": "836815d1-ab1d-4110-a7fe-091e8cdceb47",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 61 · 2026-05-14T21:45:43.054Z_

I now have sufficient material to write the review. Let me now produce the detailed R2 review focused on Novelty and Related Work.

---

## Review: OntoCoDec: Near-Complete Type-Valid Information Extraction via Compiled Ontology Constraints

**Reviewer 2 (R2) -- Focus: Novelty and Related Work**

---

### 1. Summary

This paper measures the rate at which LLMs violate ontology domain/range constraints during zero-shot information extraction (15-19% on SciERC and DocRED), then proposes OntoCoDec, a two-layer constrained decoding framework: a grammar layer (XGrammar CFG) that enforces JSON structure, entity-type vocabulary, and relation vocabulary, and a semantic layer that uses a stateful entity registry plus dynamic logit masking to enforce domain/range constraints. The two layers compose via bitwise AND of token masks. On SciERC, DR violations drop 94% (15.4% to 0.9%); on DocRED, 45% for Qwen3-8B and 90% for Llama-3.1-8B, with F1 preserved or slightly improved. The paper also provides a decidability taxonomy and a constraint tightness analysis explaining cross-dataset variation.

---

### 2. Strengths

**S1. Problem identification is well-motivated and concrete.** The violation landscape study provides useful empirical grounding. The four-category violation taxonomy (DR, RV, ET, CF) is clear and actionable. The per-relation breakdown showing Compare at 42.4% vs. Used-for at 0.8% makes a compelling case that violations are non-uniform and practically relevant. Regardless of whether this constitutes a standalone contribution, it is good empirical practice.

**S2. The paper is honest about limitations.** The authors proactively report the CF trade-off (0.08% to 9.90% on SciERC), acknowledge that post-hoc filtering achieves higher F1, clearly state that S2 does not solve CF, and appropriately qualify the title as "Near-Complete" rather than "Guaranteed." This level of intellectual honesty is appreciated and strengthens credibility.

**S3. Cross-model validation is a genuine positive.** Testing on both Qwen3-8B and Llama-3.1-8B with zero code modification and obtaining consistent structural guarantees (RV/ET to 0%) across both is a meaningful engineering validation. The dual-factor analysis (tightness x RV baseline) explaining the Qwen vs. Llama DocRED asymmetry is a thoughtful analytical contribution.

**S4. The constraint tightness formalization is useful.** Defining tightness as 1 - |V(r)|/|T|^2 and showing it predicts fallback frequency and residual DR is a clean analytical insight. The near-bijection between fallback rate (10.2%) and residual DR (10.21%) on DocRED is striking evidence.

**S5. Related work coverage is extensive.** The appendix related work section covers 5 paradigms with approximately 25+ references. The positioning against PICARD, Synchromesh, MGD, and the PLDI'25 type-constrained code generation work is explicit and detailed. The paper clearly identifies the gap it fills (semantic domain/range constraints at decode time for IE, as opposed to code generation).

---

### 3. Weaknesses

**W1. The grammar layer is not a novel contribution -- it is an application of XGrammar.** The grammar layer compiles a JSON schema with enum constraints into an XGrammar CFG. This is precisely what XGrammar, Outlines, and LMQL were designed to do. Framing this as a "contribution layer" of OntoCoDec overstates the novelty. Any practitioner using XGrammar with a properly specified JSON schema would achieve RV=0% and ET=0% -- these results follow directly from existing tooling. The paper should more explicitly acknowledge that the grammar layer is an off-the-shelf application rather than a contribution.

**W2. The semantic layer is a lookup table with logit masking -- the novelty is narrow.** The core technical mechanism is: (1) parse the prefix to detect which JSON field is being generated, (2) look up the relation type in a constraint table, (3) mask logits of entity types not in dom(r) or range(r). The entity registry is a dictionary. The position detection is regex on JSON keys. The masking is setting logits to -inf. Each component is individually straightforward. The "first-token masking" approach (mapping each entity type to its first subword token) works only because the type vocabularies are very small (6 types in both datasets) -- the paper should discuss scalability to ontologies with hundreds of types where first-token uniqueness may not hold.

**W3. "Near-complete" in the title is not justified given DocRED results.** On DocRED with Qwen3-8B, DR drops from 18.5% to only 10.2% -- a 45% reduction with 10.2% residual violations. This is not "near-complete" by any reasonable standard. One in ten triples still violates domain/range constraints. The title claim derives primarily from SciERC (0.93% residual), but SciERC has only 7 relations with loose constraints (tightness=0.333). The DocRED result, which is the more realistic and challenging benchmark, directly contradicts the "near-complete" framing. Even with Llama (2.55% residual), DocRED still shows substantial residual. The paper should either restrict "near-complete" to the SciERC result or change the title.

**W4. The violation landscape study (C1) is an incremental observation, not an independent contribution.** Running an LLM on two IE benchmarks and counting how many outputs violate schema constraints is a straightforward measurement. The claim "first systematic study of ontological constraint violations in LLM-based IE" is technically defensible (no one else published exactly this measurement), but the study reveals an expected finding -- LLMs produce outputs that violate constraints they were never explicitly trained to respect. The tightness correlation is intuitive (tighter constraints are harder to satisfy by chance). This motivates the method but does not constitute a standalone contribution worthy of its own contribution bullet.

**W5. The CF trade-off undermines the core value proposition.** OntoCoDec reduces DR violations from 15.4% to 0.93% on SciERC, but introduces CF violations from 0.08% to 9.90%. Ablation confirms CF is 100% attributable to the semantic layer. The net effect is: 14.4pp reduction in DR violations, but 9.8pp increase in CF violations. While the paper argues DR violations are "harder" than CF violations, this is a subjective judgment. For downstream knowledge graph construction, cross-field inconsistency (the same entity getting different types in different triples) can be equally problematic. The paper frames CF as a "different severity" issue, but does not provide empirical evidence (e.g., downstream task impact) to support this severity distinction.

**W6. Post-hoc filtering outperforms OntoCoDec on the paper's own F1 metric.** The paper acknowledges post-hoc filtering achieves higher F1 (SciERC 8.63 vs 8.36; DocRED 9.61 vs 8.23). The rebuttal relies on recall preservation and "information coverage," but in the low-F1 regime (~8%), the practical difference between these approaches is marginal. A simple baseline (generate then filter) outperforms the proposed method on the metric most readers will focus on, which weakens the contribution's practical impact.

**W7. Missing related work and insufficient differentiation from existing systems.**

- **Guidance library** (Microsoft, 2023): A widely-used constrained generation library that supports stateful token masking conditioned on generation history. OntoCoDec's semantic layer is functionally similar to a Guidance program with state tracking. Not discussed.

- **InstructUIE** (Wang et al., 2023): Instruction-tuned universal IE that could be combined with constrained decoding. Not cited.

- **DeepKE** (Zhang et al., 2022): An open-source knowledge extraction toolkit that supports schema-guided extraction. The paper should discuss how OntoCoDec relates to existing IE toolkits that already incorporate schema awareness.

- **Type-constrained knowledge graph completion** (Krompass et al., 2015; Jain et al., 2018): The idea of restricting entity types based on relation domain/range during knowledge graph operations has been explored in KG completion. The paper does not acknowledge this lineage at all, despite the mechanism being conceptually identical (just applied during embedding-based link prediction rather than autoregressive decoding).

- **NeuroLogic Decoding** (Lu et al., 2021): While cited in the appendix, the main related work section does not adequately discuss how NeuroLogic's predicate logic constraints differ from OntoCoDec's approach. NeuroLogic supports conjunction and disjunction of lexical constraints during beam search -- the semantic layer's masking is a special case of this.

- **FLAN-T5 / structured generation for IE**: The paper focuses exclusively on decoder-only models. No discussion of whether the approach is applicable to or differentiated from encoder-decoder structured generation approaches.

**W8. The decidability taxonomy is a relabeling, not a contribution.** Classifying constraints as "local," "prefix-decidable," and "non-local" is a standard categorization in formal language theory (the distinction between regular, context-free, and context-sensitive constraints). Applying these labels to IE constraints does not constitute a novel taxonomy. The paper presents this as a principled classification, but it is essentially: (a) things we can check with a fixed grammar, (b) things we can check with a stateful processor, (c) things we cannot check in a single pass. This is self-evident given the architecture.

**W9. Experimental scope is narrow.** Only two 8B-class models, only zero-shot setting, only two datasets. The paper does not test on any biomedical IE benchmark (where ontology compliance is arguably most critical), does not test on models larger than 8B (where violation rates may differ substantially), and does not combine OntoCoDec with fine-tuned models (where the practical impact would be most relevant). The zero-shot setting with ~8% F1 makes it difficult to assess whether the method has practical value.

---

### 4. Questions for Authors

**Q1.** How does the first-token masking approach scale to ontologies with hundreds or thousands of entity types? At what point does first-token uniqueness break down, and what is the fallback?

**Q2.** Can you provide a direct comparison between OntoCoDec and simply using the Guidance library (or Outlines with custom logits processors) to implement the same constraint logic? What specifically does OntoCoDec provide beyond what a skilled engineer could build in an afternoon using existing tools?

**Q3.** The CF trade-off: have you measured downstream impact? If the extracted knowledge graph is used for question answering or reasoning, does DR reduction with CF increase lead to better or worse downstream performance than the unconstrained baseline?

**Q4.** Grammar-only on DocRED increases DR from 18.5% to 26.2%. This means grammar enforcement actively makes things worse for type validity. How do you reconcile this with the claim that grammar is an "enabling prerequisite" for semantic enforcement? The data shows grammar enforcement is actively harmful without semantic enforcement.

**Q5.** Why was SciERC chosen as a primary evaluation benchmark given it has only 7 relations and loose constraints? The strong headline number (94% reduction) comes from the easier benchmark. DocRED is more representative of real-world ontology complexity -- should the paper lead with DocRED results?

**Q6.** The paper reports "zero F1 cost" but absolute F1 is ~8%. Have you verified that the constraint enforcement mechanism does not disproportionately affect the small number of correct predictions? At 8% F1, the system is already performing poorly; maintaining this performance is not a strong signal.

---

### 5. Preliminary Scores

| Dimension | Score | Rationale |
|-----------|-------|-----------|
| **Soundness** | 3.0 | Experiments are well-executed and honestly reported. The violation measurement methodology is sound. Bootstrap CIs are appropriate. However, the "near-complete" claim is not supported by DocRED results, and the CF trade-off is inadequately analyzed for downstream impact. The grammar layer contribution is overstated. |
| **Excitement** | 2.0 | The core technical contribution -- logit masking conditioned on a constraint lookup table -- is a straightforward engineering combination of existing techniques (XGrammar + a stateful logits processor). The violation landscape study confirms expected behavior. The results are mixed: strong on SciERC (easy benchmark) but weak on DocRED (realistic benchmark), with a problematic CF trade-off. Post-hoc filtering, a trivial baseline, outperforms on F1. The paper reads more as a well-executed engineering report than a research contribution with novel insights. |
| **Overall Assessment** | 2.5 | The paper identifies a real problem and provides an honest empirical investigation, which I appreciate. However, the novelty bar for a top venue like EMNLP is not met. The grammar layer is XGrammar applied to IE. The semantic layer is a constraint lookup table with logit masking. The decidability taxonomy relabels standard concepts. The headline result (94% DR reduction) comes from the easier dataset; the harder dataset shows 45% reduction with 10% residual. The CF trade-off partially negates the benefit. Missing related work in type-constrained KG completion and constrained generation libraries weakens the positioning. The paper would benefit from: (1) testing on fine-tuned models where practical impact is clearer, (2) downstream task evaluation showing that DR reduction translates to better end-task performance, (3) more honest framing that acknowledges the grammar layer as off-the-shelf and positions the contribution as the semantic layer plus the empirical analysis. |
| **Confidence** | 4.0 | I am familiar with constrained decoding literature, ontology-aware IE, and knowledge graph completion. I have read the paper carefully including the appendix. |

---

### 6. Summary Recommendation

The paper addresses a real problem -- LLMs violate ontology constraints during IE -- and provides thorough empirical investigation. However, the technical novelty is limited: the grammar layer is a direct application of XGrammar, the semantic layer is a lookup table with logit masking, and the decidability taxonomy relabels standard concepts. The strongest result (94% DR reduction) comes from the easier benchmark (SciERC, 7 relations, loose constraints); the more realistic benchmark (DocRED, 96 relations) shows only 45% reduction for Qwen with 10.2% residual DR. The CF trade-off (0.08% to 9.90%) partially negates the DR benefit. Post-hoc filtering, a trivial baseline, outperforms on F1. Key related work in type-constrained KG completion and constrained generation libraries is missing. I recommend major revisions with resubmission, conditional on: (a) testing with fine-tuned models, (b) downstream task evaluation, (c) more honest contribution framing, and (d) addressing the CF trade-off with a concrete solution rather than a future work direction.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b58f01a4-6973-4c9a-b3df-69ef32a387a2",
  "isSidechain": true,
  "agentId": "aaaf91bd2cb668cad",
  "requestId": "req_011Cb3C5nxsBpe89u6sJCuao",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2c06026b-3796-4019-8920-8c64b423c2ce",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b35164d6-59ff-4dc9-a0a2-e7bd8feeacab",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QUcF5wXeAdxiVbVHuUZ3WY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1944,
      "cache_read_input_tokens": 72861,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1944,
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
