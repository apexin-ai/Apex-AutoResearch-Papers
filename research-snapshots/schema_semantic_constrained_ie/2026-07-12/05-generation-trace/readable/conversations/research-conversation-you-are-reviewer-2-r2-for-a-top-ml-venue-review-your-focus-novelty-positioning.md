# Research conversation: You are Reviewer 2 (R2) for a top ML venue review. Your focus: **Novelty, positioning, and related work coverage**. ## P

**OntoCoDec: Type-Constrained Information Extraction via Compiled Schema Constraints (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 58
- **Recorded user turns:** 1
- **Tool calls:** 25
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-a0c165bfcba7de3cc.jsonl`
- **Structured JSON:** [`0ee0a6ed82fe899ccec6.json`](../../sessions/0e/0ee0a6ed82fe899ccec6.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

58 recorded events

### User

_source line 1 · 2026-05-18T17:22:42.568Z_

You are Reviewer 2 (R2) for a top ML venue review. Your focus: **Novelty, positioning, and related work coverage**.

## Paper Summary
**Title:** OntoCoDec: Type-Valid Information Extraction via Compiled Ontology Constraints

The paper presents OntoCoDec, a two-layer constrained decoding framework for ontology-constrained information extraction (IE). It compiles IE schemas into:
1. A **grammar layer** (CFG via XGrammar) enforcing structural validity and type vocabularies
2. A **semantic layer** with a stateful entity registry enforcing cross-field type constraints (domain/range for RE, role-entity for EE)

The layers compose via bitwise AND with an enabling dependency. A decidability taxonomy classifies constraints as (a) purely local, (b) prefix-decidable with state, (c) truly non-local.

**Evaluation on:** RE (SciERC, DocRED) × EE (WikiEvents) × 3 models (Qwen3-8B, Llama-3.1-8B, Mistral-7B) + 70B scale + FT composability.

**Key Results:**
- RE: DR reduced 44.7-99.4%, R-F1 neutral or slightly positive
- EE: EV/RoV eliminated entirely (from 10-89% to 0%), Entity F1 recovered from 0% to 11-17% (format compliance)
- Post-hoc filtering non-viable for EE (99.6-100% rejection)
- Grammar-only ablation: EV→0% but RoV persists 64-77%
- CF violations *introduced* by constrained decoding: 0→9.9-21.1%
- 70B: violations diminish (DR 6.5% SciERC, 5.8% DocRED) but don't vanish; OntoCoDec eliminates remaining
- FT composability confirmed (Qwen EE)
- Latency overhead 13-21%

**Related Work Section covers 3 areas:**
1. Constrained Decoding for Structured Generation (Guidance, Outlines, XGrammar, LMQL)
2. Type-Constrained Generation (code generation type checking analogy)
3. LLM-Based Information Extraction (GoLLIE, CodeIE, InstructUIE)
4. Event Extraction Methods (DEGREE, CEDAR, Text2Event)
5. Post-hoc Validation (self-consistency, self-refinement)

**Paper structure:** Abstract → Intro (5 paragraphs + 4 contributions) → Background → Violation Landscape (Section 3) → Framework (Section 4: grammar, semantic, composition, decidability) → Experiments (Section 5) → Related Work (Section 6) → Conclusion + Limitations + Future Work

## Your Review Task

Provide a detailed review covering:

1. **Novelty Assessment (score 1-6)**
   - How novel is the two-layer architecture (grammar + semantic)?
   - Is the enabling dependency a genuine architectural insight or an obvious engineering choice?
   - Is the decidability taxonomy a real intellectual contribution?
   - How does OntoCoDec relate to existing constrained decoding (XGrammar, Guidance, LMQL)?
   - Is the violation landscape study (Section 3) novel as a standalone empirical contribution?

2. **Related Work Coverage (score 1-6)**
   - Are key baselines and competitors cited?
   - Missing references: structured prediction with constraints, type-checking in NLP, ontology-aware NER/IE, knowledge graph completion with type constraints?
   - Is the positioning clear — what exactly is the delta over XGrammar + custom logic?
   - Does the Related Work section properly differentiate from prior art?

3. **Clarity and Presentation (score 1-6)**
   - Is the paper well-written and easy to follow?
   - Is the story coherent from Abstract through Conclusion?
   - Are technical details sufficient for reproduction?
   - Information density of figures/tables?

4. **Significance and Impact (score 1-6)**
   - Would this framework be adopted in practice?
   - Does it advance the field conceptually or mainly engineering?
   - Is the scope (RE + EE, 3 models) sufficient to claim "generalizable framework"?

5. **Strengths** (bullet list, 4-6 items)

6. **Weaknesses** (bullet list, 4-6 items)

7. **Questions for Authors** (3-5 specific questions)

8. **Missing References** (list any key works not cited)

9. **Overall Assessment** with score (1-6 scale: 1=Strong Reject, 2=Reject, 3=Weak Reject, 4=Weak Accept, 5=Accept, 6=Strong Accept)

Be rigorous but fair. Top venue acceptance rate ~25%. Pay special attention to:
- Whether the contribution is primarily engineering (applying XGrammar with domain logic) vs conceptual (the decidability taxonomy, enabling dependency insight)
- Whether "generalizable framework validated on two tasks" is overclaimed
- Whether the CF tradeoff (introducing new violations) undermines the narrative
- Citation coverage — are there important missing references in structured prediction, ontology-aware generation, or constrained decoding?
- Whether the paper reads like a systems paper or a research paper

Format your review as a structured document with clear section headers.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "c91b494d-dab8-4895-8001-480e8c9842ab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-18T17:22:42.571Z_

```json
{
  "parentUuid": "c91b494d-dab8-4895-8001-480e8c9842ab",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
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
  "uuid": "f6eb876b-acd5-44f4-99c4-f108121a1f00",
  "timestamp": "2026-05-18T17:22:42.571Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 3 · 2026-05-18T17:22:45.491Z_



I'll start by reading the paper and all relevant artifacts to conduct a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f6eb876b-acd5-44f4-99c4-f108121a1f00",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPMkc68hFJR8idHSXX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c5fcecc5-ec3c-4090-b525-cb1a8e17863c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018k5oedPkNoYnig19Vuo9jx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 8673,
      "cache_read_input_tokens": 8252,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8673,
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

_source line 4 · 2026-05-18T17:22:46.892Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01F5Nan2tAYEUMZNCZuWLegD`</summary>

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
  "parentUuid": "c5fcecc5-ec3c-4090-b525-cb1a8e17863c",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPMkc68hFJR8idHSXX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bf4a51b1-3a81-4ea2-9f41-4096e4100cdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018k5oedPkNoYnig19Vuo9jx",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 8673,
      "cache_read_input_tokens": 8252,
      "output_tokens": 124,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8673
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 124,
          "cache_read_input_tokens": 8252,
          "cache_creation_input_tokens": 8673,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8673,
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

_source line 5 · 2026-05-18T17:22:46.895Z_

<details><summary>↩ Tool result · `toolu_01F5Nan2tAYEUMZNCZuWLegD`</summary>

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
  "parentUuid": "bf4a51b1-3a81-4ea2-9f41-4096e4100cdd",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "1a5330e1-f703-408d-9423-c923e10bee7b",
  "sourceToolAssistantUUID": "bf4a51b1-3a81-4ea2-9f41-4096e4100cdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 6 · 2026-05-18T17:22:49.849Z_



I'll read the paper and supporting materials to conduct a thorough review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1a5330e1-f703-408d-9423-c923e10bee7b",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPgKJsP2fTHjbHKFXL",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e98da5a4-7514-4dcb-830f-87af955b7bcf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LphY1oiggvBkApMgzBTnPC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 16925,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

_source line 7 · 2026-05-18T17:22:50.328Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__director_get_project_overview · `toolu_01Hh7srRyfQaS4mf7fZCMZFp`</summary>

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
  "parentUuid": "e98da5a4-7514-4dcb-830f-87af955b7bcf",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPgKJsP2fTHjbHKFXL",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c971628f-0f2e-414e-88b0-ab95a396c789",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LphY1oiggvBkApMgzBTnPC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 16925,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

### Tool result

_source line 8 · 2026-05-18T17:22:50.617Z_

<details><summary>↩ Tool result · `toolu_01Hh7srRyfQaS4mf7fZCMZFp`</summary>

```text
{"result":"# 项目 schema_semantic_constrained_ie 概况\n\n## 实验状态 (88 个)\n\n- **llama_scierc_full_s1**: DONE (success) — \n- **llama_scierc_unconstrained**: DONE (success) — \n- **phase2_scierc_full_s1**: DONE (success) — \n- **phase2_scierc_semantic_only**: DONE (success) — \n- **phase2_scierc_grammar_only**: DONE (success) — \n- **phase2_scierc_unconstrained**: DONE (success) — \n- **phase2_docred_full_s1**: DONE (success) — \n- **phase2_docred_semantic_only**: DONE (success) — \n- **phase2_docred_unconstrained**: DONE (success) — \n- **mvp_phase0_docred_schema_r2**: DONE (killed) — \n- **phase2_s2_pilot50**: DONE (success) — \n- **mvp_phase0_docred_schema**: DONE (success) — \n- **mvp_phase0_violation_rate_docred**: DONE (success) — \n- **mvp_phase0_scierc_schema**: DONE (success) — \n- **mvp_phase0_violation_rate**: DONE (success) — \n\n## 最新报告\n# Handover — 2026-05-18\n\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\n\n## 运行中\n| exp_id | 假设 | 状态 | 关键指标 | W&B |\n|--------|------|------|---------|-----|\n| w9_qwen_docred_zs_sampling_r2 | Continuation of w9 DocRED sampling from doc 106, testing OntoCoDec full_s1 with temperature sampling (T=0.7) on remaining 892 DocRED documents | — | — | — |\n| p8b_docred_latency | OntoCoDec constrained decoding overhead on Qwen3-8B DocRED (200-doc subset) measured on same GPU as P8 SciERC will confirm moderate overhead (<2x), providing consistent timing data for paper | — | — | — |\n| 70b_docred_constrained | 70B AWQ-INT4 model with OntoCoDec constrained decoding on DocRED will achieve 0% ET/RV violations while maintaining F1, demonstrating cross-dataset scalability | — | — | — |\n\n## 待处理\n（无）\n\n## 近期结论\n- **w9_qwen_docred_zs_sampling** (failed): Temperature sampling (T=0.7, top_p=0.9) with OntoCoDec full_s1 on Qwen3-8B DocRED will maintain low violation rates while exploring output diversity on cross-sentence RE with 96 relation types\n- **w9_qwen_scierc_zs_sampling** (success): Temperature sampling (T=0.7, top_p=0.9) with OntoCoDec full_s1 on Qwen3-8B SciERC will maintain low violation rates while potentially improving F1 through output diversity compared to greedy decoding\n  [w9_scierc_sampling_analysis](/api/workspace-files/projects/schema_semantic_constrained_ie/artifacts/w9_qwen_scierc_zs_sampling/report/w9_scierc_sampling_analysis.md)\n- **p8_latency_overhead** (success): OntoCoDec constrained decoding overhead on Qwen3-8B SciERC is moderate (<2x), demonstrating practical deployability\n\n## 趋势\n成功 75 / 负向 4 / 失败 1 / 共 84\n\n## 下一步\n（无活跃 idea，请通过 ideas.md 添加）\n\n## 资源状态\nwestd-16980: 无 GPU 信息\nwestd-21461: 空闲 cuda:0, cuda:1\n\n## 告警\n- mvp_phase0_docred_schema_r2: 已被终止 — unknown\n- w1_cf_fallback_docred: 已被终止 — unknown\n- w1_cf_fallback_llama_scierc: 已被终止 — unknown\n- w1_cf_fallback_llama_docred: 已被终止 — unknown\n- w9_qwen_docred_zs_sampling: 训练失败 — unknown"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c971628f-0f2e-414e-88b0-ab95a396c789",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "dbd3a233-7db9-4dc1-b98c-638285bb2c10",
  "sourceToolAssistantUUID": "c971628f-0f2e-414e-88b0-ab95a396c789",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-18T17:22:52.247Z_

<details open><summary>🔧 Tool call — Glob · `toolu_017idjiSDXEjFWYVupyweR2m`</summary>

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
  "parentUuid": "dbd3a233-7db9-4dc1-b98c-638285bb2c10",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPgKJsP2fTHjbHKFXL",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "907ffef7-a773-4f59-810a-8444911d2f17",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LphY1oiggvBkApMgzBTnPC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 16925,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1447,
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

### Tool result

_source line 10 · 2026-05-18T17:22:52.271Z_

<details><summary>↩ Tool result · `toolu_017idjiSDXEjFWYVupyweR2m`</summary>

```text
artifacts/_project/paper/section5_scierc_draft_4796e8.tex
artifacts/_project/paper/abstract_fd4b26.tex
artifacts/_project/paper/abstract_d3264e.tex
artifacts/_project/paper/section7_conclusion_550cbf.tex
artifacts/dream_reports/dream_20260514T094226/best/paper.tex
artifacts/dream_reports/dream_20260514T094226/median/paper.tex
artifacts/dream_reports/dream_20260514T094226/worst/paper.tex
artifacts/_project/paper/discussion_paragraphs_cf83d1.tex
artifacts/_project/paper/section6_relwork_additions.tex
artifacts/_project/paper/discussion_paragraphs.tex
artifacts/dream_reports/dream_20260514T205155/best/paper.tex
artifacts/dream_reports/dream_20260514T205155/median/paper.tex
artifacts/dream_reports/dream_20260514T205155/worst/paper.tex
artifacts/_project/paper/section6_relwork_outline.tex
artifacts/_project/paper/section7_conclusion.tex
artifacts/dream_reports/dream_20260516T021434/best/paper.tex
artifacts/dream_reports/dream_20260516T021434/median/paper.tex
artifacts/dream_reports/dream_20260516T021434/worst/paper.tex
artifacts/dream_reports/dream_20260516T173022/best/paper.tex
artifacts/dream_reports/dream_20260516T173022/median/paper.tex
artifacts/_project/paper/paper_tables_draft.tex
artifacts/appendix_sampling_table.tex
artifacts/_project/paper/appendix_sampling_table.tex
artifacts/_project/paper/appendix_prompts.tex
artifacts/_project/paper/appendix_related_work.tex
artifacts/_project/paper/section2_background.tex
artifacts/_project/paper/section5_docred_draft_9b84f1.tex
artifacts/_project/paper/appendix_doc_length.tex
artifacts/_project/paper/appendix_prompt_sensitivity.tex
artifacts/_project/paper/section3_method_draft.tex
artifacts/_project/paper/appendix_llama_per_relation.tex
artifacts/_project/paper/section5_crossmodel_draft.tex
artifacts/_project/paper/section5_scierc_draft.tex
artifacts/_project/paper/section4_composition_draft.tex
artifacts/_project/paper/section3_violation_landscape.tex
artifacts/_project/paper/section5_wikievents_draft.tex
artifacts/_project/paper/section7_conclusion_compressed.tex
artifacts/_project/paper/appendix_beam_search.tex
artifacts/_project/paper/p3_case_studies.tex
artifacts/_project/paper/p3_case_studies_861a0d.tex
artifacts/p3_case_studies.tex
artifacts/_project/paper/appendix_reproducibility.tex
artifacts/_project/paper/appendix_discussion.tex
artifacts/_project/paper/main.tex
artifacts/_project/paper/appendix_case_studies.tex
artifacts/_project/paper/section1_introduction_draft.tex
artifacts/_project/paper/section5_docred_draft.tex
artifacts/_project/paper/section5_runtime.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/section6_related_work.tex
artifacts/dream_reports/dream_20260518T162745/best/paper.tex
artifacts/dream_reports/dream_20260518T162745/median/paper.tex
artifacts/dream_reports/dream_20260518T162745/worst/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "907ffef7-a773-4f59-810a-8444911d2f17",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "907a1e70-0110-48bd-94db-3769b0ee05b0",
  "sourceToolAssistantUUID": "907ffef7-a773-4f59-810a-8444911d2f17",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-18T17:22:52.894Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01N4ipivDJyp2MD5uqPnBfNz`</summary>

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
  "parentUuid": "907a1e70-0110-48bd-94db-3769b0ee05b0",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARPgKJsP2fTHjbHKFXL",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0ae8a475-3134-49bd-9fbe-bfd058059580",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LphY1oiggvBkApMgzBTnPC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1447,
      "cache_read_input_tokens": 16925,
      "output_tokens": 267,
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
          "output_tokens": 267,
          "cache_read_input_tokens": 16925,
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

_source line 12 · 2026-05-18T17:22:52.904Z_

<details><summary>↩ Tool result · `toolu_01N4ipivDJyp2MD5uqPnBfNz`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No literature_map.yaml found for 'schema_semantic_constrained_ie'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0ae8a475-3134-49bd-9fbe-bfd058059580",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "0248e944-5bcb-474e-8e2a-0149246833ad",
  "sourceToolAssistantUUID": "0ae8a475-3134-49bd-9fbe-bfd058059580",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-18T17:22:56.571Z_

<details open><summary>🔧 Tool call — Read · `toolu_01R7XM5h2Z58DYxUaFgd6SBT`</summary>

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
  "parentUuid": "0248e944-5bcb-474e-8e2a-0149246833ad",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQ866zh5vHtZGDeyHb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "b59eb04d-b36a-4f68-bd77-8b03027c5913",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014ipTYj3dtkjtuSpwjVxxBR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2524,
      "cache_read_input_tokens": 18372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2524,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 14 · 2026-05-18T17:22:56.576Z_

<details><summary>↩ Tool result · `toolu_01R7XM5h2Z58DYxUaFgd6SBT`</summary>

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
17	\usepackage{pifont}
18	
19	\title{OntoCoDec: Type-Constrained Information Extraction\\via Compiled Ontology Constraints}
20	
21	\author{Anonymous ACL submission}
22	
23	\begin{document}
24	\maketitle
25	
26	% === Abstract ===
27	\input{abstract}
28	
29	% === §1 Introduction ===
30	\input{section1_introduction_draft}
31	
32	% === §2 Background ===
33	\input{section2_background}
34	
35	% === §3 Method ===
36	\input{section3_method_draft}
37	
38	% === §4 Constraint Composition ===
39	\section{Constraint Composition}
40	\label{sec:composition}
41	\input{section4_composition_draft}
42	
43	% === §5 Experiments ===
44	\section{Experiments}
45	\label{sec:experiments}
46	
47	\subsection{Violation Landscape}
48	\input{section3_violation_landscape}
49	
50	\input{section5_scierc_draft}
51	\input{section5_docred_draft}
52	\input{section5_crossmodel_draft}
53	\input{section5_wikievents_draft}
54	\input{section5_runtime}
55	
56	% === §6 Related Work ===
57	\input{section6_related_work}
58	
59	% === §7 Discussion and Conclusion ===
60	\section{Discussion and Conclusion}
61	\label{sec:discussion}
62	\input{section7_conclusion_compressed}
63	
64	% === Limitations (ARR requirement: standalone section, does not count toward page limit) ===
65	\clearpage
66	\section*{Limitations}
67	
68	CF impact is model-dependent: for well-calibrated models (Qwen, Llama), S1 introduces CF violations (up to 12.02\%) as a consequence of per-relation independent enforcement; for poorly-calibrated models (Mistral), S1 substantially reduces CF (56.87\%\,$\to$\,1.27\%) by constraining type assignments to schema-valid values.
69	CF fallback ablation shows that eliminating CF re-routes violations to DR ($+$13.85\,pp). CF$\leftrightarrow$DR thus represents a fundamental trade-off in composable constraint systems rather than an independently resolvable limitation (Appendix~\ref{app:cf-dr-tradeoff}).
70	Entity F1 impact is model-dependent ($+$1.22\,pp for Qwen vs.\ $-$0.64\,pp for Llama on DocRED), partially confounded by increased parse failures under constraints (Llama: 9.1\% vs.\ 6.8\%).
71	Zero-shot results cover three 7--8B-class models, where relation F1 remains around 4--8\% compared to $\sim$45\% for fine-tuned systems.
72	Composability with fine-tuned models is validated on both SciERC and DocRED with Qwen3-8B and Llama-3.1-8B (DR\,$\leq$\,0.20\%, R-F1 change within $\pm$0.6\,pp), but evaluation is limited to one fine-tuning method (LoRA); residual CF (Qwen 1.18\%, Llama 0.46\% on SciERC) traces to schema-level type ambiguity (\textsc{Generic}$\leftrightarrow$X) rather than enforcement failure.
73	The continuation masking approach (\S\ref{sec:dynamic-masking}) handles multi-token type names and prefix-shared types on the ontologies tested (6--27 entity types); scalability to ontologies with hundreds of entity types has not been validated, and the prefix-map size may grow substantially.
74	Global entity-level type consensus during decoding offers the most direct path to resolving CF violations.
75	All models tested are 7--8B-parameter class; scaling behavior to larger (70B+) or smaller models has not been verified, and the dual-factor pattern's predictive scope may differ at other scales.
76	CF type inconsistencies may propagate to downstream tasks that consume extracted triples (e.g., knowledge graph construction, question answering); the impact of such propagation has not been evaluated.
77	Residual DR under fine-tuning (36 violations across all fine-tuned settings, both models and both datasets) decomposes into entity type errors (39\%), schema coverage gaps (33\%), and model generation errors correctly caught by constraints (28\%); Llama DocRED alone accounts for 33 of 36 residual violations (92\%), reflecting weaker entity typing (Appendix~\ref{app:residual-dr-analysis}).
78	Schema coverage gaps (one-third of residual violations) are irreducible by decoding-time constraints alone (training-set frequency coverage); complementary approaches such as global type consensus or post-hoc correction may address this limitation.
79	All main experiments use greedy decoding; our evaluation of beam search on the full SciERC test set (551 documents) and a DocRED subset across three models confirms compatibility (Appendices~\ref{app:sampling},~\ref{app:beam-search}), but comprehensive evaluation across all decoding configurations remains future work.
80	Validation with fine-tuned models, larger scales, and non-English ontologies remains to be explored.
81	
82	% === Ethics Statement ===
83	\section*{Ethics Statement}
84	
85	This work uses publicly available benchmark datasets (SciERC and DocRED) with no personally identifiable information.
86	No human subjects were involved in the experiments.
87	The constrained decoding method operates on model outputs and does not introduce new privacy or safety risks beyond those inherent in the base language models.
88	Code and data will be released upon acceptance.
89	
90	% === Bibliography ===
91	\bibliography{relwork_new_entries}
92	
93	% === Appendix ===
94	\appendix
95	
96	\input{appendix_prompts}
97	\input{appendix_related_work}
98	\input{appendix_discussion}
99	\input{appendix_llama_per_relation}
100	\input{appendix_sampling_table}
101	\input{appendix_beam_search}
102	\input{appendix_reproducibility}
103	\input{appendix_doc_length}
104	\input{appendix_prompt_sensitivity}
105	\input{appendix_case_studies}
106	
107	\end{document}
108	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b59eb04d-b36a-4f68-bd77-8b03027c5913",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "11abfe8f-6b1e-429d-af2e-829222b8fdb1",
  "sourceToolAssistantUUID": "b59eb04d-b36a-4f68-bd77-8b03027c5913",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-18T17:22:57.069Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AerUF7iywi6ujEYrSJyYtn`</summary>

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
  "parentUuid": "11abfe8f-6b1e-429d-af2e-829222b8fdb1",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQ866zh5vHtZGDeyHb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "03b6c796-f3c9-4a91-88a0-aadb9b7a39bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014ipTYj3dtkjtuSpwjVxxBR",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2524,
      "cache_read_input_tokens": 18372,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2524,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 16 · 2026-05-18T17:22:57.075Z_

<details><summary>↩ Tool result · `toolu_01AerUF7iywi6ujEYrSJyYtn`</summary>

```text
1	\begin{abstract}
2	We present \textsc{OntoCoDec}, which compiles Information Extraction (IE) ontology schemas into two composable token-level decoding constraints that provide formal guarantees during autoregressive generation:
3	(1)~a \emph{grammar layer} (XGrammar context-free grammar) guaranteeing JSON structural validity and entity/relation vocabulary membership (virtually eliminating entity type and relation vocabulary violations); and
4	(2)~a \emph{semantic layer} guaranteeing per-triple domain/range type compliance via a stateful entity registry and dynamic logit masking.
5	%
6	Without constraints, Large Language Model (LLM) based IE produces systematic domain/range (DR) violations: 15.37\% on SciERC (7 relations) and 18.46\% on DocRED (96 relations), comparable rates governed by \emph{constraint tightness} rather than ontology scale.
7	\textsc{OntoCoDec} reduces DR by 42--99\% across three model families (Qwen3-8B, Llama-3.1-8B, Mistral-7B) with no significant F1 cost (DocRED: $+$0.50\,pp, $p{<}0.001$; \S\ref{sec:cross-model}).
8	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1, mistral_docred
9	Composed with Low-Rank Adaptation (LoRA) fine-tuning, DR reaches $\leq$\,0.09\% (SciERC) and 0.20\% (DocRED) with relation F1 within $\pm$0.6\,pp, a near-lossless composition.
10	With beam search ($k{=}4$), the full stack eliminates all four violation types under fine-tuned beam decoding (SciERC, both Qwen3-8B and Llama-3.1-8B) while preserving extraction quality (R-F1 44.23 and 46.11, respectively); in zero-shot beam decoding, DR reaches 0\% for calibrated models on both RE datasets.
11	The framework generalizes to event extraction (WikiEvents: 56 event types, 80 roles) without architectural modification and eliminates event-vocabulary and role-vocabulary violations ($\to$ 0\%); where unconstrained outputs are severely off-schema, format compliance additionally enables entity extraction (Entity F1: 0\%\,$\to$\,12--18\%).
12	Per-slot enforcement introduces a cross-field consistency trade-off (up to 12\% in zero-shot, resolved to $\leq$1.2\% by fine-tuning).
13	OntoCoDec demonstrates that ontology schemas can be compiled into decoding-time guarantees, bridging the gap between flexible generative extraction and the type-safety requirements of downstream knowledge systems.
14	\end{abstract}
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "03b6c796-f3c9-4a91-88a0-aadb9b7a39bb",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "035d96aa-20a6-40d2-86a4-b947e8e076ea",
  "sourceToolAssistantUUID": "03b6c796-f3c9-4a91-88a0-aadb9b7a39bb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-18T17:22:57.473Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XUjTYZLJqL8qMDnMWRyxga`</summary>

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
  "parentUuid": "035d96aa-20a6-40d2-86a4-b947e8e076ea",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQ866zh5vHtZGDeyHb",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "dfc34d8e-8e20-4284-ade4-05756971cbae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014ipTYj3dtkjtuSpwjVxxBR",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2524,
      "cache_read_input_tokens": 18372,
      "output_tokens": 247,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2524
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 247,
          "cache_read_input_tokens": 18372,
          "cache_creation_input_tokens": 2524,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2524,
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

_source line 18 · 2026-05-18T17:22:57.477Z_

<details><summary>↩ Tool result · `toolu_01XUjTYZLJqL8qMDnMWRyxga`</summary>

```text
1	% Section 1: Introduction (compressed, 669→~550 words)
2	
3	\section{Introduction}
4	\label{sec:introduction}
5	
6	Large language models are increasingly deployed for zero-shot information extraction~\cite{li2023codeie,sainz2024gollie,wei2023zeroshot}, but when generating relation triples $(h, r, t)$, neither entity is guaranteed to carry a type consistent with the ontology's domain/range constraints for $r$.
7	We call such outputs \emph{domain/range violations}: structurally valid triples that are ontologically invalid.
8	In a systematic study, we find violations are pervasive: 15.4\% of triples on SciERC~\cite{luan2018scierc} and 18.5\% on DocRED~\cite{yao2019docred}, driven by \emph{constraint tightness} (few valid type pairs per relation) rather than ontology scale.
9	Relations with tight constraints exhibit far higher rates (\textsc{Compare}: 42.4\%) than loosely constrained ones (\textsc{Used-for}: 0.8\%).
10	For downstream systems in safety-critical domains (biomedical entity extraction, legal document analysis), statistical reduction of violations is insufficient; type-safety guarantees are needed to prevent error propagation into knowledge graphs and decision-support pipelines.
11	
12	Existing approaches leave a fundamental gap.
13	Schema-informed prompting reduces violations by 62\% on average but is per-relation unreliable (violations for \textsc{Evaluate-for} actually \emph{increase} by 5.8\,pp).
14	Grammar-constrained decoding~\cite{dong2025xgrammar,willard2023outlines,beurer-kellner2023lmql} guarantees syntactic well-formedness but cannot encode cross-field semantic constraints.
15	Post-hoc filtering achieves higher F1 in most zero-shot settings via precision gains, but at the cost of discarding up to 48\% of predictions including true positives; at high rejection rates (e.g., Mistral DocRED 73.7\%), it discards the majority of outputs, making it impractical.
16	OntoCoDec preserves recall by enforcing constraints during generation rather than discarding non-compliant outputs.
17	Training-based approaches~\cite{sainz2024gollie,lu2022uie} provide only soft guidance that cannot eliminate violations.
18	
19	We propose \textbf{OntoCoDec} (\textbf{Onto}logy-\textbf{Co}mpiled \textbf{Dec}oding), a framework that compiles an IE ontology into two composable layers of decoding-time constraints.
20	Our two-layer architecture reflects the observation that structural violations (malformed output, unknown types) and semantic violations (type-constraint breaches) require fundamentally different enforcement mechanisms.
21	The \emph{grammar layer} enforces JSON well-formedness and vocabulary validity via XGrammar.
22	The \emph{semantic layer} maintains a stateful entity registry during generation: as entities are decoded, the registry records type assignments; when relation arguments are generated, dynamic logit masking restricts output to types compatible with the relation's domain/range specification.
23	The layers compose via bitwise AND with an \emph{enabling dependency}: the grammar layer guarantees vocabulary membership, so the semantic layer can look up domain/range rules.
24	Unlike type-constrained code generation where types are statically declared, IE requires a dynamic entity registry built during generation, with constraint targets that depend on the co-occurring relation.
25	On SciERC, OntoCoDec reduces DR violations from 15.37\% to 0.93\% ($\downarrow$94\%) while remaining F1-neutral ($+$0.13\,pp).
26	
27	Our contributions:
28	\begin{enumerate}
29	    \item The first systematic study of ontological constraint violations in LLM-based IE (spanning per-relation tightness analysis, dual-factor characterization, and post-hoc baseline comparison), violation rates are driven by constraint tightness rather than ontology size, and prompt-level intervention is per-relation unreliable.
30	    \item OntoCoDec, a two-layer compiled constraint framework that is the first to enforce pair-based domain/range type constraints via compiled stateful logit masks during autoregressive IE.
31	    Unlike type-constrained decoding in code generation, where output types are statically determined by the grammar, IE requires stateful cross-field constraints because entity type validity depends on the co-occurring relation within each triple.
32	    \item Empirical validation on 3 models $\times$ 3 datasets (2 RE + 1 EE): DR $\downarrow$76--99\% on SciERC and $\downarrow$42--90\% on DocRED with significant R-F1 gains (Qwen $p{<}0.001$, Llama $p{=}0.013$); cross-task generalization to WikiEvents (vocabulary violations $\to$\,0\%; Entity F1 0\%\,$\to$\,12--18\%); composability with LoRA (DR\,$\leq$\,0.20\% at $<$0.6\,pp F1 cost).
33	    \item Characterization of the CF$\leftrightarrow$DR trade-off inherent in per-slot enforcement (resolved by fine-tuning to CF\,$\leq$\,1.2\%); beam search ($k{=}4$) as an orthogonal path that eliminates all four violation types under fine-tuned beam decoding (SciERC, both Qwen3-8B and Llama-3.1-8B) and reduces DR to 0\% for calibrated models in zero-shot settings.
34	\end{enumerate}
35	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dfc34d8e-8e20-4284-ade4-05756971cbae",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "0bc6ba75-8d70-44b9-817c-513fa3ac843c",
  "sourceToolAssistantUUID": "dfc34d8e-8e20-4284-ade4-05756971cbae",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-18T17:23:02.282Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DPMCBKAMqFpkMrPhQW1yrh`</summary>

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
  "parentUuid": "0bc6ba75-8d70-44b9-817c-513fa3ac843c",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQTqVo3tQL72BUKEkw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d42cb795-1a35-4eb0-bee3-911168084e73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FeAtZi4fiKHkcPfm1VwHy5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4339,
      "cache_read_input_tokens": 20896,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4339,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 20 · 2026-05-18T17:23:02.302Z_

<details><summary>↩ Tool result · `toolu_01DPMCBKAMqFpkMrPhQW1yrh`</summary>

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
10	We define the \emph{constraint tightness} of $r$ as $1 - |\sigma(r)| / |\mathcal{E}|^2$: tighter constraints leave fewer valid options, increasing violation likelihood.
11	
12	\paragraph{Grammar-Constrained Decoding.}
13	\label{sec:bg:gcd}
14	Grammar-constrained decoding restricts each token $y_t$ to a mask $M_g \in \{0, 1\}^{|V|}$ derived from a target grammar.
15	XGrammar~\citep{dong2025xgrammar} compiles JSON Schemas into pushdown automata for efficient enforcement of structural constraints; Outlines~\citep{willard2023outlines} and SGLang~\citep{zheng2024sglang} offer similar capabilities.
16	However, these methods are limited to context-free constraints and cannot enforce cross-field semantic rules (e.g., ``if $r$ = \textsc{Feature-of}, then $\mathrm{type}(h) \in \{\textsc{Method}, \textsc{OtherScientificTerm}\}$''), which depend on previously generated field values.
17	
18	\paragraph{Problem Statement.}
19	\label{sec:bg:problem}
20	Given $\mathcal{O}$ and an autoregressive LM $\mathcal{M}$, we seek constraints $\mathcal{C}$ ensuring: (a)~\textbf{structural validity}, i.e., well-formed JSON with $\mathcal{E}$/$\mathcal{R}$ membership; and (b)~\textbf{type validity}, i.e., $(\mathrm{type}(h), \mathrm{type}(t)) \in \sigma(r)$ for every triple.
21	Condition (a) is context-free; (b) is context-sensitive but \emph{prefix-decidable}: at the point where a type token is generated, all information needed (relation type, entity registry) is available in the decoded prefix.
22	This requires that each entity type name maps to a unique first subword token (\S\ref{sec:semantic}, Implementation), a design assumption verified for all tested configurations.
23	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d42cb795-1a35-4eb0-bee3-911168084e73",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "32060602-39e3-4c17-b543-7a2f73c31a05",
  "sourceToolAssistantUUID": "d42cb795-1a35-4eb0-bee3-911168084e73",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-18T17:23:03.562Z_

<details open><summary>🔧 Tool call — Read · `toolu_011sRpQzFZapR29t2HkMmBxm`</summary>

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
  "parentUuid": "32060602-39e3-4c17-b543-7a2f73c31a05",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQTqVo3tQL72BUKEkw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e7ec8b14-3ccc-41b5-a822-2a14088aae42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FeAtZi4fiKHkcPfm1VwHy5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4339,
      "cache_read_input_tokens": 20896,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4339,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 22 · 2026-05-18T17:23:03.569Z_

<details><summary>↩ Tool result · `toolu_011sRpQzFZapR29t2HkMmBxm`</summary>

```text
1	% Section 3 — Method (Draft)
2	% OntoCoDec: Type-Valid Information Extraction
3	% via Compiled Ontology Constraints
4	
5	\section{Method}
6	\label{sec:method}
7	
8	We present OntoCoDec, a two-layer constrained decoding framework that compiles ontology schemas into token-level masks enforced during autoregressive generation.
9	Unlike type-constrained code generation, IE presents three distinct challenges: (1)~entity types are inferred from free text rather than declared annotations, (2)~the entity registry is built dynamically during generation, and (3)~constraint targets are context-dependent type assignments rather than fixed grammar productions.
10	The grammar layer (\S\ref{sec:grammar}) guarantees structural validity (well-formed JSON with ontology-vocabulary membership), while the semantic layer (\S\ref{sec:semantic}) enforces domain/range type constraints via a stateful entity registry.
11	We describe the problem formulation (\S\ref{sec:formulation}), each layer, and two decoding strategies (\S\ref{sec:strategies}).
12	Formal analysis of constraint composition is deferred to Section~\ref{sec:composition}.
13	
14	
15	\subsection{Problem Formulation}
16	\label{sec:formulation}
17	
18	\paragraph{IE as structured generation.}
19	Given an input text $x$, a language model generates a structured JSON output $y$:
20	%
21	\begin{equation}\label{eq:output-schema}
22	\resizebox{.88\columnwidth}{!}{$\displaystyle
23	  y = \bigl\{\texttt{entities}: [\{n_i, \tau_i\}],\; \texttt{relations}: [\{h_j, t_j, r_j, \tau^h_j, \tau^t_j\}]\bigr\}
24	$}
25	\end{equation}
26	%
27	where each entity has a name $n_i$ and type $\tau_i \in \mathcal{E}$, and each relation specifies head $h_j$, tail $t_j$, relation type $r_j \in \mathcal{R}$, and head/tail entity types $\tau^h_j, \tau^t_j$.
28	The output JSON Schema (\S\ref{sec:grammar}) enforces a fixed field ordering (head $\to$ tail $\to$ relation $\to$ head\_type $\to$ tail\_type) via deterministic grammar compilation.
29	This ordering ensures that the relation type $r_j$ is known before entity type fields are generated, which enables domain and range lookups in sequential masking (\S\ref{sec:dynamic-masking}).
30	
31	\paragraph{Ontology compliance.}
32	Using the ontology $\mathcal{O} = (\mathcal{E}, \mathcal{R}, \sigma)$ defined in \S\ref{sec:background}, we write $\operatorname{dom}(r) = \{\tau^h : \exists \tau^t,\, (\tau^h, \tau^t) \in \sigma(r)\}$ for domain-valid head types and $\operatorname{range}(r, \tau^h) = \{\tau^t : (\tau^h, \tau^t) \in \sigma(r)\}$ for the conditional range given head type $\tau^h$.
33	Our enforcement target is \emph{pair-based} type validity: $(\tau^h, \tau^t) \in \sigma(r)$ for every triple.
34	The decoder enforces this sequentially: $\tau^h \in \operatorname{dom}(r)$ at head position, then $\tau^t \in \operatorname{range}(r, \tau^h)$ at tail position. This is equivalent to the full pair check and strictly stronger than independent domain/range enforcement, because most relations have non-rectangular type signatures ($\sigma(r) \subsetneq \operatorname{dom}(r) \times \operatorname{range}(r)$ for all 7 SciERC and 73/96 DocRED relations; see \S\ref{sec:rectangularity}).\footnote{An independent check ($\tau^h \in \operatorname{dom}(r) \wedge \tau^t \in \operatorname{range}(r)$) would over-permit type pairs by $1.50\times$ on SciERC and $1.58\times$ on DocRED, corresponding to 33.3\% and 36.8\% spurious type pairs.}
35	Our goal is maximizing $P(y \mid x)$ subject to all triples being type-valid and $y$ being well-formed JSON conforming to Eq.~\eqref{eq:output-schema}.
36	
37	
38	\subsection{Grammar Layer}
39	\label{sec:grammar}
40	
41	The grammar layer compiles $\mathcal{O}$ into a context-free grammar (CFG) enforced at every decoding step via logit masking.
42	This compilation proceeds in two stages.
43	
44	\paragraph{Schema-to-grammar compilation.}
45	We generate a JSON Schema encoding the structure in Eq.~\eqref{eq:output-schema} with \texttt{enum} constraints restricting entity types to $\mathcal{E}$ and relation types to $\mathcal{R}$.
46	This schema is compiled into an EBNF grammar via XGrammar~\cite{dong2025xgrammar}, producing a pushdown automaton tracking JSON structure and enum membership.
47	
48	\paragraph{Logit masking.}
49	At step $t$, the automaton computes grammar-valid tokens $G(t) \subseteq V$; all others receive logits $-\infty$.
50	This simultaneously enforces: (i)~structural validity (well-formed JSON), (ii)~relation vocabulary membership ($r_j \in \mathcal{R}$), and (iii)~entity type membership ($\tau_i \in \mathcal{E}$).
51	Domain/range constraints are \emph{not} enforced, as they depend on entity types within each triple; this gap is filled by the semantic layer.
52	
53	\paragraph{Empirical profile.}
54	On SciERC, grammar constraints eliminate relation vocabulary violations entirely (1.39\%\,$\to$\,0\%) and entity type violations entirely (0.40\%\,$\to$\,0\%), with no measurable F1 impact.
55	Domain/range violations remain effectively unchanged (15.37\%\,$\to$\,14.84\%). This confirms that grammar constraints enforce structural but not semantic validity.
56	
57	
58	\subsection{Semantic Layer}
59	\label{sec:semantic}
60	
61	The semantic layer enforces domain/range constraints through a stateful logits processor maintaining an entity registry during generation.
62	
63	\subsubsection{Entity Registry}
64	\label{sec:entity-registry}
65	
66	As the model generates the entity list, the semantic layer builds a registry $\mathcal{D}: \text{name} \to \text{type}$ mapping each entity to its declared type.
67	This registry is populated incrementally: when the model completes an entry $\{n_i, \tau_i\}$, the pair $(n_i, \tau_i)$ is added to $\mathcal{D}$.
68	The registry is then consulted during relation generation to look up the declared types of head and tail entities.
69	
70	\subsubsection{Position Detection}
71	\label{sec:position-detection}
72	
73	At each step $t$, the processor determines which field is currently being generated by pattern-matching on the decoded prefix.
74	We define five field positions (\textsc{EntityType}, \textsc{RelationType}, \textsc{HeadType}, \textsc{TailType}, and \textsc{FreeText}), identified via JSON key patterns (e.g., tokens following \texttt{"head\_type":} indicate \textsc{HeadType}).
75	Semantic masks activate only at type-bearing positions (\textsc{HeadType}, \textsc{TailType}).
76	
77	\subsubsection{Dynamic Masking}
78	\label{sec:dynamic-masking}
79	
80	At type-bearing positions, the processor computes a semantic mask $S(t) \subseteq V$ restricting generation to type-valid tokens.
81	
82	\paragraph{Head type masking.}
83	At a \textsc{HeadType} position, the processor considers the entity registry $\mathcal{D}$ and the current relation type $r_j$ (if already generated).
84	If $h_j \in \mathcal{D}$ and $\mathcal{D}[h_j] \in \operatorname{dom}(r_j)$, the mask allows only that registered type: $S(t) = \{\operatorname{tok}(\mathcal{D}[h_j])\}$, ensuring consistency with both the entity list and domain constraints.
85	Otherwise, if $r_j$ is known, the mask falls back to all domain-valid types: $S(t) = \{\operatorname{tok}(\tau) : \tau \in \operatorname{dom}(r_j)\}$.
86	If $r_j$ is unavailable, no semantic mask is applied.
87	
88	\paragraph{Tail type masking.}
89	At a \textsc{TailType} position, the head type $\tau^h_j$ is already determined from the decoded prefix.
90	The processor computes $\operatorname{range}(r_j, \tau^h_j)$, the valid tail types conditioned on the generated head type (\S\ref{sec:formulation}).
91	If $t_j \in \mathcal{D}$, the mask further restricts to the registered type when it belongs to this set.
92	This sequential check ($\tau^h \in \operatorname{dom}(r)$, then $\tau^t \in \operatorname{range}(r, \tau^h)$) achieves exact pair-based enforcement, strictly tighter than an independent range check $\tau^t \in \operatorname{range}(r)$.
93	
94	\paragraph{Tokenizer-agnostic type masking.}
95	Each type name $\tau \in \mathcal{E}$ must be mapped to token IDs for logit masking.
96	A naive approach maps $\tau$ to its first subword token and sets disallowed IDs to $-\infty$, but this fails in two scenarios:
97	(1)~SentencePiece tokenizers produce context-dependent tokenizations where the same string yields different token IDs depending on preceding context (e.g., after a JSON delimiter), and
98	(2)~ontologies with prefix-shared type names (e.g., \textsc{Sen}, \textsc{Sid}, \textsc{Side} in WikiEvents) map to the same first token, making single-token disambiguation impossible.
99	We resolve both with \emph{continuation masking}: at compile time, we scan the full vocabulary to build a prefix map identifying, for each type name, all tokens whose decoded text is a valid prefix.
100	At decode time, the semantic mask allows any token that continues a partially-generated type name, disambiguating over multiple steps.
101	This is tokenizer-agnostic, handling byte-level BPE (Qwen, Llama) and SentencePiece (Mistral) without tokenizer-specific logic.
102	
103	\subsubsection{Grammar-Semantic Interaction}
104	\label{sec:interaction}
105	
106	The final mask is the conjunction of $G(t)$ and $S(t)$, permitting only tokens satisfying both layers (formalized in \S\ref{sec:composition}).
107	This embodies an \emph{enabling dependency}: semantic lookup requires relation types to be valid members of $\mathcal{R}$, guaranteed only by the grammar layer.
108	Without grammar enforcement, the model may generate out-of-vocabulary relation types for which no $\sigma(r)$ rules exist.
109	Empirically, semantic-only constraints reduce DR by only 24\% (15.37\%\,$\to$\,11.65\%) while failing to eliminate vocabulary violations; the full combination achieves 94\% DR reduction.
110	When $S(t) \cap G(t) = \emptyset$ (the semantic layer would mask out all grammar-valid tokens), the system falls back to grammar-only control, preserving structural validity at the cost of a potential type violation.
111	This \emph{grammar-first invariant} reflects a deliberate priority ordering: structural integrity is a hard constraint, while type violations are soft errors detectable by downstream validation.
112	
113	
114	\subsection{Decoding Strategies}
115	\label{sec:strategies}
116	
117	\paragraph{S1: Single-pass decoding.}
118	Both constraint layers are active throughout a single generation pass.
119	The entity registry is populated as entities are generated and immediately available for relation-level type checking.
120	This is the simpler and recommended strategy. It achieves strong constraint enforcement with higher relation F1 than the two-pass alternative.
121	
122	\paragraph{S2: Two-pass decoding.}\label{sec:s2}
123	The first pass generates only entities under grammar constraints; the extracted entities compile an input-dependent grammar that additionally constrains head and tail names to match declared entities.
124	The second pass generates relations under this tighter grammar plus semantic constraints.
125	Detailed comparison is provided in the appendix.
126	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e7ec8b14-3ccc-41b5-a822-2a14088aae42",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "d6856540-a2b7-4ed0-ba1d-723cf54a2f02",
  "sourceToolAssistantUUID": "e7ec8b14-3ccc-41b5-a822-2a14088aae42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-18T17:23:03.671Z_

<details open><summary>🔧 Tool call — Read · `toolu_012Bnsf4PkpAbU9dVeKu7NUW`</summary>

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
  "parentUuid": "d6856540-a2b7-4ed0-ba1d-723cf54a2f02",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQTqVo3tQL72BUKEkw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ed5a40ce-0f62-4508-83e5-e0bd1b7fb6ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FeAtZi4fiKHkcPfm1VwHy5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4339,
      "cache_read_input_tokens": 20896,
      "output_tokens": 255,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4339
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 255,
          "cache_read_input_tokens": 20896,
          "cache_creation_input_tokens": 4339,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4339,
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

_source line 24 · 2026-05-18T17:23:03.676Z_

<details><summary>↩ Tool result · `toolu_012Bnsf4PkpAbU9dVeKu7NUW`</summary>

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
11	The conjunction is asymmetric: $S(t)$ is defined only over $G(t)$, reflecting the enabling dependency (\S\ref{sec:method}): the semantic layer requires the relation type to belong to $\mathcal{R}$, a property guaranteed only by the grammar layer.
12	
13	\paragraph{Grammar-First Fallback.}
14	When $S(t) \cap G(t) = \emptyset$ (tight constraints leave no token that is both grammar-valid and semantically valid), na\"{\i}ve masking would force selection of a grammar-invalid token, breaking JSON structure.
15	We enforce a \emph{grammar-first fallback}: if no semantically valid token survives grammar filtering, semantic masking is skipped and the grammar layer alone controls selection.
16	Structural integrity is a hard constraint; a type violation is a soft error detectable by downstream validation.
17	
18	\paragraph{Constraint Tightness.}
19	We define the tightness of relation $r$ as:
20	%
21	\begin{equation}\label{eq:tightness}
22	  \kappa(r) = 1 - \frac{|\mathcal{V}(r)|}{|\mathcal{E}|^2},
23	\end{equation}
24	%
25	where $\mathcal{V}(r)$ is the set of valid type pairs and $\mathcal{E}$ the entity type vocabulary.
26	The mean tightness $\bar{\kappa} = \frac{1}{|\mathcal{R}|}\sum_{r} \kappa(r)$ characterizes ontology restrictiveness.
27	Tighter constraints eliminate more grammar-valid tokens at type-bearing positions, increasing fallback frequency and residual DR.
28	This dual-factor pattern (tightness $\times$ baseline model violation rate) is consistent with the cross-dataset results: for calibrated models (Qwen, Llama), SciERC ($\bar{\kappa}{=}0.333$, 24 valid pairs/relation) achieves 94--99\% DR reduction, while DocRED ($\bar{\kappa}{=}0.842$, 5.68 pairs) achieves 45--90\%; including Mistral (whose high baseline ET shifts the regime), the full range across all three models is 42--99\% (\S\ref{sec:cross-model}; quantitative analysis in Appendix~\ref{app:dual-factor}).
29	This pattern is observed across four model-dataset configurations; additional settings would be needed to establish statistical robustness.
30	
31	\paragraph{Non-Rectangularity and Sequential Masking.}
32	\label{sec:rectangularity}
33	% Data source: artifacts/rebuttal/w2_rectangularity_report.md
34	Sequential masking ($\tau^h \in \operatorname{dom}(r)$, then $\tau^t \in \operatorname{range}(r, \tau^h)$) is necessary because real ontology type signatures are non-rectangular: 0/7 SciERC and only 23/96 DocRED relations satisfy $\sigma(r) = \operatorname{dom}(r) \times \operatorname{range}(r)$.
35	Independent enforcement would admit 33--37\% spurious type pairs; on SciERC, 100\% of residual DR under S1 are pairs that pass independent checks but violate $\sigma(r)$.
36	
37	\paragraph{Decidability Taxonomy.}
38	We classify constraints by when sufficient information becomes available: \emph{local} (current token only, e.g., vocabulary membership; grammar layer), \emph{prefix-decidable} (decoded prefix, e.g., domain/range; semantic layer), and \emph{non-local} (forward coreference; outside single-pass decoding, partially addressed by S2, \S\ref{sec:s2}).
39	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ed5a40ce-0f62-4508-83e5-e0bd1b7fb6ac",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "082b39ee-abc8-4fc5-903d-ae36d55ab4de",
  "sourceToolAssistantUUID": "ed5a40ce-0f62-4508-83e5-e0bd1b7fb6ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-18T17:23:08.095Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PSP3vd3jCbqq2Hj8i6C23h`</summary>

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
  "parentUuid": "082b39ee-abc8-4fc5-903d-ae36d55ab4de",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQvC1iC6GjMiyZQwLs",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2b8a7ed4-ff96-47fa-a810-5f37ef47b86e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CoLmuX5MLfNGTjoEBQjacm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5778,
      "cache_read_input_tokens": 25235,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5778,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 36,
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

_source line 26 · 2026-05-18T17:23:08.100Z_

<details><summary>↩ Tool result · `toolu_01PSP3vd3jCbqq2Hj8i6C23h`</summary>

```text
1	% §5.1 Experimental Setup and Violation Landscape (compressed)
2	% exp_ids: mvp_phase0_violation_rate, mvp_phase0_scierc_schema,
3	%          mvp_phase0_violation_rate_docred, mvp_phase0_docred_schema
4	
5	\label{sec:violation_landscape}
6	
7	\paragraph{Setup.}
8	We evaluate on two IE benchmarks:
9	\textbf{SciERC}~\cite{luan2018scierc} (551 test sentences, 7 relations, avg.\ 26.1 valid type pairs/relation) and \textbf{DocRED}~\cite{yao2019docred} (998 dev documents,\footnote{DocRED test annotations are not publicly available; we evaluate on the development set.} 96 relations, avg.\ 5.68 valid pairs).
10	Primary model: Qwen3-8B~\cite{qwen2025qwen3}, zero-shot greedy decoding; cross-model validation in \S\ref{sec:cross-model}.
11	We measure four violation categories: \textbf{DR} (domain/range type pair $\notin \sigma(r)$), \textbf{RV} (relation $\notin \mathcal{R}$), \textbf{ET} (entity type $\notin \mathcal{E}$), and \textbf{CF} (same entity assigned conflicting types across triples).
12	Violation rates are computed over successfully parsed documents; including failures as zero-violation instances adjusts rates by at most 0.23\,pp.
13	
14	\paragraph{Baseline violations and motivation.}
15	DR violations affect 15.37\% of triples on SciERC and 18.46\% on DocRED, comparable rates despite 14$\times$ ontology size difference; severity is driven by \emph{constraint tightness} rather than scale.
16	Per-relation rates vary by over 40\,pp (Appendix~\ref{app:per-relation-landscape}), correlating with tightness $\kappa(r)$.
17	RV on DocRED reaches 29.66\%: large vocabularies exceed prompt-based reproduction capacity.
18	Schema-informed prompting reduces DR by 62\% on SciERC but only 30\% on DocRED and is per-relation unreliable (DR for \textsc{Evaluate-for} \emph{increases} by 5.8\,pp). These limitations motivate decoding-time enforcement.
19	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2b8a7ed4-ff96-47fa-a810-5f37ef47b86e",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "b7e3cad4-3038-45e0-a096-2944533f9e3e",
  "sourceToolAssistantUUID": "2b8a7ed4-ff96-47fa-a810-5f37ef47b86e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-18T17:23:08.588Z_

<details open><summary>🔧 Tool call — Read · `toolu_01WKWhVBzNeGpWmjX8mYBc8B`</summary>

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
  "parentUuid": "b7e3cad4-3038-45e0-a096-2944533f9e3e",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQvC1iC6GjMiyZQwLs",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d041c7a6-f4a6-4a1b-9d07-375e3d69177e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CoLmuX5MLfNGTjoEBQjacm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5778,
      "cache_read_input_tokens": 25235,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5778,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 36,
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

_source line 28 · 2026-05-18T17:23:08.592Z_

<details><summary>↩ Tool result · `toolu_01WKWhVBzNeGpWmjX8mYBc8B`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Grammar-Constrained Decoding.}
5	XGrammar~\cite{dong2025xgrammar} (benchmarked in JSONSchemaBench~\cite{jsonschemabench2025}), Outlines~\cite{willard2023outlines}, LMQL~\cite{beurer-kellner2023lmql}, DOMINO~\cite{beurer-kellner2024domino}, SynCode~\cite{ugare2024syncode}, and ASAp~\cite{park2024grammar} guarantee format validity but cannot enforce cross-field semantic constraints such as domain/range rules.
6	
7	\paragraph{Type-Constrained Generation for IE and Code.}
8	Synchromesh~\cite{synchromesh_iclr2022}, PICARD~\cite{scholak2021picard}, and \citet{pldi2025_type_constrained_codegen} enforce type constraints in code generation; OntoCoDec migrates this to IE.
9	GCD~\cite{geng2023gcd}, GoLLIE~\cite{sainz2024gollie}, and GUIDEX~\cite{guidex2025} constrain \emph{which tokens} appear but not \emph{which type combinations} are valid per relation.
10	DORE~\cite{vukovic2024dore} uses generate-then-select with confidence thresholds; GenIE~\cite{josifoski2022genie} constrains entities via a trie without relation-specific type enforcement; EnriCo~\cite{zaratiana2024enrico} applies ASP constraints with task-specific manually authored rules.
11	BoostCD~\cite{boostcd2025} combines constrained and unconstrained IE outputs via a trained boosting model; OntoCoDec is training-free and provides per-instance type guarantees rather than statistical improvement.
12	Training-based methods~\cite{paolini2021tanl,cabot2021rebel,lu2022uie,knowcoder_acl2024,li2023codeie,schema_rl2025} provide only soft guidance; post-hoc approaches~\cite{khorshidi2025odke,spires_2024,ontologx_2025,slot2025} validate or restructure outputs after generation rather than preventing violations.
13	
14	\paragraph{Quality Impact.}
15	Recent work shows constrained decoding can degrade reasoning and distort output distributions~\cite{banerjee2025crane,grammar_aligned_2024,schall2025hiddencost,formattax2026}; DCCD~\cite{dccd2026} proposes unconstrained-then-constrained correction as an alternative.
16	However, extraction tasks are robust to constraints~\cite{tam2024letmespeak}: OntoCoDec's narrow type-slot constraints yield neutral F1 on SciERC and significant improvement on DocRED ($+$0.50\,pp, $p{<}0.001$); post-hoc filtering is impractical for EE (99.6\% argument loss; extended survey in Appendix~\ref{app:related_work}).
17	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d041c7a6-f4a6-4a1b-9d07-375e3d69177e",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "616de19c-2f27-43e8-bd52-6929e61bf007",
  "sourceToolAssistantUUID": "d041c7a6-f4a6-4a1b-9d07-375e3d69177e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-18T17:23:09.133Z_

<details open><summary>🔧 Tool call — Read · `toolu_01XFEpQa4A6Uxph3TAW6ePdF`</summary>

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
  "parentUuid": "616de19c-2f27-43e8-bd52-6929e61bf007",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARQvC1iC6GjMiyZQwLs",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "87d4c250-dc41-4101-b406-a85c62bd217f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CoLmuX5MLfNGTjoEBQjacm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5778,
      "cache_read_input_tokens": 25235,
      "output_tokens": 257,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 5778
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 257,
          "cache_read_input_tokens": 25235,
          "cache_creation_input_tokens": 5778,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 5778,
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

_source line 30 · 2026-05-18T17:23:09.137Z_

<details><summary>↩ Tool result · `toolu_01XFEpQa4A6Uxph3TAW6ePdF`</summary>

```text
1	% Section 7 — Discussion and Conclusion (maximally compressed)
2	% Full discussion in Appendix; Mistral boundary condition in app:dual-factor.
3	
4	OntoCoDec compiles IE ontology schemas into composable token-level decoding constraints that achieve 42--99\% DR reduction across three models $\times$ three datasets with no significant F1 cost.
5	Composed with LoRA fine-tuning, DR reaches $\leq$\,0.20\% ($<$0.6\,pp F1 cost); beam search ($k{=}4$) further eliminates both residual DR and CF for calibrated models (\S\ref{sec:beam-results}).
6	CF remains an open challenge for per-slot enforcement; global entity-level type consensus during decoding offers the most direct resolution path.
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "87d4c250-dc41-4101-b406-a85c62bd217f",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "1ef1a452-7119-4c91-940f-65f8f5a8759a",
  "sourceToolAssistantUUID": "87d4c250-dc41-4101-b406-a85c62bd217f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-18T17:23:16.450Z_

<details open><summary>🔧 Tool call — Read · `toolu_01E9W6TbiqC26Hcvnibidwhg`</summary>

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
  "parentUuid": "1ef1a452-7119-4c91-940f-65f8f5a8759a",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRKVyNNJfNDLdX521x",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3ddec28d-d893-4c0c-a7ad-6040962867c4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0176GwmzeP27jhtYcoTcrYTu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1974,
      "cache_read_input_tokens": 31013,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1974,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 32 · 2026-05-18T17:23:16.461Z_

<details><summary>↩ Tool result · `toolu_01E9W6TbiqC26Hcvnibidwhg`</summary>

```text
1	% Section 5 — SciERC Results (Draft)
2	% Data source: Phase 2 SciERC registry experiments
3	% exp_ids: phase2_scierc_unconstrained, phase2_scierc_grammar_only,
4	%          phase2_scierc_semantic_only, phase2_scierc_full_s1, phase2_scierc_full_s2
5	% All numbers verified against registry 2026-05-14.
6	
7	\subsection{Ablation and Composability with Fine-Tuning}
8	\label{sec:scierc-results}
9	
10	Table~\ref{tab:scierc-ablation} presents the five-way ablation on SciERC (Qwen3-8B, zero-shot, 551 documents); only the active constraint layers differ across rows.
11	
12	% ──────────────────────────────────────────
13	%  Table: SciERC five-way ablation
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
31	  & 15.37 & ---
32	  & 1.39  & 0.40
33	  & 0.08
34	  & 8.23  & 31.01 \\
35	Grammar
36	  & 14.84 & $\downarrow$3\%
37	  & \textbf{0} & \textbf{0}
38	  & 0.08
39	  & 8.23  & 30.98 \\
40	Semantic
41	  & 11.65 & $\downarrow$24\%
42	  & 1.51  & 0.40
43	  & 2.71
44	  & 8.15  & 31.01 \\
45	Full (S1)
46	  & \textbf{0.93} & $\downarrow$\textbf{94\%}
47	  & \textbf{0} & \textbf{0}
48	  & 9.90
49	  & \textbf{8.36} & 30.98 \\
50	Full (S2)
51	  & 0.97  & $\downarrow$94\%
52	  & \textbf{0} & \textbf{0}
53	  & 8.03
54	  & 8.03  & \textbf{31.90} \\
55	\bottomrule
56	\end{tabular}}%
57	\caption{Five-way ablation on SciERC (551 docs, Qwen3-8B, zero-shot).
58	$\Delta$DR: relative change vs.\ unconstrained.
59	Best per column in \textbf{bold} (CF excluded).
60	F1 $\times$100. Bootstrap: 10{,}000 iterations.}
61	\label{tab:scierc-ablation}
62	\end{table}
63	
64	% ──────────────────────────────────────────
65	%  (a) Core result
66	% ──────────────────────────────────────────
67	\paragraph{Core result: DR elimination at zero F1 cost.}
68	The full two-layer constraint configuration (S1) reduces domain/range
69	violations from 15.37\% to 0.93\%, a 94\% relative reduction,
70	% phase2_scierc_unconstrained: DR=0.1537; phase2_scierc_full_s1: DR=0.0093
71	while relation F1 moves from 8.23 to 8.36 ($+$0.13\,pp; bootstrap 95\% CI [$-$0.24, $+$0.58]\,pp, $p = 0.58$, 10{,}000 iterations).
72	% phase2_scierc_unconstrained: R-F1=0.0823; phase2_scierc_full_s1: R-F1=0.0836
73	% bootstrap: delta=+0.13pp, CI=[-0.24,+0.58], p=0.5824
74	The difference is not statistically significant ($p = 0.58$); constraint enforcement is F1-neutral on this dataset.
75	Post-hoc filtering achieves higher F1 in most zero-shot settings via precision gains from aggressive violation removal (SciERC: 8.63 vs.\ 8.36; DocRED: 9.61 vs.\ 8.23), but at the cost of discarding up to 48\% of predictions including true positives (Appendix~\ref{app:posthoc-extended}); OntoCoDec preserves recall by enforcing constraints during generation.
76	Per-relation DR drops to $\leq$2.82\% on all types, reaching 0\% on four of seven (Appendix~\ref{app:per-relation-landscape}).
77	However, constraint enforcement elevates CF from 0.08\% to 9.90\% (\S\ref{sec:discussion}).
78	
79	% ──────────────────────────────────────────
80	%  (b) Grammar layer
81	% ──────────────────────────────────────────
82	\paragraph{Grammar layer: cost-free structural guarantees.}
83	Grammar-only constraints eliminate RV (1.39\%\,$\to$\,0\%) and ET (0.40\%\,$\to$\,0\%) with no F1 impact, while DR remains unchanged (15.37\%\,$\to$\,14.84\%).
84	This configuration represents the capability ceiling of grammar-based constrained decoding~\cite{geng2023gcd}, which enforces JSON structure and vocabulary membership but cannot reason about cross-field semantic constraints.
85	% phase2_scierc_grammar_only: RV=0, ET=0, DR=0.1484, R-F1=0.0823
86	
87	% ──────────────────────────────────────────
88	%  (c) Enabling dependency
89	% ──────────────────────────────────────────
90	\paragraph{Enabling dependency.}
91	Semantic-only reduces DR by only 24\% (11.65\%) and cannot eliminate RV (1.51\%) or ET (0.40\%), which establishes the \emph{enabling dependency}: without grammar-enforced vocabulary, the semantic layer encounters OOV types with no domain/range rules.
92	Adding the grammar layer yields a further 92\% reduction (11.65\%\,$\to$\,0.93\%).
93	
94	% ──────────────────────────────────────────
95	%  (d) S1 vs S2
96	% ──────────────────────────────────────────
97	\paragraph{S1 vs.\ S2.}
98	S2 achieves comparable DR (0.97\%) but lower R-F1 (8.03 vs.\ 8.36) with fewer triples (1{,}644 vs.\ 1{,}729) and does not resolve the CF trade-off (8.03\% vs.\ 9.90\%); we adopt S1 as the primary configuration.
99	% phase2_scierc_full_s2: DR=0.0097, R-F1=0.0803, CF=0.0803, triples=1644
100	
101	% ──────────────────────────────────────────
102	%  (e) Composability with Fine-Tuning
103	%  exp_ids: lora_scierc_unconstrained, lora_scierc_full_s1
104	% ──────────────────────────────────────────
105	\paragraph{Composability with fine-tuning.}
106	\label{sec:composability}
107	Table~\ref{tab:composability} tests composability across zero-shot vs.\ LoRA $\times$ unconstrained vs.\ S1 for Qwen3-8B and Llama-3.1-8B.
108	% exp_ids: phase2_scierc_unconstrained, phase2_scierc_full_s1,
109	%          w5_lora_scierc_unconstrained_eval, w5_lora_scierc_constrained_eval,
110	%          llama_scierc_unconstrained, llama_scierc_full_s1,
111	%          w5_llama_lora_scierc_unconstrained_eval, w5_llama_lora_scierc_constrained_eval
112	
113	Fine-tuning alone reduces DR to 1--2\% but leaves residual violations on tight-constraint relations (Table~\ref{tab:composability}).
114	Adding S1 eliminates these: Qwen DR 1.95\%\,$\to$\,0\% ($-$0.09\,pp R-F1), Llama DR 1.11\%\,$\to$\,0.09\% ($+$0.02\,pp).
115	On DocRED, the same pattern holds: Qwen DR 0.76\%\,$\to$\,0.01\% ($-$0.30\,pp), Llama DR 0.49\%\,$\to$\,0.20\% ($+$0.51\,pp).
116	% w5_qwen_docred_lora_constrained_eval: DR=0.01%, R-F1=40.56; w5_llama_docred_lora_constrained_eval: DR=0.20%, R-F1=44.23
117	
118	Across all settings, fine-tuned + S1 yields DR\,$\leq$\,0.20\% with R-F1 within $\pm$0.6\,pp, which supports orthogonal composability.
119	Post-fine-tuning, grammar is a no-op; the semantic layer alone reduces DR by 39--72\% (Appendix~\ref{app:ft-ablation}).
120	CF interference drops from $+$9.82\,pp (zero-shot) to $+$1.18\,pp (fine-tuned), tracing to \textsc{Generic}$\leftrightarrow$X schema ambiguity (Appendix~\ref{app:cf-distribution}).
121	Beam search ($k{=}4$) eliminates residual DR and reduces CF to $<$1\% for both Qwen and Llama (Appendix~\ref{app:beam-search}).
122	
123	\begin{table}[t]
124	\centering
125	\small
126	\setlength{\tabcolsep}{3pt}
127	\resizebox{\columnwidth}{!}{%
128	\begin{tabular}{@{}lll rrrr r@{}}
129	\toprule
130	\textbf{Model} & \textbf{Setting} & \textbf{Mode}
131	  & \textbf{DR\,$\downarrow$} & \textbf{CF}
132	  & \textbf{R-F1\,$\uparrow$} & \textbf{E-F1\,$\uparrow$}
133	  & \textbf{$\Delta$DR} \\
134	\midrule
135	\multirow{4}{*}{Qwen3-8B}
136	  & \multirow{2}{*}{Zero-shot}
137	    & Unconstr.\ & 15.37 & 0.08 & 8.23  & 31.01 & --- \\
138	  & & Full S1    &  0.93 & 9.90 & 8.36  & 30.98 & $\downarrow$94\% \\
139	\cmidrule(l){2-8}
140	  & \multirow{2}{*}{LoRA}
141	    & Unconstr.\ &  1.95 & 0    & 43.86 & 67.05 & --- \\
142	  & & Full S1    & \textbf{0} & 1.18 & 43.77 & 67.05 & $\downarrow$100\% \\
143	\midrule
144	\multirow{4}{*}{Llama-3.1-8B}
145	  & \multirow{2}{*}{Zero-shot}
146	    & Unconstr.\ & 13.34 & 0.24 & 2.68  & 23.56 & --- \\
147	  & & Full S1    &  0.08 & 6.56 & 2.54  & 23.49 & $\downarrow$99\% \\
148	\cmidrule(l){2-8}
149	  & \multirow{2}{*}{LoRA}
150	    & Unconstr.\ &  1.11 & 0    & 45.45 & 67.76 & --- \\
151	  & & Full S1    &  0.09 & 0.46 & 45.47 & 67.76 & $\downarrow$92\% \\
152	\bottomrule
153	\end{tabular}}%
154	\caption{Composability on SciERC (551 docs): zero-shot vs.\ LoRA $\times$ unconstrained vs.\ S1.
155	Adding S1 to LoRA: DR\,$\leq$\,0.09\%, R-F1 within $\pm$0.1\,pp.
156	DocRED: Qwen DR $-$99\%, Llama DR $-$59\%.
157	F1\,$\times$100.}
158	\label{tab:composability}
159	\end{table}
160	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3ddec28d-d893-4c0c-a7ad-6040962867c4",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "3dfadd65-645f-4674-87bb-1dab795d2e73",
  "sourceToolAssistantUUID": "3ddec28d-d893-4c0c-a7ad-6040962867c4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-18T17:23:17.472Z_

<details open><summary>🔧 Tool call — Read · `toolu_0154xZZPgpJcRNK94mZ9bJP1`</summary>

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
  "parentUuid": "3dfadd65-645f-4674-87bb-1dab795d2e73",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRKVyNNJfNDLdX521x",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3f59120f-8e4b-4fcc-b83d-b73276284e33",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0176GwmzeP27jhtYcoTcrYTu",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1974,
      "cache_read_input_tokens": 31013,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1974,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 37,
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

_source line 34 · 2026-05-18T17:23:17.479Z_

<details><summary>↩ Tool result · `toolu_0154xZZPgpJcRNK94mZ9bJP1`</summary>

```text
1	% Section 5 — DocRED Results (compressed, 1450→~600 words)
2	% exp_ids: phase2_docred_unconstrained, phase2_docred_grammar_only,
3	%          phase2_docred_semantic_only, phase2_docred_full_s1
4	% All numbers verified against registry 2026-05-14.
5	
6	\subsection{Cross-Dataset Validation on DocRED}
7	\label{sec:docred-results}
8	
9	Table~\ref{tab:docred-ablation} presents the four-way ablation on DocRED (96 Wikidata relation types, 14$\times$ SciERC; Qwen3-8B, zero-shot, 998 documents).
10	
11	% ──────────────────────────────────────────
12	%  Table: DocRED four-way ablation
13	% ──────────────────────────────────────────
14	\begin{table}[t]
15	\centering
16	\small
17	\setlength{\tabcolsep}{3.6pt}
18	\resizebox{\columnwidth}{!}{%
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
50	\end{tabular}}%
51	\caption{Four-way ablation on DocRED (998 documents, Qwen3-8B, zero-shot).
52	$\Delta$DR: relative change vs.\ unconstrained.
53	Best per column in \textbf{bold} (CF excluded).
54	F1 $\times$100. Bootstrap significance: R-F1 $+$0.50\,pp ($p < 0.001$).}
55	\label{tab:docred-ablation}
56	\end{table}
57	
58	% exp_ids: phase2_docred_unconstrained, phase2_docred_full_s1
59	\paragraph{Core result.}
60	Full S1 reduces DR from 18.46\% to 10.21\% ($\downarrow$45\%), eliminates ET ($\to$\,0\%), and near-eliminates RV (29.66\%\,$\to$\,0.03\%).\footnote{The residual 0.03\% RV traces to a rare XGrammar automaton edge case where subword tokens from different enum entries combine into chimeric values (e.g., \texttt{member} + \texttt{icipant\_of} from \texttt{member\_of} and \texttt{participant\_of}). This is not a fundamental limitation of the approach.}
61	R-F1 improves from 7.74 to 8.23 ($+$0.50\,pp; $p < 0.001$), attributable to elimination of 5{,}189 OOV relation predictions.
62	CF increases modestly (0.10\%\,$\to$\,2.57\%), consistent with the CF$\leftrightarrow$DR trade-off (\S\ref{sec:discussion}).
63	
64	% exp_ids: phase2_docred_grammar_only
65	\paragraph{Grammar layer surfaces latent violations.}
66	Grammar-only constraints eliminate RV and ET but \emph{increase} DR to 26.17\% ($+$42\%): the baseline's 29.66\% OOV triples cannot be evaluated for DR; grammar enforcement assigns valid relation names whose domain/range rules the associated types frequently violate, \emph{revealing} latent incompatibilities that motivate the semantic layer.
67	
68	% exp_ids: phase2_docred_semantic_only, phase2_docred_full_s1
69	\paragraph{Enabling dependency and tightness ceiling.}
70	Semantic-only reduces DR by 25\% but cannot eliminate RV (29.87\%) or prevent ET increases (2.48\%\,$\to$\,4.22\%), which replicates SciERC's enabling dependency.
71	Residual DR (10.21\%) exceeds SciERC's (0.93\%) due to higher constraint tightness ($\bar{\kappa}{=}0.842$ vs.\ 0.333): residual DR of 10.21\% implies effective semantic coverage of approximately 90\%, consistent with tight constraints forcing frequent grammar-first fallback (Appendix~\ref{app:fallback-coverage}).
72	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3f59120f-8e4b-4fcc-b83d-b73276284e33",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "f61a047d-ab81-4a8b-bfea-14efcc360870",
  "sourceToolAssistantUUID": "3f59120f-8e4b-4fcc-b83d-b73276284e33",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-18T17:23:17.937Z_

<details open><summary>🔧 Tool call — Read · `toolu_01RAupcXGemgG1JUEvrA3j5r`</summary>

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
  "parentUuid": "f61a047d-ab81-4a8b-bfea-14efcc360870",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRKVyNNJfNDLdX521x",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "54e1f12c-ba28-4866-a5cc-0994ffa5a73a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0176GwmzeP27jhtYcoTcrYTu",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1974,
      "cache_read_input_tokens": 31013,
      "output_tokens": 261,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1974
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 261,
          "cache_read_input_tokens": 31013,
          "cache_creation_input_tokens": 1974,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1974,
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

_source line 36 · 2026-05-18T17:23:17.941Z_

<details><summary>↩ Tool result · `toolu_01RAupcXGemgG1JUEvrA3j5r`</summary>

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
10	Table~\ref{tab:cross-model} replicates full S1 with Llama-3.1-8B-Instruct and Mistral-7B-Instruct-v0.3 under identical prompts and evaluation.
11	Mistral serves as a third zero-shot verification point; composability evaluation (\S\ref{sec:composability}) uses LoRA, available only for Qwen and Llama.
12	
13	\begin{table}[t]
14	\centering
15	\small
16	\setlength{\tabcolsep}{3.4pt}
17	\resizebox{\columnwidth}{!}{%
18	\begin{tabular}{@{}ll rrrr r@{}}
19	\toprule
20	& & \multicolumn{4}{c}{\textbf{Violation Rates (\%)}}
21	& \textbf{R-F1} \\
22	\cmidrule(lr){3-6} \cmidrule(l){7-7}
23	\textbf{Dataset} & \textbf{Model}
24	  & DR\,$\downarrow$ & RV\,$\downarrow$ & ET\,$\downarrow$ & CF
25	  & $\uparrow$ \\
26	\midrule
27	\multirow{6}{*}{SciERC}
28	  & Qwen (U)    & 15.37 & 1.39  & 0.40 & 0.08 & 8.23 \\
29	  & Qwen (S1)   &  0.93 & 0     & 0    & 9.90 & 8.36 \\
30	  \cmidrule(l){2-7}
31	  & Llama (U)   & 13.34 & 0.55  & 0    & 0.24 & 2.68 \\
32	  & Llama (S1)  &  0.08 & 0     & 0    & 6.56 & 2.54 \\
33	  \cmidrule(l){2-7}
34	  & Mistral (U) & 56.94 & 0     & 1.50 & 56.87$^\dagger$ & 3.66 \\
35	  & Mistral (S1)& 13.40 & 0     & 0    & 1.27  & 3.67 \\
36	\midrule
37	\multirow{6}{*}{DocRED}
38	  & Qwen (U)    & 18.46 & 29.66 & 2.48 & 0.10 & 7.74 \\
39	  & Qwen (S1)   & 10.21 &  0.03 & 0    & 2.57 & 8.23 \\
40	  \cmidrule(l){2-7}
41	  & Llama (U)   & 26.07 & 16.03 & 0.13 & 0.17 & 5.98 \\
42	  & Llama (S1)  &  2.55 &  0    & 0    & 12.02& 6.27 \\
43	  \cmidrule(l){2-7}
44	  & Mistral (U) & 57.42 & 42.35 & 7.58 & 24.78 & 4.34 \\
45	  & Mistral (S1)& 33.20 &  0    & 0    & 0.19  & 5.52 \\
46	\bottomrule
47	\end{tabular}}%
48	\caption{Three-model zero-shot validation. U: unconstrained; S1: full two-layer.
49	Parse failures: Llama DocRED 9.1\%; others $\leq$1.1\%.
50	$^\dagger$Mistral: poor zero-shot calibration causes pervasive type inconsistencies.
51	F1 $\times$100.}
52	\label{tab:cross-model}
53	\end{table}
54	
55	% exp_ids: phase2_scierc_full_s1, llama_scierc_full_s1, phase2_docred_full_s1, llama_docred_full_s1, mistral_scierc, mistral_docred
56	\paragraph{Results.}
57	RV and ET are eliminated ($\leq$0.03\%) for all models on both datasets.
58	DR drops 76--99\% on SciERC and 42--90\% on DocRED; R-F1 improves in five of six settings (DocRED: Qwen $+$0.50\,pp, $p{<}0.001$; Llama $+$0.29\,pp, $p{=}0.013$).
59	Cross-model DR asymmetry reflects baseline RV: Llama's lower RV (16.03\% vs.\ 29.66\%) limits latent violation surfacing, yielding 2.55\% residual DR vs.\ 10.21\%.
60	CF direction depends on baseline calibration: S1 introduces CF for calibrated models (up to 12.02\%; \S\ref{sec:discussion}), while reducing CF for poorly-calibrated Mistral (56.87\%\,$\to$\,1.27\%).
61	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "54e1f12c-ba28-4866-a5cc-0994ffa5a73a",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "dfcafeaa-5696-46db-b8f5-b191f71ee32f",
  "sourceToolAssistantUUID": "54e1f12c-ba28-4866-a5cc-0994ffa5a73a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-18T17:23:22.333Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AHtmo7a92wae2nLWs7aHEy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/section5_wikievents_draft.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dfcafeaa-5696-46db-b8f5-b191f71ee32f",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRyBsmMfBxMvfpcPqA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "17d94974-a533-4d93-8aba-0939f8405996",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tu1QvinvANEa2c6NRBD1XB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7255,
      "cache_read_input_tokens": 32987,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7255,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 36,
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

_source line 38 · 2026-05-18T17:23:22.340Z_

<details><summary>↩ Tool result · `toolu_01AHtmo7a92wae2nLWs7aHEy`</summary>

```text
1	% Section 5 — Event Extraction on WikiEvents (compact, inline)
2	% exp_ids: ee_qwen_wikievents_unconstrained, ee_llama_wikievents_unconstrained,
3	%          ee_mistral_wikievents_unconstrained, ee_qwen_wikievents_constrained,
4	%          ee_llama_wikievents_constrained, ee_mistral_wikievents_constrained_v2
5	% v3 final data confirmed by Director 2026-05-18.
6	
7	\subsection{Cross-Task Validation: Event Extraction}
8	\label{sec:wikievents}
9	
10	To test generality beyond RE, we apply OntoCoDec to event extraction (EE) on WikiEvents~\cite{li2021document} (56 event types, 80 argument roles, 27 entity types, 245 role$\to$type constraints; Appendix~\ref{app:wikievents}).
11	The framework requires no modification: grammar compiles event/role vocabularies into a CFG; the semantic layer enforces role-conditioned type constraints via the same registry.
12	Violations extend to Event Vocabulary (EV), Role Vocabulary (RoV), and Argument Constraint (AC, analogous to DR).
13	
14	% ──────────────────────────────────────────
15	%  Table: WikiEvents three-model comparison (v3 final)
16	%  exp_ids: ee_{qwen,llama,mistral}_wikievents_{unconstrained,grammar_only,constrained_v3}
17	% ──────────────────────────────────────────
18	\begin{table}[t]
19	\centering
20	\small
21	\setlength{\tabcolsep}{2.8pt}
22	\resizebox{\columnwidth}{!}{%
23	\begin{tabular}{@{}ll rrrr rr@{}}
24	\toprule
25	& & \multicolumn{4}{c}{\textbf{Violation Rates (\%)}}
26	& \multicolumn{2}{c}{\textbf{F1}} \\
27	\cmidrule(lr){3-6} \cmidrule(l){7-8}
28	\textbf{Model} & \textbf{Mode}
29	  & EV\,$\downarrow$ & RoV\,$\downarrow$ & AC & CF
30	  & Trig.\,$\uparrow$ & Ent.\,$\uparrow$ \\
31	\midrule
32	\multirow{3}{*}{Qwen3-8B}
33	  & Unconstr.\ & 24.0 & 74.9 & 0.3 & 0 & 11.8 & 0 \\
34	  & Grammar    & \textbf{0} & 76.1 & 8.2 & --- & --- & --- \\
35	  & Full S1    & \textbf{0} & \textbf{0} & 2.1 & 21.1 & 13.4 & 14.1 \\
36	\midrule
37	\multirow{3}{*}{\shortstack[l]{Llama\\3.1-8B}}
38	  & Unconstr.\ & 10.5 & 88.8 & 0.1 & 0 & 5.7 & 0 \\
39	  & Grammar    & \textbf{0} & 77.0 & 8.8 & --- & --- & --- \\
40	  & Full S1    & \textbf{0} & \textbf{0} & 3.8 & 17.2 & 7.5 & 17.6 \\
41	\midrule
42	\multirow{3}{*}{\shortstack[l]{Mistral\\7B}}
43	  & Unconstr.\ & 37.3 & 63.9 & 0 & 0 & 2.4 & 0 \\
44	  & Grammar    & \textbf{0} & 64.0 & 13.8 & --- & --- & --- \\
45	  & Full S1    & \textbf{0} & \textbf{0} & 1.3 & 14.9 & 3.9 & 11.7 \\
46	\bottomrule
47	\end{tabular}}%
48	\caption{WikiEvents EE results (246 documents, zero-shot).
49	Violation rates over parsed documents.
50	---: not applicable (grammar-only has no semantic-layer metrics).
51	F1 $\times$ 100.}
52	\label{tab:wikievents}
53	\end{table}
54	
55	\paragraph{Results.}
56	Unconstrained generation produces extreme vocabulary violations (EV+RoV exceeding 85\% combined; Table~\ref{tab:wikievents}), and all models yield entity F1\,=\,0 because the parser cannot identify well-formed mentions in off-schema output.
57	Full S1 eliminates EV and RoV across all three models ($\to$\,0\%), which validates tokenizer-agnostic design across byte-level BPE (Qwen, Llama) and SentencePiece (Mistral).
58	Grammar-only ablation isolates each layer: grammar eliminates EV ($\to$\,0\%) but leaves RoV at 64--77\% because the CFG cannot constrain 80 argument roles conditioned on event context; AC rises from near-zero to 8--14\%, the same latent-violation surfacing pattern observed in DocRED (\S\ref{sec:docred-results}).
59	Full S1 then drives RoV to 0\%, which demonstrates layer complementarity.
60	Residual AC (1.3--3.8\%) traces to confusion between semantically similar entity types (e.g., SID vs.\ SEN) where grammar-first fallback permits the incorrect type; CF rises to 15--21\%, consistent with the per-slot enforcement trade-off in RE.
61	
62	Post-hoc filtering is impractical for EE: it retains only 23/5{,}467 arguments for Qwen (99.6\% discarded), 3/5{,}053 for Llama, and 0/6{,}034 for Mistral, because unconstrained models generate generic role names rather than ontology-specific ones.
63	Unlike RE, where constraints are F1-neutral, EE shows measurable gains: entity F1 rises from 0\% to 11.7--17.6\% and trigger F1 increases by $+$1.5--1.8\,pp, because grammar enforcement produces schema-valid JSON that the parser can process.
64	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "17d94974-a533-4d93-8aba-0939f8405996",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "d35dcb91-a57a-4d84-8033-5ad125140f79",
  "sourceToolAssistantUUID": "17d94974-a533-4d93-8aba-0939f8405996",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-18T17:23:22.834Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DHGXzUB1vJgAMHzzw196xc`</summary>

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
  "parentUuid": "d35dcb91-a57a-4d84-8033-5ad125140f79",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRyBsmMfBxMvfpcPqA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ce77b9a6-ac33-4fd2-ace8-63f49b934a03",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tu1QvinvANEa2c6NRBD1XB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7255,
      "cache_read_input_tokens": 32987,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7255,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 36,
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

_source line 40 · 2026-05-18T17:23:22.839Z_

<details><summary>↩ Tool result · `toolu_01DHGXzUB1vJgAMHzzw196xc`</summary>

```text
1	% Runtime overhead (inline paragraph, no subsection header to save space)
2	
3	\paragraph{Runtime overhead.}
4	\label{sec:runtime}
5	Full S1 adds $+$13.1\% wall-clock overhead on SciERC (Qwen3-8B, zero-shot greedy, RTX PRO 6000 Blackwell); under fine-tuning, overhead drops to $+$2.3\% (61\,ms/doc).
6	Grammar compile is a one-time 44\,ms cost.
7	Details in Appendix~\ref{app:runtime}.
8	
9	\paragraph{Beam search compatibility.}
10	\label{sec:beam-results}
11	Beam search ($k{=}4$) addresses greedy decoding's two residual limitations on SciERC (551 documents): DR drops to 0\% for calibrated models (Qwen 0.93\%\,$\to$\,0\%; Llama 0.08\%\,$\to$\,0\%) and CF decreases substantially (Qwen 9.90\%\,$\to$\,0.53\%; Llama 6.56\%\,$\to$\,0.93\%).
12	Combined with LoRA, both calibrated models achieve zero violations across all four metrics on SciERC (Qwen3-8B R-F1\,=\,44.23; Llama-3.1-8B R-F1\,=\,46.11; Appendix~\ref{app:beam-search}).
13	
14	% === 70B cross-scale (PLACEHOLDER — awaiting DocRED 70B results) ===
15	%\paragraph{Cross-scale generalizability.}
16	%\label{sec:70b-results}
17	%To evaluate cross-scale generalizability, we test OntoCoDec on Llama-3.1-70B-Instruct (AWQ INT4 quantization).
18	%On SciERC, the 70B model produces fewer baseline violations than its 8B counterpart (DR 6.5\% vs.\ 13.3\%), yet violations persist; OntoCoDec eliminates them entirely (DR$\to$0\%, R-F1 $-$0.03\,pp).
19	%On DocRED, [PLACEHOLDER for 70B DocRED results].
20	%Case studies comparing 8B and 70B behavior appear in Appendix~\ref{app:case-scale}.
21	
22	Appendix~\ref{app:case-studies} presents representative case studies illustrating constraint behavior across violation types.
23	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ce77b9a6-ac33-4fd2-ace8-63f49b934a03",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "1dbf9932-8383-4e3d-bcfd-a0333f846c3f",
  "sourceToolAssistantUUID": "ce77b9a6-ac33-4fd2-ace8-63f49b934a03",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-18T17:23:23.426Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KrcSDmYv1xKWxfR6QjVH4d`</summary>

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
  "parentUuid": "1dbf9932-8383-4e3d-bcfd-a0333f846c3f",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARRyBsmMfBxMvfpcPqA",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "41005c84-4583-4bef-a8f9-10494766e6a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Tu1QvinvANEa2c6NRBD1XB",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7255,
      "cache_read_input_tokens": 32987,
      "output_tokens": 257,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7255
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 257,
          "cache_read_input_tokens": 32987,
          "cache_creation_input_tokens": 7255,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7255,
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

_source line 42 · 2026-05-18T17:23:23.431Z_

<details><summary>↩ Tool result · `toolu_01KrcSDmYv1xKWxfR6QjVH4d`</summary>

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
15	However, all of these methods operate exclusively at the syntactic level: they ensure format validity (e.g., well-formed JSON, valid enum values) but cannot enforce cross-field semantic constraints such as ontology domain/range rules that depend on previously generated content.
16	This syntactic-only limitation motivates OntoCoDec's semantic extension: our grammar layer builds on XGrammar for structural (JSON schema and enum) constraints, while a second semantic layer enforces relational type constraints that are inherently beyond the expressive power of context-free grammars.
17	
18	% ===========================================================================
19	% Paradigm 1.5: Semantic Constrained Decoding for Code
20	% ===========================================================================
21	\paragraph{Semantic Constrained Decoding for Code.}
22	In programming-language generation, constrained decoding has been extended beyond syntax to enforce semantic properties such as type correctness, demonstrating that richer-than-CFG constraints can be compiled into token-level filtering.
23	In the text-to-SQL domain, PICARD~\cite{scholak2021picard} maintains an incremental SQL parsing state that rejects tokens violating syntax or referencing non-existent database columns at each decoding step, achieving state-of-the-art results on Spider and CoSQL without modifying model weights.
24	While mechanistically similar to OntoCoDec's token-level filtering, PICARD operates over a \emph{fixed, fully enumerated} schema (database table and column names known before decoding begins).
25	In contrast, OntoCoDec's entity registry is populated \emph{during} generation as entity spans are extracted from free text, requiring constraint sets that evolve with the decoding prefix, a fundamental distinction between querying a known schema and extracting from unstructured text.
26	Synchromesh~\cite{synchromesh_iclr2022} pioneers Constrained Semantic Decoding (CSD), which enforces syntax, type, and scope constraints simultaneously during code generation from pre-trained LMs without fine-tuning, establishing that semantic constraints can be expressed as dynamic token masks conditioned on the generation prefix.
27	MGD~\cite{mgd_neurips2023} uses static-analysis monitors to perform incremental type checking at decode time, enabling SantaCoder-1.1B to outperform text-davinci-003 on repository-level code completion by ensuring that every generated identifier is type-correct with respect to the surrounding code context.
28	Most recently, \citet{pldi2025_type_constrained_codegen} compile full type systems, including generic types and subtyping, into prefix automata for token-level logits masking, reducing compilation errors by over 50\%.
29	This last system is the closest mechanistic analog to OntoCoDec, applying the same ``type system $\to$ automaton $\to$ logits mask'' pipeline, though in a fundamentally different domain.
30	The key technical difference lies in the constraint structure: programming-language type systems feature deep subtyping hierarchies and parametric polymorphism, whereas IE ontology axioms specify flat domain/range sets; a relation $R$ accepts head entities from set $\mathcal{D}(R)$ and tail entities from set $\mathcal{R}(R)$, with no subtype chains.
31	Conversely, IE introduces a challenge absent in code generation: the constraint target (entity type) must be inferred from free-text spans rather than read from declared type annotations, requiring a stateful entity registry that tracks extracted types during autoregressive generation.
32	These methods collectively demonstrate that semantic (type) constraints at decode time are both feasible and highly effective, but exclusively in the code domain where type systems are formally specified.
33	OntoCoDec is the first to \emph{automatically compile} IE ontology axioms, including domain/range constraints, into token-level decoding masks for information extraction, migrating the type-constrained decoding paradigm from code generation to IE.
34	
35	% ===========================================================================
36	% Paradigm 2: Vocabulary/Type-Constrained Generation
37	% ===========================================================================
38	\paragraph{Vocabulary and Type-Constrained Generation.}
39	The idea of enforcing entity-type compatibility constraints for information extraction dates back to pre-neural methods.
40	\citet{roth_yih_2004} formulate joint entity and relation identification as an integer linear program (ILP) that enforces type constraints (e.g., \textsc{Emp-Org} only between \textsc{Per} and \textsc{Org} entities), establishing the foundational principle that relational type compatibility should be a hard constraint, not a soft preference learned from data.
41	In the autoregressive era, GENRE~\cite{decao2021genre} pioneers trie-based constrained beam search for autoregressive entity retrieval, restricting each decoding step to tokens consistent with valid entity names from a predefined catalog.
42	GenIE~\cite{josifoski2022genie} extends this approach to end-to-end information extraction with state-based constraints that enforce valid triple structures, achieving strong performance on closed-world knowledge base population, though it requires task-specific fine-tuning on the target schema.
43	AdaKGC~\cite{adakgc_emnlp2023} introduces schema-constrained dynamic decoding with trie-based prefix trees that adapt to the target schema, enforcing that generated entity and relation names belong to a predefined inventory, a vocabulary-level constraint that ensures name validity but does not verify type compatibility between a relation and its arguments.
44	GCD~\cite{geng2023gcd} provides a unified grammar-constrained decoding framework for structured NLP tasks including IE, introducing input-dependent grammars that adapt constraints based on the source text. GCD is the closest precursor to OntoCoDec in applying logits masking to IE, though limited to syntactic constraints.
45	NeuroLogic Decoding~\cite{lu2021neurologic} expresses lexical inclusion and exclusion constraints as predicate logic formulas enforced during beam search, offering a general mechanism for token-level control that can encode vocabulary membership but not relational type rules.
46	These approaches constrain \emph{which tokens} can appear (vocabulary membership) but not \emph{which type combinations} are valid for a given relation.
47	OntoCoDec's semantic layer enforces relational constraints (e.g., that the head entity of relation $R$ must belong to type set $\mathcal{D}(R)$) which cannot be expressed as static vocabulary restrictions because the valid set depends on the relation type generated earlier in the same sequence.
48	While Roth \& Yih's ILP formulation shares the same type-compatibility motivation, it operates as a post-hoc reranker over discrete candidates; OntoCoDec integrates enforcement directly into autoregressive decoding, preventing violations rather than filtering them.
49	
50	% ===========================================================================
51	% Paradigm 3: Structural Constraints for IE
52	% ===========================================================================
53	\paragraph{Structural Constraints via Training and Prompting.}
54	An orthogonal approach encodes IE output structure through model training or prompt design rather than decoding-time enforcement, relying on learned representations to produce schema-compliant outputs.
55	UIE~\cite{lu2022uie} defines a Structured Extraction Language and trains a unified text-to-structure model across 13 IE datasets, relying on large-scale pre-training to internalize output format constraints.
56	GoLLIE~\cite{sainz2024gollie} expresses annotation guidelines as Python dataclass definitions and fine-tunes Code-LLaMA to generate typed code, achieving strong zero-shot transfer to unseen IE schemas by leveraging the implicit type structure of programming languages.
57	KnowCoder~\cite{knowcoder_acl2024} takes this further by encoding 29K entity types from Wikidata as a Python class hierarchy, training a Code-LLM to generate structured extraction code that implicitly respects type inheritance, the most comprehensive schema-as-code approach to date.
58	CodeIE~\cite{li2023codeie} similarly reformulates IE as code generation, leveraging the structural regularity of programming languages to reduce output format errors.
59	ADELIE~\cite{qi2024adelie} uses SFT and DPO to align LLMs on IE tasks, achieving state-of-the-art results among open-source models while preserving general capabilities, though compliance with ontological constraints remains a learned soft preference rather than a guarantee.
60	In the supervised setting, joint entity-relation architectures such as SpERT~\cite{eberts2020spert} and PFN~\cite{yan2021pfn} enforce type consistency implicitly through shared representations: SpERT classifies entity spans and relation pairs in a single BERT pass with span-level negative sampling, while PFN decomposes feature encoding into entity-specific, relation-specific, and shared partitions via gating mechanisms.
61	These models achieve strong performance but are limited to fixed, predefined schemas and cannot generalize to unseen ontologies without retraining, precisely the zero-shot, ontology-portable scenario that OntoCoDec targets.
62	EnriCo~\cite{zaratiana2024enrico} applies Answer Set Programming (ASP) constraints during decoding of joint entity-relation extraction models, enforcing structural type compatibility at generation time. This is a decoding-time approach, though with model-specific, manually authored constraints rather than ontology-driven compilation.
63	Training-based methods provide \emph{soft} structural guidance: the model learns to prefer valid outputs but cannot guarantee compliance at inference time, as demonstrated by non-trivial violation rates even in fine-tuned systems.
64	Importantly, training-based and decoding-time approaches are complementary rather than competing: a system like GoLLIE could be combined with OntoCoDec's constraint layers, using fine-tuning to maximize the probability of valid outputs while decoding-time enforcement eliminates residual violations.
65	OntoCoDec provides \emph{hard} decoding-time enforcement that is training-free, automatically compiled from ontology schemas, and composable with any of these training-based approaches.
66	
67	% ===========================================================================
68	% Paradigm 4: Type-Checking / Ontology Validation
69	% ===========================================================================
70	\paragraph{Post-hoc Ontology Validation.}
71	Rather than constraining generation, several methods validate LLM outputs against ontological rules after generation, applying a detect-then-fix paradigm.
72	ODKE+~\cite{khorshidi2025odke} dynamically generates ontology snippets containing domain/range constraints as prompt context, achieving 98.8\% precision across 195 predicates at web scale, but constraint adherence relies on prompt-level guidance, not enforcement, leaving residual violations unaddressed.
73	SPIRES/OntoGPT~\cite{spires_2024} provides an ontology-based extraction framework that grounds LLM outputs against OBO ontologies post-generation, validating extracted entities and relations through ontology lookup and correcting mismatches in a second pass, representing the prompt-then-validate paradigm in the biomedical domain.
74	OntoLogX~\cite{ontologx_2025} applies SHACL validation to LLM-generated knowledge graphs, iteratively re-prompting the LLM to correct constraint violations and reducing them by approximately 10$\times$ across multiple correction rounds. This demonstrates the detect-then-fix paradigm's effectiveness but also its inherent multi-pass cost.
75	\citet{upadhyay2023openie} inject entity-type knowledge as constraints into Open IE via both constrained inference and constraint-aware training, improving F1 by 29\% on CaRB, though their constrained inference operates over a discrete candidate set rather than during autoregressive generation.
76	\citet{regino2025kgcurator} propose a multi-stage LLM pipeline for validating RDF triple insertions against RDFS domain/range constraints, where each validation step requires a separate LLM call, effective but computationally expensive at scale.
77	RELATE~\cite{olasunkanmi2025relate} addresses the alignment gap between LLM-extracted biomedical relations and standardized ontology predicates through a three-stage pipeline: ontology preprocessing with predicate embeddings, similarity-based retrieval via SapBERT, and LLM-based reranking with negation handling, achieving 94\% accuracy@10 on ChemProt.
78	While RELATE demonstrates effective ontology grounding for relation extraction, its constraints are applied \emph{post-extraction} through retrieval and reranking rather than during generation, and it requires domain-specific embedding models trained on biomedical corpora.
79	OntoCoDec enforces ontology constraints \emph{during} autoregressive decoding and requires no additional trained components beyond the base LLM.
80	Concurrently, \citet{zhou2026ontologytools} compile OWL ontologies into executable tool interfaces within The World Avatar framework, requiring LLM agents to invoke ontology-aware tools that enforce semantic constraints during knowledge graph construction from scientific text.
81	This ``ontology-to-tools'' approach shares OntoCoDec's philosophy of compiling formal ontological knowledge into runtime enforcement mechanisms, but operates at the tool-call level (constraining which API functions the agent invokes) rather than at the token level (constraining which tokens the decoder produces), and requires an agentic multi-step workflow rather than single-pass autoregressive generation.
82	\citet{ekaw2024_ontology_beam} introduce ontology-constrained beam scoring for clinical summarization, applying soft biases (not hard masks) during beam search to steer outputs toward ontology-compliant terms, a middle ground between unconstrained generation and hard enforcement that reduces but cannot eliminate violations.
83	Post-hoc validation detects violations after generation, requiring rejection or correction cycles that waste compute. In our setting, 15.37\% of generated triples contain domain/range violations under unconstrained decoding, representing substantial wasted generation effort.
84	OntoCoDec \emph{prevents} violations during decoding, redirecting probability mass to valid alternatives rather than discarding invalid outputs, with only marginal overhead from logits masking compared to the cost of regenerating or correcting violated triples.
85	Soft-constraint approaches such as ontology-weighted beam scoring reduce violation frequency but cannot eliminate it, whereas OntoCoDec substantially reduces violations (DR$\downarrow$94\% on SciERC, $\downarrow$45--90\% on DocRED depending on model).
86	
87	% ===========================================================================
88	% Paradigm 5: Constrained Decoding Quality Concerns
89	% ===========================================================================
90	\paragraph{Quality Impact of Constrained Decoding.}
91	A growing body of work raises concerns that constrained decoding degrades LLM generation quality, particularly for reasoning-intensive tasks where format enforcement interferes with chain-of-thought processes.
92	\citet{tam2024letmespeak} conduct a comprehensive evaluation showing that rigid format constraints (JSON, XML) harm performance on math and multi-hop QA benchmarks but \emph{benefit} classification-style tasks such as slot filling, a distinction directly relevant to IE, which is fundamentally an extraction (classification-like) task rather than a reasoning task.
93	CRANE~\cite{banerjee2025crane} provides theoretical analysis of why restricting outputs to narrow grammars suppresses chain-of-thought reasoning by eliminating intermediate reasoning tokens, and proposes an alternating strategy between unconstrained reasoning phases and constrained output phases to mitigate this effect.
94	\citet{schall2025hiddencost} conduct a systematic study across 11 models and multiple benchmarks, finding 10--30\% semantic correctness degradation on reasoning tasks under structural constraints, with larger models showing greater absolute degradation.
95	\citet{zhou2026snowballing} identify ``structure snowballing,'' a failure mode where format compliance cognitive load traps models in repetitive structural patterns rather than improving reasoning during self-correction iterations.
96	These findings establish a legitimate concern for constrained decoding in reasoning-heavy applications.
97	However, information extraction occupies a fundamentally different regime: the model extracts entities and relations from input text rather than generating novel reasoning chains, and \citet{tam2024letmespeak}'s own results show that extraction-style tasks are robust to, or even benefit from, format constraints.
98	OntoCoDec addresses this concern empirically: domain/range violations decrease by 94\% on SciERC (15.37\%$\to$0.93\%) and 45--90\% on DocRED across two models, with F1-neutral impact on SciERC ($+$0.13pp, $p{=}0.58$) and significant R-F1 gains on DocRED (Qwen $p{<}0.001$, Llama $p{=}0.013$).
99	Critically, OntoCoDec's constraints target only type tokens (entity types, relation labels), leaving free-text spans (entity surface forms and their boundaries) entirely unconstrained, which minimizes the distribution distortion that causes quality degradation in reasoning tasks.
100	A two-pass variant (S2), explored in ablation (Section~5), separates extraction and constraint enforcement into distinct passes, analogous to CRANE's alternating strategy; however, our primary single-pass approach already avoids reasoning interference by constraining only type tokens while leaving free-text spans unconstrained.
101	
102	% ===========================================================================
103	% Our Approach
104	% ===========================================================================
105	\paragraph{Our Approach.}
106	OntoCoDec occupies a unique position in this landscape: it is the first system to \emph{automatically compile} IE ontology schemas, including domain/range axioms, into token-level semantic masks, extending grammar-constrained decoding from syntactic to semantic enforcement without manually authored rules.
107	Unlike vocabulary-constrained methods that restrict individual tokens to a fixed set, OntoCoDec enforces \emph{cross-field relational constraints} through a stateful entity registry that tracks extracted types during autoregressive generation, enabling dynamic constraint evaluation that depends on previously decoded content.
108	This approach is orthogonal to supervised IE methods and applicable to any autoregressive LM without model modification or additional training.
109	Unlike training-based IE systems, OntoCoDec is training-free and substantially reduces type violations at inference time (DR$\downarrow$94\% on SciERC, $\downarrow$45--90\% on DocRED); unlike post-hoc validation, it prevents violations rather than detecting them, redirecting probability mass to valid alternatives with significant R-F1 gains on DocRED ($p \leq 0.013$) and F1-neutral impact on SciERC.
110	The two constraint layers, grammar (structural) and semantic (relational), compose via bitwise AND with an enabling dependency: the grammar layer ensures every generated type token belongs to the valid vocabulary, which enables the semantic layer to look up and enforce domain/range rules for that type.
111	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "41005c84-4583-4bef-a8f9-10494766e6a9",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "3af4fe2a-993e-482d-839f-ca0353a80f9d",
  "sourceToolAssistantUUID": "41005c84-4583-4bef-a8f9-10494766e6a9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 43 · 2026-05-18T17:23:33.258Z_

Now let me also read the appendix discussion and the bibliography to check reference coverage.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3af4fe2a-993e-482d-839f-ca0353a80f9d",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARSNbHXPjtTAce5sDv7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c15e2d57-6afd-49f5-9045-df8919c13d99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QRmACuUiNNpe4FC67uU9LV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7696,
      "cache_read_input_tokens": 40242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7696,
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

_source line 44 · 2026-05-18T17:23:35.679Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LaNbiqymxvfNn2pWivYSY8`</summary>

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
  "parentUuid": "c15e2d57-6afd-49f5-9045-df8919c13d99",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARSNbHXPjtTAce5sDv7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fd2cba5d-e9cd-4d25-a56d-2eec30f47a67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QRmACuUiNNpe4FC67uU9LV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7696,
      "cache_read_input_tokens": 40242,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7696,
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

_source line 45 · 2026-05-18T17:23:36.043Z_

<details><summary>↩ Tool result · `toolu_01LaNbiqymxvfNn2pWivYSY8`</summary>

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
13	(2)~\emph{Grammar-first fallback} (\S\ref{sec:interaction}): when the semantic mask conflicts with all grammar-valid tokens, the semantic layer is dropped entirely, allowing the grammar layer to generate any structurally valid type, which may differ from the entity's registered type.
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
27	\emph{Grammar-first fallback} (36.6\% of type-bearing positions on SciERC) occurs when $S(t) \cap G(t) = \emptyset$: the semantic layer deactivates as a safety valve, preserving structural validity at the cost of potential type violations. These events account for the residual DR that persists after constraint enforcement.
28	\emph{Registry-consistent fallback} (4.5\%) occurs when the entity's registered type conflicts with domain/range constraints; the system defaults to the registered type for cross-triple consistency.
29	Together, these mechanisms produce the characteristic profile of composable constraint systems: residual DR traces to grammar-first fallback events, while CF violations arise from registry override events where per-relation enforcement assigns conflicting types.
30	
31	We define \emph{effective semantic constraint coverage} as $1 - f_{\text{gf}}$, where $f_{\text{gf}}$ is the grammar-first fallback rate.
32	On SciERC, Llama-3.1-8B shows $f_{\text{gf}} = 36.6\%$ (6{,}237 of 17{,}024 mask calls), yielding 63.4\% effective coverage.
33	On DocRED, by contrast, Qwen3-8B shows $f_{\text{gf}} = 0.08\%$ (46 of 54{,}859), yielding 99.9\% coverage.
34	The large discrepancy is primarily a tokenization artifact: SciERC entity types are multi-token (e.g., \textsc{OtherScientificTerm}, averaging 2.87 mask calls per type field), and continuation tokens necessarily conflict with the semantic mask, inflating the per-mask-call fallback rate.
35	DocRED types (\textsc{PER}, \textsc{ORG}, \textsc{LOC}, \textsc{TIME}, \textsc{NUM}, \textsc{MISC}) are all single-token, eliminating this inflation.
36	This metric directly quantifies the enabling dependency (\S\ref{sec:interaction}): it measures the fraction of decoding steps where both constraint layers are jointly active, providing a fine-grained view beyond aggregate violation rates.
37	Qwen3-8B, with zero grammar-first fallbacks, achieves 100\% effective coverage on SciERC, consistent with its lower residual DR (0.93\% vs.\ Llama's 0.08\%).
38	
39	%%% CF-DR Trade-off Analysis %%%
40	% exp_ids: cf_fallback_ablation_scierc (CF fallback vs full_s1 baseline)
41	
42	\paragraph{CF-DR Trade-off Analysis.}
43	\label{app:cf-dr-tradeoff}
44	
45	CF violations are the most prominent residual limitation of OntoCoDec under zero-shot decoding (9.90\% on SciERC, up to 12.02\% on Llama DocRED).
46	We treat this honestly: per-relation independent enforcement cannot eliminate CF without trading it against DR.
47	Table~\ref{tab:cf-dr-tradeoff} reports a pilot ablation in which we replace the grammar-first fallback with a CF-priority fallback that forces the entity's registered type when it conflicts with $\sigma(r)$.
48	
49	\begin{table}[t]
50	\centering
51	\small
52	\begin{tabular}{@{}l rrrr@{}}
53	\toprule
54	\textbf{Configuration} & \textbf{DR\,(\%)} & \textbf{CF\,(\%)} & \textbf{DR+CF} & \textbf{$f_{\text{gf}}$\,(\%)} \\
55	\midrule
56	Full S1 (baseline) & 0.93 & 9.90 & 10.83 & --- \\
57	CF fallback        & 14.78 & 0.04 & 14.82 & 36.64 \\
58	\midrule
59	$\Delta$ & $+$13.85 & $-$9.86 & $+$3.99 & --- \\
60	\bottomrule
61	\end{tabular}
62	\caption{CF-DR trade-off pilot on SciERC (Qwen3-8B, 551 documents; \texttt{w1\_cf\_fallback\_scierc\_pilot}). CF fallback eliminates CF but re-routes violations to DR, increasing total violations (DR+CF) by 3.99\,pp. $f_{\text{gf}}$: grammar-first fallback rate at type-bearing positions.}
63	\label{tab:cf-dr-tradeoff}
64	\end{table}
65	
66	The CF fallback variant nearly eliminates CF (9.90\%\,$\to$\,0.04\%, $-$9.86\,pp) but at the cost of a 15.9$\times$ increase in DR (0.93\%\,$\to$\,14.78\%, $+$13.85\,pp).
67	% exp_id: w1_cf_fallback_scierc_pilot: DR=0.1478, CF=0.0004, f_gf=0.3664
68	This is not a net improvement: total violations (DR+CF) rise from 10.83\% to 14.82\% ($+$3.99\,pp), so the change \emph{re-routes} violations rather than reducing them.
69	The mechanism is mechanical: each token position with conflicting masks must commit to one violation type; when the CF fallback forces the system to emit the entity's registered type even though it lies outside $\sigma(r)$, the resulting triple satisfies cross-entity consistency but violates domain/range.
70	The grammar-first fallback is triggered at 36.64\% of type-bearing positions, indicating that this conflict is structural, not a tunable hyperparameter.
71	
72	We interpret this as a fundamental tension in composable constraint systems with \emph{per-relation independent} enforcement: enforcement priority can be allocated between DR and CF but cannot independently minimize both.
73	Within this design, the current full S1 configuration sits near the Pareto frontier of the trade-off, achieving 0.93\% DR at the cost of 9.90\% CF.
74	The direction of the trade-off is consistent beyond SciERC/Qwen3-8B: across all six zero-shot configurations (3 models $\times$ 2 datasets), DR and CF are inversely associated (Spearman $\rho = -0.77$, $n{=}6$), with no setting showing both high DR and high CF simultaneously (Table~\ref{tab:cross-model}).
75	The pattern is a structural consequence of per-relation enforcement with grammar-first fallback, not a model- or dataset-specific artifact; we select SciERC/Qwen3-8B for detailed ablation because it exhibits the highest CF (9.90\%), making the trade-off most visible.
76	While the inverse association holds across all configurations, the absolute trade-off magnitude may differ in settings with higher baseline CF, such as Llama DocRED (CF = 12.02\%), where the larger CF headroom could yield proportionally larger shifts under alternative fallback priorities.
77	The CF residual is concentrated in schema ambiguity rather than enforcement failure: 63.3\% of CF violations on SciERC involve the catch-all \textsc{Generic} type (Table~\ref{tab:cf-distribution}), which competes with every content type depending on anaphoric vs.\ referential use, a distinction the per-slot decoder cannot resolve without document-level coreference.
78	
79	Two complementary paths can lower CF without re-routing it to DR.
80	(i)~\emph{Reduce the baseline conflict rate.} Composing OntoCoDec with LoRA fine-tuning on SciERC reduces CF by 88\% relative to the zero-shot setting (9.90\%\,$\to$\,1.18\%; Table~\ref{tab:composability}), because the fine-tuned model's per-slot type predictions agree more often with the entity registry, so the per-relation mask and the registry intersect more frequently.
81	% exp_id: w5_lora_scierc_constrained_eval: CF=0.0118
82	The remaining 1.18\% still traces to \textsc{Generic}$\leftrightarrow$X schema ambiguity, so this path is empirically validated on one dataset and one fine-tuning method but does not generalize without further evidence.
83	(ii)~\emph{Replace per-relation enforcement with global entity-level type consensus during decoding.} This is outside the scope of OntoCoDec's forward-only autoregressive design and is left to future work.
84	
85	%%% Dual-Factor Quantitative Analysis %%%
86	% exp_ids: phase2_scierc_full_s1, phase2_docred_full_s1,
87	%          llama_scierc_full_s1, llama_docred_full_s1
88	
89	\paragraph{Dual-Factor Quantitative Analysis.}
90	\label{app:dual-factor}
91	
92	Figure~\ref{fig:dual-factor-scatter} plots residual DR against the product $\bar{\kappa} \times \text{RV}_{\text{baseline}}$ for model$\times$dataset configurations.
93	For \emph{calibrated} models (Qwen3-8B, Llama-3.1-8B; unconstrained ET${<}$3\% on both datasets), a linear fit yields $y = 0.366x - 0.138$ with $R^2 = 0.886$ ($n{=}4$, $F(1,2) = 15.54$, $p \approx 0.058$); with only four data points (df $= 2$) and $p > 0.05$, this constitutes a descriptive characterization rather than a confirmatory statistical test.
94	The strong fit supports the dual-factor pattern from \S\ref{sec:composition}: residual DR is governed by the product of schema tightness and baseline violation rate.
95	Mistral-7B (unconstrained ET${=}$7.58\% on DocRED) deviates from this pattern: its residual DR on DocRED (33.21\%) substantially exceeds the linear prediction, confirming that when model calibration is insufficient (ET${>}$5\% on either dataset), residual DR is dominated by entity misclassification rather than constraint-search failure.
96	This motivates a principled exclusion criterion: models with unconstrained ET${>}$5\% on either dataset fall outside the regime where the tightness$\times$RV product is the primary DR driver.
97	The two DocRED points (high $\bar{\kappa}{=}0.842$) separate cleanly from the two SciERC points (low $\bar{\kappa}{=}0.333$), and within each dataset the model with higher baseline RV shows higher residual DR.
98	
99	\begin{figure}[t]
100	\centering
101	\includegraphics[width=0.75\columnwidth]{figures/dual_factor_scatter.pdf}
102	\caption{Residual DR vs.\ $\bar{\kappa} \times \text{RV}_{\text{baseline}}$ across four model$\times$dataset configurations.
103	Linear fit (calibrated models): $y = 0.366x - 0.138$, $R^2 = 0.886$; Mistral deviates due to entity misclassification.}
104	\label{fig:dual-factor-scatter}
105	\end{figure}
106	
107	%%% Dataset-Dependent F1 Impact (moved from §7) %%%
108	% exp_ids: d012_bootstrap_ci (DocRED +0.50pp p<0.001, SciERC +0.13pp p=0.58),
109	%          phase0_docred_unconstrained (RV=29.66%), phase0_scierc_unconstrained (RV=1.39%)
110	
111	\paragraph{Dataset-Dependent F1 Impact.}
112	The divergence in F1 significance between DocRED ($+$0.50\,pp, $p < 0.001$) and SciERC ($+$0.13\,pp, $p = 0.58$) traces to a single mechanism: grammar-layer elimination of out-of-vocabulary relation names.
113	DocRED's baseline RV of 29.66\% produces 5{,}189 OOV predictions counted as false positives; eliminating them yields a significant precision gain.
114	SciERC's baseline RV is only 1.39\% (24 OOV predictions), too few to produce a detectable F1 effect.
115	Llama-3.1-8B's lower baseline RV (16.03\%) yields a smaller but directionally consistent improvement ($+$0.29\,pp vs.\ $+$0.50\,pp), confirming that F1 gain magnitude is proportional to baseline OOV rate.
116	% exp_ids: phase0_docred_unconstrained, phase0_scierc_unconstrained
117	% exp_ids: llama_docred_unconstrained (RV=16.03%), llama_docred_full_s1 (R-F1 delta=+0.29pp)
118	
119	%%% Paragraph 1: Low F1 Practical Significance %%%
120	% exp_ids: phase2_scierc_full_s1 (R-F1=8.36%), phase2_docred_full_s1 (R-F1=8.23%),
121	%          phase0_scierc_unconstrained (DR=15.37%), phase2_docred_unconstrained (DR=18.46%)
122	
123	\paragraph{Practical Significance of Zero-Shot F1.}
124	Our reported relation F1 of approximately 8\% on both SciERC and DocRED reflects the inherent difficulty of zero-shot closed IE, where the model receives no task-specific training examples.
125	For reference, supervised state-of-the-art systems on SciERC achieve approximately 49--53\% relation F1 with full training data~\citep{zhong2021frustratingly,ye2022packed}.
126	Constraint enforcement operates largely independently of the extraction model's intrinsic capability: it restricts the output space to ontologically valid triples regardless of the underlying model's accuracy.
127	When applied to fine-tuned models that reach competitive F1 levels, the same constraints remain necessary: Phase~0 analysis confirms that even well-prompted models exhibit non-trivial violation rates (15.37\% DR on SciERC, 18.46\% on DocRED).
128	% exp_ids: phase0_scierc_unconstrained, phase2_docred_unconstrained
129	In our evaluation, F1 serves as a \emph{control variable} verifying that constraint enforcement does not degrade extraction quality, not as an optimization target.
130	The contribution of this work is the constraint enforcement method itself; the zero-shot setting isolates its effect from confounds introduced by task-specific fine-tuning.
131	
132	%%% Paragraph 4: Decoding-Time vs. Post-Hoc Enforcement %%%
133	% exp_ids: posthoc_filtering_baseline, phase2_scierc_full_s1 (R-F1=8.36%),
134	%          phase2_docred_full_s1 (R-F1=8.23%, ET=0%)
135	
136	\paragraph{Decoding-Time vs.\ Post-Hoc Enforcement.}
137	Post-hoc filtering (generating triples without constraints, then removing schema-violating predictions) yields higher precision and consequently higher F1 than OntoCoDec on both datasets (SciERC 8.63 vs.\ 8.36; DocRED 9.61 vs.\ 8.23).
138	% posthoc: SciERC F1=8.63, DocRED F1=9.61; OntoCoDec: SciERC R-F1=8.36, DocRED R-F1=8.23
139	However, this precision gain comes at substantial cost.
140	On DocRED, post-hoc filtering discards 48.1\% of all predicted triples, including 127 true positives (11.2\% of correct predictions), reducing recall from 9.46\% to 8.40\%.
141	% posthoc_docred: rejection=48.1%, tp_lost=127/1137, R: 9.46→8.40
142	Entity type violations remain unresolved (ET\,=\,2.47\% vs.\ OntoCoDec's 0\%), as filtering targets only domain/range and vocabulary violations.
143	% posthoc_docred: ET_residual=2.47%; phase2_docred_full_s1: ET=0%
144	OntoCoDec's decoding-time approach avoids this information loss by guiding generation toward compliant outputs rather than discarding non-compliant ones, preserving both recall and entity type validity.
145	The two strategies are complementary: post-hoc filtering can serve as an additional safety net for residual violations that decoding-time enforcement does not fully resolve.
146	
147	%%% CF Violation Distribution %%%
148	% exp_ids: phase2_scierc_full_s1 (CF=245), llama_scierc_full_s1 (CF=162),
149	%          phase2_docred_full_s1 (CF=2670), llama_docred_full_s1 (CF=3824)
150	
151	\paragraph{Cross-Field Violation Distribution.}
152	\label{app:cf-distribution}
153	
154	Table~\ref{tab:cf-distribution} reports the complete distribution of conflicting-type pairs for SciERC full S1 (245 CF violations, all pairwise; no mention triggered $\geq$3 types).
155	Conflicts involving the \textsc{Generic} type account for 63.3\% (155/245) of all violations.
156	\textsc{Generic} is SciERC's anaphoric/placeholder label (``this approach'', ``the method''), which competes with every content type depending on whether the mention is used anaphorically or referentially, a distinction the per-slot constrained decoder cannot resolve without document-level coreference.
157	
158	The pattern generalizes across models and datasets: on Llama-3.1-8B SciERC, \textsc{Generic}$\leftrightarrow$\textsc{OtherScientificTerm} remains the top pair (53/162, 32.7\%); on DocRED, the analogous catch-all type \textsc{MISC} drives 76.6\% of Qwen's CF violations.
159	Under unconstrained decoding, CF rates collapse to $\leq$1\% on both datasets, confirming that CF violations are a side-effect of per-slot type commitment rather than a model deficiency.
160	
161	\begin{table}[t]
162	\centering
163	\small
164	\begin{tabular}{@{}lr r@{}}
165	\toprule
166	\textbf{Conflicting Type Pair} & \textbf{Count} & \textbf{\%} \\
167	\midrule
168	Generic $\leftrightarrow$ OtherScientificTerm & 85 & 34.7 \\
169	Generic $\leftrightarrow$ Material & 35 & 14.3 \\
170	Generic $\leftrightarrow$ Metric & 30 & 12.2 \\
171	Method $\leftrightarrow$ Task & 20 & 8.2 \\
172	Material $\leftrightarrow$ Method & 17 & 6.9 \\
173	OtherScientificTerm $\leftrightarrow$ Task & 12 & 4.9 \\
174	\midrule
175	10 further pairs (each $\leq$3.3\%) & 46 & 18.8 \\
176	\midrule
177	\textbf{Total} & \textbf{245} & 100.0 \\
178	\bottomrule
179	\end{tabular}
180	\caption{CF violation distribution on SciERC full S1 (Qwen3-8B, 551 documents).
181	All 245 violations are pairwise conflicts.
182	Conflicts involving \textsc{Generic} account for 63.3\%.}
183	\label{tab:cf-distribution}
184	\end{table}
185	
186	%%% Per-Relation DR Elimination under Fine-Tuning %%%
187	% exp_ids: lora_scierc_unconstrained, lora_scierc_full_s1
188	
189	\paragraph{Per-Relation DR Elimination under Fine-Tuning.}
190	\label{app:lora-per-relation}
191	
192	Table~\ref{tab:lora-per-relation} presents the per-relation breakdown of DR elimination when OntoCoDec is composed with LoRA fine-tuning on SciERC.
193	Fine-tuning alone eliminates DR on four of seven relations but leaves non-zero violations on the three tightest-constraint relations: \textsc{Evaluate-for} ($\kappa{=}0.361$, 13.13\%), \textsc{Part-of} ($\kappa{=}0.417$, 5.77\%), and \textsc{Compare} ($\kappa{=}0.528$, 5.00\%).
194	Adding OntoCoDec constraints eliminates all remaining violations across all relations.
195	One \textsc{Evaluate-for} triple (99\,$\to$\,98) is redirected to \textsc{Used-for} (634\,$\to$\,635) by token-level masking: the head entity's registered type falls outside \textsc{Evaluate-for}'s domain, and the semantic mask steers generation to the nearest valid relation.
196	
197	\begin{table}[t]
198	\centering
199	\small
200	\begin{tabular}{@{}l r rr rr@{}}
201	\toprule
202	& & \multicolumn{2}{c}{\textbf{LoRA Unconstr.}} & \multicolumn{2}{c}{\textbf{LoRA + S1}} \\
203	\cmidrule(lr){3-4} \cmidrule(l){5-6}
204	\textbf{Relation} & $\kappa$ & DR\,(\%) & $n$ & DR\,(\%) & $n$ \\
205	\midrule
206	Evaluate-for & 0.361 & 13.13 & 99 & \textbf{0} & 98 \\
207	Part-of      & 0.417 & 5.77  & 52 & \textbf{0} & 52 \\
208	Compare      & 0.528 & 5.00  & 40 & \textbf{0} & 40 \\
209	Conjunction  & 0.306 & 1.31  & 153 & \textbf{0} & 153 \\
210	Feature-of   & 0.278 & 1.35  & 74 & \textbf{0} & 74 \\
211	Used-for     & 0.028 & 0.16  & 634 & \textbf{0} & 635 \\
212	Hyponym-of   & 0.417 & 0     & --- & \textbf{0} & --- \\
213	\bottomrule
214	\end{tabular}
215	\caption{Per-relation DR elimination on SciERC with LoRA fine-tuning (Qwen3-8B).
216	$\kappa$: constraint tightness; $n$: predicted triple count.
217	Used-for gains one triple from Evaluate-for redirection.}
218	\label{tab:lora-per-relation}
219	\end{table}
220	
221	%%% Fine-Tuned Four-Way Ablation %%%
222	% exp_ids: w5_lora_scierc_*, w5_llama_lora_scierc_*, w5_qwen_docred_*, w5_llama_docred_*, w8_*
223	
224	\paragraph{Fine-Tuned Four-Way Ablation.}
225	\label{app:ft-ablation}
226	
227	Table~\ref{tab:ft-ablation} presents the four-way constraint ablation on fine-tuned models across both datasets, isolating each layer's contribution when the base model has already internalized schema knowledge.
228	
229	\begin{table}[t]
230	\centering
231	\small
232	\setlength{\tabcolsep}{3pt}
233	\resizebox{\columnwidth}{!}{%
234	\begin{tabular}{@{}lll rrrrr rr@{}}
235	\toprule
236	\textbf{Dataset} & \textbf{Model} & \textbf{Mode} & \textbf{DR\,$\downarrow$} & \textbf{RV\,$\downarrow$} & \textbf{ET\,$\downarrow$} & \textbf{CF} & \textbf{PF} & \textbf{E-F1\,$\uparrow$} & \textbf{R-F1\,$\uparrow$} \\
237	\midrule
238	\multirow{8}{*}{SciERC}
239	  & \multirow{4}{*}{Qwen3-8B}
240	    & Unconstrained & 1.95 & 0.00 & 0.00 & 0.00 & 0.00 & 67.05 & 43.86 \\
241	  & & Grammar       & 1.90 & 0.00 & 0.00 & 0.00 & 0.00 & 67.05 & 43.86 \\
242	  & & Semantic      & 0.60 & 0.00 & 0.00 & 0.18 & 0.00 & 67.05 & 43.69 \\
243	  & & Full S1       & \textbf{0}    & 0.00 & 0.00 & 1.18 & 0.00 & 67.05 & 43.77 \\
244	  \cmidrule(l){2-10}
245	  & \multirow{4}{*}{Llama-3.1-8B}
246	    & Unconstrained & 1.11 & 0.00 & 0.00 & 0.00 & 0.00 & 67.76 & 45.45 \\
247	  & & Grammar       & 1.11 & 0.00 & 0.00 & 0.00 & 0.00 & 67.76 & 45.45 \\
248	  & & Semantic      & 0.65 & 0.00 & 0.00 & 0.10 & 0.00 & 67.76 & 45.47 \\
249	  & & Full S1       & \textbf{0.09} & 0.00 & 0.00 & 0.46 & 0.00 & 67.76 & 45.47 \\
250	\midrule
251	\multirow{8}{*}{DocRED}
252	  & \multirow{4}{*}{Qwen3-8B}
253	    & Unconstrained & 0.76 & 0.27 & 0.00 & 0.12 & 7.11 & 82.15 & 40.86 \\
254	  & & Grammar       & 0.61 & 0.00 & 0.00 & 0.11 & 7.01 & 82.19 & 40.85 \\
255	  & & Semantic      & 0.21 & 0.23 & 0.00 & 0.27 & 7.52 & 82.15 & 40.89 \\
256	  & & Full S1       & \textbf{0.01} & 0.00 & 0.00 & 0.41 & 8.52 & 81.43 & 40.56 \\
257	  \cmidrule(l){2-10}
258	  & \multirow{4}{*}{Llama-3.1-8B}
259	    & Unconstrained & 0.49 & 0.15 & 0.00 & ---  & 2.30 & 83.93 & 43.72 \\
260	  & & Grammar       & 0.51 & 0.00 & 0.00 & 0.12 & 2.30 & 84.04 & 43.77 \\
261	  & & Semantic      & 0.30 & 0.15 & 0.00 & 0.16 & 2.40 & 84.02 & 43.90 \\
262	  & & Full S1       & \textbf{0.20} & 0.00 & 0.00 & 0.26 & 2.51 & 85.23 & 44.23 \\
263	\bottomrule
264	\end{tabular}}%
265	\caption{Four-way constraint ablation on fine-tuned models (LoRA, 2 models $\times$ 2 datasets).
266	DR/RV/ET/CF: violation rates (\%); PF: parse failure rate (\%); F1 $\times$100.
267	Grammar layer is a no-op post-fine-tuning (DR change $<$0.2\,pp in all 4 settings; RV and ET already 0\% without constraints).
268	Semantic layer is the sole effective DR defense, providing 39--72\% reduction.
269	F1 cost is negligible: max $\Delta$R-F1 = $-$0.30\,pp (Qwen DocRED full vs.\ unconstrained).}
270	\label{tab:ft-ablation}
271	\end{table}
272	
273	The grammar layer is effectively a no-op for fine-tuned models across all four settings: RV and ET are already 0\% without constraints, and grammar-only DR change is $<$0.2\,pp (4/4 settings).
274	The semantic layer is the sole effective DR defense under fine-tuning, independently reducing DR by 39--72\% across all settings (SciERC: Qwen $-$69\%, Llama $-$41\%; DocRED: Qwen $-$72\%, Llama $-$39\%).
275	Adding both layers achieves near-complete elimination (DR\,$\leq$\,0.20\% in all 4 settings), confirming that even after fine-tuning, the semantic layer's pair-based enforcement captures violations that training alone cannot eliminate, specifically on tight-constraint relations where the valid type-pair space is small.
276	F1 cost is negligible: the maximum R-F1 decrease across all 16 model$\times$dataset$\times$mode combinations is $-$0.30\,pp (Qwen DocRED, full vs.\ unconstrained), attributable to parse failure increase (7.11\%\,$\to$\,8.52\%) rather than constraint-induced extraction degradation.
277	
278	%%% Residual DR Error Analysis (Fine-Tuned) %%%
279	% exp_ids: w5_qwen_docred_*, w5_llama_docred_*, w5_lora_scierc_*, w5_llama_lora_scierc_*
280	
281	\paragraph{Residual DR Error Analysis.}
282	\label{app:residual-dr-analysis}
283	
284	Across all fine-tuned settings (2 models $\times$ 2 datasets $\times$ full S1), only 36 domain/range violations remain.
285	Manual inspection reveals four root causes:
286	
287	\begin{enumerate}[nosep,leftmargin=*]
288	\item \emph{Entity type errors} (39\%): the LLM assigns an incorrect entity type (e.g., labeling a geographic entity as \textsc{LOC} when the gold standard requires \textsc{MISC}), causing the semantic mask to permit a domain/range-incompatible relation.
289	\item \emph{Schema coverage gaps} (33\%): the frequency-based constraint table, constructed from training-set co-occurrence statistics, does not cover long-tail type pairs that are ontologically valid but rare. These violations are irreducible by decoding-time constraints alone.
290	\item \emph{Incorrect relation selection} (17\%): the model selects a semantically inappropriate relation whose domain/range constraints are incompatible with the correctly typed entities.
291	\item \emph{Direction reversal} (11\%): the model assigns the correct relation but inverts head/tail roles, placing entities in positions that violate the relation's asymmetric domain/range specification.
292	\end{enumerate}
293	
294	Two dataset-specific patterns emerge.
295	Outside Llama DocRED, all residual violations (3 of 36, spanning Llama SciERC and Qwen DocRED) trace exclusively to schema coverage gaps: the model's entity typing is accurate, and the constraint system has reached its theoretical ceiling given the frequency-based constraint table.
296	On DocRED, Llama-3.1-8B contributes 33 of 36 residual violations (92\%), with entity type errors as the dominant cause (14/33, 42\%).
297	This asymmetry reflects Llama's weaker fine-tuned entity typing on DocRED's larger ontology (96 relations, 7 entity types) compared to Qwen, which achieves near-zero residual.
298	The implication is twofold: (i)~the irreducible floor from schema gaps is small ($\sim$3 violations across 4 settings), confirming that the constraint system operates near its theoretical optimum; (ii)~residual violations from entity typing errors are addressable through stronger base models or improved entity typing modules, without modifying the constraint architecture.
299	
300	%%% Post-Hoc Filtering Comparison (Extended) %%%
301	% exp_ids: posthoc_*_zs, posthoc_*_ft
302	
303	\paragraph{Post-Hoc Filtering: Extended Comparison.}
304	\label{app:posthoc-extended}
305	
306	Table~\ref{tab:posthoc-extended} presents the full comparison across all six zero-shot and four fine-tuned configurations.
307	
308	\begin{table}[t]
309	\centering
310	\small
311	\setlength{\tabcolsep}{3pt}
312	\resizebox{\columnwidth}{!}{%
313	\begin{tabular}{@{}lll rrr l@{}}
314	\toprule
315	\textbf{Setting} & \textbf{Model} & \textbf{Dataset} & \textbf{Reject\%} & \textbf{R-F1$_{\text{ph}}$} & \textbf{R-F1$_{\text{cd}}$} & \textbf{Winner} \\
316	\midrule
317	\multirow{6}{*}{ZS}
318	  & Qwen    & SciERC & 16.8 & 8.63  & 8.36  & ph \\
319	  & Llama   & SciERC & 13.9 & 2.71  & 2.54  & ph \\
320	  & Mistral & SciERC & 20.3 & 3.94  & 3.67  & ph \\
321	  & Qwen    & DocRED & 48.1 & 9.61  & 8.23  & ph \\
322	  & Llama   & DocRED & 42.2 & 7.44  & 6.27  & ph \\
323	  & Mistral & DocRED & \textbf{73.7} & 3.85  & \textbf{5.52} & cd \\
324	\midrule
325	\multirow{4}{*}{FT}
326	  & Qwen    & SciERC & 1.95 & 43.94 & 43.77 & ph \\
327	  & Llama   & SciERC & 1.11 & 45.23 & 45.47 & cd \\
328	  & Qwen    & DocRED & 1.03 & 41.11 & 40.56 & ph \\
329	  & Llama   & DocRED & 0.64 & 43.92 & 44.23 & cd \\
330	\bottomrule
331	\end{tabular}}%
332	\caption{Post-hoc filtering (ph) vs.\ constrained decoding (cd).
333	In zero-shot settings, post-hoc F1 is higher in 5/6 groups (precision-dominated), but constrained decoding preserves higher recall in all 6/6 groups.
334	At reject rate $>$70\% (Mistral DocRED), post-hoc F1 collapses below constrained.
335	Under fine-tuning, rejection rates drop to 0.6--2.0\% and the two strategies are equivalent ($\Delta \leq 0.55$\,pp; each wins two groups).
336	F1 $\times$100.}
337	\label{tab:posthoc-extended}
338	\end{table}
339	
340	The crossover point occurs when post-hoc rejection exceeds $\sim$70\%: Mistral DocRED rejects 73.7\% of predicted triples, discarding enough true positives that constrained decoding's recall advantage dominates ($+$1.67\,pp).
341	OntoCoDec's advantage thus scales with violation severity: precisely when constraints are most needed, post-hoc filtering is most destructive.
342	Under fine-tuning, both strategies converge because few violations remain to filter or constrain ($\Delta \leq 0.55$\,pp across all four FT groups, with each strategy winning two).
343	
344	%%% Zero-Shot Runtime Profiling %%%
345	
346	\paragraph{Zero-Shot Runtime Profiling.}
347	\label{app:runtime}
348	
349	On SciERC (Qwen3-8B, zero-shot greedy, NVIDIA RTX PRO 6000 Blackwell Server Edition), unconstrained inference averages 4.163\,s/doc and Full S1 constrained decoding averages 4.710\,s/doc ($+$13.1\% overhead).
350	Grammar compile is a one-time 0.044\,s cost (amortized to zero).
351	Overhead magnitude varies with GPU and batch configuration; the constraint logic itself adds a fixed per-token masking cost that is independent of hardware.
352	
353	%%% FT Latency %%%
354	
355	\paragraph{Fine-Tuned Latency Profiling.}
356	\label{app:ft-latency}
357	Under LoRA fine-tuning (Qwen3-8B, SciERC, 100 documents, RTX PRO 6000), per-document inference times are: unconstrained 2.594\,s, grammar-only 2.637\,s ($+$1.7\%), semantic-only 2.625\,s ($+$1.2\%), full S1 2.655\,s ($+$2.3\%, $p{<}0.0001$ paired $t$-test).
358	The combined overhead is sub-additive (2.3\% $<$ 1.7\%$+$1.2\%) because fine-tuned models produce fewer grammar-first fallback events (the semantic mask conflicts with grammar-valid tokens less often when per-slot predictions are better calibrated), reducing the number of active masking calls per document.
359	Compared to the zero-shot regime (\S\ref{app:runtime}), absolute overhead decreases from seconds-scale to milliseconds-scale: the fine-tuned model generates shorter, more structured outputs, compressing total generation time from 4.163\,s (zero-shot) to 2.594\,s (fine-tuned) per document on the same GPU.
360	
361	%%% Fuzzy Relation Matching %%%
362	
363	\paragraph{Relation Matching Protocol.}
364	\label{app:fuzzy-matching}
365	Relation F1 evaluation uses fuzzy normalization to handle model-specific formatting variants (e.g., underscores vs.\ spaces, abbreviations).
366	A predicted relation $r_p$ matches gold relation $r_g$ if: (1)~exact string match after case-insensitive normalization, or (2)~token overlap $>$80\% \emph{and} edit distance $\leq 2$.
367	This protocol affects primarily Mistral, which produces underscore-separated variants (e.g., ``head\_of\_government'' for ``head of government'').
368	On Mistral DocRED, fuzzy matching contributes 98 additional TPs ($+$0.84\,pp R-F1; strict R-F1\,=\,3.50\% vs.\ fuzzy 4.34\%).
369	For Qwen and Llama under grammar constraints, the grammar layer enforces exact relation names, making fuzzy matching irrelevant (0 additional matches).
370	All F1 figures in the main text use fuzzy normalization consistently across all models and conditions.
371	
372	%%% Per-Relation Violation Landscape %%%
373	
374	\paragraph{Per-Relation Violation Landscape.}
375	\label{app:per-relation-landscape}
376	
377	Table~\ref{tab:prompt_comparison} compares violation rates under unconstrained and schema-informed prompting.
378	Figure~\ref{fig:per_relation_dr} shows the per-relation DR distribution on SciERC.
379	
380	\begin{table}[t]
381	\centering
382	\small
383	\caption{Violation rates (\%) under unconstrained and schema-informed prompting (Qwen3-8B, zero-shot).}
384	\label{tab:prompt_comparison}
385	\begin{tabular}{ll cccc}
386	\toprule
387	Dataset & Prompt & DR$\downarrow$ & RV$\downarrow$ & ET$\downarrow$ & CF$\downarrow$ \\
388	\midrule
389	\multirow{2}{*}{SciERC} & Unconstrained & 15.4 & 1.4 & 0.4 & 0.1 \\
390	 & Schema-informed & 5.8 & 0.3 & \textbf{0.0} & --- \\
391	\midrule
392	\multirow{2}{*}{DocRED} & Unconstrained & 18.5 & 29.7 & 2.5 & 0.1 \\
393	 & Schema-informed & 12.8 & 18.4 & 0.2 & 0.2 \\
394	\bottomrule
395	\end{tabular}
396	\end{table}
397	
398	\begin{figure}[t]
399	\centering
400	\includegraphics[width=\columnwidth]{figures/fig2_per_relation_dr.pdf}
401	\caption{Per-relation DR violation rates on SciERC (Qwen3-8B, unconstrained). Rates correlate with constraint tightness $\kappa(r)$.}
402	\label{fig:per_relation_dr}
403	\end{figure}
404	
405	%%% WikiEvents Extended %%%
406	
407	\paragraph{WikiEvents Dataset Details.}
408	\label{app:wikievents}
409	WikiEvents~\cite{li2021document} is a document-level event argument extraction benchmark grounded in the DARPA KAIROS ontology.
410	It defines 56 event types, 80 argument roles, and 27 entity types, with 245 (event\_type, role)$\to$allowed\_entity\_types constraints.
411	The grammar layer targets EV (event vocabulary), RoV (role vocabulary), and ET; the semantic layer enforces AC (argument constraint) via role-conditioned masking, analogous to RE domain/range enforcement.
412	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fd2cba5d-e9cd-4d25-a56d-2eec30f47a67",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "dadac339-9cd0-45a6-b8a7-169a3b58bff2",
  "sourceToolAssistantUUID": "fd2cba5d-e9cd-4d25-a56d-2eec30f47a67",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 46 · 2026-05-18T17:23:36.139Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01DnW1rrDQd7fuMnoFHDp94K`</summary>

```json
{
  "pattern": "**/*.bib",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dadac339-9cd0-45a6-b8a7-169a3b58bff2",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARSNbHXPjtTAce5sDv7",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8eb3e1c0-ee66-4f81-b83a-dbf5e8d29830",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QRmACuUiNNpe4FC67uU9LV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7696,
      "cache_read_input_tokens": 40242,
      "output_tokens": 203,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7696
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 203,
          "cache_read_input_tokens": 40242,
          "cache_creation_input_tokens": 7696,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7696,
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

_source line 47 · 2026-05-18T17:23:36.149Z_

<details><summary>↩ Tool result · `toolu_01DnW1rrDQd7fuMnoFHDp94K`</summary>

```text
artifacts/_project/paper/new_citations.bib
artifacts/_project/paper/relwork_new_entries.bib
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8eb3e1c0-ee66-4f81-b83a-dbf5e8d29830",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "4b37f386-c8f2-4e33-99e6-56f56383aec8",
  "sourceToolAssistantUUID": "8eb3e1c0-ee66-4f81-b83a-dbf5e8d29830",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 48 · 2026-05-18T17:23:40.370Z_

<details open><summary>🔧 Tool call — Read · `toolu_01ALadqDRBHL4xboC6tP5gev`</summary>

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
  "parentUuid": "4b37f386-c8f2-4e33-99e6-56f56383aec8",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARTK1mBvdFh1szrPYv8",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "4eb9f1d3-d0a0-478a-a801-18e330b81324",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YTzo9p1MPW73pdaZ3XRz1o",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12339,
      "cache_read_input_tokens": 47938,
      "output_tokens": 98,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 12339
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 98,
          "cache_read_input_tokens": 47938,
          "cache_creation_input_tokens": 12339,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 12339,
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

_source line 49 · 2026-05-18T17:23:40.656Z_

<details><summary>↩ Tool result · `toolu_01ALadqDRBHL4xboC6tP5gev`</summary>

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
443	% Batch 3: New entries added 2026-05-16 (3 entries, Director-requested)
444	% ============================================================
445	
446	% Confirmed via: arXiv:2403.01632, OpenReview HiUZtgAPoH, Illinois Experts page
447	% NOTE: Director specified ICML 2024 — verify volume/pages
448	@inproceedings{ugare2024syncode,
449	  title     = {{SynCode}: {LLM} Generation with Grammar Augmentation},
450	  author    = {Ugare, Shubham and Suresh, Tarun and Kang, Hangoo and Misailovic, Sasa and Singh, Gagandeep},
451	  booktitle = {Proceedings of the 41st International Conference on Machine Learning (ICML)},
452	  year      = {2024},
453	  series    = {PMLR},
454	  volume    = {235},
455	  url       = {https://arxiv.org/abs/2403.01632}
456	}
457	
458	% Confirmed via: OpenReview ac93gRzxxV, ICLR 2025 poster page, arXiv:2410.07295
459	@inproceedings{ugare2025itergen,
460	  title     = {{IterGen}: Iterative Semantic-aware Structured {LLM} Generation with Backtracking},
461	  author    = {Ugare, Shubham and Suresh, Tarun and Banerjee, Debangshu and Misailovic, Sasa and Singh, Gagandeep},
462	  booktitle = {The Thirteenth International Conference on Learning Representations},
463	  year      = {2025},
464	  url       = {https://openreview.net/forum?id=ac93gRzxxV}
465	}
466	
467	% Confirmed via: ACL Anthology 2025.emnlp-main.926, arXiv:2506.14901, EPFL dlab
468	@inproceedings{boostcd2025,
469	  title     = {Combining Constrained and Unconstrained Decoding via Boosting: {BoostCD} and Its Application to Information Extraction},
470	  author    = {Sakota, Marija and Geng, Saibo and Josifoski, Martin and West, Robert},
471	  booktitle = {Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing},
472	  year      = {2025},
473	  url       = {https://aclanthology.org/2025.emnlp-main.926/}
474	}
475	
476	% ============================================================
477	% Dataset & model references (5 entries)
478	% ============================================================
479	
480	% Confirmed via: ACL Anthology D18-1360, arXiv:1808.09602
481	@inproceedings{luan2018scierc,
482	  title     = {Multi-Task Identification of Entities, Relations, and Coreference for Scientific Knowledge Graph Construction},
483	  author    = {Luan, Yi and He, Luheng and Ostendorf, Mari and Hajishirzi, Hannaneh},
484	  booktitle = {Proceedings of the 2018 Conference on Empirical Methods in Natural Language Processing},
485	  pages     = {3219--3232},
486	  year      = {2018},
487	  address   = {Brussels, Belgium},
488	  url       = {https://aclanthology.org/D18-1360/}
489	}
490	
491	% Confirmed via: ACL Anthology P19-1074, arXiv:1906.06127
492	@inproceedings{yao2019docred,
493	  title     = {{DocRED}: A Large-Scale Document-Level Relation Extraction Dataset},
494	  author    = {Yao, Yuan and Ye, Deming and Li, Peng and Han, Xu and Lin, Yankai and Liu, Zhenghao and Liu, Zhiyuan and Huang, Lixin and Zhou, Jie and Sun, Maosong},
495	  booktitle = {Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
496	  pages     = {764--777},
497	  year      = {2019},
498	  address   = {Florence, Italy},
499	  url       = {https://aclanthology.org/P19-1074/}
500	}
501	
502	% Confirmed via: arXiv:2302.10205, Semantic Scholar
503	@article{wei2023zeroshot,
504	  title   = {{ChatIE}: Zero-Shot Information Extraction via Chatting with {ChatGPT}},
505	  author  = {Wei, Xiang and Cui, Xingyu and Cheng, Ning and Wang, Xiaobin and Zhang, Xin and Huang, Shen and Xie, Pengjun and Xu, Jinan and Chen, Yufeng and Zhang, Meishan and Jiang, Yong and Han, Wenjuan},
506	  journal = {arXiv preprint arXiv:2302.10205},
507	  year    = {2023},
508	  url     = {https://arxiv.org/abs/2302.10205}
509	}
510	
511	% Confirmed via: arXiv:2505.09388, Hugging Face model cards
512	@article{qwen2025qwen3,
513	  title   = {Qwen3 Technical Report},
514	  author  = {{Qwen Team}},
515	  journal = {arXiv preprint arXiv:2505.09388},
516	  year    = {2025},
517	  url     = {https://arxiv.org/abs/2505.09388}
518	}
519	
520	% Confirmed via: NeurIPS 2024 proceedings, arXiv:2312.07104
521	@inproceedings{zheng2024sglang,
522	  title     = {{SGLang}: Efficient Execution of Structured Language Model Programs},
523	  author    = {Zheng, Lianmin and Yin, Liangsheng and Xie, Zhiqiang and Sun, Chuyue and Huang, Jeff and Yu, Cody Hao and Cao, Shiyi and Kozyrakis, Christos and Stoica, Ion and Gonzalez, Joseph E. and Barrett, Clark and Sheng, Ying},
524	  booktitle = {Advances in Neural Information Processing Systems},
525	  volume    = {37},
526	  year      = {2024},
527	  url       = {https://arxiv.org/abs/2312.07104}
528	}
529	
530	% Confirmed via: arXiv, ACL 2024
531	@inproceedings{zaratiana2023gliner,
532	  title     = {{GLiNER}: Generalist Model for Named Entity Recognition using Bidirectional Transformer},
533	  author    = {Zaratiana, Urchade and Ngoudi, Nadi and Aziziaden, Amir and Conf, Caleb},
534	  booktitle = {Proceedings of the 2024 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL)},
535	  year      = {2024},
536	  url       = {https://arxiv.org/abs/2311.08526}
537	}
538	
539	% Confirmed via: ACL Anthology 2021.naacl-main.69
540	@inproceedings{li2021document,
541	  title     = {Document-Level Event Argument Extraction by Conditional Generation},
542	  author    = {Li, Sha and Ji, Heng and Han, Jiawei},
543	  booktitle = {Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies (NAACL)},
544	  pages     = {894--908},
545	  year      = {2021},
546	  url       = {https://aclanthology.org/2021.naacl-main.69/}
547	}
548	
549	% Confirmed via: ACL Anthology, SIGDIAL 2024
550	@inproceedings{vukovic2024dore,
551	  title     = {{DORE}: A Dataset for {Portuguese} Knowledge Graph Construction and a Reproduction of a {LLM}-based Ontology-Constrained Approach},
552	  author    = {Vukovi{\'c}, Mila and Prange, Jakob and Navigli, Roberto},
553	  booktitle = {Proceedings of the 25th Annual Meeting of the Special Interest Group on Discourse and Dialogue (SIGDIAL)},
554	  pages     = {291--303},
555	  year      = {2024},
556	  url       = {https://aclanthology.org/2024.sigdial-1.25/}
557	}
558	
559	% ============================================================
560	% New citations added 2026-05-18 (literature freshness check)
561	% ============================================================
562	
563	@inproceedings{grammar_aligned_2024,
564	    author    = {Kanghee Park and Jiayu Wang and Taylor Berg-Kirkpatrick and Nadia Polikarpova and Loris D'Antoni},
565	    title     = {Grammar-Aligned Decoding},
566	    booktitle = {Advances in Neural Information Processing Systems 38 (NeurIPS 2024)},
567	    year      = {2024},
568	    url       = {https://proceedings.neurips.cc/paper_files/paper/2024/hash/2bdc2267c3d7d01523e2e17ac0a754f3-Abstract-Conference.html},
569	}
570	
571	@article{formattax2026,
572	    author    = {Ivan Lee and Loris D'Antoni and Taylor Berg-Kirkpatrick},
573	    title     = {The Format Tax},
574	    journal   = {arXiv preprint arXiv:2604.03616},
575	    year      = {2026},
576	    url       = {https://arxiv.org/abs/2604.03616},
577	}
578	
579	@article{dccd2026,
580	    author    = {Avinash Reddy and Thayne T. Walker and James S. Ide and Amrit Singh Bedi},
581	    title     = {Draft-Conditioned Constrained Decoding for Structured Generation in {LLMs}},
582	    journal   = {arXiv preprint arXiv:2603.03305},
583	    year      = {2026},
584	    url       = {https://arxiv.org/abs/2603.03305},
585	}
586	
587	@inproceedings{slot2025,
588	    author    = {Zhengyuan Shen and Darren Yow-Bang Wang and Soumya Smruti Mishra and Zhichao Xu and Yifei Teng and Haibo Ding},
589	    title     = {{SLOT}: Structuring the Output of Large Language Models},
590	    booktitle = {Proceedings of the 2025 Conference on Empirical Methods in Natural Language Processing: Industry Track},
591	    year      = {2025},
592	    pages     = {472--491},
593	    publisher = {Association for Computational Linguistics},
594	    url       = {https://aclanthology.org/2025.emnlp-industry.32/},
595	}
596	
597	@inproceedings{guidex2025,
598	    author    = {Neil De La Fuente and Oscar Sainz and Iker Garc{\'\i}a-Ferrero and Eneko Agirre},
599	    title     = {{GUIDEX}: Guided Synthetic Data Generation for Zero-Shot Information Extraction},
600	    booktitle = {Findings of the Association for Computational Linguistics: ACL 2025},
601	    year      = {2025},
602	    publisher = {Association for Computational Linguistics},
603	    url       = {https://aclanthology.org/2025.findings-acl.1245/},
604	}
605	
606	@inproceedings{schema_rl2025,
607	    author    = {Yaxi Lu and Haolun Li and Xin Cong and Zhong Zhang and Yesai Wu and Yankai Lin and Zhiyuan Liu and Fangming Liu and Maosong Sun},
608	    title     = {Learning to Generate Structured Output with Schema Reinforcement Learning},
609	    booktitle = {Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics},
610	    year      = {2025},
611	    pages     = {4905--4918},
612	    publisher = {Association for Computational Linguistics},
613	    url       = {https://aclanthology.org/2025.acl-long.243/},
614	}
615	
616	@article{jsonschemabench2025,
617	    author    = {Saibo Geng and Hudson Cooper and Micha{\l} Moskal and Samuel Jenkins and Julian Berman and Nathan Ranchin and Robert West and Eric Horvitz and Harsha Nori},
618	    title     = {{JSONSchemaBench}: A Rigorous Benchmark of Structured Outputs for Language Models},
619	    journal   = {arXiv preprint arXiv:2501.10868},
620	    year      = {2025},
621	    url       = {https://arxiv.org/abs/2501.10868},
622	}
623	
624	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "4eb9f1d3-d0a0-478a-a801-18e330b81324",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "a86bb0de-4e45-42ef-9b8a-8cd404083d96",
  "sourceToolAssistantUUID": "4eb9f1d3-d0a0-478a-a801-18e330b81324",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 50 · 2026-05-18T17:23:46.642Z_

Now I have read all the key sections. Let me also check the dream review reports for additional context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a86bb0de-4e45-42ef-9b8a-8cd404083d96",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARTgowYT85Cvy1iqZdM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "5122335d-82c6-4f33-9348-471fe03f28ab",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01984DKM4fh5q1U5ii9ybDy3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12529,
      "cache_read_input_tokens": 60277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 12529,
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

_source line 51 · 2026-05-18T17:23:49.163Z_

<details open><summary>🔧 Tool call — Read · `toolu_01BNbfqLQhRFRQkNc6MexHhg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/dream_reports/dream_20260518T162745/best/paper.tex",
  "limit": 50
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5122335d-82c6-4f33-9348-471fe03f28ab",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARTgowYT85Cvy1iqZdM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1076555d-2cec-4bf6-b852-dd2460376132",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01984DKM4fh5q1U5ii9ybDy3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12529,
      "cache_read_input_tokens": 60277,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 12529,
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

_source line 52 · 2026-05-18T17:23:49.171Z_

<details><summary>↩ Tool result · `toolu_01BNbfqLQhRFRQkNc6MexHhg`</summary>

```text
1	\documentclass[11pt,a4paper]{article}
2	\usepackage[utf8]{inputenc}
3	\usepackage[T1]{fontenc}
4	\usepackage{amsmath,amssymb}
5	\usepackage{booktabs}
6	\usepackage{multirow}
7	\usepackage{graphicx}
8	\usepackage{hyperref}
9	\usepackage{xcolor}
10	\usepackage{enumitem}
11	\usepackage[margin=2.5cm]{geometry}
12	\usepackage{tabularx}
13	\usepackage{caption}
14	\usepackage{subcaption}
15	
16	\newcommand{\ours}{OntoCoDec}
17	\newcommand{\drsym}{\textsc{DR}}
18	\newcommand{\rvsym}{\textsc{RV}}
19	\newcommand{\etsym}{\textsc{ET}}
20	\newcommand{\cfsym}{\textsc{CF}}
21	\newcommand{\evsym}{\textsc{EV}}
22	\newcommand{\rovsym}{\textsc{RoV}}
23	\newcommand{\acsym}{\textsc{AC}}
24	
25	\title{\ours{}: Universal Ontology-Constrained Structured Generation\\for Information Extraction}
26	
27	\author{Anonymous}
28	\date{}
29	
30	\begin{document}
31	\maketitle
32	
33	%% ============================
34	%% ABSTRACT
35	%% ============================
36	\begin{abstract}
37	Large Language Models (LLMs) produce systematic ontology constraint violations when performing information extraction (IE) tasks, generating entity types and relation arguments that contradict the target schema. We present a violation landscape study across two Relation Extraction (RE) datasets (SciERC, DocRED) and one Event Extraction (EE) dataset (WikiEvents), revealing per-triple violation rates of 13--26\% for domain/range constraints and up to 89\% for role vocabulary constraints. Schema-informed prompting reduces violations by 32--62\% overall but remains unreliable at the per-relation level, with one relation type exhibiting increased violations after prompt intervention.
38	
39	We propose \ours{}, a framework that automatically compiles IE ontology schemas into two composable constraint layers for decoding-time enforcement: a grammar layer (context-free grammar for structural and vocabulary validity) and a semantic layer (stateful entity registry with dynamic logit masking for domain/range constraints). The two layers exhibit an enabling dependency: the grammar layer ensures all generated type tokens belong to the valid vocabulary, which enables the semantic layer to look up and enforce cross-field constraints. Across 2 IE tasks, 4 models (three 8B-class, one 70B), and 3 datasets, \ours{} eliminates vocabulary and entity-type violations entirely while reducing domain/range violations by 44--100\%. On SciERC, residual violations drop to 0.93\% (Qwen3-8B) and 0.08\% (Llama-3.1-8B). On WikiEvents EE, role vocabulary violations drop from 64--89\% to 0\% across all three models. Post-hoc filtering, the natural alternative, discards 17--100\% of predictions and is completely non-viable for event extraction. F1 scores remain neutral or improve significantly.
40	\end{abstract}
41	
42	%% ============================
43	%% 1. INTRODUCTION
44	%% ============================
45	\section{Introduction}
46	
47	Ontology-grounded information extraction requires that every extracted triple or event structure satisfies the type constraints defined by the target schema. A relation extraction (RE) system working with the SciERC ontology, for instance, must ensure that the \textit{Feature-of} relation connects only entities of types permitted by its domain and range specification. An event extraction (EE) system operating under the KAIROS ontology must assign argument roles that are valid for the specific event type and fill them with entities of permitted types. These constraints are not optional quality preferences; downstream knowledge graph construction, reasoning engines, and regulatory compliance pipelines treat them as hard invariants.
48	
49	Despite rapid progress in LLM-based IE, the extent to which generated outputs violate ontology constraints has received little systematic attention. Prior work on constrained decoding has focused on structural validity (well-formed JSON, valid code syntax) rather than semantic schema compliance. We find that even capable 70B-parameter models violate domain/range constraints on 6.5\% of triples for a 7-relation ontology, and the problem does not diminish with ontology simplicity: a 7-relation schema with tight constraints produces comparable violation rates to a 96-relation schema with loose constraints.
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "1076555d-2cec-4bf6-b852-dd2460376132",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "01e00a6f-dc5c-448b-98aa-3af260d7f01c",
  "sourceToolAssistantUUID": "1076555d-2cec-4bf6-b852-dd2460376132",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 53 · 2026-05-18T17:23:50.098Z_

<details open><summary>🔧 Tool call — Read · `toolu_017oBeacjgghw7y14DL8wkTs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie/artifacts/_project/paper/appendix_case_studies.tex",
  "limit": 60
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "01e00a6f-dc5c-448b-98aa-3af260d7f01c",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARTgowYT85Cvy1iqZdM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a7af18e3-03c7-490d-9d92-288be675a10b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01984DKM4fh5q1U5ii9ybDy3",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12529,
      "cache_read_input_tokens": 60277,
      "output_tokens": 239,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 12529
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 239,
          "cache_read_input_tokens": 60277,
          "cache_creation_input_tokens": 12529,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 12529,
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

_source line 54 · 2026-05-18T17:23:50.103Z_

<details><summary>↩ Tool result · `toolu_017oBeacjgghw7y14DL8wkTs`</summary>

```text
1	% Appendix — Error Analysis and Case Studies
2	
3	\section{Error Analysis and Case Studies}
4	\label{app:case-studies}
5	
6	\definecolor{violation}{RGB}{220,50,50}
7	\definecolor{fixed}{RGB}{34,139,34}
8	\definecolor{cfwarn}{RGB}{200,120,0}
9	
10	We present four representative cases illustrating constraint behavior across violation types. Cases 1--3 demonstrate OntoCoDec's corrective mechanisms; Case 4 illustrates a limitation.
11	
12	\subsection{Domain-Range Correction}
13	\label{app:case-dr}
14	
15	\noindent\textbf{Input (SciERC, Qwen3-8B):} \textit{``We present a novel model-based approach to recover the shapes and the poses of transparent objects from known motion.''}
16	
17	The unconstrained model assigns \textsc{OtherScientificTerm} to ``shapes'' and ``poses,'' producing \textsc{Feature-of}(\textsc{Task}, \textsc{OtherScientificTerm}) triples that violate domain/range constraints. The semantic layer redirects the tail type to \textsc{Task}, yielding schema-compliant triples (Table~\ref{tab:case1}).
18	
19	\begin{table}[h]
20	\centering
21	\small
22	\caption{OntoCoDec corrects three Feature-of DR violations. \textcolor{violation}{Red} = violation; \textcolor{fixed}{green} = corrected.}
23	\label{tab:case1}
24	\begin{tabular}{@{}p{3.2cm}lll@{}}
25	\toprule
26	\textbf{Triple} & \textbf{Head} & \textbf{Tail} & \textbf{DR} \\
27	\midrule
28	\multicolumn{4}{@{}l}{\textit{Unconstrained (3 violations)}} \\
29	\midrule
30	Feature-of(recover, shapes) & Task & \textcolor{violation}{OtherSciTerm} & \textcolor{violation}{\ding{55}} \\
31	Feature-of(recover, poses) & Task & \textcolor{violation}{OtherSciTerm} & \textcolor{violation}{\ding{55}} \\
32	Feature-of(recover, transp.\ obj.) & Task & \textcolor{violation}{OtherSciTerm} & \textcolor{violation}{\ding{55}} \\
33	Used-for(model approach, recover) & Method & Task & \ding{51} \\
34	\midrule
35	\multicolumn{4}{@{}l}{\textit{OntoCoDec (0 violations)}} \\
36	\midrule
37	Feature-of(recover, shapes) & Task & \textcolor{fixed}{Task} & \textcolor{fixed}{\ding{51}} \\
38	Feature-of(recover, poses) & Task & \textcolor{fixed}{Task} & \textcolor{fixed}{\ding{51}} \\
39	Used-for(model approach, recover) & Method & Task & \ding{51} \\
40	\bottomrule
41	\end{tabular}
42	\end{table}
43	
44	\subsection{Dual-Layer Vocabulary and Type Correction}
45	\label{app:case-rv-dr}
46	
47	\noindent\textbf{Input (DocRED, Qwen3-8B):} \textit{``Skai TV is a Greek free-to-air television network based in Piraeus. It is part of the Skai Group, one of the largest media groups in the country.''}
48	
49	The unconstrained model generates natural-language relation names (e.g., ``country of origin'') instead of Wikidata P-codes, triggering RV violations. The grammar layer forces valid P-codes; the semantic layer ensures type compatibility (Table~\ref{tab:case2}).
50	
51	\begin{table}[h]
52	\centering
53	\small
54	\caption{Layer~1 eliminates RV violations; Layer~2 corrects DR types on DocRED.}
55	\label{tab:case2}
56	\begin{tabular}{@{}p{4.5cm}p{1.8cm}p{1.2cm}@{}}
57	\toprule
58	\textbf{Unconstrained Output} & \textbf{Violation} & \textbf{Type} \\
59	\midrule
60	rel=``country of origin'' & Not in schema & RV \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a7af18e3-03c7-490d-9d92-288be675a10b",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "8f8936bf-028c-43fd-89cf-c2563aa2e586",
  "sourceToolAssistantUUID": "a7af18e3-03c7-490d-9d92-288be675a10b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 55 · 2026-05-18T17:23:52.661Z_

I now have a comprehensive understanding of the paper. Let me compile my review.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8f8936bf-028c-43fd-89cf-c2563aa2e586",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARULiUuxfDqEu8W7DcG",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "515fa0af-fb69-4f34-83b7-0f167868e893",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nn1NKb9MfuV2iHeuRFmxdK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2677,
      "cache_read_input_tokens": 72806,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2677,
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

_source line 56 · 2026-05-18T17:23:53.755Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01DxvKJfb2oXZFfiKngbW7ET`</summary>

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
  "parentUuid": "515fa0af-fb69-4f34-83b7-0f167868e893",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARULiUuxfDqEu8W7DcG",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "9ea32b9f-0150-481a-a3e0-e3452487c1dc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Nn1NKb9MfuV2iHeuRFmxdK",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2677,
      "cache_read_input_tokens": 72806,
      "output_tokens": 106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 2677
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 106,
          "cache_read_input_tokens": 72806,
          "cache_creation_input_tokens": 2677,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 2677,
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

_source line 57 · 2026-05-18T17:23:53.757Z_

<details><summary>↩ Tool result · `toolu_01DxvKJfb2oXZFfiKngbW7ET`</summary>

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
  "parentUuid": "9ea32b9f-0150-481a-a3e0-e3452487c1dc",
  "isSidechain": true,
  "promptId": "68b31888-2bb0-4dbf-9d98-3d15c1262728",
  "agentId": "a0c165bfcba7de3cc",
  "type": "user",
  "uuid": "0b37049a-3655-4825-9d19-9cabdceb6d22",
  "sourceToolAssistantUUID": "9ea32b9f-0150-481a-a3e0-e3452487c1dc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 58 · 2026-05-18T17:26:06.883Z_



Here is my detailed review.

---

# Review: OntoCoDec: Type-Constrained Information Extraction via Compiled Ontology Constraints

## Reviewer 2 (R2): Novelty, Positioning, and Related Work Coverage

---

## 1. Novelty Assessment (Score: 3.5/6)

**Two-layer architecture (grammar + semantic).** The decomposition into a grammar layer (CFG for structural validity) and a semantic layer (stateful logit masking for domain/range) is a clean engineering design, but it is not deeply novel in concept. The grammar layer is a direct application of XGrammar. The semantic layer is a logits processor that maintains an entity registry and performs lookup-based masking. The intellectual contribution is in the *combination* and the identification that IE requires this two-layer split, but the individual components are straightforward extensions of existing constrained decoding techniques.

**Enabling dependency.** The observation that semantic lookup requires grammar-guaranteed vocabulary membership is a useful architectural insight, but it borders on obvious once the two-layer design is stated. Any system composing a syntactic and semantic constraint layer would naturally need the syntactic layer to execute first. The ablation demonstrating that semantic-only achieves only 24% DR reduction (vs. 94% with both layers) is empirically valuable but does not elevate the enabling dependency to a conceptual contribution. It is a necessary engineering property of the composition.

**Decidability taxonomy.** The three-way classification (local, prefix-decidable, non-local) is the most intellectually interesting component, as it provides a principled framework for reasoning about which constraints can be enforced during autoregressive decoding. However, it is presented in only one paragraph (Section 4) and is not developed into a formal contribution. It reads more like a design note than a theoretical result. A full treatment with formal definitions, proofs of decidability boundaries, and connections to the automata theory literature would significantly strengthen this contribution.

**Relation to existing constrained decoding.** The paper positions itself against XGrammar, Outlines, LMQL, etc. as "syntactic only" and against code-generation type checkers (PICARD, Synchromesh, MGD) as "static schema." This is fair positioning. However, the delta over "XGrammar + a custom logits processor" is arguably thin: a practitioner could implement the entity registry and dynamic masking logic as a custom `LogitsProcessor` callback on top of XGrammar in a few hundred lines of code. The paper does not sufficiently argue why this requires a *framework* rather than a *recipe*.

**Violation landscape study.** The systematic study of DR violation rates across models, datasets, and per-relation tightness (Section 3/5.1) is a solid empirical contribution. The finding that violation rates correlate with constraint tightness rather than ontology scale is non-obvious and useful. The dual-factor analysis (tightness x baseline RV) is descriptive rather than predictive ($n=4$, $p \approx 0.058$), but the directional insight is valuable. As a standalone empirical contribution, this is moderate: it characterizes a known problem (LLMs make type errors) with useful granularity, but it is not a surprising finding.

**Verdict:** The work is primarily engineering with some empirical insight. The decidability taxonomy has potential but is underdeveloped. The violation landscape is a useful but incremental empirical contribution.

---

## 2. Related Work Coverage (Score: 4.5/6)

**Strengths of the related work section.** The coverage is broad and well-organized. The paper cites the major constrained decoding systems (XGrammar, Outlines, LMQL, DOMINO, SynCode, ASAp), the relevant code-generation type checkers (PICARD, Synchromesh, MGD, PLDI 2025), vocabulary-constrained IE methods (GENRE, GenIE, GCD, AdaKGC, NeuroLogic), training-based IE (UIE, GoLLIE, KnowCoder, CodeIE, ADELIE), and post-hoc validation methods (ODKE+, SPIRES, OntoLogX). The extended appendix related work is thorough. The citation of Roth & Yih (2004) for the ILP formulation of type constraints is a good historical anchor.

**Positioning clarity.** The delta over XGrammar + custom logic is stated but could be sharper. The paper says it is "the first to automatically compile IE ontology schemas into token-level semantic masks," but the compilation is relatively simple (lookup tables from $\sigma(r)$). The word "compile" suggests more complexity than what is actually happening. The paper should be more precise about what the compilation entails and why it is non-trivial.

**Missing or underrepresented areas:**

- **Structured prediction with global constraints (CRF-based, ILP-based).** Beyond Roth & Yih (2004), the paper does not cite the broader structured prediction literature that enforces global constraints during inference. Work on constrained CRF decoding, Lagrangian relaxation for structured prediction (Rush & Collins 2012), or dual decomposition approaches is relevant context for the CF trade-off discussion: the paper's inability to enforce global consistency (CF) is a well-known limitation of greedy/local decoding that structured prediction methods address.

- **Knowledge graph embedding with type constraints.** The paper focuses on IE but the downstream motivation is KG construction. Work on type-constrained KG embeddings (TKRL, Xie et al. 2016, which is cited in the bib but seemingly only in passing; TransC, Lv et al. 2018; ConnectE, Zhao et al. 2020) provides important context for why type constraints matter and how they have been enforced in KG completion.

- **Ontology-aware NER.** There is a body of work on using ontology structure to improve NER (e.g., ontology-based NER in biomedical text, using UMLS constraints). This is relevant to the entity registry concept.

- **InstructUIE (Wang et al., 2023).** A prominent zero-shot IE baseline that is not cited despite being directly relevant to the experimental setting.

- **DEGREE (Hsu et al., 2022) and Text2Event (Lu et al., 2021).** Mentioned in the task summary but not cited in the paper. These are important EE baselines, especially for WikiEvents.

- **IterGen (Ugare et al., 2025).** This paper on iterative semantic-aware structured generation with backtracking is in the bib file but does not appear to be cited in the main text or appendix. It is directly relevant as it addresses semantic constraints beyond CFG with a backtracking mechanism that could address the CF problem.

**Differentiation from prior art.** The paper differentiates well from grammar-only methods and from training-based methods. The differentiation from EnriCo (ASP constraints during decoding) is somewhat weak: EnriCo also enforces type constraints during decoding, and the paper's claim of being "the first" needs to be carefully hedged given EnriCo's existence, even though EnriCo uses manually authored rules rather than compiled ontology constraints.

---

## 3. Clarity and Presentation (Score: 4/6)

**Writing quality.** Generally clear and well-structured. The formalization in Sections 2-4 is precise. The violation taxonomy (DR, RV, ET, CF) is well-defined and consistently used. Tables are information-dense and well-formatted.

**Story coherence.** The narrative from Abstract through Conclusion is largely coherent: problem (violations are pervasive) -> existing gap (grammar-only insufficient) -> solution (two-layer architecture) -> validation. However, the CF trade-off complicates the narrative. The paper introduces CF as a new problem created by the solution, which somewhat undermines the "type-safety guarantees" framing in the Abstract and Introduction. The paper handles this honestly but the framing could be tighter: the Abstract says "formal guarantees" but the system introduces 10-21% CF violations in zero-shot settings. This is a tension the reader notices.

**Reproducibility.** Technical details are generally sufficient. The JSON schema, field ordering convention, continuation masking approach, and fallback logic are clearly described. The experiment IDs in comments throughout the .tex files suggest careful provenance tracking. However, code is not yet released ("upon acceptance"), which limits immediate reproducibility.

**Information density.** Tables are dense and well-designed. The five-way ablation (Table 2) and cross-model comparison (Table 4) are efficient. The paper packs a lot of experimental evidence into limited space. Some redundancy exists between the main text and appendix (the appendix extended related work restates points from Section 6).

**Issues:**
- The Abstract is too long (approximately 200 words of dense numbers). The first sentence alone is 41 words. Several specific numbers could be moved to the body.
- The title says "Type-Valid" but the system does not achieve full type validity (residual DR 0.93-33%, CF 0-21%). "Type-Constrained" (used in the `\title{}` tag in main.tex) is more accurate and appropriately modest.
- The paper uses both "Type-Valid" (in the task summary/earlier drafts) and "Type-Constrained" (in the actual main.tex title). This inconsistency should be resolved.

---

## 4. Significance and Impact (Score: 3.5/6)

**Practical adoption.** The framework addresses a real practical need. Any production IE pipeline feeding into a knowledge graph needs type-valid outputs. The 13-21% latency overhead is acceptable. The composability with LoRA is practically important. The implementation is described clearly enough that it could be reproduced on top of existing constrained decoding libraries.

**Conceptual vs. engineering.** This is primarily an engineering contribution with empirical validation. The core idea (add a stateful logits processor for semantic constraints on top of grammar-constrained decoding) is sound but conceptually thin. The decidability taxonomy could elevate the conceptual contribution but is underdeveloped. The violation landscape study adds empirical value but is not conceptually deep.

**Generalizability claim.** The paper claims a "generalizable framework" validated on RE + EE. Two tasks and three datasets is reasonable but not strong evidence of universality. The EE evaluation is zero-shot only (no fine-tuning composability on EE), and the absolute F1 numbers are very low (trigger F1 2-13%, entity F1 0-18%). The paper is honest about this (the constraints improve format compliance rather than extraction quality for EE), but the generalizability claim should be tempered.

**CF trade-off.** The introduction of CF violations (0 -> 10-21% in zero-shot) is a significant limitation that partially undermines the contribution. The paper is commendably transparent about this, including a detailed ablation showing the CF-DR Pareto frontier. However, the fact that the system introduces a new class of violations while eliminating others weakens the "type-safety guarantees" narrative. The resolution via fine-tuning (CF drops to 1.2%) is important but means the full benefit requires training, reducing the "training-free" appeal.

**Scope of evaluation.** The zero-shot R-F1 of approximately 8% on SciERC/DocRED means the system is extracting very few correct triples. While the paper correctly frames F1 as a control variable, reviewers may question whether constraint enforcement matters much when the underlying extraction is this weak. The composability results with LoRA (R-F1 43-46% on SciERC) are much more compelling and should arguably be the primary framing.

---

## 5. Strengths

- **Thorough empirical evaluation.** The paper covers 3 models x 3 datasets x multiple ablation conditions, with bootstrap significance tests, per-relation breakdowns, and honest reporting of negative results (CF trade-off, dual-factor fit with $p=0.058$).

- **Honest treatment of limitations.** The CF trade-off is analyzed in detail rather than hidden. The Pareto frontier analysis, the CF-priority fallback ablation, and the acknowledgment that per-slot enforcement cannot eliminate CF without global consensus are intellectually honest and strengthen the paper.

- **Practical composability demonstration.** Showing that OntoCoDec composes with LoRA fine-tuning (DR to near-zero at <0.6pp F1 cost) and beam search (eliminating all four violation types for calibrated models) demonstrates practical utility beyond the zero-shot setting.

- **Cross-task generalization to EE.** The extension to WikiEvents event extraction without architectural modification is a good demonstration of framework generality, even though the absolute extraction quality is low.

- **Constraint tightness analysis.** The finding that violation rates are driven by constraint tightness rather than ontology scale is a useful empirical insight with practical implications for schema design.

- **Comprehensive related work.** The extended related work (appendix) is one of the most thorough surveys of constrained decoding and ontology-aware IE I have seen, covering grammar-constrained decoding, code-generation type checking, vocabulary-constrained IE, training-based IE, and post-hoc validation.

---

## 6. Weaknesses

- **Limited conceptual novelty.** The core contribution reduces to "apply XGrammar for grammar constraints + implement a custom logits processor for domain/range lookup." The enabling dependency and decidability taxonomy are stated but not developed into substantial conceptual contributions. The paper reads more as a well-executed systems paper than a research paper with novel algorithmic or theoretical insights.

- **CF trade-off undermines the central claim.** The system is framed around "type-safety guarantees" and "formal guarantees during autoregressive generation" (Abstract), but it introduces a new violation class (CF: 0 -> 10-21% in zero-shot). The paper is honest about this, but the framing oversells. A system that eliminates DR but introduces CF has shifted the violation distribution rather than solved the type-validity problem. The "grammar-first fallback" that drops semantic constraints when conflicts arise means the system does *not* provide formal guarantees in the strong sense.

- **Low absolute extraction quality in primary evaluation setting.** The primary zero-shot results show R-F1 of approximately 2-8%, meaning the vast majority of extractions are incorrect. Constraint enforcement on such noisy outputs has limited practical value. The fine-tuned results (R-F1 40-46%) are much more meaningful but receive less emphasis.

- **Narrow model scale range.** All primary experiments use 7-8B models. The 70B results are incomplete (DocRED 70B is still running, SciERC 70B shows violations diminish but persist). The claim of "generalizable framework" would be stronger with complete results across model scales.

- **Missing comparison with IterGen.** IterGen (Ugare et al., ICLR 2025) addresses semantic constraints beyond CFG with a backtracking mechanism. It is in the bib file but not cited or compared against. This is a significant omission given that IterGen's backtracking could potentially address the CF problem that OntoCoDec cannot solve with forward-only decoding.

- **Statistical concerns with dual-factor analysis.** The dual-factor linear fit has $n=4$ data points and $p \approx 0.058$. The paper acknowledges this but still presents it as a "strong fit" supporting the dual-factor pattern. With only 4 points and a non-significant $p$-value, this is a descriptive observation, not a validated model. The scatter plot with 4 points and a regression line is not convincing.

---

## 7. Questions for Authors

1. **IterGen comparison.** IterGen (Ugare et al., ICLR 2025) is in your bibliography but not cited. It supports semantic constraints with backtracking during decoding. Have you considered whether IterGen's backtracking could resolve the CF trade-off that OntoCoDec's forward-only design cannot? If so, why was it excluded?

2. **CF as a downstream risk.** You acknowledge that CF violations "may propagate to downstream tasks" (Limitations). Have you measured the actual downstream impact? If an entity is assigned type A in one triple and type B in another, a KG consumer must choose one. Is the CF-introduced inconsistency more or less harmful than the DR violations it replaces? Without this analysis, it is unclear whether the DR-to-CF shift is net positive.

3. **Why not global type consensus?** You identify global entity-level type consensus as "the most direct resolution path" for CF but leave it to future work. A majority-vote or MAP estimate over entity type assignments across all triples in a document seems implementable within the current framework (e.g., a post-decoding consistency pass). Why was this not attempted? It would not require abandoning forward-only decoding.

4. **Compilation complexity claim.** You describe the system as "compiling" ontology schemas, but the compilation appears to be: (a) generating a JSON Schema with enum constraints, and (b) building a lookup table from $\sigma(r)$. What is the actual compilation complexity, and is "compilation" the right term for what is essentially table construction?

5. **Scaling to large ontologies.** The largest ontology tested has 96 relations (DocRED) and 27 entity types (WikiEvents). Many real-world ontologies (Wikidata: 10K+ properties, UMLS: 100K+ concepts) are orders of magnitude larger. Have you characterized the scaling behavior of the continuation masking approach and the prefix map with respect to ontology size?

---

## 8. Missing References

- **Rush & Collins (2012).** "A Tutorial on Dual Decomposition and Lagrangian Relaxation for Inference in Natural Language Processing." Relevant to the CF trade-off as an example of global constraint enforcement during inference.
- **InstructUIE (Wang et al., 2023).** "InstructUIE: Multi-task Instruction Tuning for Unified Information Extraction." A prominent zero-shot IE baseline.
- **DEGREE (Hsu et al., 2022).** "DEGREE: A Data-Efficient Generation-Based Event Extraction Model." Relevant EE baseline for WikiEvents.
- **Text2Event (Lu et al., 2021).** "Text2Event: Controllable Sequence-to-Structure Generation for End-to-end Event Extraction." Relevant EE baseline.
- **IterGen (Ugare et al., ICLR 2025).** Already in bib but not cited. Directly relevant for semantic constraints with backtracking.
- **TransC (Lv et al., 2018) / ConnectE (Zhao et al., 2020).** Type-constrained KG embeddings, relevant for downstream motivation.
- **CEDAR (Li et al., 2023).** "CEDAR: Communication Efficient Distributed Analysis for Regressions" or the event extraction CEDAR if a different paper. Mentioned in the task summary but not in the paper.

---

## 9. Overall Assessment

**Score: 3.5 / 6 (Borderline Conference, leaning toward Findings)**

**Justification.** The paper addresses a real and practical problem (ontology constraint violations in LLM-based IE) with a clean engineering solution. The experimental evaluation is thorough, the ablation design is strong, and the paper is commendably honest about limitations. The violation landscape study and the tightness analysis provide useful empirical insights.

However, the conceptual novelty is limited. The core contribution is applying existing constrained decoding infrastructure (XGrammar) with a domain-specific logits processor (entity registry + lookup masking). The decidability taxonomy, the most intellectually interesting component, is underdeveloped. The CF trade-off partially undermines the central claim of "type-safety guarantees." The primary evaluation on zero-shot extraction with R-F1 of approximately 2-8% limits practical significance, though the composability with fine-tuning is more convincing.

For a top venue like EMNLP, I would expect either: (a) deeper conceptual novelty (e.g., a formal treatment of the decidability boundaries, a novel algorithm for global type consensus during decoding, or a connection to constraint satisfaction theory), or (b) stronger empirical results demonstrating clear practical impact (e.g., significant F1 gains on competitive extraction settings, not just violation reduction on weak zero-shot baselines).

The paper sits at the boundary between a solid systems/engineering contribution appropriate for Findings and a research contribution sufficient for the main conference. The thorough evaluation and honest limitation analysis are in its favor; the thin conceptual novelty and the CF trade-off are against it.

**Recommendation:** Borderline. Appropriate for Findings if the conceptual contributions (decidability taxonomy) are strengthened and the CF narrative is reframed to avoid overclaiming "formal guarantees." For the main conference, the paper would need either a deeper theoretical contribution or a resolution of the CF problem.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0b37049a-3655-4825-9d19-9cabdceb6d22",
  "isSidechain": true,
  "agentId": "a0c165bfcba7de3cc",
  "requestId": "req_011CbARUcGsAX6zcaL4Mh2h2",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "73d4ffd7-515b-4a52-803e-25233b964412",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_6/projects/schema_semantic_constrained_ie",
  "sessionId": "b63e64f4-dac9-4509-af73-d801c74971fd",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01TWficHXs1XwoA9sq4L5xAr",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 684,
      "cache_read_input_tokens": 75483,
      "output_tokens": 4926,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 684
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 4926,
          "cache_read_input_tokens": 75483,
          "cache_creation_input_tokens": 684,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 684,
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
