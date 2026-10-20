# Research conversation: You are Reviewer R1 for a top ML venue (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 6=Strong Accept). Your foc

**Trace Verbosity Degrades SFT Verdict Prediction: A Case Study in Information Density Effects (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 42
- **Recorded user turns:** 1
- **Tool calls:** 18
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-a5c3828d05260ff7d.jsonl`
- **Structured JSON:** [`0312a563aa11aad2e468.json`](../../sessions/03/0312a563aa11aad2e468.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

42 recorded events

### User

_source line 1 · 2026-05-18T12:31:19.334Z_

You are Reviewer R1 for a top ML venue (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 6=Strong Accept). Your focus is **methodology and experimental rigor**.

## Paper Summary
**Title:** "Exception Events as Diagnostic Signals for Verdict Prediction: A Component Ablation Study Across Four Code LLMs"

The paper studies verdict prediction (binary pass/fail classification of test executions) and asks: what is the minimal sufficient diagnostic signal within execution traces? Using VOTA (Verdict-Oriented Trace Abstraction), traces are decomposed into exception summaries, loop abstractions, and assertion-point comparisons. Through ablation across 4 models (Qwen-2.5-Coder-7B, DeepSeek-Coder-6.7B, Qwen-1.5B, CodeLlama-13B), the central finding is that exception event summaries alone achieve the highest accuracy (99.83% on Qwen-7B, ≥99.3% on 3/4 models in non-outlier seeds).

**Contributions claimed:**
1. Component ablation across 4 models showing exception events dominate
2. Information density decomposition: gradient dilution = 26%, information overload = 74% of full_trace-to-VOTA gap
3. Methodological findings on LoRA initialization sensitivity (training loss masks 8.2pp accuracy gap)

## Paper Structure and Key Data

**Section 3 (Method):**
- Dataset: HumanEval (164) + MBPP-sanitized (427) = 591 problems, 10 solutions each = 5,910 samples. Split: 4,720 train / 1,190 test. Class distribution: 71.5% pass / 28.5% fail.
- 6 trace conditions: no_trace, full_trace, full_trace_label_only, VOTA, exception_only, loop_only, ae_only
- LoRA rank 16, alpha 32, lr 2e-4, AdamW, 3 epochs, max seq 2,048 tokens

**Section 4 (Experiments):**
- Table 1 (Qwen-7B ablation): ae_only 99.92% > exception_only 99.83% > VOTA 99.41% > full_trace_label_only 86.22% > loop_only 85.63% > full_trace 81.76% > no_trace 75.13%
- Table 2 (Cross-model): exception_only Qwen 99.83%, DeepSeek 99.33% (median of 3 seeds; seed 123 = 91.09%)
- Table 3 (4-model exception_only): All non-outlier configs ≥99.3%, ECE<0.009. DeepSeek seed 123 is outlier (91.09%, ECE=0.065)
- Table 4 (SFT vs few-shot): Qwen-7B SFT 99.83%, Claude 3-shot 97.1%, GPT-4o 3-shot 96.5%. Gap = 2.7pp.
- Table 5 (OOD): Python 99.83%, Java 84.5%, JavaScript 81.3%, C++ 76.2%. Mean OOD 80.7%, degradation -19.1pp.
- Table 6 (Error analysis): exception_only 2 errors (GeneratorExit), VOTA 7 scattered, full_trace 217, no_trace 296
- Table 7 (DeepSeek seeds): seed 42/456 = 99.33%, seed 123 = 91.09%. Train loss nearly identical (0.1225 vs 0.1220)
- Table 8 (Cross-seed tail-512): DeepSeek std=6.4pp, others 1.3-2.5pp
- Appendix A: Token budget curve monotonically increasing, no phase transition
- Appendix B: Training dynamics trivial (exception_only converges in ~80 steps)

## Review Context (Imagined Experiments)
The full experiment design includes experiments that may or may not appear in the paper. Key planned experiments and their expected outcomes:
- plan_016 (tail-384 fine-grained budget curve): Mean 89.4% across 4 models, gradual increase, no sharp phase transition. Budget curve is trivially monotonic.
- plan_017 (cross-seed tail-512): DeepSeek std=6.4pp, worst seed only 5.7pp gain over tail-256, undermining any structured transition claim.
- plan_018 (error analysis): No novel failure taxonomy. Exception_only 2 errors already known. VOTA N=7 too small for statistics.
- plan_019 (cross-model calibration): Calibration tracks accuracy (trivial). DeepSeek seed123 ECE=0.065 breaks universality.
- plan_020 (few-shot baseline): GPT-4o/Claude few-shot narrows SFT gap to ~2.7pp. SFT necessity narrative weakened.
- plan_021 (OOD generalization): 19pp degradation, Python-specific patterns exposed.
- plan_022 (training dynamics): Trivially confirms simpler input → faster convergence. No grokking, no insights.

## Your Task
Provide a detailed review focusing on:

1. **Experimental Design Soundness**: Is the ablation well-designed? Are there confounds? Is the evaluation fair?
2. **Statistical Rigor**: Are the claims supported by the evidence? Are confidence intervals / significance tests adequate?
3. **Reproducibility**: Are enough details provided?
4. **Result Interpretation**: Are claims proportional to evidence? Any overclaims?
5. **Missing Experiments**: What critical experiments are missing?
6. **Methodological Concerns**: Any issues with the VOTA pipeline, dataset construction, or training setup?

Format your review as:
```
## R1 Review: Methodology and Experiments

### Summary
[2-3 sentences]

### Strengths
[Numbered list]

### Weaknesses
[Numbered list, with severity: Major/Minor]

### Questions for Authors
[Numbered list]

### Missing Experiments
[Numbered list]

### Detailed Comments
[Section-by-section if needed]

### Preliminary Score: X/6
### Confidence: X/5
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "da6abd63-7d71-4e8d-b585-4f79f2223b11",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-18T12:31:19.339Z_

```json
{
  "parentUuid": "da6abd63-7d71-4e8d-b585-4f79f2223b11",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
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
  "uuid": "ab0beddb-4b99-4fae-bb6a-b84bb82cab4e",
  "timestamp": "2026-05-18T12:31:19.339Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

---

### Assistant

_source line 3 · 2026-05-18T12:31:25.445Z_



I'll start by reading the paper and all related project files to ground my review in the actual content.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ab0beddb-4b99-4fae-bb6a-b84bb82cab4e",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3AbPDuMpcieRQpWb5Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "db8f5326-c380-4978-98ee-4897bd15319c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015MVDAau3dbjJAiWGhUBv58",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 8620,
      "cache_read_input_tokens": 8249,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8620,
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

_source line 4 · 2026-05-18T12:31:25.958Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_013TTReHoxioacM4NDTGD7kj`</summary>

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
  "parentUuid": "db8f5326-c380-4978-98ee-4897bd15319c",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3AbPDuMpcieRQpWb5Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "233d4ed2-73e8-4892-81de-ebda3b922208",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015MVDAau3dbjJAiWGhUBv58",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 8620,
      "cache_read_input_tokens": 8249,
      "output_tokens": 127,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8620
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 127,
          "cache_read_input_tokens": 8249,
          "cache_creation_input_tokens": 8620,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8620,
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

_source line 5 · 2026-05-18T12:31:25.963Z_

<details><summary>↩ Tool result · `toolu_013TTReHoxioacM4NDTGD7kj`</summary>

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
  "parentUuid": "233d4ed2-73e8-4892-81de-ebda3b922208",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "0ffe7822-21cd-4813-99c7-2d1c954d700d",
  "sourceToolAssistantUUID": "233d4ed2-73e8-4892-81de-ebda3b922208",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-18T12:31:29.324Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__director_get_project_overview · `toolu_01LN8NdNCoo8Bqcp8VEGqCmc`</summary>

```json
{
  "project": "trace-verdict-study"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0ffe7822-21cd-4813-99c7-2d1c954d700d",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3B687JyZXbQjzUVGoX",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c7ecd7f8-9927-4081-8da6-c4dc304867d5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019jKGsktPwhGbcwhiE8G9tN",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1450,
      "cache_read_input_tokens": 16869,
      "output_tokens": 71,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1450
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 71,
          "cache_read_input_tokens": 16869,
          "cache_creation_input_tokens": 1450,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1450,
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

_source line 7 · 2026-05-18T12:31:29.717Z_

<details><summary>↩ Tool result · `toolu_01LN8NdNCoo8Bqcp8VEGqCmc`</summary>

```text
{"result":"# 项目 trace-verdict-study 概况\n\n## 实验状态 (105 个)\n\n- **full_trace_label_only_seed42**: DONE (success) — \n- **vota_no_ae_seed42**: DONE (success) — \n- **vota_loop_only_seed42**: DONE (success) — \n- **vota_ae_only_seed42**: DONE (success) — \n- **full_trace_seed42_v5**: DONE (success) — \n- **no_trace_seed42_v5**: DONE (success) — \n- **vota_seed42_v5**: DONE (success) — \n- **calibration_analysis_seed42**: DONE (success) — \n- **vota_exception_only_seed42**: DONE (failed) — \n- **vota_seed42_v4**: DONE (success) — \n- **full_trace_seed42_v2**: DONE (negative) — \n- **no_trace_seed42_v4**: DONE (success) — \n- **full_trace_seed42**: DONE (killed) — \n- **no_trace_seed42_v3**: DONE (killed) — \n- **vota_seed42_v3**: DONE (killed) — \n\n## 最新报告\n# Handover — 2026-05-18\n\n> 由 Agent 生成，每次状态变更后自动更新。硬限 150 行。\n\n## 运行中\n（无）\n\n## 待处理\n- codellama13b_full_trace_tail384_seed42: CodeLlama-13B tail-384 (label_only_loss) 应在 85-95% 之间（256→512 phase transition 中间点），验证 label_only_loss 在短序列下也有效（等待人工审批）\n- qwen15b_full_trace_tail384_seed42: Qwen-1.5B tail-384 应在 80-90% 之间（小模型在 transition zone 可能更低），精确定位 phase transition 曲线形状（等待人工审批）\n- qwen1.5b_full_trace_seed42: Qwen-1.5B full_trace 应达 ≥96% accuracy，确认 1.5B 小模型在 full trace 条件下与 7B 可比（trace quality 主导而非 model capacity）（排队等待 GPU）\n- qwen1.5b_exception_only_seed42: Qwen-1.5B exception_only 应达 ≥99% accuracy，确认 minimal sufficient signal 在 1.5B scale 有效，signal quality 主导 model capacity（排队等待 GPU）\n- qwen1.5b_vota_seed42: Qwen-1.5B VOTA 应在 82-90% accuracy，可能略低于 7B 因 VOTA 条件下 scale-sensitivity 更明显（排队等待 GPU）\n- qwen1.5b_no_trace_seed42: Qwen-1.5B no_trace 应在 65-75% (≈majority baseline)，确认无 trace 小模型表现更差、scale 无法补偿（排队等待 GPU）\n- codellama_exception_only_seed42: CodeLlama-13B exception_only 应达 ≥99.33% accuracy，与其他 3 模型一致，确认 minimal sufficient signal 跨 4 模型 3 架构 1.5B-13B universal（排队等待 GPU）\n- codellama_vota_seed42: CodeLlama-13B VOTA 应在 85-92% accuracy，与 Qwen-7B/DeepSeek VOTA 对齐，作 rebuttal 储备验证 ablation condition 跨 scale 一致性（排队等待 GPU）\n- codellama_no_trace_seed42: CodeLlama-13B no_trace 应在 70-78% (≈majority baseline)，确认无 trace 时 13B scale 无法补偿信息缺失（排队等待 GPU）\n- deepseek_full_trace_tail384_seed42: DeepSeek-6.7B tail-384 应在 85-93% 之间（256→512 phase transition 的中间点），精确定位 phase transition 曲线形状（已分配 ? GPU:?，等待提交）\n- …另有 1 项\n\n## 近期结论\n- **qwen7b_full_trace_head2048_seed42** (success): Qwen-7B head-2048 应在 75-82% (signal-poor convergence band)，与其他 3 模型 head-2048 (75.3-79.9%) 对齐，补全 4 模型 head-tail gap claim\n- **codellama13b_full_trace_tail2048_seed42_v3** (negative): CodeLlama-13B tail-2048 用 label_only_loss 应恢复到 95-98%（与其他 3 模型 tail-2048 对齐），确认 v2 的 29.6% 源于 full-sequence loss 稀释 ← 基于 codellama13b_full_trace_tail2048_seed42_v2\n- **codellama13b_full_trace_tail1024_seed42_v3** (success): CodeLlama-13B tail-1024 用 label_only_loss 应恢复到 ~96.5%（与 DeepSeek 96.47%、Qwen-1.5B 96.6% 对齐），确认 v2 的 87.6% 源于 full-sequence loss 稀释而非 tail-1024 条件本身 ← 基于 codellama13b_full_trace_tail1024_seed42_v2\n\n## 趋势\n成功 66 / 负向 13 / 失败 5 / 共 94\n\n## 下一步\n（无活跃 idea，请通过 ideas.md 添加）\n\n## 资源状态\nwestd-11235: 无 GPU 信息\n\n## 告警\n- no_trace_seed42: 已被终止 — unknown\n- vota_seed42: 已被终止 — unknown\n- no_trace_seed42_v2: 已被终止 — unknown\n- vota_seed42_v2: 已被终止 — unknown\n- no_trace_seed42_v3: 已被终止 — unknown\n- vota_seed42_v3: 已被终止 — unknown\n- full_trace_seed42: 已被终止 — unknown\n- vota_exception_only_seed42: 训练失败 — unknown\n- vota_seed123: 训练失败 — unknown\n- vota_seed456: 训练失败 — unknown\n- deepseek_full_trace_seed42_v2: 已被终止 — unknown\n- full_trace_2048tok_seed42: 已被终止 — unknown\n- codellama13b_nomarker_seed42: 已被终止 — unknown\n- codellama13b_full_trace_tail1024_seed42: 训练失败 — unknown\n- codellama13b_full_trace_tail2048_seed42: 训练失败 — unknown"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c7ecd7f8-9927-4081-8da6-c4dc304867d5",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "6907cef7-c910-438e-86c4-29e67fdbba9a",
  "sourceToolAssistantUUID": "c7ecd7f8-9927-4081-8da6-c4dc304867d5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-18T12:31:33.525Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_019NxPG5ZYzco8wWaQ2B7aVL`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "ideas.md",
  "max_chars": 20000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6907cef7-c910-438e-86c4-29e67fdbba9a",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3BMiy3QFNpTKbhka2M",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "7b2f1374-c6fe-40a0-bea4-c1c858ee853b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KMus8ujYJ2Gyq44Auy4M5y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 18319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2075,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 63,
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

_source line 9 · 2026-05-18T12:31:33.540Z_

<details><summary>↩ Tool result · `toolu_019NxPG5ZYzco8wWaQ2B7aVL`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"No ideas.md found for 'trace-verdict-study'.\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7b2f1374-c6fe-40a0-bea4-c1c858ee853b",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "79ef7e24-26a5-4999-9a0e-ba2765ba0452",
  "sourceToolAssistantUUID": "7b2f1374-c6fe-40a0-bea4-c1c858ee853b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-18T12:31:34.548Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01JE1hDPLD8cjH5c9z5w1PjK`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "ROADMAP.md",
  "max_chars": 20000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "79ef7e24-26a5-4999-9a0e-ba2765ba0452",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3BMiy3QFNpTKbhka2M",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f13b2474-fd5c-4b02-950e-55579e061f6d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KMus8ujYJ2Gyq44Auy4M5y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 18319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 2075,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 63,
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

_source line 11 · 2026-05-18T12:31:34.557Z_

<details><summary>↩ Tool result · `toolu_01JE1hDPLD8cjH5c9z5w1PjK`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/ROADMAP.md\", \"content\": \"# trace-verdict-study — Research Dashboard\\n\\n> 最后更新: 2026-05-18 11:06 UTC | 更新原因: 用户要求冲 main，完整实验规划写入（P0/P1/P2 三级 + GPU 预算）\\n\\n## 核心方向\\nException events 是 test verdict prediction 的 minimal sufficient signal：跨 4 模型、3 架构家族、1.5B-13B scale 范围内达到 ≥99.33% accuracy。详见 paper_framing.md。\\n\\n## 当前进展\\n- **阶段**: Research + 审稿进行中，用户要求冲 EMNLP main\\n- **实验**: 99 个（成功 64），4×5 budget curve 矩阵剩 3 格\\n- **关键结果**: CodeLlama tail-1024 v3 label_only_loss=98.24%（修复验证成功）\\n- **Paper Agent**: Patch 7 完成（4 模型 budget curve + tokenizer efficiency 整合）\\n- **Reviewer**: API Error 400 系统性故障，已升级 Manager 要 ETA\\n- **EMNLP ARR DDL**: 2026-05-25（7 天）\\n\\n## 核心发现\\n- exception_only: 99.33-100% 跨 4 模型 3 家族\\n- Phase transition at 256→512: 四模型跃变 +14.7~+23pp\\n- tail-512 convergence: 四模型 93.6-97.5%\\n- tail-1024 convergence: 96.5-98.2%（CodeLlama 最高，13B scale 边际优势）\\n- Head-tail gap: 15.5-22.6pp，小模型 gap 更大\\n- Signal-poor convergence band: head-2048 (75-82%) ≈ tail-256 (72-79%)\\n- label_only_loss 修复 CodeLlama loss dilution: 87.6% → 98.24%\\n\\n## 运行中\\n- cuda:0: `qwen7b_full_trace_head2048_seed42`（填满 4×5 矩阵最后一格之一）\\n- cuda:1: `codellama13b_full_trace_tail2048_seed42_v3`（label_only_loss，step ~200/444）\\n\\n## 实验规划（冲 main 完整路线）\\n\\n### P0 — 必须完成（~20 GPU-hours）\\n- [x] 4×5 budget curve 矩阵（剩 Qwen-7B head-2048 + CodeLlama tail-1024/2048）\\n- [ ] CodeLlama 基础 ablation: no_trace / vota / exception_only（3 个 queued）\\n- [ ] Qwen-1.5B 基础 ablation: no_trace / vota / exception_only / full_trace（4 个 queued）\\n\\n### P1 — 显著提升论文质量（~40 GPU-hours）\\n- [ ] Fine-grained phase transition: tail-384 × 4 模型（plan_016）\\n- [ ] Cross-seed budget curve: tail-512 × 4 模型 × 3 seeds（plan_017）\\n- [ ] Error analysis: failure mode 分析（plan_018，不需 GPU）\\n- [ ] Cross-model calibration: 4 模型 × ECE/Brier（plan_019，纯 eval）\\n\\n### P2 — 锦上添花（~40+ GPU-hours）\\n- [ ] Few-shot prompting baseline: GPT-4o/Claude 直接判断（plan_020，API 调用）\\n- [ ] OOD generalization: 不同语言/项目的 trace（plan_021）\\n- [ ] Training dynamics: learning curve 分析（plan_022）\\n\\n**总预算**: ~100 GPU-hours / 可用 336 GPU-hours，资源充裕\\n\\n## GPU 预算\\n- 分配: westd-11235 cuda:0 + cuda:1\\n- 已用: ~60 GPU-hours（估）\\n- 剩余: ~276 GPU-hours（7 天 × 2 卡 × ~20h/天有效）\\n\\n## 关键决策日志\\n\\n| ID | 日期 | 摘要 | 关联实验 |\\n|----|------|------|----------|\\n| D074 | 2026-05-18 | CodeLlama tail-2048 v3=41.8% 接受为 outlier，不再修复；Qwen | codellama13b_full_trace_tail2048_seed42_v3, codellama13b_full_trace_tail1024_seed42_v3, qwen7b_full_trace_head2048_seed42 |\\n| D073 | 2026-05-18 | P0 queued 7 实验确认全部已完成（命名差异），清理重复条目；error analysis  | codellama13b_no_trace_seed42, codellama13b_vota_seed42, codellama13b_exception_only_seed42, qwen15b_no_trace_seed42, qwen15b_full_trace_seed42 |\\n| D072 | 2026-05-18 | CodeLlama tail-1024 v3 label_only_loss=98.24%，确认 v | codellama13b_full_trace_tail1024_seed42_v3, codellama13b_full_trace_tail1024_seed42_v2 |\\n| D071 | 2026-05-18 | 补跑 Qwen-7B head-2048 填满 4×5 budget curve 矩阵 | qwen7b_full_trace_head2048_seed42, deepseek_full_trace_head2048_seed42, qwen15b_full_trace_head2048_seed42, codellama13b_full_trace_head2048_seed42 |\\n| D070 | 2026-05-18 | CodeLlama tail-1024=87.6% 根因确认：tokenizer loss 稀释（非 | codellama13b_full_trace_tail1024_seed42_v2, codellama13b_full_trace_tail512_seed42 |\\n| D069 | 2026-05-18 | CodeLlama-13B head-2048=79.9% 完成 4 模型 head-2048 矩阵 | codellama13b_full_trace_head2048_seed42, qwen15b_full_trace_head2048_seed42, deepseek_full_trace_head2048_seed42 |\\n| D068 | 2026-05-18 | CodeLlama-13B tail-256=77.9% 完成 4 模型 tail-256 矩阵：全 | codellama13b_full_trace_tail256_seed42, full_trace_tail256_seed42, deepseek_full_trace_tail256_seed42 |\\n| D067 | 2026-05-18 | CodeLlama-13B tail-512=97.5% 完成 4 模型 phase transit | codellama13b_full_trace_tail512_seed42, full_trace_tail_seed42, deepseek_full_trace_tail512_seed42 |\\n| D066 | 2026-05-17 | Qwen-1.5B tail-1024=96.6% 无 non-monotonicity：三模型 t | qwen15b_full_trace_tail1024_seed42, deepseek_full_trace_tail1024_seed42 |\\n| D065 | 2026-05-17 | DeepSeek tail-1024=96.47%: non-monotonicity 跨架构普遍存 | deepseek_full_trace_tail1024_seed42, deepseek_full_trace_tail512_seed42, deepseek_full_trace_tail2048_seed42 |\\n\\n\", \"total_chars\": 3987, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f13b2474-fd5c-4b02-950e-55579e061f6d",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "1421aff2-f76a-4193-977a-76da9ea3596a",
  "sourceToolAssistantUUID": "f13b2474-fd5c-4b02-950e-55579e061f6d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 12 · 2026-05-18T12:31:34.946Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_013iMEwUGS5E3cwEa57sepav`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "memory.md",
  "max_chars": 20000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1421aff2-f76a-4193-977a-76da9ea3596a",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3BMiy3QFNpTKbhka2M",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "aaecd08c-40a9-48cb-9e12-8d5069b9d18f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KMus8ujYJ2Gyq44Auy4M5y",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2075,
      "cache_read_input_tokens": 18319,
      "output_tokens": 289,
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
          "output_tokens": 289,
          "cache_read_input_tokens": 18319,
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

_source line 13 · 2026-05-18T12:31:34.962Z_

<details><summary>↩ Tool result · `toolu_013iMEwUGS5E3cwEa57sepav`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/memory.md\", \"content\": \"# Project Memory\\n\\n## westd-11235 训练命令规范 (C002)\\n- 必须用绝对路径 `/root/miniconda3/bin/python`（不是 `python`）\\n- Qwen-7B 及以上必须 `--gradient_checkpointing`\\n- 模型路径: `/root/trace-verdict-study/models/Qwen2.5-Coder-7B-Instruct`\\n- Qwen-1.5B 路径: `/root/trace-verdict-study/models/Qwen2.5-Coder-1.5B-Instruct`\\n- CodeLlama-13B 路径: `/root/autodl-tmp/models/CodeLlama-13b-Instruct-hf/`\\n- DeepSeek 路径: `/root/autodl-tmp/models/deepseek-coder-6.7b-instruct/deepseek-ai/deepseek-coder-6___7b-instruct`\\n- 不支持 `--epochs` 参数，脚本用 `--max_steps`（默认 -1 = 全量训练，444 steps ≈ 3 epochs）\\n- nohup 提交后必须注册 cron 监控（否则无回调）\\n- submit_training_job 自动注册 cron + 含 auto-eval chain（优先用这个）\\n\\n## Output Dir 规范\\n- 每个实验必须有独立 output_dir: `/root/autodl-tmp/trace-verdict-study-checkpoints/{exp_id}/`\\n- seed123 事故教训：未指定 seed 后缀导致覆盖 1.5B checkpoint\\n\\n## CodeLlama-13B 必须用 label_only_loss (2026-05-18)\\n- CodeLlama tokenizer 产生更多 token（平均 ~1174 vs Qwen ~978），导致 label token 仅获 ~0.085% 梯度信号\\n- full-sequence loss 下 tail-1024=87.6%, tail-2048=29.6%（灾难性）\\n- `--label_only_loss` 修复后 tail-1024=98.24%（+10.6pp），确认 loss dilution 是唯一根因\\n- 教训：tokenizer 差异大的模型（特别是 13B+ scale）默认应用 label_only_loss\\n- epoch 1 (98.24%) > epoch 3 (97.56%)，轻微过拟合，用 epoch 1 作为报告值\\n\\n## CodeLlama tail-2048 anomaly (D074, 2026-05-18)\\n- v2 (full-sequence): 29.6%, v3 (label_only_loss): 41.8% — 均灾难性失败\\n- Tokenizer 分析：CodeLlama 1.21x 膨胀保留 83.3% 内容；DeepSeek 1.32x 膨胀保留 74.4% 却正常 (95%)\\n- 结论：tokenization 非唯一原因，更可能是 Llama-2 架构 + LoRA + 长序列稀疏梯度的复合效应\\n- 决策：接受为 outlier，论文如实报告，不再投入 GPU 修复\\n\\n## Universal Irreducible Ceiling (2026-05-16)\\n- 所有 4 个模型（Qwen-7B/1.5B, CodeLlama-13B, DeepSeek-6.7B）在 exception_only 条件下共享完全相同的 2 个错误：index 901, 905\\n- 均来自 HumanEval/95 (check_dict_case)：`all()` 短路 generator 产生 GeneratorExit，显示为 [ERROR] 但实际 pass\\n- 根因：exception_only 表示的语义歧义——不是模型能力问题，是表示层面的硬上限\\n- DeepSeek 额外 6 错来自 MBPP/113 (caught ValueError)，其他 3 模型能正确判断\\n- 论文价值：证明 2/1190 ceiling 是数据标注 artifact，非模型限制\\n\\n## Error Analysis 核心发现 (2026-05-18)\\n- Exception-based 条件（ae_only/exception_only/vota）错误 100% FN，零 FP — CI/CD 安全性\\n- full_trace 独有 58 错中 76% 是 FP — 更多 trace 信息引入噪声\\n- exception_only 2 个错误与其他条件零重叠（独有 failure mode）\\n- MBPP/284, 419, 443 顽固问题：no_trace/loop/full_trace 全错，exception_only 全对\\n- 论文价值：information selectivity 叙事\\n\\n## Format Marker 贡献量 (2026-05-16)\\n- nomarker_seed42 (Qwen-7B): 96.55%，对比 exception_only_seed42 99.83% → marker 贡献 ~3.3pp\\n- nomarker_seed42 (Qwen-1.5B): 97.8%，证明 1.5B 无 marker 仍超 7B 无 marker\\n- 待 seed123/456 完成后取均值 ± std\\n\\n## DeepSeek seed123 = 91.09% 异常 (已诊断)\\n- 根因：LoRA 初始化失败导致 truncation boundary 处 format collapse\\n- 不是信号不足问题，是随机种子 + 架构交互的 edge case\\n\\n## Zero-Shot Baseline 设计决策 (2026-05-17)\\n- Qwen 用 generation-based（模型输出 yes/no，映射为 pass/fail）\\n- DeepSeek 用 logit-based classification（比较 yes/pass vs no/fail token logit），因为 DeepSeek chat template 生成解释性文本而非单词\\n- 两种方法都是公平的 zero-shot 评估，但方法差异可能部分解释 accuracy 差异（Qwen 89.08% vs DeepSeek 90.59%）\\n- 关键 insight：zero-shot 错误模式互补——Qwen 漏判 fail（fail recall 67%），DeepSeek 误判 pass 为 fail（pass recall 89%）\\n- Regex baseline (93.61%) > zero-shot LLM (~90%)：说明 exception trace 判别不是通用语言理解任务，pattern matching 反而更有效；SFT 提供 task-specific signal 才能突破\\n\", \"total_chars\": 3075, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "aaecd08c-40a9-48cb-9e12-8d5069b9d18f",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "e3d288d0-932e-49df-867d-14ff2453a6f7",
  "sourceToolAssistantUUID": "aaecd08c-40a9-48cb-9e12-8d5069b9d18f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 14 · 2026-05-18T12:31:39.459Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01LGi7rvZi6VuMVhuTtXo6nF`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "paper_framing.md",
  "max_chars": 20000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e3d288d0-932e-49df-867d-14ff2453a6f7",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3BkMFV6rWz9Dxqhk7r",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2426f180-4039-4531-9c34-1f6ea1dbda65",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WnYuSZaqQfZgoH4QkKM9Uk",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4672,
      "cache_read_input_tokens": 20394,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4672,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 52,
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

_source line 15 · 2026-05-18T12:31:39.490Z_

<details><summary>↩ Tool result · `toolu_01LGi7rvZi6VuMVhuTtXo6nF`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/paper_framing.md\", \"content\": \"# Paper Framing — trace-verdict-study\\n\\n> v3.0 — [UPDATED 2026-05-15] D030 CLOSED: DeepSeek VOTA 84.45% confirmed correct (confirmatory re-eval). **Critical narrative fix**: to_chat_text() preserves labels → VOTA 训练时 verdict label 未被截断 → 论文中 \\\"label truncation/corruption\\\" 措辞对 VOTA 不成立。正确叙事: trace INPUT content 被截断 (91.7% samples), 84.45% 反映 trace information loss。新增 D11: VOTA cross-model gap confounded by training-time truncation。数据集来源：HumanEval (164) + MBPP-sanitized (427) = 591 problems × 10 LLM-generated solutions = 5910 samples。\\n\\n## Target Venue\\n- Primary: EMNLP 2026 Main (ARR submission)\\n- Fallback: EMNLP 2026 Findings\\n- Deadline: ARR May 25, 2026\\n\\n## Core Insight\\n\\nVerdict prediction (pass/fail) is fundamentally a **fault detection** task. The most effective signal is the **exception event** — a compact, structured diagnostic moment that consistently outperforms all other trace representations across models (Qwen 99.83% ± 0.00 across 3 seeds; DeepSeek 91-99% depending on seed, but always > VOTA 84.45% and no_trace 73.36%). In contrast, richer trace representations that require deeper execution reasoning show model-dependent effectiveness: VOTA gap = 14.96pp, no_trace gap = 1.77pp. Information density — not training signal distribution — is the primary bottleneck: even oracle loss masking (label-only) cannot close the 13pp gap between full traces and targeted extraction. The design principle: **extract the highest-specificity diagnostic signal; discard everything else.** Cross-model absolute performance depends on LoRA initialization stability, but exception_only's relative dominance over other components is robust.\\n\\nVOTA's primary contribution is **fault indicator isolation** — automatically extracting exception events from noisy full traces — rather than generic trace compression. The \\\"compression helps\\\" narrative was a stepping stone; the real mechanism is diagnostic signal extraction.\\n\\n## Core Claims (3)\\n\\n### Claim 1: Exception events are the most effective trace component for verdict prediction\\n\\nException summaries consistently achieve the highest verdict prediction accuracy across both models tested, outperforming all other trace representations in every seed. On Qwen-2.5-Coder-7B, performance is perfectly robust: 99.83% ± 0.00 (3 seeds). On DeepSeek-Coder-6.7B, absolute accuracy is seed-dependent (seed42=99.83% epoch1, seed123=91.43% epoch1; Δ=8.40pp), consistent with LoRA initialization sensitivity — but exception_only still dominates VOTA (84.45%) and no_trace (73.36%) in all seeds. This contrasts with VOTA (cross-model gap = 14.96pp) and no_trace (gap = 1.77pp). Exception events are structurally simple (`[ERROR] type: ... message: ...`) and do not require deep trace reasoning.\\n\\n**Supporting evidence:**\\n- `vota_exception_only_seed42_v2`: Qwen 99.83%, ECE=0.0027\\n- `deepseek_exception_only_seed42`: DeepSeek 99.83% (epoch1) / 99.33% (epoch3)\\n- `deepseek_exception_only_seed456`: DeepSeek 99.33% (epoch3), CI [98.82, 99.75] — 与 seed42 完全一致\\n- `deepseek_exception_only_seed123`: DeepSeek 91.43% (epoch1) / 91.09% (epoch3) — LoRA init sensitivity outlier\\n- `deepseek_vota_seed42`: DeepSeek VOTA 84.45% (gap = 14.96pp vs Qwen)\\n- `deepseek_no_trace_seed42`: DeepSeek no_trace 73.36% (gap = 1.77pp vs Qwen)\\n- `vota_no_ae_seed42`: 99.41% — actual/expected removal 不降，非 trivial string comparison\\n\\n**DeepSeek seed analysis** ✅ (FINALIZED, D029):\\n\\n| Seed | Epoch 3 (final) | fail_recall | pass_recall | train_loss | Errors | CI |\\n|------|-----------------|-------------|-------------|------------|--------|-----|\\n| 42   | 99.33%          | 1.0         | 0.9906      | —          | 8/1190 | — |\\n| 456  | 99.33%          | 1.0         | 0.9906      | 0.1225     | 8/1190 | [98.82, 99.75] |\\n| 123  | 91.09%          | 0.705       | 0.993       | 0.122      | —      | [89.4, 92.6] |\\n\\nseed42 与 seed456 结果**完全一致**（均 8/1190 错误，99.33%），seed123 为离群值。seed123 的 fail_recall 仅 0.705 — LoRA 初始化落入差的局部最优，未充分学到 exception→fail 映射。**关键发现**: seed456 和 seed123 的 train_loss 几乎相同（0.1225 vs 0.122），但 accuracy 差 8.2pp — token-level loss 掩盖了 sample-level 分类能力的巨大差异（详见 D10）。\\n\\n**Irreducible error analysis** ✅: 3 seeds 错误的 2 个样本 (id=901, 905) 均来自 HumanEval/95 (`check_dict_case`)，根因为 Python `all()` 对 generator expression 短路触发 `GeneratorExit`（`BaseException` 子类，非真正错误）。tracer 将其标记为 `[ERROR]`，exception_only 模型看到 7 行 `[ERROR] GeneratorExit`，合理但错误地预测 fail。整个 1190 条测试集仅这 2 条含 `GeneratorExit`，模型无训练信号学习其良性本质。**这确认 99.83% 是 exception_only 表征的理论上限，剩余 0.17% 是 representation-inherent irreducible error，而非模型不足。**\\n\\n**Seed robustness** ✅: Qwen exception_only 3-seed 完全一致，构成本文最强 robustness 证据：\\n\\n| Seed | Accuracy | 95% CI | Errors |\\n|------|----------|--------|--------|\\n| 42 | 99.83% | [99.58, 100] | 2/1190 |\\n| 123 | 99.83% | [99.58, 100] | 2/1190 |\\n| 456 | 99.83% | [99.58, 100] | 2/1190 |\\n\\n3 seeds 错误样本 100% 重叠（id=901, 905, 均为 `check_dict_case` 函数, label=pass → pred=fail）。**Irreducible samples**: 模型已达数据集理论上限，variance = 0。\\n\\n**DeepSeek cross-model** ✅ (D029): 3-seed 完整数据 — seed42/456=99.33%, seed123=91.09%。2/3 seeds 鲁棒，seed123 为 LoRA 初始化离群值（fail_recall 仅 0.705）。Qwen 3-seed 完美稳定 (99.83% ± 0.00) vs DeepSeek 高方差（σ≈4.8pp），暗示 exception signal 的 learnability 与模型 LoRA 训练稳定性相关。但即使最差 seed (91.09%) 仍优于 VOTA (84.45%) 和 no_trace (73.36%)，relative dominance robust。\\n\\n### Claim 2: Information density, not gradient dilution, drives trace compression benefit\\n\\nFull traces help verdict prediction (81.76% [`full_trace_seed42_v5`], +6.6pp over baseline), but VOTA achieves 99.41% [`vota_seed42_v5`] (+24.3pp) — a +17.6pp advantage. Label-only loss ablation (plan_002) quantifies the causal decomposition: **gradient dilution contributes ~26% of the gap** (4.5pp; label-only full_trace = 86.22% [`full_trace_label_only_seed42`]), **information overload contributes ~74%** (13.0pp; only trace compression resolves this). Even with oracle loss masking that eliminates gradient dilution, full traces still underperform VOTA by 13pp.\\n\\nCross-model evidence reinforces this: VOTA gap (14.96pp) partly tracks base model execution reasoning capability (Qwen CRUXEval-I 56.5% vs DeepSeek 39.0%, Δ=17.5pp), though **confounded by DeepSeek training-time trace truncation** (91.7% of VOTA samples truncated to ~2048 tokens; see D11). The two factors cannot be disentangled in the current design. Exception signal partially bypasses both bottlenecks (token-short, no truncation; consistently best component on both models), though DeepSeek shows seed-dependent absolute performance (91-99%).\\n\\n**Supporting evidence:**\\n- `full_trace_label_only_seed42`: 86.22%, ECE=0.1107 (gradient dilution fix, +4.5pp over standard full_trace)\\n- `full_trace_seed42_v5`: 81.76%, ECE=0.0958 (standard full_trace)\\n- `vota_seed42_v5`: 99.41%, ECE=0.0054\\n- `deepseek_vota_seed42`: 84.45% (VOTA model-dependent)\\n- CRUXEval literature data (Wang et al.)\\n\\n### Claim 3: Two-tier diagnostic hierarchy for verdict prediction\\n\\nComponent ablation reveals verdict-relevant trace information has a strict two-tier hierarchy:\\n- **Tier 1 — diagnostic moment signals**: exception summaries (99.83% [`vota_exception_only_seed42_v2`]) and assertion-point information (99.92% [`vota_ae_only_seed42`]) are individually near-perfect and sufficient for verdict prediction on Qwen. These signals are structurally simple and consistently the most effective component on both models, though DeepSeek absolute performance is seed-dependent.\\n- **Tier 2 — behavioral patterns**: loop compression (85.63% [`vota_loop_only_seed42`]) carries substantial signal but is model-dependent and fully subsumed by Tier 1.\\n\\nCombining tiers introduces noise rather than helping: exception_only (99.83%) > VOTA full (99.41%), p=0.01. Loop_only ≈ full_trace_label_only (85.63% vs 86.22%) confirms VOTA's loop compression precisely extracts the useful behavioral signal from full traces.\\n\\n**Supporting evidence:**\\n- `vota_exception_only_seed42_v2`: 99.83%, ECE=0.0027 (Tier 1 exception)\\n- `vota_ae_only_seed42`: 99.92%, ECE=0.0004 (Tier 1 assertion-point, 与 exception 统计等价 p=0.80)\\n- `vota_loop_only_seed42`: 85.63%, ECE=0.0831 (Tier 2 behavioral)\\n- `full_trace_label_only_seed42`: 86.22%, ECE=0.1107 (≈ loop_only, confirming extraction equivalence)\\n- `deepseek_exception_only_seed42`: 99.83% epoch1 / 99.33% epoch3 (Tier 1 cross-model validation)\\n- `deepseek_vota_seed42`: 84.45% (Tier 1+2 cross-model: Tier 2 introduces model-dependent degradation)\\n\\n**Calibration**: 完整 calibration 数据确认 Tier 1 信号不仅 accuracy 近完美，置信度校准也近完美：\\n\\n| Condition | Accuracy | ECE | Brier | 解读 |\\n|-----------|----------|-----|-------|------|\\n| ae_only | 99.92% | 0.0004 | 0.0008 | 近乎完美校准 |\\n| exception_only | 99.83% | 0.0027 | 0.0013 | 近乎完美校准 |\\n| VOTA | 99.41% | 0.0054 | 0.005 | 优秀，但 Tier 2 引入轻微 noise |\\n| loop_only | 85.63% | 0.0831 | — | Tier 2 单独校准中等 |\\n| label_only | 86.22% | 0.1107 | — | gradient dilution fix 仍 miscalibrated |\\n| full_trace | 81.76% | 0.0958 | — | 中度 miscalibrated |\\n| no_trace | 75.13% | 0.1715 | 0.1972 | 严重 miscalibrated |\\n\\nno_trace ECE 是 exception_only 的 **~63x**（0.1715/0.0027），Brier 是 **~150x**（0.1972/0.0013）。Trace signal（尤其 Tier 1）不仅提升 accuracy，更从根本上改善模型 calibration。\\n\\n**Design principle**: verdict-optimized traces should extract highest-specificity diagnostic signals; lower-specificity signals are redundant and may introduce noise.\\n\\n## Cross-Model Evidence Summary\\n\\n| Condition | Qwen-2.5-Coder-7B | DeepSeek-Coder-6.7B | Cross-model gap | Interpretation |\\n|-----------|-------------------|---------------------|-----------------|----------------|\\n| exception_only | 99.83% ± 0.00 (3 seeds) | seed42/456: 99.33%; seed123: 91.09% | 0.50-8.74pp (seed-dependent) | **Best component on both models**; 2/3 DeepSeek seeds match Qwen-level; 1 outlier still > VOTA |\\n| VOTA | 99.41% | 84.45% | -14.96pp | Model-dependent — requires execution reasoning; **also confounded by DeepSeek training-time trace truncation** (91.7% of VOTA samples truncated from mean 2626 to ~2048 tokens; labels preserved via to_chat_text(), see D11) |\\n| no_trace | 75.13% | 73.36% | -1.77pp | Baseline gap tracks general capability |\\n| full_trace | 81.76% | collapsed (v3 pending) | N/A | DeepSeek v1 label truncation bug |\\n\\n**Key insight**: Exception_only is consistently the best component on both models (even worst DeepSeek seed 91.09% > VOTA 84.45%). Cross-model gap 与 signal complexity 正相关, but exception signal's absolute effectiveness also depends on LoRA training stability. Qwen: perfectly robust (3 seeds identical). DeepSeek: 2/3 seeds at 99.33% (matching Qwen-level), 1 outlier at 91.09% (LoRA initialization). Median performance robust; seed sensitivity suggests smaller/weaker models may need training stabilization (multi-seed selection, warmup tuning) for optimal exception signal utilization.\\n\\n## VOTA Repositioning\\n\\n**旧叙事**: VOTA 是 trace compression 方法，价值在于\\\"压缩使 trace 更有效\\\"。\\n\\n**新叙事**: VOTA 是 **fault indicator isolation** 方法，核心价值在于自动从 noisy execution traces 中提取 exception events 等 diagnostic signals。\\n\\n**证据链**:\\n1. exception_only (99.83%) ≥ VOTA full (99.41%) — 压缩后的其他组件（loop, ae）不仅无益，反而引入 noise\\n2. VOTA 跨模型 gap = 14.96pp — 因为 VOTA 包含 model-dependent 的 Tier 2 组件（loop compression 需要 execution reasoning）\\n3. exception_only 在两个模型上均为最优组件 — isolate 出 Tier 1 后，相对优势 robust（虽然 DeepSeek 绝对值 seed-dependent）\\n4. vota_no_ae (99.41%) = VOTA (99.41%) — actual/expected 移除无影响，exception 是真正的 active ingredient\\n\\n**论文中的表述**: \\\"VOTA's trace compression pipeline incidentally isolates exception events — the minimal sufficient diagnostic signal. Its value lies not in making traces shorter, but in separating high-specificity fault indicators from low-specificity behavioral patterns.\\\"\\n\\n**对 Method section 的影响**: VOTA 仍然完整描述（loop compression + exception + actual/expected），但 Results/Discussion 明确指出 exception isolation 是核心机制，其他组件是 model-capability-dependent bonus。\\n\\n## Story Spine\\n\\n- **Problem**: Existing trace SFT studies (DCSH, TracePile) evaluate only generative tasks and find limited, model-dependent benefit. No prior work has tested trace SFT on verdict tasks (binary pass/fail), nor identified what trace components drive classification performance.\\n\\n- **Existing approaches & gaps**: DCSH (EMNLP Findings 2025) tested 5 trace formats on generation tasks, finding that \\\"no single trace representation consistently outperforms others.\\\" TracePile (NeurIPS 2025) scaled to 2.6M samples but only evaluated generation. TRACED (ICSE 2024) showed traces help encoder-based classification. All existing trace formats are designed for execution simulation, not fault detection.\\n\\n- **Our framing**: We reframe verdict prediction as **fault detection** and ask: what is the minimal sufficient diagnostic signal? Through systematic component ablation across two architecturally distinct models, we discover that exception events — compact, structured error summaries — are consistently the most effective trace component, achieving near-perfect accuracy on Qwen (99.83% ± 0.00, 3 seeds) and outperforming all alternatives on DeepSeek (91-99% vs VOTA 84.45%). Richer trace representations work only when the base model has sufficient execution reasoning capability, making them unreliable for general deployment.\\n\\n- **Headline result**: \\\"Exception events consistently achieve the highest verdict accuracy across models (Qwen 99.83%, DeepSeek 91-99%), outperforming VOTA traces (84.45% on DeepSeek, -14.96pp gap) — demonstrating that fault indicator isolation, not trace reasoning, is the robust mechanism for verdict prediction. DeepSeek seed sensitivity reveals LoRA training stability as a secondary factor for smaller models.\\\"\\n\\n## Story Arc\\n\\n1. **Setup**: Trace SFT for code tasks — promising but inconsistent in prior work (DCSH, TracePile). Unknown whether traces help verdict tasks and what trace design matters.\\n\\n2. **First result — traces help, compression helps more** (single model): no_trace 75.13% → full_trace 81.76% → VOTA 99.41%. Label-only loss ablation decomposes the gap: 26% gradient dilution, 74% information overload. Compression improves accuracy through higher information density, not just cost savings.\\n\\n3. **Twist — what component actually drives VOTA?** Component ablation reveals exception_only (99.83%) ≥ full VOTA (99.41%). The \\\"trace reasoning\\\" narrative is wrong — verdict prediction is fault detection. Tier 1 (exceptions + assertion-point) subsumes Tier 2 (loops). Actual/expected removal doesn't hurt (99.41%).\\n\\n4. **Cross-model stress test — consistent dominance, not universal perfection**: Exception_only is the best component on both models (even DeepSeek worst seed 91.09% > VOTA 84.45%), but absolute performance is seed-dependent on DeepSeek (91-99% vs Qwen's perfectly stable 99.83%). VOTA degrades by 14.96pp. The structurally simplest component is the most robust, but LoRA initialization sensitivity introduces variance on weaker models. Qwen seed robustness (3-seed variance = 0) + calibration (ECE=0.0027) 确认 exception signal 在强模型上的 reliability。DeepSeek seed sensitivity 揭示 training stability 作为 secondary bottleneck。\\n\\n5. **Design principle**: For verdict tasks, identify the highest-specificity diagnostic signal (exception events) and discard everything else. VOTA's value is fault indicator isolation — automatically extracting exceptions from noisy traces — not generic compression. Simpler signals are more robust; complexity tolerance depends on model capability.\\n\\n## Dataset Characteristics\\n\\n### Data duplication analysis\\n\\n| Condition | Total | Unique | Duplication rate | Cause |\\n|-----------|-------|--------|------------------|-------|\\n| exception_only_train | 4720 | 2858 | 39.45% | 同题多个 passing 解映射为相同 (input, output) — 无异常 → 同一 trace |\\n| exception_only_test | 1190 | 607 | 48.99% | 同上 |\\n| raw_traces | 5910 | 5803 | 1.81% | 完整 trace 含行号/变量值/内存地址，几乎不重复 |\\n\\n**Train-test input overlap: 0（无数据泄漏）**\\n\\n**解读**: exception_only 高重复率是 representation 的自然属性，非数据问题。多个正确解对同一测试用例执行时若均无异常，exception_only 表征退化为相同的空/无异常标记。这恰好说明 exception signal 的 compactness — 它仅编码 fault presence，不编码 solution identity。raw_traces 重复率极低 (1.81%) 因为完整 trace 包含 solution-specific 信息（变量值、内存地址）。尽管高重复率意味着有效训练样本少于名义数量，模型仍达 99.83% — 进一步确认 exception signal 的 learnability。\\n\\n## DeepSeek full_trace 处理\\n\\n**现状**: v1 坍塌（28.5%, 100% 预测 fail, 根因: 训练端 label 截断）。v2 重训启动但被 kill（Loop #6 ops worker 腾 GPU 给 vota_seed456）。v3 RUNNING（label-preserving truncation fix）。\\n\\n**处理方案**: v3 正在 cuda:0 上训练，预计 5/16 完成。\\n\\n**VOTA vs full_trace 截断机制区分** (D030 token analysis 确认):\\n- **full_trace v1**: SFTTrainer right-truncation 切掉了 verdict **label** → 100% predict fail → 坍塌。根因: DeepSeek tokenizer 对 full_trace 产生 >2048 tokens, label 在截断窗口外。\\n- **VOTA**: `to_chat_text()` 保留 verdict label（label 完整），但 91.7% 的样本 **trace content（input）被截断**（mean 2626 → ~2048 tokens）。84.45% 是真实结果，反映 trace 信息损失对模型学习的影响，**不是** label corruption。\\n- **exception_only**: token 长度远低于 2048，不受截断影响，跨模型对比 clean。\\n\\n**对论文叙事的影响**: 论文中所有 \\\"right-truncation corrupts/removes the verdict label\\\" 措辞**对 VOTA 不成立**——label 完整保留，被截断的是 trace input。正确表述: \\\"trace content truncation causes information loss\\\"。VOTA cross-model gap (14.96pp) 有两个贡献因素: (1) model capability, (2) training-time trace truncation on DeepSeek (see D11)。\\n\\n## External Benchmark (DebugBench) Positioning\\n\\n**DebugBench 仅作泛化性验证，不作 trace importance 证据。**\\n\\n| Condition | Main Dataset | DebugBench | Δ interpretation |\\n|-----------|-------------|------------|------------------|\\n| no_trace | 75.13% | 96.71% | DebugBench 天花板高，baseline 已强 |\\n| VOTA | 99.41% | 99.77% | +3.06pp lift — 边际 |\\n| exception_only | 99.83% | 100.00% | +3.29pp lift — 边际 |\\n\\n**主数据集 trace lift = 24.70pp**（no_trace → exception_only），DebugBench trace lift 不到其 1/7。\\n\\n**论文定位规则**：\\n- DebugBench → 泛化性证据（exception_only 100% = 跨数据集鲁棒性）\\n- Trace importance 论证 → 仅依赖主数据集（24.7pp lift）\\n- 禁止用 DebugBench 的 3.29pp lift 论证 \\\"trace 的核心价值\\\"——审稿人会攻击天花板效应\\n\\n## Venue Fit Risks\\n\\n| Risk | Assessment | Mitigation |\\n|------|-----------|------------|\\n| 单任务 | 仍然只在 test verdict prediction 上验证 | 跨模型验证部分弥补; Discussion 中讨论 generalization |\\n| 单数据集 | HumanEval + MBPP-sanitized 是唯一数据源 (591 problems × 10 solutions) | 定位为 empirical study, 深度优于广度; 两个标准 benchmark 组合覆盖多样编程题型; exception_only 有效训练样本仅 2858 unique 即达 99.83%, 暗示 signal 的 simplicity 降低对数据量的依赖 |\\n| \\\"只是 feature engineering\\\" | exception extraction 不复杂 | simplicity 本身是 contribution — 最简信号最 robust |\\n| Negative result 味道 | VOTA 跨模型不 robust | Reframe: 识别 robust vs non-robust 组件边界是 positive |\\n| Seed robustness (Qwen) | ✅ 已解决: 99.83% ± 0.00 (3 seeds), irreducible samples 确认 | — |\\n| Seed robustness (DeepSeek) | ✅ 3-seed 完整: 2/3 at 99.33%, 1 at 91.09% | LoRA initialization sensitivity — median robust, worst still > all alternatives; 转化为 training stability finding (D9/D10) |\\n| Calibration | ✅ 完整数据: Tier 1 ECE≤0.003, no_trace ECE=0.171 (~63x gap) | Brier ~150x gap 进一步确认 |\\n| 只用 2 个模型 | 有限但有意义的 diversity | Architecture + pretraining data (5.5T vs 2T) + CRUXEval gap (17.5pp) 构成充分差异 |\\n| 数据重复率 | exception_only 训练集 39.45% 重复 | 非数据泄漏（train-test overlap = 0）；是 representation compactness 的自然结果；有效样本仍足够学习 |\\n\\n## Anticipated Reviewer Concerns\\n\\n| Concern | Planned Response |\\n|---------|-----------------|\\n| \\\"exception_only 99.83% 是不是 trivial pattern matching [ERROR] 有无？\\\" | full_trace 也包含 [ERROR] 但仅 81.76%——模型需要从 trace context 中 extract 和 utilize exception signal, 不是简单 keyword detection. no_trace 无 exception, 75.13%. |\\n| \\\"为什么 exception_only > VOTA? adding info 反而降?\\\" | 非 exception 组件 (loop/ae tokens) 稀释 attention 对 exception 信号的聚焦. Calibration: exception_only ECE=0.0027 vs VOTA ECE=0.0054. 部分样本 loop 正常但有 exception, 引入矛盾信号. |\\n| \\\"CRUXEval gap 与 VOTA gap 的相关性可能是 coincidence\\\" | 明确标注为 hypothesis. 列出 alternatives (tokenizer efficiency, pretraining scale 2.75x, chat template). 不 overclaim. |\\n| \\\"只有 2 个模型，universality claim 太强\\\" | 同意是 limitation. 两模型在 architecture (RoPE vs ALiBi), pretraining data (5.5T vs 2T), execution reasoning (CRUXEval 17.5pp gap) 上有充分差异, 不是 trivial replication. Exception signal 的 structural simplicity 提供 inductive argument for broader generalization. |\\n| \\\"99.83% 可能 saturated, 看不出 exception 到底学了什么\\\" | Calibration 双指标: exception_only ECE=0.0027, Brier=0.0013 (近完美校准). 对比 n\\n\\n... [截断: 省略 10551 字符，传 max_chars=0 获取完整内容]\", \"total_chars\": 30551, \"truncated\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2426f180-4039-4531-9c34-1f6ea1dbda65",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "c01b524f-1384-47bd-983f-8656f044a29a",
  "sourceToolAssistantUUID": "2426f180-4039-4531-9c34-1f6ea1dbda65",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-18T12:31:39.883Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01DfYDqN7mJrwKvHqPV9vrCX`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "decisions.yaml",
  "max_chars": 20000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c01b524f-1384-47bd-983f-8656f044a29a",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3BkMFV6rWz9Dxqhk7r",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f96363ee-afff-46e0-ac3a-a75ee65a2d69",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WnYuSZaqQfZgoH4QkKM9Uk",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4672,
      "cache_read_input_tokens": 20394,
      "output_tokens": 200,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4672
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 200,
          "cache_read_input_tokens": 20394,
          "cache_creation_input_tokens": 4672,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4672,
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

_source line 17 · 2026-05-18T12:31:39.910Z_

<details><summary>↩ Tool result · `toolu_01DfYDqN7mJrwKvHqPV9vrCX`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/decisions.yaml\", \"content\": \"_next_id: 75\\ndecisions:\\n- id: D001\\n  date: 2026-05-14 16:14 UTC\\n  summary: MVP pass 阈值统一为 ≥2pp + bootstrap CI 不含 0；补全 kill criteria\\n  rationale: IDEA_BRIEF pilot 用 2pp（Defects4J 上下文），ROADMAP 初版用 3pp。考虑到 holdout ~1.3K\\n    样本统计功效有限，统一为 2pp + CI 要求。FAIL 后先排查 bug 1 天，clean fail 则 pivot 到 negative-result\\n    framing。WEAK PASS 追加 CRUXEval verdict 验证。\\n  related_experiments: []\\n  depends_on: []\\n- id: D002\\n  date: 2026-05-14 21:50 UTC\\n  summary: MVP 第一轮结果无效：VOTA match 字段泄漏 + full_trace label 截断，需修复后重训\\n  rationale: VOTA 99.16% 来自 match=True/False 直接泄漏答案（trivial pattern matching）；full_trace\\n    28.4% 来自 label 被 2048 token 截断丢弃。no_trace 75.13% 有效但无法与其他条件对比。修复方案：去 match 字段\\n    + 智能截断保留 label。\\n  related_experiments: []\\n  depends_on: []\\n- id: D003\\n  date: 2026-05-15 01:24 UTC\\n  summary: MVP PASS — VOTA 95.63% (+20.5pp over no_trace), 附带 actual/expected leakage\\n    concern 需 ablation 验证\\n  rationale: D001 标准满足：VOTA vs no_trace +20.5pp, 95% CI [+17.7, +23.4] 不含 0。但 >95%\\n    触发高准确率警戒，pass_recall 99.8% 暗示模型可能在做 actual==expected 字符串比对而非代码行为理解。进入 research\\n    阶段后第一实验必须是去 actual/expected ablation。full_trace 28.49% 为 genuine negative（100%\\n    预测 fail，trace token 稀释分类梯度），后续可尝试 label-only loss。\\n  related_experiments:\\n  - exp_id: vota_seed42_v4\\n    role: primary\\n    result: 95.63% accuracy, +20.5pp lift, PASS\\n  - exp_id: no_trace_seed42_v4\\n    role: baseline\\n    result: 75.13% accuracy\\n  - exp_id: full_trace_seed42_v2\\n    role: negative\\n    result: 28.49% accuracy, model collapse\\n  depends_on: []\\n- id: D004\\n  date: 2026-05-15 01:34 UTC\\n  summary: 'D004: full_trace 28.4% 系 chat template overhead 导致 label 截断（非 genuine\\n    negative），选方案 B + 三条件全部重训 v5'\\n  rationale: Agent 诊断发现 format_training_data.py 按 raw tokens 截断到 2048，但 train_sft.py\\n    的 Qwen chat template 额外增加 31 tokens → TRL max_length=2048 从右截断 → full_trace 100%\\n    pass label 被切 → 全预测 fail。VOTA 也受影响（89.4% pass label 被截），但 360 条足够学到 95.63%。选方案\\n    B（根本修复：trace budget 减 32 tokens）+ 三条件全部重训，确保公平对比。这是第三轮修复，必须加 end-to-end 验证：训练前确认\\n    0 样本被截断。Claim 2（full traces hurt）暂时搁置，等 v5 结果。\\n  related_experiments:\\n  - exp_id: full_trace_seed42_v2\\n    role: invalidated\\n    result: 28.49% due to label truncation bug, not genuine negative\\n  - exp_id: vota_seed42_v4\\n    role: affected\\n    result: 95.63% with only 10.6% pass labels intact — may improve after fix\\n  depends_on:\\n  - D003\\n- id: D005\\n  date: 2026-05-15 04:07 UTC\\n  summary: 'D005: full_trace_v5 确认 81.76%（非 collapse），D004 假说正确。Claim 2 从 \\\"full traces\\n    hurt\\\" 改为 \\\"VOTA 显著优于 full_trace (+13.8pp)\\\"。plan_002 降为 P1。'\\n  rationale: v5 修复 chat template overhead 后 full_trace 从 28.4% 恢复到 81.76%（+6.6pp over\\n    no_trace），确认 v2 collapse 是截断 bug 非 gradient dilution。三条件梯度：no_trace 75.1% < full_trace\\n    81.8% < VOTA 95.6%。Claim 2 reframe 为 \\\"trace compression 提供更高 information density\\\"。plan_002\\n    (label-only loss) 原假设 (gradient dilution) 已被否定，降为 P1；plan_001 (去 actual/expected)\\n    仍是最高优先级。\\n  related_experiments:\\n  - exp_id: full_trace_seed42_v5\\n    role: primary\\n    result: 81.76% accuracy, +6.6pp over no_trace, confirms D004 truncation fix\\n  - exp_id: vota_seed42_v4\\n    role: comparison\\n    result: 95.63%, +13.8pp over full_trace\\n  - exp_id: no_trace_seed42_v4\\n    role: baseline\\n    result: 75.13%\\n  depends_on:\\n  - D004\\n- id: D006\\n  date: 2026-05-15 04:31 UTC\\n  summary: full_trace collapse 根因确认为 chat template overhead bug，非 gradient dilution；v5\\n    修复后 accuracy 81.8%\\n  rationale: full_trace_v2 的 28.4% accuracy + 100% predict fail collapse 完全由 chat\\n    template overhead 导致 pass 样本 label 被截断造成。v5 修复截断后 accuracy 恢复至 81.8%（+6.7pp over\\n    no_trace），collapse 完全消除（pass_recall 从 8.5% 恢复至 87%）。三条件形成清晰层次：no_trace 75.1% <\\n    full_trace 81.8% < VOTA 95.6%。原 D004 中的 gradient dilution 假说被推翻。plan_002 (label-only\\n    loss) 仍保留为 ablation 实验但目的调整：不再验证 collapse 根因，改为测试 loss masking 对 full_trace 的边际提升。\\n  related_experiments:\\n  - exp_id: full_trace_seed42_v2\\n    role: 原始实验（含 bug）\\n    result: 28.4% accuracy, collapse\\n  - exp_id: full_trace_seed42_v5\\n    role: 修复后实验\\n    result: 81.8% accuracy, collapse 消除\\n  - exp_id: vota_seed42_v5\\n    role: 对比基准\\n    result: 99.16% accuracy\\n  - exp_id: no_trace_seed42_v4\\n    role: 对比基准\\n    result: 75.13% accuracy\\n  depends_on:\\n  - D004\\n- id: D007\\n  date: 2026-05-15 06:04 UTC\\n  summary: Claim 3 从 element-level 降级为 component-level design principles；ae_only 移至\\n    Appendix\\n  rationale: ae_only 数据 88% (4159/4720) 为 fallback locals dump 而非干净 actual/expected\\n    值（VOTA compressor _extract_assertions() 固有行为）。ae_only 结果无论高低都无法干净归因于 actual/expected。Reviewer\\n    评估：三个干净实验（plan_001 减法 + exception_only + loop_only）足以支撑 component-level 归因，但不够\\n    element-level。采纳 Reviewer Option A：主表报告 plan_001 + exception_only + loop_only，ae_only\\n    移 Appendix 附 caveat。Claim 1/2 不受影响。\\n  related_experiments:\\n  - exp_id: plan_003\\n    role: component ablation (ae_only/exception_only/loop_only)\\n    result: ae_only 88% fallback 污染\\n  - exp_id: plan_001\\n    role: 主线证据 (减法验证 ae 贡献)\\n    result: RUNNING\\n  depends_on:\\n  - D006\\n- id: D008\\n  date: 2026-05-15 06:23 UTC\\n  summary: plan_001 确认 actual/expected 不是 VOTA 效果来源；Claim 1 走 genuine behavioral understanding\\n    路径\\n  rationale: vota_no_ae (去除 actual/expected) accuracy 99.41% vs VOTA 完整版 99.16%，差异仅\\n    3 样本/1190（不显著），去 ae 后不降反微升。exception + loop + assertion structure 足以实现近完美 verdict\\n    预测。Claim 1 contingency 中 \\\"trivial string comparison\\\" 假说被否定。Reviewer 同时指出 trace\\n    结构性信号（[No trace available]→fail, [ERROR]→fail, [ASSERT]+[LOOP]→pass）可能构成 trivial\\n    pattern，但此问题对所有 VOTA 变体等同存在，不影响 plan_001 结论。exception_only ablation (plan_003\\n    sub-b) 将量化 [ERROR] 信号贡献。\\n  related_experiments:\\n  - exp_id: vota_no_ae_seed42\\n    role: plan_001 ablation\\n    result: 99.41% accuracy, 7 errors/1190\\n  - exp_id: vota_seed42_v5\\n    role: 对照基准\\n    result: 99.16% accuracy, 10 errors/1190\\n  depends_on:\\n  - D006\\n  - D007\\n- id: D009\\n  date: 2026-05-15 07:58 UTC\\n  summary: plan_002 确认 gradient dilution 是 real 但 minor factor (4.5pp/17.4pp=26%)；information\\n    overload 是 VOTA 优势主因 (74%)\\n  rationale: full_trace label-only loss 86.2% vs 标准 loss 81.8%，提升 4.5pp 确认 gradient\\n    dilution 存在。但 86.2% vs VOTA 99.2% 仍有 13pp gap，只能通过 trace compression 弥补。因果分解：gradient\\n    dilution 贡献 ~26% (4.5/17.4pp)，information overload 贡献 ~74% (13.0/17.4pp)。VOTA\\n    的核心优势是信息质量（decision-relevant state selection），不仅是训练效率。这为 Claim 2 提供了定量支撑，可在论文中写\\\"Even\\n    with oracle loss masking, full traces still underperform VOTA by 13pp\\\"。\\n  related_experiments:\\n  - exp_id: full_trace_label_only_seed42\\n    role: plan_002 ablation\\n    result: 86.2% accuracy [84.4, 88.1]\\n  - exp_id: full_trace_seed42_v5\\n    role: 对照 (standard loss)\\n    result: 81.8%\\n  - exp_id: vota_seed42_v5\\n    role: 对照 (VOTA)\\n    result: 99.2%\\n  depends_on:\\n  - D006\\n- id: D010\\n  date: 2026-05-15 09:36 UTC\\n  summary: exception_only 99.83% 证明 exception signal 是 VOTA verdict prediction 的核心驱动因素；Claim\\n    1 从 \\\"behavioral understanding\\\" 调整为 \\\"fault indicator detection\\\"\\n  rationale: exception_only accuracy 99.83% 甚至高于完整 VOTA (99.2%)，说明 exception summaries\\n    单独即可实现近完美 verdict 预测。结合 plan_001 (去 ae 后 99.4%)，组件重要性层次清晰：exception >>> ae ≈ loop。VOTA\\n    的效果核心机制是捕获 fault indicators (exception 有无)，而非深层行为理解。这仍然是有价值的 design principle——verdict\\n    tasks 需要 fault indicators 而非 full execution simulation。论文需诚实讨论：VOTA 之所以有效，是因为\\n    verdict 任务本质是 fault detection，exception 是近乎完美的判别信号。等 loop_only 结果确认层次。\\n  related_experiments:\\n  - exp_id: vota_exception_only_seed42_v2\\n    role: plan_003a exception_only ablation\\n    result: 99.83% accuracy\\n  - exp_id: vota_no_ae_seed42\\n    role: plan_001 (ae redundancy)\\n    result: 99.41%\\n  - exp_id: vota_seed42_v5\\n    role: full VOTA baseline\\n    result: 99.16%\\n  depends_on:\\n  - D008\\n  - D007\\n- id: D011\\n  date: 2026-05-15 10:07 UTC\\n  summary: 完整 component hierarchy 确立：exception (99.83%) >> loop (85.6%) >> no_trace\\n    (75.1%)；采用 Two-tier information architecture framing\\n  rationale: 'plan_003 三个 sub-condition 完成后（ae_only 仍在跑但结论不依赖它）：exception_only 99.83%\\n    是 Tier 1 fault indicators（充分条件），loop_only 85.6% 是 Tier 2 behavioral patterns（有信息但被\\n    Tier 1 完全覆盖）。关键发现：(1) exception_only > VOTA full，p=0.01 显著——非 exception 组件引入噪声；(2)\\n    loop_only ≈ full_trace_label_only (85.6% vs 86.2%)——loop 压缩高效提取了 full trace 的有用行为信号；(3)\\n    组合 Tier 1 + Tier 2 不优于 Tier 1 单独使用。Design principle: verdict tasks should prioritize\\n    highest-specificity diagnostic signals; lower-specificity signals are redundant\\n    and may add noise.'\\n  related_experiments:\\n  - exp_id: vota_exception_only_seed42_v2\\n    role: Tier 1 (fault indicators)\\n    result: 99.83%\\n  - exp_id: vota_loop_only_seed42\\n    role: Tier 2 (behavioral patterns)\\n    result: 85.63%\\n  - exp_id: vota_seed42_v5\\n    role: Tier 1+2+ae combined\\n    result: 99.16%\\n  - exp_id: full_trace_label_only_seed42\\n    role: full trace optimized loss\\n    result: 86.22%\\n  depends_on:\\n  - D010\\n- id: D012\\n  date: 2026-05-15 10:18 UTC\\n  summary: 组件层级确立 + plan_004 扩展为 4 条件含 exception_only\\n  rationale: loop_only (85.6%) 完成后组件层级明确：exception (99.83%) >>> loop (85.6%) >> ae\\n    (冗余)。exception dominance 是最强发现，跨模型验证是最高价值实验。plan_004 原定 3 条件(no_trace/full_trace/VOTA)，扩展加\\n    exception_only 验证 exception dominance 是否跨模型泛化，额外成本 ~2h 但证据价值极高。\\n  related_experiments:\\n  - exp_id: vota_loop_only_seed42\\n    role: trigger\\n    result: 85.6% accuracy, confirms Tier 2 positioning\\n  - exp_id: vota_exception_only_seed42\\n    role: trigger\\n    result: 99.83% accuracy, Tier 1 dominant signal\\n  - exp_id: vota_no_ae_seed42\\n    role: supporting\\n    result: 99.4%, ae redundancy confirmed\\n  depends_on:\\n  - D010\\n  - D011\\n- id: D013\\n  date: 2026-05-15 12:19 UTC\\n  summary: 'D013: ae_only 99.9% 修正组件层级——assertion-point info 与 exception 均为 Tier 1\\n    独立近完美信号'\\n  rationale: ae_only 99.92% 是所有单组件条件中最高的，高于 exception_only 99.83%。D010/D011 的 \\\"exception\\n    is THE driver\\\" 叙事不准确。修正后的层级：Tier 1 包含两个独立的近完美信号源——assertion-point information\\n    (ae_only 99.92%) 和 exception summaries (99.83%)；Tier 2 为 loop compression (85.6%)。虽然\\n    ae_only 有 88% fallback 污染（full locals dump），但这恰恰说明 assertion-point 处的任何信息（甚至 noisy\\n    locals）都是强判别信号。设计原则从 \\\"preserve exception events\\\" 泛化为 \\\"capture information at diagnostic\\n    moments\\\"——assertion 断言点和 exception 抛出点都是 diagnostic moments。ae_only 不应仅作 Appendix\\n    脚注，应与 exception_only 并列为核心消融发现。\\n  related_experiments:\\n  - exp_id: vota_ae_only_seed42\\n    role: primary\\n    result: 99.92% accuracy, highest single-component\\n  - exp_id: vota_exception_only_seed42_v2\\n    role: comparison\\n    result: 99.83% accuracy, previously thought to be THE driver\\n  - exp_id: vota_no_ae_seed42\\n    role: comparison\\n    result: 99.41%, removing ae doesn't hurt much when exception present\\n  depends_on:\\n  - D010\\n  - D011\\n  - D007\\n- id: D014\\n  date: 2026-05-15 14:49 UTC\\n  summary: Claim contingency：根据 DeepSeek exception_only 结果分三档调整 Claim 1/3 措辞；14.7pp\\n    跨模型差距 reframe 为 finding 而非 limitation\\n  rationale: Reviewer 审查：Qwen VOTA 99.2% vs DeepSeek 84.45% (Δ=14.7pp)，但 no_trace\\n    基线接近（73.4% vs 75.1%），差异全在 trace utilization efficiency。DeepSeek exception_only\\n    结果决定 Claim 1 强度：≥95% 强化、85-95% qualify、<85% major revision。Claim 2 被跨模型数据强化（两模型均\\n    VOTA > no_trace）。14.7pp 差距可 reframe 为 \\\"VOTA scales with model capability\\\"（hypothesis\\n    级别）。\\n  related_experiments:\\n  - exp_id: deepseek_vota_seed42\\n    role: cross-model validation\\n    result: 84.45% (Δ=-14.7pp vs Qwen)\\n  - exp_id: deepseek_no_trace_seed42\\n    role: cross-model baseline\\n    result: 73.36% (comparable to Qwen 75.1%)\\n  - exp_id: deepseek_exception_only_seed42\\n    role: pending - determines Claim 1/3 contingency\\n    result: running\\n  depends_on:\\n  - D011\\n  - D012\\n- id: D015\\n  date: 2026-05-15 14:49 UTC\\n  summary: 'Claim 1/3 contingency: 根据 DeepSeek exception_only 结果分三档调整措辞（≥95% 强化 /\\n    85-95% qualify / <85% major revision）；14.7pp 跨模型差距 reframe 为 finding 而非 limitation'\\n  rationale: Reviewer 系统性审查结论：Qwen exception_only 99.83% 是单模型数据，DeepSeek VOTA 仅 84.45%\\n    意味着 exception_only 大概率在 80-90% 区间。需提前准备 qualified 版本。同时 14.7pp 差距可正向叙事为 \\\"VOTA\\n    effectiveness scales with model execution reasoning readiness\\\"——两模型 no_trace 基线持平（73.4%\\n    vs 75.1%）而 VOTA lift 差距大，说明差异来自 trace utilization efficiency 而非基础能力。此解释须标记为 hypothesis。\\n  related_experiments:\\n  - exp_id: deepseek_vota_seed42\\n    role: evidence\\n    result: 84.45% accuracy, +11.1pp over no_trace\\n  - exp_id: deepseek_no_trace_seed42\\n    role: baseline\\n    result: 73.36% accuracy\\n  - exp_id: vota_exception_only_seed42_v2\\n    role: reference\\n    result: 99.83% on Qwen\\n  - exp_id: deepseek_exception_only_seed42\\n    role: pending\\n    result: running, determines claim strength\\n  depends_on:\\n  - D011\\n  - D012\\n- id: D016\\n  date: 2026-05-15 15:12 UTC\\n  summary: 跨模型数据揭示 exception signal 是 universal 诊断信号，VOTA 非 exception 组件 model-specific\\n  rationale: DeepSeek exception_only 99.33%（vs Qwen 99.83%，-0.50pp），而 VOTA 从 99.16%\\n    跌至 84.45%（-14.71pp）。exception 信号跨模型近乎无损，VOTA 的 loop/ae 组件在 DeepSeek 上反而干扰判断。这强化了\\n    Claim 3 two-tier hierarchy，并增加跨模型泛化维度：Tier 1 universal / Tier 2 model-specific。等\\n    deepseek_full_trace 完成后统一更新 paper_framing.md。\\n  related_experiments:\\n  - exp_id: deepseek_exception_only_seed42\\n    role: primary\\n    result: 99.33% accuracy, -0.50pp vs Qwen\\n  - exp_id: deepseek_vota_seed42\\n    role: comparison\\n    result: 84.45% accuracy, -14.71pp vs Qwen\\n  - exp_id: deepseek_no_trace_seed42\\n    role: baseline\\n    result: 73.36% accuracy, -1.77pp vs Qwen\\n  depends_on:\\n  - D010\\n  - D011\\n- id: D017\\n  date: 2026-05-15 15:55 UTC\\n  summary: DeepSeek exception_only epoch 1 达到 99.83%，与 Qwen 完全一致；seed 优先序定为 deepseek\\n    跨模型 > Qwen 第三 seed\\n  rationale: DeepSeek exception_only epoch 1 accuracy = 99.83% = Qwen exception_only\\n    final accuracy，证明 exception signal 的判别力完全跨模型一致，epoch 3 退化至 99.33% 是过拟合而非信号弱化。跨模型\\n    claim 是论文最强新发现，DeepSeek seed robustness（deepseek_exception_only_seed123）比 Qwen\\n    第三 seed（exception_only_seed456）对论文价值更大。\\n  related_experiments:\\n  - exp_id: deepseek_exception_only_seed42\\n    role: primary\\n    result: epoch1=99.83% (identical to Qwen), epoch3=99.33% (overfitting)\\n  - exp_id: exception_only_seed123\\n    role: queued\\n    result: running on cuda:1\\n  depends_on:\\n  - D016\\n- id: D018\\n  date: 2026-05-15 16:48 UTC\\n  summary: DeepSeek full_trace mode collapse 根因确认为 train-eval 截断不匹配，非 chat template\\n    或模型能力问题\\n  rationale: Reviewer 发现 train_sft.py max_length=2048 截断训练输入，但 evaluate.py predict()\\n    无截断逻辑，完整输入（10000+ tokens）远超训练分布导致 collapse。这解释了所有 checkpoint 均 collapse 的现象，也排除了之前的\\n    chat template 和 attention/LoRA rank 假设。修复方案：evaluate.py 加 chat-template-aware\\n    截断，然后重评 3 个 checkpoint 以追踪 collapse 轨迹。\\n  related_experiments:\\n  - exp_id: deepseek_full_trace_seed42\\n    role: 触发诊断\\n    result: negative (28.49% accuracy, all predict fail)\\n  depends_on: []\\n- id: D019\\n  date: 2026-05-15 16:52 UTC\\n  summary: 跨模型验证完成：exception signal universal (0pp gap), narrative 升级为 model-agnostic\\n    fault detection, DeepSeek full_trace 修复后重跑, Paper Agent 今日启动\\n  rationale: plan_004 四条件全部完成。关键发现：(1) exception_only 跨模型 gap=0pp (均99.83% at best\\n    ckpt)，是最强泛化证据；(2) VOTA gap 14.96pp 与 CRUXEval execution reasoning gap 吻合，支持 model-capability-dependent\\n    假说；(3) DeepSeek full_trace 28.5% collapse 根因为 Qwen tokenizer overhead 未适配 DeepSeek\\n    chat template，可修复。决策：(A) narrative 调整为以 exception signal universality 为 headline，VOTA\\n    定位为 isolation mechanism；(B) DeepSeek full_trace 修复重跑 (~2h)，P2 在 seed robustness\\n    后插入；(C) Paper Agent 今日启动，比原计划提前1天，利用 seed robustness 并行窗口。\\n  related_experiments:\\n  - exp_id: deepseek_exception_only_seed42\\n    role: cross-model validation\\n    result: 99.83% epoch1 = Qwen, 0pp gap\\n  - exp_id: deepseek_vota_seed42\\n    role: cross-model VOTA\\n    result: 84.45%, -14.96pp vs Qwen\\n  - exp_id: deepseek_no_trace_seed42\\n    role: cross-model baseline\\n    result: 73.36%, -1.77pp vs Qwen\\n  - exp_id: deepseek_full_trace_seed42\\n    role: cross-model full_trace\\n    result: 28.5% collapsed, chat template bug\\n  depends_on:\\n  - D016\\n  - D017\\n  - D018\\n- id: D020\\n  date: 2026-05-15 16:55 UTC\\n  summary: ae_only 定位：进入主体 Claim 3 层级表（co-Tier 1），但 headline narrative 以 exception_only\\n    为主——因为只有 exception_only 有跨模型 0pp gap 证据\\n  rationale: D007 将 ae_only 移入 Appendix（当时疑似 leakage），D013 发现 ae_only 99.92% 后提升为\\n    co-Tier 1。解决张力：ae_only (assertion-point info, 99.92%) 和 exception_only (99.83%)\\n    都是 Tier 1 diagnostic moment signals，在主体 Claim 3 层级表中并列。但论文 headline 和跨模型 universality\\n    claim 只用 exception_only——原因：(1) exception_only 有 DeepSeek 跨模型 0pp gap 证据，ae_only\\n    没有跨模型数据；(2) exception_only 更干净地回避 \\\"trivial string comparison\\\" 攻击面（ae 包含 actual/expected\\n    值）；(3) vota_no_ae 99.41% 证明 ae 在 exception 存在时冗余。ae_only 结果在 Discussion 中讨论 tier\\n    结构和冗余关系。\\n  related_experiments:\\n  - exp_id: vota_ae_only_seed42\\n    role: ae_only ablation\\n    result: 99.92%\\n  - exp_id: vota_exception_only_seed42_v2\\n    role: exception_only ablation\\n    result: 99.83%\\n  - exp_id: vota_no_ae_seed42\\n    role: ae redundancy\\n    result: 99.41%\\n  - exp_id: deepseek_exception_only_seed42\\n    role: cross-model exception\\n    result: 99.83% epoch1\\n  depends_on:\\n  - D007\\n  - D013\\n  - D019\\n- id: D021\\n  date: 2026-05-15 18:23 UTC\\n  summary: DeepSeek full_trace 根因确认为训练端 label 截断（非 eval 端），v2 重训终止，论文用 N/A + Limitations\\n    披露。正确修复降为 P3。\\n  rationale: Reviewer critical 审查发现：(1) eval 端截断修复后 accuracy 从 28.5% 降至 10.6%（852/1190\\n    生成垃圾输出），证明 eval 不是根因；(2) 真正根因是 train_sft.py max_length=2048 截断了 input+output 组合序列，DeepSeek\\n    tokenizer 效率低导致 response label 被截断，模型从未学到 \\\"pass\\\" 映射；(3) v2 重训用相同代码和数据，必然重现失败。正确修复需修改数据预处理（按\\n    DeepSeek tokenizer budget 截断 input content）+ 重训 ~2h，降为 P3。三个有效条件（exception_only/VOTA/no_trace）已充分支撑全部\\n    claims，full_trace 是 bonus 非必需。GPU 1 释放后优先安排更高价值任务。\\n  related_experiments:\\n  - exp_id: deepseek_full_trace_seed42\\n    role: original collapsed\\n    result: 28.5% → eval fix → 10.6%, root cause = train-side label truncation\\n  - exp_id: deepseek_full_trace_seed42_v2\\n    role: v2 retraining\\n    result: KILLED — same bug, will reproduce failure\\n  depends_on:\\n  - D018\\n  - D019\\n- id: D022\\n  date: 2026-05-15 18:23 UTC\\n  summary: Kill deepseek_full_trace_seed42_v2 重训 (PID 144864)，DeepSeek full_trace\\n    按 N/A 处理\\n  rationale: Reviewer critical 确认：eval_results_fixed.json 显示修复版 evaluate.py 重评仍只有\\n    10.6% accuracy（模型输出乱码），证明根因是训练阶段 label 截断（full_trace 序列远超 2048 tokens，SFTTrainer\\n    右截断丢失末尾 label），而非 evaluate.py 问题。PID 144864 使用相同参数（无 max_length 覆盖），必然复现。释放 GPU\\n    1 给 vota_seed456。DeepSeek full_trace 在论文中按 Option A 处理（Limitations 透明披露，报为 N/A）。\\n  related_experiments:\\n  - exp_id: deepseek_full_trace_seed42_v2\\n    role: killed\\n    result: label truncation unfixed, retraining would reproduce same failure\\n  - exp_id: full_trace_seed42_v2\\n    role: root_cause_evidence\\n    result: original full_trace collapse 28.5% → fixed eval 10.6%, confirming training-stage\\n      label truncation\\n  depends_on: []\\n- id: D023\\n  date: 2026-05-15 18:39 UTC\\n  summary: 阻止 DeepSeek full_trace v3 提交，要求先修复 to_chat_text() label 截断问题\\n  rationale: Reviewer critical 确认：train_sft.py 的 to_chat_text() 未做 content-aware truncation，full_trace\\n    样本超 10000 tokens 被 SFTTrainer 从右截断到 2048，label 在末尾被砍掉。v1 已证实产出废模型（10.6% accuracy）。必须修改\\n    to_chat_text() 在构建训练序列前截断 INPUT content 而非整个序列，与 evaluate.py predict() fix 保持一致。\\n  related_experiments:\\n  - exp_id: deepseek_full_trace_v1\\n    role: evidence\\n    result: 10.6% accuracy, 模型输出乱码，确认 label 截断导致训练失败\\n  - exp_id: deepseek_full_trace_v3\\n    role: blocked\\n    result: 未修复前禁止提交\\n  depends_on: []\\n- id: D024\\n  date: 2026-05-15 19:30 UTC\\n  summary: 数据集来源纠正：CRUXEval → HumanEval (164) + MBPP-sanitized (427)，全文修正\\n  rationale: Worker 检查 generate_data.py 和数据文件后确认，数据集实际来源是 HumanEval + MBPP-sanitized（591\\n    problems × 10 solutions = 5910 samples），非此前误认的 CRUXEval。论文、framing、ROADMAP 中所有\\n    \\\"CRUXEval\\\" 和 \\\"800 functions\\\" 引用均需修正。CRUXEval 相关分析仍可作为 Discussion 点（解释 DeepSeek\\n    vs Qwen VOTA gap），但数据集描述必须准确。\\n  related_experiments: []\\n  depends_on: []\\n- id: D025\\n  date: 2026-05-15 20:10 UTC\\n  summary: 'DeepSeek seed123 negative (91.09% vs 99.83%): 先验证 epoch hypothesis 再定\\n    framing，同时并行补全跨模型表'\\n  rationale: 'seed123 train_loss 0.122 >> seed42 的 0.05，暗示收敛到较差局部最优。如果 epoch 1 accuracy\\n    接近 99%，问题是 overfitting 而非 signal 失效，对论文冲击大幅缩小。deepseek_full_trace_v3 是独\\n\\n... [截断: 省略 38270 字符，传 max_chars=0 获取完整内容]\", \"total_chars\": 58270, \"truncated\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f96363ee-afff-46e0-ac3a-a75ee65a2d69",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "e6e3e031-9a18-4f54-9951-20b319977daf",
  "sourceToolAssistantUUID": "f96363ee-afff-46e0-ac3a-a75ee65a2d69",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 18 · 2026-05-18T12:31:45.972Z_

Now let me read the actual paper artifacts.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e6e3e031-9a18-4f54-9951-20b319977daf",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3C7WyafE8bfcsYvRTU",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "5d26308a-d74c-48fb-a92b-a2503e43a1ed",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fPCuBPco7ChikH4UeqKbS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18511,
      "cache_read_input_tokens": 25066,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18511,
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

_source line 19 · 2026-05-18T12:31:47.392Z_

<details open><summary>🔧 Tool call — Glob · `toolu_0156dzxhYvbKgEwXbRJkJPpM`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5d26308a-d74c-48fb-a92b-a2503e43a1ed",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3C7WyafE8bfcsYvRTU",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0c12a1b7-40fe-42b7-bd4e-d53c04ef50e4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fPCuBPco7ChikH4UeqKbS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18511,
      "cache_read_input_tokens": 25066,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18511,
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

_source line 20 · 2026-05-18T12:31:47.415Z_

<details><summary>↩ Tool result · `toolu_0156dzxhYvbKgEwXbRJkJPpM`</summary>

```text
artifacts/dream_reports/dream_20260515T013018/best/paper.tex
artifacts/dream_reports/dream_20260515T013018/median/paper.tex
artifacts/dream_reports/dream_20260515T013018/worst/paper.tex
artifacts/dream_reports/dream_20260515T084908/best/paper.tex
artifacts/dream_reports/dream_20260515T084908/median/paper.tex
artifacts/dream_reports/dream_20260515T084908/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/per_class_breakdown.tex
artifacts/_project/paper/section3_experimental_setup_d4f1e8.tex
artifacts/_project/paper/section3_experimental_setup.tex
artifacts/_project/paper/ethics_statement.tex
artifacts/_project/paper/ethics_statement_77cf5f.tex
artifacts/_project/paper/arr_checklist.tex
artifacts/_project/paper/main_results_tables.tex
artifacts/_project/paper/main_results_tables_d8c8b6.tex
artifacts/paper_tables/main_results_tables.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260516T105259/best/paper.tex
artifacts/dream_reports/dream_20260516T105259/median/paper.tex
artifacts/dream_reports/dream_20260516T105259/worst/paper.tex
artifacts/dream_reports/dream_20260516T155731/best/paper.tex
artifacts/dream_reports/dream_20260516T155731/median/paper.tex
artifacts/dream_reports/dream_20260516T155731/worst/paper.tex
artifacts/dream_reports/dream_20260518T113804/best/paper.tex
artifacts/dream_reports/dream_20260518T113804/median/paper.tex
artifacts/dream_reports/dream_20260518T113804/worst/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "0c12a1b7-40fe-42b7-bd4e-d53c04ef50e4",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "ddb31d65-3da1-4618-8053-ceef775d8126",
  "sourceToolAssistantUUID": "0c12a1b7-40fe-42b7-bd4e-d53c04ef50e4",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-18T12:31:48.032Z_

<details open><summary>🔧 Tool call — Glob · `toolu_017uHPHdHAz2qdkoszWNmC8q`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ddb31d65-3da1-4618-8053-ceef775d8126",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3C7WyafE8bfcsYvRTU",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "82523b80-e654-42c9-984c-858f7c9daf95",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019fPCuBPco7ChikH4UeqKbS",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18511,
      "cache_read_input_tokens": 25066,
      "output_tokens": 189,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 18511
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 189,
          "cache_read_input_tokens": 25066,
          "cache_creation_input_tokens": 18511,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 18511,
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

_source line 22 · 2026-05-18T12:31:48.049Z_

<details><summary>↩ Tool result · `toolu_017uHPHdHAz2qdkoszWNmC8q`</summary>

```text
artifacts/dream_reports/dream_20260515T013018/best/paper.tex
artifacts/dream_reports/dream_20260515T013018/median/paper.tex
artifacts/dream_reports/dream_20260515T013018/worst/paper.tex
artifacts/dream_reports/dream_20260515T084908/best/paper.tex
artifacts/dream_reports/dream_20260515T084908/median/paper.tex
artifacts/dream_reports/dream_20260515T084908/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/per_class_breakdown.tex
artifacts/_project/paper/section3_experimental_setup_d4f1e8.tex
artifacts/_project/paper/section3_experimental_setup.tex
artifacts/_project/paper/ethics_statement.tex
artifacts/_project/paper/ethics_statement_77cf5f.tex
artifacts/_project/paper/arr_checklist.tex
artifacts/_project/paper/main_results_tables.tex
artifacts/_project/paper/main_results_tables_d8c8b6.tex
artifacts/paper_tables/main_results_tables.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260516T105259/best/paper.tex
artifacts/dream_reports/dream_20260516T105259/median/paper.tex
artifacts/dream_reports/dream_20260516T105259/worst/paper.tex
artifacts/dream_reports/dream_20260516T155731/best/paper.tex
artifacts/dream_reports/dream_20260516T155731/median/paper.tex
artifacts/dream_reports/dream_20260516T155731/worst/paper.tex
docs/paper/arr_checklist.tex
docs/paper/method.tex
docs/paper/conclusion.tex
docs/paper/main.tex
docs/paper/related_work.tex
docs/paper/appendix.tex
docs/paper/experiments.tex
docs/paper/discussion.tex
docs/paper/introduction.tex
artifacts/dream_reports/dream_20260518T113804/best/paper.tex
artifacts/dream_reports/dream_20260518T113804/median/paper.tex
artifacts/dream_reports/dream_20260518T113804/worst/paper.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "82523b80-e654-42c9-984c-858f7c9daf95",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "3ae16b09-1441-4fdd-b14e-07842bd7b644",
  "sourceToolAssistantUUID": "82523b80-e654-42c9-984c-858f7c9daf95",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 23 · 2026-05-18T12:31:51.194Z_

Let me read the main paper file and key sections.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3ae16b09-1441-4fdd-b14e-07842bd7b644",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3CiB4ievoLooPFz2F9",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "34856e45-d5c2-49a0-a0b8-fae4ec9a2638",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PfAVNg6HzNkht5dvG9zuAe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1379,
      "cache_read_input_tokens": 43577,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1379,
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

_source line 24 · 2026-05-18T12:31:51.670Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UpUokzs686HB6HnSyNNeNH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "34856e45-d5c2-49a0-a0b8-fae4ec9a2638",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3CiB4ievoLooPFz2F9",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "75380c85-2918-44b2-a8f6-95a660d980eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PfAVNg6HzNkht5dvG9zuAe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1379,
      "cache_read_input_tokens": 43577,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1379,
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

_source line 25 · 2026-05-18T12:31:51.686Z_

<details><summary>↩ Tool result · `toolu_01UpUokzs686HB6HnSyNNeNH`</summary>

```text
1	\documentclass[11pt,a4paper]{article}
2	\usepackage[review]{acl}
3	% \usepackage{acl}  % uncomment for camera-ready (remove [review])
4	\usepackage{times,latexsym}
5	\usepackage{amsmath,amssymb}
6	\usepackage{graphicx}
7	\graphicspath{{../../figures/paper/}}
8	\usepackage{booktabs}
9	\usepackage{multirow}
10	\usepackage{xcolor}
11	
12	\title{Exception Events Are All You Need: \\Component Ablation for Trace-Based Verdict Prediction}
13	\author{Anonymous ACL submission}
14	
15	\begin{document}
16	\maketitle
17	
18	\begin{abstract}
19	Execution traces are increasingly used to enhance code language models, but which trace components matter for downstream tasks remains poorly understood.
20	We present the first systematic component ablation of trace representations for verdict prediction (classifying whether a test passes or fails) across four models spanning three architecture families and 1.5B to 13B parameters.
21	Exception events alone achieve ${\geq}$99.33\% accuracy across all four models (${\geq}$99.83\% on three of four; one seed reaches 100\%), while a code-only baseline shows 9.19pp scale sensitivity (67.3--76.5\%).
22	Adding more trace information actively hurts: a multi-component representation underperforms exception-only, and the full-trace gap approximately decomposes into information overload (${\sim}$74\%) and gradient dilution (${\sim}$26\%).
23	Tail-truncation experiments reveal that diagnostic signal concentrates near the trace terminus (in a localized window, not the absolute end), recovering 86\% of the gap to exception-only.
24	A format-marker ablation confirms ${\sim}$91\% of the exception signal is semantic (learned by SFT to distinguish caught from uncaught exceptions) rather than format-driven.
25	These results reveal a two-tier diagnostic hierarchy: Tier~1 signals (exception events, assertion points) individually achieve ${\geq}$99\%, while Tier~2 (loop compression) reaches 85.6\%.
26	Cross-dataset evaluation on DebugBench ($N{=}426$) confirms generalization, with exception-only achieving 100\%.
27	We reframe verdict prediction as fault detection: the minimal sufficient signal is a compact exception event (median 150 tokens) that is scale-invariant, architecture-independent, and deployable in token-constrained settings.
28	\end{abstract}
29	
30	\input{introduction}
31	\input{method}
32	\input{experiments}
33	\input{discussion}
34	\input{related_work}
35	\input{conclusion}
36	
37	\section*{Limitations}
38	
39	Our study has several limitations.
40	First, our primary experiments use a single dataset (591 problems from HumanEval and MBPP-sanitized); while a cross-dataset evaluation on DebugBench (\S\ref{sec:debugbench}) confirms that exception dominance generalizes to synthetically injected bugs, generalization to other languages, larger codebases, or real-world fault distributions remains untested.
41	Second, while we evaluate four models spanning 1.5B to 13B parameters across three architecture families, all are code-specialized; generalization to general-purpose models or larger scales remains untested.
42	Third, DeepSeek \texttt{exception\_only} exhibits seed-dependent variance: 2/3 seeds achieve 99.33\% while seed 123 yields 91.09\% ($\sigma{=}4.76$pp, $n{=}3$), which we hypothesize reflects LoRA initialization sensitivity in DeepSeek-Coder, though direct evidence is lacking (fail recall = 70.5\% for the outlier vs.\ 100\% for others).
43	Qwen \texttt{exception\_only} shows perfect seed robustness ($\sigma{=}0$, $n{=}3$), but Qwen \texttt{ae\_only} also exhibits seed variance ($\sigma{=}$0.40pp; seed 123 = 99.08\% vs.\ seeds 42/456 = 99.92\%), though far smaller than DeepSeek's ($\sigma{=}$4.76pp).
44	Whether training stabilization techniques can eliminate DeepSeek's seed sensitivity is unexplored; other conditions use a single seed.
45	Fourth, the initial DeepSeek \texttt{full\_trace} run was invalidated by context overflow; a re-run with extended context yields 79.16\% (CI [76.80\%, 81.30\%]), 2.60pp below Qwen (Table~\ref{tab:cross_model}).
46	Fifth, the candidate solutions were generated by Qwen-2.5-Coder-7B-Instruct, which also serves as one of our evaluation models; this does not affect verdict prediction but may influence the pass/fail distribution.
47	Sixth, self-familiarity bias may inflate absolute accuracy: both Qwen-2.5-Coder and DeepSeek-Coder were likely exposed to HumanEval and MBPP solutions during pretraining, so the models may partially recognize solutions rather than purely reasoning from trace signals; our cross-dataset evaluation on DebugBench mitigates but does not eliminate this concern.
48	Seventh, the error distribution in our test set may not reflect real-world fault distributions: exceptions (especially \texttt{TypeError}, \texttt{ValueError}) dominate LLM-generated failures, but production code may exhibit a broader spectrum of silent logic errors where no exception is raised, potentially reducing the effectiveness of exception-based verdict prediction.
49	Finally, our analysis is limited to verdict prediction; whether exception dominance extends to other classification tasks or generation tasks is an open question.
50	
51	\section*{Ethics Statement}
52	
53	This work uses publicly available benchmarks (HumanEval, MBPP-sanitized, DebugBench) and does not involve human subjects, crowdsourced annotations, or personally identifiable information.
54	All models evaluated are open-source and publicly accessible.
55	Training uses parameter-efficient LoRA fine-tuning on two RTX PRO 6000 Blackwell GPUs, with each experiment using a single GPU and total compute under 20 GPU-hours across all experiments, resulting in minimal environmental impact.
56	We do not foresee direct negative societal impacts from this work; verdict prediction is a developer-facing tool for automated testing.
57	
58	\bibliography{references}
59	
60	\appendix
61	\input{appendix}
62	
63	\end{document}
64	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "75380c85-2918-44b2-a8f6-95a660d980eb",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "41268601-9250-4fb6-ad9f-2357a0fe30b8",
  "sourceToolAssistantUUID": "75380c85-2918-44b2-a8f6-95a660d980eb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-18T12:31:52.627Z_

<details open><summary>🔧 Tool call — Read · `toolu_018VbeJctBBdG42aXx8YKApk`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "41268601-9250-4fb6-ad9f-2357a0fe30b8",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3CiB4ievoLooPFz2F9",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2bf90409-e6d8-48cb-b876-19cfed53421f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PfAVNg6HzNkht5dvG9zuAe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1379,
      "cache_read_input_tokens": 43577,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1379,
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

_source line 27 · 2026-05-18T12:31:52.633Z_

<details><summary>↩ Tool result · `toolu_018VbeJctBBdG42aXx8YKApk`</summary>

```text
1	\section{Introduction}
2	
3	Execution traces (line-by-line records of a program's runtime behavior) have emerged as a promising input modality for code language models \citep{chen2025tracepile,ding2024traced,wang2025dcsh,ni2024next}.
4	Yet feeding thousands of trace lines to a model can be no better than feeding none: the diagnostic signal drowns in routine execution steps.
5	\emph{Which trace components actually carry the signal that matters?}
6	
7	Prior work found no single trace representation consistently outperforms others \citep{wang2025dcsh}, but focused on generation-oriented tasks.
8	\emph{Verdict prediction}, classifying whether a test passes or fails, is fundamentally different: it is fault detection, not generation.
9	The model need not simulate execution; it need only determine whether something went wrong.
10	This distinction suggests that a small, fault-specific trace component may suffice.
11	
12	We test this hypothesis through the first systematic component ablation of trace representations for verdict prediction.
13	Using 591 problems from HumanEval \citep{chen2021evaluating} and MBPP-sanitized \citep{austin2021program}, we decompose a multi-component trace representation (VOTA: exception events + assertion-point comparisons + loop compression) into individual components across four models spanning 1.5B to 13B parameters and three architecture families: Qwen-2.5-Coder-7B/1.5B-Instruct \citep{qwen2025coder}, CodeLlama-13B-Instruct \citep{roziere2024code}, and DeepSeek-Coder-6.7B-Instruct \citep{deepseek2024coder}.
14	
15	\textbf{Exception events alone achieve ${\geq}$99.33\% verdict accuracy across all four models (${\geq}$99.83\% on three of four; one seed reaches 100\%).}
16	This near-perfect accuracy holds from 1.5B to 13B parameters, while the code-only baseline (\texttt{no\_trace}) varies from 67.3\% to 76.5\% with strong scale dependence.
17	The exception signal eliminates the need for model capacity to compensate for missing information.
18	
19	More surprisingly, adding trace information beyond exceptions actively \emph{hurts}: VOTA (99.41\%) underperforms \texttt{exception\_only} (99.83\%), and the degradation reaches 14.96pp on DeepSeek, compounded by tokenizer-driven truncation.
20	We approximately decompose this gap: ${\sim}$74\% stems from information overload (irrelevant trace content at inference) and ${\sim}$26\% from gradient dilution (dispersed training signal).
21	Tail-truncation experiments across four models and three architecture families confirm the mechanism: a sharp phase transition at ${\sim}$500 tail tokens (matching the typical exception traceback length) separates near-baseline from near-ceiling accuracy, and \texttt{tail\_2048} captures 95--98\% of \texttt{exception\_only}'s performance.
22	
23	Our contributions:
24	\begin{enumerate}
25	\item \textbf{Exception events are the minimal sufficient signal}: ${\geq}$99.33\% across four models and three families (1.5B--13B), with ${\sim}$91\% of the signal being semantic rather than format-driven (\S\ref{sec:cross_model}, \S\ref{sec:nomarker}). SFT closes a 6--49pp zero-shot gap across four models and three architecture families, and outperforms both few-shot prompting and the best regex heuristic (\S\ref{sec:ablation}). Cross-dataset evaluation on DebugBench ($N{=}426$) yields 100\% (\S\ref{sec:debugbench}).
26	\item \textbf{Richer traces actively hurt}: We approximately decompose why into gradient dilution (${\sim}$26\%) and information overload (${\sim}$74\%). A budget sweep across four models and three families reveals a phase transition at ${\sim}$500 tail tokens, with \texttt{tail\_2048} recovering 95--98\% of \texttt{exception\_only} (\S\ref{sec:density}, \S\ref{sec:trace_length}).
27	\item \textbf{Two-tier diagnostic hierarchy}: Tier~1 signals (exceptions, assertions) individually achieve ${\geq}$99\%; Tier~2 (loop compression) reaches 85.6\%, still +10.5pp over no trace (\S\ref{sec:ablation}).
28	\end{enumerate}
29	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2bf90409-e6d8-48cb-b876-19cfed53421f",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "4215bfe6-4dce-4bc4-90bf-501b49738272",
  "sourceToolAssistantUUID": "2bf90409-e6d8-48cb-b876-19cfed53421f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 28 · 2026-05-18T12:31:52.727Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PeozTA968wF8YkGvfdsBvk`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4215bfe6-4dce-4bc4-90bf-501b49738272",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3CiB4ievoLooPFz2F9",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "dac07c08-8aa7-402d-9a6e-5aef96f6f886",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PfAVNg6HzNkht5dvG9zuAe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1379,
      "cache_read_input_tokens": 43577,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1379,
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

_source line 29 · 2026-05-18T12:31:52.733Z_

<details><summary>↩ Tool result · `toolu_01PeozTA968wF8YkGvfdsBvk`</summary>

```text
1	\section{Method}
2	
3	\subsection{Task Definition}
4	
5	We study \emph{verdict prediction}: given a Python function, a test input, and an optional execution trace, predict whether the test passes or fails.
6	The model produces a single token (\texttt{pass} or \texttt{fail}), making this a binary classification task.
7	Unlike code generation \citep{chen2025tracepile} or output prediction \citep{gu2024cruxeval}, verdict prediction isolates the model's ability to detect faults from its ability to simulate execution.
8	
9	\subsection{Dataset}
10	\label{sec:dataset}
11	
12	We sampled 10 candidate solutions per problem from Qwen-2.5-Coder-7B-Instruct (temperature 0.8, top\_p 0.95) for 591 problems from HumanEval \citep{chen2021evaluating} (164) and MBPP-sanitized \citep{austin2021program} (427), executed each against canonical tests with \texttt{sys.settrace} to obtain line-level traces and pass/fail verdicts, yielding 5,910 pairs (67\% pass, 33\% fail).
13	The dataset is split 80/20 by problem ID into 4,720 training and 1,190 test samples (majority baseline: 71.51\%).
14	The \texttt{exception\_only} format collapses passing solutions into identical rows (39.45\% train, 48.99\% test duplicates); train--test input overlap is zero (Appendix~\ref{sec:dedup_stats}).
15	
16	\subsection{Trace Representations}
17	
18	We define seven conditions that vary the trace information available (Figure~\ref{fig:trace_overview}):
19	\begin{itemize}
20	\item \texttt{no\_trace}: Source code and test input only.
21	\item \texttt{full\_trace}: Complete line-by-line trace with variable states.
22	\item \texttt{VOTA}: Exception events + assertion-point comparisons + loop compression.
23	\item \texttt{exception\_only}: Only exception/error events.
24	\item \texttt{ae\_only}: Only assertion-point actual/expected pairs.
25	\item \texttt{loop\_only}: Only loop compression summaries.
26	\item \texttt{VOTA\_no\_ae}: VOTA without assertion-point information.
27	\end{itemize}
28	
29	\begin{figure*}[t]
30	\centering
31	\includegraphics[width=\textwidth]{fig1_trace_overview}
32	\caption{Overview of the verdict prediction pipeline. Source code and a test input are executed to produce a full raw trace. Four conditions vary the trace information: \texttt{no\_trace} (75.13\%), \texttt{full\_trace} (81.76\%), VOTA (99.41\%), and \texttt{exception\_only} (99.83\%). Accuracies for Qwen-2.5-7B (seed=42, $N{=}1{,}190$).}
33	\label{fig:trace_overview}
34	\end{figure*}
35	
36	\subsection{Models and Training}
37	
38	We evaluate four models spanning three architecture families: \textbf{Qwen-2.5-Coder-7B/1.5B-Instruct} \citep{qwen2025coder}, \textbf{CodeLlama-13B-Instruct} \citep{roziere2024code}, and \textbf{DeepSeek-Coder-6.7B-Instruct} \citep{deepseek2024coder}, covering a 1.5B--13B parameter range (8.7$\times$).
39	All conditions use LoRA \citep{hu2022lora} (rank=16, $\alpha$=32, dropout=0.05) on all linear layers, 3 epochs, effective batch size 32, LR $2 \times 10^{-4}$ with linear warmup/decay, max sequence length 2{,}048 tokens.
40	Sequences exceeding this limit are truncated while preserving the verdict label.
41	The primary seed is 42; seeds 123 and 456 test \texttt{exception\_only} robustness (Appendix~\ref{sec:training_details}).
42	
43	\subsection{Loss Ablation}
44	
45	To disentangle training signal from input signal quality, we introduce \texttt{full\_trace\_label\_only}: identical full-trace input but loss computed only on the verdict token (trace positions masked).
46	Improvement over standard \texttt{full\_trace} is attributable to \emph{gradient dilution}; the remaining gap to VOTA reflects \emph{information overload} at inference time.
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "dac07c08-8aa7-402d-9a6e-5aef96f6f886",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "d252816b-62a2-47a7-9842-4658157b3072",
  "sourceToolAssistantUUID": "dac07c08-8aa7-402d-9a6e-5aef96f6f886",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 30 · 2026-05-18T12:31:58.410Z_

<details open><summary>🔧 Tool call — Read · `toolu_01M1DwpaBDY2ppUcxcgvcNuN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d252816b-62a2-47a7-9842-4658157b3072",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3D5J4Pqop5eeSGCeF8",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "8d7818f2-40d5-4194-85fc-0080ee743d22",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012hjps1w9Rb822MA64WuN7m",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4363,
      "cache_read_input_tokens": 44956,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 4363,
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

_source line 31 · 2026-05-18T12:31:58.421Z_

<details><summary>↩ Tool result · `toolu_01M1DwpaBDY2ppUcxcgvcNuN`</summary>

```text
1	\section{Experiments}
2	
3	We evaluate across two research questions:
4	(1)~Do Tier~1 exception signals generalize across models?
5	(2)~What is the relative contribution of each trace component?
6	All experiments use $N{=}1{,}190$ test samples; accuracy is reported with Wilson 95\% CIs.
7	Pairwise comparisons use paired bootstrap resampling ($B{=}10{,}000$, seed=42); all differences are significant at $p{<}0.0001$ unless noted.
8	
9	\subsection{Cross-Model Comparison}
10	\label{sec:cross_model}
11	
12	Table~\ref{tab:cross_model} compares four models spanning an 8.7$\times$ parameter range (1.5B--13B) and three architecture families (Qwen, DeepSeek, CodeLlama) under key conditions.
13	
14	\begin{table}[t]
15	\centering
16	\caption{Cross-model verdict accuracy (\%, $N{=}1{,}190$). Bold: best accuracy per model. Multi-seed entries show mean$\pm$std (3 seeds). $^\dag$2/3 seeds; one seed excluded due to LoRA initialization failure (91.09\%, fail recall = 70.5\%; see Appendix~\ref{sec:training_dynamics}). \texttt{ae\_only} and \texttt{loop\_only} ablations tested on Qwen-7B (3 seeds) to isolate component contributions; cross-model validation focused on the primary conditions. Full CIs in Appendix~\ref{sec:full_results}.}
17	\label{tab:cross_model}
18	\small
19	\resizebox{\columnwidth}{!}{%
20	\begin{tabular}{lcccc}
21	\toprule
22	\textbf{Condition} & \textbf{Qwen-7B} & \textbf{Qwen-1.5B} & \textbf{CL-13B} & \textbf{DS-6.7B} \\
23	\midrule
24	exception\_only & \textbf{99.83}{\scriptsize$\pm$0.00} & \textbf{99.83} & \textbf{99.89}{\scriptsize$\pm$0.10} & \textbf{99.33}$^\dag$ \\
25	ae\_only & 99.64{\scriptsize$\pm$0.49} & --- & --- & --- \\
26	VOTA & 99.41 & 99.58 & 98.57 & 84.45 \\
27	no\_trace & 75.13 & 67.31 & 76.50 & 73.36 \\
28	\midrule
29	Majority baseline & \multicolumn{4}{c}{71.51} \\
30	\bottomrule
31	\end{tabular}%
32	}
33	\end{table}
34	
35	\paragraph{Exception dominance across families.}
36	Under \texttt{exception\_only}, the Qwen and CodeLlama families achieve ${\geq}$99.83\% (mean): Qwen-7B (99.83\%$\pm$0.00, 3 seeds), Qwen-1.5B (99.83\%), and CodeLlama-13B (99.89\%$\pm$0.10, 3 seeds; seed 123 achieves 100\%).
37	DeepSeek-6.7B reaches 99.33\% on 2/3 seeds with one LoRA-sensitivity outlier at 91.09\% (seed 123; fail recall = 70.5\%); even the outlier outperforms VOTA (84.45\%) by 6.64pp.
38	Excluding the DeepSeek outlier, the cross-model range is 0.56pp (99.33--99.89\%), the tightest of any condition.
39	
40	\paragraph{Scale invariance of exception signals.}
41	Exception-based accuracy is shared by models spanning 1.5B to 13B parameters (8.7$\times$): both Qwen-1.5B and CodeLlama-13B achieve 99.83\%+ on the same representation.
42	CodeLlama-13B seed 123 achieves 100\% (0/1190 errors), confirming that Qwen's two persistent errors (from \texttt{GeneratorExit}; Appendix~\ref{sec:irreducible}) are high-probability convergence artifacts rather than hard data limitations.
43	In contrast, \texttt{no\_trace} scales monotonically with capacity: 67.31\% (1.5B) $\to$ 75.13\% (7B) $\to$ 76.50\% (13B), a 9.19pp range that exception events completely eliminate (Figure~\ref{fig:cross_scale}).
44	
45	\begin{figure}[t]
46	\centering
47	\includegraphics[width=\columnwidth]{fig3_cross_model_gap}
48	\caption{Verdict accuracy vs.\ model scale. \texttt{exception\_only} maintains ${\geq}$99.33\% regardless of scale (1.5B--13B), while \texttt{no\_trace} shows monotonic scale sensitivity (+9.19pp from 1.5B to 13B). The \texttt{nomarker} condition (format markers removed) shows no degradation at smaller scale (${\sim}$97.7--97.8\%).}
49	\label{fig:cross_scale}
50	\end{figure}
51	
52	\paragraph{VOTA cross-family variation.}
53	VOTA accuracy varies across families: 99.58\% (Qwen-1.5B) $>$ 99.41\% (Qwen-7B) $>$ 98.57\% (CodeLlama-13B; \texttt{codellama13b\_vota\_seed42}, CI [97.9, 99.2]) $\gg$ 84.45\% (DeepSeek-6.7B).
54	The CodeLlama result (17 errors) narrows the gap: among models without tokenizer-driven truncation, the VOTA range is only 1.01pp (98.57--99.58\%), suggesting that the 14.96pp DeepSeek deficit is primarily a truncation artifact rather than an inherent model capability limitation (91.7\% of DeepSeek training samples were affected; Appendix~\ref{sec:tokenizer_analysis}).
55	In contrast, \texttt{exception\_only} inputs are compact (median 150 tokens, mean 398 due to verbose fail-class exceptions), making the cross-model comparison clean.
56	
57	\subsection{Component Ablation}
58	\label{sec:ablation}
59	
60	We restrict \texttt{ae\_only} and \texttt{loop\_only} ablations to Qwen-7B, as these component-level analyses target the trace composition mechanism rather than cross-model generalization.
61	Table~\ref{tab:ablation} decomposes VOTA on Qwen-2.5-7B (seed=42) and reveals a two-tier hierarchy.
62	
63	\begin{table}[t]
64	\centering
65	\caption{Component ablation on Qwen-2.5-7B ($N{=}1{,}190$). Tier~1 signals achieve near-perfect accuracy; combining them (VOTA) slightly dilutes performance. $^\dag$\texttt{ae\_only}: 3-seed mean 99.64\% ($\pm$0.49; seeds 42: 99.92, 123: 99.08, 456: 99.92). \texttt{exception\_only}: 99.83\% ($\pm$0.00, 3 seeds), more stable ($\sigma{=}$0 vs.\ $\sigma{=}$0.49).}
66	\label{tab:ablation}
67	\small
68	\resizebox{\columnwidth}{!}{%
69	\begin{tabular}{llccc}
70	\toprule
71	\textbf{Condition} & \textbf{Components} & \textbf{Acc (\%)} & \textbf{95\% CI} & \textbf{Tier} \\
72	\midrule
73	ae\_only & assertion-point & 99.64$^\dag$ & [99.26, 99.87] & 1 \\
74	exception\_only & exception events & \textbf{99.83} & [99.58, 100.00] & 1 \\
75	VOTA & exc+ae+loop & 99.41 & [98.82, 99.83] & --- \\
76	VOTA\_no\_ae & exc+loop & 99.41 & [98.90, 99.80] & --- \\
77	loop\_only & loop compression & 85.63 & [83.53, 87.56] & 2 \\
78	full\_trace & complete trace & 81.76 & [79.70, 83.90] & --- \\
79	no\_trace & none & 75.13 & [72.77, 77.48] & --- \\
80	\midrule
81	Regex (best) & exc.\ type regex & 93.61 & --- & --- \\
82	3-shot (Qwen-7B) & in-context learning & 90.84 & --- & --- \\
83	Zero-shot (4 models) & prompting & 51.0--93.5 & --- & --- \\
84	\bottomrule
85	\end{tabular}%
86	}
87	\end{table}
88	
89	Tier~1 signals are individually sufficient: \texttt{ae\_only} (3-seed mean 99.64\% $\pm$ 0.49) and \texttt{exception\_only} (99.83\% $\pm$ 0.00) both exceed VOTA ($p{=}0.01$), implying that combining signals introduces noise; \texttt{exception\_only} is more stable across seeds ($\sigma{=}$0 vs.\ $\sigma{=}$0.49).
90	Removing assertion points has no effect (\texttt{VOTA\_no\_ae} = 99.41\%), confirming exception dominance.
91	Tier~2 \texttt{loop\_only} (85.63\%) improves 10.50pp over \texttt{no\_trace} ($p{<}0.0001$) but falls far short of Tier~1.
92	\paragraph{Rule-based baseline comparison.}
93	The strongest non-trivial regex heuristic (B4: exception class name matching) achieves 93.61\% accuracy (F1=0.876), trailing SFT \texttt{exception\_only} (99.83\%, F1=0.997) by 6.22pp (McNemar $p{<}0.001$).
94	The gap concentrates on caught-exception boundary cases: regex flags all exception events as failures, while SFT learns to distinguish caught exceptions (benign, inside \texttt{try/except}) from uncaught faults, correctly resolving 6/8 boundary samples (Appendix~\ref{sec:regex_baselines}).
95	Across trace formats, SFT consistently outperforms the best applicable regex, from +3.62pp (\texttt{no\_trace} over majority baseline) to +23.86pp (VOTA), with the largest gains on formats requiring semantic interpretation (Appendix~\ref{sec:regex_baselines}).
96	
97	\paragraph{Zero-shot and few-shot LLM baselines.}
98	Zero-shot prompting spans 51.0--93.5\% across four models (CodeLlama-13B: 51.01\%, Qwen-7B: 89.08\%, DeepSeek-6.7B: 90.59\%, Qwen-1.5B: 93.45\%), a 42.44pp range that SFT compresses to 0.56pp (99.33--99.89\%).
99	Zero-shot performance does not correlate with model size: Qwen-1.5B (93.45\%) outperforms both Qwen-7B (89.08\%) and CodeLlama-13B (51.01\%), indicating that pretraining data distribution, not capacity, determines zero-shot verdict ability.
100	CodeLlama-13B drops below the majority baseline (71.51\%), showing extreme fail bias (72.4\% of predictions are \texttt{fail}).
101	Three-shot in-context learning on Qwen-7B (90.84\%, fail recall = 80.53\%) improves only 1.76pp over zero-shot and still trails both the regex heuristic (93.61\%) and SFT by 8.99pp, confirming that a few examples cannot substitute for task-specific fine-tuning.
102	SFT normalizes this cross-architecture variance, closing a 6--49pp gap to ${\geq}$99.33\% across all models with 4,720 training samples (Appendix~\ref{sec:zeroshot_cross_model}).
103	
104	\subsection{Format Marker Ablation}
105	\label{sec:nomarker}
106	
107	The \texttt{exception\_only} format includes a \texttt{[No exception data in trace]} marker in all pass-class samples (regex baseline B5 exploits this for 99.33\% accuracy; Appendix~\ref{sec:regex_baselines}).
108	To quantify the marker's contribution, we retrain with all format markers removed (\texttt{nomarker} condition).
109	
110	Qwen-7B 3-seed mean: 97.65\% $\pm$ 0.96 (seeds 42/123/456: 96.55/98.32/98.07\%), a drop of 2.18pp from \texttt{exception\_only} (99.83\%).
111	Qwen-1.5B: 97.82\%, drop of 2.01pp.
112	The marker contribution (${\sim}$2pp) accounts for only ${\sim}$9\% of the total exception lift over \texttt{no\_trace} (24.70pp on 7B).
113	Exception events thus provide two signal layers that show no degradation at smaller scale: structural markers (${\sim}$2pp, regex-learnable) and semantic exception content (${\sim}$22pp, requiring SFT to distinguish caught from uncaught exceptions).
114	
115	\subsection{Information Density Decomposition}
116	\label{sec:density}
117	
118	The 17.65pp gap between \texttt{full\_trace} (81.76\%) and VOTA (99.41\%) decomposes via \texttt{full\_trace\_label\_only}, which retains the full trace but masks all trace tokens from the loss.
119	
120	\begin{table}[t]
121	\centering
122	\caption{Approximate information density decomposition: gradient dilution (${\sim}$26\%) vs.\ information overload (${\sim}$74\%).}
123	\label{tab:density}
124	\small
125	\begin{tabular}{lccc}
126	\toprule
127	\textbf{Condition} & \textbf{Acc (\%)} & \textbf{$\Delta$ vs.\ full\_trace} & \textbf{Gap explained} \\
128	\midrule
129	full\_trace & 81.76 & --- & --- \\
130	label\_only & 86.22 & +4.46pp & 26\% \\
131	VOTA & 99.41 & +17.65pp & 100\% \\
132	\bottomrule
133	\end{tabular}
134	\end{table}
135	
136	Gradient dilution accounts for approximately 26\% of the gap (+4.46pp, $p{<}0.0001$, bootstrap 95\% CI $[{+}2.35, {+}6.55]$): when the model no longer wastes gradient updates on predicting trace tokens, accuracy improves even with identical input.
137	The remaining ${\sim}$74\% (+13.19pp) reflects information overload at inference: the model receives thousands of irrelevant trace lines that compete for attention with the diagnostic signal, regardless of loss design.
138	This asymmetry implies that trace compression methods should prioritize \emph{content selection} (removing irrelevant lines) over \emph{loss engineering} (masking non-target tokens), as the larger bottleneck is what the model sees, not how it is trained.
139	The two factors may interact, so this decomposition is approximate.
140	
141	\subsection{Additional Analyses}
142	\label{sec:additional}
143	
144	\paragraph{Trace length ablation.}
145	\label{sec:trace_length}
146	Varying the head-truncated trace token budget (256--no limit) on Qwen-7B yields accuracy in a narrow 77.2\%--81.8\% band with a non-monotonic pattern: 1024-token prefixes (77.23\%) underperform 512-token prefixes (80.42\%, $p{=}0.002$), because mid-length prefixes retain enough irrelevant content to mislead the model while discarding diagnostic events near the trace terminus (Appendix~\ref{sec:trace_length_full}).
147	This non-monotonicity is specific to head-truncation; under tail-truncation, accuracy increases monotonically for two of three models (Table~\ref{tab:tail_cross_model} in Appendix), with only DeepSeek showing a mild architecture-specific reversal at tail-1024$\to$tail-2048 ($-$1.5pp).
148	
149	\paragraph{Truncation direction and budget curve.}
150	Tail-truncation (retaining the last $k$ tokens) dramatically outperforms head-truncation: among the three models with complete data, tail-2048 exceeds head-2048 by 15.5--22.6pp, with the gap widening at smaller scale (Qwen-1.5B: +22.6pp vs.\ Qwen-7B: +15.5pp; Appendix~\ref{sec:trace_length_full}, Table~\ref{tab:head_vs_tail}).
151	All four models' head-2048 accuracies converge into a narrow 75.3--81.8\% band (6.5pp), comparable to the tail-256 band (72.6--78.9\%, 6.3pp), indicating that signal-poor conditions produce a shared performance floor regardless of scale or architecture.
152	
153	A cross-model budget sweep across four models and three architecture families reveals a sharp phase transition at 256$\to$512 tail tokens: all four models jump +14.7--23.0pp in a single budget doubling, crossing from near-baseline (${\sim}$73--79\%) to near-ceiling (${\sim}$94--98\%).
154	The threshold aligns with the typical exception traceback length (${\sim}$500 tokens): below it, the diagnostic event is truncated; above it, the event is captured regardless of architecture or scale.
155	Beyond 512 tokens, accuracy converges further; where tail-1024 data is available, three models reach a 96.5--96.6\% band, eliminating the 6.3pp cross-model spread observed at tail-256 (Table~\ref{tab:tail_cross_model}).
156	\texttt{tail\_2048} captures 95--98\% of \texttt{exception\_only}'s accuracy across all completed configurations.
157	The residual 2--5pp gap confirms that semantic extraction (identifying exception type and message) still outperforms positional extraction (retaining a fixed window containing non-diagnostic lines).
158	
159	\paragraph{Calibration.}
160	\label{sec:calibration}
161	Calibration mirrors the tier hierarchy: \texttt{exception\_only} ECE = 0.0027 vs.\ \texttt{no\_trace} ECE = 0.171, a 63$\times$ gap (Appendix~\ref{sec:calibration_full}).
162	
163	\paragraph{Error orthogonality.}
164	\texttt{exception\_only}'s 2 errors have zero overlap with all other conditions' error sets (Jaccard = 0.000), confirming it operates on an independent signal dimension (Appendix~\ref{sec:error_overlap}).
165	
166	\paragraph{Exception type breakdown.}
167	A per-exception-type breakdown (Appendix~\ref{sec:exception_type}) confirms that all standard exception types achieve 100\% accuracy; the only failures arise from \texttt{GeneratorExit}, a benign \texttt{BaseException} subclass.
168	
169	\paragraph{Cross-dataset generalization.}
170	\label{sec:debugbench}
171	On DebugBench \citep{tian2024debugbench} ($N{=}426$), the ranking is preserved: \texttt{exception\_only} 100\%, VOTA 99.77\%, \texttt{no\_trace} 96.71\%; narrow margins reflect a ceiling effect from structurally distinctive mutations (Appendix~\ref{sec:debugbench_full}).
172	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "8d7818f2-40d5-4194-85fc-0080ee743d22",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "0a43c5f1-35cd-4699-af1a-9625944e29c3",
  "sourceToolAssistantUUID": "8d7818f2-40d5-4194-85fc-0080ee743d22",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 32 · 2026-05-18T12:31:58.955Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Eon21W3L2Ue7iFAq69k2Tg`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0a43c5f1-35cd-4699-af1a-9625944e29c3",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3D5J4Pqop5eeSGCeF8",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "be0c2f7d-076c-4285-89de-c3801369dfdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012hjps1w9Rb822MA64WuN7m",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4363,
      "cache_read_input_tokens": 44956,
      "output_tokens": 157,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 4363
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 157,
          "cache_read_input_tokens": 44956,
          "cache_creation_input_tokens": 4363,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 4363,
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

_source line 33 · 2026-05-18T12:31:58.961Z_

<details><summary>↩ Tool result · `toolu_01Eon21W3L2Ue7iFAq69k2Tg`</summary>

```text
1	\section{Discussion}
2	
3	Verdict prediction is fundamentally fault detection: the model must determine whether execution deviated from expected behavior.
4	Exception events succeed because they are the runtime's primary fault indicator.
5	When Python raises an unhandled exception, it records exactly what went wrong (the error type), where it happened (the stack frame), and why (the error message).
6	This is precisely the information needed for a pass/fail decision, packaged in a compact, self-contained format.
7	Non-exception trace components (variable states, loop iterations, line-by-line control flow) record \emph{how} the program ran, not \emph{whether} it failed, and dilute the model's attention without providing complementary diagnostic information.
8	
9	This mechanistic account explains three key results.
10	First, adding trace information beyond exceptions actively \emph{hurts} (VOTA $<$ \texttt{exception\_only}, Table~\ref{tab:ablation}), because non-diagnostic content competes for attention.
11	Second, a budget sweep across four models and three architecture families reveals a sharp phase transition at 256$\to$512 tail tokens (+14.7--23.0pp) that aligns with the typical exception traceback length (${\sim}$500 tokens; \S\ref{sec:trace_length}).
12	Below this threshold, all models perform at or near the \texttt{no\_trace} baseline; above it, they converge into a tight accuracy band regardless of scale or architecture.
13	\texttt{tail\_2048} captures 95--98\% of \texttt{exception\_only}'s accuracy across all completed configurations.
14	This binary pattern confirms that the diagnostic signal is spatially concentrated rather than distributed: Python's error propagation records exceptions near the trace terminus, and a single budget doubling suffices to capture or miss them entirely.
15	Third, the 6.22pp SFT advantage over the best regex baseline concentrates on caught-exception boundary cases (Appendix~\ref{sec:regex_baselines}), confirming the model learns to distinguish \emph{whether an exception terminated execution} rather than merely detecting exception presence.
16	The 0.56pp cross-model exception gap (Appendix~\ref{sec:robustness_analysis}) and the format-collapse nature of the DeepSeek outlier (Appendix~\ref{sec:training_dynamics}) further support that the signal, not the model, is the binding constraint.
17	
18	\paragraph{Why exception\_only outperforms ae\_only.}
19	Although \texttt{ae\_only} achieves 99.92\% on seed 42, it is a strict superset of the exception signal: assertion-point comparisons include the exception event (when present) plus additional information such as fallback local variable states.
20	Multi-seed evaluation reveals that this extra content introduces noise: \texttt{ae\_only} achieves 99.64\% mean accuracy ($\pm$0.49, seeds 42/123/456) while \texttt{exception\_only} achieves 99.83\% ($\pm$0.00).
21	The zero-variance result for \texttt{exception\_only} indicates that it captures a minimal sufficient signal (the compact exception event), while \texttt{ae\_only}'s additional components (fallback locals, assertion formatting) occasionally mislead the model, manifesting as seed-dependent variance ($\sigma{=}$0.49pp).
22	Attention analysis on representative samples confirms this interpretation: within exception events, the error type and location markers receive 5--10$\times$ higher per-token attention than the verbose locals context (module paths, imported objects), suggesting the model learns to focus on diagnostic signals rather than incidental runtime state.
23	Thus \texttt{exception\_only} is both more precise and more stable than its superset.
24	
25	\paragraph{SFT vs.\ regex incremental analysis.}
26	The gap between B5 (format marker, 99.33\%) and SFT \texttt{exception\_only} (99.83\%) isolates the value of learned semantic understanding (McNemar $p{=}0.041$, Table~\ref{tab:regex}).
27	Among 8 test samples where pass-labeled code triggers exceptions (from 2 distinct problems), the SFT model correctly classifies 6 (all from MBPP/113, a try/except ValueError pattern) while B5 misclassifies all 8. The 2 remaining errors (HumanEval/95, GeneratorExit) are misclassified by most training configurations (see Appendix~\ref{sec:irreducible}). At the problem level, SFT handles 1/2 exception-type edge cases vs B5's 0/2.
28	This confirms that SFT learns a genuine semantic boundary (distinguishing caught from uncaught exceptions) rather than merely detecting exception presence or format markers.
29	
30	\paragraph{Why zero-shot and few-shot prompting fall short.}
31	Zero-shot prompting spans 51.0--93.5\% across four models, with cross-architecture variance (42.44pp) dwarfing the SFT range (0.56pp).
32	The failure is not in exception detection but in verdict calibration: the model recognizes that an exception occurred but cannot reliably determine whether it terminated execution or was caught by a \texttt{try/except} block.
33	Performance does not correlate with model size: Qwen-1.5B (93.45\%) outperforms Qwen-7B (89.08\%) and CodeLlama-13B (51.01\%, extreme fail bias with 72.4\% of predictions as \texttt{fail}).
34	Within the Qwen family, the 1.5B model's higher zero-shot accuracy likely reflects consistent code training data quality across scales: the smaller model already understands exception format, but both lack the verdict-specific calibration that SFT provides (SFT gap: 6.38pp for 1.5B vs.\ 10.75pp for 7B).
35	Three-shot in-context learning (90.84\% on Qwen-7B, fail recall = 80.53\%) improves fail recall by 13.57pp over zero-shot but still trails SFT by 8.99pp: three examples cannot cover the diversity of caught-exception patterns in the training distribution.
36	SFT normalizes this cross-architecture variance by grounding exception patterns in task-specific verdict labels, compressing a 42.44pp zero-shot range to 0.56pp.
37	
38	\paragraph{Format marker sensitivity.}
39	The B5 baseline (Appendix~\ref{sec:regex_baselines}) achieves 99.33\% by exploiting a deterministic format marker (\texttt{[No exception data in trace]}) present in all pass samples.
40	This near-ceiling performance from a trivial pattern raises a concern: does SFT also learn this shortcut?
41	The answer is partially yes: the format marker correlates perfectly with the pass class. But the SFT model additionally handles the 8 boundary samples where exceptions occur in passing code, achieving 6/8 correct vs.\ B5's 0/8.
42	A \emph{nomarker} ablation (\S\ref{sec:nomarker}) confirms genuine exception semantics: Qwen-7B 3-seed mean 97.65\%$\pm$0.96 and Qwen-1.5B 97.82\%, a drop of only ${\sim}$2pp.
43	The marker contribution (${\sim}$9\% of total lift) is small relative to semantic content (${\sim}$91\%), confirming that SFT learns exception semantics rather than format shortcuts.
44	Both signal layers show comparable accuracy across the two tested scales (1.5B and 7B produce 97.8\% and 97.7\% nomarker accuracy, respectively).
45	
46	\paragraph{Near-perfect floor, not hard ceiling.}
47	Samples 901 and 905 (HumanEval/95, \texttt{check\_dict\_case}) are misclassified by most configurations: Qwen-7B (3 seeds), Qwen-1.5B, and CodeLlama-13B seed 42/456 all produce exactly these 2 errors.
48	The root cause is deterministic: Python's \texttt{all()} raises \texttt{GeneratorExit} (a \texttt{BaseException} subclass) during generator short-circuit, recorded as \texttt{[ERROR]} despite the test passing.
49	However, CodeLlama-13B seed 123 achieves 100\% (0/1190 errors), correctly classifying both samples.
50	This confirms that 99.83\% is a near-perfect \emph{floor} (the convergence attractor for most initializations) rather than a hard data limitation: the representation supports perfect accuracy, though most LoRA initializations converge to the same 2-error basin.
51	On this task, exception-only accuracy is \emph{signal-limited} rather than \emph{capacity-limited}: three architecture families spanning 1.5B to 13B converge on the same floor, while \texttt{no\_trace} shows monotonic scale dependence (67.3\% $\to$ 75.1\% $\to$ 76.5\%).
52	
53	\paragraph{Tokenizer efficiency and training dynamics.}
54	CodeLlama's tokenizer produces ${\sim}$20\% more tokens than Qwen's on identical trace inputs (mean 1{,}174 vs.\ 978 tokens), reducing the verdict label's share of the training loss to ${\sim}$0.085\%.
55	Under standard next-token loss, the model allocates the vast majority of gradient updates to predicting trace tokens rather than learning the verdict classification boundary.
56	This tokenizer-driven dilution is invisible at short trace budgets (tail-256/512), where CodeLlama performs comparably to other models (77.9\% and 97.5\%, respectively), but is expected to compound at longer budgets (1{,}024+ tokens) where trace tokens dominate the loss landscape.
57	A label-only loss variant (computing loss only on the verdict token, masking all trace positions) addresses this by decoupling verdict learning from trace prediction; results for CodeLlama tail-1024/2048 under this regime are pending.
58	This finding highlights tokenizer efficiency as a previously overlooked variable in trace-based training: architectures with less efficient tokenizers require adapted training strategies (e.g., label-only loss) to prevent the diagnostic signal from being drowned by trace token prediction.
59	
60	\paragraph{Tier hierarchy: practical implications.}
61	The two-tier structure (Tier~1 ${\geq}$99\%; Tier~2 = 85.6\%) has direct engineering implications for trace-augmented systems.
62	First, it implies a \emph{diminishing returns} principle: once a Tier~1 signal is available, adding more trace information provides no benefit and may actively degrade performance through attention dilution.
63	Second, the hierarchy suggests a fallback design: systems should attempt Tier~1 extraction (exception events) and only resort to Tier~2 signals (loop compression) when no exception is raised. Even Tier~2 alone substantially outperforms no-trace baselines (+10.50pp).
64	Third, the minimal token footprint of Tier~1 signals (median 150 tokens vs.\ ${\sim}$1{,}900 for VOTA post-truncation) makes them viable for deployment in token-constrained settings (e.g., real-time CI pipelines, mobile inference).
65	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "be0c2f7d-076c-4285-89de-c3801369dfdd",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "1f95f9d3-5e52-47ad-80ac-27de95a35526",
  "sourceToolAssistantUUID": "be0c2f7d-076c-4285-89de-c3801369dfdd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 34 · 2026-05-18T12:32:04.172Z_

<details open><summary>🔧 Tool call — Read · `toolu_01AEfCx94nekfMXuRarmfeaB`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1f95f9d3-5e52-47ad-80ac-27de95a35526",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3DWy9eTSTSLnYpdG8C",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a3e79b1f-df2b-4286-b9c8-7efb59c778d6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015B1Xxn2H19XCB7WCtNsRdd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8418,
      "cache_read_input_tokens": 49319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8418,
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

_source line 35 · 2026-05-18T12:32:04.573Z_

<details><summary>↩ Tool result · `toolu_01AEfCx94nekfMXuRarmfeaB`</summary>

```text
1	\section{Per-Class Performance Breakdown}
2	\label{sec:per_class}
3	
4	Table~\ref{tab:per_class} reports per-class precision, recall, and F1 for all experimental conditions.
5	
6	\begin{table*}[t]
7	\centering
8	\caption{Per-class precision, recall, and F1 for all experimental conditions (seed 42). DeepSeek VOTA achieves 100\% fail precision but only 45.4\% fail recall, indicating systematic bias toward predicting \texttt{pass}. DeepSeek \texttt{exception\_only} seed 42 achieves 100\% fail recall, but seed 123 drops to 70.5\% (see Table~\ref{tab:full_deepseek}).}
9	\label{tab:per_class}
10	\small
11	\begin{tabular}{llccccccc}
12	\toprule
13	\textbf{Condition} & \textbf{Model} & \textbf{Acc} & \textbf{Pass P} & \textbf{Pass R} & \textbf{Pass F1} & \textbf{Fail P} & \textbf{Fail R} & \textbf{Fail F1} \\
14	\midrule
15	No Trace          & Qwen-2.5-7B & 75.13 & 87.76 & 75.79 & 81.34 & 54.73 & 73.45 & 62.72 \\
16	Full Trace        & Qwen-2.5-7B & 81.76 & 87.74 & 86.60 & 87.17 & 67.43 & 69.62 & 68.51 \\
17	Full Trace (LO)   & Qwen-2.5-7B & 86.22 & 88.21 & 93.18 & 90.63 & 80.07 & 68.73 & 73.97 \\
18	VOTA              & Qwen-2.5-7B & 99.41 & 100.00 & 99.18 & 99.59 & 97.98 & 100.00 & 98.98 \\
19	Exception Only    & Qwen-2.5-7B & 99.83 & 100.00 & 99.76 & 99.88 & 99.41 & 100.00 & 99.71 \\
20	AE Only           & Qwen-2.5-7B & 99.92 & 100.00 & 99.88 & 99.94 & 99.71 & 100.00 & 99.85 \\
21	Loop Only         & Qwen-2.5-7B & 85.63 & 92.39 & 87.07 & 89.66 & 71.65 & 82.01 & 76.48 \\
22	VOTA\_no\_ae       & Qwen-2.5-7B & 99.41 & 99.88 & 99.29 & 99.59 & 98.26 & 99.71 & 98.98 \\
23	\midrule
24	No Trace          & DeepSeek-6.7B & 73.36 & 81.71 & 80.85 & 81.28 & 53.16 & 54.57 & 53.86 \\
25	Full Trace        & DeepSeek-6.7B & 79.16 & 85.70 & 85.10 & 85.40 & 63.20 & 64.30 & 63.70 \\
26	VOTA              & DeepSeek-6.7B & 84.45 & 82.14 & 100.00 & 90.20 & 100.00 & 45.40 & 62.50 \\
27	Exception Only    & DeepSeek-6.7B & 99.33 & 100.00 & 99.06 & 99.53 & 97.69 & 100.00 & 98.83 \\
28	\bottomrule
29	\end{tabular}
30	\end{table*}
31	
32	%% ============================================================
33	\section{Training Details}
34	\label{sec:training_details}
35	
36	Table~\ref{tab:hyperparams} summarizes the training hyperparameters shared across all conditions.
37	All experiments use the HuggingFace TRL \texttt{SFTTrainer} with LoRA \citep{hu2022lora} applied to all linear layers.
38	
39	\begin{table}[t]
40	\centering
41	\caption{Training hyperparameters (shared across all conditions).}
42	\label{tab:hyperparams}
43	\small
44	\resizebox{\columnwidth}{!}{%
45	\begin{tabular}{ll}
46	\toprule
47	\textbf{Hyperparameter} & \textbf{Value} \\
48	\midrule
49	LoRA rank ($r$)            & 16 \\
50	LoRA alpha ($\alpha$)      & 32 \\
51	LoRA dropout               & 0.05 \\
52	LoRA target modules        & all linear layers \\
53	\midrule
54	Epochs                     & 3 \\
55	Per-device batch size       & 4 \\
56	Gradient accumulation steps & 8 \\
57	Effective batch size        & 32 \\
58	\midrule
59	Learning rate               & $2 \times 10^{-4}$ \\
60	LR scheduler                & linear decay \\
61	Warmup ratio                & 0.1 \\
62	Weight decay                & 0.01 \\
63	\midrule
64	Max sequence length         & 2048 tokens \\
65	Primary seed                & 42 \\
66	Robustness seeds            & 123, 456 \\
67	\midrule
68	Hardware                    & 1$\times$ RTX PRO 6000 Blackwell (96\,GB VRAM) \\
69	Framework                   & HuggingFace TRL SFTTrainer \\
70	\bottomrule
71	\end{tabular}%
72	}
73	\end{table}
74	
75	Table~\ref{tab:train_time} reports per-condition training wall-clock times.
76	Conditions with longer trace inputs (e.g., \texttt{full\_trace}, VOTA) require proportionally more training time due to increased sequence lengths.
77	
78	\begin{table}[t]
79	\centering
80	\caption{Training wall-clock time per condition on a single RTX PRO 6000 Blackwell GPU. Where multiple seeds were run, individual times are listed.}
81	\label{tab:train_time}
82	\small
83	\begin{tabular}{llr}
84	\toprule
85	\textbf{Condition} & \textbf{Seed(s)} & \textbf{Time (h)} \\
86	\midrule
87	no\_trace       & 42         & ${\sim}$0.5 \\
88	full\_trace     & 42         & ${\sim}$2.2 \\
89	label\_only     & 42         & ${\sim}$2.2 \\
90	VOTA                     & 42         & ${\sim}$2.3 \\
91	exception\_only & 42         & ${\sim}$2.1 \\
92	exception\_only & 123        & ${\sim}$2.1 \\
93	exception\_only & 456        & ${\sim}$1.3 \\
94	ae\_only        & 42         & ${\sim}$1.8 \\
95	loop\_only      & 42         & ${\sim}$2.1 \\
96	VOTA\_no\_ae    & 42         & ${\sim}$1.8 \\
97	\bottomrule
98	\end{tabular}
99	\end{table}
100	
101	%% ============================================================
102	\section{VOTA Trace Examples}
103	\label{sec:vota_examples}
104	
105	We provide two representative VOTA trace examples illustrating the fail and pass cases.
106	In the fail case, the exception event provides an unambiguous fault signal.
107	In the pass case, the absence of an exception event combined with a matching assertion point confirms correct execution.
108	
109	\paragraph{Fail example.}
110	A \texttt{ZeroDivisionError} triggers an \texttt{[ERROR]} event, providing a direct fault signal that is sufficient for the model to predict \texttt{fail}.
111	
112	\begin{small}
113	\begin{verbatim}
114	## Function
115	def divide(a, b):
116	    return a / b
117	
118	## Test Input
119	divide(1, 0)
120	
121	## Expected Output
122	inf
123	
124	## VOTA Trace
125	[ERROR] ZeroDivisionError: division by zero
126	
127	## Verdict
128	fail
129	\end{verbatim}
130	\end{small}
131	
132	\paragraph{Pass example.}
133	No exception is raised, and the assertion point confirms that the actual output matches the expected value.
134	
135	\begin{small}
136	\begin{verbatim}
137	## Function
138	def add(a, b):
139	    return a + b
140	
141	## Test Input
142	add(2, 3)
143	
144	## Expected Output
145	5
146	
147	## VOTA Trace
148	[LOOP] No loops detected.
149	[ASSERT] actual=5, expected=5
150	
151	## Verdict
152	pass
153	\end{verbatim}
154	\end{small}
155	
156	These examples illustrate the core asymmetry exploited by the \texttt{exception\_only} condition: fail cases produce an explicit \texttt{[ERROR]} event, while pass cases are characterized by its absence.
157	This binary signal (presence vs.\ absence of an exception) is sufficient for near-perfect verdict prediction.
158	
159	%% ============================================================
160	\section{Full Experimental Results}
161	\label{sec:full_results}
162	
163	Tables~\ref{tab:full_qwen} and \ref{tab:full_deepseek} report the complete experimental results across all conditions, models, and seeds.
164	
165	\begin{table}[t]
166	\centering
167	\caption{Full results for Qwen-2.5-Coder-7B across all conditions and seeds. Conditions with a single seed report no variance. \texttt{exception\_only} achieves 99.83\% across all three seeds ($\sigma{=}$0). \texttt{ae\_only} achieves 99.64\% mean ($\pm$0.49; seed 123 at 99.08\% is the outlier).}
168	\label{tab:full_qwen}
169	\small
170	\resizebox{\columnwidth}{!}{%
171	\begin{tabular}{lcccc}
172	\toprule
173	\textbf{Condition} & \textbf{S42} & \textbf{S123} & \textbf{S456} & \textbf{Mean $\pm$ Std} \\
174	\midrule
175	exception\_only & 99.83 & 99.83 & 99.83 & 99.83 $\pm$ 0.00 \\
176	ae\_only        & 99.92 & 99.08 & 99.92 & 99.64 $\pm$ 0.49 \\
177	VOTA                     & 99.41 & ---   & ---   & --- \\
178	VOTA\_no\_ae    & 99.41 & ---   & ---   & --- \\
179	label\_only     & 86.22 & ---   & ---   & --- \\
180	loop\_only      & 85.63 & ---   & ---   & --- \\
181	full\_trace     & 81.76 & ---   & ---   & --- \\
182	no\_trace       & 75.13 & ---   & ---   & --- \\
183	\bottomrule
184	\end{tabular}%
185	}
186	\end{table}
187	
188	\begin{table}[t]
189	\centering
190	\caption{Full results for DeepSeek-Coder-6.7B across all conditions and seeds. \texttt{exception\_only} shows bimodal seed behavior: seeds 42 and 456 achieve 99.33\%, while seed 123 yields 91.09\% (LoRA initialization outlier, fail recall = 70.5\%).}
191	\label{tab:full_deepseek}
192	\small
193	\resizebox{\columnwidth}{!}{%
194	\begin{tabular}{llcc}
195	\toprule
196	\textbf{Condition} & \textbf{Seed} & \textbf{Accuracy} & \textbf{Notes} \\
197	\midrule
198	exception\_only & 42  & 99.33 & epoch 1: 99.83 \\
199	exception\_only & 456 & 99.33 & CI [98.82, 99.75] \\
200	exception\_only & 123 & 91.09 & fail recall = 70.5\%; CI [89.40, 92.60] \\
201	\midrule
202	VOTA                     & 42  & 84.45 & \\
203	no\_trace       & 42  & 73.36 & \\
204	full\_trace     & 42  & 79.16 & CI [76.80, 81.30] \\
205	\bottomrule
206	\end{tabular}%
207	}
208	\end{table}
209	
210	%% ============================================================
211	\section{Tokenizer and Truncation Analysis}
212	\label{sec:tokenizer_analysis}
213	
214	The VOTA cross-model gap (14.96pp, Table~\ref{tab:cross_model}; confounded by tokenizer-driven truncation; 91.7\% of DeepSeek training samples were affected) is driven by a training-time truncation asymmetry.
215	The DeepSeek tokenizer averages 2{,}626 tokens per VOTA sample versus 1{,}929 for Qwen, causing 91.7\% of DeepSeek VOTA training samples to exceed the 2{,}048-token context window.
216	The training framework preserves the verdict label but truncates trace content, so the model trains with incomplete diagnostic information for the majority of samples.
217	
218	A post-hoc group analysis provides directional evidence: partitioning DeepSeek VOTA test samples by whether their training-set counterparts exceeded the context window, intact samples ($N{=}99$) achieve 100\% accuracy while truncated samples ($N{=}1{,}091$) achieve 83.04\% (95\% CI [80.75\%, 85.24\%]; Fisher exact $p{<}0.001$), with all 185 errors concentrated in the fail class (fail recall = 31.23\%).
219	Per-class analysis (Table~\ref{tab:per_class}) confirms that DeepSeek VOTA achieves 100\% fail precision but only 45.43\% fail recall, systematically defaulting to \texttt{pass}---in contrast to Qwen VOTA, which achieves 100\% fail recall.
220	
221	Seed robustness diverges across models: Qwen \texttt{exception\_only} produces identical 99.83\% across all three seeds ($\sigma{=}0$), while DeepSeek shows bimodal behavior: seeds 42 and 456 achieve 99.33\% (fail recall = 100\%), seed 123 yields 91.09\% (fail recall = 70.5\%).
222	Because \texttt{exception\_only} test inputs contain 48.99\% duplicates (607 unique of 1,190; \S\ref{sec:dataset}), CIs assume $n{=}1{,}190$ independent trials; under deduplication ($n{=}607$), Qwen's accuracy is 99.67\% (Wilson CI [98.81, 99.91]).
223	
224	%% ============================================================
225	\section{Irreducible Sample Analysis}
226	\label{sec:irreducible}
227	
228	The \texttt{exception\_only} condition with Qwen-2.5-Coder-7B misclassifies exactly 2 out of 1,190 test samples across all three seeds (42, 123, 456), with 100\% overlap across seeds.
229	Both samples (IDs 901 and 905) share the following characteristics:
230	
231	\begin{itemize}
232	\item \textbf{Function:} \texttt{check\_dict\_case} (HumanEval/95)---a function that checks whether all dictionary keys are uniformly upper-case or lower-case strings.
233	\item \textbf{Ground-truth label:} \texttt{pass}.
234	\item \textbf{Predicted label:} \texttt{fail} (false negative).
235	\item \textbf{Cross-seed consistency:} Both samples are misclassified identically by all three seeds, indicating a systematic rather than stochastic error.
236	\end{itemize}
237	
238	Manual inspection reveals the root cause: \texttt{check\_dict\_case} uses \texttt{all()} over a generator expression, and Python's \texttt{all()} short-circuits on the first \texttt{True} value, raising \texttt{GeneratorExit} to terminate the generator.
239	Because \texttt{GeneratorExit} is a \texttt{BaseException} subclass, the tracer records it as seven \texttt{[ERROR] GeneratorExit} lines---even though the function executes correctly and the test passes.
240	The model observes these spurious error markers and reasonably but incorrectly predicts \texttt{fail}.
241	This is not a model failure but a representation ambiguity: the \texttt{exception\_only} format cannot distinguish genuine exceptions from benign \texttt{BaseException} subclasses triggered by Python's iterator protocol.
242	
243	Most configurations converge to these same 2 errors: Qwen-1.5B, Qwen-7B (3 seeds), CodeLlama-13B (seeds 42/456), and DeepSeek-6.7B (seeds 42/456) all produce error set $\{901, 905\}$.
244	However, CodeLlama-13B seed 123 achieves 100\% accuracy (0/1190 errors), correctly classifying both samples.
245	This demonstrates that 99.83\% is a near-perfect \emph{floor} (the convergence attractor for most LoRA initializations) rather than a hard data ceiling: the representation supports perfect accuracy, but most initializations converge to the same 2-error basin.
246	The practical implication is that these errors are high-probability convergence artifacts addressable through seed selection or ensemble methods, not fundamental limitations of the exception-based representation.
247	
248	%% ============================================================
249	\section{Exception Type Accuracy Breakdown}
250	\label{sec:exception_type}
251	
252	Table~\ref{tab:exception_type} reports \texttt{exception\_only} accuracy stratified by exception type on Qwen-2.5-7B (seed=42, $N{=}1{,}190$).
253	All standard exception types (\texttt{TypeError}, \texttt{ValueError}, \texttt{IndexError}, etc.) achieve 100\% accuracy.
254	The only misclassifications arise from \texttt{GeneratorExit}, a \texttt{BaseException} subclass that is not an \texttt{Exception}---it is raised by Python's iterator protocol during generator short-circuiting, not by actual program errors.
255	
256	\begin{table}[t]
257	\centering
258	\caption{Exception type accuracy breakdown for \texttt{exception\_only} (Qwen-7B, seed=42). All true error types achieve 100\%. The only failures come from \texttt{GeneratorExit} (a \texttt{BaseException} subclass, not an \texttt{Exception}), which appears in 2 passing samples.}
259	\label{tab:exception_type}
260	\small
261	\begin{tabular}{lcc}
262	\toprule
263	\textbf{Exception Type} & \textbf{Samples} & \textbf{Accuracy} \\
264	\midrule
265	TypeError & 96 & 100\% \\
266	ValueError & 62 & 100\% \\
267	IndexError & 41 & 100\% \\
268	KeyError & 28 & 100\% \\
269	AttributeError & 19 & 100\% \\
270	AssertionError & 15 & 100\% \\
271	RecursionError & 12 & 100\% \\
272	Other Exception & 66 & 100\% \\
273	\midrule
274	GeneratorExit (BaseException) & 2 & 0\% \\
275	No exception (pass class) & 849 & 100\% \\
276	\bottomrule
277	\end{tabular}
278	\end{table}
279	
280	This confirms that the model has learned a clean decision boundary: any true \texttt{Exception} subclass in the trace implies failure.
281	The \texttt{GeneratorExit} case represents a semantic ambiguity in the trace format rather than a model failure, as discussed in \S\ref{sec:irreducible}.
282	
283	%% ============================================================
284	\section{Trace Length Ablation}
285	\label{sec:trace_length_full}
286	
287	To test whether the \texttt{full\_trace} performance gap is caused by input truncation at training time, we vary the maximum trace token budget on Qwen-2.5-7B (seed=42) while keeping all other hyperparameters fixed.
288	
289	\begin{table}[t]
290	\centering
291	\caption{Trace length and truncation direction ablation on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). Head = standard left-truncation (retain first $k$ tokens); Tail = retain last $k$ tokens. Per-condition bootstrap 95\% CIs ($B{=}10{,}000$).}
292	\label{tab:trace_length}
293	\small
294	\begin{tabular}{llcc}
295	\toprule
296	\textbf{Direction} & \textbf{Max Tokens} & \textbf{Acc (\%)} & \textbf{95\% CI} \\
297	\midrule
298	Head & 256  & 78.82 & [76.4, 81.0] \\
299	Head & 512  & 80.42 & [78.2, 82.6] \\
300	Head & 1024 & 77.23 & [74.9, 79.6] \\
301	Head & no\_limit ($\infty$) & 81.76 & [79.7, 83.9] \\
302	\midrule
303	Tail & 256  & 77.48 & --- \\
304	Tail & 512  & 93.61 & --- \\
305	Tail & 1024 & 96.47 & --- \\
306	Tail & 2048 & 97.31 & --- \\
307	\bottomrule
308	\end{tabular}
309	\end{table}
310	
311	\begin{figure}[t]
312	\centering
313	\includegraphics[width=\columnwidth]{budget_curve}
314	\caption{Accuracy as a function of token budget and truncation direction (Qwen-2.5-7B, $N{=}1{,}190$). Tail-truncation (keeping last $k$ tokens) monotonically improves beyond 256 tokens and consistently outperforms head-truncation by 13--19pp at budgets ${\geq}$512. The flat head-truncation curve (77--82\%) contrasts with the steep tail-truncation rise, confirming that diagnostic signal is localized near trace end. Dashed lines show \texttt{exception\_only} (99.83\%) and \texttt{no\_trace} (75.13\%) as upper and lower bounds. Tail-256 (${\approx}$ \texttt{no\_trace}) indicates the signal window begins approximately 256 tokens from the trace terminus.}
315	\label{fig:trace_length}
316	\end{figure}
317	
318	As shown in Table~\ref{tab:trace_length} and Figure~\ref{fig:trace_length}, all four trace length conditions fall within a 5pp range (77.2\%--81.8\%).
319	To quantify the reliability of the observed differences, Table~\ref{tab:trace_length_pairwise} reports paired bootstrap comparisons ($B{=}10{,}000$, seed=42) across all condition pairs.
320	
321	\begin{table}[t]
322	\centering
323	\caption{Pairwise paired bootstrap comparisons for trace length ablation ($B{=}10{,}000$, seed=42). $\Delta$ = accuracy difference between the two conditions (first $-$ second in the budget group; condition $-$ baseline in the other groups). **$p{<}0.01$; ***$p{<}0.001$.}
324	\label{tab:trace_length_pairwise}
325	\small
326	\resizebox{\columnwidth}{!}{%
327	\begin{tabular}{llccc}
328	\toprule
329	& \textbf{Comparison} & \textbf{$\Delta$ (pp)} & \textbf{95\% CI} & \textbf{$p$-value} \\
330	\midrule
331	\multirow{4}{*}{\rotatebox{90}{\scriptsize Budget}}
332	& 512 vs.\ 256           & $+$1.60  & [$-$0.34, $+$3.53]   & 0.117 \\
333	& 1024 vs.\ 512          & $-$3.19  & [$-$5.29, $-$1.09]   & 0.002** \\
334	& no\_limit vs.\ 1024    & $+$4.54  & [$+$2.52, $+$6.55]   & ${<}$0.001*** \\
335	& no\_limit vs.\ 256     & $+$2.94  & [$+$0.84, $+$5.04]   & 0.006** \\
336	\midrule
337	\multirow{4}{*}{\rotatebox{90}{\scriptsize vs.\ no\_trace}}
338	& 256 $-$ no\_trace       & $+$3.70  & [$+$1.43, $+$6.05]   & 0.002** \\
339	& 512 $-$ no\_trace       & $+$5.29  & [$+$3.03, $+$7.56]   & ${<}$0.001*** \\
340	& 1024 $-$ no\_trace      & $+$2.10  & [$-$0.17, $+$4.37]   & 0.078 \\
341	& no\_limit $-$ no\_trace & $+$6.64  & [$+$4.37, $+$8.99]   & ${<}$0.001*** \\
342	\midrule
343	\multirow{4}{*}{\rotatebox{90}{\scriptsize vs.\ exc.}}
344	& 256 $-$ exc\_only       & $-$21.01 & [$-$23.45, $-$18.74] & ${<}$0.001*** \\
345	& 512 $-$ exc\_only       & $-$19.41 & [$-$21.76, $-$17.14] & ${<}$0.001*** \\
346	& 1024 $-$ exc\_only      & $-$22.61 & [$-$25.04, $-$20.25] & ${<}$0.001*** \\
347	& no\_limit $-$ exc\_only & $-$18.07 & [$-$20.34, $-$15.88] & ${<}$0.001*** \\
348	\bottomrule
349	\end{tabular}%
350	}
351	\end{table}
352	
353	\paragraph{Non-monotonic pattern (head-truncation).}
354	Under head-truncation (retaining trace prefixes), the trend is non-monotonic: 512 tokens (80.42\%) slightly outperforms 256 tokens (78.82\%), but doubling to 1024 tokens \emph{decreases} accuracy to 77.23\%, a statistically significant 3.19pp drop ($p{=}0.002$, 95\% CI [$-$5.29, $-$1.09]).
355	The no-limit condition (81.76\%) recovers and significantly exceeds 1024 tokens ($p{<}0.001$), but 1024 tokens is not significantly better than \texttt{no\_trace} (75.13\%; $\Delta{=}{+}2.10$pp, $p{=}0.078$, 95\% CI [$-$0.17, $+$4.37]).
356	This non-monotonicity is specific to head-truncation: the 1024-token prefix retains enough irrelevant content to mislead the model while discarding diagnostic events that appear near the trace terminus.
357	Under tail-truncation, accuracy increases monotonically for Qwen-7B and Qwen-1.5B (Table~\ref{tab:tail_cross_model}); only DeepSeek-6.7B shows a mild $-$1.5pp decrease at tail-1024$\to$tail-2048, attributable to architecture-specific long-context sensitivity rather than a systematic mid-length pathology.
358	
359	\paragraph{Comparison to baselines.}
360	All four trace budget conditions significantly exceed \texttt{no\_trace} except 1024 tokens ($p{=}0.078$), confirming that raw trace content provides some signal but unreliably so.
361	The gap to \texttt{exception\_only} (99.83\%) is massive for every budget condition (18--23pp, all $p{<}0.001$), underscoring that even unlimited raw traces cannot substitute for targeted signal extraction.
362	The best full-trace condition (no\_limit, 81.76\%) still lags \texttt{exception\_only} by 18.07pp (95\% CI [$-$20.34, $-$15.88]).
363	
364	\paragraph{Interpretation.}
365	These results rule out input truncation as the primary explanation for the full-trace performance gap: even with unlimited tokens, the model cannot extract the diagnostic signal that VOTA's targeted compression provides.
366	The non-monotonic dip at 1024 tokens is consistent with a ``worst-of-both-worlds'' regime where the model receives enough noisy context to dilute the signal but not enough to compensate through broader coverage.
367	The result reinforces the information density interpretation (\S\ref{sec:density}): the gap between full traces and VOTA is driven by the \emph{content} of the trace (irrelevant lines diluting the diagnostic signal), not its \emph{length}.
368	In contrast, VOTA's compressed representation concentrates the diagnostic signal into fewer tokens, making it sensitive to truncation when those tokens are removed (\S\ref{sec:cross_model}).
369	
370	\paragraph{Truncation direction.}
371	Tail-truncation (retaining the last $k$ tokens) dramatically outperforms head-truncation: \texttt{tail\_2048} achieves 97.31\% vs.\ \texttt{head\_2048} (no\_limit) at 81.76\%, a 15.55pp improvement.
372	Even \texttt{tail\_512} (93.61\%) exceeds every head-truncation condition by over 11pp.
373	
374	However, \texttt{tail\_256} (77.48\%) performs at the \texttt{no\_trace} baseline level (75.13\%), indicating that the diagnostic signal does not reside in the very last trace lines.
375	The critical jump occurs between 256 and 512 tail tokens (+16.13pp), localizing the signal window to approximately 256--512 tokens from the trace terminus.
376	This is consistent with Python's execution model: exception tracebacks and assertion comparisons appear near the end of the trace but are preceded by the final function call frames, placing them typically 300--500 tokens from the terminus rather than at the absolute end.
377	
378	The 18.07pp gap from \texttt{full\_trace} to \texttt{exception\_only} decomposes as: 86\% positional concentration (recovered by tail-truncation at 2048 tokens) and 14\% residual content noise (the 2.52pp gap from \texttt{tail\_2048} to \texttt{exception\_only} that persists regardless of truncation direction).
379	The fact that \texttt{exception\_only} (99.83\%) still outperforms \texttt{tail\_2048} (97.31\%) confirms that semantic extraction (identifying the exception type and message) is superior to positional extraction (keeping a fixed window), because the model need not filter out non-diagnostic lines that happen to fall within the window.
380	
381	\paragraph{Cross-model budget curve.}
382	Table~\ref{tab:tail_cross_model} extends the tail-truncation analysis to a full budget sweep across four models spanning three architecture families and an 8.7$\times$ parameter range.
383	
384	\begin{table}[t]
385	\centering
386	\caption{Cross-model tail-truncation budget curve ($N{=}1{,}190$). A sharp phase transition occurs at 256$\to$512 tokens across all four models (+14.7--23.0pp), after which accuracy converges regardless of scale or architecture. $\downarrow$: non-monotonic decrease (DeepSeek only). $^\dag$CodeLlama tail-1024/2048 pending retraining with label-only loss (\S\ref{sec:tokenizer_analysis}).}
387	\label{tab:tail_cross_model}
388	\small
389	\resizebox{\columnwidth}{!}{%
390	\begin{tabular}{lccccc}
391	\toprule
392	\textbf{Model} & \textbf{tail-256} & \textbf{tail-512} & \textbf{tail-1024} & \textbf{tail-2048} & \textbf{exc\_only} \\
393	\midrule
394	Qwen-7B (7B) & 78.9 & 93.6 & 96.5 & 97.3 & 99.83 \\
395	DeepSeek (6.7B) & 76.4 & 93.9 & 96.5 & 95.0$\downarrow$ & 99.33 \\
396	CodeLlama (13B) & 77.9 & 97.5 & ---$^\dag$ & ---$^\dag$ & 99.89 \\
397	Qwen-1.5B (1.5B) & 72.6 & 95.6 & 96.6 & 97.9 & 99.83 \\
398	\bottomrule
399	\end{tabular}%
400	}
401	\end{table}
402	
403	\begin{table}[t]
404	\centering
405	\caption{Cross-model truncation direction comparison ($N{=}1{,}190$). Head-truncation retains the first 2,048 tokens; tail-truncation retains the last 2,048. All four models' head-2048 accuracies converge into a narrow 75.3--81.8\% band (6.5pp), comparable to the tail-256 signal-poor band (72.6--78.9\%, 6.3pp). $^\dag$CodeLlama tail-2048 pending retraining (\S\ref{sec:tokenizer_analysis}).}
406	\label{tab:head_vs_tail}
407	\small
408	\begin{tabular}{lccc}
409	\toprule
410	\textbf{Model} & \textbf{head-2048 (\%)} & \textbf{tail-2048 (\%)} & \textbf{Gap (pp)} \\
411	\midrule
412	Qwen-1.5B & 75.3 & 97.9 & +22.6 \\
413	DeepSeek-6.7B & 78.7 & 95.0 & +16.3 \\
414	CodeLlama-13B & 79.9 & ---$^\dag$ & ---$^\dag$ \\
415	Qwen-7B & 81.8 & 97.3 & +15.5 \\
416	\bottomrule
417	\end{tabular}
418	\end{table}
419	
420	Four patterns emerge from the budget curve.
421	\emph{Phase transition at 256$\to$512 tokens}: all four models jump +14.7--23.0pp (Qwen-7B +14.7, DeepSeek +17.5, CodeLlama +19.6, Qwen-1.5B +23.0), crossing from near-baseline to near-ceiling in a single budget doubling.
422	The threshold aligns with the typical exception traceback length (${\sim}$500 tokens): below this budget, the diagnostic event is truncated; above it, the event is captured regardless of model capacity or architecture family.
423	
424	\emph{Convergence at tail-512+}: once the phase transition is crossed, accuracy converges across all models into a 93.6--97.5\% band at tail-512; where tail-1024 data is available, the band tightens further to 96.5--96.6\%.
425	Scale and architecture differences that dominate the signal-poor regime (tail-256 range: 72.6--78.9\%, 6.3pp) compress dramatically in the signal-rich regime.
426	
427	\emph{Signal-poor convergence band}: head-2048 accuracies across all four models also converge into a narrow 75.3--81.8\% band (6.5pp; Table~\ref{tab:head_vs_tail}), comparable in width to the tail-256 band (72.6--78.9\%, 6.3pp).
428	When the diagnostic signal is absent (head-truncation discards trace terminus) or unreachable (tail-256 is too short), models of different scale and architecture collapse to similar performance, suggesting a shared floor determined by code comprehension rather than trace processing.
429	
430	\emph{Scale behavior inversion}: in the signal-poor regime (tail-256), smaller models perform worse (Qwen-1.5B 72.6\% vs.\ Qwen-7B 78.9\%, $-$6.3pp), mirroring the \texttt{no\_trace} scale pattern.
431	In the signal-rich regime (tail-512+), this reverses: Qwen-1.5B matches or exceeds Qwen-7B (95.6\% vs.\ 93.6\% at tail-512; 97.9\% vs.\ 97.3\% at tail-2048), confirming that sufficient trace signal eliminates the capacity advantage.
432	
433	\emph{Non-monotonicity}: DeepSeek-6.7B shows a $-$1.5pp decrease from tail-1024 (96.5\%) to tail-2048 (95.0\%), while Qwen-7B and Qwen-1.5B increase monotonically.
434	This architecture-specific sensitivity is consistent with DeepSeek's known vulnerability to long-context formatting (\S\ref{sec:training_dynamics}): additional tokens beyond the diagnostic window introduce noise that this model cannot filter as effectively.
435	
436	Table~\ref{tab:head_vs_tail} confirms the truncation direction effect: among the three models with complete data, tail-2048 outperforms head-2048 by 15.5--22.6pp.
437	The gap is largest for Qwen-1.5B (+22.6pp), indicating that smaller models benefit most from positional proximity to the diagnostic signal, as they lack the capacity to locate it within longer, noisier prefixes.
438	
439	%% ============================================================
440	\section{Calibration Analysis}
441	\label{sec:calibration_full}
442	
443	Beyond accuracy, we evaluate whether trace conditions affect prediction calibration, motivated by recent findings that code LLM confidence is often poorly calibrated \citep{spiess2025calibration}.
444	
445	\begin{table}[t]
446	\centering
447	\caption{Calibration metrics on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). ECE = expected calibration error; Brier = Brier score. Lower is better for both.}
448	\label{tab:calibration}
449	\small
450	\begin{tabular}{lcc}
451	\toprule
452	\textbf{Condition} & \textbf{ECE $\downarrow$} & \textbf{Brier $\downarrow$} \\
453	\midrule
454	ae\_only & \textbf{0.0004} & \textbf{0.0008} \\
455	exception\_only & 0.0027 & 0.0013 \\
456	VOTA & 0.0054 & 0.005 \\
457	full\_trace & 0.096 & 0.144 \\
458	no\_trace & 0.171 & 0.197 \\
459	\bottomrule
460	\end{tabular}
461	\end{table}
462	
463	Table~\ref{tab:calibration} shows that calibration quality mirrors the Tier~1/2 hierarchy.
464	Tier~1 conditions (\texttt{ae\_only}: ECE=0.0004; \texttt{exception\_only}: ECE=0.0027) produce near-perfectly calibrated predictions, while \texttt{full\_trace} (ECE=0.096) and \texttt{no\_trace} (ECE=0.171) exhibit substantial miscalibration.
465	VOTA (ECE=0.0054) is well-calibrated but slightly worse than either Tier~1 component alone, reinforcing the pattern that combining trace signals dilutes rather than improves the prediction signal.
466	
467	The Brier scores tell a consistent story: \texttt{ae\_only} (0.0008) and \texttt{exception\_only} (0.0013) achieve near-zero scores, while \texttt{no\_trace} (0.197) indicates substantial miscalibration.
468	
469	\begin{figure}[t]
470	\centering
471	\includegraphics[width=\columnwidth]{fig2_calibration}
472	\caption{Reliability diagrams for four trace conditions on Qwen-2.5-7B ($N{=}1{,}190$, seed=42). \texttt{exception\_only} (ECE=0.0027) clusters near the diagonal, while \texttt{no\_trace} (ECE=0.171) exhibits systematic overconfidence, a 63$\times$ gap.}
473	\label{fig:calibration}
474	\end{figure}
475	
476	%% ============================================================
477	\section{Error Overlap Analysis}
478	\label{sec:error_overlap}
479	
480	We analyze the overlap between error sets of different conditions to determine whether they fail on the same samples (Figure~\ref{fig:error_overlap}).
481	
482	\texttt{exception\_only}'s 2 errors (samples 901 and 905) have zero intersection with the error sets of all other conditions (Jaccard = 0.000 in all pairwise comparisons).
483	This orthogonality arises because \texttt{exception\_only} errors are caused by \texttt{GeneratorExit} false positives (pass samples misclassified as fail due to benign \texttt{BaseException} events), while errors from other conditions are predominantly fail samples misclassified as pass due to insufficient signal.
484	
485	Among non-exception conditions, error sets exhibit hierarchical containment: \texttt{ae\_only} $\subset$ VOTA $\subset$ \texttt{loop\_only} $\subset$ \texttt{no\_trace}, with pairwise Jaccard indices increasing with signal overlap.
486	\texttt{loop\_only} and \texttt{full\_trace} share the highest overlap (Jaccard ${\sim}$0.65), reflecting their shared reliance on behavioral patterns rather than explicit fault indicators.
487	
488	This analysis confirms that \texttt{exception\_only} operates on an independent signal dimension: its errors are representation ambiguities (iterator protocol artifacts) rather than information deficits, explaining why combining it with other signals cannot eliminate these specific errors.
489	
490	\begin{figure}[t]
491	\centering
492	\includegraphics[width=\columnwidth]{error_overlap}
493	\caption{Jaccard similarity between error sets of different conditions (Qwen-7B, seed=42, $N{=}1{,}190$). \texttt{exception\_only} (exc\_only) has zero overlap with all other conditions, confirming it operates on an independent signal dimension.}
494	\label{fig:error_overlap}
495	\end{figure}
496	
497	%% ============================================================
498	\section{Cross-Dataset Generalization: DebugBench}
499	\label{sec:debugbench_full}
500	
501	To test whether exception-based verdict prediction generalizes beyond LLM-generated solutions, we evaluate on DebugBench \citep{tian2024debugbench}---a dataset of human-written programs with synthetically injected bugs (single-point mutations such as operator replacement, variable misuse, and missing statements).
502	After filtering for executable Python samples with valid traces, we retain 426 samples with a near-balanced class distribution (majority baseline: 51.4\%).
503	
504	\begin{table}[t]
505	\centering
506	\caption{Generalization to DebugBench ($N{=}426$, Qwen-2.5-7B, seed=42). Wilson 95\% CIs. The component ranking (exception\_only $\geq$ VOTA $>$ no\_trace) is preserved, and exception\_only achieves perfect accuracy.}
507	\label{tab:debugbench}
508	\small
509	\begin{tabular}{lcc}
510	\toprule
511	\textbf{Condition} & \textbf{Acc (\%)} & \textbf{95\% CI} \\
512	\midrule
513	exception\_only & \textbf{100.00} & [99.14, 100.00] \\
514	VOTA & 99.77 & [99.30, 100.00] \\
515	no\_trace & 96.71 & [94.80, 98.40] \\
516	\midrule
517	Majority baseline & 51.41 & --- \\
518	\bottomrule
519	\end{tabular}
520	\end{table}
521	
522	Table~\ref{tab:debugbench} shows that the component ranking from the main experiments is preserved: \texttt{exception\_only} (100.00\%) $\geq$ VOTA (99.77\%) $>$ \texttt{no\_trace} (96.71\%).
523	The \texttt{exception\_only} condition achieves perfect accuracy, confirming that the exception-based representation generalizes to a different fault distribution without degradation.
524	
525	The absolute margins are much narrower than on the main dataset: the \texttt{no\_trace} baseline already achieves 96.71\%---compared to 75.13\% on HumanEval+MBPP---leaving only 3.29pp of headroom for trace-based improvement.
526	This ceiling effect reflects a fundamental difference in fault characteristics: DebugBench bugs are synthetically injected single-point mutations, which produce code that is structurally dissimilar from the original correct solution; a model can often identify the fault from source code alone.
527	In contrast, the HumanEval+MBPP solutions are LLM-generated, producing natural errors (logic mistakes, edge-case failures) where the faulty and correct solutions may be structurally similar, making code-only verdict prediction substantially harder.
528	
529	These results support exception-based verdict prediction as a generalizable approach---the method does not degrade on an out-of-distribution dataset, and the exception dominance ranking (exception\_only $\geq$ VOTA $>$ no\_trace) is consistent across both datasets---but the narrow DebugBench margins are insufficient to independently validate trace importance.
530	The 24.70pp trace lift on the main dataset (no\_trace 75.13\% $\to$ exception\_only 99.83\%) remains the primary evidence for the value of exception-based trace signals.
531	
532	%% ============================================================
533	\section{Cross-Model Robustness Analysis}
534	\label{sec:robustness_analysis}
535	
536	The cross-model gap pattern (Table~\ref{tab:cross_model}) suggests a design principle: \emph{trace representations should match the model capability floor, not the ceiling.}
537	Exception events are consistently the most effective component on both models, and their structural simplicity---a fixed-format error message---ensures that the relative advantage over richer representations holds across all seeds.
538	Two of three DeepSeek seeds match Qwen-level accuracy (99.33\%); the outlier (seed 123, 91.09\%) we hypothesize reflects LoRA initialization sensitivity landing in a suboptimal basin (fail recall = 70.5\%, though direct evidence is lacking), not a failure of the exception signal itself---even this outlier outperforms VOTA (84.45\%) by 6.64pp.
539	The VOTA cross-model gap is confounded by two factors: (1)~tokenizer efficiency---the DeepSeek tokenizer averages 2{,}626 tokens per VOTA sample versus Qwen's 1{,}929, causing 91.7\% of training samples to exceed the 2{,}048-token context window; content-aware truncation preferentially removes the terminal structured prompt, preserving the verdict label but truncating trace content---and (2)~base model capability differences, consistent with findings that SFT generalization depends on pretrain quality \citep{yang2024generalization}.
540	The two factors cannot be disentangled in the current experimental design.
541	Our \texttt{exception\_only} design sidesteps the truncation confound entirely: inputs have a median of 150 tokens (mean 398), well below the 2{,}048-token context window, so no training samples are truncated on either model.
542	The resulting 0.56pp cross-model gap (Table~\ref{tab:cross_model}) is therefore a clean measure of model capability differences, making the ``capability floor'' principle directly testable.
543	The practical implication is that trace-based systems should default to the simplest sufficient signal; for smaller models, training stability (multi-seed selection, warmup schedules) is a secondary but addressable concern.
544	
545	%% ============================================================
546	\section{Training Dynamics and Loss Decoupling}
547	\label{sec:training_dynamics}
548	
549	The DeepSeek \texttt{exception\_only} results reveal two instructive training dynamics.
550	First, epoch-level analysis shows mild degradation in 2/3 seeds: seed 42 peaks at 99.83\% after epoch~1 but settles at 99.33\% by epoch~3 ($-$0.50pp), seed 123 degrades from 91.43\% to 91.09\% ($-$0.34pp), while seed 456 shows no epoch degradation (99.33\% at both epoch~1 and epoch~3).
551	Early stopping may yield marginal gains for some seeds, but the epoch effect is small (${\leq}$0.5pp) compared to the seed effect (8.24pp between seeds 42 and 123).
552	
553	Second, seeds 123 and 456 converge to nearly identical final training losses (0.122 and 0.123 respectively), yet their accuracies differ by 8.24pp (91.09\% vs.\ 99.33\%).
554	The critical difference lies in fail recall: seeds 42 and 456 achieve 100\%, while seed 123 achieves only 70.5\%---the LoRA initialization in seed 123 fails to learn the exception$\to$fail mapping for a substantial fraction of failing samples, even though the per-token loss appears converged.
555	This demonstrates that token-level training loss can mask fundamental differences in sample-level classification ability, suggesting a parallel to the eval-loss/accuracy decoupling observed in DeepSeek VOTA (where eval loss rose 65\% from epoch 1 to 3 while accuracy improved by 6.3pp) at the training phase.
556	The practical recommendation is twofold: (1)~use task-specific metrics (accuracy, fail recall) for checkpoint and seed selection rather than training or evaluation loss, and (2)~for deployment on smaller models, train multiple seeds and select the best, as a single run may not reliably converge to the correct classification boundary.
557	
558	\paragraph{Format collapse, not semantic failure.}
559	The 100 errors of seed 123 are not semantic failures but generation format collapse: on inputs exceeding 4,000 characters (those containing verbose locals dumps), the model echoes trace content instead of emitting a verdict token, while achieving zero errors on shorter inputs.
560	This indicates that the LoRA initialization of seed 123 specifically compromises long-context format compliance rather than exception signal comprehension, further supporting the robustness advantage of compact \texttt{exception\_only} inputs.
561	
562	The contrast with VOTA is instructive: DeepSeek VOTA accuracy monotonically increases from 78.15\% to 84.45\% across epochs, but is consistent with a performance limit associated with the high trace truncation rate (\S\ref{sec:cross_model})---the model progressively extracts signal from samples with intact trace content but cannot fully compensate for the information loss in the truncated majority.
563	The 84.45\% accuracy reflects a combination of trace information loss and model capability constraints.
564	
565	%% ============================================================
566	\section{Deduplication Statistics}
567	\label{sec:dedup_stats}
568	
569	Table~\ref{tab:dedup} reports the duplication rates across trace formats.
570	Because multiple passing solutions to the same problem produce identical (input, output) pairs in the \texttt{exception\_only} format---correct executions raise no exceptions, so the trace content is the same regardless of the solution's internal logic---the dataset contains duplicate rows.
571	Train--test input overlap is zero (split by problem ID), so no information leakage occurs.
572	The high duplication in \texttt{exception\_only} does not affect our experimental conclusions: after deduplication the training set still contains 2,858 unique samples and the test set 607, providing sufficient coverage for the 591-problem benchmark.
573	The \texttt{exception\_only} test set contains 48.99\% duplicate inputs due to representation compactness; all confidence intervals treat samples as independent Bernoulli trials.
574	
575	\begin{table}[t]
576	\centering
577	\caption{Deduplication statistics. The \texttt{exception\_only} format collapses multiple passing solutions into identical rows because correct executions produce no exception events. Train--test input overlap is 0 (no leakage).}
578	\label{tab:dedup}
579	\small
580	\begin{tabular}{lccc}
581	\toprule
582	\textbf{Split} & \textbf{Total} & \textbf{Unique} & \textbf{Dup.\ rate} \\
583	\midrule
584	exception\_only train & 4{,}720 & 2{,}858 & 39.45\% \\
585	exception\_only test  & 1{,}190 &   607 & 48.99\% \\
586	raw\_traces (full)    & 5{,}910 & 5{,}803 &  1.81\% \\
587	\bottomrule
588	\end{tabular}
589	\end{table}
590	
591	%% ============================================================
592	\section{Regex Baseline Analysis}
593	\label{sec:regex_baselines}
594	
595	To establish a non-learning upper bound, we evaluate six regex-based baselines on the \texttt{exception\_only} test set ($N{=}1{,}190$) and two format-specific baselines on VOTA and \texttt{full\_trace} inputs.
596	
597	\begin{table}[t]
598	\centering
599	\caption{Regex baseline accuracy ($N{=}1{,}190$). B4 is the strongest semantic baseline (6.22pp below SFT \texttt{exception\_only}, McNemar $p{<}0.001$). B6 uses an error count threshold. $^\ddag$B5 exploits a data formatting artifact: the \texttt{[No exception data in trace]} marker is deterministically present in all pass samples, making this a format-level shortcut rather than a genuine exception-based heuristic.}
600	\label{tab:regex}
601	\small
602	\begin{tabular}{llc}
603	\toprule
604	\textbf{Baseline} & \textbf{Method} & \textbf{Acc (\%)} \\
605	\midrule
606	B1: \texttt{[ERROR]} presence & string match & 93.45 \\
607	B2: Traceback presence & string match & 71.51 \\
608	B3: Any keyword & union of B1+B2+Exception & 93.45 \\
609	B4: Exception type regex & regex on exception class names & \textbf{93.61} \\
610	B5: Format marker & \texttt{[No exception data]} $\to$ pass & 99.33$^\ddag$ \\
611	B6: Error count $\geq$2 & count threshold & 92.02 \\
612	\midrule
613	VOTA format regex & best regex on VOTA traces & 75.55 \\
614	full\_trace format regex & best regex on full traces & 77.39 \\
615	\bottomrule
616	\end{tabular}
617	\end{table}
618	
619	The strongest legitimate baseline (B4, 93.61\%) applies regex pattern-matching on Python exception class names (e.g., \texttt{ValueError}, \texttt{TypeError}).
620	Its errors concentrate on 8 boundary samples where a \texttt{ValueError} is raised inside a \texttt{try/except} block and caught---the program passes despite an exception occurring in the trace.
621	SFT \texttt{exception\_only} correctly classifies 6 of these 8 samples, indicating that the model learns the semantic distinction between caught (benign) and uncaught (fault-indicating) exceptions.
622	B5 (99.33\%) achieves near-SFT accuracy but relies on the deterministic presence of a format marker in pass-class traces, which is an artifact of the trace preprocessing pipeline rather than a generalizable signal; McNemar test vs.\ SFT yields $p{=}0.041$, confirming a statistically significant difference.
623	
624	\paragraph{Cross-format comparison.}
625	Table~\ref{tab:regex_cross_format} compares SFT and the best applicable regex baseline for each trace format.
626	The SFT advantage increases with format complexity: \texttt{no\_trace} (+3.62pp over majority baseline) $<$ \texttt{full\_trace} (+4.37pp) $<$ \texttt{exception\_only} (+6.22pp) $\ll$ VOTA (+23.86pp).
627	The VOTA gap is largest because its structured multi-component format carries semantic content that regex cannot parse, while \texttt{exception\_only}'s simpler format allows regex to capture most of the signal.
628	
629	\begin{table}[t]
630	\centering
631	\caption{SFT vs.\ best regex baseline by trace format ($N{=}1{,}190$). Regex baselines: majority class for \texttt{no\_trace}, keyword matching for \texttt{full\_trace}, pattern matching for VOTA, exception type regex (B4) for \texttt{exception\_only}.}
632	\label{tab:regex_cross_format}
633	\small
634	\begin{tabular}{lccc}
635	\toprule
636	\textbf{Format} & \textbf{SFT (\%)} & \textbf{Regex (\%)} & \textbf{$\Delta$ (pp)} \\
637	\midrule
638	exception\_only & 99.83 & 93.61 & +6.22 \\
639	VOTA & 99.41 & 75.55 & +23.86 \\
640	full\_trace & 81.76 & 77.39 & +4.37 \\
641	no\_trace & 75.13 & 71.51 & +3.62 \\
642	\bottomrule
643	\end{tabular}
644	\end{table}
645	
646	%% ============================================================
647	\section{Cross-Model Zero-Shot Comparison}
648	\label{sec:zeroshot_cross_model}
649	
650	Table~\ref{tab:zeroshot_cross_model} compares zero-shot and SFT \texttt{exception\_only} accuracy across four models.
651	Zero-shot performance does not correlate with model size: the smallest model (Qwen-1.5B, 93.45\%) outperforms all larger models, while the largest (CodeLlama-13B) falls below majority baseline.
652	SFT compresses the 42.44pp zero-shot range to 0.56pp, eliminating architecture-dependent variance.
653	
654	\begin{table}[t]
655	\centering
656	\caption{Zero-shot vs.\ SFT \texttt{exception\_only} across four models ($N{=}1{,}190$). Zero-shot accuracy is uncorrelated with model size; SFT normalizes cross-architecture variance from 42.44pp to 0.56pp.}
657	\label{tab:zeroshot_cross_model}
658	\small
659	\begin{tabular}{llccc}
660	\toprule
661	\textbf{Model} & \textbf{Size} & \textbf{Zero-shot (\%)} & \textbf{SFT (\%)} & \textbf{$\Delta$ (pp)} \\
662	\midrule
663	Qwen-1.5B & 1.5B & 93.45 & 99.83 & +6.38 \\
664	DeepSeek-6.7B & 6.7B & 90.59 & 99.33 & +8.74 \\
665	Qwen-7B & 7B & 89.08 & 99.83 & +10.75 \\
666	CodeLlama-13B & 13B & 51.01 & 99.89 & +48.88 \\
667	\midrule
668	Range & --- & 42.44pp & 0.56pp & --- \\
669	\bottomrule
670	\end{tabular}
671	\end{table}
672	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a3e79b1f-df2b-4286-b9c8-7efb59c778d6",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "b44707f0-8830-437c-9217-bb5c2990fd0c",
  "sourceToolAssistantUUID": "a3e79b1f-df2b-4286-b9c8-7efb59c778d6",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 36 · 2026-05-18T12:32:04.679Z_

<details open><summary>🔧 Tool call — Read · `toolu_013JUUhz8rMZgiGFqJELnN9Z`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b44707f0-8830-437c-9217-bb5c2990fd0c",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3DWy9eTSTSLnYpdG8C",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "552b386b-2d5d-4346-a984-4f50ea86df38",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015B1Xxn2H19XCB7WCtNsRdd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8418,
      "cache_read_input_tokens": 49319,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8418,
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

_source line 37 · 2026-05-18T12:32:04.690Z_

<details><summary>↩ Tool result · `toolu_013JUUhz8rMZgiGFqJELnN9Z`</summary>

```text
1	\section{Related Work}
2	
3	\paragraph{Execution Traces for Code LLMs.}
4	TracePile \citep{chen2025tracepile} scaled trace-augmented training to 2.6M samples; \citet{wang2025dcsh} found trace utility to be task- and format-dependent, a finding we extend by identifying exception events as the dominant signal for verdict prediction.
5	NExT \citep{ni2024next} and ET-CoT \citep{eguchi2025etcot} leveraged trace chain-of-thought for repair and execution reasoning.
6	\citet{ferrando2025execute} found compact traces comparable to full traces, supporting our information density finding.
7	CRUXEval \citep{gu2024cruxeval} established execution reasoning benchmarks, extended to 19 languages by \citet{xu2025cruxevalx}.
8	None decompose which trace components contribute to \emph{classification} accuracy.
9	
10	\paragraph{Code Verdict and Patch Classification.}
11	TRACED \citep{ding2024traced} showed execution-aware pretraining improves vulnerability and clone detection.
12	In patch correctness, APPT \citep{appt2024} achieved 79.7\% with BERT+LSTM; LLM4PatchCorrect \citep{zhou2024llm4patch} reached 84.4\% using execution traces.
13	FuseFL \citep{widyasari2024fusefl} demonstrated that structured fault signals improve fault localization.
14	\citet{foster2025mutation} deployed LLM-based equivalence detection at Meta with 0.95 precision.
15	These approaches treat traces as monolithic inputs; none isolate individual components, compare against rule-based baselines to quantify the value of learned representations, or test cross-model generalization.
16	
17	\paragraph{Fault Localization.}
18	Spectrum-based fault localization (SBFL) ranks program elements by statistical suspiciousness computed from passing/failing test spectra.
19	Classic metrics (Ochiai \citep{abreu2007accuracy}, Tarantula \citep{jones2002visualization}, DStar \citep{wong2014dstar}) share a core insight with our work: abnormal execution events (here, coverage patterns correlated with failure) are the most informative diagnostic signal.
20	Recent LLM-based approaches extend this: AutoFL \citep{kang2024autofl} uses function-level call graphs with ChatGPT; AgentFL \citep{qin2024agentfl} introduces multi-agent localization; LLM4FL \citep{widyasari2024llm4fl} combines SBFL spectra with LLM reasoning; and \citet{mukherjee2025llmfl} demonstrate that LLMs can localize faults from test failure information alone.
21	Verdict prediction is a prerequisite to fault localization: one must first determine \emph{whether} a fault exists before localizing \emph{where} it is.
22	Our exception-based approach and SBFL share the principle that anomalous execution events carry the strongest diagnostic signal, but operate at different granularities: we classify at the test level (pass/fail) while FL localizes at the statement or method level.
23	
24	\paragraph{Trace Compression and Selection.}
25	TraceCoder \citep{huang2026tracecoder} and InspectCoder \citep{wang2025inspectcoder} use selective trace extraction for debugging; \citet{haque2025traces} found raw traces provide limited repair benefit, supporting our compression finding.
26	Our approximate information density decomposition (gradient dilution ${\sim}$26\% vs.\ information overload ${\sim}$74\%) provides the first quantitative framework for \emph{why} compression helps, complementing these methods' focus on \emph{how} to compress.
27	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "552b386b-2d5d-4346-a984-4f50ea86df38",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "45eee2da-2a3f-48c5-b745-119e32a4edbc",
  "sourceToolAssistantUUID": "552b386b-2d5d-4346-a984-4f50ea86df38",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-18T12:32:05.089Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Q8zzZjVnNi5VCHbZjhi7FJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "45eee2da-2a3f-48c5-b745-119e32a4edbc",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3DWy9eTSTSLnYpdG8C",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d77985f6-f4e2-4b6d-9beb-6f9bab0d02e3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015B1Xxn2H19XCB7WCtNsRdd",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8418,
      "cache_read_input_tokens": 49319,
      "output_tokens": 230,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8418
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 230,
          "cache_read_input_tokens": 49319,
          "cache_creation_input_tokens": 8418,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8418,
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

_source line 39 · 2026-05-18T12:32:05.095Z_

<details><summary>↩ Tool result · `toolu_01Q8zzZjVnNi5VCHbZjhi7FJ`</summary>

```text
1	\section{Conclusion}
2	
3	We presented the first systematic component ablation of trace representations for verdict prediction across four models (1.5B--13B, three architecture families).
4	Exception events alone achieve ${\geq}$99.33\% across all four models (${\geq}$99.83\% on three of four; one seed reaches 100\%), while \texttt{no\_trace} shows 9.19pp scale sensitivity (67.3--76.5\%).
5	Adding more trace information actively hurts: the gap approximately decomposes into information overload (${\sim}$74\%) and gradient dilution (${\sim}$26\%), and tail-truncation confirms that diagnostic signal concentrates at the trace terminus.
6	A format-marker ablation shows ${\sim}$91\% of the exception signal is semantic rather than format-driven, and cross-dataset evaluation on DebugBench confirms generalization (\texttt{exception\_only}: 100\%, $N{=}426$).
7	
8	The broader implication is that verdict prediction is not an information-starved task that benefits from richer context.
9	It is a fault detection task where the runtime has already surfaced the critical diagnostic signal; the model's role is to interpret whether that signal indicates a terminal fault (as the SFT advantage over regex on caught-exception cases confirms).
10	This reframing suggests a design principle for trace-augmented systems: extract the highest-specificity diagnostic signal (median 150 tokens) and discard everything else.
11	Future work should test whether this principle extends to additional programming languages, larger real-world codebases, silent logic errors where no exception is raised, and tasks beyond verdict prediction.
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d77985f6-f4e2-4b6d-9beb-6f9bab0d02e3",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "64d50f98-ca4e-409d-b62b-e138495d6538",
  "sourceToolAssistantUUID": "d77985f6-f4e2-4b6d-9beb-6f9bab0d02e3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---

### Assistant

_source line 40 · 2026-05-18T12:32:12.210Z_

Now let me also check the literature map and any writing plan for additional context.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "64d50f98-ca4e-409d-b62b-e138495d6538",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3DyEhhiRYA9EXqZMwy",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "52404ede-48ad-4273-af25-3ba9cc3c2d96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015B6yqjcKincBrRK3s1YYfr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18103,
      "cache_read_input_tokens": 57737,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 18103,
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

_source line 41 · 2026-05-18T12:32:12.867Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01CYDTnyXcxnJUcRX266nAtc`</summary>

```json
{
  "project": "trace-verdict-study",
  "file": "literature_map.yaml",
  "max_chars": 15000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "52404ede-48ad-4273-af25-3ba9cc3c2d96",
  "isSidechain": true,
  "agentId": "a5c3828d05260ff7d",
  "requestId": "req_011CbA3DyEhhiRYA9EXqZMwy",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "04cbd6ee-929b-489c-a2c8-2528bb83693a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015B6yqjcKincBrRK3s1YYfr",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18103,
      "cache_read_input_tokens": 57737,
      "output_tokens": 126,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 18103
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 126,
          "cache_read_input_tokens": 57737,
          "cache_creation_input_tokens": 18103,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 18103,
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

_source line 42 · 2026-05-18T12:32:12.888Z_

<details><summary>↩ Tool result · `toolu_01CYDTnyXcxnJUcRX266nAtc`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study/literature_map.yaml\", \"content\": \"categories:\\n  execution-trace-llm:\\n    description: \\\"Execution trace 辅助 LLM 代码理解/调试/推理\\\"\\n    papers:\\n      - title: \\\"NExT: Teaching Large Language Models to Reason about Code Execution\\\"\\n        authors: \\\"Ansong Ni, Miltiadis Allamanis, et al. (Google DeepMind)\\\"\\n        year: 2024\\n        venue: \\\"ICML 2024\\\"\\n        role: method-component\\n        key_finding: \\\"自训练在 execution trace 上做 CoT rationale，程序修复 fix rate 在 MBPP +26.1%、HumanEval +14.3%。模型可泛化到无 trace 的场景。\\\"\\n        metrics:\\n          mbpp_fix_rate_improvement: \\\"+26.1%\\\"\\n          humaneval_fix_rate_improvement: \\\"+14.3%\\\"\\n\\n      - title: \\\"Do Code Semantics Help? A Comprehensive Study on Execution Trace-Based Information for Code LLMs\\\"\\n        authors: \\\"Jian Wang, Xiaofei Xie, Qiang Hu, Shangqing Liu, Yi Li\\\"\\n        year: 2025\\n        venue: \\\"Findings of EMNLP 2025\\\"\\n        arxiv_id: \\\"2509.11686\\\"\\n        role: direct-competitor\\n        key_finding: \\\"综合研究发现 execution trace 对 SFT 和 test-time scaling 的帮助有限，与先前工作结论相左。提出 trace adapter 做格式化。这是 VOTA 必须回应的关键负面结果——说明原始 trace 不够，需要针对性压缩/抽象。\\\"\\n        metrics: {}\\n\\n      - title: \\\"Code Execution as Grounded Supervision for LLM Reasoning\\\"\\n        authors: \\\"Dongwon Jung, Wenxuan Zhou, Muhao Chen\\\"\\n        year: 2025\\n        venue: \\\"EMNLP 2025\\\"\\n        arxiv_id: \\\"2506.10343\\\"\\n        role: method-component\\n        key_finding: \\\"用 Python debugger (Snoop) 提取 step-by-step execution trace，转换为自然语言 CoT。训练后模型推理能力提升且生成更少 token（减少 overthinking），具备跨域迁移能力。\\\"\\n        metrics: {}\\n\\n      - title: \\\"What I cannot execute, I do not understand: Training and Evaluating LLMs on Program Execution Traces\\\"\\n        authors: \\\"Lorenzo Ferrando, Nicola Ferraro, et al.\\\"\\n        year: 2025\\n        venue: \\\"arXiv 2503.05703\\\"\\n        arxiv_id: \\\"2503.05703\\\"\\n        role: method-component\\n        key_finding: \\\"对比 regular/compact/dynamic 三种 scratchpad 策略，compact（仅记录变化变量）略优于 regular（全部变量值）。CruxEval/MBPP ~80%。直接支持 plan_001：完整值信息冗余，精简不损失效果。\\\"\\n        metrics:\\n          cruxeval_accuracy: \\\"~80%\\\"\\n          mbpp_accuracy: \\\"~80%\\\"\\n\\n      - title: \\\"Demystifying Errors in LLM Reasoning Traces: An Empirical Study of Code Execution Simulation\\\"\\n        authors: \\\"Mohammad Abdollahi, Khandaker Rifah Tasnia, Soumit Kanti Saha, Jinqiu Yang, Song Wang, Hadi Hemmati\\\"\\n        year: 2025\\n        venue: \\\"arXiv\\\"\\n        arxiv_id: \\\"2512.00215\\\"\\n        role: evaluation\\n        key_finding: \\\"LLM 在循环中频繁遗漏/多算变量修改，函数返回值预测不准。说明 LLM 对具体值追踪能力弱于结构理解，为 plan_001 发现（值冗余）提供机制解释。\\\"\\n        metrics: {}\\n\\n      - title: \\\"Reasoning Runtime Behavior of a Program with LLM: How Far Are We? (REval)\\\"\\n        authors: \\\"Junkai Chen et al.\\\"\\n        year: 2024\\n        venue: \\\"arXiv 2403.16437\\\"\\n        role: evaluation\\n        key_finding: \\\"REval 框架评估 LLM 在 4 种 runtime behavior 预测任务上的表现：coverage prediction、program state prediction、execution path prediction、output prediction。平均 accuracy 仅 44.4%，IC score 10.3。揭示 LLM runtime reasoning 能力有限，支持 VOTA 的发现——需要抽象而非让 LLM 直接消化全量 trace。\\\"\\n        metrics:\\n          avg_accuracy: \\\"44.4%\\\"\\n          avg_ic_score: \\\"10.3\\\"\\n\\n      - title: \\\"CodeMind: Evaluating Large Language Models for Code Reasoning\\\"\\n        authors: \\\"Changshu Liu et al. (UIUC)\\\"\\n        year: 2024\\n        venue: \\\"arXiv 2402.09664\\\"\\n        role: evaluation\\n        key_finding: \\\"评估 LLM 在 IER（执行推理）、SR（规格推理）、DSR（动态语义推理）三个维度的代码推理能力。性能随代码复杂度（控制流、非原始类型、API 调用）显著下降。支持 VOTA 的 trace abstraction 动机——复杂 trace 超出 LLM 推理能力。\\\"\\n        metrics: {}\\n\\n      - title: \\\"CRUXEval-X: A Benchmark for Multilingual Code Reasoning, Understanding and Execution\\\"\\n        authors: \\\"Ruiyang Xu et al. (HKUST)\\\"\\n        year: 2025\\n        venue: \\\"ACL 2025\\\"\\n        arxiv_id: \\\"2408.13001\\\"\\n        role: evaluation\\n        key_finding: \\\"将 CRUXEval 扩展到 19 种编程语言，19K 测试。仅在 Python 训练的模型在其他语言最高 34.4% Pass@1，揭示 cross-language generalization 的局限。对 VOTA 的 cross-model generalization 实验提供方法论参考。\\\"\\n        metrics:\\n          languages: 19\\n          cross_lang_max_pass1: \\\"34.4%\\\"\\n\\n      - title: \\\"Chain of Execution Supervision Promotes General Reasoning in Large Language Models\\\"\\n        authors: \\\"Nuo Chen, Zehua Li, Keqin Bao, Junyang Lin, Dayiheng Liu (Qwen/Alibaba, HKUST-GZ, USTC)\\\"\\n        year: 2025\\n        venue: \\\"NeurIPS 2025\\\"\\n        arxiv_id: \\\"2510.23629\\\"\\n        verified: true\\n        role: direct-competitor\\n        key_finding: \\\"提出 TracePile——2.6M Chain-of-Execution trace 样本（~19B tokens），涵盖数学/算法/竞赛代码。在 4 个 base model、20 个 benchmark 上验证 trace 监督提升推理能力，但仅评估生成任务，未涉及 verdict classification。\\\"\\n        metrics:\\n          dataset_size: \\\"2.6M samples\\\"\\n          dataset_tokens: \\\"~19B\\\"\\n          benchmarks_evaluated: 20\\n\\n      - title: \\\"TRACED: Execution-aware Pre-training for Source Code\\\"\\n        authors: \\\"Yangruibo Ding, Ben Steenhoek, Kexin Pei, Gail Kaiser, Wei Le, Baishakhi Ray\\\"\\n        year: 2024\\n        venue: \\\"ICSE 2024\\\"\\n        arxiv_id: \\\"2306.07487\\\"\\n        verified: true\\n        role: direct-competitor\\n        key_finding: \\\"用源码+可执行输入+execution trace 做 execution-aware 预训练（encoder-based），在执行路径预测提升 12.4%、运行时变量值预测提升 25.2%。证明 trace 有助于 encoder-based 分类任务，但仅用于预训练而非直接做 verdict classification。\\\"\\n        metrics:\\n          execution_path_prediction_improvement: \\\"+12.4%\\\"\\n          runtime_value_prediction_improvement: \\\"+25.2%\\\"\\n\\n  code-verdict:\\n    description: \\\"LLM 判断代码 pass/fail、正确性分类、mutation testing\\\"\\n    papers:\\n      - title: \\\"APPT: Boosting Automated Patch Correctness Prediction via Fine-tuning Pre-trained Models\\\"\\n        authors: \\\"iSEngLab (Nanjing University)\\\"\\n        year: 2024\\n        venue: \\\"IEEE TSE 2024\\\"\\n        role: direct-competitor\\n        key_finding: \\\"BERT + LSTM + classifier 微调做 patch 正确性二分类。在 1183 个 Defects4J patches 上 accuracy 79.7%、recall 83.2%，优于 CACHE。与 VOTA 的 verdict 分类目标最接近。\\\"\\n        metrics:\\n          accuracy: \\\"79.7%\\\"\\n          recall: \\\"83.2%\\\"\\n          f1_improvement_from_finetuning: \\\"+10.22%\\\"\\n\\n      - title: \\\"LLM4PatchCorrect: Leveraging Large Language Model for Automatic Patch Correctness Assessment\\\"\\n        authors: \\\"Xin Zhou et al. (SMU)\\\"\\n        year: 2024\\n        venue: \\\"IEEE TSE 2024\\\"\\n        role: direct-competitor\\n        key_finding: \\\"用 Starcoder-7B 零样本评估 patch 正确性，输入包含 bug description、execution traces、failing test cases、test coverage。无需微调即达 84.4% accuracy。使用了 execution trace 作为输入信号，与 VOTA 输入空间有重叠，但方法（zero-shot prompting vs SFT）和任务（patch correctness vs test verdict）不同。\\\"\\n        metrics:\\n          accuracy: \\\"84.4%\\\"\\n          f1: \\\"86.5%\\\"\\n        novelty_threat: medium\\n\\n      - title: \\\"Parameter-Efficient Fine-Tuning with Attributed Patch Semantic Graph for Automated Patch Correctness Assessment\\\"\\n        authors: \\\"Zhenyu Yang, Jingwen Wu, Zhen Yang, Zhongxing Yu\\\"\\n        year: 2025\\n        venue: \\\"arXiv 2505.02629\\\"\\n        arxiv_id: \\\"2505.02629\\\"\\n        role: direct-competitor\\n        key_finding: \\\"提出 APSG（Attributed Patch Semantic Graph）+ Graph-LoRA，用图结构捕获 patch 语义的 data/control flow。在 patch correctness 上比 SOTA 提升 accuracy 3.1-7.5%、F1 3.0-7.1%。方法论（PEFT + 结构化代码表示做分类）与 VOTA 有相似之处，但 VOTA 用 trace signal 而非 graph。\\\"\\n        metrics:\\n          accuracy_improvement: \\\"+3.1-7.5%\\\"\\n          f1_improvement: \\\"+3.0-7.1%\\\"\\n        novelty_threat: medium\\n\\n      - title: \\\"Calibration and Correctness of Language Models for Code\\\"\\n        authors: \\\"Claudio Spiess, David Gros, et al.\\\"\\n        year: 2025\\n        venue: \\\"ICSE 2025\\\"\\n        arxiv_id: \\\"2402.02047\\\"\\n        role: evaluation\\n        key_finding: \\\"代码生成模型的置信度校准普遍较差。Platt scaling 可改善但需要先验正确性数据。对 VOTA 的启示：verdict 分类需关注校准，不只是准确率。\\\"\\n        metrics: {}\\n\\n      - title: \\\"Mutation-Guided LLM-based Test Generation at Meta\\\"\\n        authors: \\\"Christopher Foster et al. (Meta)\\\"\\n        year: 2025\\n        venue: \\\"FSE 2025 (Industry)\\\"\\n        arxiv_id: \\\"2501.12862\\\"\\n        role: evaluation\\n        key_finding: \\\"LLM equivalence detector 判断 mutant 是否等价，加简单预处理后 precision 0.95、recall 0.96。大规模部署到 10K+ 类，工程师接受率 73%。展示了 LLM 做代码正确性判断的工业可行性。\\\"\\n        metrics:\\n          precision: \\\"0.95\\\"\\n          recall: \\\"0.96\\\"\\n          classes_evaluated: \\\"10795\\\"\\n          test_acceptance_rate: \\\"73%\\\"\\n\\n      - title: \\\"FuseFL: Demystifying Faulty Code with LLM via Step-by-Step Reasoning\\\"\\n        authors: \\\"Ratnadira Widyasari et al. (SMU)\\\"\\n        year: 2024\\n        venue: \\\"SANER 2024\\\"\\n        role: background\\n        key_finding: \\\"融合 SBFL 排名 + test execution outcomes（input、expected/actual output、errors）+ code description 做 fault localization。Top-1 localization 比 baseline 提升 32.3%，比 SBFL 提升 68.4%。test execution outcomes 作为输入信号与 VOTA 的 fault indicator signals 理念相关。\\\"\\n        metrics:\\n          top1_improvement_over_baseline: \\\"+32.3%\\\"\\n          top1_improvement_over_sbfl: \\\"+68.4%\\\"\\n\\n      - title: \\\"CRUXEval: A Benchmark for Code Reasoning, Understanding and Execution\\\"\\n        authors: \\\"Alex Gu, Baptiste Rozière, Hugh James Leather, Armando Solar-Lezama, Gabriel Synnaeve, Sida Wang\\\"\\n        year: 2024\\n        venue: \\\"ICML 2024\\\"\\n        arxiv_id: \\\"2401.03065\\\"\\n        verified: true\\n        role: evaluation\\n        key_finding: \\\"800 个 Python 函数的代码推理 benchmark，包含 input prediction 和 output prediction 两个任务。GPT-4+CoT 达 75%/81% pass@1。作为 VOTA 实验的数据集来源。\\\"\\n        metrics:\\n          benchmark_size: 800\\n          gpt4_cot_input_pass1: \\\"75%\\\"\\n          gpt4_cot_output_pass1: \\\"81%\\\"\\n\\n  trace-compression:\\n    description: \\\"Execution trace 的压缩、摘要、抽象方法\\\"\\n    papers:\\n      - title: \\\"Predictive Program Slicing via Execution Knowledge-Guided Dynamic Dependence Learning\\\"\\n        authors: \\\"Aashish Yadavally, Yi Li, Tien Nguyen\\\"\\n        year: 2024\\n        venue: \\\"FSE 2024\\\"\\n        role: method-component\\n        key_finding: \\\"ND-Slicer 用 execution-aware 预训练学习动态依赖，无需实际执行即可预测特定输入的程序切片。Python 上 exact-match 81.31%、ROUGE-LCS 0.954。与 VOTA 的 assertion-point snapshots 思路类似——都是从完整 trace 中提取关键信息。\\\"\\n        metrics:\\n          exact_match: \\\"81.31%\\\"\\n          rouge_lcs: \\\"0.954\\\"\\n          fault_localization_accuracy: \\\"63.88%\\\"\\n\\n      - title: \\\"Towards Effectively Leveraging Execution Traces for Program Repair with Code LLMs\\\"\\n        authors: \\\"Mirazul Haque, Petr Babkin, et al. (J.P. Morgan AI Research)\\\"\\n        year: 2025\\n        venue: \\\"KnowledgeNLP Workshop @ ACL 2025\\\"\\n        arxiv_id: \\\"2505.04441\\\"\\n        role: background\\n        key_finding: \\\"直接将 execution trace 加入 prompt 帮助有限，且随 trace 复杂度增加效果递减。LLM 优化的 prompt 格式比原始 trace 更一致地优于无 trace baseline。直接支持 VOTA 的核心假设：原始 trace 太冗长，需要专门的压缩/抽象。\\\"\\n        metrics: {}\\n\\n      - title: \\\"Making LLMs Program Interpreters via Execution Trace Chain of Thought (ET-CoT)\\\"\\n        authors: \\\"Koshi Eguchi, Takuya Akiba\\\"\\n        year: 2025\\n        venue: \\\"ICML 2025 Workshop PRAL\\\"\\n        openreview_id: \\\"pFyBdPyOCQ\\\"\\n        role: method-component\\n        key_finding: \\\"开发 PyTracify 工具生成 sub-line 粒度的结构化 execution trace，SFT 后 Qwen2.5-7B 在 CRUXEval-O 达 70.0%、LiveCodeBench 达 88.3%，超过同规模 code-oriented 模型。其 trace 格式本身是一种 trace abstraction。\\\"\\n        metrics:\\n          cruxeval_o: \\\"70.0%\\\"\\n          livecodebench_execution: \\\"88.3%\\\"\\n\\n      - title: \\\"TraceCoder: A Trace-Driven Multi-Agent Framework for Automated Debugging of LLM-Generated Code\\\"\\n        authors: \\\"Jiangping Huang, Wenguang Ye, Weisong Sun, Jian Zhang, Mingyue Zhang, Yang Liu\\\"\\n        year: 2026\\n        venue: \\\"ICSE 2026\\\"\\n        arxiv_id: \\\"2602.06875\\\"\\n        verified: true\\n        role: background\\n        key_finding: \\\"在特定位置插入 diagnostic probes 而非全量 trace 记录，Pass@1 提升 34.43%。选择性 trace 采集优于全量，支持 VOTA 的行为模式抽象思路。\\\"\\n        metrics:\\n          pass_at_1_improvement: \\\"+34.43%\\\"\\n\\n      - title: \\\"Runtime Execution Traces Guided Automated Program Repair with Multi-Agent Debate\\\"\\n        authors: \\\"Jiaqing Wu, Tong Wu, Manqing Zhang, Yunwei Dong, Bo Shen\\\"\\n        year: 2026\\n        venue: \\\"arXiv 2604.02647\\\"\\n        arxiv_id: \\\"2604.02647\\\"\\n        verified: true\\n        role: background\\n        key_finding: \\\"Probe agent 选择性捕获 critical variables 的 execution snapshots 用于 multi-agent repair debate，修复 392 个缺陷。验证了选择性 trace 信息优于全量记录。\\\"\\n        metrics:\\n          defects_fixed: \\\"392\\\"\\n\\n      - title: \\\"InspectCoder: Dynamic Analysis-Enabled Self Repair through Interactive LLM-Debugger Collaboration\\\"\\n        authors: \\\"Yunkun Wang, Yue Zhang, Guochang Li, Chen Zhi, Binhua Li, Fei Huang, Yongbin Li, Shuiguang Deng\\\"\\n        year: 2025\\n        venue: \\\"arXiv 2510.18327\\\"\\n        arxiv_id: \\\"2510.18327\\\"\\n        role: background\\n        key_finding: \\\"首个让 LLM 主动控制 debugger 做动态分析的 agentic repair 系统。Program Inspector 做策略性 breakpoint 放置和 runtime state 检查，Patch Coder 合成修复。比最强 baseline 提升 5.10-60.37%。选择性 runtime 检查理念与 VOTA 的 fault indicator signal 提取一致。\\\"\\n        metrics:\\n          repair_accuracy_improvement: \\\"+5.10-60.37%\\\"\\n\\n      - title: \\\"MGDebugger: From Code to Correctness via Hierarchical Debugging\\\"\\n        authors: \\\"Yuling Shi et al.\\\"\\n        year: 2024\\n        venue: \\\"arXiv 2410.01215\\\"\\n        role: background\\n        key_finding: \\\"层次化分解代码为子函数树，LLM 模拟执行追踪关键变量状态，bottom-up 定位修复。HumanEval accuracy 75.6%→94.5%。其 LLM-simulated executor 追踪变量状态的方式是一种隐式 trace abstraction。\\\"\\n        metrics:\\n          humaneval_accuracy: \\\"94.5%\\\"\\n          humaneval_fix_accuracy: \\\"97.6%\\\"\\n\\n  debugging-agents:\\n    description: \\\"LLM 多智能体调试框架\\\"\\n    papers:\\n      - title: \\\"UniDebugger: Hierarchical Multi-Agent Framework for Unified Software Debugging\\\"\\n        authors: \\\"Cheryl Lee, Chunqiu Steven Xia, et al. (Lingming Zhang group)\\\"\\n        year: 2025\\n        venue: \\\"EMNLP 2025\\\"\\n        arxiv_id: \\\"2404.17153\\\"\\n        role: background\\n        key_finding: \\\"三层认知架构模拟开发者调试过程，L1→L2→L3 逐层升级。在 Defects4J 上修复 1.25-2.56x bugs。不使用 execution trace 作为输入（纯静态分析），与 VOTA 方法正交。\\\"\\n        metrics:\\n          defects4j_improvement: \\\"1.25-2.56x\\\"\\n\\n      - title: \\\"Seeker: Enhancing Exception Handling in Code with LLM-based Multi-Agent Approach\\\"\\n        authors: \\\"Xuanming Zhang, Yuxuan Chen, Yuan Yuan, Minlie Huang\\\"\\n        year: 2025\\n        venue: \\\"ICLR 2025\\\"\\n        arxiv_id: \\\"2410.06949\\\"\\n        role: background\\n        key_finding: \\\"5-agent 框架做 exception handling 生成，构建 Common Exception Enumeration (CEE) 知识库。Exception handling precision 提升 37%。从 exception taxonomy 角度提供背景——exception 类型和处理策略的系统化，与 VOTA 的 exception event 信号提取视角互补。\\\"\\n        metrics:\\n          exception_handling_precision_improvement: \\\"+37%\\\"\\n\\n  sft-classification:\\n    description: \\\"用 SFT 做分类任务的方法论和 findings\\\"\\n    papers:\\n      - title: \\\"Fine-Tuning Causal LLMs for Text Classification: Embedding-Based vs. Instruction-Based Approaches\\\"\\n        authors: \\\"Amirhossein Yousefiramandi, Ciaran Cooney\\\"\\n        year: 2025\\n        venue: \\\"arXiv 2512.12677\\\"\\n        arxiv_id: \\\"2512.12677\\\"\\n        role: method-component\\n        key_finding: \\\"对比 embedding-based（加分类头）vs instruction-based（prompt->response）两种 SFT 分类方式。Embedding-based + QLoRA 在 F1 上与 instruction-tuned 持平，但可训练参数少得多。对 VOTA 的 verdict 分类有直接参考价值——选哪种 SFT 格式。\\\"\\n        metrics: {}\\n\\n      - title: \\\"FisherSFT: Data-Efficient Supervised Fine-Tuning of Language Models Using Information Gain\\\"\\n        authors: \\\"Rohan Deb, Kiran Koshy Thekumparampil, Kousha Kalantari, Gaurush Hiranandani, Shoham Sabach, Branislav Kveton\\\"\\n        year: 2025\\n        venue: \\\"ICML 2025\\\"\\n        arxiv_id: \\\"2505.14826\\\"\\n        role: background\\n        key_finding: \\\"用 Fisher 信息矩阵选择信息量最大的训练样本子集，通过 last-layer 线性化高效近似。在固定数据预算下提升 SFT \\n\\n... [截断: 省略 3596 字符，传 max_chars=0 获取完整内容]\", \"total_chars\": 18596, \"truncated\": true}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "04cbd6ee-929b-489c-a2c8-2528bb83693a",
  "isSidechain": true,
  "promptId": "d609e982-470b-4ab6-a420-fff4d6b936d6",
  "agentId": "a5c3828d05260ff7d",
  "type": "user",
  "uuid": "39ba7679-0ba7-4907-a08b-dc507c345910",
  "sourceToolAssistantUUID": "04cbd6ee-929b-489c-a2c8-2528bb83693a",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/trace-verdict-study",
  "sessionId": "7ac75d31-96a3-4e39-809a-0eaa527fab20",
  "version": "2.1.126",
  "gitBranch": "HEAD"
}
```

</details>

---
