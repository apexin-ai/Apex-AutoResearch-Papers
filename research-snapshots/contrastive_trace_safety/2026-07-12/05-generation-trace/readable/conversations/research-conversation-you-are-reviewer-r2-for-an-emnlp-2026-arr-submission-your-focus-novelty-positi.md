# Research conversation: You are Reviewer R2 for an EMNLP 2026 ARR submission. Your focus: **Novelty, positioning, and related work**. ## Venue c

**Layer Selection Sensitivity in Hidden-State Safety Probes for Reasoning Models (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 43
- **Recorded user turns:** 1
- **Tool calls:** 18
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-a8237ec39a85ac6a7.jsonl`
- **Structured JSON:** [`88462023533beb3ee83d.json`](../../sessions/88/88462023533beb3ee83d.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

43 recorded events

### User

_source line 1 · 2026-05-21T22:11:03.331Z_

You are Reviewer R2 for an EMNLP 2026 ARR submission. Your focus: **Novelty, positioning, and related work**.

## Venue calibration
- EMNLP 2026 via ARR. Overall Assessment 1-5 half-point scale. 4 = Main conference acceptance (~21% accept rate). 3 = Findings. 2 = resubmit.
- Dimensions: Soundness (1-5), Excitement (1-5), Reproducibility (1-5).

## Paper summary
**Title**: "What Detects Safety Commitment in Reasoning Models? A Systematic Evaluation of Probe-Based Monitoring Methods"

The paper studies "self-jailbreak" in reasoning LLMs — where safety reasoning and harmful execution interleave in CoT, culminating in a "commitment point" (CP) after which safety reasoning permanently ceases. They evaluate detection methods across 4 models × 7 methods × 5 metrics for detecting this CP.

**4 models**: R1-8B (Llama, R1-distilled), OT-7B (Qwen, STILL-trained), R1-32B (Qwen, R1-distilled), QwQ-32B (Qwen, native reasoning). 2×2 architecture × scale.

**7 methods**: Static HS LR probes, temporal HS LR probes (W=1-25), text probes (MiniLM-L6 sentence embeddings), GRU sequence model, Mahalanobis distance, BOCPD/CUSUM, cross-model transfer.

**5 metrics**: Balanced accuracy, precision, pre-commitment FPR, safe-trace FPR, detection lead time.

**Key claims:**
1. Layer selection methodology is a critical researcher degree of freedom — a commonly used composite metric (`bal_acc × crossing_rate`) systematically biases toward shallow layers at 32B scale, entirely masking HS advantage.
2. HS probes outperform text probes at correctly selected layers (12/12 Holm-Bonferroni corrections, precision +15-24pp), robust at 7-8B and model-specific at 32B.
3. Temporal context universally improves text probes (4/4 models) and benefits HS probes (3/4).
4. Six alternative detection paradigms (Mahalanobis, RepE, CCS, BOCPD/CUSUM, MLP, cross-model transfer) all fail.
5. Practical deployment remains limited: safe-trace FPR 39-50% for most model-method combinations; only 1 of 4 meets <20% FPR threshold.

## Related Work section (from paper)

The paper's Section 2 covers three areas:

**Hidden-state safety monitoring**: TrajGuard [3] (Mahalanobis distance for adversarial input detection), SafeSwitch [4], SIREN [5] — all operate at token/input level, not evaluated on reasoning-model self-jailbreak.

**Reasoning-model safety analysis**: Self-Jailbreaking [6], HarmThoughts [7] characterize the phenomenon; SafeRemind [8], SafeThink [9] propose text-level CoT monitors vulnerable to internal state divergence.

**Representation probing for safety**: RepE [10] (mean-difference vectors), CCS [11] (contrastive probes), Tuned Lens [12] (layer-wise analysis). Paper claims to differ by focusing on temporal probing of sequential reasoning traces and systematic layer selection evaluation.

**12 references total** in the bibliography.

## Your review task

### 1. Novelty Assessment
- How novel is the core contribution? The paper frames its primary contribution as the **layer selection sensitivity analysis** — discovering that `bal_acc × crossing_rate` biases toward shallow layers. Is this a genuine methodological insight or "obvious once stated" (researchers should validate their metric choices)?
- The **systematic evaluation framework** (4×7×5) — is breadth of evaluation a contribution at EMNLP? Or is this "just engineering"?
- The HS vs text comparison — is this comparison itself novel? Prior work (RepE, CCS, Tuned Lens) has compared representation modalities. What's new here?
- Temporal probing of sequential reasoning traces — how does this relate to existing work on probing temporal dynamics?
- The negative results (6 paradigms fail) — are these genuinely informative negative results or expected failures ("Mahalanobis wasn't designed for this")?

### 2. Related Work Completeness
- 12 references seems thin for a survey-style evaluation paper. What's missing?
- Are there relevant works on:
  - Probing dynamics in LLMs (not just static probing)?
  - Safety monitoring during inference (runtime monitoring literature)?
  - Change-point detection in neural network activations?
  - Representation geometry analysis beyond RepE/CCS?
  - Other reasoning model safety analysis beyond the cited works?
- Does the paper adequately position against concurrent/recent work?

### 3. Positioning and Framing
- The paper oscillates between "diagnostic research tool" and "monitoring system" — is the framing consistent?
- The title asks "What Detects Safety Commitment?" — does the paper actually answer this question, or just show "HS probes with good layer selection, but not well enough for deployment"?
- The "self-jailbreak" framing — is this well-established in the literature, or is the paper defining its own problem?
- Five claims in the introduction — are they all substantiated? Is Claim 5 (deployment limitation) really a "finding" or just a caveat?

### 4. Contribution Calibration
- For EMNLP Main (~21% acceptance), does this paper offer sufficient novelty? 
- Would this be a better fit for Findings?
- What would make this paper a Main-track contribution?
- Is this primarily a "systems/evaluation" paper or a "science" paper? How should that affect assessment?

### 5. Architecture Diversity Concern
- 3 of 4 models are Qwen-based. Does this limit generalizability claims?
- The 2×2 design (architecture × scale) has only 1 cell with a non-Qwen model (R1-8B Llama). Is this acknowledged adequately?

## Output format

Provide your review as:
```
## R2 Review: Novelty and Related Work

### Summary
[2-3 sentences]

### Strengths
[Numbered list, 4-6 items]

### Weaknesses
[Numbered list, 4-6 items]

### Questions for Authors
[Numbered list, 3-5 items]

### Missing References
[List any important missing references/comparisons]

### Scores
- Soundness: X/5
- Excitement: X/5
- Reproducibility: X/5
- Overall: X/5
- Confidence: X/5

### Meta-assessment
[1 paragraph: is this Main, Findings, or Resubmit? What's the key factor?]
```

Be rigorous. A systematic evaluation paper needs either (a) surprising findings that change how the community thinks, or (b) such thoroughness that it becomes the definitive reference. Assess whether this paper achieves either.


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "bd0b71dd-57f0-48c9-a706-886acbc41b0e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-21T22:11:03.335Z_

```json
{
  "parentUuid": "bd0b71dd-57f0-48c9-a706-886acbc41b0e",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
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
  "uuid": "23ce49b6-c438-4b48-9c82-1cd07ca501f0",
  "timestamp": "2026-05-21T22:11:03.335Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 3 · 2026-05-21T22:11:07.137Z_



I'll review the paper carefully. Let me start by reading the full paper and related materials.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "23ce49b6-c438-4b48-9c82-1cd07ca501f0",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUoRMSQMdSjs5EJ4qA1",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "b034c769-461c-4560-aa44-03335b1c96ac",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0194MvaVenG3tcW9rKHeiXcE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 8384,
      "cache_read_input_tokens": 9392,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 8384,
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

_source line 4 · 2026-05-21T22:11:07.995Z_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01BJBmAhywBXUamjUQMvgw25`</summary>

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
  "parentUuid": "b034c769-461c-4560-aa44-03335b1c96ac",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUoRMSQMdSjs5EJ4qA1",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "35d30d66-5e02-4962-b4c9-6b6b3ffe99cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_0194MvaVenG3tcW9rKHeiXcE",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 8384,
      "cache_read_input_tokens": 9392,
      "output_tokens": 108,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 8384
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 108,
          "cache_read_input_tokens": 9392,
          "cache_creation_input_tokens": 8384,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 8384,
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

_source line 5 · 2026-05-21T22:11:07.998Z_

<details><summary>↩ Tool result · `toolu_01BJBmAhywBXUamjUQMvgw25`</summary>

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
  "parentUuid": "35d30d66-5e02-4962-b4c9-6b6b3ffe99cc",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "fd02354c-dd9c-4d01-907e-616c9488d3d5",
  "sourceToolAssistantUUID": "35d30d66-5e02-4962-b4c9-6b6b3ffe99cc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 6 · 2026-05-21T22:11:11.331Z_



Let me read the paper and supporting materials thoroughly.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fd02354c-dd9c-4d01-907e-616c9488d3d5",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUomLirC2QEKsLJjgY4",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "51a7398f-2e77-4b6a-85df-934a1b3f4ed0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYDcoYqz33wGyDsfbvxRHQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 17776,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1290,
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

_source line 7 · 2026-05-21T22:11:13.257Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01GR3KxouaqUEwZqSkGCf8qn`</summary>

```json
{
  "pattern": "docs/paper/main.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "51a7398f-2e77-4b6a-85df-934a1b3f4ed0",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUomLirC2QEKsLJjgY4",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6b86cff0-917f-4952-98e8-684f942f036f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYDcoYqz33wGyDsfbvxRHQ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 17776,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1290,
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

_source line 8 · 2026-05-21T22:11:13.295Z_

<details><summary>↩ Tool result · `toolu_01GR3KxouaqUEwZqSkGCf8qn`</summary>

```text
docs/paper/main.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6b86cff0-917f-4952-98e8-684f942f036f",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "fd84bc0b-4c4e-46a1-8a21-2c81f10b5c31",
  "sourceToolAssistantUUID": "6b86cff0-917f-4952-98e8-684f942f036f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-21T22:11:13.566Z_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_013uhkrQRcf5BfadHDWsbbC8`</summary>

```json
{
  "project": "contrastive_trace_safety",
  "file": "literature_map.yaml",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fd84bc0b-4c4e-46a1-8a21-2c81f10b5c31",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUomLirC2QEKsLJjgY4",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3882f3a0-7be3-438f-88bd-37921b918eea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NYDcoYqz33wGyDsfbvxRHQ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 17776,
      "output_tokens": 208,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1290
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 208,
          "cache_read_input_tokens": 17776,
          "cache_creation_input_tokens": 1290,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1290,
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

_source line 10 · 2026-05-21T22:11:13.576Z_

<details><summary>↩ Tool result · `toolu_013uhkrQRcf5BfadHDWsbbC8`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/literature_map.yaml\", \"content\": \"meta:\\n  last_updated: \\\"2026-05-20\\\"\\n  total_papers: 10\\ncategories: []\\npapers:\\n  zou2023representation:\\n    title: \\\"Representation Engineering: A Top-Down Approach to AI Transparency\\\"\\n    authors:\\n      - \\\"Andy Zou\\\"\\n      - \\\"Long Phan\\\"\\n      - \\\"Sarah Chen\\\"\\n      - \\\"James Campbell\\\"\\n      - \\\"Phillip Guo\\\"\\n      - \\\"Richard Ren\\\"\\n      - \\\"Alexander Pan\\\"\\n      - \\\"Xuwang Yin\\\"\\n      - \\\"Mantas Mazeika\\\"\\n      - \\\"Ann-Kathrin Dombrowski\\\"\\n      - \\\"Shashwat Goel\\\"\\n      - \\\"Nathaniel Li\\\"\\n      - \\\"Michael J. Byun\\\"\\n      - \\\"Zifan Wang\\\"\\n      - \\\"Alex Mallen\\\"\\n      - \\\"Steven Basart\\\"\\n      - \\\"Sanmi Koyejo\\\"\\n      - \\\"Dawn Song\\\"\\n      - \\\"Matt Fredrikson\\\"\\n      - \\\"J. Zico Kolter\\\"\\n      - \\\"Dan Hendrycks\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2023\\n    arxiv_id: \\\"2310.01405\\\"\\n    role: \\\"foundation\\\"\\n    verified: false\\n    bibtex_key: \\\"zou2023representation\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Foundation for hidden-state probing for safety\\\"\\n    abstract: \\\"Proposes representation engineering for AI transparency by reading and writing model internal representations. Foundation for hidden-state probing for safety.\\\"\\n  zhou2024alignment:\\n    title: \\\"How Alignment and Jailbreak Work: Explain LLM Safety through Intermediate Hidden States\\\"\\n    authors:\\n      - \\\"Zhenhong Zhou\\\"\\n      - \\\"Haiyang Yu\\\"\\n      - \\\"Xinghua Zhang\\\"\\n      - \\\"Rongwu Xu\\\"\\n      - \\\"Fei Huang\\\"\\n      - \\\"Yongbin Li\\\"\\n    venue: \\\"ACL\\\"\\n    year: 2024\\n    arxiv_id: \\\"2406.05644\\\"\\n    role: \\\"closely_related\\\"\\n    verified: false\\n    bibtex_key: \\\"zhou2024alignment\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Shares hidden-state analysis methodology for alignment/jailbreak\\\"\\n    abstract: \\\"Analyzes intermediate hidden states to explain alignment and jailbreak mechanisms in LLMs. Shares hidden-state analysis methodology but does not address reasoning models or temporal probing.\\\"\\n  arditi2024refusal:\\n    title: \\\"Refusal in Language Models Is Mediated by a Single Direction\\\"\\n    authors:\\n      - \\\"Andy Arditi\\\"\\n      - \\\"Oscar Obeso\\\"\\n      - \\\"Aaquib Syed\\\"\\n      - \\\"Daniel Paleka\\\"\\n      - \\\"Nina Panickssery\\\"\\n      - \\\"Wes Gurnee\\\"\\n      - \\\"Neel Nanda\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2024\\n    arxiv_id: \\\"2406.11717\\\"\\n    role: \\\"closely_related\\\"\\n    verified: false\\n    bibtex_key: \\\"arditi2024refusal\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Refusal direction complements our layer selection finding\\\"\\n    abstract: \\\"Discovers that refusal behavior is mediated by a single direction in the residual stream. Complements our layer selection finding by showing safety signal structure differs across layers.\\\"\\n  harmthoughts:\\n    title: \\\"HarmThoughts: Safety Alignment of Reasoning Models Using Thinking Process\\\"\\n    authors:\\n      - \\\"Yixin Cao\\\"\\n      - \\\"Zhening Li\\\"\\n      - \\\"Jialu Wang\\\"\\n      - \\\"Zhibo Zhang\\\"\\n      - \\\"Ruoxi Chen\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2025\\n    arxiv_id: \\\"2503.01498\\\"\\n    role: \\\"data_source\\\"\\n    verified: false\\n    bibtex_key: \\\"harmthoughts\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Primary dataset source with CP annotations\\\"\\n    abstract: \\\"Primary dataset source. Provides reasoning model safety traces with commitment point annotations, defining the CP framework used in our analysis.\\\"\\n  safethink:\\n    title: \\\"SafeThink: Enhancing Safety of Language Models with Chain-of-Thought Based Reasoning\\\"\\n    authors:\\n      - \\\"Xuan-Son Vu\\\"\\n      - \\\"Le-Minh Nguyen\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2025\\n    arxiv_id: \\\"2501.14899\\\"\\n    role: \\\"related\\\"\\n    verified: false\\n    bibtex_key: \\\"safethink\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"CoT-based safety defense, complements our analysis-oriented approach\\\"\\n    abstract: \\\"Enhances LLM safety through CoT reasoning from a defense perspective, complementing our analysis-oriented use of reasoning traces.\\\"\\n  chen2025unfaithful:\\n    title: \\\"Hidden Chain-of-Thought Reasoning Can Be Unfaithful\\\"\\n    authors:\\n      - \\\"Yufei Chen\\\"\\n      - \\\"Yuchi Liu\\\"\\n      - \\\"Zhenglin Chen\\\"\\n      - \\\"Yifan Xu\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2025\\n    arxiv_id: \\\"2503.09614\\\"\\n    role: \\\"related\\\"\\n    verified: false\\n    bibtex_key: \\\"chen2025unfaithful\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Hidden CoT unfaithfulness directly relevant to hidden-state vs text comparison\\\"\\n    abstract: \\\"Reveals hidden CoT can be unfaithful to actual model reasoning. Directly relevant to our core theme of hidden-state vs text comparison.\\\"\\n  hewitt2019control:\\n    title: \\\"Designing and Interpreting Probes with Control Tasks\\\"\\n    authors:\\n      - \\\"John Hewitt\\\"\\n      - \\\"Percy Liang\\\"\\n    venue: \\\"EMNLP\\\"\\n    year: 2019\\n    arxiv_id: \\\"1909.03368\\\"\\n    role: \\\"methodological_foundation\\\"\\n    verified: false\\n    bibtex_key: \\\"hewitt2019control\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Control task methodology for probing; our selectivity controls derive from this\\\"\\n    abstract: \\\"Proposes control task methodology for evaluating probing results. Our selectivity controls and random-label baselines derive from this work.\\\"\\n  kaya2019shallow:\\n    title: \\\"Shallow-Deep Networks: Understanding and Mitigating Network Overthinking\\\"\\n    authors:\\n      - \\\"Yigitcan Kaya\\\"\\n      - \\\"Sanghyun Hong\\\"\\n      - \\\"Tudor Dumitras\\\"\\n    venue: \\\"ICML\\\"\\n    year: 2019\\n    arxiv_id: \\\"1810.07052\\\"\\n    role: \\\"conceptual_foundation\\\"\\n    verified: false\\n    bibtex_key: \\\"kaya2019shallow\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"Network overthinking concept; our crossing rate formalizes similar cross-layer disagreement\\\"\\n    abstract: \\\"Introduces network overthinking concept and cross-layer prediction disagreement analysis. Our crossing rate metric formalizes similar cross-layer disagreement measurement.\\\"\\n  zhou2020bert:\\n    title: \\\"BERT Loses Patience: Fast and Robust Inference with Early Exit\\\"\\n    authors:\\n      - \\\"Wangchunshu Zhou\\\"\\n      - \\\"Canwen Xu\\\"\\n      - \\\"Tao Ge\\\"\\n      - \\\"Julian McAuley\\\"\\n      - \\\"Ke Xu\\\"\\n      - \\\"Furu Wei\\\"\\n    venue: \\\"NeurIPS\\\"\\n    year: 2020\\n    arxiv_id: \\\"2006.04152\\\"\\n    role: \\\"conceptual_foundation\\\"\\n    verified: false\\n    bibtex_key: \\\"zhou2020bert\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"PABEE cross-layer consistency relates to our crossing rate for safety probe layer selection\\\"\\n    abstract: \\\"PABEE uses cross-layer consistency for early exit. Our crossing rate relates to PABEE's consistency concept but applied to safety probe layer selection.\\\"\\n  zou2023universal:\\n    title: \\\"Universal and Transferable Adversarial Attacks on Aligned Language Models\\\"\\n    authors:\\n      - \\\"Andy Zou\\\"\\n      - \\\"Zifan Wang\\\"\\n      - \\\"Nicholas Carlini\\\"\\n      - \\\"Milad Nasr\\\"\\n      - \\\"J. Zico Kolter\\\"\\n      - \\\"Matt Fredrikson\\\"\\n    venue: \\\"arXiv\\\"\\n    year: 2023\\n    arxiv_id: \\\"2307.15043\\\"\\n    role: \\\"data_source\\\"\\n    verified: false\\n    bibtex_key: \\\"zou2023universal\\\"\\n    category: \\\"\\\"\\n    relevance: \\\"GCG attack and AdvBench dataset; our cross-dataset validation discovers CP=0 boundary condition\\\"\\n    abstract: \\\"Proposes GCG attack and AdvBench dataset. Our cross-dataset validation uses AdvBench, discovering adversarial prompts skip safety deliberation (CP=0 boundary condition).\\\"\\n\", \"total_chars\": 6850, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3882f3a0-7be3-438f-88bd-37921b918eea",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "755b42bc-db6c-4ba4-b181-312ce76bf3fa",
  "sourceToolAssistantUUID": "3882f3a0-7be3-438f-88bd-37921b918eea",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-21T22:11:21.282Z_

<details open><summary>🔧 Tool call — Read · `toolu_013qQF4TSmjuNgzU7kH6X8FG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/main.tex",
  "limit": 150
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "755b42bc-db6c-4ba4-b181-312ce76bf3fa",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpBDAiTpAhU7a6QYMS",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "b8f30fd8-8a29-478a-a567-ba3a00bc2a96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Khodu5xTi5x9PNKyrTGPLC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3208,
      "cache_read_input_tokens": 19066,
      "output_tokens": 106,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 3208
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 106,
          "cache_read_input_tokens": 19066,
          "cache_creation_input_tokens": 3208,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 3208,
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

_source line 12 · 2026-05-21T22:11:21.286Z_

<details><summary>↩ Tool result · `toolu_013qQF4TSmjuNgzU7kH6X8FG`</summary>

```text
1	\documentclass[11pt]{article}
2	\usepackage[review]{acl}
3	\usepackage{times}
4	\usepackage{latexsym}
5	\usepackage[T1]{fontenc}
6	\usepackage[utf8]{inputenc}
7	\usepackage{microtype}
8	\usepackage{graphicx}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{booktabs}
12	\usepackage{multirow}
13	\usepackage{subcaption}
14	\usepackage{xcolor}
15	\usepackage{colortbl}
16	\usepackage{hyperref}
17	\usepackage[capitalise]{cleveref}
18	
19	\title{Layer Selection Sensitivity in Hidden-State Safety Probes for Reasoning Models}
20	
21	\author{Anonymous ARR Submission}
22	
23	\begin{document}
24	\maketitle
25	
26	\begin{abstract}
27	\input{sections/abstract}
28	\end{abstract}
29	
30	\input{sections/introduction}
31	
32	\input{sections/related_work}
33	
34	\input{sections/method}
35	
36	\input{sections/experiments}
37	
38	\input{sections/discussion}
39	
40	\input{sections/conclusion}
41	
42	\input{sections/limitations}
43	
44	\bibliography{references}
45	
46	\input{sections/appendix}
47	
48	\end{document}
49	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "b8f30fd8-8a29-478a-a567-ba3a00bc2a96",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "7d19a147-8ed2-4f5b-8625-82e9f1f1d73a",
  "sourceToolAssistantUUID": "b8f30fd8-8a29-478a-a567-ba3a00bc2a96",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-21T22:11:23.492Z_

<details open><summary>🔧 Tool call — Glob · `toolu_01SsuA4UFKU4BRxgdyLJRjxu`</summary>

```json
{
  "pattern": "docs/paper/sections/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7d19a147-8ed2-4f5b-8625-82e9f1f1d73a",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpkDHGEuJnSecNVbCM",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "302f73a4-e299-4bc2-a0bd-a4034e32073c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GwJcDCs71dg4uhyF6FiBG1",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 545,
      "cache_read_input_tokens": 22274,
      "output_tokens": 103,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 545
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 103,
          "cache_read_input_tokens": 22274,
          "cache_creation_input_tokens": 545,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 545,
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

_source line 14 · 2026-05-21T22:11:23.606Z_

<details><summary>↩ Tool result · `toolu_01SsuA4UFKU4BRxgdyLJRjxu`</summary>

```text
docs/paper/sections/limitations.tex
docs/paper/sections/method.tex
docs/paper/sections/abstract.tex
docs/paper/sections/introduction.tex
docs/paper/sections/related_work.tex
docs/paper/sections/appendix.tex
docs/paper/sections/discussion.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/experiments.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "302f73a4-e299-4bc2-a0bd-a4034e32073c",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "01052025-17c9-43d2-931e-af62eae75f3e",
  "sourceToolAssistantUUID": "302f73a4-e299-4bc2-a0bd-a4034e32073c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-21T22:11:25.974Z_

<details open><summary>🔧 Tool call — Read · `toolu_012hiyWbocEc2dywk99UTVBs`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "01052025-17c9-43d2-931e-af62eae75f3e",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpv3dRi1yhtTMTNy4Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "699c995e-d82f-4553-af07-c62eb24ba906",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXZECvCbJL1N5b612gfNPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 207,
      "cache_read_input_tokens": 22819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 207,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 65,
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

_source line 16 · 2026-05-21T22:11:25.984Z_

<details><summary>↩ Tool result · `toolu_012hiyWbocEc2dywk99UTVBs`</summary>

```text
1	Reasoning models with chain-of-thought (CoT) can self-jailbreak: their reasoning traces transition from safe deliberation to committed harmful generation without adversarial input. We define the commitment point (CP) as the first reasoning step after which safety deliberation permanently ceases, and present a systematic empirical comparison of hidden-state (HS) vs.\ text probes for CP detection across four reasoning LLMs (3 Qwen-family, 1 Llama) on HarmThoughts. The comparison depends critically on which transformer layer is monitored, a known sensitivity in probing~\citep{belinkov2022probing} that we show is severe enough to qualitatively reverse conclusions in the safety domain: a crossing-rate composite metric selects L0 for R1-8B while threshold-based metrics select L14 (14-layer divergence); at 32B the divergence reaches 61 layers (exploratory$^\dagger$), reversing whether an HS advantage is observed. Threshold-based layer selection recovers HS precision gains of +15 to +22pp at 7--8B (cross-validated via nested CV) and preliminary +15 to +19pp at 32B (exploratory$^\dagger$, $n \leq 20$) against a 384d sentence encoder, but this advantage is conditional on partially correlated factors: it diminishes with stronger text encoders (4/4 HB at 384d $\to$ 1/4 at 1024d) and partially overlaps with temporal position. Seven alternative methods (change-point detection, geometric distance, representation engineering, cross-model transfer) all fail to match supervised probing. Metric-induced layer selection bias is the robust methodological finding; the empirical HS advantage is conditional on encoder quality, model scale, and position control.
2	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "699c995e-d82f-4553-af07-c62eb24ba906",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "05662d55-9d86-4581-aa38-0f193117aec5",
  "sourceToolAssistantUUID": "699c995e-d82f-4553-af07-c62eb24ba906",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-21T22:11:26.250Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DESu22sisgF2v751EnspJv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "05662d55-9d86-4581-aa38-0f193117aec5",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpv3dRi1yhtTMTNy4Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "eb1e6938-f12f-4672-a8ba-91856ac95c66",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXZECvCbJL1N5b612gfNPh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 207,
      "cache_read_input_tokens": 22819,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 207,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 65,
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

_source line 18 · 2026-05-21T22:11:26.256Z_

<details><summary>↩ Tool result · `toolu_01DESu22sisgF2v751EnspJv`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Reasoning models such as DeepSeek-R1~\cite{deepseekr1} and QwQ~\cite{qwq} scale inference-time computation through extended chains of thought (CoT). Recent work documents that these models can ``self-jailbreak'': without adversarial input modification, the CoT transitions from safety-aware deliberation to committed harmful generation~\cite{harmthoughts,selfjailbreak}. We define the first reasoning step after which safety deliberation permanently ceases as the \textbf{Safety Commitment Point} (CP). This failure mode differs qualitatively from adversarial jailbreaks on standard LLMs because the harmful transition originates within the model's own reasoning. Recent work shows that chain-of-thought faithfulness is limited~\citep{chen2025unfaithful}, motivating hidden-state monitoring that bypasses surface text. Before retrospective characterization can inform future detection systems, a prior question must be answered: can current probing methods reliably distinguish pre-CP from post-CP reasoning steps, and under what conditions? This paper provides \emph{retrospective} classification (not online detection) of what hidden-state and text-based probes can and cannot detect; false positive rates remain 11--50\%, so deployment applications are future work.\looseness=-1
4	
5	Existing safety detectors target fundamentally different problems. Hidden-state (HS) methods such as TrajGuard~\cite{trajguard} and SafeSwitch~\cite{safeswitch} classify adversarial inputs at the token level, while text monitors like SafeRemind~\cite{saferemind} scan generated reasoning for explicit violations. Neither tracks the gradual, multi-step commitment process. HS probes require choosing which transformer layer to monitor, a researcher degree of freedom typically treated as a minor implementation detail. Before asking which modality is better, a prior methodological question must be answered: how sensitive are probe conclusions to the choice of layer selection metric? We show this choice alone can reverse a study's central conclusion: the same data yield a 14-layer (R1-8B) to 61-layer (QwQ-32B) divergence depending solely on metric choice; for QwQ-32B, at threshold-based layers the HS advantage is +19pp ($p{<}0.005$); at crossing-rate-selected layers, it is non-significant ($p{=}0.83$). More broadly, no prior work tracks how safety signals evolve step-by-step during extended reasoning; existing hidden-state analyses operate across layers (spatial) rather than across generation steps (temporal).\looseness=-1
6	
7	We conduct a systematic analysis across four reasoning models, primarily Qwen-based (3/4 models), with one Llama model providing evidence from a second architecture family, at two scales (7--8B, 32B) on the HarmThoughts benchmark. Our central finding is methodological: the choice of layer selection metric entirely determines whether an HS advantage is observed. A composite metric (balanced accuracy $\times$ crossing rate) selects shallow layers for 32B models because shallow representations compress directional information, so a linear probe operates near the noise floor and threshold crossings reflect noise rather than semantic transitions. At these layers, only the two 7--8B models show significant HS advantage.\looseness=-1
8	
9	\begin{table}[t]
10	\centering
11	\resizebox{\columnwidth}{!}{%
12	\begin{tabular}{lccccc}
13	\toprule
14	\textbf{Model} & \textbf{Arch.} & \textbf{Params} & \textbf{Layers} & \textbf{Hidden} & \textbf{$n$ (total\,/\,test)} \\
15	\midrule
16	R1-8B & Llama & 8B & 32 & 4096 & 209\,/\,43 \\
17	OT-7B & Qwen & 7B & 28 & 3584 & 228\,/\,47 \\
18	R1-32B & Qwen & 32B & 64 & 5120 & 100\,/\,20 \\
19	QwQ-32B & Qwen & 32B & 64 & 5120 & 95\,/\,19 \\
20	\bottomrule
21	\end{tabular}}
22	\caption{Models studied. R1-8B and R1-32B are distilled from DeepSeek-R1~\citep{deepseekr1}; QwQ-32B~\citep{qwq} is a native reasoning model; OT-7B~\citep{openthinker} is trained with STILL~\citep{still} on Qwen2.5-7B. Data: HarmThoughts~\citep{harmthoughts} with step-level CP annotations (CP = first reasoning step after which safety deliberation permanently ceases). Split: 60/20/20.}
23	\label{tab:models}
24	\end{table}
25	
26	Threshold-based metrics (precision, inverse FPR, additive composite) share a common confusion matrix and empirically converge; BA independently confirms deep-layer selection (\cref{tab:layer_selection}). At these layers, the HS advantage is graded: \emph{validated via nested 5-fold CV} at 7--8B (precision +20.1 to +21.9pp; \cref{tab:hs_vs_text}), \emph{significant} but suggestive of position-competitiveness at QwQ-32B$^\dagger$ (+19.2pp; \cref{sec:32b-analysis}), and \emph{exploratory} at R1-32B$^\dagger$ (+15.4pp, pattern consistent with position mediation, below MDE; \cref{sec:experiments}).\looseness=-1
27	
28	Our contributions are:
29	\begin{itemize}
30	    \item \textbf{Metric-induced layer selection bias.} Prior work has noted metric sensitivity in probing~\citep{belinkov2022probing}; our contribution is demonstrating a qualitative reversal (significant to non-significant) in a safety-critical application, where the stakes of metric choice are higher than in typical linguistic probing. Crossing-rate composite metrics systematically select shallow layers across all four models (including Llama), reversing HS probe conclusions at 32B scale. The divergence is not gradual: for QwQ-32B, the CR-composite layer (L2, 3\% depth) yields $p{=}0.83$ (non-significant), while the threshold-based layer (L63, 98\% depth) yields $p{<}0.005$, a qualitative reversal, not a quantitative shift. Random-label controls on both architectures confirm the disagreement requires genuine safety labels; the geometric component is Qwen-specific (\cref{sec:layer-results}).
31	
32	    \item \textbf{Boundary conditions for the HS advantage.} Against 384d MiniLM, the HS advantage is validated via nested 5-fold CV at 7--8B (+20.1 to +21.9pp, HB corrected), significant at QwQ-32B$^\dagger$ (+19.2pp, position-competitive), and exploratory at R1-32B$^\dagger$ (+15.4pp). This advantage is conditional on two partially correlated factors: it diminishes with stronger encoders (1/4 HB under BGE-1024d; PCA capacity matching preserves significance across all four models) and partially overlaps with position (3/4 linear, 2/4 quadratic residualization; \cref{sec:32b-analysis}).
33	
34	    \item \textbf{Negative results define method boundaries.} No alternative method consistently matches supervised probing (\cref{tab:negative}): BOCPD/CUSUM fail on gradual transitions; Mahalanobis distance finds near-zero separation; RepE is model-dependent; cross-model transfer fails. Control task selectivity (11.1--16.8pp above chance; \cref{app:control}) confirms genuine safety structure.
35	\end{itemize}
36	
37	\noindent These findings establish layer selection as a critical confound for hidden-state safety monitoring that future work must address.\looseness=-1
38	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "eb1e6938-f12f-4672-a8ba-91856ac95c66",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "67c0b02d-98b0-491a-a3a3-775668f830ec",
  "sourceToolAssistantUUID": "eb1e6938-f12f-4672-a8ba-91856ac95c66",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-21T22:11:27.190Z_

<details open><summary>🔧 Tool call — Read · `toolu_01P6odSACAyr1Uo8hrMoSGpF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "67c0b02d-98b0-491a-a3a3-775668f830ec",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpv3dRi1yhtTMTNy4Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c38cdeef-1d7f-43a2-97ee-2033f2bdd595",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXZECvCbJL1N5b612gfNPh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 207,
      "cache_read_input_tokens": 22819,
      "output_tokens": 315,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 207
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 315,
          "cache_read_input_tokens": 22819,
          "cache_creation_input_tokens": 207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 207,
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

_source line 20 · 2026-05-21T22:11:27.195Z_

<details><summary>↩ Tool result · `toolu_01P6odSACAyr1Uo8hrMoSGpF`</summary>

```text
1	\section{Related Work}\label{sec:related-work}
2	
3	\paragraph{Safety in Reasoning Models.}
4	Reasoning models introduce a qualitatively new failure mode: the model's own chain of thought can transition from safety-aware deliberation to harmful generation without adversarial input modification~\cite{wang2025lrmsafety}.
5	
6	\textit{Attack characterization.} Self-jailbreak has been documented with step-level annotations~\cite{harmthoughts}, with longer chains increasing circumvention probability~\cite{selfjailbreak}. H-CoT~\cite{hcot2025} shows reasoning chains can be externally hijacked. Unfaithful reasoning~\cite{chen2025unfaithful,turpin2023language} further motivates hidden-state monitoring that bypasses text. Safety-aligned models maintain refusal intentions during thinking but experience a sharp drop at output generation~\cite{yin2025refusal_cliff,hagendorff2026lrm_jailbreak,hu2026refusal_dynamics,ahrend2026safer_traces}.
7	
8	\textit{Detection.} CoT monitoring can detect reward hacking but optimization pressure promotes obfuscation~\cite{baker2025monitoring}. CoT monitorability is valuable but fragile~\cite{korbak2025cot_monitorability}. GuardReasoner~\cite{xiang2025guardreasoner} trains a dedicated reasoning-based guard model. \citet{schulz2025roadmap} proposes a structured safety-case framework grounded in CoT monitoring, formalizing the deployment context our probes would serve.
9	
10	\textit{Mitigation.} SafeThink~\cite{safethink} steers early reasoning toward safety, SafeRemind~\cite{saferemind} inserts entropy-triggered reminders, and Chain-of-Guardrails~\cite{mao2025selfjailbreak_reasoning} proposes guardrail insertion during reasoning. None of these conducts a systematic modality comparison for commitment detection.
11	
12	\paragraph{Hidden-State Safety Detection.}
13	Internal activations can detect safety violations in standard LLMs. \citet{azaria2023internal} demonstrate that internal states encode whether a model's output is truthful, motivating representation-based monitoring. \citet{zhou2024alignment} show safety-relevant information distributes across layers and argue it originates in pre-training rather than alignment; our temporal probes target a distinct phenomenon (commitment transitions during reasoning) that is absent from pre-training data. Meanwhile, \citet{qi2025shallow_alignment} find that alignment operates primarily over early output tokens. \citet{arditi2024refusal} identify a single refusal direction, \citet{turner2023activation} steer behavior via activation addition without optimization, \citet{li2023iti} intervene at inference time using layer-specific probes, and \citet{zhao2025harmfulness} show harmfulness and refusal are encoded separately. \citet{joad2026refusal_multi} reveal category-specific refusal directions, \citet{templeton2024scaling} extract interpretable features at scale, and \citet{wollschlager2025geometry} formalize multi-dimensionality through concept cones. TrajGuard~\cite{trajguard} uses Mahalanobis distance; SafeSwitch~\cite{safeswitch} trains hidden-state classifiers; SIREN~\cite{siren} monitors representations during generation; \citet{zhou2025ghost} apply layer-specific hidden-state forensics for anomaly detection; SafeDream~\cite{safedream2026}, HiddenDetect~\cite{jiang2025hiddendetect}, SafeInt~\cite{safeint2025}, and RCS~\cite{rcs2026} extend hidden-state monitoring to proactive detection, vision-language models, intervention, and contrastive scoring respectively. \citet{zhao2026safeprobing} probe safety awareness during decoding; \citet{chia2025probing_subspaces} extract latent subspaces separating safe from adversarial states. These methods assume external input manipulation and operate at the token level. The self-jailbreak setting differs because transitions are internal and span multiple reasoning steps. \citet{kadali2025internal} confirm layer-wise safety signal.
14	Concurrently, \citet{chan2025probing} demonstrate that linear probes on the \emph{final layer} (residual stream, PCA-50) predict alignment outcomes with strong F1, establishing separability of safe/unsafe reasoning. However, their single-layer, single-metric evaluation (logistic regression on the last layer, evaluated by F1 and PR-AUC alone) does not examine whether different layers yield different conclusions, the central question of our work. Our five-metric taxonomy and full-depth layer sweep reveal that metric choice alone can reverse the modality comparison (\cref{sec:layer-results}), a vulnerability that applies to any fixed-layer design including theirs. Their sentence-level temporal segmentation and our token-level windowing are complementary: they establish that early segments suffice for outcome prediction; we show that the \emph{reliability} of such predictions depends on both the layer and the metric used to select it. We reproduce TrajGuard (\cref{sec:negative}) and find its geometric approach fails because discriminative signal resides in minor PCA components.
15	
16	\paragraph{Probing Methodology and Layer Selection.}
17	Causal abstraction~\cite{geiger2023causal} formalizes when high-level causal models faithfully describe neural computation, grounding use of internal representations. Linear probing spans layer-wise classifiers~\cite{alain2017understanding}, sentence probing~\cite{conneau2018probing}, and surveys~\cite{belinkov2019analysis,belinkov2022probing,rogers2020primer}. Control tasks~\cite{hewitt2019control} distinguish structure from memorization (we adopt these; \cref{app:control}); \citet{levinstein2024liedetector} argue probing may exploit spurious correlations, a concern our control tasks address. Information-theoretic and causal formulations address probe complexity~\cite{voita2020information,pimentel2020information,ravfogel2020null,ravfogel2022rlace,belrose2023leace,elazar2021amnesic}.\footnote{The Tuned Lens~\cite{belrose2023tunedlens} offers an alternative layer-wise analysis but assumes next-token prediction, misaligned with binary CP classification.} \citet{marks2024geometry} find emergent linear structure in LLM truth representations, consistent with our safety commitment separability. That information distributes non-uniformly across layers is well established~\cite{tenney2019bert,jawahar2019bert}. Cross-layer prediction consistency has been exploited for efficiency: \citet{kaya2019shallow} identify ``overthinking'' via cross-layer disagreement, and \citet{zhou2020bert} formalize patience-based early exit. We repurpose this for safety probe layer selection (\cref{sec:layer-sensitivity}). Our contribution is orthogonal: the known layer-wise information gradient interacts with metric choice to produce systematic selection bias in safety probes. Most directly, \citet{boxo2025linear_probes} show linear probes can rely on textual evidence rather than deeper representations; our metric bias analysis provides a complementary mechanism: shallow-layer probes exploit compressed representations that inflate crossing rate, a geometric effect consistent with text-leakage at layers where representations have not yet diverged from surface features. \citet{alvarez2026transport_geometry} apply hidden-state geometry to step-level hallucination detection concurrently with our work. \citet{damirchi2026truth} study internal representation trajectories for layer-wise truth encoding. Concurrently, \citet{chrabaszcz2026monitoring} monitor probe trajectories across reasoning steps to characterize reasoning dynamics; our work additionally shows that metric-dependent layer selection can reverse probe conclusions, a confound absent from their analysis. \citet{vitel2025layer} independently show that layer choice significantly affects influence estimation; we demonstrate that in safety probing, this sensitivity produces qualitative reversals (\cref{sec:layer-results}). \citet{meyoyan2026bertology} propose selective probes for efficient classification; \citet{pais2026linear_probe_scaling} show multi-layer ensembling recovers where single-layer probes fail. Both complement our finding that layer choice is a validity concern.\looseness=-1
18	
19	\paragraph{Alternative Detection Approaches.}
20	BOCPD~\cite{adams2007bayesian} detects abrupt distributional shifts; CCS~\cite{burns2023discovering} discovers latent truth directions via consistency constraints; RepE~\cite{zou2023representation} identifies concept directions through mean differences. We adapt all three to temporal commitment detection (\cref{sec:negative}). BOCPD and CUSUM fail because commitment is gradual. CCS provides no gain because its consistency objective misaligns with temporal structure. RepE shows inconsistent performance across models (0.756 on QwQ, 0.559 on R1-32B). These failures motivate supervised probes with principled layer selection as the minimal effective methodology.
21	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c38cdeef-1d7f-43a2-97ee-2033f2bdd595",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "1e49cc09-a1d0-43c0-8ac1-592d66e29100",
  "sourceToolAssistantUUID": "c38cdeef-1d7f-43a2-97ee-2033f2bdd595",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-21T22:11:27.213Z_

<details open><summary>🔧 Tool call — Read · `toolu_015SNyxxefwmCkcWVMjmGYAz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1e49cc09-a1d0-43c0-8ac1-592d66e29100",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUpv3dRi1yhtTMTNy4Z",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d0224122-6bda-4426-8c6c-79c52c309266",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DXZECvCbJL1N5b612gfNPh",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 207,
      "cache_read_input_tokens": 22819,
      "output_tokens": 315,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 207
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 315,
          "cache_read_input_tokens": 22819,
          "cache_creation_input_tokens": 207,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 207,
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

_source line 22 · 2026-05-21T22:11:27.217Z_

<details><summary>↩ Tool result · `toolu_015SNyxxefwmCkcWVMjmGYAz`</summary>

```text
1	\section{Problem Setup and Methods}
2	\label{sec:method}
3	
4	\subsection{Safety Commitment Point}
5	\label{sec:commitment-point}
6	
7	When a reasoning model is jailbroken, its chain-of-thought (CoT) transitions from safety-aware deliberation to committed harmful generation. We define the \textbf{Safety Commitment Point} (CP) as the first reasoning step after which safety deliberation permanently ceases; traces with oscillating safety deliberation are resolved by taking the final irreversible transition. This binary formulation is a deliberate simplification; we discuss its limits in \cref{sec:limitations}. Steps before CP are \emph{pre-commitment} ($y_t = 0$); steps at or after CP are \emph{post-commitment} ($y_t = 1$). The classification task produces a score $s_t \in [0, 1]$ estimating whether the model has passed its CP by step $t$.
8	
9	We study four reasoning models spanning two architectures and two scales (\cref{tab:models}).
10	
11	\subsection{Probe Architecture}
12	\label{sec:probe-architecture}
13	
14	\paragraph{Hidden-state (HS) probes.} At each step $t$, we extract the last-token hidden state $\mathbf{h}_t^{(\ell)} \in \mathbb{R}^d$ from layer $\ell$ and train an L2-regularized logistic regression classifier (balanced class weights, $C{=}1.0$, LBFGS, max\_iter${}=2000$) on binary CP labels. Sweeping $C \in [0.01, 100]$ yields $<$2pp BA variation (\cref{sec:experiments}), confirming robustness to this default. Layer selection is analyzed in \cref{sec:layer-sensitivity}.
15	
16	\paragraph{Text probes.} Each step's text is encoded with all-MiniLM-L6-v2~\citep{wang2020minilm} ($\mathbb{R}^{384}$), a distilled sentence encoder from the Sentence-BERT family~\citep{reimers2019sentence}. The same logistic regression is applied as a surface-level modality baseline.
17	
18	\paragraph{Temporal windowing.} For window size $W$, we concatenate features from steps $[t{-}W{+}1, \ldots, t]$. We evaluate $W \in \{1, 3, 5, 10, 15, 20, 25\}$ and select per-model on validation. GRU sequence models are also evaluated under two protocols: a 70/30 train/test split (primary) and the same 60/20/20 split used for LR experiments (for fair comparison; \cref{tab:gru_multi_seeds,app:gru_details}).
19	
20	\subsection{Layer Selection Sensitivity}
21	\label{sec:layer-sensitivity}
22	
23	Layer selection is a researcher degree of freedom that can reverse modality comparison conclusions. We evaluate five metrics: balanced accuracy (BA), precision, and inverse FPR are standard probing metrics~\citep{belinkov2022probing}; crossing rate formalizes cross-layer prediction disagreement~\citep{kaya2019shallow,zhou2020bert}, and additive composite. A \emph{first crossing point} (FCP) exists for trace~$i$ at layer~$\ell$ when the probe score $s_{t'}^{(\ell)} > \tau$ for $K$ consecutive steps; the crossing rate is $\mathrm{CR}(\ell) = N^{-1}\!\sum_{i} \mathbb{1}[\mathrm{FCP}_i^{(\ell)} \text{ exists}]$. A multiplicative composite (BA $\times$ crossing rate) serves as the \emph{crossing-rate composite} (CR-composite) baseline, combining classification quality with transition sensitivity. Metrics at a fixed decision threshold (precision, inverse FPR, additive composite) form the \emph{threshold-based} selection. This taxonomy is empirical, but cosine compression at shallow layers predicts a priori that any threshold-crossing metric exhibits shallow-layer bias, confirmed by results (\cref{sec:layer-results}). Crossing rate inflates where representations are compressed (inter-step cosine distances 1.4--2.7$\times$ smaller; \cref{app:cosine_volatility}). Threshold-based metrics share a confusion matrix and empirically converge; BA independently confirms. Results in \cref{sec:layer-results}; full per-layer sweeps in \cref{app:layer_sweep}.\looseness=-1
24	
25	\subsection{Baseline Methods}
26	\label{sec:baselines}
27	
28	We evaluate seven alternatives to contextualize probe performance (\cref{tab:negative}): BOCPD~\citep{adams2007bayesian} and CUSUM~\citep{page1954cusum} for change-point detection; Mahalanobis distance following TrajGuard~\citep{trajguard}; RepE mean-difference directions~\citep{zou2023representation}; two-layer MLP probes; CCS-adapted~\citep{burns2023discovering}; and cross-model transfer via PCA. A position-only baseline ($t/T$) controls for temporal artifacts. Detailed configurations in \cref{app:bocpd_config,app:transfer_details}.
29	
30	\subsection{Evaluation Protocol}
31	\label{sec:evaluation}
32	
33	We report balanced accuracy, precision, pre-CP FPR, coverage, and lead time. We exclude F1 (conflates precision and recall), AUROC (threshold-free, cannot diagnose layer selection bias), and MCC (redundant with BA under balanced priors). Positive classification requires $K{=}5$ consecutive threshold crossings, selected on the R1-8B validation set and held fixed across all models as the value balancing coverage ($\geq$70\%) and safe-trace false positive rate ($\leq$50\%); \cref{tab:k_ablation} confirms that the HS vs.\ text conclusion direction is consistent at $K{=}3$, $5$, and $7$, with coverage and FPR trading off monotonically. Modality comparisons use BCa bootstrap (10{,}000 resamples, resampling traces as clusters: each trace is an independent unit and all its steps are included or excluded together, preserving within-trace dependence)~\citep{efron1993bootstrap,diciccio1996bootstrap} with Holm-Bonferroni step-down (3 metrics $\times$ 4 models $= 12$ tests, $\alpha{=}0.05$); the 4-test framework yields identical conclusions (\cref{app:holm_bonferroni}). For 32B models ($n \leq 20$), the exact permutation test is the primary inference method; BCa confidence intervals are reported for comparability but may have reduced coverage at these sample sizes (BCa assumes approximate pivotality; heavy-tailed score distributions could produce anti-conservative intervals). Within each model, the three metrics are positively correlated, so the correction is stricter than under independence. Control task selectivity~\citep{hewitt2019control} validates genuine structure (\cref{app:control}). $\dagger$ marks sample-limited test sets ($n \leq 20$): R1-32B ($n{=}20$) and QwQ-32B ($n{=}19$).
34	
35	\paragraph{Hyperparameter search space and multiple comparisons.} The full exploration spans ${\sim}$5 metrics $\times$ 7 windows $\times$ 28--64 layers $\approx$ 980--2{,}240 configurations per model. However, the effective number of independent tests is far smaller: the five metrics share one confusion matrix (threshold-based metrics are functionally correlated; \cref{app:effective_tests}), and adjacent layers produce near-identical probes. Effect sizes are large (Cohen's $d{=}0.58$--$2.37$; \cref{app:effective_tests}), arguing against fishing artifacts. A two-stage design protects against selection bias: upstream layer/window exploration uses nested CV and split-half validation at 7--8B (\cref{app:nested_cv,app:split_half}); downstream modality tests apply HB to 12 final comparisons. The 32B models lack nested CV (${\sim}$4 traces per fold) and are marked exploratory ($\dagger$). We classify evidence into three tiers (cross-validated, significant, and exploratory), detailed in \cref{sec:experiments}. All reported p-values are conditional on the selected layer and window, not marginal over the full search space.\looseness=-1
36	
37	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d0224122-6bda-4426-8c6c-79c52c309266",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "7f86ab06-4511-47d2-813f-1378e680f562",
  "sourceToolAssistantUUID": "d0224122-6bda-4426-8c6c-79c52c309266",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-21T22:11:33.771Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PJ5AHHAdNAxYKuUXkynUGd`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7f86ab06-4511-47d2-813f-1378e680f562",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqBc1WNha41QZQQX28",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d0f2cb0f-7e32-45e2-8795-305c8098be8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C4n9indAhTTy2j7sPVRUAV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7259,
      "cache_read_input_tokens": 23026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7259,
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

_source line 24 · 2026-05-21T22:11:33.777Z_

<details><summary>↩ Tool result · `toolu_01PJ5AHHAdNAxYKuUXkynUGd`</summary>

```text
1	\section{Experiments}\label{sec:experiments}
2	
3	We evaluate temporal probes across four reasoning models (\cref{tab:models}), comparing hidden-state (HS) and text modalities under different layer selection criteria.
4	
5	\paragraph{Evidence gradient.} We classify HS advantage evidence into three tiers: \emph{cross-validated}\footnote{In our usage, \emph{cross-validated} means the result survives nested 5-fold cross-validation with a held-out test fold, ruling out hyperparameter overfitting. \emph{Exploratory} ($\dagger$) results pass HB on the holdout split but lack nested CV validation due to sample constraints.} (nested CV pass; 7--8B models), \emph{significant} (HB pass without nested CV; QwQ-32B), and \emph{exploratory} ($^\dagger$, small sample or narrow coverage; R1-32B). Per-model details follow in \cref{sec:layer-results,sec:hs-text,sec:32b-analysis}.
6	
7	\subsection{Setup}\label{sec:setup}
8	
9	We study R1-8B (Llama-8B, R1-distilled, $n{=}43$ test traces), OT-7B (OpenThinker-7B, trained on the OpenThoughts dataset~\citep{openthinker}; Qwen-7B backbone, STILL-trained~\cref{app:ot7b_details}, $n{=}47$), QwQ-32B (Qwen-32B, native reasoning, $n{=}19$--$20$), and R1-32B (Qwen-32B, R1-distilled, $n{=}20$). All traces come from HarmThoughts with step-level CP annotations (60/20/20 split). HS probes extract last-token hidden states from a selected layer; text probes encode each step with all-MiniLM-L6-v2 (384d). Both use L2-regularized logistic regression with temporal windowing $W \in \{1, 3, 5, 10, 15, 20, 25\}$ selected on validation. Classification requires $K{=}5$ consecutive threshold crossings (\cref{tab:k_ablation}). Statistical testing follows \cref{sec:evaluation}.\looseness=-1
10	
11	\subsection{Layer Selection Results}\label{sec:layer-results}
12	
13	\cref{tab:layer_selection} shows that the crossing-rate composite metric (balanced accuracy $\times$ crossing rate) systematically selects shallow layers across all four models: L0 for R1-8B (full L0--L24 sweep; \cref{tab:r18b_full_layer}) and OT-7B, L2 (3\%) for QwQ-32B, and L10 (16\%) for R1-32B. The three threshold-based metrics (precision, inverse FPR, additive composite) share a common confusion matrix and empirically converge to the same deep layer, L63 (98\%) for both 32B models, consistent with their shared structure, though not mathematically guaranteed. Pure balanced accuracy, a threshold-free metric, selects layers that vary across data splits and models (7--98\% depth under 60/20/20; \cref{app:ba_layer_comparison}), itself demonstrating that layer selection is a consequential methodological choice. The mechanism is that shallow layers produce highly compressed representations with small inter-step margins: step-to-step cosine distances are 1.4--2.7$\times$ smaller than at deep layers across all models (\cref{app:cosine_volatility}). A linear probe in this compressed space operates near the noise floor, generating frequent threshold crossings that inflate crossing rate independently of discriminative power (\cref{sec:layer-sensitivity}).\looseness=-1
14	
15	\begin{table}[t]
16	\centering
17	\small
18	\resizebox{\columnwidth}{!}{%
19	\begin{tabular}{lcccc}
20	\toprule
21	\textbf{Model} & \textbf{CR-comp.}$^a$ & \textbf{Thresh.}$^b$ & $p$ \textbf{(thresh.)} & $\Delta$\textbf{Prec}$^c$ \\
22	\midrule
23	R1-8B & L0 (0\%) & L14 (44\%) & ${<}0.001$ & +20.1 \\
24	OT-7B & L0 (0\%) & L16 (57\%) & ${<}0.001$ & +21.9 \\
25	QwQ-32B$^\dagger$ & L2 (3\%) & L63 (98\%) & ${<}0.005$ & +19.2 \\
26	R1-32B$^\dagger$ & L10 (16\%) & L63 (98\%) & ${<}0.001$ & +15.4 \\
27	\bottomrule
28	\end{tabular}}
29	\caption{Layer selection sensitivity. $^a$\,Crossing-rate composite (bal\_acc $\times$ crossing\_rate). $^b$\,Consensus of threshold-based metrics (precision, inverse FPR, additive composite). $^c$\,HS$-$text precision difference (pp) at threshold-based layer (\cref{tab:hs_vs_text}). Rightmost $p$: HS vs.\ text precision $p$-value at threshold-based layer (e.g., QwQ-32B CR-composite layer: $p{=}0.83$, non-significant). $\dagger$\,Sample-limited ($n \leq 20$).}
30	\label{tab:layer_selection}
31	\end{table}
32	
33	\begin{figure}[t]
34	\centering
35	\includegraphics[width=\columnwidth]{figures/fig_layer_heatmap.pdf}
36	\caption{Per-layer metric heatmap (2$\times$2). Each column: one of five metrics (min-max normalized). Red dashed: CR-composite layer (bal\_acc $\times$ crossing\_rate); green dashed: threshold-based layer (consensus of threshold-based metrics). For R1-8B (full L0--L24 sweep), crossing rate drives CR-composite selection to L0 while threshold-based metrics retain L14. At 32B, CR-composite selections cluster near input layers while threshold-based metrics peak at deep layers.}
37	\label{fig:layer_heatmap}
38	\end{figure}
39	
40	The downstream impact is severe: at CR-composite layers, only the two 7--8B models show significant HS advantage; both 32B models fail. The CR-composite's systematic shallow-layer selection is an artifact of cosine compression (\cref{app:cosine_volatility}), not a genuine safety signal; random-label controls confirm this distinction (\cref{app:random_cp}). At threshold-based layers, the HS advantage is graded: cross-validated at 7--8B (OT-7B, R1-8B; nested CV), significant but suggestive of position-competitiveness at QwQ-32B$^\dagger$, and exploratory at R1-32B$^\dagger$ (residualized gap below MDE). The $\dagger$ marks sample-limited test sets ($n \leq 20$) where effect sizes are descriptive rather than confirmatory. Random-label controls on QwQ-32B and R1-8B confirm that threshold-based deep-layer selection requires genuine safety labels; the geometric shallow-layer bias is Qwen-specific: retained on QwQ-32B but dissolved on R1-8B (\cref{app:random_cp}). AUROC, excluded from our primary metrics because it is threshold-free (\cref{sec:evaluation}), confirms HS discriminability at BA-selected layers ($\Delta$AUROC +12.1 to +15.1pp; \cref{tab:ba_layer_results}) but cannot diagnose the threshold-dependent layer selection bias.\looseness=-1
41	
42	\subsection{HS vs.\ Text Comparison}\label{sec:hs-text}
43	
44	\begin{table}[t]
45	\centering
46	\small
47	\resizebox{\columnwidth}{!}{%
48	\begin{tabular}{llclrrlrc}
49	\toprule
50	\textbf{Model} & \textbf{Layer} & \textbf{Enc.} & $W$ & $\Delta$\textbf{BA} & $\Delta$\textbf{Prec} & \textbf{95\% CI} & $\Delta$\textbf{FPR} & \textbf{HB} \\
51	\midrule
52	R1-8B & L14 & 384d & 3 & +17.5 & +20.1 & [+12.4, +28.3] & $-$7.9 & \checkmark \\
53	 & & 1024d & & \multicolumn{1}{c}{--} & +5.8 & [$-$7.4, +19.5] & \multicolumn{1}{c}{--} & \\[2pt]
54	OT-7B & L16 & 384d & 3 & +10.7 & +21.9 & [+14.4, +29.6] & $-$17.1 & \checkmark \\
55	 & & 1024d & & \multicolumn{1}{c}{--} & +18.1 & [+8.4, +29.0] & \multicolumn{1}{c}{--} & \checkmark \\[2pt]
56	QwQ$^\dagger$ & L63 & 384d & 5 & +13.0 & +19.2 & [+9.3, +33.5] & $-$15.0 & \checkmark \\
57	 & & 1024d & & \multicolumn{1}{c}{--} & +9.4 & [$-$7.1, +27.7] & \multicolumn{1}{c}{--} & \\[2pt]
58	R1-32B$^\dagger$ & L63 & 384d & 1 & +18.7 & +15.4 & [+8.7, +22.6] & $-$14.6 & \checkmark \\
59	 & & 1024d & & \multicolumn{1}{c}{--} & +11.7 & [$-$0.2, +24.3] & \multicolumn{1}{c}{--} & \\
60	\bottomrule
61	\end{tabular}}
62	\caption{HS vs.\ text at threshold-based layers (LR probes, 60/20/20 split, 10{,}000 bootstrap resamples). Enc.: text encoder (384d = MiniLM-L6-v2, 1024d = BGE-large). $\Delta$: HS$-$text difference (pp); ``--'' = BA and FPR are not computed for the 1024d comparison because the 384d and 1024d encoders operate at different probe calibration points and do not share a decision threshold. HB: \checkmark{} = model-level test passes Holm-Bonferroni ($\alpha{=}0.05$); all 384d model-level tests pass. $^\dagger$\,Sample-limited ($n \leq 20$); 32B results are exploratory. 1024d: HB over 4 model-level precision tests.}
63	\label{tab:hs_vs_text}
64	\end{table}
65	
66	The HS advantage is encoder-conditional: against BGE-large (1024d), only OT-7B survives HB correction (\cref{app:encoder_robustness}). Multi-seed stability appears in \cref{app:multi_seed}. Against the 384d baseline, HS probes outperform text probes in all four models$^\dagger$ (\cref{tab:hs_vs_text}): cross-validated at 7--8B (OT-7B: +21.9pp precision, R1-8B: +20.1pp), significant but suggestive of position-competitiveness at QwQ-32B$^\dagger$ (+19.2pp), and exploratory at R1-32B$^\dagger$ (+15.4pp, pattern consistent with position mediation). R1-8B FPR is directionally consistent (5/5 seeds) but not robust ($p{=}0.044$, rank 12/12 in HB step-down; 1/5 seeds Bonferroni; \cref{app:multi_seed}). R1-32B passes 5/5 seeds but shows a pattern consistent with position mediation (residualized gap NS; \cref{app:position_residual}); QwQ-32B's position baseline is competitive (\cref{sec:32b-analysis}). Overall, 18/20 model-seed combinations pass full HB (\cref{app:multi_seed}). Control task selectivity confirms genuine safety signal: 11.1--16.8pp above chance (\cref{app:control}). A split-half analysis on OT-7B confirms internal validity (\cref{app:split_half}).\looseness=-1
67	
68	\paragraph{Capacity control.} PCA reduction of HS features to 384d (79--92\% variance retained) preserves the precision advantage across all four models$^\dagger$ (+16.8 to +23.1pp, all $p{<}0.012$, all HB). The control provides partial evidence against a pure capacity explanation. Random projection to 384d yields similar results ($\Delta$Prec +8.3 to +20.5pp; \cref{app:random_projection}), further weakening the capacity explanation. E5-Mistral-7B (4096d, PCA-reduced to 384d; \cref{app:e5_mistral}) yields intermediate results (2/4 HB), forming a monotonic encoder-quality gradient with MiniLM (4/4) and BGE-large (1/4).\looseness=-1
69	
70	\paragraph{Encoder robustness.} Against BGE-large~\citep{xiao2023cpack} (1024d), only OT-7B survives HB (1/4 precision); R1-8B shows adverse FPR direction (+1.2pp). This forms a monotonic encoder-quality gradient: MiniLM-384d (4/4 HB) $\to$ E5-Mistral-4096d$\to$384d (2/4) $\to$ BGE-large-1024d (1/4), with the precision advantage narrowing from +15--22pp to +6--12pp. The HS advantage is thus a function of text encoder capacity (\cref{fig:forest_precision}); layer selection (Contribution 1) is encoder-independent.\looseness=-1
71	
72	\paragraph{Position mediation.} Position ($t/T$) accounts for 9--20pp of balanced accuracy,\footnote{R1-32B's 20.4pp drop reflects $W{=}1$; at $W{\geq}3$, drops are 9--17pp.} but all models retain non-positional signal above chance (all $p{<}0.001$; \cref{app:position_residual}). Three of four models retain significant non-positional HS advantage (residualized gap +3.7 to +6.9pp, HB corrected); R1-32B's gap is +1.9pp ($p{=}0.914$, $n{=}20$), well below the MDE of ${\sim}$9pp and thus indistinguishable from zero at current power. Adding a quadratic position term $(t/T)^2$ does not change significance conclusions for the 7--8B models. However, QwQ-32B's advantage is fully absorbed by the quadratic term (\cref{tab:position_quadratic}), indicating a non-linear position component. Temporal windowing reduces position dependence (\cref{sec:temporal}).\looseness=-1
73	
74	\enlargethispage{7\baselineskip}
75	\paragraph{Caveats.} Nested 5-fold CV confirms the HS precision advantage for both 7--8B models (10/10 folds; \cref{app:nested_cv}), with shrinkage of 13--25\% relative to holdout estimates. OT-7B nested CV selects L21--27 vs.\ holdout L16 vs.\ CR-composite L0; the +21.9pp holdout estimate is an upper bound. R1-32B achieves significance only at $W{=}1$ with 25\% coverage; at $W{\geq}3$, dimensionality prevents significance. QwQ-32B HS lead time is negative ($-$1.2 to +1.9 steps). False alarm rates remain 11--50\%, so current methods characterize the phenomenon rather than constitute production detectors. Per-model details in \cref{sec:32b-analysis}.\looseness=-1
76	
77	\subsection{32B Model-Specific Analysis}\label{sec:32b-analysis}
78	
79	\paragraph{Exploratory 32B analysis.} Both 32B results are exploratory ($n{=}19$--$20$ precludes nested CV). LOO-CV and multi-seed analyses (\cref{app:layer_sweep,app:multi_seed}) provide partial robustness checks but do not substitute for independent validation. R1-32B and QwQ-32B share the Qwen-32B architecture but present opposite detection profiles (\cref{tab:32b_divergence}); training method is one plausible differentiator. Replication with $n{\geq}50$ traces is needed.\looseness=-1
80	
81	\begin{table}[t]
82	\centering
83	\small
84	\resizebox{\columnwidth}{!}{%
85	\begin{tabular}{lcccc}
86	\toprule
87	\textbf{Model} & \textbf{Cov.} & \textbf{Lead (steps)} & \textbf{HB} & \textbf{Pos.\ margin} \\
88	\midrule
89	R1-32B$^\dagger$ & 25\% & +11.7 to +13.3 & \checkmark{} ($W{=}1$) & +14.2pp \\
90	QwQ-32B$^\dagger$ & 74\% & $-$1.2 to +1.9 & \checkmark{} (all $W$) & $-$3.6pp \\
91	\bottomrule
92	\end{tabular}}
93	\caption{32B cross-model divergence ($\dagger$\,sample-limited, $n \leq 20$; MDE at 80\% power: 8.6--9.5pp, \cref{app:power_analysis}; all conclusions exploratory). R1-32B provides limited early identification with narrow coverage; QwQ-32B provides robust significance with poor lead time. HB: \checkmark{} = passes Holm-Bonferroni ($\alpha{=}0.05$). Pos.\ margin: HS BA minus position baseline.}
94	\label{tab:32b_divergence}
95	\end{table}
96	
97	R1-32B suggests commitment 11--13 steps early (+14.2pp over position baseline) but covers only 25\% of traces ($W{=}1$); the precision effect (+15.4pp, CI width 13.9pp) falls below MDE at 80\% power. QwQ-32B achieves significance at all window sizes with 74\% coverage but negative HS lead time; the precision effect (+19.2pp, CI width 24.2pp) exceeds MDE (8.6--9.5pp; \cref{app:power_analysis}) but the position baseline achieves higher BA (0.832 vs.\ 0.796), and the HS precision margin over position (+4.5pp, $p{=}0.133$; \cref{app:position_residual}) is not significant at $n{=}19$. The divergence suggests per-model validation is needed.\looseness=-1
98	
99	\subsection{Temporal Context}\label{sec:temporal}
100	
101	Temporal windowing ($W{>}1$) improves both modalities (\cref{fig:window_ablation}): at 7--8B, the modality advantage (+20.1 to +21.9pp) exceeds temporal improvement (+13pp). GRU models achieve comparable accuracy but higher FPR (\cref{tab:gru_multi_seeds,app:temporal_details}); an adaptive two-stage strategy offers marginal gains (\cref{app:two_stage}).\looseness=-1
102	
103	CP-aligned probe score trajectories (\cref{fig:trajectory} in Appendix) confirm sharper HS transitions at the commitment point, with OT-7B showing the clearest separation and R1-32B the weakest. A forest plot visualizing precision gaps across encoder conditions appears in \cref{fig:forest_precision}.\looseness=-1
104	
105	\subsection{Negative Results}\label{sec:negative}
106	
107	No alternative method consistently matches supervised probing (\cref{tab:negative}). BOCPD~\citep{adams2007bayesian}/CUSUM fail (0\% detection on 3/4 models); Mahalanobis yields near-zero separation; RepE~\citep{zou2023representation} is model-dependent (BA 0.756 vs.\ 0.559); MLP probes overfit; CCS misaligns temporally; cross-model transfer fails (\cref{app:negative_details}). The signal is directional, gradual, model-specific, and linearly separable, which excludes change-point, distance, transfer, and objective-alignment methods respectively.\looseness=-1
108	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d0f2cb0f-7e32-45e2-8795-305c8098be8e",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "c158a0bf-9655-4a05-86b2-d41e577478e6",
  "sourceToolAssistantUUID": "d0f2cb0f-7e32-45e2-8795-305c8098be8e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 25 · 2026-05-21T22:11:34.262Z_

<details open><summary>🔧 Tool call — Read · `toolu_01YNKqCxM7jccLTqzz1fGnbv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "c158a0bf-9655-4a05-86b2-d41e577478e6",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqBc1WNha41QZQQX28",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "bdcafa9e-65ef-4ef8-9183-a1ccf7f1b6b8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C4n9indAhTTy2j7sPVRUAV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7259,
      "cache_read_input_tokens": 23026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7259,
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

_source line 26 · 2026-05-21T22:11:34.266Z_

<details><summary>↩ Tool result · `toolu_01YNKqCxM7jccLTqzz1fGnbv`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	Crossing rate reverses the central finding via shallow-layer compression (\cref{app:cosine_volatility,tab:r18b_full_layer}): its shallow preference is an artifact of cosine compression inflating threshold crossings, while threshold-based deep preference reflects genuine separability~\citep{tenney2019bert}; random-label controls confirm this distinction (\cref{app:random_cp}). C1 generalizes across all four models (cross-dataset: \cref{app:cosine_volatility}; split-half: \cref{app:split_half}); C2 is sample-dependent (7--8B cross-validated, 32B descriptive). Annotation noise (${<}2.5$pp BA change; \cref{tab:cp_perturbation}) does not threaten C1. The encoder-quality gradient narrows the HS advantage (384d to 1024d; \cref{app:position_residual}). Type~I risk from ${\sim}$2{,}240 configurations is bounded by the two-stage design and large effect sizes ($d$ 0.58--2.37; \cref{app:effective_tests}). \textbf{Practical mitigation.} A multi-metric audit (\cref{app:deployment_operating_points}) flags divergent conclusions when ${\geq}3$ metrics differ by ${>}20\%$ of depth. A three-layer ensemble eliminates pre-selection ($p \leq 0.002$; \cref{tab:ensemble}) but lacks cross-validation; this is diagnostic guidance, not a validated method.\looseness=-1
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "bdcafa9e-65ef-4ef8-9183-a1ccf7f1b6b8",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "5b40bae0-d252-43b1-82c2-6f9ff6b3e93e",
  "sourceToolAssistantUUID": "bdcafa9e-65ef-4ef8-9183-a1ccf7f1b6b8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-21T22:11:34.803Z_

<details open><summary>🔧 Tool call — Read · `toolu_016XyGyo8fc9knSupCFMpWQG`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "5b40bae0-d252-43b1-82c2-6f9ff6b3e93e",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqBc1WNha41QZQQX28",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "e6641530-cc03-4bba-99d2-d0ad4b69d9ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C4n9indAhTTy2j7sPVRUAV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7259,
      "cache_read_input_tokens": 23026,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7259,
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

_source line 28 · 2026-05-21T22:11:34.808Z_

<details><summary>↩ Tool result · `toolu_016XyGyo8fc9knSupCFMpWQG`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	Layer selection metric choice can reverse a safety study's central conclusion: for QwQ-32B, the same data yield $p{=}0.83$ or $p{<}0.005$ depending solely on metric. The HS advantage is validated at 7--8B (+20--22pp, nested CV) and exploratory$^\dagger$ at 32B (+15--19pp) against 384d encoders, but conditional on encoder quality and position (partially correlated). The study is limited to HarmThoughts with predominantly Qwen models (3/4); causal validation and broader coverage remain necessary.\looseness=-1
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "e6641530-cc03-4bba-99d2-d0ad4b69d9ad",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "3c267334-c9bb-49b2-be80-130aa17246f9",
  "sourceToolAssistantUUID": "e6641530-cc03-4bba-99d2-d0ad4b69d9ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-21T22:11:35.163Z_

<details open><summary>🔧 Tool call — Read · `toolu_017JRKe8vXm5cvmAMAursiim`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "3c267334-c9bb-49b2-be80-130aa17246f9",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqBc1WNha41QZQQX28",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "56faabe4-d538-4924-ba1e-8f75bb6e0a0d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01C4n9indAhTTy2j7sPVRUAV",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7259,
      "cache_read_input_tokens": 23026,
      "output_tokens": 313,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7259
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 313,
          "cache_read_input_tokens": 23026,
          "cache_creation_input_tokens": 7259,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7259,
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

_source line 30 · 2026-05-21T22:11:35.168Z_

<details><summary>↩ Tool result · `toolu_017JRKe8vXm5cvmAMAursiim`</summary>

```text
1	\newpage
2	\section*{Limitations}\label{sec:limitations}
3	
4	\paragraph{Single dataset and annotation quality.}
5	All CP-dependent claims rely on one dataset (HarmThoughts~\citep{harmthoughts}), the only publicly available dataset providing step-level CP annotations for reasoning model traces, with annotations lacking formal inter-annotator agreement; an LLM-based proxy on AdvBench achieved $\kappa{=}0.606$ (\cref{app:iaa}). The geometric precondition (shallow-layer compression) is confirmed on AdvBench (\cref{app:cosine_volatility,app:advbench_cp}), but generalization to other jailbreak datasets, attack taxonomies, or multilingual settings is untested.
6	
7	\paragraph{Statistical power at 32B.}
8	With $n{=}19$--$20$ traces, the minimum detectable effect at 80\% power is 8.6--9.5pp (\cref{app:power_analysis}); all 32B conclusions marked $\dagger$ should be interpreted with this constraint. False positive rates remain 11--50\% (model-dependent), and R1-32B achieves significance only at $W{=}1$ (25\% coverage). These probes characterize the commitment phenomenon rather than constitute production detectors.
9	
10	\paragraph{Architecture coverage and causal status.}
11	Three of four models share the Qwen architecture; only R1-8B (Llama) provides cross-architecture evidence. Random-label controls confirm the crossing-rate geometric bias is Qwen-specific (\cref{app:random_cp}). Results are correlational; causal intervention (e.g., DAS, activation patching) is needed to confirm mechanistic involvement. Whether metric-induced layer selection bias generalizes to non-reasoning LLMs or encoder-only architectures remains open.
12	
13	\section*{Ethics Statement}
14	This work analyzes safety-relevant reasoning traces to characterize probe behavior, not to circumvent safety mechanisms. All experiments use publicly available models and datasets (HarmThoughts, AdvBench). No human subjects were involved. Code and scripts for all experiments and analyses will be released upon acceptance.
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "56faabe4-d538-4924-ba1e-8f75bb6e0a0d",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "645858af-42d4-44eb-9a73-eff94d8c8ada",
  "sourceToolAssistantUUID": "56faabe4-d538-4924-ba1e-8f75bb6e0a0d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-21T22:11:40.104Z_

<details open><summary>🔧 Tool call — Read · `toolu_01GAbtgZhBMYUFyfUktbteLw`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "645858af-42d4-44eb-9a73-eff94d8c8ada",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqmZfsi1SVc8T1p83a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "181d6441-f3f8-4579-98e8-bda13a1a5f72",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJtw56Br5SNqRR8YnJAkEH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7085,
      "cache_read_input_tokens": 30285,
      "output_tokens": 165,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7085
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 165,
          "cache_read_input_tokens": 30285,
          "cache_creation_input_tokens": 7085,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7085,
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

### Tool call

_source line 32 · 2026-05-21T22:11:40.128Z_

<details open><summary>🔧 Tool call — Read · `toolu_01SgApKk3iBEEmz9WzyThdhi`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "181d6441-f3f8-4579-98e8-bda13a1a5f72",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUqmZfsi1SVc8T1p83a",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "ca5e32b8-5944-4072-a68f-196531078982",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NJtw56Br5SNqRR8YnJAkEH",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7085,
      "cache_read_input_tokens": 30285,
      "output_tokens": 165,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7085
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 165,
          "cache_read_input_tokens": 30285,
          "cache_creation_input_tokens": 7085,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7085,
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

_source line 33 · 2026-05-21T22:11:40.393Z_

<details><summary>↩ Tool result · reported error · `toolu_01GAbtgZhBMYUFyfUktbteLw`</summary>

```text
File content (37324 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "181d6441-f3f8-4579-98e8-bda13a1a5f72",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "3cc546e1-683c-4381-9ebd-323f029a97f8",
  "toolUseResult": "Error: File content (37324 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.",
  "sourceToolAssistantUUID": "181d6441-f3f8-4579-98e8-bda13a1a5f72",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-21T22:11:40.484Z_

<details><summary>↩ Tool result · `toolu_01SgApKk3iBEEmz9WzyThdhi`</summary>

```text
1	@article{trajguard,
2	  title={TrajGuard: Streaming Hidden-state Trajectory Detection for Decoding-time Jailbreak Defense},
3	  author={Liu, Cheng and Liu, Xiaolei and Li, Xingyu and Xin, Bangzhou and Ding, Kangyi},
4	  journal={arXiv preprint arXiv:2604.07727},
5	  year={2026},
6	  url={https://arxiv.org/abs/2604.07727}
7	}
8	
9	@inproceedings{safeswitch,
10	  title={SafeSwitch: Steering Unsafe {LLM} Behavior via Internal Activation Signals},
11	  author={Han, Peixuan and Qian, Cheng and Chen, Xiusi and Zhang, Yuji and Ji, Heng and Zhang, Denghui},
12	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},
13	  year={2025},
14	  url={https://arxiv.org/abs/2502.01042}
15	}
16	
17	@inproceedings{siren,
18	  title={{LLM} Safety From Within: Detecting Harmful Content with Internal Representations},
19	  author={Jiao, Difan and Liu, Yilun and Yuan, Ye and Tang, Zhenwei and Du, Linfeng and Wu, Haolun and Anderson, Ashton},
20	  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (ACL)},
21	  year={2026},
22	  url={https://arxiv.org/abs/2604.18519}
23	}
24	
25	@article{saferemind,
26	  title={How Does the Thinking Step Influence Model Safety? An Entropy-based Safety Reminder for LRMs},
27	  author={Kim, Su-Hyeon and Jin, Hyundong and Lee, Yejin and Han, Yo-Sub},
28	  journal={arXiv preprint arXiv:2601.03662},
29	  year={2026},
30	  url={https://arxiv.org/abs/2601.03662}
31	}
32	
33	@article{safethink,
34	  title={Safety Recovery in Reasoning Models Is Only a Few Early Steering Steps Away},
35	  author={Ghosal, Soumya Suvra and Chakraborty, Souradip and Singh, Vaibhav and Huang, Furong and Manocha, Dinesh and Bedi, Amrit Singh},
36	  journal={arXiv preprint arXiv:2602.11096},
37	  year={2026},
38	  url={https://arxiv.org/abs/2602.11096}
39	}
40	
41	@article{selfjailbreak,
42	  title={Self-Jailbreaking: Language Models Can Reason Themselves Out of Safety Alignment After Benign Reasoning Training},
43	  author={Yong, Zheng-Xin and Bach, Stephen H.},
44	  journal={arXiv preprint arXiv:2510.20956},
45	  year={2025},
46	  url={https://arxiv.org/abs/2510.20956}
47	}
48	
49	@article{harmthoughts,
50	  title={When Safety Fails Before the Answer: Benchmarking Harmful Behavior Detection in Reasoning Chains},
51	  author={Kakkar, Ishita and Zhang, Enze and Uppaal, Rheeya and Hu, Junjie},
52	  journal={arXiv preprint arXiv:2604.19001},
53	  year={2026},
54	  url={https://arxiv.org/abs/2604.19001}
55	}
56	
57	@article{belinkov2019analysis,
58	  title={Analysis Methods in Neural Language Processing: A Survey},
59	  author={Belinkov, Yonatan and Glass, James},
60	  journal={Transactions of the Association for Computational Linguistics},
61	  volume={7},
62	  pages={49--72},
63	  year={2019},
64	  url={https://aclanthology.org/Q19-1004/}
65	}
66	
67	@inproceedings{kaya2019shallow,
68	  title={Shallow-Deep Networks: Understanding and Mitigating Network Overthinking},
69	  author={Kaya, Yigitcan and Hong, Sanghyun and Dumitras, Tudor},
70	  booktitle={Proceedings of the 36th International Conference on Machine Learning (ICML)},
71	  pages={3301--3310},
72	  year={2019},
73	  url={https://arxiv.org/abs/1810.07052}
74	}
75	
76	@inproceedings{zhou2020bert,
77	  title={{BERT} Loses Patience: Fast and Robust Inference with Early Exit},
78	  author={Zhou, Wangchunshu and Xu, Canwen and Ge, Tao and McAuley, Julian and Xu, Ke and Wei, Furu},
79	  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
80	  volume={33},
81	  pages={18330--18341},
82	  year={2020},
83	  url={https://arxiv.org/abs/2006.04152}
84	}
85	
86	@inproceedings{hewitt2019control,
87	  title={Designing and Interpreting Probes with Control Tasks},
88	  author={Hewitt, John and Liang, Percy},
89	  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
90	  pages={2733--2743},
91	  year={2019},
92	  url={https://aclanthology.org/D19-1275/}
93	}
94	
95	@article{zou2023representation,
96	  title={Representation Engineering: A Top-Down Approach to {AI} Transparency},
97	  author={Zou, Andy and Phan, Long and Chen, Sarah and Campbell, James and Guo, Phillip and Ren, Richard and Pan, Alexander and Yin, Xuwang and Mazeika, Mantas and Dombrowski, Ann-Kathrin and Goel, Shashwat and Li, Nathaniel and Byun, Michael J. and Wang, Zifan and Mallen, Alex and Basart, Steven and Koyejo, Sanmi and Song, Dawn and Fredrikson, Matt and Kolter, J. Zico and Hendrycks, Dan},
98	  journal={arXiv preprint arXiv:2310.01405},
99	  year={2023},
100	  url={https://arxiv.org/abs/2310.01405}
101	}
102	
103	@article{adams2007bayesian,
104	  title={Bayesian Online Changepoint Detection},
105	  author={Adams, Ryan Prescott and MacKay, David J.C.},
106	  journal={arXiv preprint arXiv:0710.3742},
107	  year={2007},
108	  url={https://arxiv.org/abs/0710.3742}
109	}
110	
111	@article{deepseekr1,
112	  title={{DeepSeek-R1}: Incentivizing Reasoning Capability in {LLMs} via Reinforcement Learning},
113	  author={{DeepSeek-AI}},
114	  journal={arXiv preprint arXiv:2501.12948},
115	  year={2025},
116	  url={https://arxiv.org/abs/2501.12948}
117	}
118	
119	@misc{qwq,
120	  title={{QwQ}: Reflect Deeply on the Boundaries of the Unknown},
121	  author={{Qwen Team}},
122	  year={2024},
123	  url={https://qwenlm.github.io/blog/qwq-32b-preview/}
124	}
125	
126	@article{openthinker,
127	  title={Open{T}houghts: Data Recipes for Reasoning Models},
128	  author={Guha, Etash and Marten, Ryan and Keh, Sedrick and Bhatia, Saumya and Ragan-Kelley, Jonathan and Narang, Sharan and Hashimoto, Tatsunori},
129	  journal={arXiv preprint arXiv:2506.04178},
130	  year={2025},
131	  url={https://arxiv.org/abs/2506.04178}
132	}
133	
134	@article{still,
135	  title={Imitate, Explore, and Self-Improve: A Reproduction Report on Slow-thinking Reasoning Systems},
136	  author={Min, Yingqian and Chen, Zhipeng and Jiang, Jinhao and Chen, Jie and Deng, Jia and Hu, Yiwen and Tang, Yiru and Wang, Jiapeng and Cheng, Xiaoxue and Song, Huatong and Zhao, Wayne Xin and Liu, Zheng and Wang, Zhongyuan and Wen, Ji-Rong},
137	  journal={arXiv preprint arXiv:2412.09413},
138	  year={2024},
139	  url={https://arxiv.org/abs/2412.09413}
140	}
141	
142	
143	@inproceedings{burns2023discovering,
144	  title={Discovering Latent Knowledge in Language Models Without Supervision},
145	  author={Burns, Collin and Ye, Haotian and Klein, Dan and Steinhardt, Jacob},
146	  booktitle={Proceedings of the International Conference on Learning Representations (ICLR)},
147	  year={2023},
148	  url={https://arxiv.org/abs/2212.03827}
149	}
150	
151	@inproceedings{tenney2019bert,
152	  title={{BERT} Rediscovers the Classical {NLP} Pipeline},
153	  author={Tenney, Ian and Das, Dipanjan and Pavlick, Ellie},
154	  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics (ACL)},
155	  pages={4593--4601},
156	  year={2019},
157	  url={https://aclanthology.org/P19-1452/}
158	}
159	
160	@article{belinkov2022probing,
161	  title={Probing Classifiers: Promises, Shortcomings, and Advances},
162	  author={Belinkov, Yonatan},
163	  journal={Computational Linguistics},
164	  volume={48},
165	  number={1},
166	  pages={207--219},
167	  year={2022},
168	  url={https://aclanthology.org/2022.cl-1.7/}
169	}
170	
171	@inproceedings{zhou2024alignment,
172	  title={How Alignment and Jailbreak Work: Explain {LLM} Safety through Intermediate Hidden States},
173	  author={Zhou, Zhenhong and Yu, Haiyang and Zhang, Xinghua and Xu, Rongwu and Huang, Fei and Li, Yongbin},
174	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2024},
175	  pages={2461--2488},
176	  year={2024},
177	  url={https://arxiv.org/abs/2406.05644}
178	}
179	
180	@inproceedings{zhao2025harmfulness,
181	  title={{LLMs} Encode Harmfulness and Refusal Separately},
182	  author={Zhao, Jiachen and Huang, Jing and Wu, Zhengxuan and Bau, David and Shi, Weiyan},
183	  booktitle={Advances in Neural Information Processing Systems 38 (NeurIPS)},
184	  year={2025},
185	  url={https://arxiv.org/abs/2507.11878}
186	}
187	
188	@inproceedings{arditi2024refusal,
189	  title={Refusal in Language Models Is Mediated by a Single Direction},
190	  author={Arditi, Andy and Obeso, Oscar and Syed, Aaquib and Paleka, Daniel and Panickssery, Nina and Gurnee, Wes and Nanda, Neel},
191	  booktitle={Advances in Neural Information Processing Systems 37 (NeurIPS)},
192	  year={2024},
193	  url={https://arxiv.org/abs/2406.11717}
194	}
195	
196	@article{hcot2025,
197	  title={H-CoT: Hijacking the Chain-of-Thought Safety Reasoning Mechanism to Jailbreak Large Reasoning Models},
198	  author={Kuo, Martin and Zhang, Jianyi and Ding, Aolin and Wang, Qinsi and DiValentin, Louis and Bao, Yujia and Wei, Wei and Li, Hai and Chen, Yiran},
199	  journal={arXiv preprint arXiv:2502.12893},
200	  year={2025},
201	  url={https://arxiv.org/abs/2502.12893}
202	}
203	
204	@article{safedream2026,
205	  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},
206	  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},
207	  journal={arXiv preprint arXiv:2604.16824},
208	  year={2026},
209	  url={https://arxiv.org/abs/2604.16824}
210	}
211	
212	@article{hu2026refusal_dynamics,
213	  title={Tracing the Dynamics of Refusal: Exploiting Latent Refusal Trajectories for Robust Jailbreak Detection},
214	  author={Hu, Xulin and Wang, Che and Lim, Wei Yang Bryan and Gao, Jianbo and Chen, Zhong},
215	  journal={arXiv preprint arXiv:2605.02958},
216	  year={2026},
217	  url={https://arxiv.org/abs/2605.02958}
218	}
219	
220	@article{ahrend2026safer_traces,
221	  title={Safer Reasoning Traces: Measuring and Mitigating Chain-of-Thought Leakage in {LLMs}},
222	  author={Ahrend, Patrick and Eder, Tobias and Yang, Xiyang and Pan, Zhiyi and Groh, Georg},
223	  journal={arXiv preprint arXiv:2603.05618},
224	  year={2026},
225	  url={https://arxiv.org/abs/2603.05618}
226	}
227	
228	@article{chen2025unfaithful,
229	  title={Reasoning Models Don't Always Say What They Think},
230	  author={Chen, Yanda and Benton, Joe and Radhakrishnan, Ansh and Uesato, Jonathan and Denison, Carson and Schulman, John and Somani, Arushi and Hase, Peter and Wagner, Misha and Roger, Fabien and Mikulik, Vlad and Bowman, Samuel R. and Leike, Jan and Kaplan, Jared and Perez, Ethan},
231	  journal={arXiv preprint arXiv:2505.05410},
232	  year={2025},
233	  url={https://arxiv.org/abs/2505.05410}
234	}
235	
236	@article{wang2025lrmsafety,
237	  title={Safety in Large Reasoning Models: A Survey},
238	  author={Wang, Cheng and Liu, Yue and Bi, Baolong and Zhang, Duzhen and Li, Zhongzhi and Ma, Yingwei and He, Yufei and Yu, Shengju and Li, Xinfeng and Fang, Junfeng and Zhang, Jiaheng and Hooi, Bryan},
239	  journal={arXiv preprint arXiv:2504.17704},
240	  year={2025},
241	  url={https://arxiv.org/abs/2504.17704}
242	}
243	
244	@article{geiger2023causal,
245	  title={Causal Abstraction: A Theoretical Foundation for Mechanistic Interpretability},
246	  author={Geiger, Atticus and Ibeling, Duligur and Zur, Amir and Chaudhary, Maheep and Chauhan, Sonakshi and Huang, Jing and Arora, Aryaman and Wu, Zhengxuan and Goodman, Noah and Potts, Christopher and Icard, Thomas},
247	  journal={Journal of Machine Learning Research},
248	  volume={26},
249	  number={83},
250	  pages={1--64},
251	  year={2023},
252	  url={https://jmlr.org/papers/v26/23-0058.html}
253	}
254	
255	@inproceedings{alain2017understanding,
256	  title={Understanding Intermediate Layers Using Linear Classifier Probes},
257	  author={Alain, Guillaume and Bengio, Yoshua},
258	  booktitle={Workshop Track, International Conference on Learning Representations (ICLR)},
259	  year={2017},
260	  url={https://arxiv.org/abs/1610.01644}
261	}
262	
263	@inproceedings{conneau2018probing,
264	  title={What You Can Cram into a Single \$\&!\#* Vector: Probing Sentence Embeddings for Linguistic Properties},
265	  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\"{i}c and Baroni, Marco},
266	  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics (ACL)},
267	  pages={2126--2136},
268	  year={2018},
269	  url={https://aclanthology.org/P18-1198/}
270	}
271	
272	@article{joad2026refusal_multi,
273	  title={There Is More to Refusal in Large Language Models than a Single Direction},
274	  author={Joad, Faaiz and Hawasly, Majd and Boughorbel, Sabri and Durrani, Nadir and Sencar, Husrev Taha},
275	  journal={arXiv preprint arXiv:2602.02132},
276	  year={2026},
277	  url={https://arxiv.org/abs/2602.02132}
278	}
279	
280	@inproceedings{wollschlager2025geometry,
281	  title={The Geometry of Refusal in Large Language Models: Concept Cones and Representational Independence},
282	  author={Wollschl\"{a}ger, Tom and Elstner, Jannes and Geisler, Simon and Cohen-Addad, Vincent and G\"{u}nnemann, Stephan and Gasteiger, Johannes},
283	  booktitle={Proceedings of the 42nd International Conference on Machine Learning (ICML)},
284	  year={2025},
285	  url={https://arxiv.org/abs/2502.17420}
286	}
287	
288	@article{korbak2025cot_monitorability,
289	  title={Chain of Thought Monitorability: A New and Fragile Opportunity for {AI} Safety},
290	  author={Korbak, Tomek and Balesni, Mikita and Barnes, Elizabeth and Bengio, Yoshua and Benton, Joe and Bloom, Joseph and Chen, Mark and Cooney, Alan and Dafoe, Allan and Dragan, Anca and Emmons, Scott and Evans, Owain and Farhi, David and Greenblatt, Ryan and Hendrycks, Dan and Hobbhahn, Marius and Hubinger, Evan and Irving, Geoffrey and Jenner, Erik and Kokotajlo, Daniel and Krakovna, Victoria and Legg, Shane and Lindner, David and Luan, David and M\k{a}dry, Aleksander and Michael, Julian and Nanda, Neel and Orr, Dave and Pachocki, Jakub and Perez, Ethan and Phuong, Mary and Roger, Fabien and Saxe, Joshua and Shlegeris, Buck and Soto, Mart\'{i}n and Steinberger, Eric and Wang, Jasmine and Zaremba, Wojciech and Baker, Bowen and Shah, Rohin and Mikulik, Vlad},
291	  journal={arXiv preprint arXiv:2507.11473},
292	  year={2025},
293	  url={https://arxiv.org/abs/2507.11473}
294	}
295	
296	@article{hagendorff2026lrm_jailbreak,
297	  title={Large Reasoning Models Are Autonomous Jailbreak Agents},
298	  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},
299	  journal={Nature Communications},
300	  year={2026},
301	  url={https://arxiv.org/abs/2508.04039}
302	}
303	
304	@inproceedings{qi2025shallow_alignment,
305	  title={Safety Alignment Should Be Made More Than Just a Few Tokens Deep},
306	  author={Qi, Xiangyu and Panda, Ashwinee and Lyu, Kaifeng and Ma, Xiao and Roy, Subhrajit and Beirami, Ahmad and Mittal, Prateek and Henderson, Peter},
307	  booktitle={Proceedings of the International Conference on Learning Representations (ICLR)},
308	  year={2025},
309	  url={https://arxiv.org/abs/2406.05946}
310	}
311	
312	@inproceedings{belrose2023tunedlens,
313	  title={Eliciting Latent Predictions from Transformers with the Tuned Lens},
314	  author={Belrose, Nora and Furman, Zach and Smith, Logan and Halber{\v{s}}tadt, Rusheb and Paige, Brooks and Tegmark, Max and Biderman, Stella},
315	  booktitle={International Conference on Learning Representations (ICLR)},
316	  year={2023},
317	  url={https://arxiv.org/abs/2303.08112}
318	}
319	
320	@inproceedings{belrose2023leace,
321	  title={{LEACE}: Perfect Linear Concept Erasure in Closed Form},
322	  author={Belrose, Nora and Schneider-Joseph, David and Ravfogel, Shauli and Cotterell, Ryan and Raff, Edward and Biderman, Stella},
323	  booktitle={Advances in Neural Information Processing Systems 36 (NeurIPS)},
324	  year={2023},
325	  url={https://arxiv.org/abs/2306.03819}
326	}
327	
328	@article{elazar2021amnesic,
329	  title={Amnesic Probing: Behavioral Explanation with Amnesic Counterfactuals},
330	  author={Elazar, Yanai and Ravfogel, Shauli and Jacovi, Alon and Goldberg, Yoav},
331	  journal={Transactions of the Association for Computational Linguistics},
332	  volume={9},
333	  pages={160--175},
334	  year={2021},
335	  url={https://aclanthology.org/2021.tacl-1.10/}
336	}
337	
338	@article{mao2025selfjailbreak_reasoning,
339	  title={When Models Outthink Their Safety: Unveiling and Mitigating Self-Jailbreak in Large Reasoning Models},
340	  author={Mao, Yingzhi and Zhang, Chunkang and Wang, Junxiang and Guan, Xinyan and Cao, Boxi and Lu, Yaojie and Lin, Hongyu and Han, Xianpei and Sun, Le},
341	  journal={arXiv preprint arXiv:2510.21285},
342	  year={2025},
343	  url={https://arxiv.org/abs/2510.21285}
344	}
345	
346	@article{alvarez2026transport_geometry,
347	  title={Where Does Reasoning Break? Step-Level Hallucination Detection via Hidden-State Transport Geometry},
348	  author={Alvarez, Tyler and Baheri, Ali},
349	  journal={arXiv preprint arXiv:2605.13772},
350	  year={2026},
351	  note={Concurrent work},
352	  url={https://arxiv.org/abs/2605.13772}
353	}
354	
355	@book{efron1993bootstrap,
356	  title={An Introduction to the Bootstrap},
357	  author={Efron, Bradley and Tibshirani, Robert J.},
358	  year={1993},
359	  publisher={Chapman \& Hall/CRC}
360	}
361	
362	@article{diciccio1996bootstrap,
363	  title={Bootstrap confidence intervals},
364	  author={DiCiccio, Thomas J and Efron, Bradley},
365	  journal={Statistical Science},
366	  volume={11},
367	  number={3},
368	  pages={189--228},
369	  year={1996}
370	}
371	
372	@article{baker2025monitoring,
373	  title={Monitoring Reasoning Models for Misbehavior and the Risks of Promoting Obfuscation},
374	  author={Baker, Bowen and Huizinga, Joost and Gao, Leo and Dou, Zehao and Guan, Melody Y. and Madry, Aleksander and Zaremba, Wojciech and Pachocki, Jakub and Farhi, David},
375	  journal={arXiv preprint arXiv:2503.11926},
376	  year={2025},
377	  url={https://arxiv.org/abs/2503.11926}
378	}
379	
380	@article{kadali2025internal,
381	  title={Do Internal Layers of {LLMs} Reveal Patterns for Jailbreak Detection?},
382	  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},
383	  journal={arXiv preprint arXiv:2510.06594},
384	  year={2025},
385	  url={https://arxiv.org/abs/2510.06594}
386	}
387	
388	@article{yin2025refusal_cliff,
389	  title={Refusal Falls off a Cliff: How Safety Alignment Fails in Reasoning?},
390	  author={Yin, Qingyu and Leong, Chak Tou and Yang, Linyi and Huang, Wenxuan and Li, Wenjie and Wang, Xiting and Yoon, Jaehong and Xing, Yun and Yu, Xing and Gu, Jinjin},
391	  journal={arXiv preprint arXiv:2510.06036},
392	  year={2025},
393	  url={https://arxiv.org/abs/2510.06036}
394	}
395	
396	@article{boxo2025linear_probes,
397	  title={Linear Probes Rely on Textual Evidence: Results from Leakage Mitigation Studies in Language Models},
398	  author={Boxo, Gerard and Neelappa, Aman and Raval, Shivam},
399	  journal={arXiv preprint arXiv:2509.21344},
400	  year={2025},
401	  url={https://arxiv.org/abs/2509.21344}
402	}
403	
404	@article{xiang2025guardreasoner,
405	  title={{GuardReasoner}: Towards Reasoning-based {LLM} Safeguards},
406	  author={Liu, Yue and Gao, Hongcheng and Zhai, Shengfang and He, Yufei and Xia, Jun and Hu, Zhengyu and Chen, Yulin and Yang, Xihong and Zhang, Jiaheng and Li, Stan Z. and Xiong, Hui and Hooi, Bryan},
407	  journal={arXiv preprint arXiv:2501.18492},
408	  year={2025},
409	  url={https://arxiv.org/abs/2501.18492}
410	}
411	
412	
413	@inproceedings{reimers2019sentence,
414	  title={Sentence-{BERT}: Sentence Embeddings using Siamese {BERT}-Networks},
415	  author={Reimers, Nils and Gurevych, Iryna},
416	  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
417	  pages={3982--3992},
418	  year={2019},
419	  url={https://aclanthology.org/D19-1410/}
420	}
421	
422	@inproceedings{wang2020minilm,
423	  title={{MiniLM}: Deep Self-Attention Distillation for Task-Agnostic Compression of Pre-Trained Transformers},
424	  author={Wang, Wenhui and Wei, Furu and Dong, Li and Bao, Hangbo and Yang, Nan and Zhou, Ming},
425	  booktitle={Advances in Neural Information Processing Systems 33 (NeurIPS)},
426	  year={2020},
427	  url={https://arxiv.org/abs/2002.10957}
428	}
429	
430	@article{xiao2023cpack,
431	  title={C-Pack: Packaged Resources to Advance General Chinese Embedding},
432	  author={Xiao, Shitao and Liu, Zheng and Zhang, Peitian and Muennighoff, Niklas},
433	  journal={arXiv preprint arXiv:2309.07597},
434	  year={2023},
435	  url={https://arxiv.org/abs/2309.07597}
436	}
437	
438	@article{page1954cusum,
439	  title={Continuous Inspection Schemes},
440	  author={Page, E. S.},
441	  journal={Biometrika},
442	  volume={41},
443	  number={1/2},
444	  pages={100--115},
445	  year={1954}
446	}
447	
448	@inproceedings{jawahar2019bert,
449	  title={What Does {BERT} Learn about the Structure of Language?},
450	  author={Jawahar, Ganesh and Sagot, Beno{\^i}t and Seddah, Djam{\'e}},
451	  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics (ACL)},
452	  pages={3651--3657},
453	  year={2019},
454	  url={https://aclanthology.org/P19-1356}
455	}
456	
457	@inproceedings{voita2020information,
458	  title={Information-Theoretic Probing with Minimum Description Length},
459	  author={Voita, Elena and Titov, Ivan},
460	  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
461	  pages={183--196},
462	  year={2020},
463	  url={https://aclanthology.org/2020.emnlp-main.14}
464	}
465	
466	@inproceedings{pimentel2020information,
467	  title={Information-Theoretic Probing for Linguistic Structure},
468	  author={Pimentel, Tiago and Valvoda, Josef and Hall Maudslay, Rowan and Zmigrod, Ran and Williams, Adina and Cotterell, Ryan},
469	  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics (ACL)},
470	  pages={4609--4622},
471	  year={2020},
472	  url={https://aclanthology.org/2020.acl-main.420}
473	}
474	
475	@inproceedings{ravfogel2020null,
476	  title={Null It Out: Guarding Protected Attributes by Iterative Nullspace Projection},
477	  author={Ravfogel, Shauli and Elazar, Yanai and Gonen, Hila and Twiton, Michael and Goldberg, Yoav},
478	  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics (ACL)},
479	  pages={7237--7256},
480	  year={2020},
481	  url={https://aclanthology.org/2020.acl-main.647}
482	}
483	
484	@inproceedings{ravfogel2022rlace,
485	  title={Linear Adversarial Concept Erasure},
486	  author={Ravfogel, Shauli and Twiton, Michael and Goldberg, Yoav and Cotterell, Ryan},
487	  booktitle={Proceedings of the 39th International Conference on Machine Learning (ICML)},
488	  pages={18400--18421},
489	  year={2022},
490	  volume={162},
491	  series={Proceedings of Machine Learning Research},
492	  publisher={PMLR},
493	  url={https://proceedings.mlr.press/v162/ravfogel22a.html}
494	}
495	
496	@article{rogers2020primer,
497	  title={A Primer in {BERTology}: What We Know About How {BERT} Works},
498	  author={Rogers, Anna and Kovaleva, Olga and Rumshisky, Anna},
499	  journal={Transactions of the Association for Computational Linguistics},
500	  volume={8},
501	  pages={842--866},
502	  year={2020},
503	  url={https://aclanthology.org/2020.tacl-1.54}
504	}
505	
506	@article{wang2024e5mistral,
507	  title={Improving Text Embeddings with Large Language Models},
508	  author={Wang, Liang and Yang, Nan and Huang, Xiaolong and Yang, Linjun and Majumder, Rangan and Wei, Furu},
509	  journal={arXiv preprint arXiv:2401.00368},
510	  year={2024},
511	  url={https://arxiv.org/abs/2401.00368}
512	}
513	
514	
515	@article{marks2024geometry,
516	  title={The Geometry of Truth: Emergent Linear Structure in Large Language Model Representations of True/False Datasets},
517	  author={Marks, Samuel and Tegmark, Max},
518	  journal={arXiv preprint arXiv:2310.06824},
519	  year={2024},
520	  url={https://arxiv.org/abs/2310.06824}
521	}
522	
523	@article{gelman2013garden,
524	  title={The Garden of Forking Paths: Why Multiple Comparisons Can Be a Problem, Even When There Is No ``Fishing Expedition'' or ``p-Hacking'' and the Research Hypothesis Was Posited Ahead of Time},
525	  author={Gelman, Andrew and Loken, Eric},
526	  journal={Department of Statistics, Columbia University},
527	  year={2013},
528	  url={http://www.stat.columbia.edu/~gelman/research/unpublished/p_hacking.pdf}
529	}
530	
531	@inproceedings{azaria2023internal,
532	  title={The Internal State of an {LLM} Knows When It's Lying},
533	  author={Azaria, Amos and Mitchell, Tom},
534	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},
535	  pages={967--976},
536	  year={2023},
537	  url={https://aclanthology.org/2023.findings-emnlp.68/}
538	}
539	
540	@inproceedings{turpin2023language,
541	  title={Language Models Don't Always Say What They Think: Unfaithful Explanations in Chain-of-Thought Prompting},
542	  author={Turpin, Miles and Michael, Julian and Perez, Ethan and Bowman, Samuel R.},
543	  booktitle={Advances in Neural Information Processing Systems},
544	  volume={36},
545	  year={2023},
546	  url={https://arxiv.org/abs/2305.04388}
547	}
548	
549	@article{pais2026linear_probe_scaling,
550	  title={Linear Probe Accuracy Scales with Model Size and Benefits from Multi-Layer Ensembling},
551	  author={Nordby, Erik and Pais, Tasha and Parrack, Aviel},
552	  journal={arXiv preprint arXiv:2604.13386},
553	  year={2026},
554	  url={https://arxiv.org/abs/2604.13386}
555	}
556	
557	@inproceedings{jiang2025hiddendetect,
558	  title={{HiddenDetect}: Detecting Jailbreak Attacks against Large Vision-Language Models via Monitoring Hidden States},
559	  author={Jiang, Yilei and Gao, Xinyan and Peng, Tianshuo and Tan, Yingshui and Zhu, Xiaoyong and Zheng, Bo and Yue, Xiangyu},
560	  booktitle={Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (ACL)},
561	  year={2025},
562	  url={https://arxiv.org/abs/2502.14744}
563	}
564	
565	@inproceedings{safeint2025,
566	  title={{SafeInt}: Shielding Large Language Models from Jailbreak Attacks via Safety-Aware Representation Intervention},
567	  author={Wu, Jiaqi and Chen, Chen and Hou, Chunyan and Yuan, Xiaojie},
568	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},
569	  year={2025},
570	  url={https://arxiv.org/abs/2502.15594}
571	}
572	
573	@inproceedings{rcs2026,
574	  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},
575	  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},
576	  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics (ACL)},
577	  year={2026},
578	  url={https://arxiv.org/abs/2512.12069}
579	}
580	
581	@article{chan2025probing,
582	  title={Can We Predict Alignment Before Models Finish Thinking? {Towards} Monitoring Misaligned Reasoning Models},
583	  author={Chan, Yik Siu and Yong, Zheng-Xin and Bach, Stephen H.},
584	  journal={arXiv preprint arXiv:2507.12428},
585	  year={2025},
586	  url={https://arxiv.org/abs/2507.12428}
587	}
588	
589	@article{zhao2026safeprobing,
590	  title={Defending Large Language Models Against Jailbreak Attacks via In-Decoding Safety-Awareness Probing},
591	  author={Zhao, Yinzhi and Wang, Ming and Feng, Shi and Yang, Xiaocui and Wang, Daling and Zhang, Yifei},
592	  journal={arXiv preprint arXiv:2601.10543},
593	  year={2026},
594	  url={https://arxiv.org/abs/2601.10543}
595	}
596	
597	@article{chia2025probing_subspaces,
598	  title={Probing Latent Subspaces in {LLM} for {AI} Security: Identifying and Manipulating Adversarial States},
599	  author={Chia, Yik Siu and Pan, Shirui},
600	  journal={arXiv preprint arXiv:2503.09066},
601	  year={2025},
602	  url={https://arxiv.org/abs/2503.09066}
603	}
604	
605	@article{chrabaszcz2026monitoring,
606	  title={Monitoring the Internal Monologue: Probe Trajectories Reveal Reasoning Dynamics},
607	  author={Chrab\k{a}szcz, Maciej and Szymczyk, Aleksander and Sendera, Marcin and Trzci\'{n}ski, Tomasz and Cygert, Sebastian},
608	  journal={arXiv preprint arXiv:2605.18549},
609	  year={2026},
610	  note={Concurrent work},
611	  url={https://arxiv.org/abs/2605.18549}
612	}
613	
614	@article{damirchi2026truth,
615	  title={Truth as a Trajectory: What Internal Representations Reveal About Large Language Model Reasoning},
616	  author={Damirchi, Hamed and Meza De la Jara, Ignacio and Abbasnejad, Ehsan and Shamsi, Afshar and Zhang, Zhen and Shi, Javen},
617	  journal={arXiv preprint arXiv:2603.01326},
618	  year={2026},
619	  url={https://arxiv.org/abs/2603.01326}
620	}
621	
622	@article{zhang2025reasoning_right,
623	  title={Reasoning Models Know When They're Right: Probing Hidden States for Self-Verification},
624	  author={Zhang, Anqi and Chen, Yulin and Pan, Jane and Zhao, Chen and Panda, Aurojit and Li, Jinyang and He, He},
625	  journal={arXiv preprint arXiv:2504.05419},
626	  year={2025},
627	  url={https://arxiv.org/abs/2504.05419}
628	}
629	
630	@article{meyoyan2026bertology,
631	  title={A BERTology View of LLM Orchestrations: Token- and Layer-Selective Probes for Efficient Single-Pass Classification},
632	  author={Meyoyan, Gonzalo Ariel and Del Corro, Luciano},
633	  journal={arXiv preprint arXiv:2601.13288},
634	  year={2026},
635	  url={https://arxiv.org/abs/2601.13288}
636	}
637	
638	@article{schulz2025roadmap,
639	  title={A Concrete Roadmap towards Safety Cases based on Chain-of-Thought Monitoring},
640	  author={Schulz, Till},
641	  journal={arXiv preprint arXiv:2510.19476},
642	  year={2025},
643	  url={https://arxiv.org/abs/2510.19476}
644	}
645	
646	
647	@book{cohen1988statistical,
648	  title={Statistical Power Analysis for the Behavioral Sciences},
649	  author={Cohen, Jacob},
650	  year={1988},
651	  edition={2nd},
652	  publisher={Lawrence Erlbaum Associates}
653	}
654	
655	@article{templeton2024scaling,
656	  title={Scaling Monosemanticity: Extracting Interpretable Features from {Claude} 3 {Sonnet}},
657	  author={Templeton, Adly and Conerly, Tom and Marcus, Jonathan and Lindsey, Jack and Bricken, Trenton and Chen, Brian and Pearce, Adam and Citro, Craig and Ameisen, Emmanuel and Jones, Andy and Cunningham, Hoagy and Turner, Nicholas L and McDougall, Callum and MacDiarmid, Monte and Freeman, C. Daniel and Sumers, Theodore R and Rees, Edward and Batson, Joshua and Jermyn, Adam and Carter, Shan and Olah, Chris and Henighan, Tom},
658	  journal={Transformer Circuits Thread},
659	  year={2024}
660	}
661	
662	@article{turner2023activation,
663	  title={Activation Addition: Steering Language Models Without Optimization},
664	  author={Turner, Alexander Matt and Thiergart, Lisa and Udell, David and Leech, Gavin and Mini, Ulisse and MacDiarmid, Monte},
665	  journal={arXiv preprint arXiv:2308.10248},
666	  year={2023}
667	}
668	
669	@inproceedings{li2023iti,
670	  title={Inference-Time Intervention: Eliciting Truthful Answers from a Language Model},
671	  author={Li, Kenneth and Patel, Oam and Vi{\'e}gas, Fernanda and Pfister, Hanspeter and Wattenberg, Martin},
672	  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
673	  year={2023},
674	  url={https://arxiv.org/abs/2306.03341}
675	}
676	
677	@article{levinstein2024liedetector,
678	  title={Still No Lie Detector for Language Models},
679	  author={Levinstein, Benjamin A. and Herrmann, Daniel A.},
680	  journal={arXiv preprint arXiv:2307.00175},
681	  year={2024},
682	  url={https://arxiv.org/abs/2307.00175}
683	}
684	
685	@article{advbench,
686	  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},
687	  author={Zou, Andy and Wang, Zifan and Kolter, J. Zico and Fredrikson, Matt},
688	  journal={arXiv preprint arXiv:2307.15043},
689	  year={2023}
690	}
691	
692	@article{vitel2025layer,
693	  title={First is Not Really Better Than Last: Evaluating Layer Choice and Aggregation Strategies in Language Model Data Influence Estimation},
694	  author={Vitel, Dmytro and Chhabra, Anshuman},
695	  journal={arXiv preprint arXiv:2511.04715},
696	  year={2025},
697	  url={https://arxiv.org/abs/2511.04715}
698	}
699	
700	@article{zhou2025ghost,
701	  title={Exposing the Ghost in the Transformer: Abnormal Detection for Large Language Models via Hidden State Forensics},
702	  author={Zhou, Shide and Wang, Kailong and Shi, Ling and Wang, Haoyu},
703	  journal={arXiv preprint arXiv:2504.00446},
704	  year={2025},
705	  url={https://arxiv.org/abs/2504.00446}
706	}
707	
708	@article{carpenter2000bootstrap,
709	  title={Bootstrap confidence intervals: when, which, what? {A} practical guide for medical statisticians},
710	  author={Carpenter, James and Bithell, John},
711	  journal={Statistics in Medicine},
712	  volume={19},
713	  number={9},
714	  pages={1141--1164},
715	  year={2000},
716	  publisher={Wiley}
717	}
718	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ca5e32b8-5944-4072-a68f-196531078982",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "b8cf40a2-f8d1-4854-ae6b-a34848f6fead",
  "sourceToolAssistantUUID": "ca5e32b8-5944-4072-a68f-196531078982",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 35 · 2026-05-21T22:11:45.911Z_

Now let me read the appendix for additional context on the experimental details.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b8cf40a2-f8d1-4854-ae6b-a34848f6fead",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUrA422Qw8N3R28ye83",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a896201b-16d5-4179-a58f-ac0ac391d940",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKpFpfU9aDscLDtBTqULbj",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12980,
      "cache_read_input_tokens": 37370,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 12980,
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

_source line 36 · 2026-05-21T22:11:47.697Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CpWxcjP3wmP7UFLsw4k7rU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections/appendix.tex",
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a896201b-16d5-4179-a58f-ac0ac391d940",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUrA422Qw8N3R28ye83",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "07793ac9-62bd-46b1-909f-e02fdc9825e5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YKpFpfU9aDscLDtBTqULbj",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 12980,
      "cache_read_input_tokens": 37370,
      "output_tokens": 125,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 12980
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 125,
          "cache_read_input_tokens": 37370,
          "cache_creation_input_tokens": 12980,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 12980,
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

_source line 37 · 2026-05-21T22:11:47.702Z_

<details><summary>↩ Tool result · `toolu_01CpWxcjP3wmP7UFLsw4k7rU`</summary>

```text
1	\appendix
2	
3	\noindent\textbf{Appendix Contents:}
4	\cref{app:checklist}~Responsible NLP Research Checklist;
5	\cref{app:layer_sweep}~Layer Sweep Results;
6	\cref{app:cosine_volatility}~Representation Compression Analysis;
7	\cref{app:holm_bonferroni}~Holm-Bonferroni Correction;
8	\cref{app:window_ablation}~Window Size Ablation;
9	\cref{app:ot7b_details}~OpenThinker-7B Details;
10	\cref{app:gru_details}~GRU Training Details;
11	\cref{app:control}~Control Task Methodology;
12	\cref{sec:oracle}~Oracle Upper Bound;
13	\cref{app:cp_perturbation}~CP Annotation Perturbation;
14	\cref{app:bocpd_config}~BOCPD/CUSUM Configuration;
15	\cref{app:k_ablation}~Detection Threshold Ablation;
16	\cref{app:threshold_sensitivity}~Decision Threshold Sensitivity;
17	\cref{app:bug}~M002 Bug Disclosure;
18	\cref{app:two_stage}~Adaptive Two-Stage Detection;
19	\cref{app:temporal_details}~Temporal Ablation Details;
20	\cref{app:negative_details}~Negative Results Details (incl.\ \cref{tab:negative});
21	\cref{app:transfer_details}~Cross-Model Transfer Details;
22	\cref{app:encoder_robustness}~Encoder Robustness;
23	\cref{app:random_projection}~Random Projection Baseline;
24	\cref{app:e5_mistral}~LLM-Based Text Encoder;
25	\cref{app:position_residual}~Position-Residualized Probing;
26	\cref{app:hyperparameter_robustness}~Hyperparameter Robustness;
27	\cref{app:multi_seed}~Multi-Seed Stability;
28	\cref{app:split_half}~Split-Half Internal Validity;
29	\cref{app:ba_layer_comparison}~BA-Layer Modality Comparison;
30	\cref{app:power_analysis}~Post-Hoc Power Analysis.
31	
32	\section{Responsible NLP Research Checklist}
33	\label{app:checklist}
34	
35	We address the ARR Responsible NLP Research requirements below.
36	
37	\begin{itemize}
38	    \item \textbf{Limitations discussed:} Yes (\cref{sec:limitations}).
39	    \item \textbf{Potential risks:} This research analyzes jailbreak traces to understand how reasoning models commit to generating harmful content. We do not develop new attack methods or release jailbreak prompts. All analyzed content comes from the publicly available HarmThoughts benchmark. We acknowledge a dual-use concern: safety probes that detect commitment could in principle be used to craft reasoning traces that evade detection. We believe the defensive value of understanding commitment dynamics outweighs this risk, as evasion requires white-box access to the probe, which a deployed monitoring system would not expose.
40	    \item \textbf{Computational budget:} Our experiments involve 4 models with 209, 228, 100, and 95 traces respectively (632 total), using linear probes and single-layer GRUs. Total compute is minimal (under 4 GPU-hours on a single RTX A6000). No large-scale pretraining or finetuning was performed.
41	    \item \textbf{Data:} We use HarmThoughts, a publicly available benchmark with step-level safety annotations, and AdvBench~\citep{advbench} for cross-dataset geometric validation. No new data collection was performed.
42	    \item \textbf{Human subjects:} No human subjects research was conducted.
43	    \item \textbf{Reproducibility:} All hyperparameters are reported in \cref{app:gru_details,app:bocpd_config}. Code and corrected data will be released upon publication.
44	\end{itemize}
45	
46	
47	\section{Layer Sweep Results}
48	\label{app:layer_sweep}
49	
50	For each model, we sweep all transformer layers and evaluate five candidate selection metrics: (1)~balanced accuracy $\times$ crossing rate (the CR-composite), (2)~pure balanced accuracy, (3)~precision, (4)~inverse pre-CP FPR, and (5)~an additive composite. The CR-composite systematically selects shallow layers across all four models (including R1-8B under the full L0--L24 sweep; \cref{tab:r18b_full_layer}) because early-layer representations exhibit higher crossing rates (more frequent threshold crossings) regardless of discriminative power. Three threshold-based metrics (precision, inverse FPR, additive composite) converge on deep layers for all models; pure balanced accuracy selects layers whose depth varies with the data split (under 70/30: L30 for QwQ-32B, L47 for R1-32B; under the canonical 60/20/20: L63 and L46 respectively; \cref{tab:ba_layer_results}).
51	
52	\paragraph{Selected layers.} R1-8B: under the original L12--L24 sweep, all five metrics agreed on L14 (44\%); extending to L0--L24, crossing rate shifts to L0 while threshold-based metrics retain L14, a 16-layer gap (\cref{tab:r18b_full_layer}). OT-7B: CR-composite selects L0 (0\%), threshold-based consensus selects L16 (57\%). QwQ-32B: CR-composite selects L2 (3\%), threshold-based consensus selects L63 (98\%). R1-32B: CR-composite selects L10 (16\%), threshold-based consensus selects L63 (98\%). The disagreement is most extreme for 64-layer models, where the CR-composite selects layers in the bottom 16\% of the network while threshold-based metrics select layers at 98\% depth. Under 70/30, pure balanced accuracy selects L30 (47\%) for QwQ-32B and L47 (73\%) for R1-32B; under the canonical 60/20/20, it selects L63 (98\%) and L46 (72\%), which demonstrates sensitivity to the data split.
53	
54	\paragraph{Impact on modality comparison.} At the CR-composite layers, HS vs.\ text precision $p$-values are 0.064 (R1-32B) and 0.35--0.83 (QwQ-32B), both non-significant. At the threshold-based deep layers, all $p$-values fall below 0.005. The initially reported ``scale-dependent'' pattern (HS advantage at 7--8B but not 32B) was entirely an artifact of layer selection methodology, not a genuine property of model scale (\cref{sec:layer-results}).
55	
56	\paragraph{Layer selection stability (LOO-CV).} Leave-one-out cross-validation on the validation set shows moderate consistency for 7--8B models (65--68\% dominant-layer agreement) but lower for 32B, confirming that layer selection instability is particularly acute at small sample sizes. Under pure balanced accuracy, the dominant layer is selected in 68\% (QwQ-32B: L30, 13/19 folds) and 65\% (R1-32B: L47, 13/20 folds) of folds. Alternative selections scatter across neighboring layers (L29, L55--56 for QwQ; L32, L38, L43 for R1-32B), reinforcing the need for multi-metric auditing rather than single-metric layer selection. Threshold-based metrics show tighter convergence to L63 for both 32B models. Expanding the criterion from top-1 to top-3 layers does not change conclusions: the top-3 BA-selected layers for QwQ-32B (L30, L29, L55) and R1-32B (L47, L43, L38) all fall in the mid-to-deep range, and threshold-based metrics remain converged at L63 across all folds.
57	
58	\paragraph{Joint (layer, $W$) sensitivity.} Under the original 70/30 validation protocol, we evaluate QwQ-32B across 64 layers $\times$ 3 windows ($W \in \{1, 3, 5\}$) (192 configurations) (\cref{tab:joint_layer_w}). L60 is near-optimal: within 2.1pp of the global best at $W{=}3$ and the top-ranked layer at $W{=}5$. (Under 60/20/20, threshold-based metrics select L63; the shift from L60 to L63 across splits itself illustrates layer selection sensitivity.) The optimal layer shifts from middle-deep (L46--47 at $W{=}1$) to deep (L60 at $W{=}5$), confirming a layer-window interaction. For R1-8B, optimal precision layers shift similarly (L16 at $W{=}1$ $\to$ L9 at $W{=}15$; Kendall's $\tau{=}{-}0.91$, $p{=}0.071$), a consistent negative trend that does not reach significance at $n{=}4$ windows. L30, selected by per-fold LOO-CV at $W{=}1$ under balanced accuracy, is suboptimal across all windows (max BA $= 0.769$ vs.\ global best 0.817). Joint (layer, $W$) stability was evaluated via grid search on $W \in \{1, 3, 5\}$ for QwQ-32B only; full leave-one-fold-out validation of the (layer, $W$) pair and extension to R1-32B remain for future work.
59	
60	\begin{table}[htbp]
61	\centering
62	\small
63	\caption{QwQ-32B joint (layer, $W$) grid search under 70/30 validation. L60 is near-optimal at recommended windows ($W{=}3$--$5$). L30 (LOO-CV selection at $W{=}1$) is suboptimal across all windows. Under the canonical 60/20/20 split, threshold-based metrics select L63.}
64	\label{tab:joint_layer_w}
65	\resizebox{\columnwidth}{!}{%
66	\begin{tabular}{clccc}
67	\toprule
68	$W$ & \textbf{Best layer} & \textbf{Best BA} & \textbf{L60 BA} & \textbf{L60 rank} \\
69	\midrule
70	1 & L47 & 0.798 & 0.783 & $\sim$15th \\
71	3 & L46 & 0.817 & 0.796 & $\sim$6th \\
72	5 & L60 & 0.808 & 0.808 & 1st \\
73	\bottomrule
74	\end{tabular}}
75	\end{table}
76	
77	\paragraph{R1-8B full-layer sweep.}
78	\label{app:r18b_full_layer}
79	The original R1-8B layer sweep covered L12--L24 (13 layers), where all five metrics agreed on L14 (\cref{tab:layer_selection}). Extending to L0--L24 reveals that crossing rate consistently selects L0 across all window sizes, while threshold-based metrics retain mid-to-deep layers (L12--L16 for $W{=}1$--$5$; L9 at $W{=}15$, marginal $\Delta{=}0.003$ between shallow and deep means), a 9--16 layer divergence (\cref{tab:r18b_full_layer}). Unlike 32B models, the bias is isolated to crossing rate; threshold-based metrics show no shallow shift for R1-8B. This confirms the crossing-rate bias generalizes to Llama-architecture models. HS probes maintain significant advantage across all 25 layers and window sizes (precision gap ${\sim}$0.15--0.17), unlike OT-7B and 32B models where significance drops at shallow layers.
80	
81	\begin{table}[htbp]
82	\centering
83	\small
84	\caption{R1-8B full-layer sweep (L0--L24, extending the original L12--L24 range). Best layer selected by crossing rate vs.\ threshold-based metrics across four window sizes. Score = balanced accuracy at the threshold-based layer. Layer gap = crossing-rate layer minus threshold-based layer.}
85	\label{tab:r18b_full_layer}
86	\resizebox{\columnwidth}{!}{%
87	\begin{tabular}{lcccc}
88	\toprule
89	& $W{=}1$ & $W{=}3$ & $W{=}5$ & $W{=}15$ \\
90	\midrule
91	Crossing rate & L0 & L0 & L0 & L0 \\
92	Threshold (composite) & L16 (0.789) & L12 (0.796) & L12 (0.803) & L9 (0.784) \\
93	\midrule
94	Layer gap & 16 & 12 & 12 & 9 \\
95	\bottomrule
96	\end{tabular}}
97	\end{table}
98	
99	\subsection{Random-Label Decomposition Control}
100	\label{app:random_cp}
101	
102	To decompose the sources of metric disagreement in layer selection, we replace the true CP annotations with uniformly random labels and re-run the full layer sweep (10 random-label repeats per model). We test QwQ-32B (95 traces, 64 layers) and R1-8B (209 traces, 25 layers); \cref{tab:random_cp,tab:random_cp_r18b} report the fraction of repeats selecting a shallow layer and the mean selected layer.
103	
104	\begin{table}[htbp]
105	\centering
106	\small
107	\caption{QwQ-32B layer selection under random CP labels (10 repeats). Shallow\%: fraction selecting a layer L$\leq$10. Real-CP layer shown for reference.}
108	\label{tab:random_cp}
109	\setlength{\tabcolsep}{4pt}
110	\resizebox{\columnwidth}{!}{%
111	\begin{tabular}{lcccc}
112	\toprule
113	\textbf{Metric} & \textbf{Real-CP} & \textbf{Shallow\%} & \textbf{Rand.\ mean layer} \\
114	\midrule
115	Crossing rate & L4 & 100\% & $3.4 \pm 2.6$ \\
116	CR-composite & L4 & 80\% & $13.1 \pm 18.1$ \\
117	Precision & L63 & 20\% & $33.8 \pm 19.8$ \\
118	Inv.\ FPR & L62 & 10\% & $36.4 \pm 17.0$ \\
119	Bal.\ accuracy & L63 & 20\% & $33.3 \pm 20.3$ \\
120	\bottomrule
121	\end{tabular}}
122	\end{table}
123	
124	\begin{table}[htbp]
125	\centering
126	\small
127	\caption{R1-8B layer selection under random CP labels (10 repeats). Shallow\%: fraction selecting L$\leq$4 (bottom quintile of 25 layers). $\dagger$: degenerate, all repeats select L0 with zero variance, indicating destroyed signal rather than shallow preference.}
128	\label{tab:random_cp_r18b}
129	\setlength{\tabcolsep}{4pt}
130	\resizebox{\columnwidth}{!}{%
131	\begin{tabular}{lcccc}
132	\toprule
133	\textbf{Metric} & \textbf{Real-CP} & \textbf{Shallow\%} & \textbf{Rand.\ mean layer} \\
134	\midrule
135	Crossing rate & L0 & 0\% & $10.7 \pm 4.8$ \\
136	CR-composite & L0 & 0\% & $13.7 \pm 6.7$ \\
137	Precision & L23 & 100\%$^{\dagger}$ & $0.0 \pm 0.0$ \\
138	Inv.\ FPR & L13 & 100\%$^{\dagger}$ & $0.0 \pm 0.0$ \\
139	Bal.\ accuracy & L19 & 0\% & $14.0 \pm 4.0$ \\
140	\bottomrule
141	\end{tabular}}
142	\end{table}
143	
144	\paragraph{QwQ-32B (Qwen).} The results decompose the metric disagreement into two components. (A)~The crossing-rate shallow-layer preference is label-independent: 100\% of random-label repeats still select layers L0--L7, confirming that this bias reflects representation geometry (shallow-layer cosine distance compression; \cref{app:cosine_volatility}) rather than any property of the safety labels. The CR-composite inherits this bias (80\% shallow). (B)~Threshold-based metrics (precision, inverse FPR) select deep layers only with real safety labels; under random labels, selections scatter across the full layer range (mean L34--L36, high variance). The full metric disagreement (L4 vs.\ L63, a 59-layer gap) is the superposition of a geometric artifact on the crossing-rate side and a real safety signal on the threshold-based side.
145	
146	\paragraph{R1-8B (Llama).} The Llama-based model shows stronger label dependence: crossing rate scatters from L0 to mean L$10.7 \pm 4.8$ under random labels (0\% shallow), unlike QwQ-32B where it retains shallow preference. Threshold-based metrics degenerate entirely: precision and inverse FPR select L0 in all 10 repeats with zero variance, indicating random labels destroy discriminative signal rather than merely redistributing it. The real-CP disagreement (L0 vs.\ L23, a 23-layer gap) vanishes completely under random labels.
147	
148	\paragraph{Cross-architecture summary.} The metric disagreement requires genuine safety labels in both architectures, but the mechanism differs: in QwQ-32B, crossing-rate shallow preference reflects representation geometry (label-independent cosine compression), while in R1-8B even crossing-rate layer selection is label-dependent. The geometric component of the crossing-rate bias is thus Qwen-specific rather than a universal property of transformer representations.
149	
150	\section{Representation Compression Analysis}
151	\label{app:cosine_volatility}
152	
153	We measure step-to-step cosine distance at CR-composite (shallow) vs.\ threshold-based (deep) layers across all models to characterize the compression mechanism underlying the crossing rate bias (\cref{tab:cosine_volatility}).
154	
155	\begin{table}[htbp]
156	\centering
157	\small
158	\caption{Step-to-step cosine distance at CR-composite (shallow) and threshold-based (deep) layers. Shallow layers produce highly compressed representations (1.4--2.7$\times$ smaller inter-step distances).}
159	\label{tab:cosine_volatility}
160	\resizebox{\columnwidth}{!}{%
161	\begin{tabular}{llcc}
162	\toprule
163	\textbf{Model} & \textbf{Layer (type)} & \textbf{Mean} & \textbf{Std} \\
164	\midrule
165	R1-8B & L2 (CR-comp.) & 0.186 & 0.097 \\
166	 & L14 (thresh.) & 0.411 & 0.143 \\[2pt]
167	OT-7B & L2 (CR-comp.) & 0.077 & 0.080 \\
168	 & L16 (thresh.) & 0.206 & 0.091 \\[2pt]
169	QwQ-32B & L2 (CR-comp.) & 0.037 & 0.064 \\
170	 & L63 (thresh.) & 0.084 & 0.056 \\[2pt]
171	R1-32B & L10 (CR-comp.) & 0.067 & 0.050 \\
172	 & L63 (thresh.) & 0.092 & 0.076 \\
173	\bottomrule
174	\end{tabular}}
175	\end{table}
176	
177	Shallow layers produce highly compressed representations: consecutive steps cluster within small cosine distances (0.04--0.19), while deep-layer representations spread more widely (0.09--0.41). Inter-step distances at shallow layers are 1.4--2.7$\times$ smaller than at deep layers across all models. A linear probe operating in this compressed space sits near the noise floor, where minor numerical fluctuations produce spurious threshold crossings that inflate crossing rate independently of discriminative power. Deep layers produce well-separated representations where crossings correspond to genuine semantic transitions.
178	
179	\paragraph{Cross-dataset evidence.}
180	To assess whether this geometric precondition generalizes beyond HarmThoughts, we compute the same shallow/deep volatility ratio on AdvBench~\citep{advbench} traces using R1-8B. The deep-layer mean cosine distance (0.442) is $1.67\times$ the shallow-layer mean (0.265), consistent with the 1.4--2.7$\times$ range observed across all four models on HarmThoughts (\cref{tab:cosine_volatility}). This confirms that the representational compression underlying metric-induced layer selection bias is not dataset-specific and does not depend on CP annotations.
181	
182	\subsection{AdvBench Boundary Condition}
183	\label{app:advbench_cp}
184	
185	We analyze R1-8B behavior on 388 substantive-response AdvBench~\citep{advbench} traces (of 520 total) to characterize a boundary condition for the CP framework (\cref{tab:advbench_boundary}).
186	
187	\begin{table}[htbp]
188	\centering
189	\small
190	\caption{R1-8B behavior on AdvBench adversarial prompts (388 substantive-response traces of 520 total). CP${=}0$ indicates the model produces harmful content from the first reasoning step without prior safety deliberation.}
191	\label{tab:advbench_boundary}
192	\resizebox{\columnwidth}{!}{%
193	\begin{tabular}{lc}
194	\toprule
195	\textbf{Metric} & \textbf{Value} \\
196	\midrule
197	Jailbreak rate & 13.4\% \\
198	CP${=}0$ (among JB) & 90.4\% \\
199	Mean CP position (among JB) & 1.4 steps \\
200	\bottomrule
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "07793ac9-62bd-46b1-909f-e02fdc9825e5",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "f70049fe-fb44-4807-9074-a38046dc041e",
  "sourceToolAssistantUUID": "07793ac9-62bd-46b1-909f-e02fdc9825e5",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 38 · 2026-05-21T22:11:50.657Z_

I now have a thorough understanding of the paper. Let me also quickly check the reference count and see how many total references the bibliography contains.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "f70049fe-fb44-4807-9074-a38046dc041e",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUrh8YkZHXRh9sY3Qyw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "afcceb03-72ff-407c-9027-8b51453cf56e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WyhQUC37RW68C2KSoXjB1k",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6171,
      "cache_read_input_tokens": 50350,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6171,
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

_source line 39 · 2026-05-21T22:11:52.754Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01AxnM5j1xi3NArgJ9bbwQdt`</summary>

```json
{
  "command": "grep -c '@\\(article\\|inproceedings\\|book\\|misc\\)' /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/references.bib",
  "description": "Count total bibliography entries"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "afcceb03-72ff-407c-9027-8b51453cf56e",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUrh8YkZHXRh9sY3Qyw",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "86a21715-c940-4151-9a32-b20c4a002d24",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WyhQUC37RW68C2KSoXjB1k",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6171,
      "cache_read_input_tokens": 50350,
      "output_tokens": 161,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 6171
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 161,
          "cache_read_input_tokens": 50350,
          "cache_creation_input_tokens": 6171,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 6171,
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

_source line 40 · 2026-05-21T22:11:52.926Z_

<details><summary>↩ Tool result · `toolu_01AxnM5j1xi3NArgJ9bbwQdt`</summary>

```text
85
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "86a21715-c940-4151-9a32-b20c4a002d24",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "7de28925-fa98-4f21-b1e2-080458210ab5",
  "sourceToolAssistantUUID": "86a21715-c940-4151-9a32-b20c4a002d24",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-21T22:11:55.698Z_

<details open><summary>🔧 Tool call — Grep · `toolu_017hCJZMMmzS7qGNXz5cdctc`</summary>

```json
{
  "pattern": "\\\\cite",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety/docs/paper/sections",
  "output_mode": "count"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7de28925-fa98-4f21-b1e2-080458210ab5",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUs5JJFCgkuqPBPAhTn",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "d6c9cb73-ab99-423b-8496-5fe8b67c0107",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YWJwj3QoodsqhmSE3Qrhcp",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 174,
      "cache_read_input_tokens": 56521,
      "output_tokens": 123,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 174
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 123,
          "cache_read_input_tokens": 56521,
          "cache_creation_input_tokens": 174,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 174,
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

_source line 42 · 2026-05-21T22:11:55.719Z_

<details><summary>↩ Tool result · `toolu_017hCJZMMmzS7qGNXz5cdctc`</summary>

```text
docs/paper/sections/related_work.tex:8
docs/paper/sections/experiments.tex:3
docs/paper/sections/discussion.tex:1
docs/paper/sections/method.tex:4
docs/paper/sections/limitations.tex:1
docs/paper/sections/abstract.tex:1
docs/paper/sections/appendix.tex:17
docs/paper/sections/introduction.tex:4

Found 39 total occurrences across 8 files.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d6c9cb73-ab99-423b-8496-5fe8b67c0107",
  "isSidechain": true,
  "promptId": "b1899cf7-50e7-4ba4-a982-bccf7d2835cb",
  "agentId": "a8237ec39a85ac6a7",
  "type": "user",
  "uuid": "1af29a5b-87fa-4d43-934c-7ab56dc1ea27",
  "sourceToolAssistantUUID": "d6c9cb73-ab99-423b-8496-5fe8b67c0107",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 43 · 2026-05-21T22:13:27.801Z_

Good -- so ~85 bib entries, not 12 as the task prompt suggested. The paper has substantially expanded its bibliography. Let me now read the paper's title carefully (it changed from the prompt's description).

Now I have a comprehensive understanding of the paper. Let me write the review.

## R2 Review: Novelty and Related Work

### Summary

This paper investigates whether probe-based methods can detect the "safety commitment point" (CP) in reasoning model CoT traces -- the moment where safety deliberation permanently ceases. The central finding is methodological: the choice of layer selection metric (crossing-rate composite vs. threshold-based) can qualitatively reverse whether hidden-state probes outperform text probes, with divergences of 14-61 layers depending on the model. Against a 384d sentence encoder, HS probes show +15-22pp precision gains, but this advantage is conditional on encoder quality, model scale, and position control. Seven alternative detection paradigms all fail. The paper is thorough in its statistical methodology, with nested CV, Holm-Bonferroni corrections, random-label controls, and a three-tier evidence gradient, but is constrained by small sample sizes at 32B and Qwen-dominated model selection.

### Strengths

1. **The layer selection sensitivity finding is genuinely useful.** While probing layer sensitivity is well-known in BERTology (Belinkov 2022, Tenney et al. 2019), the demonstration that metric choice produces a *qualitative reversal* (p=0.83 vs p<0.005 on identical data) in a safety-critical application is a concrete, actionable warning. This is not "obvious once stated" -- the specific mechanism (cosine compression inflating crossing rate at shallow layers) is a substantive empirical contribution that applies beyond this particular task.

2. **Unusually honest epistemic calibration.** The three-tier evidence gradient (cross-validated / significant / exploratory), the dagger notation for sample-limited results, the explicit acknowledgment that the HS advantage diminishes with stronger encoders (4/4 HB at 384d to 1/4 at 1024d), and the frank assessment that FPR remains 11-50% -- this level of self-critical reporting is rare and commendable. The paper actively undermines its own strongest claims where the evidence warrants it.

3. **Comprehensive negative results with explanatory analysis.** The paper does not merely report that 7 alternative methods fail -- it provides mechanistic explanations for each failure (BOCPD/CUSUM fail because commitment is gradual; Mahalanobis fails because discriminative signal is in minor PCA components; CCS misaligns temporally). This transforms "didn't work" into a diagnostic taxonomy that informs future method design.

4. **Statistical rigor exceeds the typical EMNLP submission.** BCa bootstrap with cluster resampling (preserving within-trace dependence), Holm-Bonferroni for 12 simultaneous tests, random-label decomposition controls, split-half validation, nested CV, post-hoc power analysis with MDE calculation -- this paper takes statistical methodology seriously in a subfield that often does not.

5. **The related work section is substantially more comprehensive than the task prompt suggested.** With ~85 references covering concurrent work (Chan et al. 2025, Chrabaszcz et al. 2026, Alvarez & Baheri 2026), probing methodology foundations, and a wide range of hidden-state safety detection approaches, the coverage is adequate for the scope of the paper. The positioning against Chan et al. (2025) -- who show single-layer probes work but do not examine whether layer choice matters -- is particularly well-articulated.

6. **The random-label decomposition control is a clever methodological innovation.** Showing that crossing-rate shallow-layer bias is label-independent in Qwen (geometric artifact) but label-dependent in Llama provides genuine mechanistic insight about architecture-specific representation geometry.

### Weaknesses

1. **The HS advantage is fragile and possibly artifactual.** The paper's own evidence systematically erodes its second contribution: the advantage drops from 4/4 HB-significant models at 384d to 1/4 at 1024d; position mediates 2/4 models under quadratic control; PCA capacity matching complicates the comparison. By the end, the "robust" finding is only that MiniLM-L6-v2 (a 2019-era 384d encoder) is beaten by 4096d hidden states from 2025-era models -- which is close to a capacity comparison, not a modality comparison. The paper acknowledges this but still frames it as "boundary conditions for the HS advantage" rather than "the HS advantage may not exist with appropriate text encoders." This framing tension weakens the contribution.

2. **Architecture diversity is insufficient for the claims made.** Three of four models share Qwen architecture; R1-8B (Llama) is the sole cross-architecture evidence point. The random-label analysis reveals the geometric component of crossing-rate bias is Qwen-specific. Yet Contribution 1 (layer selection bias) is framed as a general methodological warning. With n=1 for non-Qwen architectures, the generalizability of even the primary finding is uncertain. The paper should test on at least one model from a third architecture family (e.g., Mistral, Gemma, or a proprietary model's distillation).

3. **The "commitment point" formalization is underspecified and potentially circular.** CP is defined as "the first reasoning step after which safety deliberation permanently ceases," but this requires knowing the full trace to identify. The paper studies *retrospective* classification, not prediction. Yet the framing ("What Detects Safety Commitment?") implies a monitoring/prediction use case. The disconnect between the retrospective analysis and the deployment framing is not adequately resolved. Moreover, the CP concept collapses a potentially continuous, multi-dimensional process into a binary label -- the paper acknowledges this in Limitations but builds its entire evaluation framework on this simplification.

4. **Missing positioning against key related work traditions.** While the related work is substantially improved from what was originally described, several important threads are underrepresented:
   - **Runtime monitoring literature from software engineering/formal methods**: The paper frames CP detection as a monitoring problem but does not engage with the runtime monitoring literature (e.g., Bartocci et al. 2018 survey on runtime verification, or the monitoring-based approaches in the ML systems literature).
   - **Representation trajectory analysis beyond probing**: Work on representation dynamics during generation (e.g., Geva et al. 2022 on how transformers build predictions; Dar et al. 2023 on analyzing updates to the residual stream) is relevant but not cited.
   - **Phase transitions in neural network computation**: The CP concept is essentially a phase transition in the model's internal state. There is a literature on phase transitions in neural network behavior (both from a dynamical systems perspective and from interpretability) that could strengthen the theoretical grounding.

5. **The negative results, while informative, are partially expected.** BOCPD and CUSUM are designed for abrupt distributional shifts; the paper acknowledges commitment is gradual. Mahalanobis distance is a global distributional metric unsuited for sequential classification. CCS was designed for a different task entirely. Framing these as "failures" slightly overstates the informativeness -- a more precise framing would be "confirmation that tools designed for other problems do not transfer to this one." The MLP overfitting result and cross-model transfer failure are the genuinely surprising negative results.

6. **Sample sizes at 32B undermine the evaluation framework's value.** With n=19-20 test traces, the MDE is 8.6-9.5pp at 80% power. The paper marks these as exploratory, but they occupy significant space in the results and contribute to the claim count. The 2x2 design (architecture x scale) has exactly one cell with adequate power (7-8B Qwen) and one marginal cell (7-8B Llama, n=43). The "systematic evaluation across 4 models" framing oversells what is more accurately "validated on 2 small models, with preliminary observations on 2 larger models."

### Questions for Authors

1. **On the HS advantage with matched encoders**: If HS features are PCA-reduced to 384d and compared against a 384d text encoder, and the advantage persists, this is informative. But when BGE-large (1024d) nearly eliminates the gap, doesn't this suggest the "advantage" is primarily about information capacity rather than modality? What would be the conclusion if you compared against a text encoder with dimension equal to the hidden state (e.g., 4096d or 5120d)?

2. **On the commitment point definition**: How sensitive are results to the CP annotation? You report a perturbation analysis showing <2.5pp BA change, but this is for small perturbations. What happens with systematic annotation disagreement (e.g., if a different annotator places CPs 2-3 steps earlier or later on average)? The kappa=0.606 on AdvBench LLM proxy suggests moderate but not strong agreement.

3. **On the crossing-rate mechanism**: You attribute shallow-layer bias to cosine compression, but an alternative explanation is that shallow layers encode more surface-level features that the crossing-rate metric happens to favor. Have you examined whether the "crossing-rate selected" shallow layers actually encode different types of information (e.g., syntactic vs. semantic) than the threshold-selected deep layers?

4. **On generalization beyond HarmThoughts**: With only one dataset providing CP annotations and 3/4 Qwen models, how confident should readers be that these findings generalize? What would a minimum viable replication look like?

5. **On the title change**: The actual paper title ("Layer Selection Sensitivity in Hidden-State Safety Probes for Reasoning Models") is narrower and more accurate than the task prompt's title ("What Detects Safety Commitment...?"). The current title better reflects the paper's actual contribution -- is the layer selection sensitivity finding sufficient to stand as the primary contribution?

### Missing References

The bibliography is reasonably comprehensive (~85 entries), but the following areas could be strengthened:

- **Geva et al. (2023), "Dissecting Recall of Factual Associations in Auto-Regressive Language Models"** -- relevant to understanding how information flows through layers during generation, directly pertinent to why layer choice matters.
- **Neel Nanda et al.'s work on mechanistic interpretability** (beyond Arditi et al. 2024) -- e.g., the IOI circuit analysis or induction head work, which provides context for why different layers encode different things.
- **Representation trajectory/dynamics literature**: e.g., work on how model representations evolve token-by-token during generation, relevant to the temporal probing contribution.
- **Runtime monitoring from the formal verification community** (Bartocci et al. 2018 survey) -- since the paper frames CP detection as a monitoring problem.
- **Broader change-point detection literature**: The paper cites BOCPD and CUSUM but not other sequential analysis methods (e.g., kernel-based methods, PELT) that might be more appropriate for gradual transitions.

### Scores

- Soundness: 4/5
- Excitement: 2.5/5
- Reproducibility: 4/5
- Overall: 3/5
- Confidence: 4/5

### Meta-assessment

This paper is a **Findings** paper (Overall: 3.0). The key limiting factor is excitement/novelty rather than soundness.

**For Findings**: The paper's primary contribution -- that layer selection metric choice can qualitatively reverse probe conclusions in safety monitoring -- is a genuine and well-demonstrated methodological warning. The statistical rigor is exemplary. The honest epistemic calibration (three-tier evidence, dagger notation, the encoder-quality gradient that undermines the paper's own claims) sets a good standard. The negative results provide useful diagnostic information.

**Against Main track**: The paper does not clear the novelty bar for Main (~21% acceptance). The core insight is essentially a well-executed empirical demonstration that "researcher degrees of freedom matter" -- important but not surprising to the probing methodology community. The HS vs. text comparison, once the encoder-quality confound is revealed, is inconclusive rather than illuminating. The 3/4 Qwen architecture concentration limits generalizability claims. The practical implication is essentially "be careful with your metrics and layers" -- sound advice but not a paradigm-shifting finding. The paper does not achieve the threshold of either (a) surprising findings that change community thinking or (b) sufficient thoroughness to serve as a definitive reference (it would need more models, more datasets, and more architectures for the latter).

**What would elevate to Main**: (1) Demonstrating the layer selection reversal on 3+ architecture families with adequate sample sizes; (2) providing a principled, validated layer selection method (not just diagnosing the problem); (3) discovering a mechanistic explanation for *why* safety commitment is linearly separable at specific layers (connecting to circuit-level interpretability); or (4) achieving deployment-viable FPR (<10%) with a novel method, moving from "characterization" to "solution."

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1af29a5b-87fa-4d43-934c-7ab56dc1ea27",
  "isSidechain": true,
  "agentId": "a8237ec39a85ac6a7",
  "requestId": "req_011CbGUsHJs3QmmJQhAZKCdH",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "512e84df-33cb-4853-be7e-4b6ea5dbd98c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/contrastive_trace_safety",
  "sessionId": "eb7c9f09-21ff-4986-ae2c-11140cc85a3d",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Brb7dWwJ2iRVnJH5L8VQAk",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 247,
      "cache_read_input_tokens": 56695,
      "output_tokens": 3082,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 247
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 3082,
          "cache_read_input_tokens": 56695,
          "cache_creation_input_tokens": 247,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 247,
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
