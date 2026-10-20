# paper related work

**The Embedding Alignment Gap: Why Diversity-Based Data Selection Accelerates Model Collapse in Iterative Self-Training** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 26
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/workers/worker_paper_related_work_20260514T081834.log`
- **Structured JSON:** [`8d0c4f678899bf38b42a.json`](../../sessions/8d/8d0c4f678899bf38b42a.json)

## Before a recorded user message

26 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify",
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
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
    "mcp__agent-ml-research__edit_paper_section",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__write_paper_section"
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
  "uuid": "3d26f5c5-5b9c-4daa-bfb9-311ac31c11d6",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-4-projects-div-cal-verify/memory/"
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
    "resetsAt": 1778764200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "78964c19-c4fb-48e6-8339-099e5dffdbf8",
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5"
}
```

---

### Assistant

_source line 4_

I'll start by reading the current related work and references to understand what's already covered.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "bf07c3d3-5b81-447d-9281-36bfd30b9542",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ji8ob3tgDmo7RDF8jNpYcr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 11705,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11705
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01S2AKLRknpksrtfY57FxdmR`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__edit_paper_section",
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
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "c5dab57b-5f43-4901-ab1a-36569514f048",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ji8ob3tgDmo7RDF8jNpYcr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 11705,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 11705
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

_source line 6 · 2026-05-14T08:18:46.413Z_

<details><summary>↩ Tool result · `toolu_01S2AKLRknpksrtfY57FxdmR`</summary>

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
  "tool_name": "mcp__agent-ml-research__edit_paper_section"
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
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "177bf3a1-ac20-4d5e-b8bb-7a4076f4be20",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__edit_paper_section"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__edit_paper_section",
    "total_deferred_tools": 24
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
Let me read the current related work section and the existing references.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "0208de40-c062-4f34-a259-da216879e35a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DD8GcUKvQwWNCVt6x12swW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 856,
      "cache_read_input_tokens": 23546,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 856
      },
      "output_tokens": 53,
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

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01B2rM6vXuJu5KFjMfCWKrHR`</summary>

```json
{
  "project": "div_cal_verify",
  "file": "related_work.md",
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
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "be163c2f-1830-4e4b-bf8e-c4b5506b5f12",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DD8GcUKvQwWNCVt6x12swW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 856,
      "cache_read_input_tokens": 23546,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 856
      },
      "output_tokens": 53,
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

_source line 9 · 2026-05-14T08:18:50.010Z_

<details><summary>↩ Tool result · `toolu_01B2rM6vXuJu5KFjMfCWKrHR`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work.md'\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "7b6f5576-e831-4687-8255-6f490cd7ec22",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work.md'\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"file must be one of ['ARCHITECTURE.md', 'DATA.md', 'EVALUATION.md', 'MODELS.md', 'ROADMAP.md', 'constraints.yaml', 'decisions.yaml', 'ideas.md', 'literature_map.yaml', 'memory.md', 'paper_checklist.yaml', 'paper_framing.md', 'paper_provenance.yaml', 'report.md', 'writing_plan.yaml'], got 'related_work.md'\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 10_

<details open><summary>🔧 Tool call — Glob · `toolu_01RQZgyEuVUPP6SfbRQbEBMq`</summary>

```json
{
  "pattern": "**/artifacts/related_work_references.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "33545dc8-ab72-4a1c-b39d-d265fb0be1f7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DD8GcUKvQwWNCVt6x12swW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 856,
      "cache_read_input_tokens": 23546,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 856
      },
      "output_tokens": 53,
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

_source line 11_

<details open><summary>🔧 Tool call — Glob · `toolu_01PhvN3uuxkxmpJhzN6njSsf`</summary>

```json
{
  "pattern": "**/paper/**"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "78048f91-146a-4c79-ac9b-ce283f33dd94",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DD8GcUKvQwWNCVt6x12swW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 856,
      "cache_read_input_tokens": 23546,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 856
      },
      "output_tokens": 53,
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

_source line 12 · 2026-05-14T08:18:50.555Z_

<details><summary>↩ Tool result · `toolu_01RQZgyEuVUPP6SfbRQbEBMq`</summary>

```text
artifacts/related_work_references.md
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "b361b28e-6768-41fe-a724-cb2e13b5db3f",
  "tool_use_result": {
    "filenames": [
      "artifacts/related_work_references.md"
    ],
    "durationMs": 21,
    "numFiles": 1,
    "truncated": false
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-14T08:18:50.556Z_

<details><summary>↩ Tool result · `toolu_01PhvN3uuxkxmpJhzN6njSsf`</summary>

```text
docs/paper/acl.sty
docs/paper/acl_natbib.bst
artifacts/_project/paper/methodology.tex
artifacts/_project/paper/experiments_112f46.tex
artifacts/_project/paper/experiments.tex
docs/paper/methodology.tex
docs/paper/main.blg
docs/paper/main.bbl
docs/paper/main.tex
docs/paper/figures/fig_ppl_trends.pdf
docs/paper/figures/fig_ratio_trajectory.pdf
docs/paper/main.aux
docs/paper/main.out
docs/paper/main.log
docs/paper/main.pdf
docs/paper/conclusion.tex
docs/paper/experiments.tex
docs/paper/introduction.tex
docs/paper/references.bib
docs/paper/related_work.tex
docs/paper/discussion.tex
docs/paper/results.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "45827650-462a-4aab-9a68-1322b34a2a2a",
  "tool_use_result": {
    "filenames": [
      "docs/paper/acl.sty",
      "docs/paper/acl_natbib.bst",
      "artifacts/_project/paper/methodology.tex",
      "artifacts/_project/paper/experiments_112f46.tex",
      "artifacts/_project/paper/experiments.tex",
      "docs/paper/methodology.tex",
      "docs/paper/main.blg",
      "docs/paper/main.bbl",
      "docs/paper/main.tex",
      "docs/paper/figures/fig_ppl_trends.pdf",
      "docs/paper/figures/fig_ratio_trajectory.pdf",
      "docs/paper/main.aux",
      "docs/paper/main.out",
      "docs/paper/main.log",
      "docs/paper/main.pdf",
      "docs/paper/conclusion.tex",
      "docs/paper/experiments.tex",
      "docs/paper/introduction.tex",
      "docs/paper/references.bib",
      "docs/paper/related_work.tex",
      "docs/paper/discussion.tex",
      "docs/paper/results.tex"
    ],
    "durationMs": 17,
    "numFiles": 22,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 14_

<details open><summary>🔧 Tool call — Read · `toolu_01YALPZ31rag4t6H2YtBWvcU`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "8200e7c7-8634-46e5-b5e6-5b79dd4f164b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UQCHHcqxVXo7hJpUcEeoFe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 687,
      "cache_read_input_tokens": 24402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 687
      },
      "output_tokens": 42,
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

_source line 15 · 2026-05-14T08:18:54.213Z_

<details><summary>↩ Tool result · `toolu_01YALPZ31rag4t6H2YtBWvcU`</summary>

```text
1	\section{Related Work}
2	
3	\subsection{Model Collapse in Iterative Training}
4	
5	\citet{shumailov2024ai} demonstrate that language models trained recursively on their own generated data undergo irreversible tail distribution erosion, establishing model collapse as a fundamental limitation of self-consuming training loops. \citet{alemohammad2024self} formalize this as Model Autophagy Disorder (MAD), proving theoretically that without fresh real data, iterative self-consumption degrades either quality or diversity. Subsequent work has extended these findings along several axes: \citet{dohmatob2025strong} establish a sharp phase transition in collapse behavior beyond a critical iteration threshold; \citet{seddik2024how} derive the maximum synthetic data proportion before collapse becomes inevitable; and \citet{guo2024curious} track the decay of lexical, syntactic, and semantic diversity across self-training generations, finding the strongest degradation in high-entropy generation tasks.
6	
7	On the mitigation side, \citet{gerstgrasser2024model} show that accumulating data across generations---rather than replacing it---can prevent collapse, while \citet{briesch2023large} confirm that replacement-based training degrades output diversity proportionally to synthetic data fraction. Our work operates within the replacement setting where collapse is expected, but reveals that a natural mitigation strategy---diversity-based data selection---can paradoxically \emph{accelerate} rather than prevent collapse when it relies on the training model's own representations.
8	
9	It is instructive to contrast self-consuming language model training with self-play in reinforcement learning \citep{silver2017mastering} and self-training with verification \citep{singh2024beyond}. In both settings, models train iteratively on their own outputs, yet collapse does not occur---because an external reward signal (game outcome, unit test, verifier) anchors the training distribution. Pure language model self-training lacks such an anchor: the model is both generator and (implicit) evaluator, and embedding-based selection provides a proxy signal that degrades endogenously rather than an external ground truth that remains stable.
10	
11	\subsection{Data Curation and Selection for LLM Training}
12	
13	Data selection has emerged as a key lever for training efficiency and quality. \citet{sorscher2022beyond} show that metric-guided data pruning can break neural scaling law power laws, motivating a family of embedding-based and model-aware selection methods. SemDeDup \citep{abbas2023semdedup} removes semantic near-duplicates using pretrained embeddings; D4 \citep{tirumala2023d4} combines deduplication with diversity-maximizing selection in embedding space; and DSIR \citep{xie2023data} selects data via importance resampling to match target domain feature distributions. More recent approaches optimize for task-specific signals: LESS \citep{xia2024less} selects instruction-tuning data based on gradient similarity to target tasks; DsDm \citep{engstrom2024dsdm} frames selection as datamodel-based optimization, noting that naive quality proxies can harm downstream performance; QuRating \citep{wettig2024qurating} uses LLM-generated quality scores; and SelectIT \citep{liu2024selectit} leverages model uncertainty for instruction data filtering.
14	
15	These methods are designed for one-shot curation of static datasets, where the embedding model is fixed and its representation quality is not in question. We show that the iterative self-training setting introduces a qualitatively different failure mode: when the model providing embeddings co-degrades with the training distribution, embedding-based selection amplifies rather than counteracts distributional collapse. Data mixing strategies that blend real and synthetic data across generations \citep{gerstgrasser2024model} offer a complementary mitigation but do not address the selection mechanism itself.
16	
17	\subsection{Embedding-Based Diversity and Representation Learning}
18	
19	Submodular maximization provides the algorithmic foundation for embedding-based diversity selection. \citet{iyer2013submodular} establish the optimization framework for submodular functions under budget constraints; \citet{wei2015submodularity} formalize data subset selection via facility location and graph-cut objectives in feature space; and \citet{mirzasoleiman2020coresets} apply gradient-embedding facility location for coreset construction. These methods assume a fixed, high-quality embedding space---an assumption we show breaks down under iterative self-training.
20	
21	Active learning methods face a related challenge: acquisition functions must remain well-calibrated as the model updates. BADGE \citep{ash2020deep} selects diverse batches via gradient embeddings; BatchBALD \citep{kirsch2019batchbald} maximizes joint mutual information; and subsequent work has shown that standard acquisition strategies degrade under distribution shift \citep{kothawade2021similar} and that embedding quality determines selection effectiveness \citep{yehuda2022active}. However, active learning typically involves a few rounds of model updating, not the sustained multi-generation feedback loop where selection bias compounds into the selecting model's own training data.
22	
23	The representation learning literature documents several mechanisms by which embedding spaces can lose expressiveness. \citet{jing2022understanding} characterize dimensional collapse in contrastive learning, where embeddings are driven into low-dimensional subspaces; \citet{hua2021feature} identify correlated feature axes as a driver of this collapse; and \citet{papyan2020prevalence} show that deep network representations converge to low-dimensional simplex structures during prolonged training. \citet{laurent2024feature} argue that feature collapse can be benign in classification, but our findings demonstrate that in iterative self-training, the same geometric contraction becomes pathological---it causes diversity selection to invert its intended effect.
24	
25	\subsection{Representation Drift and Proxy Misalignment}
26	
27	Our work connects two established literatures that, together, explain why internal-embedding diversity selection fails under iterative training.
28	
29	The concept drift literature studies how learned representations degrade under sustained distribution shift. \citet{lu2019learning} and \citet{gama2014survey} provide comprehensive taxonomies of drift detection and adaptation. In the continual learning setting, \citet{caccia2022new} quantify abrupt representation change during sequential training, and \citet{davari2022probing} demonstrate that representation-level forgetting proceeds independently of task performance---paralleling our finding that embedding geometry diverges from content diversity even as standard representation quality metrics (RankMe, $k$-NN accuracy) remain stable.
30	
31	The Goodhart's law and reward hacking literature formalizes the failure of proxy optimization under distribution shift. \citet{gao2023scaling} derive scaling laws showing that overoptimizing a proxy reward model degrades true objective performance; \citet{skalse2022defining} prove that non-trivial proxy rewards are inherently exploitable; \citet{pan2022effects} map how proxy-objective misalignment compounds under increasing optimization pressure; and \citet{karwowski2024goodhart} provide geometric characterizations of when proxy optimization diverges from the true objective. The embedding alignment gap is an instance of this phenomenon: internal embedding diversity serves as a proxy for content diversity, and this proxy progressively loses fidelity as the model's representations co-evolve with the selected data distribution.
32	
33	Finally, measuring diversity itself requires careful metric design. Distinct-N \citep{li2016diversity} and Self-BLEU \citep{zhu2018texygen} quantify surface-level lexical diversity, while \citet{tevet2021evaluating} audit failure modes of both n-gram and neural diversity metrics. MAUVE \citep{pillutla2021mauve} measures distributional gaps between generated and human text via embedding-space divergence frontiers. We use rare n-gram density as our content diversity measure precisely because, unlike embedding-based metrics, it is model-independent and directly captures the lexical tail erosion that defines model collapse.
34	
35	\paragraph{Positioning.} The embedding alignment gap as a concept---that proxy metrics degrade under optimization---is well established across the literatures surveyed above. Our contribution is not conceptual novelty but empirical quantification: we provide a controlled factorial ablation (four methods $\times$ three seeds) that decomposes the failure into its constituent factors, a diagnostic metric (selection ratio) that tracks proxy-target divergence in real time, and evidence that the failure is specific to internal embeddings rather than to diversity selection in general.
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "826f015a-502b-4023-947c-6bee903cbbfc",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/related_work.tex",
      "content": "\\section{Related Work}\n\n\\subsection{Model Collapse in Iterative Training}\n\n\\citet{shumailov2024ai} demonstrate that language models trained recursively on their own generated data undergo irreversible tail distribution erosion, establishing model collapse as a fundamental limitation of self-consuming training loops. \\citet{alemohammad2024self} formalize this as Model Autophagy Disorder (MAD), proving theoretically that without fresh real data, iterative self-consumption degrades either quality or diversity. Subsequent work has extended these findings along several axes: \\citet{dohmatob2025strong} establish a sharp phase transition in collapse behavior beyond a critical iteration threshold; \\citet{seddik2024how} derive the maximum synthetic data proportion before collapse becomes inevitable; and \\citet{guo2024curious} track the decay of lexical, syntactic, and semantic diversity across self-training generations, finding the strongest degradation in high-entropy generation tasks.\n\nOn the mitigation side, \\citet{gerstgrasser2024model} show that accumulating data across generations---rather than replacing it---can prevent collapse, while \\citet{briesch2023large} confirm that replacement-based training degrades output diversity proportionally to synthetic data fraction. Our work operates within the replacement setting where collapse is expected, but reveals that a natural mitigation strategy---diversity-based data selection---can paradoxically \\emph{accelerate} rather than prevent collapse when it relies on the training model's own representations.\n\nIt is instructive to contrast self-consuming language model training with self-play in reinforcement learning \\citep{silver2017mastering} and self-training with verification \\citep{singh2024beyond}. In both settings, models train iteratively on their own outputs, yet collapse does not occur---because an external reward signal (game outcome, unit test, verifier) anchors the training distribution. Pure language model self-training lacks such an anchor: the model is both generator and (implicit) evaluator, and embedding-based selection provides a proxy signal that degrades endogenously rather than an external ground truth that remains stable.\n\n\\subsection{Data Curation and Selection for LLM Training}\n\nData selection has emerged as a key lever for training efficiency and quality. \\citet{sorscher2022beyond} show that metric-guided data pruning can break neural scaling law power laws, motivating a family of embedding-based and model-aware selection methods. SemDeDup \\citep{abbas2023semdedup} removes semantic near-duplicates using pretrained embeddings; D4 \\citep{tirumala2023d4} combines deduplication with diversity-maximizing selection in embedding space; and DSIR \\citep{xie2023data} selects data via importance resampling to match target domain feature distributions. More recent approaches optimize for task-specific signals: LESS \\citep{xia2024less} selects instruction-tuning data based on gradient similarity to target tasks; DsDm \\citep{engstrom2024dsdm} frames selection as datamodel-based optimization, noting that naive quality proxies can harm downstream performance; QuRating \\citep{wettig2024qurating} uses LLM-generated quality scores; and SelectIT \\citep{liu2024selectit} leverages model uncertainty for instruction data filtering.\n\nThese methods are designed for one-shot curation of static datasets, where the embedding model is fixed and its representation quality is not in question. We show that the iterative self-training setting introduces a qualitatively different failure mode: when the model providing embeddings co-degrades with the training distribution, embedding-based selection amplifies rather than counteracts distributional collapse. Data mixing strategies that blend real and synthetic data across generations \\citep{gerstgrasser2024model} offer a complementary mitigation but do not address the selection mechanism itself.\n\n\\subsection{Embedding-Based Diversity and Representation Learning}\n\nSubmodular maximization provides the algorithmic foundation for embedding-based diversity selection. \\citet{iyer2013submodular} establish the optimization framework for submodular functions under budget constraints; \\citet{wei2015submodularity} formalize data subset selection via facility location and graph-cut objectives in feature space; and \\citet{mirzasoleiman2020coresets} apply gradient-embedding facility location for coreset construction. These methods assume a fixed, high-quality embedding space---an assumption we show breaks down under iterative self-training.\n\nActive learning methods face a related challenge: acquisition functions must remain well-calibrated as the model updates. BADGE \\citep{ash2020deep} selects diverse batches via gradient embeddings; BatchBALD \\citep{kirsch2019batchbald} maximizes joint mutual information; and subsequent work has shown that standard acquisition strategies degrade under distribution shift \\citep{kothawade2021similar} and that embedding quality determines selection effectiveness \\citep{yehuda2022active}. However, active learning typically involves a few rounds of model updating, not the sustained multi-generation feedback loop where selection bias compounds into the selecting model's own training data.\n\nThe representation learning literature documents several mechanisms by which embedding spaces can lose expressiveness. \\citet{jing2022understanding} characterize dimensional collapse in contrastive learning, where embeddings are driven into low-dimensional subspaces; \\citet{hua2021feature} identify correlated feature axes as a driver of this collapse; and \\citet{papyan2020prevalence} show that deep network representations converge to low-dimensional simplex structures during prolonged training. \\citet{laurent2024feature} argue that feature collapse can be benign in classification, but our findings demonstrate that in iterative self-training, the same geometric contraction becomes pathological---it causes diversity selection to invert its intended effect.\n\n\\subsection{Representation Drift and Proxy Misalignment}\n\nOur work connects two established literatures that, together, explain why internal-embedding diversity selection fails under iterative training.\n\nThe concept drift literature studies how learned representations degrade under sustained distribution shift. \\citet{lu2019learning} and \\citet{gama2014survey} provide comprehensive taxonomies of drift detection and adaptation. In the continual learning setting, \\citet{caccia2022new} quantify abrupt representation change during sequential training, and \\citet{davari2022probing} demonstrate that representation-level forgetting proceeds independently of task performance---paralleling our finding that embedding geometry diverges from content diversity even as standard representation quality metrics (RankMe, $k$-NN accuracy) remain stable.\n\nThe Goodhart's law and reward hacking literature formalizes the failure of proxy optimization under distribution shift. \\citet{gao2023scaling} derive scaling laws showing that overoptimizing a proxy reward model degrades true objective performance; \\citet{skalse2022defining} prove that non-trivial proxy rewards are inherently exploitable; \\citet{pan2022effects} map how proxy-objective misalignment compounds under increasing optimization pressure; and \\citet{karwowski2024goodhart} provide geometric characterizations of when proxy optimization diverges from the true objective. The embedding alignment gap is an instance of this phenomenon: internal embedding diversity serves as a proxy for content diversity, and this proxy progressively loses fidelity as the model's representations co-evolve with the selected data distribution.\n\nFinally, measuring diversity itself requires careful metric design. Distinct-N \\citep{li2016diversity} and Self-BLEU \\citep{zhu2018texygen} quantify surface-level lexical diversity, while \\citet{tevet2021evaluating} audit failure modes of both n-gram and neural diversity metrics. MAUVE \\citep{pillutla2021mauve} measures distributional gaps between generated and human text via embedding-space divergence frontiers. We use rare n-gram density as our content diversity measure precisely because, unlike embedding-based metrics, it is model-independent and directly captures the lexical tail erosion that defines model collapse.\n\n\\paragraph{Positioning.} The embedding alignment gap as a concept---that proxy metrics degrade under optimization---is well established across the literatures surveyed above. Our contribution is not conceptual novelty but empirical quantification: we provide a controlled factorial ablation (four methods $\\times$ three seeds) that decomposes the failure into its constituent factors, a diagnostic metric (selection ratio) that tracks proxy-target divergence in real time, and evidence that the failure is specific to internal embeddings rather than to diversity selection in general.\n",
      "numLines": 36,
      "startLine": 1,
      "totalLines": 36
    }
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — Read · `toolu_016aEUchMY1TR3pGEdzEQSs3`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/artifacts/related_work_references.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "ad8dfff4-32b9-4819-b351-6703cea3f246",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UQCHHcqxVXo7hJpUcEeoFe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 687,
      "cache_read_input_tokens": 24402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 687
      },
      "output_tokens": 42,
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

_source line 17 · 2026-05-14T08:18:54.684Z_

<details><summary>↩ Tool result · `toolu_016aEUchMY1TR3pGEdzEQSs3`</summary>

```text
1	# Related Work References — div_cal_verify
2	
3	> 36 篇经过 WebSearch 验证的引用，覆盖 8 个子领域
4	
5	## 1. Concept Drift / Embedding Drift
6	
7	1. **Lu et al. (2019)** "Learning under Concept Drift: A Review" — *IEEE Transactions on Knowledge and Data Engineering*, Vol. 31, No. 12, pp. 2346–2363
8	   - 作者: Jie Lu, Anjin Liu, Fan Dong, Feng Gu, João Gama, Guangquan Zhang
9	   - 关联: 建立了 drift 检测与适应的分类体系，为理解自训练中嵌入空间几何漂移提供了概念框架
10	
11	2. **Gama et al. (2014)** "A Survey on Concept Drift Adaptation" — *ACM Computing Surveys*, Vol. 46, No. 4, Article 44
12	   - 作者: João Gama, Indrė Žliobaitė, Albert Bifet, Mykola Pechenizkiy, Abdelhamid Bouchachia
13	   - 关联: 阐述分布漂移下决策边界退化的机制，为嵌入表征在自训练伪标签分布漂移时的失对齐提供理论基础
14	
15	3. **Caccia et al. (2022)** "New Insights on Reducing Abrupt Representation Change in Online Continual Learning" — *ICLR 2022*
16	   - 作者: Lucas Caccia, Rahaf Aljundi, Nader Asadi, Tinne Tuytelaars, Joëlle Pineau, Eugene Belilovsky
17	   - 关联: 直接量化了序贯训练中内部表征的突变幅度，其度量框架与自训练循环中嵌入对齐间隙的观测高度类似
18	
19	4. **Davari et al. (2022)** "Probing Representation Forgetting in Supervised and Unsupervised Continual Learning" — *CVPR 2022*, pp. 16712–16721
20	   - 作者: MohammadReza Davari, Nader Asadi, Sudhir Mudur, Rahaf Aljundi, Eugene Belilovsky
21	   - 关联: 表明表征层面的遗忘和漂移独立于任务性能衰退，与本文发现的嵌入几何多样性与语义内容多样性脱耦现象直接对应
22	
23	## 2. Active Learning under Distribution Shift
24	
25	5. **Ash et al. (2020)** "Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds" — *ICLR 2020*
26	   - 作者: Jordan T. Ash, Chicheng Zhang, Akshay Krishnamurthy, John Langford, Alekh Agarwal
27	   - 关联: BADGE 使用梯度嵌入上的 k-means++ 选择多样性批次——正是本文研究其在表征漂移下失效的嵌入多样性选择机制
28	
29	6. **Kirsch et al. (2019)** "BatchBALD: Efficient and Diverse Batch Acquisition for Deep Bayesian Active Learning" — *NeurIPS 2019*
30	   - 作者: Andreas Kirsch, Joost van Amersfoort, Yarin Gal
31	   - 关联: 通过联合最大化互信息实现多样性批次选择，依赖稳定表征的假设与本文对嵌入漂移的发现形成对照
32	
33	7. **Kothawade et al. (2021)** "SIMILAR: Submodular Information Measures Based Active Learning In Realistic Scenarios" — *NeurIPS 2021*
34	   - 作者: Suraj Kothawade, Nathan Beck, Krishnateja Killamsetty, Rishabh Iyer
35	   - 关联: 在分布偏移的现实场景下做主动学习，表明标准嵌入选择策略在非 i.i.d. 设置中退化——直接支持 BADGE 式选择在嵌入漂移时失效的论点（亦见 §8）
36	
37	8. **Yehuda et al. (2022)** "Active Learning Through a Covering Lens" — *NeurIPS 2022*
38	   - 作者: Ofer Yehuda, Avihu Dekel, Guy Hacohen, Daphna Weinshall
39	   - 关联: 提出基于自监督嵌入空间的覆盖选择，证明表征质量决定多样性选择的成败
40	
41	## 3. Dimensional Collapse
42	
43	9. **Jing et al. (2022)** "Understanding Dimensional Collapse in Contrastive Self-supervised Learning" — *ICLR 2022*
44	   - 作者: Li Jing, Pascal Vincent, Yann LeCun, Yuandong Tian
45	   - 关联: 刻画对比训练如何将嵌入向量驱入低维子空间——嵌入对齐间隙核心的几何秩坍塌机制
46	
47	10. **Hua et al. (2021)** "On Feature Decorrelation in Self-Supervised Learning" — *ICCV 2021*
48	    - 作者: Tianyu Hua, Wenxiao Wang, Zihui Xue, Sucheng Ren, Yue Wang, Hang Zhao
49	    - 关联: 识别自监督训练中特征轴间相关性导致的维度坍塌，与迭代自训练中嵌入多样性丧失直接对应
50	
51	11. **Papyan et al. (2020)** "Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training" — *PNAS*, 117(40), pp. 24652–24663
52	    - 作者: Vardan Papyan, X. Y. Han, David L. Donoho
53	    - 关联: 高引经典，揭示训练末期最后一层激活坍塌为低维 simplex ETF 结构——建立优化压力坍塌嵌入几何的一般性原理
54	
55	12. **Laurent et al. (2024)** "Feature Collapse" — *ICLR 2024*
56	    - 作者: Thomas Laurent, James H. von Brecht, Xavier Bresson
57	    - 关联: Laurent et al. 证明 feature collapse 在正确条件下是良性的（共享角色实体获得相似表征），但我们的工作表明在迭代自训练中同一机制成为病理性的——内部嵌入坍缩导致 diversity selection 反向选择
58	
59	## 4. Broader Model Collapse
60	
61	13. **Shumailov et al. (2024)** "AI Models Collapse When Trained on Recursively Generated Data" — *Nature*, Vol. 631
62	    - 作者: Ilia Shumailov, Zakhar Shumaylov, Yiren Zhao, Nicolas Papernot, Ross Anderson, Yarin Gal
63	    - 关联: Nature 标志性论文，证明递归训练 AI 生成数据导致不可逆的尾分布坍塌，奠定模型坍塌文献基础
64	
65	14. **Seddik et al. (2024)** "How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse" — *COLM 2024*
66	    - 作者: Mohamed El Amine Seddik, Suei-Wen Chen, Soufiane Hayou, Pierre Youssef, Mérouane Debbah
67	    - 关联: 理论刻画纯合成/混合训练下的坍塌行为，推导出坍塌不可避免的最大合成数据比例
68	
69	15. **Briesch et al. (2023)** "Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop" — *arXiv preprint, arXiv: 2311.16822*
70	    - 作者: Martin Briesch, Dominik Sobania, Franz Rothlauf
71	    - 关联: 实证表明 LLM 迭代自消费中输出多样性随合成数据比例退化，与嵌入空间多样性坍塌互补
72	
73	16. **Guo et al. (2024)** "The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text" — *Findings of NAACL 2024*
74	    - 作者: Yanzhu Guo, Guokan Shang, Michalis Vazirgiannis, Chloé Clavel
75	    - 关联: 追踪自训练轮次中词汇、句法、语义多样性的衰退，在高熵创作任务中多样性坍塌最强——直接对应嵌入空间多样性坍塌
76	
77	17. **Alemohammad et al. (2024)** "Self-Consuming Generative Models Go MAD" — *ICLR 2024*
78	    - 作者: Sina Alemohammad, Josue Casco-Rodriguez, Lorenzo Luzi, Ahmed Imtiaz Humayun, Hossein Babaei, Daniel LeJeune, Ali Siahkoohi, Richard G. Baraniuk
79	    - 关联: 提出"模型自噬障碍"(MAD)，理论证明无新鲜真实数据时自消费循环必然退化质量或多样性
80	
81	18. **Dohmatob et al. (2025)** "Strong Model Collapse" — *ICLR 2025*
82	    - 作者: Elvis Dohmatob, Yunzhen Feng, et al.
83	    - 关联: 建立"强模型坍塌"概念——迭代合成再训练超过临界阈值时的急剧退化相变，为经验坍塌文献提供严格补充
84	
85	19. **Gerstgrasser et al. (2024)** "Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data" — *ICML 2024*
86	    - 作者: Matthias Gerstgrasser, Rylan Schaeffer, Apratim Dey, Rafael Rafailov, Henry Sleight, John Hughes, Tomasz Korbak, Rajashree Agrawal, Dhruv Pai, Andrey Gromov, Daniel A. Roberts, Diyi Yang, David L. Donoho, Sanmi Koyejo
87	    - 关联: 证明累积数据可避免坍塌，仅替换式训练不可避免——我们的实验设置正是替换式（每代替换前一代），为坍塌的必然性提供理论基础
88	
89	## 5. Broader Data Selection
90	
91	20. **Xia et al. (2024)** "LESS: Selecting Influential Data for Targeted Instruction Tuning" — *ICML 2024*
92	    - 作者: Mengzhou Xia, Sadhika Malladi, Suchin Gururangan, Sanjeev Arora, Danqi Chen
93	    - 关联: 基于梯度相似性的指令微调数据选择，在迭代 SFT 场景中与多样性方法直接对比
94	
95	21. **Liu et al. (2024)** "SelectIT: Selective Instruction Tuning for LLMs via Uncertainty-Aware Self-Reflection" — *NeurIPS 2024*
96	    - 作者: Liangxin Liu, Xuebo Liu, Derek F. Wong, Dongfang Li, Ziyi Wang, Baotian Hu, Min Zhang
97	    - 关联: 使用 LLM 内部不确定性（token/句子/模型级别）选择指令数据——与多样性正交的质量信号替代方案
98	
99	22. **Wettig et al. (2024)** "QuRating: Selecting High-Quality Data for Training Language Models" — *ICML 2024*
100	    - 作者: Alexander Wettig, Aatmik Gupta, Saumya Malik, Danqi Chen
101	    - 关联: 基于 LLM 判断的四维质量评分进行预训练数据选择，表明质量选择优于启发式过滤
102	
103	23. **Engstrom et al. (2024)** "DsDm: Model-Aware Dataset Selection with Datamodels" — *ICML 2024*
104	    - 作者: Logan Engstrom, Axel Feldmann, Aleksander Madry
105	    - 关联: 将数据选择框架化为基于 datamodel 的任务性能优化，发现朴素质量代理相似性可能损害性能——与代理信号和真实训练效用之间的间隙相关
106	
107	24. **Sorscher et al. (2022)** "Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning" — *NeurIPS 2022* (Outstanding Paper Award)
108	    - 作者: Ben Sorscher, Robert Geirhos, Shashank Shekhar, Surya Ganguli, Ari S. Morcos
109	    - 关联: 证明基于质量指标的数据修剪可打破幂律缩放——激发整个数据选择文献的基础性结果
110	
111	25. **Xie et al. (2023)** "Data Selection for Language Models via Importance Resampling" (DSIR) — *NeurIPS 2023*
112	    - 作者: Sang Michael Xie, Shibani Santurkar, Tengyu Ma, Percy Liang
113	    - 关联: 基于重要性重采样的特征分布匹配框架，提供非多样性导向的可扩展选择基线
114	
115	## 6. Goodhart's Law / Reward Hacking
116	
117	26. **Gao et al. (2023)** "Scaling Laws for Reward Model Overoptimization" — *ICML 2023*
118	    - 作者: Leo Gao, John Schulman, Jacob Hilton
119	    - 关联: 定量展示对代理奖励模型的过度优化导致真实目标性能下降——与使用内部嵌入作为优化代理并随模型漂移脱耦的现象直接类比
120	
121	27. **Skalse et al. (2022)** "Defining and Characterizing Reward Hacking" — *NeurIPS 2022*
122	    - 作者: Joar Skalse, Nikolaus H. R. Howe, Dmitrii Krasheninnikov, David Krueger
123	    - 关联: 从形式化角度证明非平凡代理奖励本质上可被利用——解释了为何任何嵌入多样性指标在优化器发现代理与真实目标失对齐后都会被攻破
124	
125	28. **Pan et al. (2022)** "The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models" — *ICLR 2022*
126	    - 作者: Alexander Pan, Kush Bhatia, Jacob Steinhardt
127	    - 关联: 实证映射代理奖励误差在优化压力增加下的复合效应，直接对应嵌入多样性指标随训练推进逐步失效
128	
129	29. **Karwowski et al. (2024)** "Goodhart's Law in Reinforcement Learning" — *ICLR 2024*
130	    - 作者: Jacek Karwowski, Oliver Hayman, Xingjian Bai, Klaus Kissel, Adrià Garriga-Alonso, Ulrich Paquet
131	    - 关联: 提供代理优化偏离真实目标的几何刻画并证明早停界——几何直觉直接映射到嵌入漂移中代理指标有效性坍塌的现象
132	
133	## 7. Diversity Metrics
134	
135	30. **Li et al. (2016)** "A Diversity-Promoting Objective Function for Neural Conversation Models" — *NAACL-HLT 2016*
136	    - 作者: Jiwei Li, Michel Galley, Chris Brockett, Jianfeng Gao, Bill Dolan
137	    - 关联: 提出 Distinct-1/Distinct-2（唯一 n-gram 比例），成为与嵌入多样性指标对比的标准表面多样性度量
138	
139	31. **Zhu et al. (2018)** "Texygen: A Benchmarking Platform for Text Generation Models" — *SIGIR 2018*
140	    - 作者: Yaoming Zhu, Sidi Lu, Lei Zheng, Jiaxian Guo, Weinan Zhang, Jun Wang, Yong Yu
141	    - 关联: 提出 Self-BLEU 作为标准化多样性指标并整合文本生成评估方法论，建立了后续几何/嵌入指标试图扩展的评估框架
142	
143	32. **Tevet & Berant (2021)** "Evaluating the Evaluation of Diversity in Natural Language Generation" — *EACL 2021*
144	    - 作者: Guy Tevet, Jonathan Berant
145	    - 关联: 系统审计 n-gram 和神经多样性指标（包括 Distinct-N 和 Self-BLEU）的失效模式，直接激发了对更好的内容感知多样性度量的需求
146	
147	33. **Pillutla et al. (2021)** "MAUVE: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers" — *NeurIPS 2021* (Outstanding Paper Award)
148	    - 作者: Krishna Pillutla, Swabha Swayamdipta, Rowan Zellers, John Thickstun, Sean Welleck, Yejin Choi, Zaid Harchaoui
149	    - 关联: 在量化 LLM 嵌入空间中使用 KL 散度衡量生成文本与人类文本的分布差异——嵌入空间多样性度量的直接先例，为"嵌入对齐间隙"提供关键前置工作
150	
151	## 8. Submodular Maximization for Data Selection
152	
153	34. **Iyer & Bilmes (2013)** "Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints" — *NeurIPS 2013* (Outstanding Paper Award)
154	    - 作者: Rishabh Iyer, Jeff Bilmes
155	    - 关联: 建立带预算约束的次模最大化框架，为嵌入空间上的多样性数据选择方法奠基
156	
157	35. **Wei et al. (2015)** "Submodularity in Data Subset Selection and Active Learning" — *ICML 2015*
158	    - 作者: Kai Wei, Rishabh Iyer, Jeff Bilmes
159	    - 关联: 将数据子集选择形式化为次模最大化（facility location、graph cut），在特征/嵌入空间中度量覆盖和多样性——嵌入对齐间隙问题直接攻击的经典框架
160	
161	36. **Mirzasoleiman et al. (2020)** "Coresets for Data-efficient Training of Machine Learning Models" — *ICML 2020*
162	    - 作者: Baharan Mirzasoleiman, Jeff Bilmes, Jure Leskovec
163	    - 关联: CRAIG 使用梯度嵌入上的 facility location 次模函数选择核心集，在迭代应用时直接受嵌入空间退化影响
164	
165	## 统计
166	- 总引用数: 36
167	- 子领域覆盖: 8/8
168	- 每子领域篇数: 3–7
169	- 验证状态: 全部 VERIFIED（WebSearch 确认标题、作者、年份、venue）
170	- 年份分布: 2013–2025，其中 2020 年后 26 篇
171	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "ff6958ca-0f64-481e-92c4-0d889b889f86",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/artifacts/related_work_references.md",
      "content": "# Related Work References — div_cal_verify\n\n> 36 篇经过 WebSearch 验证的引用，覆盖 8 个子领域\n\n## 1. Concept Drift / Embedding Drift\n\n1. **Lu et al. (2019)** \"Learning under Concept Drift: A Review\" — *IEEE Transactions on Knowledge and Data Engineering*, Vol. 31, No. 12, pp. 2346–2363\n   - 作者: Jie Lu, Anjin Liu, Fan Dong, Feng Gu, João Gama, Guangquan Zhang\n   - 关联: 建立了 drift 检测与适应的分类体系，为理解自训练中嵌入空间几何漂移提供了概念框架\n\n2. **Gama et al. (2014)** \"A Survey on Concept Drift Adaptation\" — *ACM Computing Surveys*, Vol. 46, No. 4, Article 44\n   - 作者: João Gama, Indrė Žliobaitė, Albert Bifet, Mykola Pechenizkiy, Abdelhamid Bouchachia\n   - 关联: 阐述分布漂移下决策边界退化的机制，为嵌入表征在自训练伪标签分布漂移时的失对齐提供理论基础\n\n3. **Caccia et al. (2022)** \"New Insights on Reducing Abrupt Representation Change in Online Continual Learning\" — *ICLR 2022*\n   - 作者: Lucas Caccia, Rahaf Aljundi, Nader Asadi, Tinne Tuytelaars, Joëlle Pineau, Eugene Belilovsky\n   - 关联: 直接量化了序贯训练中内部表征的突变幅度，其度量框架与自训练循环中嵌入对齐间隙的观测高度类似\n\n4. **Davari et al. (2022)** \"Probing Representation Forgetting in Supervised and Unsupervised Continual Learning\" — *CVPR 2022*, pp. 16712–16721\n   - 作者: MohammadReza Davari, Nader Asadi, Sudhir Mudur, Rahaf Aljundi, Eugene Belilovsky\n   - 关联: 表明表征层面的遗忘和漂移独立于任务性能衰退，与本文发现的嵌入几何多样性与语义内容多样性脱耦现象直接对应\n\n## 2. Active Learning under Distribution Shift\n\n5. **Ash et al. (2020)** \"Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds\" — *ICLR 2020*\n   - 作者: Jordan T. Ash, Chicheng Zhang, Akshay Krishnamurthy, John Langford, Alekh Agarwal\n   - 关联: BADGE 使用梯度嵌入上的 k-means++ 选择多样性批次——正是本文研究其在表征漂移下失效的嵌入多样性选择机制\n\n6. **Kirsch et al. (2019)** \"BatchBALD: Efficient and Diverse Batch Acquisition for Deep Bayesian Active Learning\" — *NeurIPS 2019*\n   - 作者: Andreas Kirsch, Joost van Amersfoort, Yarin Gal\n   - 关联: 通过联合最大化互信息实现多样性批次选择，依赖稳定表征的假设与本文对嵌入漂移的发现形成对照\n\n7. **Kothawade et al. (2021)** \"SIMILAR: Submodular Information Measures Based Active Learning In Realistic Scenarios\" — *NeurIPS 2021*\n   - 作者: Suraj Kothawade, Nathan Beck, Krishnateja Killamsetty, Rishabh Iyer\n   - 关联: 在分布偏移的现实场景下做主动学习，表明标准嵌入选择策略在非 i.i.d. 设置中退化——直接支持 BADGE 式选择在嵌入漂移时失效的论点（亦见 §8）\n\n8. **Yehuda et al. (2022)** \"Active Learning Through a Covering Lens\" — *NeurIPS 2022*\n   - 作者: Ofer Yehuda, Avihu Dekel, Guy Hacohen, Daphna Weinshall\n   - 关联: 提出基于自监督嵌入空间的覆盖选择，证明表征质量决定多样性选择的成败\n\n## 3. Dimensional Collapse\n\n9. **Jing et al. (2022)** \"Understanding Dimensional Collapse in Contrastive Self-supervised Learning\" — *ICLR 2022*\n   - 作者: Li Jing, Pascal Vincent, Yann LeCun, Yuandong Tian\n   - 关联: 刻画对比训练如何将嵌入向量驱入低维子空间——嵌入对齐间隙核心的几何秩坍塌机制\n\n10. **Hua et al. (2021)** \"On Feature Decorrelation in Self-Supervised Learning\" — *ICCV 2021*\n    - 作者: Tianyu Hua, Wenxiao Wang, Zihui Xue, Sucheng Ren, Yue Wang, Hang Zhao\n    - 关联: 识别自监督训练中特征轴间相关性导致的维度坍塌，与迭代自训练中嵌入多样性丧失直接对应\n\n11. **Papyan et al. (2020)** \"Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training\" — *PNAS*, 117(40), pp. 24652–24663\n    - 作者: Vardan Papyan, X. Y. Han, David L. Donoho\n    - 关联: 高引经典，揭示训练末期最后一层激活坍塌为低维 simplex ETF 结构——建立优化压力坍塌嵌入几何的一般性原理\n\n12. **Laurent et al. (2024)** \"Feature Collapse\" — *ICLR 2024*\n    - 作者: Thomas Laurent, James H. von Brecht, Xavier Bresson\n    - 关联: Laurent et al. 证明 feature collapse 在正确条件下是良性的（共享角色实体获得相似表征），但我们的工作表明在迭代自训练中同一机制成为病理性的——内部嵌入坍缩导致 diversity selection 反向选择\n\n## 4. Broader Model Collapse\n\n13. **Shumailov et al. (2024)** \"AI Models Collapse When Trained on Recursively Generated Data\" — *Nature*, Vol. 631\n    - 作者: Ilia Shumailov, Zakhar Shumaylov, Yiren Zhao, Nicolas Papernot, Ross Anderson, Yarin Gal\n    - 关联: Nature 标志性论文，证明递归训练 AI 生成数据导致不可逆的尾分布坍塌，奠定模型坍塌文献基础\n\n14. **Seddik et al. (2024)** \"How Bad is Training on Synthetic Data? A Statistical Analysis of Language Model Collapse\" — *COLM 2024*\n    - 作者: Mohamed El Amine Seddik, Suei-Wen Chen, Soufiane Hayou, Pierre Youssef, Mérouane Debbah\n    - 关联: 理论刻画纯合成/混合训练下的坍塌行为，推导出坍塌不可避免的最大合成数据比例\n\n15. **Briesch et al. (2023)** \"Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop\" — *arXiv preprint, arXiv: 2311.16822*\n    - 作者: Martin Briesch, Dominik Sobania, Franz Rothlauf\n    - 关联: 实证表明 LLM 迭代自消费中输出多样性随合成数据比例退化，与嵌入空间多样性坍塌互补\n\n16. **Guo et al. (2024)** \"The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text\" — *Findings of NAACL 2024*\n    - 作者: Yanzhu Guo, Guokan Shang, Michalis Vazirgiannis, Chloé Clavel\n    - 关联: 追踪自训练轮次中词汇、句法、语义多样性的衰退，在高熵创作任务中多样性坍塌最强——直接对应嵌入空间多样性坍塌\n\n17. **Alemohammad et al. (2024)** \"Self-Consuming Generative Models Go MAD\" — *ICLR 2024*\n    - 作者: Sina Alemohammad, Josue Casco-Rodriguez, Lorenzo Luzi, Ahmed Imtiaz Humayun, Hossein Babaei, Daniel LeJeune, Ali Siahkoohi, Richard G. Baraniuk\n    - 关联: 提出\"模型自噬障碍\"(MAD)，理论证明无新鲜真实数据时自消费循环必然退化质量或多样性\n\n18. **Dohmatob et al. (2025)** \"Strong Model Collapse\" — *ICLR 2025*\n    - 作者: Elvis Dohmatob, Yunzhen Feng, et al.\n    - 关联: 建立\"强模型坍塌\"概念——迭代合成再训练超过临界阈值时的急剧退化相变，为经验坍塌文献提供严格补充\n\n19. **Gerstgrasser et al. (2024)** \"Is Model Collapse Inevitable? Breaking the Curse of Recursion by Accumulating Real and Synthetic Data\" — *ICML 2024*\n    - 作者: Matthias Gerstgrasser, Rylan Schaeffer, Apratim Dey, Rafael Rafailov, Henry Sleight, John Hughes, Tomasz Korbak, Rajashree Agrawal, Dhruv Pai, Andrey Gromov, Daniel A. Roberts, Diyi Yang, David L. Donoho, Sanmi Koyejo\n    - 关联: 证明累积数据可避免坍塌，仅替换式训练不可避免——我们的实验设置正是替换式（每代替换前一代），为坍塌的必然性提供理论基础\n\n## 5. Broader Data Selection\n\n20. **Xia et al. (2024)** \"LESS: Selecting Influential Data for Targeted Instruction Tuning\" — *ICML 2024*\n    - 作者: Mengzhou Xia, Sadhika Malladi, Suchin Gururangan, Sanjeev Arora, Danqi Chen\n    - 关联: 基于梯度相似性的指令微调数据选择，在迭代 SFT 场景中与多样性方法直接对比\n\n21. **Liu et al. (2024)** \"SelectIT: Selective Instruction Tuning for LLMs via Uncertainty-Aware Self-Reflection\" — *NeurIPS 2024*\n    - 作者: Liangxin Liu, Xuebo Liu, Derek F. Wong, Dongfang Li, Ziyi Wang, Baotian Hu, Min Zhang\n    - 关联: 使用 LLM 内部不确定性（token/句子/模型级别）选择指令数据——与多样性正交的质量信号替代方案\n\n22. **Wettig et al. (2024)** \"QuRating: Selecting High-Quality Data for Training Language Models\" — *ICML 2024*\n    - 作者: Alexander Wettig, Aatmik Gupta, Saumya Malik, Danqi Chen\n    - 关联: 基于 LLM 判断的四维质量评分进行预训练数据选择，表明质量选择优于启发式过滤\n\n23. **Engstrom et al. (2024)** \"DsDm: Model-Aware Dataset Selection with Datamodels\" — *ICML 2024*\n    - 作者: Logan Engstrom, Axel Feldmann, Aleksander Madry\n    - 关联: 将数据选择框架化为基于 datamodel 的任务性能优化，发现朴素质量代理相似性可能损害性能——与代理信号和真实训练效用之间的间隙相关\n\n24. **Sorscher et al. (2022)** \"Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning\" — *NeurIPS 2022* (Outstanding Paper Award)\n    - 作者: Ben Sorscher, Robert Geirhos, Shashank Shekhar, Surya Ganguli, Ari S. Morcos\n    - 关联: 证明基于质量指标的数据修剪可打破幂律缩放——激发整个数据选择文献的基础性结果\n\n25. **Xie et al. (2023)** \"Data Selection for Language Models via Importance Resampling\" (DSIR) — *NeurIPS 2023*\n    - 作者: Sang Michael Xie, Shibani Santurkar, Tengyu Ma, Percy Liang\n    - 关联: 基于重要性重采样的特征分布匹配框架，提供非多样性导向的可扩展选择基线\n\n## 6. Goodhart's Law / Reward Hacking\n\n26. **Gao et al. (2023)** \"Scaling Laws for Reward Model Overoptimization\" — *ICML 2023*\n    - 作者: Leo Gao, John Schulman, Jacob Hilton\n    - 关联: 定量展示对代理奖励模型的过度优化导致真实目标性能下降——与使用内部嵌入作为优化代理并随模型漂移脱耦的现象直接类比\n\n27. **Skalse et al. (2022)** \"Defining and Characterizing Reward Hacking\" — *NeurIPS 2022*\n    - 作者: Joar Skalse, Nikolaus H. R. Howe, Dmitrii Krasheninnikov, David Krueger\n    - 关联: 从形式化角度证明非平凡代理奖励本质上可被利用——解释了为何任何嵌入多样性指标在优化器发现代理与真实目标失对齐后都会被攻破\n\n28. **Pan et al. (2022)** \"The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models\" — *ICLR 2022*\n    - 作者: Alexander Pan, Kush Bhatia, Jacob Steinhardt\n    - 关联: 实证映射代理奖励误差在优化压力增加下的复合效应，直接对应嵌入多样性指标随训练推进逐步失效\n\n29. **Karwowski et al. (2024)** \"Goodhart's Law in Reinforcement Learning\" — *ICLR 2024*\n    - 作者: Jacek Karwowski, Oliver Hayman, Xingjian Bai, Klaus Kissel, Adrià Garriga-Alonso, Ulrich Paquet\n    - 关联: 提供代理优化偏离真实目标的几何刻画并证明早停界——几何直觉直接映射到嵌入漂移中代理指标有效性坍塌的现象\n\n## 7. Diversity Metrics\n\n30. **Li et al. (2016)** \"A Diversity-Promoting Objective Function for Neural Conversation Models\" — *NAACL-HLT 2016*\n    - 作者: Jiwei Li, Michel Galley, Chris Brockett, Jianfeng Gao, Bill Dolan\n    - 关联: 提出 Distinct-1/Distinct-2（唯一 n-gram 比例），成为与嵌入多样性指标对比的标准表面多样性度量\n\n31. **Zhu et al. (2018)** \"Texygen: A Benchmarking Platform for Text Generation Models\" — *SIGIR 2018*\n    - 作者: Yaoming Zhu, Sidi Lu, Lei Zheng, Jiaxian Guo, Weinan Zhang, Jun Wang, Yong Yu\n    - 关联: 提出 Self-BLEU 作为标准化多样性指标并整合文本生成评估方法论，建立了后续几何/嵌入指标试图扩展的评估框架\n\n32. **Tevet & Berant (2021)** \"Evaluating the Evaluation of Diversity in Natural Language Generation\" — *EACL 2021*\n    - 作者: Guy Tevet, Jonathan Berant\n    - 关联: 系统审计 n-gram 和神经多样性指标（包括 Distinct-N 和 Self-BLEU）的失效模式，直接激发了对更好的内容感知多样性度量的需求\n\n33. **Pillutla et al. (2021)** \"MAUVE: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers\" — *NeurIPS 2021* (Outstanding Paper Award)\n    - 作者: Krishna Pillutla, Swabha Swayamdipta, Rowan Zellers, John Thickstun, Sean Welleck, Yejin Choi, Zaid Harchaoui\n    - 关联: 在量化 LLM 嵌入空间中使用 KL 散度衡量生成文本与人类文本的分布差异——嵌入空间多样性度量的直接先例，为\"嵌入对齐间隙\"提供关键前置工作\n\n## 8. Submodular Maximization for Data Selection\n\n34. **Iyer & Bilmes (2013)** \"Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints\" — *NeurIPS 2013* (Outstanding Paper Award)\n    - 作者: Rishabh Iyer, Jeff Bilmes\n    - 关联: 建立带预算约束的次模最大化框架，为嵌入空间上的多样性数据选择方法奠基\n\n35. **Wei et al. (2015)** \"Submodularity in Data Subset Selection and Active Learning\" — *ICML 2015*\n    - 作者: Kai Wei, Rishabh Iyer, Jeff Bilmes\n    - 关联: 将数据子集选择形式化为次模最大化（facility location、graph cut），在特征/嵌入空间中度量覆盖和多样性——嵌入对齐间隙问题直接攻击的经典框架\n\n36. **Mirzasoleiman et al. (2020)** \"Coresets for Data-efficient Training of Machine Learning Models\" — *ICML 2020*\n    - 作者: Baharan Mirzasoleiman, Jeff Bilmes, Jure Leskovec\n    - 关联: CRAIG 使用梯度嵌入上的 facility location 次模函数选择核心集，在迭代应用时直接受嵌入空间退化影响\n\n## 统计\n- 总引用数: 36\n- 子领域覆盖: 8/8\n- 每子领域篇数: 3–7\n- 验证状态: 全部 VERIFIED（WebSearch 确认标题、作者、年份、venue）\n- 年份分布: 2013–2025，其中 2020 年后 26 篇\n",
      "numLines": 171,
      "startLine": 1,
      "totalLines": 171
    }
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Read · `toolu_01H9SHufzYpDevayWtaEEy5K`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "d7554569-698b-41f1-b8aa-18b92ac3f8a2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UQCHHcqxVXo7hJpUcEeoFe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 687,
      "cache_read_input_tokens": 24402,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 687
      },
      "output_tokens": 42,
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

_source line 19 · 2026-05-14T08:18:55.146Z_

<details><summary>↩ Tool result · `toolu_01H9SHufzYpDevayWtaEEy5K`</summary>

```text
1	% === 1. Concept Drift / Embedding Drift ===
2	
3	@article{lu2019learning,
4	  title={Learning under Concept Drift: A Review},
5	  author={Lu, Jie and Liu, Anjin and Dong, Fan and Gu, Feng and Gama, Jo{\~a}o and Zhang, Guangquan},
6	  journal={IEEE Transactions on Knowledge and Data Engineering},
7	  volume={31},
8	  number={12},
9	  pages={2346--2363},
10	  year={2019},
11	  publisher={IEEE}
12	}
13	
14	@article{gama2014survey,
15	  title={A Survey on Concept Drift Adaptation},
16	  author={Gama, Jo{\~a}o and {\v{Z}}liobait{\.e}, Indr{\.e} and Bifet, Albert and Pechenizkiy, Mykola and Bouchachia, Abdelhamid},
17	  journal={ACM Computing Surveys},
18	  volume={46},
19	  number={4},
20	  pages={1--37},
21	  year={2014},
22	  publisher={ACM}
23	}
24	
25	@inproceedings{caccia2022new,
26	  title={New Insights on Reducing Abrupt Representation Change in Online Continual Learning},
27	  author={Caccia, Lucas and Aljundi, Rahaf and Asadi, Nader and Tuytelaars, Tinne and Pineau, Jo{\"e}lle and Belilovsky, Eugene},
28	  booktitle={International Conference on Learning Representations},
29	  year={2022}
30	}
31	
32	@inproceedings{davari2022probing,
33	  title={Probing Representation Forgetting in Supervised and Unsupervised Continual Learning},
34	  author={Davari, MohammadReza and Asadi, Nader and Mudur, Sudhir and Aljundi, Rahaf and Belilovsky, Eugene},
35	  booktitle={Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition},
36	  pages={16712--16721},
37	  year={2022}
38	}
39	
40	% === 2. Active Learning under Distribution Shift ===
41	
42	@inproceedings{ash2020deep,
43	  title={Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds},
44	  author={Ash, Jordan T. and Zhang, Chicheng and Krishnamurthy, Akshay and Langford, John and Agarwal, Alekh},
45	  booktitle={International Conference on Learning Representations},
46	  year={2020}
47	}
48	
49	@inproceedings{kirsch2019batchbald,
50	  title={{BatchBALD}: Efficient and Diverse Batch Acquisition for Deep {B}ayesian Active Learning},
51	  author={Kirsch, Andreas and van Amersfoort, Joost and Gal, Yarin},
52	  booktitle={Advances in Neural Information Processing Systems},
53	  year={2019}
54	}
55	
56	@inproceedings{kothawade2021similar,
57	  title={{SIMILAR}: Submodular Information Measures Based Active Learning In Realistic Scenarios},
58	  author={Kothawade, Suraj and Beck, Nathan and Killamsetty, Krishnateja and Iyer, Rishabh},
59	  booktitle={Advances in Neural Information Processing Systems},
60	  year={2021}
61	}
62	
63	@inproceedings{yehuda2022active,
64	  title={Active Learning Through a Covering Lens},
65	  author={Yehuda, Ofer and Dekel, Avihu and Hacohen, Guy and Weinshall, Daphna},
66	  booktitle={Advances in Neural Information Processing Systems},
67	  year={2022}
68	}
69	
70	% === 2b. RankMe ===
71	
72	@inproceedings{garrido2023rankme,
73	  title={{RankMe}: Assessing the Downstream Performance to Judge the Quality of Learnt Representations},
74	  author={Garrido, Quentin and Balestriero, Randall and Najman, Laurent and LeCun, Yann},
75	  booktitle={International Conference on Learning Representations},
76	  year={2023}
77	}
78	
79	% === 3. Dimensional Collapse ===
80	
81	@inproceedings{jing2022understanding,
82	  title={Understanding Dimensional Collapse in Contrastive Self-supervised Learning},
83	  author={Jing, Li and Vincent, Pascal and LeCun, Yann and Tian, Yuandong},
84	  booktitle={International Conference on Learning Representations},
85	  year={2022}
86	}
87	
88	@inproceedings{hua2021feature,
89	  title={On Feature Decorrelation in Self-Supervised Learning},
90	  author={Hua, Tianyu and Wang, Wenxiao and Xue, Zihui and Ren, Sucheng and Wang, Yue and Zhao, Hang},
91	  booktitle={Proceedings of the IEEE/CVF International Conference on Computer Vision},
92	  year={2021}
93	}
94	
95	@article{papyan2020prevalence,
96	  title={Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training},
97	  author={Papyan, Vardan and Han, X. Y. and Donoho, David L.},
98	  journal={Proceedings of the National Academy of Sciences},
99	  volume={117},
100	  number={40},
101	  pages={24652--24663},
102	  year={2020}
103	}
104	
105	@inproceedings{laurent2024feature,
106	  title={Feature Collapse},
107	  author={Laurent, Thomas and von Brecht, James H. and Bresson, Xavier},
108	  booktitle={International Conference on Learning Representations},
109	  year={2024}
110	}
111	
112	% === 4. Broader Model Collapse ===
113	
114	@article{shumailov2024ai,
115	  title={{AI} Models Collapse When Trained on Recursively Generated Data},
116	  author={Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},
117	  journal={Nature},
118	  volume={631},
119	  pages={755--759},
120	  year={2024},
121	  publisher={Nature Publishing Group}
122	}
123	
124	@inproceedings{seddik2024how,
125	  title={How Bad is Training on Synthetic Data? {A} Statistical Analysis of Language Model Collapse},
126	  author={Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pierre and Debbah, M{\'e}rouane},
127	  booktitle={Conference on Language Modeling},
128	  year={2024}
129	}
130	
131	@article{briesch2023large,
132	  title={Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop},
133	  author={Briesch, Martin and Sobania, Dominik and Rothlauf, Franz},
134	  journal={arXiv preprint arXiv:2311.16822},
135	  year={2023}
136	}
137	
138	@inproceedings{guo2024curious,
139	  title={The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text},
140	  author={Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo{\'e}},
141	  booktitle={Findings of the Association for Computational Linguistics: NAACL 2024},
142	  year={2024}
143	}
144	
145	@inproceedings{alemohammad2024self,
146	  title={Self-Consuming Generative Models Go {MAD}},
147	  author={Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},
148	  booktitle={International Conference on Learning Representations},
149	  year={2024}
150	}
151	
152	@inproceedings{dohmatob2025strong,
153	  title={Strong Model Collapse},
154	  author={Dohmatob, Elvis and Feng, Yunzhen and Others},
155	  booktitle={International Conference on Learning Representations},
156	  year={2025}
157	}
158	
159	@inproceedings{gerstgrasser2024model,
160	  title={Is Model Collapse Inevitable? {B}reaking the Curse of Recursion by Accumulating Real and Synthetic Data},
161	  author={Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},
162	  booktitle={International Conference on Machine Learning},
163	  year={2024}
164	}
165	
166	% === 4b. Data Deduplication / Curation ===
167	
168	@inproceedings{abbas2023semdedup,
169	  title={{SemDeDup}: Data-efficient Learning at Web-scale through Semantic Deduplication},
170	  author={Abbas, Amro and Tirumala, Kushal and Simig, D{\'a}niel and Ganguli, Surya and Morcos, Ari S.},
171	  booktitle={Advances in Neural Information Processing Systems},
172	  year={2023}
173	}
174	
175	@inproceedings{tirumala2023d4,
176	  title={{D4}: Improving {LLM} Pretraining via Document De-Duplication and Diversification},
177	  author={Tirumala, Kushal and Simig, D{\'a}niel and Aghajanyan, Armen and Morcos, Ari S.},
178	  booktitle={Advances in Neural Information Processing Systems},
179	  year={2023}
180	}
181	
182	% === 5. Broader Data Selection ===
183	
184	@inproceedings{xia2024less,
185	  title={{LESS}: Selecting Influential Data for Targeted Instruction Tuning},
186	  author={Xia, Mengzhou and Malladi, Sadhika and Gururangan, Suchin and Arora, Sanjeev and Chen, Danqi},
187	  booktitle={International Conference on Machine Learning},
188	  year={2024}
189	}
190	
191	@inproceedings{liu2024selectit,
192	  title={{SelectIT}: Selective Instruction Tuning for {LLM}s via Uncertainty-Aware Self-Reflection},
193	  author={Liu, Liangxin and Liu, Xuebo and Wong, Derek F. and Li, Dongfang and Wang, Ziyi and Hu, Baotian and Zhang, Min},
194	  booktitle={Advances in Neural Information Processing Systems},
195	  year={2024}
196	}
197	
198	@inproceedings{wettig2024qurating,
199	  title={{QuRating}: Selecting High-Quality Data for Training Language Models},
200	  author={Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},
201	  booktitle={International Conference on Machine Learning},
202	  year={2024}
203	}
204	
205	@inproceedings{engstrom2024dsdm,
206	  title={{DsDm}: Model-Aware Dataset Selection with Datamodels},
207	  author={Engstrom, Logan and Feldmann, Axel and Madry, Aleksander},
208	  booktitle={International Conference on Machine Learning},
209	  year={2024}
210	}
211	
212	@inproceedings{sorscher2022beyond,
213	  title={Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning},
214	  author={Sorscher, Ben and Geirhos, Robert and Shekhar, Shashank and Ganguli, Surya and Morcos, Ari S.},
215	  booktitle={Advances in Neural Information Processing Systems},
216	  year={2022}
217	}
218	
219	@inproceedings{xie2023data,
220	  title={Data Selection for Language Models via Importance Resampling},
221	  author={Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},
222	  booktitle={Advances in Neural Information Processing Systems},
223	  year={2023}
224	}
225	
226	% === 6. Goodhart's Law / Reward Hacking ===
227	
228	@inproceedings{gao2023scaling,
229	  title={Scaling Laws for Reward Model Overoptimization},
230	  author={Gao, Leo and Schulman, John and Hilton, Jacob},
231	  booktitle={International Conference on Machine Learning},
232	  year={2023}
233	}
234	
235	@inproceedings{skalse2022defining,
236	  title={Defining and Characterizing Reward Hacking},
237	  author={Skalse, Joar and Howe, Nikolaus H. R. and Krasheninnikov, Dmitrii and Krueger, David},
238	  booktitle={Advances in Neural Information Processing Systems},
239	  year={2022}
240	}
241	
242	@inproceedings{pan2022effects,
243	  title={The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models},
244	  author={Pan, Alexander and Bhatia, Kush and Steinhardt, Jacob},
245	  booktitle={International Conference on Learning Representations},
246	  year={2022}
247	}
248	
249	@inproceedings{karwowski2024goodhart,
250	  title={Goodhart's Law in Reinforcement Learning},
251	  author={Karwowski, Jacek and Hayman, Oliver and Bai, Xingjian and Kissel, Klaus and Garriga-Alonso, Adri{\`a} and Paquet, Ulrich},
252	  booktitle={International Conference on Learning Representations},
253	  year={2024}
254	}
255	
256	% === 7. Diversity Metrics ===
257	
258	@inproceedings{li2016diversity,
259	  title={A Diversity-Promoting Objective Function for Neural Conversation Models},
260	  author={Li, Jiwei and Galley, Michel and Brockett, Chris and Gao, Jianfeng and Dolan, Bill},
261	  booktitle={Proceedings of the 2016 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},
262	  year={2016}
263	}
264	
265	@inproceedings{zhu2018texygen,
266	  title={Texygen: A Benchmarking Platform for Text Generation Models},
267	  author={Zhu, Yaoming and Lu, Sidi and Zheng, Lei and Guo, Jiaxian and Zhang, Weinan and Wang, Jun and Yu, Yong},
268	  booktitle={The 41st International ACM SIGIR Conference on Research \& Development in Information Retrieval},
269	  year={2018}
270	}
271	
272	@inproceedings{tevet2021evaluating,
273	  title={Evaluating the Evaluation of Diversity in Natural Language Generation},
274	  author={Tevet, Guy and Berant, Jonathan},
275	  booktitle={Proceedings of the 16th Conference of the European Chapter of the Association for Computational Linguistics},
276	  year={2021}
277	}
278	
279	@inproceedings{pillutla2021mauve,
280	  title={{MAUVE}: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers},
281	  author={Pillutla, Krishna and Swayamdipta, Swabha and Zellers, Rowan and Thickstun, John and Welleck, Sean and Choi, Yejin and Harchaoui, Zaid},
282	  booktitle={Advances in Neural Information Processing Systems},
283	  year={2021}
284	}
285	
286	% === 8. Contriever ===
287	
288	@article{izacard2022unsupervised,
289	  title={Unsupervised Dense Information Retrieval with Contrastive Learning},
290	  author={Izacard, Gautier and Caron, Mathilde and Hosseini, Lucas and Riedel, Sebastian and Bojanowski, Piotr and Joulin, Armand and Grave, Edouard},
291	  journal={Transactions on Machine Learning Research},
292	  year={2022}
293	}
294	
295	% === 9. Submodular Maximization for Data Selection ===
296	
297	@inproceedings{iyer2013submodular,
298	  title={Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints},
299	  author={Iyer, Rishabh and Bilmes, Jeff},
300	  booktitle={Advances in Neural Information Processing Systems},
301	  year={2013}
302	}
303	
304	@inproceedings{wei2015submodularity,
305	  title={Submodularity in Data Subset Selection and Active Learning},
306	  author={Wei, Kai and Iyer, Rishabh and Bilmes, Jeff},
307	  booktitle={International Conference on Machine Learning},
308	  year={2015}
309	}
310	
311	@inproceedings{mirzasoleiman2020coresets,
312	  title={Coresets for Data-efficient Training of Machine Learning Models},
313	  author={Mirzasoleiman, Baharan and Bilmes, Jeff and Leskovec, Jure},
314	  booktitle={International Conference on Machine Learning},
315	  year={2020}
316	}
317	
318	% === 10. Self-Play ===
319	
320	@article{silver2017mastering,
321	  title={Mastering the Game of {Go} without Human Knowledge},
322	  author={Silver, David and Schrittwieser, Julian and Simonyan, Karen and Antonoglou, Ioannis and Huang, Aja and Guez, Arthur and Hubert, Thomas and Baker, Lucas and Lai, Matthew and Bolton, Adrian and Others},
323	  journal={Nature},
324	  volume={550},
325	  pages={354--359},
326	  year={2017}
327	}
328	
329	@article{singh2024beyond,
330	  title={Beyond Human Data: Scaling Self-Training for Problem-Solving with Language Models},
331	  author={Singh, Avi and Co-Reyes, John D. and Agarwal, Rishabh and Anand, Ankesh and Patil, Piyush and Garcia, Xavier and Liu, Peter J. and Harrison, James and Lee, Jaehoon and Xu, Kelvin and Parisi, Aaron and Kumar, Abhishek and Alemi, Alex and Rizkowsky, Alex and Nova, Azade and Adlam, Ben and Passos, Alexandre Tachard and Anil, Rohan and Barber, David and Houlsby, Neil},
332	  journal={Transactions on Machine Learning Research},
333	  year={2024}
334	}
335	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "5991d767-6586-4647-b0a7-3220a65eed2f",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/docs/paper/references.bib",
      "content": "% === 1. Concept Drift / Embedding Drift ===\n\n@article{lu2019learning,\n  title={Learning under Concept Drift: A Review},\n  author={Lu, Jie and Liu, Anjin and Dong, Fan and Gu, Feng and Gama, Jo{\\~a}o and Zhang, Guangquan},\n  journal={IEEE Transactions on Knowledge and Data Engineering},\n  volume={31},\n  number={12},\n  pages={2346--2363},\n  year={2019},\n  publisher={IEEE}\n}\n\n@article{gama2014survey,\n  title={A Survey on Concept Drift Adaptation},\n  author={Gama, Jo{\\~a}o and {\\v{Z}}liobait{\\.e}, Indr{\\.e} and Bifet, Albert and Pechenizkiy, Mykola and Bouchachia, Abdelhamid},\n  journal={ACM Computing Surveys},\n  volume={46},\n  number={4},\n  pages={1--37},\n  year={2014},\n  publisher={ACM}\n}\n\n@inproceedings{caccia2022new,\n  title={New Insights on Reducing Abrupt Representation Change in Online Continual Learning},\n  author={Caccia, Lucas and Aljundi, Rahaf and Asadi, Nader and Tuytelaars, Tinne and Pineau, Jo{\\\"e}lle and Belilovsky, Eugene},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{davari2022probing,\n  title={Probing Representation Forgetting in Supervised and Unsupervised Continual Learning},\n  author={Davari, MohammadReza and Asadi, Nader and Mudur, Sudhir and Aljundi, Rahaf and Belilovsky, Eugene},\n  booktitle={Proceedings of the IEEE/CVF Conference on Computer Vision and Pattern Recognition},\n  pages={16712--16721},\n  year={2022}\n}\n\n% === 2. Active Learning under Distribution Shift ===\n\n@inproceedings{ash2020deep,\n  title={Deep Batch Active Learning by Diverse, Uncertain Gradient Lower Bounds},\n  author={Ash, Jordan T. and Zhang, Chicheng and Krishnamurthy, Akshay and Langford, John and Agarwal, Alekh},\n  booktitle={International Conference on Learning Representations},\n  year={2020}\n}\n\n@inproceedings{kirsch2019batchbald,\n  title={{BatchBALD}: Efficient and Diverse Batch Acquisition for Deep {B}ayesian Active Learning},\n  author={Kirsch, Andreas and van Amersfoort, Joost and Gal, Yarin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2019}\n}\n\n@inproceedings{kothawade2021similar,\n  title={{SIMILAR}: Submodular Information Measures Based Active Learning In Realistic Scenarios},\n  author={Kothawade, Suraj and Beck, Nathan and Killamsetty, Krishnateja and Iyer, Rishabh},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2021}\n}\n\n@inproceedings{yehuda2022active,\n  title={Active Learning Through a Covering Lens},\n  author={Yehuda, Ofer and Dekel, Avihu and Hacohen, Guy and Weinshall, Daphna},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n% === 2b. RankMe ===\n\n@inproceedings{garrido2023rankme,\n  title={{RankMe}: Assessing the Downstream Performance to Judge the Quality of Learnt Representations},\n  author={Garrido, Quentin and Balestriero, Randall and Najman, Laurent and LeCun, Yann},\n  booktitle={International Conference on Learning Representations},\n  year={2023}\n}\n\n% === 3. Dimensional Collapse ===\n\n@inproceedings{jing2022understanding,\n  title={Understanding Dimensional Collapse in Contrastive Self-supervised Learning},\n  author={Jing, Li and Vincent, Pascal and LeCun, Yann and Tian, Yuandong},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{hua2021feature,\n  title={On Feature Decorrelation in Self-Supervised Learning},\n  author={Hua, Tianyu and Wang, Wenxiao and Xue, Zihui and Ren, Sucheng and Wang, Yue and Zhao, Hang},\n  booktitle={Proceedings of the IEEE/CVF International Conference on Computer Vision},\n  year={2021}\n}\n\n@article{papyan2020prevalence,\n  title={Prevalence of Neural Collapse during the Terminal Phase of Deep Learning Training},\n  author={Papyan, Vardan and Han, X. Y. and Donoho, David L.},\n  journal={Proceedings of the National Academy of Sciences},\n  volume={117},\n  number={40},\n  pages={24652--24663},\n  year={2020}\n}\n\n@inproceedings{laurent2024feature,\n  title={Feature Collapse},\n  author={Laurent, Thomas and von Brecht, James H. and Bresson, Xavier},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n% === 4. Broader Model Collapse ===\n\n@article{shumailov2024ai,\n  title={{AI} Models Collapse When Trained on Recursively Generated Data},\n  author={Shumailov, Ilia and Shumaylov, Zakhar and Zhao, Yiren and Papernot, Nicolas and Anderson, Ross and Gal, Yarin},\n  journal={Nature},\n  volume={631},\n  pages={755--759},\n  year={2024},\n  publisher={Nature Publishing Group}\n}\n\n@inproceedings{seddik2024how,\n  title={How Bad is Training on Synthetic Data? {A} Statistical Analysis of Language Model Collapse},\n  author={Seddik, Mohamed El Amine and Chen, Suei-Wen and Hayou, Soufiane and Youssef, Pierre and Debbah, M{\\'e}rouane},\n  booktitle={Conference on Language Modeling},\n  year={2024}\n}\n\n@article{briesch2023large,\n  title={Large Language Models Suffer From Their Own Output: An Analysis of the Self-Consuming Training Loop},\n  author={Briesch, Martin and Sobania, Dominik and Rothlauf, Franz},\n  journal={arXiv preprint arXiv:2311.16822},\n  year={2023}\n}\n\n@inproceedings{guo2024curious,\n  title={The Curious Decline of Linguistic Diversity: Training Language Models on Synthetic Text},\n  author={Guo, Yanzhu and Shang, Guokan and Vazirgiannis, Michalis and Clavel, Chlo{\\'e}},\n  booktitle={Findings of the Association for Computational Linguistics: NAACL 2024},\n  year={2024}\n}\n\n@inproceedings{alemohammad2024self,\n  title={Self-Consuming Generative Models Go {MAD}},\n  author={Alemohammad, Sina and Casco-Rodriguez, Josue and Luzi, Lorenzo and Humayun, Ahmed Imtiaz and Babaei, Hossein and LeJeune, Daniel and Siahkoohi, Ali and Baraniuk, Richard G.},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n@inproceedings{dohmatob2025strong,\n  title={Strong Model Collapse},\n  author={Dohmatob, Elvis and Feng, Yunzhen and Others},\n  booktitle={International Conference on Learning Representations},\n  year={2025}\n}\n\n@inproceedings{gerstgrasser2024model,\n  title={Is Model Collapse Inevitable? {B}reaking the Curse of Recursion by Accumulating Real and Synthetic Data},\n  author={Gerstgrasser, Matthias and Schaeffer, Rylan and Dey, Apratim and Rafailov, Rafael and Sleight, Henry and Hughes, John and Korbak, Tomasz and Agrawal, Rajashree and Pai, Dhruv and Gromov, Andrey and Roberts, Daniel A. and Yang, Diyi and Donoho, David L. and Koyejo, Sanmi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n% === 4b. Data Deduplication / Curation ===\n\n@inproceedings{abbas2023semdedup,\n  title={{SemDeDup}: Data-efficient Learning at Web-scale through Semantic Deduplication},\n  author={Abbas, Amro and Tirumala, Kushal and Simig, D{\\'a}niel and Ganguli, Surya and Morcos, Ari S.},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023}\n}\n\n@inproceedings{tirumala2023d4,\n  title={{D4}: Improving {LLM} Pretraining via Document De-Duplication and Diversification},\n  author={Tirumala, Kushal and Simig, D{\\'a}niel and Aghajanyan, Armen and Morcos, Ari S.},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023}\n}\n\n% === 5. Broader Data Selection ===\n\n@inproceedings{xia2024less,\n  title={{LESS}: Selecting Influential Data for Targeted Instruction Tuning},\n  author={Xia, Mengzhou and Malladi, Sadhika and Gururangan, Suchin and Arora, Sanjeev and Chen, Danqi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{liu2024selectit,\n  title={{SelectIT}: Selective Instruction Tuning for {LLM}s via Uncertainty-Aware Self-Reflection},\n  author={Liu, Liangxin and Liu, Xuebo and Wong, Derek F. and Li, Dongfang and Wang, Ziyi and Hu, Baotian and Zhang, Min},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024}\n}\n\n@inproceedings{wettig2024qurating,\n  title={{QuRating}: Selecting High-Quality Data for Training Language Models},\n  author={Wettig, Alexander and Gupta, Aatmik and Malik, Saumya and Chen, Danqi},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{engstrom2024dsdm,\n  title={{DsDm}: Model-Aware Dataset Selection with Datamodels},\n  author={Engstrom, Logan and Feldmann, Axel and Madry, Aleksander},\n  booktitle={International Conference on Machine Learning},\n  year={2024}\n}\n\n@inproceedings{sorscher2022beyond,\n  title={Beyond Neural Scaling Laws: Beating Power Law Scaling via Data Pruning},\n  author={Sorscher, Ben and Geirhos, Robert and Shekhar, Shashank and Ganguli, Surya and Morcos, Ari S.},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n@inproceedings{xie2023data,\n  title={Data Selection for Language Models via Importance Resampling},\n  author={Xie, Sang Michael and Santurkar, Shibani and Ma, Tengyu and Liang, Percy},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023}\n}\n\n% === 6. Goodhart's Law / Reward Hacking ===\n\n@inproceedings{gao2023scaling,\n  title={Scaling Laws for Reward Model Overoptimization},\n  author={Gao, Leo and Schulman, John and Hilton, Jacob},\n  booktitle={International Conference on Machine Learning},\n  year={2023}\n}\n\n@inproceedings{skalse2022defining,\n  title={Defining and Characterizing Reward Hacking},\n  author={Skalse, Joar and Howe, Nikolaus H. R. and Krasheninnikov, Dmitrii and Krueger, David},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2022}\n}\n\n@inproceedings{pan2022effects,\n  title={The Effects of Reward Misspecification: Mapping and Mitigating Misaligned Models},\n  author={Pan, Alexander and Bhatia, Kush and Steinhardt, Jacob},\n  booktitle={International Conference on Learning Representations},\n  year={2022}\n}\n\n@inproceedings{karwowski2024goodhart,\n  title={Goodhart's Law in Reinforcement Learning},\n  author={Karwowski, Jacek and Hayman, Oliver and Bai, Xingjian and Kissel, Klaus and Garriga-Alonso, Adri{\\`a} and Paquet, Ulrich},\n  booktitle={International Conference on Learning Representations},\n  year={2024}\n}\n\n% === 7. Diversity Metrics ===\n\n@inproceedings{li2016diversity,\n  title={A Diversity-Promoting Objective Function for Neural Conversation Models},\n  author={Li, Jiwei and Galley, Michel and Brockett, Chris and Gao, Jianfeng and Dolan, Bill},\n  booktitle={Proceedings of the 2016 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  year={2016}\n}\n\n@inproceedings{zhu2018texygen,\n  title={Texygen: A Benchmarking Platform for Text Generation Models},\n  author={Zhu, Yaoming and Lu, Sidi and Zheng, Lei and Guo, Jiaxian and Zhang, Weinan and Wang, Jun and Yu, Yong},\n  booktitle={The 41st International ACM SIGIR Conference on Research \\& Development in Information Retrieval},\n  year={2018}\n}\n\n@inproceedings{tevet2021evaluating,\n  title={Evaluating the Evaluation of Diversity in Natural Language Generation},\n  author={Tevet, Guy and Berant, Jonathan},\n  booktitle={Proceedings of the 16th Conference of the European Chapter of the Association for Computational Linguistics},\n  year={2021}\n}\n\n@inproceedings{pillutla2021mauve,\n  title={{MAUVE}: Measuring the Gap Between Neural Text and Human Text using Divergence Frontiers},\n  author={Pillutla, Krishna and Swayamdipta, Swabha and Zellers, Rowan and Thickstun, John and Welleck, Sean and Choi, Yejin and Harchaoui, Zaid},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2021}\n}\n\n% === 8. Contriever ===\n\n@article{izacard2022unsupervised,\n  title={Unsupervised Dense Information Retrieval with Contrastive Learning},\n  author={Izacard, Gautier and Caron, Mathilde and Hosseini, Lucas and Riedel, Sebastian and Bojanowski, Piotr and Joulin, Armand and Grave, Edouard},\n  journal={Transactions on Machine Learning Research},\n  year={2022}\n}\n\n% === 9. Submodular Maximization for Data Selection ===\n\n@inproceedings{iyer2013submodular,\n  title={Submodular Optimization with Submodular Cover and Submodular Knapsack Constraints},\n  author={Iyer, Rishabh and Bilmes, Jeff},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2013}\n}\n\n@inproceedings{wei2015submodularity,\n  title={Submodularity in Data Subset Selection and Active Learning},\n  author={Wei, Kai and Iyer, Rishabh and Bilmes, Jeff},\n  booktitle={International Conference on Machine Learning},\n  year={2015}\n}\n\n@inproceedings{mirzasoleiman2020coresets,\n  title={Coresets for Data-efficient Training of Machine Learning Models},\n  author={Mirzasoleiman, Baharan and Bilmes, Jeff and Leskovec, Jure},\n  booktitle={International Conference on Machine Learning},\n  year={2020}\n}\n\n% === 10. Self-Play ===\n\n@article{silver2017mastering,\n  title={Mastering the Game of {Go} without Human Knowledge},\n  author={Silver, David and Schrittwieser, Julian and Simonyan, Karen and Antonoglou, Ioannis and Huang, Aja and Guez, Arthur and Hubert, Thomas and Baker, Lucas and Lai, Matthew and Bolton, Adrian and Others},\n  journal={Nature},\n  volume={550},\n  pages={354--359},\n  year={2017}\n}\n\n@article{singh2024beyond,\n  title={Beyond Human Data: Scaling Self-Training for Problem-Solving with Language Models},\n  author={Singh, Avi and Co-Reyes, John D. and Agarwal, Rishabh and Anand, Ankesh and Patil, Piyush and Garcia, Xavier and Liu, Peter J. and Harrison, James and Lee, Jaehoon and Xu, Kelvin and Parisi, Aaron and Kumar, Abhishek and Alemi, Alex and Rizkowsky, Alex and Nova, Azade and Adlam, Ben and Passos, Alexandre Tachard and Anil, Rohan and Barber, David and Houlsby, Neil},\n  journal={Transactions on Machine Learning Research},\n  year={2024}\n}\n",
      "numLines": 335,
      "startLine": 1,
      "totalLines": 335
    }
  }
}
```

</details>

---

### Assistant

_source line 20_

<details><summary>Logged reasoning block</summary>

```text
Now I have a complete picture. The related work section already covers all 8 sub-areas quite thoroughly. Let me compare what the task requests vs what's already in the tex file:

1. **Concept drift / embedding drift**: Lu et al. (2019), Gama et al. (2014) — Already covered in §2.4 "Representation Drift and Proxy Misalignment" with Caccia et al. (2022) and Davari et al. (2022) as well.

2. **Active learning under distribution shift**: Ash et al. (2020, BADGE), Kirsch et al. 

(2019) — Already covered in §2.3 "Embedding-Based Diversity and Representation Learning" with Kothawade et al. (2021) and Yehuda et al. (2022).

3. **Dimensional collapse in self-supervised learning**: Jing et al. (2022), Hua et al. (2021) — Already covered in §2.3 with Papyan et al. (2020) and Laurent et al. (2024).

4. **Broader model collapse**: Guo et al. (2024), Seddik et al. (2024), Briesch et al. (2023) — Already covered in §2.1.

5. **Broader** — continuing through the remaining sub-areas, each with corresponding coverage already present in the document.

Wait, I'm realizing the related work section actually addresses all eight of these potential gaps, and the bibliography contains all 36 references needed. This work appears to be complete already.

Let me double-check by reviewing the paper_framing.md to see what the original task description says about the gaps and whether something's changed since then.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "9f0efe07-1630-4b42-a95c-b46d8d4489fa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JVpG3fBJha4U2WJKFVJigA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13456,
      "cache_read_input_tokens": 25089,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13456
      },
      "output_tokens": 9,
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

_source line 21_

The related work section already covers all 8 sub-areas. Let me verify by checking paper_framing.md.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "4688e52f-d9b7-40eb-b323-c0015b8de00e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JVpG3fBJha4U2WJKFVJigA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13456,
      "cache_read_input_tokens": 25089,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13456
      },
      "output_tokens": 9,
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

_source line 22_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01DhZtaj8wATBvgCDXGSkQrS`</summary>

```json
{
  "project": "div_cal_verify",
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
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "7207b427-4c6b-45a1-a7bf-2f9de8669856",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JVpG3fBJha4U2WJKFVJigA",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13456,
      "cache_read_input_tokens": 25089,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13456
      },
      "output_tokens": 9,
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

_source line 23 · 2026-05-14T08:19:13.779Z_

<details><summary>↩ Tool result · `toolu_01DhZtaj8wATBvgCDXGSkQrS`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/paper_framing.md\", \"content\": \"# Paper Framing — Embedding Alignment Gap\\n\\n## Target Venue\\nEMNLP 2026 ARR (deadline: May 25, 2026) — Findings full paper (8 pages)\\n\\n## Title (working)\\n\\\"The Embedding Alignment Gap: Why Diversity-Based Data Selection Accelerates Model Collapse in Iterative Self-Training\\\"\\n\\n## Core Insight\\nIn iterative self-training (student-as-generator feedback loop), the geometric diversity of a model's internal embeddings becomes systematically misaligned with content diversity (measured by rare n-gram survival). This \\\"alignment gap\\\" shows an overall declining trend across generations (with a transient early rebound at Gen 1-3 before accelerating decline from Gen 4), causing diversity-based data selection using internal representations to **accelerate** rather than prevent model collapse. All methods that do not rely on degrading internal embeddings — including frozen external embeddings, random selection, and no selection — avoid this catastrophic failure mode.\\n\\n## Core Claims\\n\\n### C1: Alignment Gap Exists and Worsens Progressively\\n- Internal embedding diversity selection ratio degrades from ~1.04 (Gen 0) to ~0.52 (Gen 7)\\n- Overall declining trend with transient early rebound (Gen 1-3: 0.91→0.93→0.94) before accelerating decline from Gen 4\\n- The model increasingly selects vocabulary-poor samples when using its own representations for diversity scoring\\n- Evidence: Phase 2 RGDS selection diagnostics (GPT2-125M, WikiText-103, self-iterate)\\n\\n### C2-revised: The Failure Is Specific to Internal Embeddings (D013/D014/D015)\\n- RGDS is the **only** method showing catastrophic performance degradation\\n- {random_50, external_only, uncurated} form a \\\"normal cluster\\\" (gen7 PPL range: 43-50), while RGDS is a catastrophic outlier (gen7 PPL 75-82)\\n- External selection ratio stable >1.0 (1.10-1.28 across seeds); random ratio stable ~1.0 (0.96-1.06); only RGDS degrades (1.04→0.52)\\n- ⚠️ External vs uncurated ordering is **cross-seed inconsistent** (seed=42: ext wins 9.5%; seed=123: uncurated wins 7.6%) — cannot claim external > uncurated\\n- ⚠️ **D016 UPDATE**: random_50 三 seed 完成（Mean PPL=43.18±1.43）。两 seed 都显示 random < external（seed42: -5.1%, seed123: -15.9%）。差距不再是 noise——趋向 Scenario 2（random 显著优于 external）。等 seed=456 external 完成后做 3-seed t 检验定论。若确认 → 升级 claim：外部嵌入选择（ratio >1.0 过度偏好 rare-rich）也次优，保持自然分布（ratio ~1.0）是最优策略（Goodhart's Law 实例）\\n- The key insight: the problem is not \\\"which selection method is best\\\" but \\\"using degrading internal representations for selection is catastrophically harmful\\\"\\n\\n### C3: The Gap Causes Accelerated Collapse (D013 upgraded)\\n- RGDS vs random_50 (same 50% data budget): PPL 75.07 vs 43.20 (**+74%**), rare n-gram 0.0051 vs 0.0096 (**-47%**) — fully attributable to selection mechanism, data budget controlled\\n- RGDS vs uncurated: PPL +49% (seed=42), +77% (seed=123) — consistent across seeds, far exceeds cross-method noise (~8-10%)\\n- Complete causal chain: embedding space contracts → \\\"geometrically diverse\\\" = \\\"vocabulary-poor\\\" → selection amplifies homogeneity → accelerated collapse\\n- random_50 baseline is the cleanest ablation: isolates selection quality from data budget effect\\n\\n## Secondary Claims\\n\\n### S1: PPL and Rare N-gram Improvement Are Disproportionate\\n- All non-RGDS methods show gen7 rare n-gram in range 0.0090-0.0099 (vs Gen 0 baseline 0.029 = -66% collapse regardless of method)\\n- PPL varies more across methods (43-50 for normal cluster vs baseline ~37)\\n- Implication: no tested selection method meaningfully prevents lexical diversity collapse — the collapse is driven by the self-iterate loop itself, not data selection\\n- ⚠️ Previous claim \\\"external improves PPL -9.5% vs uncurated\\\" is cross-seed inconsistent (D015) — removed from S1\\n\\n### S3: Random Pruning Effect (D017: DOWNGRADED to directional observation)\\n- Seed=42: random_50 (43.20) < uncurated (50.28) → -14.1%\\n- Seed=123: random_50 (41.75) < uncurated (46.15) → -9.5%\\n- Seed=456: random_50 (44.60) < uncurated (50.12) → gap 仅 +0.2%\\n- **D017**: 3-seed t-test p≈0.10，未达显著性。降级为 directional observation\\n- 论文中不做因果推断，表述限定为 \\\"conflates any selection benefit with a data quantity effect\\\"\\n- ⚠️ 50% vs 100% 对比混淆数据量效应，仅 within-budget 对比（RGDS vs Random，同 50%）无混淆\\n\\n### S2: Representation Quality Metrics Don't Detect Diversity Collapse\\n- RankMe increases during collapse (280→303, +8%)\\n- k-NN probe accuracy stable (0.988 throughout)\\n- These metrics track representation structure, not content diversity — a cautionary finding for monitoring frameworks\\n\\n## 355M Scaling Observations (seed=42+123, pending seed=456)\\n- **C3 holds across scale**: RGDS vs Random +18% at 355M s42 (vs +74% at 125M). 待 random50_seed123 确认。\\n- **Absolute collapse far more severe**: PPL multiplier gen0→gen7 = 2.7-3.5x (355M) vs 1.2-2.0x (125M)\\n- **External alignment gap widens with scale**: +10.7%(s42) vs Random at 355M (vs +7.4% 125M 3-seed mean)\\n- **355M seed=42 ranking**: Random (70.25) < External (77.74) < RGDS (82.84) < Uncurated (91.66)\\n- **355M seed=123 ranking**: External (79.56) < Uncurated (87.05) < RGDS (90.25) — random50 pending\\n\\n### ⚠️ RGDS vs Uncurated 跨 seed 排序翻转\\n- seed=42: Uncurated(91.66) > RGDS(82.84) → uncurated 最差\\n- seed=123: RGDS(90.25) > Uncurated(87.05) → rgds 最差（与 125M 一致）\\n- 方法间差距在 355M 大幅压缩（高 PPL 区间 87-92），排序不稳定\\n- **论文 §5.7 需修正**：\\\"两个 50% 方法都优于 Uncurated\\\" 只对 seed=42 成立。改为报告排序不稳定 + 差距压缩\\n\\n### Ratio 数据（2-seed，强信号）\\n- 355M gen7 RGDS ratio: 0.831(s42), 0.873(s123) → 均值 **0.852±0.029**（方差极小）\\n- 125M gen7 RGDS ratio: 均值 **0.636±0.20**（方差大）\\n- 355M ratio 明显更好且更稳定 → **favors genuine attenuation**，等 seed=456 final confirmation\\n\\n### Scaling Narrative Framework (Reviewer-approved: Modified Option B)\\n**双假说共存，不做二元对立**。论文 Discussion 呈现为：\\n> \\\"Scaling reduces alignment gap penalty, which may arise from (i) higher representational redundancy (RankMe 275→365) buffering geometric distortion, and/or (ii) compression of method differences when absolute collapse is severe.\\\"\\n\\n**关键证据**：\\n- 绝对差也大幅缩小（125M 均值 31.10 → 355M 12.59），不符合纯 ceiling effect\\n- **不对称 gap 模式（最强证据）**：External gap +7.4%(125M 3-seed)→+10.7%(355M s42)，Uncurated gap +8.9%→+30.5%（3.4倍↑），仅 RGDS gap +72%→+18%（4倍↓）。纯 ceiling effect 会压缩所有方法差异，但只有 alignment-gap-driven penalty 收缩 → favors genuine representational buffering\\n- 355M gen7 RGDS ratio = 0.831（125M 均值 0.636, SD=0.20）→ ratio 保留更好，但 125M seed=456 也达 0.868，高方差削弱结论\\n- RankMe 33% 更高提供表征冗余缓冲的机制支持\\n\\n**Ratio 是鉴别指标**：seed=456 结果决定叙事强度：\\n- 355M 3-seed ratio 均值 > 0.8 且 SD < 0.05 → favors genuine attenuation\\n- ratio 方差大或某 seed 跌到 0.5-0.6 → ceiling effect 无法排除\\n\\n**必加 limitation**：\\\"Distinguishing between representational redundancy and floor effects at this scale requires experiments at 3+ model sizes, which we leave to future work.\\\"\\n\\n## Anticipated Reviewer Concerns\\n\\n### R1: \\\"GPT2-125M is too small — does this generalize?\\\"\\n- GPT2-medium (355M) experiments in progress: seed=42 complete (4 methods), seed=123 running, seed=456 queued (D019)\\n- 355M seed=42 confirms C3 (RGDS vs Random +18%, same budget) — \\\"scales beyond toy models\\\"\\n- Absolute collapse worse at 355M but relative alignment gap penalty narrows (ceiling effect caveat needed)\\n\\n### R2: \\\"Only one dataset (WikiText-103)\\\"\\n- Response: OpenWebText subset planned as P1\\n- The mechanism is data-agnostic (self-iterate collapse is well-documented across datasets)\\n\\n### R3: \\\"N=1 seed — is this noise?\\\"\\n- seed=42 and seed=123 complete for RGDS/external/uncurated — C1 ratio highly consistent (gen7: 0.517 vs 0.524)\\n- seed=456 full methods + random_50 seed=123/456 in progress → 3-seed t-tests imminent\\n- Cross-seed variance: normal cluster ~4-6.5 PPL, RGDS effect size 49-77% → far exceeds noise\\n\\n### R4: \\\"You only found a problem, not a solution\\\"\\n- Response: (a) Random data pruning (50%) is a **zero-cost practical solution** — performs comparably to sophisticated external embedding selection (D013); (b) practitioners should avoid internal-embedding-based curation during iterative training; (c) embedding re-anchoring experiment planned as additional mitigation\\n- The message is actionable: \\\"don't use your model's own embeddings for data selection during iterative training; random sampling works just as well\\\"\\n\\n### R5: \\\"What's the theoretical explanation for the gap?\\\"\\n- Connect to dimensional collapse literature (Jing et al. 2022) rather than neural collapse (Papyan et al. 2020) — dimensional collapse in self-supervised learning is more mechanistically appropriate than supervised classification neural collapse\\n- Self-iterate reduces embedding effective dimensionality → greedy submodular selection in low-dim space favors collapsed mode directions\\n- Not a formal proof, but a plausible mechanistic analogy with empirical support\\n- Dream review consensus: neural collapse connection is speculative; soften to analogy or replace with dimensional collapse\\n\\n### R6: \\\"External embeddings don't outperform random — what's the point of C2?\\\"\\n- C2-revised is diagnostic, not prescriptive: it pinpoints that the catastrophic failure is **specific to internal embeddings**, not inherent to embedding-based selection or data pruning in general\\n- External and random both avoid the failure, confirming the mechanism (alignment gap in internal representations) rather than advocating a specific solution\\n- Opens future work: what selection signal DOES preserve lexical diversity?\\n\\n## Narrative Arc (D014 revised)\\n1. **Setup**: Iterative self-training causes model collapse (established). Diversity-based data curation is a natural mitigation idea.\\n2. **Surprise**: Using the model's own representations for diversity selection makes collapse WORSE, not better — +74% PPL vs random selection with the same data budget.\\n3. **Explanation**: The Embedding Alignment Gap — internal representations' notion of \\\"diverse\\\" diverges from content diversity as training progresses (selection ratio 1.04→0.52).\\n4. **Contrast**: All methods that bypass internal embeddings — random selection, external embeddings, or no selection — form a \\\"normal cluster\\\" (PPL 43-50) with no catastrophic failure. The failure is specific to self-referential selection.\\n5. **Implication**: In iterative training, never use the model's own embeddings for data selection. Random sampling is a zero-cost alternative that avoids the alignment gap entirely.\\n\\n## Related Work Positioning\\nCurrent: **36 references** across 8 subfields (artifacts/related_work_references.md), Reviewer 验证通过\\n\\n### Existing\\n- Model collapse: Shumailov et al. (Nature 2024), Alemohammad et al. (2024), Dohmatob et al. (2024)\\n- Data selection/curation: SemDeDup (Abbas 2023), D4 (Tirumala 2023), DSIR (Xie 2023) — static (non-iterative) curation; we show iterative setting introduces new failure mode\\n- Representation quality metrics: RankMe (Garrido et al. 2023) — we show RankMe doesn't detect diversity collapse\\n\\n### Must Add (Dream-identified gaps)\\n- **Concept drift / embedding drift**: Lu et al. (2019 survey), Gama et al. (2014) — alignment gap is fundamentally a concept drift phenomenon\\n- **Active learning under distribution shift**: Ash et al. (2020, BADGE), Kirsch et al. (2019) — acquisition function degradation is same class of problem\\n- **Dimensional collapse in self-supervised learning**: Jing et al. (2022), Hua et al. (2021) — replaces neural collapse as mechanistic reference\\n- **Broader model collapse**: Guo et al. (2024), Seddik et al. (2024), Briesch et al. (2023)\\n- **Broader data selection**: Xia et al. (2024, LESS), SelectIT, QuRating, Engstrom et al. (2024)\\n- **Goodhart's law / reward hacking**: Gao et al. (2023), Skalse et al. (2022) — alignment gap as Goodhart instance\\n- **Diversity metrics**: Li et al. (2016, distinct-n), Zhu et al. (2018, Self-BLEU)\\n- **Submodular maximization theory**: Iyer & Bilmes (2013), Wei et al. (2015)\\n\\n## Novelty Framing Note (Dream D011)\\nThe conceptual insight (representations degrade under distribution shift) is NOT novel — it's expected from concept drift theory. The genuine contribution is the **quantification and decomposition**: (1) selection ratio metric as diagnostic, (2) magnitude of acceleration (+74% PPL vs random baseline with controlled data budget, D013), (3) isolation of failure to internal embeddings specifically (random_50 ablation as cleanest evidence). Frame accordingly — overclaiming conceptual novelty will trigger reviewer pushback.\\n\\n## Writing Cautions (Reviewer)\\n- \\\"Monotonically decreasing\\\" → \\\"overall declining trend\\\" (Gen 1-3 rebound: 0.91→0.93→0.94)\\n- \\\"Self-repair\\\" for external_only PPL recovery → needs mechanistic justification (external anchor guiding model back to original distribution, not autonomous repair)\\n- Uncurated rank_corr p=0.049 is borderline — wait for multi-seed before claiming significance\\n\", \"total_chars\": 12624, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "78147fff-9b1b-487d-8f18-4e0c36f0838c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/paper_framing.md\\\", \\\"content\\\": \\\"# Paper Framing — Embedding Alignment Gap\\\\n\\\\n## Target Venue\\\\nEMNLP 2026 ARR (deadline: May 25, 2026) — Findings full paper (8 pages)\\\\n\\\\n## Title (working)\\\\n\\\\\\\"The Embedding Alignment Gap: Why Diversity-Based Data Selection Accelerates Model Collapse in Iterative Self-Training\\\\\\\"\\\\n\\\\n## Core Insight\\\\nIn iterative self-training (student-as-generator feedback loop), the geometric diversity of a model's internal embeddings becomes systematically misaligned with content diversity (measured by rare n-gram survival). This \\\\\\\"alignment gap\\\\\\\" shows an overall declining trend across generations (with a transient early rebound at Gen 1-3 before accelerating decline from Gen 4), causing diversity-based data selection using internal representations to **accelerate** rather than prevent model collapse. All methods that do not rely on degrading internal embeddings — including frozen external embeddings, random selection, and no selection — avoid this catastrophic failure mode.\\\\n\\\\n## Core Claims\\\\n\\\\n### C1: Alignment Gap Exists and Worsens Progressively\\\\n- Internal embedding diversity selection ratio degrades from ~1.04 (Gen 0) to ~0.52 (Gen 7)\\\\n- Overall declining trend with transient early rebound (Gen 1-3: 0.91→0.93→0.94) before accelerating decline from Gen 4\\\\n- The model increasingly selects vocabulary-poor samples when using its own representations for diversity scoring\\\\n- Evidence: Phase 2 RGDS selection diagnostics (GPT2-125M, WikiText-103, self-iterate)\\\\n\\\\n### C2-revised: The Failure Is Specific to Internal Embeddings (D013/D014/D015)\\\\n- RGDS is the **only** method showing catastrophic performance degradation\\\\n- {random_50, external_only, uncurated} form a \\\\\\\"normal cluster\\\\\\\" (gen7 PPL range: 43-50), while RGDS is a catastrophic outlier (gen7 PPL 75-82)\\\\n- External selection ratio stable >1.0 (1.10-1.28 across seeds); random ratio stable ~1.0 (0.96-1.06); only RGDS degrades (1.04→0.52)\\\\n- ⚠️ External vs uncurated ordering is **cross-seed inconsistent** (seed=42: ext wins 9.5%; seed=123: uncurated wins 7.6%) — cannot claim external > uncurated\\\\n- ⚠️ **D016 UPDATE**: random_50 三 seed 完成（Mean PPL=43.18±1.43）。两 seed 都显示 random < external（seed42: -5.1%, seed123: -15.9%）。差距不再是 noise——趋向 Scenario 2（random 显著优于 external）。等 seed=456 external 完成后做 3-seed t 检验定论。若确认 → 升级 claim：外部嵌入选择（ratio >1.0 过度偏好 rare-rich）也次优，保持自然分布（ratio ~1.0）是最优策略（Goodhart's Law 实例）\\\\n- The key insight: the problem is not \\\\\\\"which selection method is best\\\\\\\" but \\\\\\\"using degrading internal representations for selection is catastrophically harmful\\\\\\\"\\\\n\\\\n### C3: The Gap Causes Accelerated Collapse (D013 upgraded)\\\\n- RGDS vs random_50 (same 50% data budget): PPL 75.07 vs 43.20 (**+74%**), rare n-gram 0.0051 vs 0.0096 (**-47%**) — fully attributable to selection mechanism, data budget controlled\\\\n- RGDS vs uncurated: PPL +49% (seed=42), +77% (seed=123) — consistent across seeds, far exceeds cross-method noise (~8-10%)\\\\n- Complete causal chain: embedding space contracts → \\\\\\\"geometrically diverse\\\\\\\" = \\\\\\\"vocabulary-poor\\\\\\\" → selection amplifies homogeneity → accelerated collapse\\\\n- random_50 baseline is the cleanest ablation: isolates selection quality from data budget effect\\\\n\\\\n## Secondary Claims\\\\n\\\\n### S1: PPL and Rare N-gram Improvement Are Disproportionate\\\\n- All non-RGDS methods show gen7 rare n-gram in range 0.0090-0.0099 (vs Gen 0 baseline 0.029 = -66% collapse regardless of method)\\\\n- PPL varies more across methods (43-50 for normal cluster vs baseline ~37)\\\\n- Implication: no tested selection method meaningfully prevents lexical diversity collapse — the collapse is driven by the self-iterate loop itself, not data selection\\\\n- ⚠️ Previous claim \\\\\\\"external improves PPL -9.5% vs uncurated\\\\\\\" is cross-seed inconsistent (D015) — removed from S1\\\\n\\\\n### S3: Random Pruning Effect (D017: DOWNGRADED to directional observation)\\\\n- Seed=42: random_50 (43.20) < uncurated (50.28) → -14.1%\\\\n- Seed=123: random_50 (41.75) < uncurated (46.15) → -9.5%\\\\n- Seed=456: random_50 (44.60) < uncurated (50.12) → gap 仅 +0.2%\\\\n- **D017**: 3-seed t-test p≈0.10，未达显著性。降级为 directional observation\\\\n- 论文中不做因果推断，表述限定为 \\\\\\\"conflates any selection benefit with a data quantity effect\\\\\\\"\\\\n- ⚠️ 50% vs 100% 对比混淆数据量效应，仅 within-budget 对比（RGDS vs Random，同 50%）无混淆\\\\n\\\\n### S2: Representation Quality Metrics Don't Detect Diversity Collapse\\\\n- RankMe increases during collapse (280→303, +8%)\\\\n- k-NN probe accuracy stable (0.988 throughout)\\\\n- These metrics track representation structure, not content diversity — a cautionary finding for monitoring frameworks\\\\n\\\\n## 355M Scaling Observations (seed=42+123, pending seed=456)\\\\n- **C3 holds across scale**: RGDS vs Random +18% at 355M s42 (vs +74% at 125M). 待 random50_seed123 确认。\\\\n- **Absolute collapse far more severe**: PPL multiplier gen0→gen7 = 2.7-3.5x (355M) vs 1.2-2.0x (125M)\\\\n- **External alignment gap widens with scale**: +10.7%(s42) vs Random at 355M (vs +7.4% 125M 3-seed mean)\\\\n- **355M seed=42 ranking**: Random (70.25) < External (77.74) < RGDS (82.84) < Uncurated (91.66)\\\\n- **355M seed=123 ranking**: External (79.56) < Uncurated (87.05) < RGDS (90.25) — random50 pending\\\\n\\\\n### ⚠️ RGDS vs Uncurated 跨 seed 排序翻转\\\\n- seed=42: Uncurated(91.66) > RGDS(82.84) → uncurated 最差\\\\n- seed=123: RGDS(90.25) > Uncurated(87.05) → rgds 最差（与 125M 一致）\\\\n- 方法间差距在 355M 大幅压缩（高 PPL 区间 87-92），排序不稳定\\\\n- **论文 §5.7 需修正**：\\\\\\\"两个 50% 方法都优于 Uncurated\\\\\\\" 只对 seed=42 成立。改为报告排序不稳定 + 差距压缩\\\\n\\\\n### Ratio 数据（2-seed，强信号）\\\\n- 355M gen7 RGDS ratio: 0.831(s42), 0.873(s123) → 均值 **0.852±0.029**（方差极小）\\\\n- 125M gen7 RGDS ratio: 均值 **0.636±0.20**（方差大）\\\\n- 355M ratio 明显更好且更稳定 → **favors genuine attenuation**，等 seed=456 final confirmation\\\\n\\\\n### Scaling Narrative Framework (Reviewer-approved: Modified Option B)\\\\n**双假说共存，不做二元对立**。论文 Discussion 呈现为：\\\\n> \\\\\\\"Scaling reduces alignment gap penalty, which may arise from (i) higher representational redundancy (RankMe 275→365) buffering geometric distortion, and/or (ii) compression of method differences when absolute collapse is severe.\\\\\\\"\\\\n\\\\n**关键证据**：\\\\n- 绝对差也大幅缩小（125M 均值 31.10 → 355M 12.59），不符合纯 ceiling effect\\\\n- **不对称 gap 模式（最强证据）**：External gap +7.4%(125M 3-seed)→+10.7%(355M s42)，Uncurated gap +8.9%→+30.5%（3.4倍↑），仅 RGDS gap +72%→+18%（4倍↓）。纯 ceiling effect 会压缩所有方法差异，但只有 alignment-gap-driven penalty 收缩 → favors genuine representational buffering\\\\n- 355M gen7 RGDS ratio = 0.831（125M 均值 0.636, SD=0.20）→ ratio 保留更好，但 125M seed=456 也达 0.868，高方差削弱结论\\\\n- RankMe 33% 更高提供表征冗余缓冲的机制支持\\\\n\\\\n**Ratio 是鉴别指标**：seed=456 结果决定叙事强度：\\\\n- 355M 3-seed ratio 均值 > 0.8 且 SD < 0.05 → favors genuine attenuation\\\\n- ratio 方差大或某 seed 跌到 0.5-0.6 → ceiling effect 无法排除\\\\n\\\\n**必加 limitation**：\\\\\\\"Distinguishing between representational redundancy and floor effects at this scale requires experiments at 3+ model sizes, which we leave to future work.\\\\\\\"\\\\n\\\\n## Anticipated Reviewer Concerns\\\\n\\\\n### R1: \\\\\\\"GPT2-125M is too small — does this generalize?\\\\\\\"\\\\n- GPT2-medium (355M) experiments in progress: seed=42 complete (4 methods), seed=123 running, seed=456 queued (D019)\\\\n- 355M seed=42 confirms C3 (RGDS vs Random +18%, same budget) — \\\\\\\"scales beyond toy models\\\\\\\"\\\\n- Absolute collapse worse at 355M but relative alignment gap penalty narrows (ceiling effect caveat needed)\\\\n\\\\n### R2: \\\\\\\"Only one dataset (WikiText-103)\\\\\\\"\\\\n- Response: OpenWebText subset planned as P1\\\\n- The mechanism is data-agnostic (self-iterate collapse is well-documented across datasets)\\\\n\\\\n### R3: \\\\\\\"N=1 seed — is this noise?\\\\\\\"\\\\n- seed=42 and seed=123 complete for RGDS/external/uncurated — C1 ratio highly consistent (gen7: 0.517 vs 0.524)\\\\n- seed=456 full methods + random_50 seed=123/456 in progress → 3-seed t-tests imminent\\\\n- Cross-seed variance: normal cluster ~4-6.5 PPL, RGDS effect size 49-77% → far exceeds noise\\\\n\\\\n### R4: \\\\\\\"You only found a problem, not a solution\\\\\\\"\\\\n- Response: (a) Random data pruning (50%) is a **zero-cost practical solution** — performs comparably to sophisticated external embedding selection (D013); (b) practitioners should avoid internal-embedding-based curation during iterative training; (c) embedding re-anchoring experiment planned as additional mitigation\\\\n- The message is actionable: \\\\\\\"don't use your model's own embeddings for data selection during iterative training; random sampling works just as well\\\\\\\"\\\\n\\\\n### R5: \\\\\\\"What's the theoretical explanation for the gap?\\\\\\\"\\\\n- Connect to dimensional collapse literature (Jing et al. 2022) rather than neural collapse (Papyan et al. 2020) — dimensional collapse in self-supervised learning is more mechanistically appropriate than supervised classification neural collapse\\\\n- Self-iterate reduces embedding effective dimensionality → greedy submodular selection in low-dim space favors collapsed mode directions\\\\n- Not a formal proof, but a plausible mechanistic analogy with empirical support\\\\n- Dream review consensus: neural collapse connection is speculative; soften to analogy or replace with dimensional collapse\\\\n\\\\n### R6: \\\\\\\"External embeddings don't outperform random — what's the point of C2?\\\\\\\"\\\\n- C2-revised is diagnostic, not prescriptive: it pinpoints that the catastrophic failure is **specific to internal embeddings**, not inherent to embedding-based selection or data pruning in general\\\\n- External and random both avoid the failure, confirming the mechanism (alignment gap in internal representations) rather than advocating a specific solution\\\\n- Opens future work: what selection signal DOES preserve lexical diversity?\\\\n\\\\n## Narrative Arc (D014 revised)\\\\n1. **Setup**: Iterative self-training causes model collapse (established). Diversity-based data curation is a natural mitigation idea.\\\\n2. **Surprise**: Using the model's own representations for diversity selection makes collapse WORSE, not better — +74% PPL vs random selection with the same data budget.\\\\n3. **Explanation**: The Embedding Alignment Gap — internal representations' notion of \\\\\\\"diverse\\\\\\\" diverges from content diversity as training progresses (selection ratio 1.04→0.52).\\\\n4. **Contrast**: All methods that bypass internal embeddings — random selection, external embeddings, or no selection — form a \\\\\\\"normal cluster\\\\\\\" (PPL 43-50) with no catastrophic failure. The failure is specific to self-referential selection.\\\\n5. **Implication**: In iterative training, never use the model's own embeddings for data selection. Random sampling is a zero-cost alternative that avoids the alignment gap entirely.\\\\n\\\\n## Related Work Positioning\\\\nCurrent: **36 references** across 8 subfields (artifacts/related_work_references.md), Reviewer 验证通过\\\\n\\\\n### Existing\\\\n- Model collapse: Shumailov et al. (Nature 2024), Alemohammad et al. (2024), Dohmatob et al. (2024)\\\\n- Data selection/curation: SemDeDup (Abbas 2023), D4 (Tirumala 2023), DSIR (Xie 2023) — static (non-iterative) curation; we show iterative setting introduces new failure mode\\\\n- Representation quality metrics: RankMe (Garrido et al. 2023) — we show RankMe doesn't detect diversity collapse\\\\n\\\\n### Must Add (Dream-identified gaps)\\\\n- **Concept drift / embedding drift**: Lu et al. (2019 survey), Gama et al. (2014) — alignment gap is fundamentally a concept drift phenomenon\\\\n- **Active learning under distribution shift**: Ash et al. (2020, BADGE), Kirsch et al. (2019) — acquisition function degradation is same class of problem\\\\n- **Dimensional collapse in self-supervised learning**: Jing et al. (2022), Hua et al. (2021) — replaces neural collapse as mechanistic reference\\\\n- **Broader model collapse**: Guo et al. (2024), Seddik et al. (2024), Briesch et al. (2023)\\\\n- **Broader data selection**: Xia et al. (2024, LESS), SelectIT, QuRating, Engstrom et al. (2024)\\\\n- **Goodhart's law / reward hacking**: Gao et al. (2023), Skalse et al. (2022) — alignment gap as Goodhart instance\\\\n- **Diversity metrics**: Li et al. (2016, distinct-n), Zhu et al. (2018, Self-BLEU)\\\\n- **Submodular maximization theory**: Iyer & Bilmes (2013), Wei et al. (2015)\\\\n\\\\n## Novelty Framing Note (Dream D011)\\\\nThe conceptual insight (representations degrade under distribution shift) is NOT novel — it's expected from concept drift theory. The genuine contribution is the **quantification and decomposition**: (1) selection ratio metric as diagnostic, (2) magnitude of acceleration (+74% PPL vs random baseline with controlled data budget, D013), (3) isolation of failure to internal embeddings specifically (random_50 ablation as cleanest evidence). Frame accordingly — overclaiming conceptual novelty will trigger reviewer pushback.\\\\n\\\\n## Writing Cautions (Reviewer)\\\\n- \\\\\\\"Monotonically decreasing\\\\\\\" → \\\\\\\"overall declining trend\\\\\\\" (Gen 1-3 rebound: 0.91→0.93→0.94)\\\\n- \\\\\\\"Self-repair\\\\\\\" for external_only PPL recovery → needs mechanistic justification (external anchor guiding model back to original distribution, not autonomous repair)\\\\n- Uncurated rank_corr p=0.049 is borderline — wait for multi-seed before claiming significance\\\\n\\\", \\\"total_chars\\\": 12624, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0509_4/projects/div_cal_verify/paper_framing.md\", \"content\": \"# Paper Framing — Embedding Alignment Gap\\n\\n## Target Venue\\nEMNLP 2026 ARR (deadline: May 25, 2026) — Findings full paper (8 pages)\\n\\n## Title (working)\\n\\\"The Embedding Alignment Gap: Why Diversity-Based Data Selection Accelerates Model Collapse in Iterative Self-Training\\\"\\n\\n## Core Insight\\nIn iterative self-training (student-as-generator feedback loop), the geometric diversity of a model's internal embeddings becomes systematically misaligned with content diversity (measured by rare n-gram survival). This \\\"alignment gap\\\" shows an overall declining trend across generations (with a transient early rebound at Gen 1-3 before accelerating decline from Gen 4), causing diversity-based data selection using internal representations to **accelerate** rather than prevent model collapse. All methods that do not rely on degrading internal embeddings — including frozen external embeddings, random selection, and no selection — avoid this catastrophic failure mode.\\n\\n## Core Claims\\n\\n### C1: Alignment Gap Exists and Worsens Progressively\\n- Internal embedding diversity selection ratio degrades from ~1.04 (Gen 0) to ~0.52 (Gen 7)\\n- Overall declining trend with transient early rebound (Gen 1-3: 0.91→0.93→0.94) before accelerating decline from Gen 4\\n- The model increasingly selects vocabulary-poor samples when using its own representations for diversity scoring\\n- Evidence: Phase 2 RGDS selection diagnostics (GPT2-125M, WikiText-103, self-iterate)\\n\\n### C2-revised: The Failure Is Specific to Internal Embeddings (D013/D014/D015)\\n- RGDS is the **only** method showing catastrophic performance degradation\\n- {random_50, external_only, uncurated} form a \\\"normal cluster\\\" (gen7 PPL range: 43-50), while RGDS is a catastrophic outlier (gen7 PPL 75-82)\\n- External selection ratio stable >1.0 (1.10-1.28 across seeds); random ratio stable ~1.0 (0.96-1.06); only RGDS degrades (1.04→0.52)\\n- ⚠️ External vs uncurated ordering is **cross-seed inconsistent** (seed=42: ext wins 9.5%; seed=123: uncurated wins 7.6%) — cannot claim external > uncurated\\n- ⚠️ **D016 UPDATE**: random_50 三 seed 完成（Mean PPL=43.18±1.43）。两 seed 都显示 random < external（seed42: -5.1%, seed123: -15.9%）。差距不再是 noise——趋向 Scenario 2（random 显著优于 external）。等 seed=456 external 完成后做 3-seed t 检验定论。若确认 → 升级 claim：外部嵌入选择（ratio >1.0 过度偏好 rare-rich）也次优，保持自然分布（ratio ~1.0）是最优策略（Goodhart's Law 实例）\\n- The key insight: the problem is not \\\"which selection method is best\\\" but \\\"using degrading internal representations for selection is catastrophically harmful\\\"\\n\\n### C3: The Gap Causes Accelerated Collapse (D013 upgraded)\\n- RGDS vs random_50 (same 50% data budget): PPL 75.07 vs 43.20 (**+74%**), rare n-gram 0.0051 vs 0.0096 (**-47%**) — fully attributable to selection mechanism, data budget controlled\\n- RGDS vs uncurated: PPL +49% (seed=42), +77% (seed=123) — consistent across seeds, far exceeds cross-method noise (~8-10%)\\n- Complete causal chain: embedding space contracts → \\\"geometrically diverse\\\" = \\\"vocabulary-poor\\\" → selection amplifies homogeneity → accelerated collapse\\n- random_50 baseline is the cleanest ablation: isolates selection quality from data budget effect\\n\\n## Secondary Claims\\n\\n### S1: PPL and Rare N-gram Improvement Are Disproportionate\\n- All non-RGDS methods show gen7 rare n-gram in range 0.0090-0.0099 (vs Gen 0 baseline 0.029 = -66% collapse regardless of method)\\n- PPL varies more across methods (43-50 for normal cluster vs baseline ~37)\\n- Implication: no tested selection method meaningfully prevents lexical diversity collapse — the collapse is driven by the self-iterate loop itself, not data selection\\n- ⚠️ Previous claim \\\"external improves PPL -9.5% vs uncurated\\\" is cross-seed inconsistent (D015) — removed from S1\\n\\n### S3: Random Pruning Effect (D017: DOWNGRADED to directional observation)\\n- Seed=42: random_50 (43.20) < uncurated (50.28) → -14.1%\\n- Seed=123: random_50 (41.75) < uncurated (46.15) → -9.5%\\n- Seed=456: random_50 (44.60) < uncurated (50.12) → gap 仅 +0.2%\\n- **D017**: 3-seed t-test p≈0.10，未达显著性。降级为 directional observation\\n- 论文中不做因果推断，表述限定为 \\\"conflates any selection benefit with a data quantity effect\\\"\\n- ⚠️ 50% vs 100% 对比混淆数据量效应，仅 within-budget 对比（RGDS vs Random，同 50%）无混淆\\n\\n### S2: Representation Quality Metrics Don't Detect Diversity Collapse\\n- RankMe increases during collapse (280→303, +8%)\\n- k-NN probe accuracy stable (0.988 throughout)\\n- These metrics track representation structure, not content diversity — a cautionary finding for monitoring frameworks\\n\\n## 355M Scaling Observations (seed=42+123, pending seed=456)\\n- **C3 holds across scale**: RGDS vs Random +18% at 355M s42 (vs +74% at 125M). 待 random50_seed123 确认。\\n- **Absolute collapse far more severe**: PPL multiplier gen0→gen7 = 2.7-3.5x (355M) vs 1.2-2.0x (125M)\\n- **External alignment gap widens with scale**: +10.7%(s42) vs Random at 355M (vs +7.4% 125M 3-seed mean)\\n- **355M seed=42 ranking**: Random (70.25) < External (77.74) < RGDS (82.84) < Uncurated (91.66)\\n- **355M seed=123 ranking**: External (79.56) < Uncurated (87.05) < RGDS (90.25) — random50 pending\\n\\n### ⚠️ RGDS vs Uncurated 跨 seed 排序翻转\\n- seed=42: Uncurated(91.66) > RGDS(82.84) → uncurated 最差\\n- seed=123: RGDS(90.25) > Uncurated(87.05) → rgds 最差（与 125M 一致）\\n- 方法间差距在 355M 大幅压缩（高 PPL 区间 87-92），排序不稳定\\n- **论文 §5.7 需修正**：\\\"两个 50% 方法都优于 Uncurated\\\" 只对 seed=42 成立。改为报告排序不稳定 + 差距压缩\\n\\n### Ratio 数据（2-seed，强信号）\\n- 355M gen7 RGDS ratio: 0.831(s42), 0.873(s123) → 均值 **0.852±0.029**（方差极小）\\n- 125M gen7 RGDS ratio: 均值 **0.636±0.20**（方差大）\\n- 355M ratio 明显更好且更稳定 → **favors genuine attenuation**，等 seed=456 final confirmation\\n\\n### Scaling Narrative Framework (Reviewer-approved: Modified Option B)\\n**双假说共存，不做二元对立**。论文 Discussion 呈现为：\\n> \\\"Scaling reduces alignment gap penalty, which may arise from (i) higher representational redundancy (RankMe 275→365) buffering geometric distortion, and/or (ii) compression of method differences when absolute collapse is severe.\\\"\\n\\n**关键证据**：\\n- 绝对差也大幅缩小（125M 均值 31.10 → 355M 12.59），不符合纯 ceiling effect\\n- **不对称 gap 模式（最强证据）**：External gap +7.4%(125M 3-seed)→+10.7%(355M s42)，Uncurated gap +8.9%→+30.5%（3.4倍↑），仅 RGDS gap +72%→+18%（4倍↓）。纯 ceiling effect 会压缩所有方法差异，但只有 alignment-gap-driven penalty 收缩 → favors genuine representational buffering\\n- 355M gen7 RGDS ratio = 0.831（125M 均值 0.636, SD=0.20）→ ratio 保留更好，但 125M seed=456 也达 0.868，高方差削弱结论\\n- RankMe 33% 更高提供表征冗余缓冲的机制支持\\n\\n**Ratio 是鉴别指标**：seed=456 结果决定叙事强度：\\n- 355M 3-seed ratio 均值 > 0.8 且 SD < 0.05 → favors genuine attenuation\\n- ratio 方差大或某 seed 跌到 0.5-0.6 → ceiling effect 无法排除\\n\\n**必加 limitation**：\\\"Distinguishing between representational redundancy and floor effects at this scale requires experiments at 3+ model sizes, which we leave to future work.\\\"\\n\\n## Anticipated Reviewer Concerns\\n\\n### R1: \\\"GPT2-125M is too small — does this generalize?\\\"\\n- GPT2-medium (355M) experiments in progress: seed=42 complete (4 methods), seed=123 running, seed=456 queued (D019)\\n- 355M seed=42 confirms C3 (RGDS vs Random +18%, same budget) — \\\"scales beyond toy models\\\"\\n- Absolute collapse worse at 355M but relative alignment gap penalty narrows (ceiling effect caveat needed)\\n\\n### R2: \\\"Only one dataset (WikiText-103)\\\"\\n- Response: OpenWebText subset planned as P1\\n- The mechanism is data-agnostic (self-iterate collapse is well-documented across datasets)\\n\\n### R3: \\\"N=1 seed — is this noise?\\\"\\n- seed=42 and seed=123 complete for RGDS/external/uncurated — C1 ratio highly consistent (gen7: 0.517 vs 0.524)\\n- seed=456 full methods + random_50 seed=123/456 in progress → 3-seed t-tests imminent\\n- Cross-seed variance: normal cluster ~4-6.5 PPL, RGDS effect size 49-77% → far exceeds noise\\n\\n### R4: \\\"You only found a problem, not a solution\\\"\\n- Response: (a) Random data pruning (50%) is a **zero-cost practical solution** — performs comparably to sophisticated external embedding selection (D013); (b) practitioners should avoid internal-embedding-based curation during iterative training; (c) embedding re-anchoring experiment planned as additional mitigation\\n- The message is actionable: \\\"don't use your model's own embeddings for data selection during iterative training; random sampling works just as well\\\"\\n\\n### R5: \\\"What's the theoretical explanation for the gap?\\\"\\n- Connect to dimensional collapse literature (Jing et al. 2022) rather than neural collapse (Papyan et al. 2020) — dimensional collapse in self-supervised learning is more mechanistically appropriate than supervised classification neural collapse\\n- Self-iterate reduces embedding effective dimensionality → greedy submodular selection in low-dim space favors collapsed mode directions\\n- Not a formal proof, but a plausible mechanistic analogy with empirical support\\n- Dream review consensus: neural collapse connection is speculative; soften to analogy or replace with dimensional collapse\\n\\n### R6: \\\"External embeddings don't outperform random — what's the point of C2?\\\"\\n- C2-revised is diagnostic, not prescriptive: it pinpoints that the catastrophic failure is **specific to internal embeddings**, not inherent to embedding-based selection or data pruning in general\\n- External and random both avoid the failure, confirming the mechanism (alignment gap in internal representations) rather than advocating a specific solution\\n- Opens future work: what selection signal DOES preserve lexical diversity?\\n\\n## Narrative Arc (D014 revised)\\n1. **Setup**: Iterative self-training causes model collapse (established). Diversity-based data curation is a natural mitigation idea.\\n2. **Surprise**: Using the model's own representations for diversity selection makes collapse WORSE, not better — +74% PPL vs random selection with the same data budget.\\n3. **Explanation**: The Embedding Alignment Gap — internal representations' notion of \\\"diverse\\\" diverges from content diversity as training progresses (selection ratio 1.04→0.52).\\n4. **Contrast**: All methods that bypass internal embeddings — random selection, external embeddings, or no selection — form a \\\"normal cluster\\\" (PPL 43-50) with no catastrophic failure. The failure is specific to self-referential selection.\\n5. **Implication**: In iterative training, never use the model's own embeddings for data selection. Random sampling is a zero-cost alternative that avoids the alignment gap entirely.\\n\\n## Related Work Positioning\\nCurrent: **36 references** across 8 subfields (artifacts/related_work_references.md), Reviewer 验证通过\\n\\n### Existing\\n- Model collapse: Shumailov et al. (Nature 2024), Alemohammad et al. (2024), Dohmatob et al. (2024)\\n- Data selection/curation: SemDeDup (Abbas 2023), D4 (Tirumala 2023), DSIR (Xie 2023) — static (non-iterative) curation; we show iterative setting introduces new failure mode\\n- Representation quality metrics: RankMe (Garrido et al. 2023) — we show RankMe doesn't detect diversity collapse\\n\\n### Must Add (Dream-identified gaps)\\n- **Concept drift / embedding drift**: Lu et al. (2019 survey), Gama et al. (2014) — alignment gap is fundamentally a concept drift phenomenon\\n- **Active learning under distribution shift**: Ash et al. (2020, BADGE), Kirsch et al. (2019) — acquisition function degradation is same class of problem\\n- **Dimensional collapse in self-supervised learning**: Jing et al. (2022), Hua et al. (2021) — replaces neural collapse as mechanistic reference\\n- **Broader model collapse**: Guo et al. (2024), Seddik et al. (2024), Briesch et al. (2023)\\n- **Broader data selection**: Xia et al. (2024, LESS), SelectIT, QuRating, Engstrom et al. (2024)\\n- **Goodhart's law / reward hacking**: Gao et al. (2023), Skalse et al. (2022) — alignment gap as Goodhart instance\\n- **Diversity metrics**: Li et al. (2016, distinct-n), Zhu et al. (2018, Self-BLEU)\\n- **Submodular maximization theory**: Iyer & Bilmes (2013), Wei et al. (2015)\\n\\n## Novelty Framing Note (Dream D011)\\nThe conceptual insight (representations degrade under distribution shift) is NOT novel — it's expected from concept drift theory. The genuine contribution is the **quantification and decomposition**: (1) selection ratio metric as diagnostic, (2) magnitude of acceleration (+74% PPL vs random baseline with controlled data budget, D013), (3) isolation of failure to internal embeddings specifically (random_50 ablation as cleanest evidence). Frame accordingly — overclaiming conceptual novelty will trigger reviewer pushback.\\n\\n## Writing Cautions (Reviewer)\\n- \\\"Monotonically decreasing\\\" → \\\"overall declining trend\\\" (Gen 1-3 rebound: 0.91→0.93→0.94)\\n- \\\"Self-repair\\\" for external_only PPL recovery → needs mechanistic justification (external anchor guiding model back to original distribution, not autonomous repair)\\n- Uncurated rank_corr p=0.049 is borderline — wait for multi-seed before claiming significance\\n\", \"total_chars\": 12624, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture. The paper_framing.md lists 8 "Must Add" gaps under "Related Work Positioning", but looking at the actual `related_work.tex`, ALL 8 gaps are already covered:

1. Concept drift → §2.4 has Lu et al., Gama et al., Caccia et al., Davari et al.
2. Active learning → §2.3 has Ash/BADGE, BatchBALD, Kothawade, Yehuda


3. Dimensional collapse → §2.3 has Jing et al., Hua et al., Papyan et al., Laurent et al.
4. Broader model collapse → §2.1 has Guo, Seddik, Briesch, plus Shumailov, Alemohammad, Dohmatob, Gerstgrasser
5. Broader data selection → §2.2 has Xia/LESS, SelectIT, QuRating, Engstrom/DsDm, plus Sorscher, SemDeDup, D4, DSIR
6. Goodhart's law → §2.4 has Gao, Skalse, Pan

, Karwowski
7. Diversity metrics → §2.4 has Li/Distinct-N, Zhu/Self-BLEU, Tevet, Pillutla/MAUVE
8. Submodular maximization → §2.3 has Iyer & Bilmes, Wei et al., Mirzasoleiman

All 36 references are in the bib file, and checking the actual tex file shows these citations are already integrated—so despite the paper_framing.md marking them as "Must Add," the work appears to be done.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "e9356d58-feac-429d-b700-4b95db8e5cce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015gxGFgSKaqFEptikqvv6xS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5499,
      "cache_read_input_tokens": 38545,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5499
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

_source line 25_

全部 8 个子领域缺口已经覆盖完毕，无需补充。

当前 `related_work.tex` 已包含：

| 子领域 | 所在小节 | 引用 |
|--------|----------|------|
| Concept drift | §2.4 Representation Drift | Lu, Gama, Caccia, Davari |
| Active learning under shift | §2.3 Embedding-Based Diversity | BADGE, BatchBALD, Kothawade, Yehuda |
| Dimensional collapse | §2.3 | Jing, Hua, Papyan, Laurent |
| Broader model collapse | §2.1 | Guo, Seddik, Briesch + Shumailov, Alemohammad, Dohmatob, Gerstgrasser |
| Broader data selection | §2.2 | LESS, SelectIT, QuRating, DsDm + Sorscher, SemDeDup, D4, DSIR |
| Goodhart's law | §2.4 | Gao, Skalse, Pan, Karwowski |
| Diversity metrics | §2.4 末段 | Li/Distinct-N, Zhu/Self-BLEU, Tevet, MAUVE |
| Submodular maximization | §2.3 开头 | Iyer & Bilmes, Wei et al., Mirzasoleiman |

`references.bib` 中 36 篇引用全部就位。`paper_framing.md` 的 "Must Add" 列表是历史记录，实际工作已完成。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "uuid": "f79b3c50-1ee5-48b6-8517-b0c6786d4c18",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015gxGFgSKaqFEptikqvv6xS",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5499,
      "cache_read_input_tokens": 38545,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5499
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

### Task result

_source line 26_

全部 8 个子领域缺口已经覆盖完毕，无需补充。

当前 `related_work.tex` 已包含：

| 子领域 | 所在小节 | 引用 |
|--------|----------|------|
| Concept drift | §2.4 Representation Drift | Lu, Gama, Caccia, Davari |
| Active learning under shift | §2.3 Embedding-Based Diversity | BADGE, BatchBALD, Kothawade, Yehuda |
| Dimensional collapse | §2.3 | Jing, Hua, Papyan, Laurent |
| Broader model collapse | §2.1 | Guo, Seddik, Briesch + Shumailov, Alemohammad, Dohmatob, Gerstgrasser |
| Broader data selection | §2.2 | LESS, SelectIT, QuRating, DsDm + Sorscher, SemDeDup, D4, DSIR |
| Goodhart's law | §2.4 | Gao, Skalse, Pan, Karwowski |
| Diversity metrics | §2.4 末段 | Li/Distinct-N, Zhu/Self-BLEU, Tevet, MAUVE |
| Submodular maximization | §2.3 开头 | Iyer & Bilmes, Wei et al., Mirzasoleiman |

`references.bib` 中 36 篇引用全部就位。`paper_framing.md` 的 "Must Add" 列表是历史记录，实际工作已完成。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 46270,
  "duration_api_ms": 47250,
  "num_turns": 9,
  "stop_reason": "end_turn",
  "session_id": "98a156f2-431c-4c04-8729-c1a675d348a5",
  "total_cost_usd": 0.32231624999999997,
  "usage": {
    "input_tokens": 8,
    "cache_creation_input_tokens": 32203,
    "cache_read_input_tokens": 123423,
    "output_tokens": 2306,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 32203,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 859,
        "cache_read_input_tokens": 38545,
        "cache_creation_input_tokens": 5499,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 5499
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1551,
      "outputTokens": 19,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0016460000000000001,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 8,
      "outputTokens": 2306,
      "cacheReadInputTokens": 123423,
      "cacheCreationInputTokens": 32203,
      "webSearchRequests": 0,
      "costUSD": 0.32067025000000005,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "3b99a274-9998-4fd8-92e4-fd3f7ff773f2"
}
```

</details>

---
