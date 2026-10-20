# audit exp data utilization

**Depth Profiling: Classifying Recursive Generation Depth in Base-Model LLM Text** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 129
- **Recorded user turns:** 0
- **Tool calls:** 64
- **Original source:** `logs/chats/worker_audit_exp-data-utilization_20260520T050056.jsonl`
- **Structured JSON:** [`8802dc8fd764df7d1858.json`](../../sessions/88/8802dc8fd764df7d1858.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

129 recorded events

### Tool call

_source line 1 · 2026-05-20T05:07:55.156810+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_registry",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__read_registry",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-20T05:07:55.157101+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-20T05:07:55.157258+00:00_

called mcp__agent-ml-research__read_registry

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry</summary>

```json
{
  "project": "gen-depth-fingerprint",
  "filters": "{'conclusion': 'success'}",
  "limit": "0",
  "fields": "['*']"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "mcp__agent-ml-research__read_registry",
  "tool_args": {
    "project": "gen-depth-fingerprint",
    "filters": "{'conclusion': 'success'}",
    "limit": "0",
    "fields": "['*']"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-20T05:07:55.157667+00:00_

Error: result (61,189 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "mcp__agent-ml-research__read_registry",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-20T05:07:55.157831+00:00_

called Glob

<details open><summary>🔧 Tool call — Glob</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Glob",
  "tool_args": {
    "pattern": "**/*.tex",
    "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-20T05:07:55.157969+00:00_

artifacts/_project/paper/table2.tex
artifacts/_project/paper/table1.tex
artifacts/_project/paper/table4.tex
artifacts/_project/paper/appendix_qlora.tex
artifacts/_project/paper/appendix_lofo.tex
artifacts/_project/paper/appendix_length.tex
artifacts/_project/paper/appendix_qualitative_examples.tex
artifacts/_project/paper/ethics.tex
artifacts/_project/paper/appendix_prompt_type.tex
artifacts/_project/paper/appendix_human_edit.tex
artifacts/_project/paper/appendix_error_analysis.tex
artifacts/_project/paper/appendix_domain.tex
artifacts/_project/paper/appendix_downstream.tex
artifacts/_project/paper/appendix_generator_subsets.tex
artifacts/_project/paper/appendix_tost.tex
artifacts/_project/paper/appendix_confusion_matrix.tex
artifacts/_project/paper/appendix_classifier.tex
artifacts/_project/paper/appendix_feature_distributions.tex
artifacts/_project/paper/appendix_cross_temp.tex
artifacts/_project/paper/appendix_ddr_validation.tex
artifacts/_project/paper/appendix_dataset_stats.tex
artifacts/_project/paper/appendix_finer_depth.tex
artifacts/_project/paper/appendix_transfer.tex
artifacts/_project/paper/appendix_temperature_stability.tex
artifacts/_project/paper/appendix_seed_control.tex
artifacts/_project/paper/appendix_instruct.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/appendix_ablation.tex
artifacts/_project/paper/appendix_feature_correlation.tex
artifacts/_project/paper/appendix_convergence.tex
artifacts/_project/paper/related_work.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/main.tex
artifacts/_project/paper/limitations.tex
artifacts/_project/paper/results.tex
artifacts/_project/paper/appendix_cross_model_detail.tex
artifacts/_project/paper/method.tex

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Glob",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-20T05:07:55.158140+00:00_

called Agent

<details open><summary>🔧 Tool call — Agent</summary>

```json
{
  "description": "Read registry data completely",
  "subagent_type": "general-purpose",
  "prompt": "Read the file at /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt in sequential chunks until you've read 100% of it.\n\nExtract ALL experiments with conclusion=success. For each, output a structured list with:\n- exp_id\n- name/title\n- hypothesis (brief)\n- key metrics (numbers)\n- any tags or keywords that describe what the experiment tested\n\nOutput the complete list as a clean table or structured format. Do not skip any experiments. Count the total number of success experiments at the end."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Agent",
  "tool_args": {
    "description": "Read registry data completely",
    "subagent_type": "general-purpose",
    "prompt": "Read the file at /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt in sequential chunks until you've read 100% of it.\n\nExtract ALL experiments with conclusion=success. For each, output a structured list with:\n- exp_id\n- name/title\n- hypothesis (brief)\n- key metrics (numbers)\n- any tags or keywords that describe what the experiment tested\n\nOutput the complete list as a clean table or structured format. Do not skip any experiments. Count the total number of success experiments at the end."
  }
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-20T05:07:55.158294+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
  "limit": "2000"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
    "limit": "2000"
  }
}
```

</details>

---

### Tool result

_source line 9 · 2026-05-20T05:07:55.158415+00:00_

File content (27195 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-20T05:07:55.158535+00:00_

called Agent

<details open><summary>🔧 Tool call — Agent</summary>

```json
{
  "description": "Read all tex files content",
  "subagent_type": "general-purpose",
  "prompt": "Read ALL .tex files in /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ and extract all experiment-related content: exp IDs, metric numbers (F1 scores, accuracy values, p-values), experiment description keywords (like \"cross-model\", \"temperature\", \"prompt type\", \"human edit\", \"domain\", \"LoRA\", \"QLoRA\", \"seed\", \"transfer\", \"convergence\", \"ablation\", etc.), table data, and figure references.\n\nHere is the full list of tex files to read:\n- table2.tex, table1.tex, table4.tex\n- appendix_qlora.tex, appendix_lofo.tex, appendix_length.tex, appendix_qualitative_examples.tex\n- ethics.tex, appendix_prompt_type.tex, appendix_human_edit.tex, appendix_error_analysis.tex\n- appendix_domain.tex, appendix_downstream.tex, appendix_generator_subsets.tex, appendix_tost.tex\n- appendix_confusion_matrix.tex, appendix_classifier.tex, appendix_feature_distributions.tex\n- appendix_cross_temp.tex, appendix_ddr_validation.tex, appendix_dataset_stats.tex\n- appendix_finer_depth.tex, appendix_transfer.tex, appendix_temperature_stability.tex\n- appendix_seed_control.tex, appendix_instruct.tex, discussion.tex, appendix_ablation.tex\n- appendix_feature_correlation.tex, appendix_convergence.tex, related_work.tex, abstract.tex\n- introduction.tex, conclusion.tex, main.tex, limitations.tex, results.tex\n- appendix_cross_model_detail.tex, method.tex\n\nFor each file, output:\n1. File name\n2. Any exp_id strings found (like \"eval-xxx\", \"plan-xxx\", etc.)\n3. Key metric numbers mentioned\n4. Experiment-descriptive keywords/phrases used\n5. What tables/figures are defined\n\nBe thorough - read every file completely. This is for cross-referencing which experiments are cited in the paper."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Agent",
  "tool_args": {
    "description": "Read all tex files content",
    "subagent_type": "general-purpose",
    "prompt": "Read ALL .tex files in /home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ and extract all experiment-related content: exp IDs, metric numbers (F1 scores, accuracy values, p-values), experiment description keywords (like \"cross-model\", \"temperature\", \"prompt type\", \"human edit\", \"domain\", \"LoRA\", \"QLoRA\", \"seed\", \"transfer\", \"convergence\", \"ablation\", etc.), table data, and figure references.\n\nHere is the full list of tex files to read:\n- table2.tex, table1.tex, table4.tex\n- appendix_qlora.tex, appendix_lofo.tex, appendix_length.tex, appendix_qualitative_examples.tex\n- ethics.tex, appendix_prompt_type.tex, appendix_human_edit.tex, appendix_error_analysis.tex\n- appendix_domain.tex, appendix_downstream.tex, appendix_generator_subsets.tex, appendix_tost.tex\n- appendix_confusion_matrix.tex, appendix_classifier.tex, appendix_feature_distributions.tex\n- appendix_cross_temp.tex, appendix_ddr_validation.tex, appendix_dataset_stats.tex\n- appendix_finer_depth.tex, appendix_transfer.tex, appendix_temperature_stability.tex\n- appendix_seed_control.tex, appendix_instruct.tex, discussion.tex, appendix_ablation.tex\n- appendix_feature_correlation.tex, appendix_convergence.tex, related_work.tex, abstract.tex\n- introduction.tex, conclusion.tex, main.tex, limitations.tex, results.tex\n- appendix_cross_model_detail.tex, method.tex\n\nFor each file, output:\n1. File name\n2. Any exp_id strings found (like \"eval-xxx\", \"plan-xxx\", etc.)\n3. Key metric numbers mentioned\n4. Experiment-descriptive keywords/phrases used\n5. What tables/figures are defined\n\nBe thorough - read every file completely. This is for cross-referencing which experiments are cited in the paper."
  }
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-20T05:07:55.158723+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
  "offset": "0",
  "limit": "500"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
    "offset": "0",
    "limit": "500"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-20T05:07:55.158847+00:00_

File content (27195 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-20T05:07:55.158967+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table2.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table2.tex"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-20T05:07:55.159082+00:00_

1	\begin{table}[t]
2	\centering
3	\small
4	\begin{tabular}{lp{3.2cm}ccc}
5	\toprule
6	\textbf{Feature Set} & \textbf{Features} & \textbf{LOGO F1} & \textbf{95\% CI} & \textbf{McNemar $p$} \\
7	\midrule
8	Full (7 features) & all & 0.773 & --- & --- \\
9	Surface only (2)  & TTR, hapax\_ratio & 0.688 & --- & $<$ 0.001 \\
10	Reference only (5) & entropy\_mean/std/min/max, tail\_decay & 0.713 & --- & $<$ 0.001 \\
11	\bottomrule
12	\end{tabular}
13	\caption{Feature group ablation and complementarity (8-gen 10-fold CV).
14	Both subsets significantly underperform the full set (+8.5\,pp, +5.9\,pp).
15	Permutation importance: \texttt{hapax\_ratio} (0.269) $>$ \texttt{entropy\_mean} (0.164) $>$ \texttt{ttr} (0.159).}
16	\label{tab:feature-ablation}
17	\end{table}
18	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-20T05:07:55.159215+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table1.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table1.tex"
  }
}
```

</details>

---

### Tool result

_source line 16 · 2026-05-20T05:07:55.159332+00:00_

1	%% NOTE: this standalone file is NOT \input'd by main.tex; the inline table in results.tex is authoritative.
2	\begin{table}[t]
3	\centering
4	\small
5	\begin{tabular}{llccc}
6	\toprule
7	\textbf{Held-out Generator} & \textbf{Family} & \textbf{Params} & \textbf{Macro-F1} & \textbf{95\% CI} \\
8	\midrule
9	Pythia-2.8B   & Pythia  & 2.8B & ---   & --- \\
10	Pythia-1B     & Pythia  & 1.0B & 0.806 & --- \\
11	Qwen3-1.7B   & Qwen    & 1.7B & ---   & --- \\
12	Llama-3.2-3B & Llama   & 3.2B & ---   & --- \\
13	OLMo-2-1B    & OLMo    & 1.0B & ---   & --- \\
14	Qwen3-8B     & Qwen    & 8.0B & ---   & --- \\
15	Qwen3-0.6B   & Qwen    & 0.6B & ---   & --- \\
16	Mistral-7B   & Mistral & 7.0B & 0.681 & --- \\
17	\midrule
18	\textbf{Average (8-gen)} & & & \textbf{0.762} & [0.758, 0.766] \\
19	\bottomrule
20	\end{tabular}
21	\caption{Leave-one-generator-out (LOGO) depth classification results (3-class).
22	Each row holds out one generator for testing and trains on the remaining seven.}
23	\label{tab:logo-results}
24	\end{table}
25	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 17 · 2026-05-20T05:07:55.159456+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table4.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/table4.tex"
  }
}
```

</details>

---

### Tool result

_source line 18 · 2026-05-20T05:07:55.159588+00:00_

1	\begin{table}[t]
2	\centering
3	\footnotesize
4	\resizebox{\linewidth}{!}{%
5	\begin{tabular}{llccc}
6	\toprule
7	\textbf{Reference} & \textbf{Family} & \textbf{Params} & \textbf{LOGO F1} & \textbf{Ent.\ Drift} \\
8	\midrule
9	Pythia-410M & Pythia & 410M & 0.803 & [$-$1.19, $-$1.40] \\
10	OLMo-2-1B  & OLMo   & 1.5B & 0.807 & [$-$0.61, $-$0.91] \\
11	Qwen3-0.6B & Qwen   & 0.6B & 0.816 & [$-$0.96, $-$1.35] \\
12	\bottomrule
13	\end{tabular}}
14	\caption{Cross-family reference model validation (5-gen LOGO subset). Drift direction is consistent (negative) across all three references; magnitude varies with capacity. Spread in LOGO F1 is 0.013.}
15	\label{tab:cross-ref}
16	\end{table}
17	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 19 · 2026-05-20T05:07:55.159718+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qlora.tex"
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-20T05:07:55.159842+00:00_

1	To assess whether depth signal extends beyond handcrafted features, we fine-tune a pretrained language model end-to-end as a depth classifier using QLoRA \cite{qlora}.
2	
3	\paragraph{Setup.}
4	We fine-tune Qwen3-0.6B-Base with LoRA rank 16, learning rate $2 \times 10^{-4}$, and 3 epochs, framing depth estimation as 5-class sequence classification (gen-0 through gen-4).\footnote{Evaluated on the original 6-generator subset; XGBoost 3-class F1\,=\,0.789. We expect 8-generator training to further improve given additional diversity; the comparison direction is preserved.}
5	For 3-class evaluation, we collapse predictions into gen-0\,/\,gen-1\,/\,gen-2+ post hoc.
6	All results use the same LOGO protocol as the main experiments.
7	
8	\begin{table}[h]
9	\centering
10	\small
11	\caption{QLoRA end-to-end depth classification vs.\ XGBoost on handcrafted features, under LOGO evaluation.}
12	\label{tab:qlora}
13	\resizebox{\linewidth}{!}{%
14	\begin{tabular}{lccc}
15	\toprule
16	\textbf{Method} & \textbf{5-class F1} & \textbf{3-class F1} & \textbf{Per-class F1 (5-class)} \\
17	\midrule
18	XGBoost (7 features) & 0.501 $\pm$ 0.038 & 0.789 & --- \\
19	QLoRA (Qwen3-0.6B)   & 0.583 $\pm$ 0.010 & 0.905 $\pm$ 0.003 & 0.999\,/\,0.796\,/\,0.413\,/\,0.259\,/\,0.447 \\
20	\bottomrule
21	\end{tabular}}
22	\end{table}
23	
24	\paragraph{Results.}
25	QLoRA achieves 3-class LOGO F1\,=\,0.905 ($\pm$0.003), a +11.6\,pp improvement over the XGBoost baseline (0.789).
26	On 5-class evaluation, QLoRA reaches F1\,=\,0.583 ($\pm$0.010) vs.\ 0.501 for XGBoost (+8.2\,pp), with the largest gains at gen-1 (0.796 vs.\ 0.634) and gen-2 (0.413 vs.\ 0.268).
27	The gen-2/gen-3 boundary remains the primary failure mode (gen-3 F1\,=\,0.259), consistent with the feature-level analysis in \S\ref{sec:discussion}.
28	
29	\paragraph{Hyperparameter robustness.}
30	A second run with LoRA rank 32 and seed 123 yields 5-class F1\,=\,0.587 ($\pm$0.005) and 3-class F1\,=\,0.905 ($\pm$0.004), which confirms stability acro
…[truncated 854 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 21 · 2026-05-20T05:07:55.159981+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_lofo.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_lofo.tex"
  }
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-20T05:07:55.160096+00:00_

1	We complement the permutation importance analysis (\S\ref{sec:results-differential}) with a leave-one-feature-out ablation. Each row drops one of the seven features and re-evaluates the full 6-gen LOGO protocol; $\Delta$ is the change relative to the full 7-feature ensemble (F1\,=\,0.789).
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\begin{tabular}{lcc}
7	\toprule
8	\textbf{Dropped feature} & \textbf{LOGO F1} & $\boldsymbol{\Delta}$ \textbf{vs Full} \\
9	\midrule
10	entropy\_max    & 0.774 & $-$1.50\,pp \\
11	entropy\_mean   & 0.783 & $-$0.63\,pp \\
12	ttr             & 0.784 & $-$0.55\,pp \\
13	hapax\_ratio    & 0.785 & $-$0.42\,pp \\
14	tail\_decay     & 0.786 & $-$0.33\,pp \\
15	entropy\_std    & 0.786 & $-$0.29\,pp \\
16	entropy\_min    & 0.789 & $+$0.01\,pp \\
17	\midrule
18	Full (7 features) & 0.789 & --- \\
19	\bottomrule
20	\end{tabular}
21	\caption{Leave-one-feature-out ablation (6-gen LOGO). Each row drops one feature and re-evaluates with the LOGO protocol. Sorted by impact magnitude.}
22	\label{tab:lofo}
23	\end{table}
24	
25	\paragraph{Analysis.}
26	Entropy\_max causes the largest degradation when removed ($-$1.5\,pp), despite ranking only fourth in permutation importance (split frequency 0.063). This indicates that entropy\_max provides unique signal (capturing the most surprising token under the reference model) that is not redundant with other features.
27	Conversely, entropy\_min is fully redundant ($\Delta$\,=\,+0.01\,pp), consistent with its near-zero permutation importance (0.015).
28	Six of seven features contribute positively to the ensemble, which confirms that the 7-feature design is not over-specified.
29	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-20T05:07:55.160228+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_length.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_length.tex"
  }
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-20T05:07:55.160347+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
  "offset": "0",
  "limit": "200"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
    "offset": "0",
    "limit": "200"
  }
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-20T05:07:55.160454+00:00_

File content (27195 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-20T05:07:55.160589+00:00_

1	% Appendix — Length Confound Analysis
2	% Data source: 8-generator LOGO corpus (37,058 samples)
3	
4	Surface diversity features (TTR, hapax ratio) mechanically depend on text length:
5	shorter texts yield higher type-token ratios by construction.
6	If generation depth systematically shortens text, observed depth trends could be length artifacts rather than genuine distributional shifts.
7	We investigate with three complementary analyses.
8	
9	\paragraph{(a) Length--depth correlation.}
10	Spearman rank correlation between word count and generation depth is weak across all eight generators ($|\rho| < 0.14$); depth does not systematically shorten or lengthen text in our corpus.
11	
12	\paragraph{(b) Length--feature correlations.}
13	While length--depth correlation is weak, individual features show moderate length dependence:
14	tail\_decay ($|\rho| = 0.38$), hapax\_ratio ($|\rho| = 0.30$), and TTR ($|\rho| = 0.29$).
15	Reference-model features show weaker length correlations (entropy\_mean $|\rho| = 0.09$, entropy\_std $|\rho| = 0.18$).
16	This motivates the length-matched evaluation below: if length mediates some depth--feature association, controlling for length will reduce classification performance.
17	
18	\paragraph{(c) Length-matched classification.}
19	We subsample the dataset so that word-count distributions are equalized across depth classes (gen-0\,/\,gen-1\,/\,gen-2+), then retrain the binary XGBoost classifier under pooled LOGO (8-fold).
20	Length-matched binary F1\,=\,0.724, down from 0.770 on the unmatched set ($\Delta$\,=\,$-$0.046).
21	To distinguish this from a sample-size effect, we run a random-subsample control at equal $N$ without length matching: F1\,=\,0.767, which confirms that the 0.046 drop reflects genuine length deconfounding rather than reduced data.
22	
23	\paragraph{Conclusion.}
24	Length accounts for approximately 6\% of discriminative performance ($\Delta$\,=\,0.046 out of 0.770).
25	The majority of the depth signal is length-independ
…[truncated 399 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-20T05:07:55.160742+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qualitative_examples.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_qualitative_examples.tex"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-20T05:07:55.160868+00:00_

1	\section{Qualitative Examples}
2	\label{app:qualitative}
3	
4	Table~\ref{tab:qualitative-text} presents an example generation chain from seed 120 (Pythia-2.8B, continuation prompt), illustrating how text evolves across recursive generation steps.
5	Table~\ref{tab:qualitative-features} reports the corresponding 7-feature values. Central-tendency features ($\bar{H}$, TTR, hapax ratio) drift monotonically while shape features ($H_{\max}$, tail decay) remain near-stationary, consistent with the differential depth response pattern.
6	
7	\begin{table}[t]
8	\centering
9	\caption{Example text chain from seed 120 (Pythia-2.8B, continuation prompt). Gen-0 is the original Wikipedia passage; gen-1 and gen-2 are successive LLM continuations. Text is truncated for space.}
10	\label{tab:qualitative-text}
11	\small
12	\begin{tabular}{p{0.93\columnwidth}}
13	\toprule
14	\textbf{Gen-0 (Wikipedia seed)} \\
15	\midrule
16	Aquarius is an equatorial constellation of the zodiac, between Capricornus and Pisces. Its name is Latin for ``water-carrier'' or ``cup-carrier''. Aquarius is one of the oldest of the recognized constellations along the zodiac (the Sun's apparent path). It was one of the 48 constellations listed by the 2nd century astronomer Ptolemy, and it remains one of the 88 modern constellations. It is found in a region often called the Sea due to its profusion of constellations with watery associations such as Cetus the whale, Pisces the fish, and Eridanus the river. [\ldots] \\
17	\midrule
18	\textbf{Gen-1} \\
19	\midrule
20	Babylonian astrology and was also depicted in ancient Egyptian art. In Greek mythology, Aquarius is the son of Poseidon and Gaia. He is also the god of the sea and the sky, the god of travelers, and the guardian of the underworld. In Roman mythology, Aquarius is the son of Saturn and the nymph Egeria, and the god of the sea. In Jewish mythology, Aquarius is the son of the God of the Air and the Goddess of the Moon. In Chinese mythology, Aquarius is the so
…[truncated 1341 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-20T05:07:55.161005+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ethics.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/ethics.tex"
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-20T05:07:55.161123+00:00_

1	\section*{Ethics Statement}
2	\label{sec:ethics}
3	
4	All texts analyzed in this work are LLM-generated from publicly available Wikipedia seeds; no personal or sensitive data is involved.
5	Our method estimates the generation depth of a text passage (how many recursive generation steps it has undergone), not the identity of its author.
6	Individual authorship attribution is outside both the scope and the capability of this approach; privacy implications are minimal.
7	We acknowledge that depth estimation tools could in principle be used to selectively suppress machine-generated text in contexts where such content is legitimate (e.g., accessibility tools, assistive writing).
8	We encourage deployment in data governance pipelines where provenance transparency, rather than content removal, is the objective.
9	All code, data, and trained models will be released upon publication.
10	
11	\paragraph{Licenses.}
12	All generator models are publicly available under permissive licenses (Apache 2.0 for Pythia, OLMo, and Mistral; Qwen License for Qwen3; Llama Community License for Llama 3.2).
13	Wikipedia seed passages are distributed under CC BY-SA 3.0.
14	
15	\paragraph{Compute budget.}
16	All experiments were conducted on 4$\times$ NVIDIA RTX 5090 GPUs (32\,GB each), totaling approximately 62 GPU-hours.
17	
18	\paragraph{Software.}
19	Experiments used Python 3.12.3, PyTorch 2.10.0 (CUDA 12.8), Transformers 4.57.6, XGBoost 3.2.0, scikit-learn 1.8.0, NumPy 2.2.6, pandas 3.0.2, and SciPy 1.17.1.
20	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-20T05:07:55.161249+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_prompt_type.tex"
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-20T05:07:55.161358+00:00_

1	We evaluate depth profiling under three prompt types using Pythia-2.8B: \emph{continuation} (``Continue the following text''), \emph{elaboration} (``Elaborate on the following text''), and \emph{inspired rewriting} (``Write a new passage inspired by the following text''). Each uses 995 seeds $\times$ 5 depths.
2	
3	\paragraph{Within-prompt-type classification.}
4	5-fold CV macro-F1: continuation 0.78, rewriting 0.74, elaboration 0.73. All three prompt types exhibit the same differential depth response pattern: drifting features (hapax ratio, TTR, entropy mean) show consistent monotonic trends, while near-stationary features (entropy max, tail decay) change by less than 5\%.
5	
6	\paragraph{Cross-prompt-type transfer (LOPTO).}
7	Leave-one-prompt-type-out evaluation yields average F1\,=\,0.753, which confirms that depth signal transfers across prompt types. Feature decay rates differ: continuation shows the strongest drift (16.9\% per depth step), followed by rewriting (6.1\%) and elaboration (1.4\%), consistent with continuation chains applying less semantic constraint on the output.
8	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-20T05:07:55.161478+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_human_edit.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_human_edit.tex"
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-20T05:07:55.161625+00:00_

1	We assess robustness to post-generation text modification by randomly replacing words at varying rates and re-evaluating the 8-generator LOGO pipeline (Table~\ref{tab:human-edit}).
2	Random word replacement represents a worst-case perturbation: real human editing preserves semantic coherence, so practical degradation is expected to be substantially lower than these estimates.
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\caption{Robustness to random word replacement under 8-gen LOGO evaluation (binary: gen-1 vs.\ gen-2+). Bootstrap 95\% CIs on binary F1 ($n$\,=\,1000).}
8	\label{tab:human-edit}
9	\resizebox{\linewidth}{!}{%
10	\begin{tabular}{lccc}
11	\toprule
12	\textbf{Perturbation rate} & \textbf{Binary F1} & \textbf{95\% CI} & \textbf{3-class F1} \\
13	\midrule
14	0\% (baseline) & 0.695 & [0.680, 0.710] & 0.737 \\
15	5\%            & 0.650 & [0.635, 0.666] & 0.641 \\
16	10\%           & 0.614 & [0.599, 0.629] & 0.492 \\
17	20\%           & 0.591 & [0.576, 0.605] & 0.367 \\
18	\bottomrule
19	\end{tabular}}
20	\end{table}
21	
22	Binary depth discrimination (gen-1 vs.\ gen-2+) degrades sublinearly: the first 5\% replacement causes the largest drop ($-$4.6\,pp), with diminishing marginal impact thereafter ($-$3.6\,pp for 5\%$\to$10\%, $-$2.3\,pp for 10\%$\to$20\%).
23	At 10\% replacement, binary F1 remains 0.614, well above the 0.50 random baseline, which indicates that depth signal survives moderate perturbation.
24	
25	Three-class classification is more sensitive (0.737$\to$0.367 at 20\%), because distinguishing gen-0 from gen-1 relies heavily on lexical diversity features (TTR, hapax ratio) that are directly disrupted by word replacement.
26	The binary metric, which excludes gen-0, is inherently more robust since it depends primarily on reference-model entropy features distributed across many tokens.
27	
28	\paragraph{Feature subset degradation.}
29	Table~\ref{tab:feature-degrade} compares perturbation robustness of the full 7-feature ensemble against an entro
…[truncated 4848 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-20T05:07:55.161778+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
  "offset": "0",
  "limit": "150"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt",
    "offset": "0",
    "limit": "150"
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-20T05:07:55.161891+00:00_

File content (27195 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-20T05:07:55.162005+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_error_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_error_analysis.tex"
  }
}
```

</details>

---

### Tool result

_source line 38 · 2026-05-20T05:07:55.162126+00:00_

1	We analyze the distribution and characteristics of binary classification errors (gen-1 vs.\ gen-2+) across the 8-generator LOGO evaluation ($N$\,=\,29{,}095 samples, overall error rate 28.08\%).
2	
3	\paragraph{Error asymmetry.}
4	Errors are heavily asymmetric: 86.2\% are false negatives (gen-2+ predicted as gen-1) and only 13.8\% are false positives (gen-1 predicted as gen-2+).
5	The classifier systematically under-predicts depth, consistent with the DDR pattern: shallow gen-2+ samples that have not yet accumulated sufficient distributional drift are indistinguishable from gen-1.
6	
7	\paragraph{Per-depth error rates.}
8	Error rates decrease monotonically with depth: depth-2 samples are the primary failure point (48.42\% error rate), followed by depth-3 (29.17\%) and depth-4 (20.32\%).
9	Depth-1 false positive rate is 7.11\%.
10	The monotonic decrease confirms that deeper generations accumulate progressively stronger depth signatures; the gen-1$\to$gen-2 transition is therefore the hardest to detect.
11	
12	\paragraph{Per-generator variation.}
13	Table~\ref{tab:error-by-gen} shows error rates vary substantially across generators, correlating with model scale: larger models (Mistral-7B, Qwen3-8B) produce text closer to gen-1 characteristics, which makes depth discrimination harder.
14	
15	\begin{table}[h]
16	\centering
17	\small
18	\caption{Binary classification error rates by generator (8-gen LOGO). Sorted by error rate descending.}
19	\label{tab:error-by-gen}
20	\begin{tabular}{llccc}
21	\toprule
22	\textbf{Generator} & \textbf{Family} & \textbf{Samples} & \textbf{Errors} & \textbf{Error rate} \\
23	\midrule
24	Mistral-7B-v0.3 & Mistral & 3{,}853 & 1{,}734 & 45.00\% \\
25	Qwen3-8B        & Qwen    & 3{,}502 & 1{,}197 & 34.18\% \\
26	Llama-3.2-3B    & Llama   & 3{,}685 & 1{,}112 & 30.18\% \\
27	OLMo-2-1B      & OLMo    & 3{,}718 & 1{,}054 & 28.35\% \\
28	Pythia-2.8B     & Pythia  & 3{,}614 &   866 & 23.96\% \\
29	Qwen3-1.7B     & Qwen    & 3{,}621 &   814 & 22.48
…[truncated 1169 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 39 · 2026-05-20T05:07:55.162268+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "wc -l \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
  "description": "Count lines in the registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "wc -l \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
    "description": "Count lines in the registry file"
  }
}
```

</details>

---

### Tool call

_source line 40 · 2026-05-20T05:07:55.162387+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_domain.tex"
  }
}
```

</details>

---

### Tool result

_source line 41 · 2026-05-20T05:07:55.162491+00:00_

0 /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-20T05:07:55.162623+00:00_

1	We evaluate whether depth signal generalizes beyond Wikipedia by constructing generation chains from three additional domains: News articles, Academic abstracts, and Code documentation.
2	For each domain, we sample 200 seed texts and generate chains of depth 3 using three generators (Pythia-1B, Qwen3-1.7B, Mistral-7B).
3	The same 7-feature ensemble and LOGO protocol are applied.
4	
5	\noindent\textbf{Important caveat:} Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$, which falls outside the method's reliable operating range ($t \leq 0.7$; Appendix~\ref{app:sampling-sensitivity}). Domain and temperature effects are therefore confounded in the results below; the cross-domain signal may partly reflect temperature-induced distributional divergence rather than domain generalization alone.
6	
7	\begin{table}[h]
8	\centering
9	\small
10	\caption{Cross-domain depth classification under LOGO evaluation (binary: gen-1 vs.\ gen-2+). Three generators $\times$ 200 seeds per domain. Bootstrap 95\% CIs ($n$\,=\,1000).}
11	\label{tab:domain}
12	\begin{tabular}{lccc}
13	\toprule
14	\textbf{Domain} & \textbf{Binary F1} & \textbf{95\% CI} & \textbf{3-class F1} \\
15	\midrule
16	Code           & 0.754 & [0.737, 0.770] & 0.634 \\
17	News           & 0.746 & [0.726, 0.764] & 0.652 \\
18	Academic       & 0.739 & [0.720, 0.757] & 0.622 \\
19	\bottomrule
20	\end{tabular}
21	\end{table}
22	
23	All three non-Wikipedia domains achieve binary F1 $>$ 0.73 under leave-one-generator-out evaluation, which demonstrates that depth signal is not an artifact of Wikipedia text properties.
24	
25	\paragraph{Domain $\times$ temperature interaction.}
26	Cross-domain generation used $t{=}1.0$, top-$p{=}1.0$ (vs.\ the main experiment's $t{=}0.7$, top-$p{=}0.9$).
27	Supplementary evaluation at $t{=}0.7$ reveals a domain $\times$ temperature interaction: the main Wikipedia experiment favors lower temperature (depth signal degrades monotonically with rising temperature; Appendix~\ref{app:sampling-sensit
…[truncated 1558 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-20T05:07:55.162771+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_downstream.tex"
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-20T05:07:55.162903+00:00_

1	Can depth-aware data curation improve downstream language model quality?
2	We fine-tune OLMo-2-0425-1B on five data variants (3 seeds each) and evaluate perplexity on a held-out test set (Table~\ref{tab:downstream}).
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\begin{tabular}{lrc}
8	\toprule
9	\textbf{Variant} & \textbf{$n$} & \textbf{Test PPL} \\
10	\midrule
11	All depths            & 12{,}299 & 2.335 $\pm$ 0.000 \\
12	Size-matched (random) & 3{,}951  & 2.367 $\pm$ 0.000 \\
13	Depth 0--1 only       & 3{,}951  & 2.387 $\pm$ 0.001 \\
14	Binary-filtered       & 3{,}951  & 2.389 $\pm$ 0.000 \\
15	Depth 0 only          & 797      & 2.681 $\pm$ 0.001 \\
16	\bottomrule
17	\end{tabular}
18	\caption{Downstream fine-tuning perplexity (OLMo-2-0425-1B, mean $\pm$ std across 3 seeds). At equal sample count, random subsampling (2.367) outperforms depth-aware curation (depth 0--1: 2.387, binary-filtered: 2.389).}
19	\label{tab:downstream}
20	\end{table}
21	
22	The results are unambiguous: data quantity dominates depth composition.
23	Training on all 12{,}299 samples yields the lowest perplexity (2.335).
24	At equal sample count ($n$\,=\,3{,}951), random subsampling (2.367) \emph{outperforms} both depth-stratified selection (depth 0--1: 2.387) and binary detection filtering (2.389).
25	Cross-seed variance is below 0.002 across all variants, which confirms the robustness of this null result.
26	
27	Restricting training to human-only text (depth 0, $n$\,=\,797) produces a sharp perplexity increase to 2.681, driven primarily by the 5$\times$ reduction in data volume rather than depth composition per se.
28	
29	\paragraph{Equivalence testing.}
30	We apply a two one-sided $t$-test (TOST) with a $\pm$2\% relative margin (equivalence bounds $\pm$0.047 on the ppl scale) to formally assess whether the depth-aware and random subsampling conditions produce practically indistinguishable perplexity.
31	At equal sample count ($n$\,=\,3{,}951): size-matched (random) ppl\,=\,2.367 vs.\ depth 
…[truncated 3466 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-20T05:07:55.163039+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_generator_subsets.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_generator_subsets.tex"
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-20T05:07:55.163154+00:00_

1	Table~\ref{tab:gen-subsets} summarizes the generator subsets used across experiments.
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\caption{Generator subsets by experiment type.}
7	\label{tab:gen-subsets}
8	\resizebox{\linewidth}{!}{%
9	\begin{tabular}{lcl}
10	\toprule
11	\textbf{Experiment} & $\boldsymbol{N}$ & \textbf{Generators} \\
12	\midrule
13	Main LOGO (Table~\ref{tab:logo-results}) & 8 & All: Py-2.8B/1B, OLMo, Qw-1.7B/0.6B/8B, Llama, Mistral \\
14	Cross-model chains (Table~\ref{tab:cross-ref}) & 5 & Py-2.8B/1B, OLMo, Qw-1.7B/0.6B \\
15	QLoRA (Table~\ref{tab:qlora}) & 6 & Py-2.8B/1B, OLMo, Qw-1.7B/0.6B/8B \\
16	Temperature ablation (Table~\ref{tab:sampling-ablation}) & 4 & Py-2.8B, OLMo, Qw-1.7B/0.6B \\
17	Prompt-type (Appendix~\ref{app:prompt-type}) & 1 & Py-2.8B only \\
18	Cross-domain (Table~\ref{tab:domain}) & 3 & Py-1B, Qw-1.7B, Mistral \\
19	Instruct (Table~\ref{tab:instruct}) & 3 & OLMo, Qw-1.7B, Llama \\
20	Downstream (Appendix~\ref{app:downstream}) & 5 & Py-2.8B/1B, OLMo, Qw-1.7B/0.6B \\
21	\bottomrule
22	\end{tabular}}
23	\end{table}
24	
25	The 5-generator set was the initial development subset; Qwen3-8B was added for scale evaluation, and Llama-3.2-3B and Mistral-7B-v0.3 were added last for family-diversity testing.
26	Subset differences reflect chronological expansion rather than selective reporting.
27	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-20T05:07:55.163319+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_tost.tex"
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-20T05:07:55.163452+00:00_

1	\section{Per-Generator Equivalence Testing}
2	\label{app:tost}
3	
4	To confirm that the near-stationary classification is not a pooling artifact, we apply two one-sided $t$-tests (TOST) \cite{lakens_equivalence} for each feature within each generator separately (gen-1 vs.\ gen-2+, equivalence bound $|d| < 0.20$).
5	We adopt Cohen's conventional small effect size ($d{=}0.20$) \cite{cohen1988statistical} as the smallest effect of practical significance (SESOI): effects below this threshold are unlikely to be practically meaningful for depth discrimination.
6	LOFO analysis independently supports this choice: removing any near-stationary feature changes classification F1 by $\leq$1.5\,pp (Appendix~\ref{app:lofo}), linking the statistical threshold to classification irrelevance.
7	Sensitivity analysis at $\varepsilon \in \{0.15, 0.20, 0.25\}$ confirms the partition is robust to the bound choice (see DDR Validation appendix).
8	Table~\ref{tab:tost-per-gen} reports observed $|d|$; \checkmark{} marks features for which the TOST null hypothesis (non-equivalence) is rejected at $\alpha = 0.05$.
9	
10	Entropy min passes equivalence for all eight generators; entropy max passes for six of eight (exceeding $\varepsilon$ only for Pythia-1B and Pythia-2.8B, where $|d| \approx 0.21$--$0.25$); tail decay passes for four of eight.
11	All drifting and intermediate features fail equivalence uniformly, with $|d|$ ranging from 0.23 (entropy std, Mistral) to 1.40 (entropy mean, Pythia-1B).
12	The partition is robust at the individual-generator level, with entropy min as the most consistently stationary feature.
13	Figure~\ref{fig:ddr-scatter} visualizes the DDR partition in ($|\rho|$, $d$) space, showing a clear gap between the three groups.
14	
15	\begin{table}[h]
16	\centering
17	\footnotesize
18	\caption{Per-generator TOST equivalence ($\varepsilon{=}|d|{<}0.20$, gen-1 vs.\ gen-2+). Observed $|d|$; \checkmark{} = equivalent ($p_{\mathrm{TOST}} < 0.05$). Features grouped by DDR partiti
…[truncated 1919 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-20T05:07:55.163609+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_confusion_matrix.tex"
  }
}
```

</details>

---

### Tool result

_source line 50 · 2026-05-20T05:07:55.163738+00:00_

1	Table~\ref{tab:confusion} reports the aggregated confusion matrix from the original six-generator subset (Pythia-2.8B, Pythia-1B, OLMo-2-1B, Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B) under leave-one-generator-out (LOGO) evaluation, collapsed to three ordinal classes: gen-0 (human), gen-1 (first-generation), and gen-2+ (depth $\geq$ 2).
2	The later-added Llama-3.2-3B and Mistral-7B-v0.3 are evaluated in the full 8-generator LOGO results (Table~\ref{tab:logo-results}).
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\resizebox{\linewidth}{!}{%
8	\begin{tabular}{lccc}
9	\toprule
10	& \textbf{Pred gen-0} & \textbf{Pred gen-1} & \textbf{Pred gen-2+} \\
11	\midrule
12	\textbf{True gen-0} & 5{,}937 (99.4\%) & 35 (0.6\%) & 0 (0.0\%) \\
13	\textbf{True gen-1} & 368 (6.2\%) & 4{,}437 (75.0\%) & 1{,}113 (18.8\%) \\
14	\textbf{True gen-2+} & 464 (3.0\%) & 3{,}646 (23.3\%) & 11{,}529 (73.7\%) \\
15	\bottomrule
16	\end{tabular}}
17	\caption{Aggregated 3-class confusion matrix from 6-generator LOGO evaluation ($N=27{,}529$). Each cell shows count and row-normalized percentage. Gen-0 is near-perfectly identified. Gen-1 errors are asymmetric: misclassification as gen-2+ (18.8\%) is 3$\times$ more frequent than as gen-0 (6.2\%). Gen-1 text already carries detectable recursive distortion.}
18	\label{tab:confusion}
19	\end{table}
20	
21	Figure~\ref{fig:confusion-heatmap} provides a heatmap visualization of the confusion matrix.
22	The row-normalized view highlights near-perfect gen-0 classification (99.4\% recall), gen-1 confusion primarily with gen-2+ (18.8\%) rather than gen-0 (6.2\%), and gen-2+ misclassification predominantly into gen-1 (23.3\%), consistent with DDR predictions.
23	
24	\begin{figure}[ht]
25	\centering
26	\includegraphics[width=\columnwidth]{fig_appendix_confusion.pdf}
27	\caption{3-class LOGO confusion matrix ($N$\,=\,27{,}529). (a) Raw counts. (b) Row-normalized recall percentages. Gen-0 achieves near-perfect classification; the primary confusion axis is gen-1 $\leftright
…[truncated 68 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 51 · 2026-05-20T05:07:55.163887+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_classifier.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_classifier.tex"
  }
}
```

</details>

---

### Tool call

_source line 52 · 2026-05-20T05:07:55.164012+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "wc -c \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
  "description": "Count bytes in the registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "wc -c \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
    "description": "Count bytes in the registry file"
  }
}
```

</details>

---

### Tool result

_source line 53 · 2026-05-20T05:07:55.164124+00:00_

63808 /home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 54 · 2026-05-20T05:07:55.164253+00:00_

1	To verify that the depth signal resides in the features rather than the classifier,
2	we repeat the 6-generator LOGO evaluation using Logistic Regression and Random Forest
3	in place of XGBoost (Table~\ref{tab:alt-classifier}).
4	All other settings (the same 7 features, 3-class labels, and class-balanced downsampling) are
5	kept identical. For Logistic Regression we apply standard scaling to the features.
6	
7	\begin{table}[h]
8	\centering
9	\caption{LOGO macro-F1 across three classifiers. Each column shows the held-out generator F1. (6-generator LOGO; 3-class.)}
10	\label{tab:alt-classifier}
11	\small
12	\resizebox{\linewidth}{!}{%
13	\begin{tabular}{lc cccccc}
14	\toprule
15	Classifier & Avg F1 & OLMo-2 & Py-1B & Py-2.8B & Qw-0.6B & Qw-1.7B & Qw-8B \\
16	\midrule
17	XGBoost          & 0.789 & 0.764 & 0.856 & 0.804 & 0.824 & 0.806 & 0.683 \\
18	Random Forest    & 0.790 & 0.764 & 0.856 & 0.804 & 0.825 & 0.807 & 0.684 \\
19	Logistic Regr.   & 0.725 & 0.719 & 0.781 & 0.740 & 0.745 & 0.743 & 0.624 \\
20	\bottomrule
21	\end{tabular}}
22	\end{table}
23	
24	Both tree-based classifiers achieve LOGO F1 $\approx 0.79$,
25	and even a linear model reaches $0.725$, well above the $0.33$ chance baseline for
26	three classes.
27	The per-generator ranking is also consistent across classifiers
28	(Pythia-1B easiest, Qwen3-8B hardest),
29	confirming that discriminative power originates in the entropy and lexical features,
30	not in classifier capacity.
31	Ordinal-specific methods (CORAL \cite{coral_ordinal}, Frank-Hall \cite{frank_hall_ordinal}) achieve comparable F1 with overlapping CIs, which confirms that 3-class granularity provides insufficient resolution for ranking-aware losses to improve over standard multiclass classification.
32	
33	\subsection*{Sampling Sensitivity Analysis}
34	\label{app:sampling-sensitivity}
35	
36	To assess robustness to decoding temperature, we regenerate continuation chains at $t \in \{0.5, 0.9\}$ with fixed nucleus $p{=}0.9$ (matching the default)
…[truncated 3716 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 55 · 2026-05-20T05:07:55.164411+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_distributions.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_distributions.tex"
  }
}
```

</details>

---

### Tool result

_source line 56 · 2026-05-20T05:07:55.164529+00:00_

1	\subsection*{DDR Trend Lines}
2	
3	Figure~\ref{fig:ddr-trends} shows the per-feature depth trend (mean across all samples at each depth) with individual generator traces overlaid.
4	The consistent downward trajectories for drifting features across all generators confirm that DDR is a universal property of recursive generation.
5	Shape features exhibit flat trajectories regardless of generator, with near-zero $R^2$ for the linear fit.
6	
7	\FloatBarrier
8	\begin{figure*}[ht]
9	\centering
10	\includegraphics[width=\textwidth]{fig_appendix_ddr_trends.pdf}
11	\caption{Per-feature depth trends. Black line: pooled mean ($\pm$1 std shading) across all generators. Colored traces: individual generators. Features are labeled by DDR category (drifting, intermediate, near-stationary). Spearman $\rho$ and linear $R^2$ are annotated per panel.}
12	\label{fig:ddr-trends}
13	\end{figure*}
14	
15	\subsection*{UMAP Embedding}
16	
17	Figure~\ref{fig:umap} shows a 2D UMAP projection of the 7-feature space (7{,}500 stratified samples, StandardScaler normalization, $k$\,=\,30 neighbors, min\_dist\,=\,0.3).
18	Panel (a) reveals a depth gradient from gen-0 through gen-4, with progressive overlap at deeper generations consistent with the convergence that motivates the gen-2+ class collapse.
19	Panel (b) shows the 3-class view: gen-0 forms a separable cluster, while gen-1 and gen-2+ overlap substantially, which explains the classification difficulty at this boundary.
20	
21	\FloatBarrier
22	\begin{figure}[ht]
23	\centering
24	\includegraphics[width=\columnwidth]{fig_appendix_umap.pdf}
25	\caption{UMAP 2D projection of the 7-feature space ($N$\,=\,7{,}500 stratified sample). (a) Colored by raw generation depth (0--4): a gradient structure emerges, with deeper depths converging. (b) Colored by 3-class label: gen-0 separates clearly; gen-1 and gen-2+ overlap, consistent with the high false-negative rate at the gen-1/gen-2+ boundary.}
26	\label{fig:umap}
27	\end{figure}
28	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 57 · 2026-05-20T05:07:55.164687+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_temp.tex"
  }
}
```

</details>

---

### Tool result

_source line 58 · 2026-05-20T05:07:55.164809+00:00_

1	Figure~\ref{fig:cross-temp} shows cross-temperature transfer results for the 6-generator LOGO pipeline.
2	We evaluate four train$\rightarrow$test temperature conditions using Qwen3-1.7B data regenerated at $t{=}1.0$ (remaining five generators retain $t{=}0.7$).\footnote{The $t{=}1.0$ data uses top-$p{=}0.95$ (vs.\ $p{=}0.9$ for other configurations); this difference may contribute to the observed degradation beyond the temperature effect alone.}
3	
4	\begin{figure}[ht]
5	\centering
6	\includegraphics[width=\columnwidth]{fig_appendix_cross_temp.pdf}
7	\caption{Cross-temperature transfer evaluation (6-gen LOGO). (a) Overall F1 by train$\rightarrow$test temperature condition. Matched conditions (0.7$\rightarrow$0.7, 1.0$\rightarrow$1.0) outperform cross-temperature transfer, with 0.7$\rightarrow$1.0 showing the largest degradation ($-6.6$\,pp in 3-class F1). (b) Per-generator 3-class F1 heatmap: Qwen3-1.7B shows dramatic degradation under cross-temperature conditions (0.418) while other generators remain stable. The temperature mismatch disproportionately affects the generator whose data was regenerated.}
8	\label{fig:cross-temp}
9	\end{figure}
10	
11	Key observations from the cross-temperature analysis:
12	
13	\begin{enumerate}[nosep]
14	\item \textbf{Matched-temperature robustness}: Both $t{=}0.7$ and $t{=}1.0$ matched conditions yield comparable performance (3-class F1: 0.789 vs.\ 0.726), with the gap attributable to weaker depth signal at high temperature rather than classifier degradation.
15	
16	\item \textbf{Asymmetric transfer}: Training at $t{=}1.0$ and testing at $t{=}0.7$ (F1\,=\,0.791) transfers well, but the reverse (0.7$\rightarrow$1.0, F1\,=\,0.723) degrades. This asymmetry reflects the information structure: features learned from high-variance (high-temperature) data generalize to low-variance settings, but not vice versa.
17	
18	\item \textbf{Generator-specific vulnerability}: Qwen3-1.7B, the only generator with temperature-mismatched test data, drop
…[truncated 649 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 59 · 2026-05-20T05:07:55.164947+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_ddr_validation.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_ddr_validation.tex"
  }
}
```

</details>

---

### Tool result

_source line 60 · 2026-05-20T05:07:55.165092+00:00_

1	\subsection*{Data-Driven Clustering}
2	
3	To assess whether the 3/1/3 DDR partition emerges from the data rather than post-hoc grouping, we apply $k$-means clustering ($k \in \{2,3,4,5\}$) to the seven features in standardized $(|\rho|, d)$ space (Table~\ref{tab:clustering}).
4	
5	\begin{table}[h]
6	\centering
7	\small
8	\caption{$k$-means clustering of 7 features in $(|\rho|, d)$ space.}
9	\label{tab:clustering}
10	\begin{tabular}{ccp{5.5cm}}
11	\toprule
12	$k$ & Silhouette & Clusters \\
13	\midrule
14	2 & \textbf{0.632} & \{$\bar{H}$, TTR, hapax\} $\mid$ \{$\sigma_H$, $H_{\min}$, $H_{\max}$, tail\} \\
15	3 & 0.499 & \{$\bar{H}$, TTR, hapax\} $\mid$ \{$\sigma_H$, $H_{\max}$, tail\} $\mid$ \{$H_{\min}$\} \\
16	4 & 0.571 & \{$\bar{H}$, TTR, hapax\} $\mid$ \{$H_{\max}$, tail\} $\mid$ \{$\sigma_H$\} $\mid$ \{$H_{\min}$\} \\
17	\bottomrule
18	\end{tabular}
19	\end{table}
20	
21	The primary drifting/non-drifting split ($k{=}2$, silhouette\,=\,0.632) is the strongest cluster structure.
22	At $k{=}3$, entropy min forms its own cluster rather than joining the near-stationary group because its pooled $|\rho|{=}0.40$ (driven by the gen-0/gen-1 boundary) places it far from other near-stationary features in $\rho$ space.
23	The 3/1/3 DDR partition resolves this by using the gen-1 vs.\ gen-2+ Cohen's $d$ ($d{=}0.03$) to place entropy min in the near-stationary group, a domain-informed refinement that unsupervised clustering cannot recover from pooled statistics alone.
24	At $k{=}4$ (silhouette\,=\,0.571), entropy std separates from the near-stationary group, consistent with its intermediate DDR classification.
25	
26	\subsection*{TOST Equivalence Bound Sensitivity}
27	\label{app:tost-sensitivity}
28	
29	Table~\ref{tab:tost-sensitivity} shows the fraction of generators for which each feature passes the TOST equivalence test (gen-1 vs.\ gen-2+, $\alpha{=}0.05$) at three equivalence bounds $\varepsilon$.
30	
31	\begin{table}[h]
32	\centering
33	\small
34	\caption{TOST equivalence
…[truncated 7654 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 61 · 2026-05-20T05:07:55.165242+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "head -c 5000 \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
  "description": "Read first 5000 bytes of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "head -c 5000 \"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"",
    "description": "Read first 5000 bytes of registry file"
  }
}
```

</details>

---

### Tool result

_source line 62 · 2026-05-20T05:07:55.165381+00:00_

{"result":"{\"success\": true, \"data\": {\"experiments\": {\"exp_056b_qlora_qwen_base\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:53:19.069Z\", \"updated_at\": \"2026-05-19T09:51:15.712Z\", \"hypothesis\": \"Within-model QLoRA on Qwen3-1.7B base data establishes per-model baseline for instruct comparison; expected 3-class F1 comparable to pooled base QLoRA (0.905) with potential variance from smaller per-model dataset\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && python /root/gen-depth-fingerprint/qlora_instruct.py --generator qwen3-1.7b --data_path /root/gen-depth-fingerprint/data/qwen3-1.7b/generations_shard0.jsonl --backbone /root/autodl-tmp/models/qwen3-0.6b/Qwen/Qwen3-0___6B-Base/ --device cuda:0 --output /root/gen-depth-fingerprint/results/qlora_qwen3-1.7b.json 2>&1 | tee /root/gen-depth-fingerprint/results/qlora_qwen_base.log\\\"\", \"server\": \"bjb2-18868\", \"gpu\": [\"cuda:3\"], \"pid\": \"72489\", \"log_path\": \"~/runs/gen-depth-fingerprint/exp_056b_qlora_qwen_base.log\", \"submitted_at\": \"2026-05-19T09:02:41.726Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"macro_f1_3class\": 0.904, \"macro_f1_3class_std\": 0.0094, \"macro_f1_5class\": 0.5544, \"macro_f1_5class_std\": 0.0068, \"binary_f1\": 0.8597, \"binary_f1_std\": 0.0123, \"n_samples\": 2291, \"runtime_seconds\": 880.9, \"note\": \"completed before kill signal\"}}, \"exp_055b_qlora_olmo_base\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T07:53:17.806Z\", \"updated_at\": \"2026-05-19T09:51:13.252Z\", \"hypothesis\": \"Within-model QLoRA on OLMo-2-1B base data establishes per-model baseline for instruct comparison; expected 3-class F1 comparable to pooled base QLoRA (0.905) with potential variance from smaller per-model dataset\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activ
…[truncated 3000 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 63 · 2026-05-20T05:07:55.165526+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_dataset_stats.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_dataset_stats.tex"
  }
}
```

</details>

---

### Tool result

_source line 64 · 2026-05-20T05:07:55.165673+00:00_

1	\section{Dataset Statistics}
2	\label{app:dataset-stats}
3	
4	Table~\ref{tab:dataset-stats} reports per-generator sample counts after filtering (removing generation failures, exact duplicates, and passages shorter than 50 whitespace tokens).
5	Under the 3-class evaluation scheme, the dataset contains 7{,}963 gen-0 samples (21.5\%), 7{,}896 gen-1 (21.3\%), and 21{,}199 gen-2+ (57.2\%, combining depths 2--4).
6	The gen-2+ majority reflects the chain structure (three deeper depths per chain vs.\ one each for gen-0 and gen-1); class-balanced sampling is applied during evaluation.
7	
8	\begin{table}[t]
9	\centering
10	\small
11	\begin{tabular}{llcc}
12	\toprule
13	\textbf{Generator} & \textbf{Family} & \textbf{Params} & \textbf{Samples} \\
14	\midrule
15	Pythia-1B       & Pythia  & 1.0B & 4{,}555 \\
16	Pythia-2.8B     & Pythia  & 2.8B & 4{,}609 \\
17	OLMo-2-1B      & OLMo    & 1.5B & 4{,}713 \\
18	Qwen3-0.6B     & Qwen    & 0.6B & 4{,}538 \\
19	Qwen3-1.7B     & Qwen    & 1.7B & 4{,}617 \\
20	Qwen3-8B       & Qwen    & 8.2B & 4{,}497 \\
21	Llama-3.2-3B   & Llama   & 3.2B & 4{,}680 \\
22	Mistral-7B-v0.3 & Mistral & 7.0B & 4{,}849 \\
23	\midrule
24	\multicolumn{3}{l}{\textbf{Total}} & \textbf{37{,}058} \\
25	\bottomrule
26	\end{tabular}
27	\caption[Per-generator sample counts]{Per-generator sample counts after filtering (8 generators, 5 families). Each generator starts from ${\sim}$1{,}000 shared Wikipedia seeds and produces chains of depth 4 (5 texts per chain). Attrition varies by generator due to differing generation failure rates.\protect\footnotemark}
28	\label{tab:dataset-stats}
29	\end{table}
30	\footnotetext{Table~\ref{tab:baselines} evaluates on a subset of 34{,}131 samples for which all detector scores (FastDetectGPT, Binoculars, LD-Score, Avg-LogProb) are available.}
31	
32	Figure~\ref{fig:violin} shows the full distribution of each feature across five generation depths (0--4), pooled across all eight generators ($N$\,=\,37{,}058).
33	The violin plots confirm t
…[truncated 736 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 65 · 2026-05-20T05:07:55.165813+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_finer_depth.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_finer_depth.tex"
  }
}
```

</details>

---

### Tool call

_source line 66 · 2026-05-20T05:07:55.165933+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=1 count=1 2>/dev/null",
  "description": "Read bytes 5000-10000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=1 count=1 2>/dev/null",
    "description": "Read bytes 5000-10000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 67 · 2026-05-20T05:07:55.166076+00:00_

thon /root/gen-depth-fingerprint/qlora_instruct.py --generator olmo-2-0425-1b-instruct --data_path /root/gen-depth-fingerprint/data/olmo-2-0425-1b-instruct/generations_shard0.jsonl --backbone /root/autodl-tmp/models/qwen3-0.6b/Qwen/Qwen3-0___6B-Base/ --device cuda:0 --output /root/gen-depth-fingerprint/results/qlora_olmo-2-0425-1b-instruct.json 2>&1 | tee /root/gen-depth-fingerprint/results/qlora_olmo_instruct.log\\\"\", \"server\": \"bjb2-18868\", \"gpu\": [\"cuda:0\"], \"pid\": \"71920\", \"log_path\": \"~/runs/gen-depth-fingerprint/exp_055_qlora_olmo_instruct.log\", \"submitted_at\": \"2026-05-19T09:02:34.465Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"conclusion\": \"success\", \"metrics\": {\"macro_f1_3class\": 0.8881, \"macro_f1_3class_std\": 0.0071, \"macro_f1_5class\": 0.5976, \"macro_f1_5class_std\": 0.0046, \"binary_f1\": 0.8363, \"binary_f1_std\": 0.0096, \"n_samples\": 4429, \"runtime_seconds\": 1689.7}}, \"exp_054_instruct_llama3_2_3b\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:06:07.150Z\", \"updated_at\": \"2026-05-18T07:58:31.553Z\", \"hypothesis\": \"Instruct-tuned Llama-3.2-3B-Instruct shows degraded depth signal vs base Llama-3.2-3B (F1=0.697), quantifying instruction-tuning's impact on DDR\", \"notes\": \"生成 59% (292/497 seeds) 后 Worker 与服务器断连。脚本有 resume 支持。模型已下载到 /root/autodl-tmp/models/Llama-3.2-3B-Instruct-ms/。Eval 脚本已准备: eval_exp054_instruct_llama.py\", \"conclusion\": \"success\", \"metrics\": {\"instruct_binary_f1\": 0.8381, \"instruct_binary_ci\": [0.828, 0.847], \"instruct_3class_f1\": 0.5437, \"instruct_3class_ci\": [0.53, 0.558], \"base_binary_f1\": 0.8488, \"base_3class_f1\": 0.7424, \"rho_instruct_entropy_mean\": 0.2299, \"rho_instruct_entropy_std\": 0.2623, \"rho_instruct_entropy_min\": -0.0027, \"rho_instruct_entropy_max\": 0.2036, \"rho_instruct_tail_decay\": 0.1198, \"rho_instruct_ttr\": -0.1411, \"rho_instruct_hapax_ratio\": -0.1157, \"rho
…[truncated 2832 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 68 · 2026-05-20T05:07:55.166236+00:00_

1	We evaluate finer-grained 5-class depth classification (gen-0 through gen-4) using the same 7-feature ensemble and LOGO protocol described in \S\ref{sec:method}.
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\resizebox{\linewidth}{!}{%
7	\begin{tabular}{lcccc}
8	\toprule
9	\textbf{Held-out Generator} & \textbf{Macro F1} & \textbf{Weighted F1} & \textbf{Accuracy} \\
10	\midrule
11	OLMo-2-1B       & 0.484 & 0.506 & 0.524 \\
12	Pythia-1B        & 0.543 & 0.568 & 0.575 \\
13	Pythia-2.8B      & 0.523 & 0.540 & 0.560 \\
14	Qwen3-0.6B      & 0.513 & 0.521 & 0.546 \\
15	Qwen3-1.7B      & 0.510 & 0.536 & 0.548 \\
16	Qwen3-8B        & 0.434 & 0.455 & 0.493 \\
17	\midrule
18	\textbf{Average} & \textbf{0.501 $\pm$ 0.038} & \textbf{0.521} & \textbf{0.541} \\
19	\bottomrule
20	\end{tabular}}
21	\caption{5-class LOGO evaluation. Each row holds out one generator for testing, training on the remaining five.}
22	\label{tab:5class-logo}
23	\end{table}
24	
25	\begin{table}[h]
26	\centering
27	\small
28	\resizebox{\linewidth}{!}{%
29	\begin{tabular}{lccccc}
30	\toprule
31	\textbf{Metric} & \textbf{Gen-0} & \textbf{Gen-1} & \textbf{Gen-2} & \textbf{Gen-3} & \textbf{Gen-4} \\
32	\midrule
33	Avg F1      & 0.921 & 0.634 & 0.268 & 0.259 & 0.423 \\
34	\bottomrule
35	\end{tabular}}
36	\caption{Per-class F1 averaged across all six LOGO folds.}
37	\label{tab:5class-perclass}
38	\end{table}
39	
40	\paragraph{Analysis.}
41	Moving from 3-class (gen-0 / gen-1 / gen-2+) to 5-class classification reduces LOGO macro F1 to approximately 0.50 (six-generator subset; the 3-class baseline for this subset is comparable to the 8-generator result of 0.762 in Table~\ref{tab:logo-results}).
42	The degradation is concentrated in the middle depths: gen-2 and gen-3 achieve only 0.268 and 0.259 F1, respectively.
43	The aggregated confusion matrix reveals that 36.5\% of true gen-2 samples are misclassified as gen-1, while 37.8\% of true gen-3 samples are predicted as gen-4.
44	Adjacent depths (gen-2$\leftrightarrow
…[truncated 1910 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 69 · 2026-05-20T05:07:55.166434+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_transfer.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_transfer.tex"
  }
}
```

</details>

---

### Tool result

_source line 70 · 2026-05-20T05:07:55.166591+00:00_

1	To isolate the depth signal from generator identity, we train a binary classifier (gen-1 vs.\ gen-2+) on each of the eight generators independently and evaluate on all others.
2	Table~\ref{tab:transfer} reports the full 8$\times$8 transfer matrix and Figure~\ref{fig:transfer} visualizes it as a heatmap.
3	Note that these classifiers are trained with a binary objective, whereas the LOGO classifiers in Table~\ref{tab:logo-results} are trained on a 3-class task and evaluated on the binary subtask; the two setups are therefore not directly comparable.
4	
5	\begin{table}[h]
6	\centering
7	\scriptsize
8	\setlength{\tabcolsep}{3pt}
9	\resizebox{\columnwidth}{!}{%
10	\begin{tabular}{l|cccccccc}
11	\toprule
12	\textbf{Train $\backslash$ Test} & \textbf{Py-2.8B} & \textbf{Py-1B} & \textbf{Qw-0.6B} & \textbf{Qw-1.7B} & \textbf{Qw-8B} & \textbf{OLMo-1B} & \textbf{Ll-3B} & \textbf{Mi-7B} \\
13	\midrule
14	Py-2.8B  & \underline{0.985} & 0.873 & 0.823 & 0.833 & 0.741 & 0.829 & 0.815 & 0.712 \\
15	Py-1B    & 0.834 & \underline{0.987} & 0.828 & 0.821 & 0.704 & 0.778 & 0.764 & 0.620 \\
16	Qw-0.6B  & 0.786 & 0.846 & \underline{0.991} & 0.851 & 0.786 & 0.795 & 0.760 & 0.680 \\
17	Qw-1.7B  & 0.794 & 0.839 & 0.859 & \underline{0.989} & 0.790 & 0.817 & 0.798 & 0.717 \\
18	Qw-8B   & 0.811 & 0.836 & 0.853 & 0.855 & \underline{0.984} & 0.848 & 0.839 & 0.790 \\
19	OLMo-1B  & 0.811 & 0.827 & 0.837 & 0.852 & 0.803 & \underline{0.988} & 0.828 & 0.763 \\
20	Ll-3B    & 0.856 & 0.860 & 0.845 & 0.851 & 0.798 & 0.851 & \underline{0.987} & 0.787 \\
21	Mi-7B    & 0.834 & 0.837 & 0.837 & 0.845 & 0.817 & 0.849 & 0.851 & \underline{0.969} \\
22	\bottomrule
23	\end{tabular}}
24	\caption{Cross-generator binary F1 transfer matrix (gen-1 vs.\ gen-2+). Each row trains on one generator; each column evaluates on another. Diagonal entries (\underline{underlined}) are within-generator. All 56 off-diagonal pairs exceed chance (0.5). Classifiers use the same 7-feature XGBoost configuration as LOGO but are trained 
…[truncated 1079 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 71 · 2026-05-20T05:07:55.166757+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_temperature_stability.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_temperature_stability.tex"
  }
}
```

</details>

---

### Tool result

_source line 72 · 2026-05-20T05:07:55.166888+00:00_

1	To assess whether the DDR three-way partition generalizes beyond the default temperature ($\tau{=}0.7$), we computed per-feature Cohen's $d$ (generation~1 vs.\ generation~2+) at $\tau \in \{0.5, 0.7, 0.9\}$ for all four generators in the temperature ablation (12 conditions total; Table~\ref{tab:ddr-temp-stability}).
2	
3	\begin{table}[h]
4	\centering
5	\small
6	\caption{Mean $|d|$ (gen-1 vs.\ gen-2+) across 4 generators at each temperature. Partition labels: \textbf{D}rifting ($|d|>0.5$), \textbf{I}ntermediate ($0.1{<}|d|{<}0.5$), near-\textbf{S}tationary ($|d|{<}0.1$). Boldface marks features that shift from their $\tau{=}0.7$ partition.}
7	\label{tab:ddr-temp-stability}
8	\begin{tabular}{lccc l}
9	\toprule
10	\textbf{Feature} & $\boldsymbol{\tau{=}0.5}$ & $\boldsymbol{\tau{=}0.7}$ & $\boldsymbol{\tau{=}0.9}$ & \textbf{Group} \\
11	\midrule
12	Entropy mean  & 1.39\,\textsuperscript{D} & 1.10\,\textsuperscript{D} & 0.58\,\textsuperscript{D} & Drifting \\
13	TTR           & 1.00\,\textsuperscript{D} & 0.85\,\textsuperscript{D} & \textbf{0.45}\,\textsuperscript{I} & Drifting \\
14	Hapax ratio   & 0.87\,\textsuperscript{D} & 0.75\,\textsuperscript{D} & \textbf{0.42}\,\textsuperscript{I} & Drifting \\
15	\midrule
16	Entropy std   & \textbf{0.84}\,\textsuperscript{D} & 0.52\,\textsuperscript{D} & \textbf{0.20}\,\textsuperscript{I} & Intermediate \\
17	\midrule
18	Entropy max   & 0.06\,\textsuperscript{S} & 0.09\,\textsuperscript{S} & \textbf{0.11}\,\textsuperscript{I} & Stationary \\
19	Tail decay    & 0.07\,\textsuperscript{S} & \textbf{0.12}\,\textsuperscript{I} & \textbf{0.15}\,\textsuperscript{I} & Stationary \\
20	Entropy min   & 0.04\,\textsuperscript{S} & 0.06\,\textsuperscript{S} & 0.04\,\textsuperscript{S} & Stationary \\
21	\bottomrule
22	\end{tabular}
23	\end{table}
24	
25	The partition anchors are robust: entropy mean remains drifting in all 12 conditions, TTR in 10/12, and hapax ratio in 9/12; entropy min and entropy max stay near-stationary in 10/12 and 9
…[truncated 735 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 73 · 2026-05-20T05:07:55.167037+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_seed_control.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_seed_control.tex"
  }
}
```

</details>

---

### Tool result

_source line 74 · 2026-05-20T05:07:55.167172+00:00_

1	\section{Independent-Seed Control}
2	\label{app:seed-control}
3	
4	To test for topic-level leakage from shared seeds across generators, we construct an independent-seed evaluation where Pythia-2.8B and OLMo-2-1B use completely disjoint Wikipedia seed pools (500 seeds each, zero overlap).
5	Each generator produces depth-0 through depth-4 chains on its own seed pool; features are extracted with the same Pythia-410M reference model.
6	We then train a 7-feature XGBoost classifier on one generator's data and test on the other, in both directions.
7	
8	\begin{table}[h]
9	\centering
10	\small
11	\begin{tabular}{lcc}
12	\toprule
13	\textbf{Setting} & \textbf{Binary F1} & \textbf{95\% CI} \\
14	\midrule
15	Pythia-2.8B $\rightarrow$ OLMo-2-1B & 0.695 & [0.673, 0.717] \\
16	OLMo-2-1B $\rightarrow$ Pythia-2.8B & 0.666 & [0.643, 0.689] \\
17	\midrule
18	Independent-seed average & 0.680 & --- \\
19	Shared-seed LOGO (reference) & 0.694 & [0.688, 0.700] \\
20	\bottomrule
21	\end{tabular}
22	\caption{Independent-seed cross-generator evaluation (binary: gen-1 vs.\ gen-2+). Disjoint seed pools eliminate any possibility of topic-based leakage. The average independent-seed F1 (0.680) is within 1.4\,pp of the shared-seed LOGO baseline (0.694). The classifier thus captures generative degradation patterns rather than seed-specific topic content.}
23	\label{tab:seed-control}
24	\end{table}
25	
26	The small gap ($-$1.4\,pp) between independent-seed and shared-seed evaluation falls within bootstrap confidence intervals, and both directions individually exceed 0.66.
27	Combined with the seed-level demeaning control (\S\ref{sec:results-classification}), these results provide converging evidence that depth classification is driven by distributional properties of recursive generation, not topic identity.
28	
29	\paragraph{Semantic similarity analysis.}
30	Embedding cosine similarity between consecutive depth steps increases monotonically: 0$\rightarrow$1 (0.622), 1$\rightarrow$2 (0.683), 2$\rig
…[truncated 525 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 75 · 2026-05-20T05:07:55.167343+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_instruct.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_instruct.tex"
  }
}
```

</details>

---

### Tool result

_source line 76 · 2026-05-20T05:07:55.167494+00:00_

1	\subsection*{Instruction-Tuned Model Results}
2	
3	Table~\ref{tab:instruct} summarizes depth classification under instruction tuning for three model families.
4	All results use within-model 5-fold CV on single-generator chains; LOGO evaluation is available for two models but uses earlier generator subsets (5--6 generators), so cross-model numbers are not directly comparable across rows.
5	
6	\begin{table}[h]
7	\centering
8	\small
9	\caption{Depth classification: base vs.\ instruction-tuned models (within-model 5-fold CV). $\rho$: Spearman correlation of entropy mean with depth. Rev.: number of features (out of 7) whose $\rho$ reverses sign under instruction tuning.}
10	\label{tab:instruct}
11	\resizebox{\linewidth}{!}{%
12	\begin{tabular}{lcc cc cc c}
13	\toprule
14	& \multicolumn{2}{c}{\textbf{3-class F1}} & \multicolumn{2}{c}{\textbf{Binary F1}} & \multicolumn{2}{c}{$\boldsymbol{\rho}$\textbf{(ent.\ mean)}} & \\
15	\cmidrule(lr){2-3} \cmidrule(lr){4-5} \cmidrule(lr){6-7}
16	\textbf{Model} & Base & Instruct & Base & Instruct & Base & Instruct & \textbf{Rev.} \\
17	\midrule
18	OLMo-2-1B       & 0.754 & 0.575 & 0.845 & 0.813 & $-$0.64 & $+$0.48 & 6/7 \\
19	Qwen3-1.7B      & 0.769 & 0.732 & 0.861 & 0.875 & $-$0.60 & $+$0.48 & 6/7 \\
20	Llama-3.2-3B    & 0.742 & 0.544 & 0.849 & 0.838 & $-$0.63 & $+$0.23 & 3/7 \\
21	\bottomrule
22	\end{tabular}}
23	\end{table}
24	
25	Instruction tuning degrades 3-class F1 by 3.7--19.9\,pp across all three families, while binary F1 (gen-1 vs.\ gen-2+) changes remain small ($|\Delta| \leq 3.2$\,pp).
26	The asymmetry indicates that instruction tuning primarily disrupts the gen-0/gen-1 boundary (human vs.\ first-generation), consistent with RLHF shifting the output distribution away from human-like text.
27	Entropy-mean $\rho$ reverses sign for all three models ($-0.60$--$-0.64$ base $\rightarrow$ $+0.23$--$+0.48$ instruct), and 6 of 7 features reverse for OLMo and Qwen vs.\ 3 of 7 for Llama.
28	This pattern is consistent with instruction
…[truncated 4430 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 77 · 2026-05-20T05:07:55.167655+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 78 · 2026-05-20T05:07:55.167782+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	The central finding is that recursive generation alters \emph{where} the token-level surprise distribution sits but not \emph{how} it is shaped: autoregressive sampling with fixed top-$p$ plausibly truncates the conditional distribution at a consistent shape regardless of input, while mean surprisal systematically decreases as the model conditions on its own increasingly typical outputs.
5	This asymmetry is not intrinsic to recursion but parameter-dependent: at $t{=}1.0$, the location signal collapses ($\rho$ from $-0.60$ to $-0.002$; Appendix~\ref{app:sampling-sensitivity}), and semantic-preservation constraints attenuate drift (elaboration F1\,=\,0.730 vs.\ continuation 0.781; Appendix~\ref{app:prompt-type}), consistent with \citet{broken_telephone}; cross-type transfer remains viable (F1\,=\,0.753).
6	
7	Several boundary conditions constrain practical applicability.
8	Document-level gen-1 per-class F1\,=\,0.63 is insufficient for automated filtering but sufficient for corpus-level flagging ($O(1/\sqrt{n})$ error scaling); the primary difficulty is distinguishing gen-1 from gen-2+, consistent with DDR producing the smallest location shift at the first recursive step (86\% false negatives; Appendix~\ref{app:error-analysis}).
9	Cross-temperature transfer degrades when test-time temperature exceeds training ($t{=}0.7 \rightarrow 1.0$: overall 3-class F1 drops from 0.789 to 0.723; the most affected single generator, Qwen3-1.7B, drops to per-generator F1\,=\,0.418; Appendix~\ref{app:cross-temp}); depth fingerprinting assumes matched or lower temperature.
10	These patterns hold across reference model families (F1 within 0.013; Table~\ref{tab:cross-ref}).
11	
12	DDR occupies a distinct position among recursive generation phenomena.
13	Model collapse \cite{curse_of_recursion,strong_model_collapse} describes irreversible degradation from \emph{retraining} on model outputs; inference-chain drift operates in a different re
…[truncated 1025 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 79 · 2026-05-20T05:07:55.167925+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_ablation.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_ablation.tex"
  }
}
```

</details>

---

### Tool call

_source line 80 · 2026-05-20T05:07:55.168045+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=2 count=1 2>/dev/null",
  "description": "Read bytes 10000-15000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=2 count=1 2>/dev/null",
    "description": "Read bytes 10000-15000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 81 · 2026-05-20T05:07:55.168160+00:00_

1	This appendix presents feature ablation results supporting the complementarity analysis in \S\ref{sec:results-differential}.
2	
3	\begin{table}[t]
4	\centering
5	\footnotesize
6	\begin{tabular}{lcc}
7	\toprule
8	\textbf{Feature set} & \textbf{F1} & \textbf{Top feature (imp.)} \\
9	\midrule
10	Full (7 features)     & 0.773 & hapax\_ratio (0.35) \\
11	Surface only (2)      & 0.688 & hapax\_ratio (0.41) \\
12	Reference only (5)    & 0.713 & entropy\_mean (0.27) \\
13	\bottomrule
14	\end{tabular}
15	\caption{Feature ablation (8-gen, 10-fold stratified CV, 3-class). Full $>$ surface (+8.5\,pp) and Full $>$ reference (+6.0\,pp) confirms complementarity.}
16	\label{tab:ablation}
17	\end{table}
18	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 82 · 2026-05-20T05:07:55.168304+00:00_

"tail_decay\": -0.141, \"ttr\": -0.7, \"hapax_ratio\": -0.712}, \"features_reversed\": \"6/7\", \"model_used\": \"allenai/OLMo-2-0425-1B-Instruct\"}}, \"exp_052_instruct_qwen3_1_7b\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-18T03:06:04.788Z\", \"updated_at\": \"2026-05-18T03:26:14.267Z\", \"hypothesis\": \"Instruct-tuned Qwen3-1.7B (chat template, thinking=off) shows degraded depth signal vs base Qwen3-1.7B (F1=0.709), quantifying instruction-tuning's impact on DDR\", \"spec\": {\"checkpoint_path\": \"N/A\", \"log_path\": \"/root/gen-depth-fingerprint/data/qwen3-1.7b-instruct/\"}, \"conclusion\": \"success\", \"metrics\": {\"within_binary_f1\": 0.8753, \"within_binary_ci\": [0.8667, 0.8837], \"within_3class_f1\": 0.7324, \"within_3class_ci\": [0.7195, 0.745], \"base_binary_f1\": 0.8614, \"base_3class_f1\": 0.769, \"logo_instruct_binary\": 0.658, \"logo_instruct_3class\": 0.543, \"logo_base_binary\": 0.821, \"logo_base_3class\": 0.802, \"gen1_f1_instruct\": 0.438, \"gen1_f1_base\": 0.579, \"spearman_direction\": \"reversed (instruct ρ>0, base ρ<0)\", \"delta_within_binary\": 0.014, \"delta_within_3class\": -0.037, \"delta_logo_binary\": -0.163}}, \"exp_051_independent_seed\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T22:38:00.466Z\", \"updated_at\": \"2026-05-18T02:01:42.126Z\", \"hypothesis\": \"Cross-generator depth classification with non-overlapping seeds achieves comparable F1 to shared-seed LOGO, ruling out topic fingerprint leakage\", \"spec\": {\"command\": \"generate_chain.py + extract_features.py + eval_independent_seed.py\", \"server\": \"autodl-5090\", \"data_path\": \"data/independent_seed/\", \"data_count\": \"500 seeds per generator\", \"model_name\": \"pythia-2.8b, olmo-2-1b\", \"seed\": 42, \"device\": \"cuda:3\", \"checkpoint_path\": \"N/A (evaluation only)\", \"log_path\": \"/root/gen-depth-fingerprint/results/independent_seed_control/\", \"results_path\": \"/root/gen-depth-fingerprint
…[truncated 2998 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 83 · 2026-05-20T05:07:55.168450+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_correlation.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_feature_correlation.tex"
  }
}
```

</details>

---

### Tool result

_source line 84 · 2026-05-20T05:07:55.168585+00:00_

1	\section{Feature Correlation Matrix}
2	\label{sec:appendix-feature-correlation}
3	
4	This appendix documents inter-feature correlations and the PCA analysis referenced in \S\ref{sec:results-differential}.
5	
6	\begin{table}[t]
7	\centering
8	\caption{Pearson correlation matrix of the seven depth features ($N=27{,}529$).}
9	\label{tab:feature-corr}
10	\resizebox{\columnwidth}{!}{%
11	\begin{tabular}{lrrrrrrr}
12	\toprule
13	 & $\bar{H}$ & $\sigma_H$ & $H_{\min}$ & $H_{\max}$ & $\tau$ & TTR & Hapax \\
14	\midrule
15	$\bar{H}$ & \textemdash & 0.49 & 0.31 & 0.01 & 0.07 & \textbf{0.86} & \textbf{0.81} \\
16	$\sigma_H$ & 0.49 & \textemdash & $-$0.15 & 0.16 & 0.26 & 0.43 & 0.34 \\
17	$H_{\min}$ & 0.31 & $-$0.15 & \textemdash & $-$0.04 & 0.01 & 0.20 & 0.23 \\
18	$H_{\max}$ & 0.01 & 0.16 & $-$0.04 & \textemdash & $-$0.08 & $-$0.13 & $-$0.15 \\
19	$\tau$ & 0.07 & 0.26 & 0.01 & $-$0.08 & \textemdash & 0.13 & 0.14 \\
20	TTR & \textbf{0.86} & 0.43 & 0.20 & $-$0.13 & 0.13 & \textemdash & \textbf{0.97} \\
21	Hapax & \textbf{0.81} & 0.34 & 0.23 & $-$0.15 & 0.14 & \textbf{0.97} & \textemdash \\
22	\bottomrule
23	\end{tabular}}
24	\end{table}
25	
26	TTR and hapax ratio are near-perfectly correlated ($r=0.97$), and both correlate strongly with mean entropy ($r=0.86$ and $0.81$).
27	These three drifting features form a tightly coupled cluster: PCA on the standardized drifting-feature subset shows that a single principal component explains 92.3\% of their joint variance, with near-uniform loadings (0.56--0.59). These three features thus share a single latent dimension.
28	Full 7-feature PCA yields PC1 (44.4\% variance) loading on the drifting triplet (0.53--0.55) and PC2 (18.3\% variance) capturing entropy distributional shape (entropy std vs.\ entropy min contrast).
29	In contrast, $H_{\max}$, $\tau$ (tail decay), and $H_{\min}$ show weak pairwise correlations with all other features ($|r| < 0.27$); these features capture independent aspects of the token-probability distribution.
30	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 85 · 2026-05-20T05:07:55.168726+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_convergence.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_convergence.tex"
  }
}
```

</details>

---

### Tool result

_source line 86 · 2026-05-20T05:07:55.168850+00:00_

1	This appendix visualizes per-feature convergence trajectories across generation depth, complementing the DDR analysis in \S\ref{sec:results-differential}.
2	
3	\begin{figure}[h]
4	\centering
5	\includegraphics[width=\columnwidth]{fig_convergence_dynamics.pdf}
6	\caption{Per-feature convergence dynamics across generation depths 0--4, averaged over 8 generators. Each feature is expressed as Cohen's $d$ relative to depth~0, so all features start at zero and the $y$-axis directly reflects effect size. (a)~Drifting features (hapax ratio, TTR, entropy mean) and the intermediate feature (entropy std) diverge monotonically; lexical diversity features (TTR, hapax ratio) form a fast-convergence group ($|d| > 2$ by depth~2), while entropy mean and entropy std drift more slowly. (b)~Near-stationary features (entropy max, tail decay, entropy min) remain within $|d| < 0.25$ across all depths, confirming location stability. Shaded bands indicate $\pm 1$ standard deviation across generators.}
7	\label{fig:convergence-dynamics}
8	\end{figure}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 87 · 2026-05-20T05:07:55.168973+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/related_work.tex"
  }
}
```

</details>

---

### Tool result

_source line 88 · 2026-05-20T05:07:55.169094+00:00_

1	\section{Related Work}
2	\label{sec:related}
3	
4	\subsection{AI-Generated Text Detection}
5	\label{sec:related-detection}
6	
7	Methods for distinguishing human-written from machine-generated text range from statistical tests \cite{gltr,grover,release_strategies} through zero-shot approaches \cite{detectgpt,fast_detectgpt,binoculars,dna_gpt} to learned classifiers \cite{ghostbuster,feat_aug_transformer,reliable_detection,ld_score}, with extensions to intrinsic dimensionality \cite{intrinsic_dimension}, surprisal diversity \cite{diveye}, and distributional gaps \cite{generator_barrier}; see \citet{wu_survey_2025} and \citet{jawahar_survey} for surveys.
8	Recent work moves beyond binary decisions---recognizing collaboration roles \cite{beyond_binary}, joint detection-attribution \cite{two_birds}, creator-editor modes \cite{beyond_final_actor}, multi-generator attribution \cite{semeval2024_task8}---but all target \emph{source} or \emph{production mode} taxonomies rather than recursive generation \emph{depth}; detection scores exhibit high cross-generator variance as depth predictors (binary F1 0.52--0.71; Table~\ref{tab:baselines}) \cite{paraphrase_evades,detection_possibilities}.
9	Our contribution is the task formulation (generation depth classification \cite{gutierrez_ordinal_survey,coral_ordinal}) and the finding that combining drifting and stationary features yields consistent cross-generator performance, orthogonal to source attribution \cite{uchendu_attribution,munir_looking_glass}.
10	
11	\subsection{Model Collapse and Iterative Generation}
12	\label{sec:related-collapse}
13	
14	Self-consuming generative models progressively lose distributional coverage \cite{self_consuming_mad,curse_of_recursion}, though data mixing mitigates collapse \cite{model_collapse_avoidable,strong_model_collapse}; these studies address \emph{training-loop} degradation, whereas we study \emph{inference chains} with fixed parameters.
15	Iterative self-refinement \cite{self_refine} targ
…[truncated 1990 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 89 · 2026-05-20T05:07:55.169229+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 90 · 2026-05-20T05:07:55.169352+00:00_

1	% Abstract — Depth Fingerprinting of Recursive LLM Generation Chains
2	\begin{abstract}
3	Recursive LLM generation shifts \emph{where} text sits in distributional space but leaves \emph{how} it is shaped nearly unchanged, and this asymmetry is consistent across five model families spanning 0.6B to 8B parameters.
4	We term this \emph{differential depth response} (DDR): under standard decoding, mean entropy and lexical diversity drift monotonically with generation depth while entropy max and tail decay show an order-of-magnitude smaller effect size.
5	Prior work on iterative generation tracks aggregate convergence without separating what changes from what is preserved; DDR provides this decomposition and enables coarse depth classification (gen-0\,/\,gen-1\,/\,gen-2+): a 7-feature ensemble achieves leak-free binary F1\,=\,0.694 (95\% CI [.688, .700]) under leave-one-generator-out evaluation and 0.830 on cross-model chains (5-generator subset, LOGO; 95\% CI [.818, .841]), at lower cost than multi-detector alternatives.
6	Despite measurable distributional drift, equivalence testing (TOST $\pm$2\%, $p < 0.001$) suggests no downstream training quality degradation.
7	The depth signal degrades under instruction tuning; current applicability is restricted to base models.
8	\end{abstract}
9	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 91 · 2026-05-20T05:07:55.169483+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 92 · 2026-05-20T05:07:55.169621+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	When the output of a language model is fed back as input to another (or the same) model, the resulting generation chain defines a discrete dynamical system over text distributions.
5	How do the distributional properties of generated text evolve across successive steps of this recursion?
6	Understanding this evolution is fundamental to characterizing how language models transform distributions under iterative conditioning, with implications for model collapse theory \cite{curse_of_recursion,strong_model_collapse} and data provenance \cite{ccnet,dsir} as model outputs increasingly re-enter training corpora \cite{dolma,fineweb} (an estimated 7--17\% of recent scientific publications contain substantial LLM-modified content \cite{mapping_llm_science,monitoring_ai_review}).
7	Yet existing detection methods \cite{fast_detectgpt,binoculars,ld_score,detectgpt} provide only binary real-vs-synthetic decisions, conflating qualitatively different material: a first-generation continuation retains much of the source distribution's lexical properties, while deeper recursive text exhibits measurably reduced vocabulary diversity and compressed perplexity.
8	
9	We formulate \emph{generation depth classification}, classifying text by coarse ordinal depth (gen-0\,/\,gen-1\,/\,gen-2+) rather than a binary label, and refer to the overall framework as \emph{depth fingerprinting}.
10	Concurrent studies characterize convergence in paraphrastic and translation chains \cite{broken_telephone,markovian_chains}, but none decompose the drift into structurally distinct components; our work addresses this gap in non-paraphrastic continuation chains.
11	We restrict to base (pretrained) models as a deliberate design choice: instruction-tuning introduces confounds (length regulation, format constraints, safety-driven shaping) that obscure the distributional dynamics of recursive generation; preliminary experiments confirm substantially degraded 
…[truncated 2562 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 93 · 2026-05-20T05:07:55.169771+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/conclusion.tex"
  }
}
```

</details>

---

### Tool result

_source line 94 · 2026-05-20T05:07:55.169884+00:00_

1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	Recursive generation produces a consistent, interpretable distributional signature: central-tendency features drift monotonically across depth while shape features remain an order of magnitude more stable.
5	This differential depth response enables depth classification across five model families (leak-free binary F1\,=\,0.694 under LOGO evaluation, 0.830 on cross-model chains, 5-generator subset) with no detected downstream quality degradation (preliminary TOST $\pm$2\%, $p < 0.001$; $n$\,=\,3 seeds).
6	The location-shape decomposition suggests that depth signal may arise in any iterative autoregressive process with fixed decoding, a hypothesis testable beyond text generation; current boundaries remain at instruction tuning (where token-level signal persists but handcrafted features fail to capture it) and frontier scale (70B+).
7	Code, data, and models will be released upon publication.
8	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 95 · 2026-05-20T05:07:55.170005+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/main.tex"
  }
}
```

</details>

---

### Tool call

_source line 96 · 2026-05-20T05:07:55.170122+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=3 count=1 2>/dev/null",
  "description": "Read bytes 15000-20000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=3 count=1 2>/dev/null",
    "description": "Read bytes 15000-20000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 97 · 2026-05-20T05:07:55.170265+00:00_

arent\": \"exp_043_multi_domain_seeds\", \"spec\": {\"command\": \"python run_multi_domain_t07.py (3 generators x 3 domains parallel in tmux multi_domain_t07)\", \"server\": \"autodl-5090\", \"data_path\": \"/root/gen-depth-fingerprint/experiments/multi_domain/\", \"data_count\": \"200 seeds x 3 domains x 3 generators x 4 depths = 7200 samples\", \"model_name\": \"Pythia-1B, Qwen3-1.7B, Mistral-7B-v0.3 (gen) + Pythia-410M (ref)\", \"seed\": \"default\", \"gpu\": \"cuda:0,1,2\", \"checkpoint_source\": \"N/A (generation + evaluation pipeline, no pretrained checkpoint)\", \"eval_data\": \"News/Academic/Code seeds 200 per domain, generated chains depth 0-3\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/experiments/multi_domain/multi_domain_results_t07.json\", \"log_path\": \"/root/gen-depth-fingerprint/experiments/multi_domain/run_t07.log\"}, \"metrics\": {\"news_binary_f1\": 0.7119, \"news_binary_ci\": [0.6898, 0.7332], \"news_3class_f1\": 0.7149, \"academic_binary_f1\": 0.6279, \"academic_binary_ci\": [0.6027, 0.6515], \"academic_3class_f1\": 0.6564, \"code_binary_f1\": 0.6872, \"code_binary_ci\": [0.6641, 0.71], \"code_3class_f1\": 0.6729, \"overall_binary_f1\": 0.6757, \"overall_3class_f1\": 0.6814, \"delta_vs_t10_news\": -0.034, \"delta_vs_t10_academic\": -0.1107, \"delta_vs_t10_code\": -0.0663}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-17T07:22:04.483Z\"}, \"multi-domain-seeds\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T03:38:54.349Z\", \"updated_at\": \"2026-05-17T05:05:40.584Z\", \"hypothesis\": \"Domain independence: depth fingerprint 的 differential depth response 不依赖 seed domain——在 News/Academic/Code 三个非 Wikipedia 域上，7-feature ensemble 的 binary F1 与 Wikipedia baseline 差异 <10pp，证明 DDR 是生成过程的固有特性而非特定域文本属性的 artifact\", \"spec\": {\"command\": \"python multi_domain_generation.py + eval\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,1,2,3\", \"data_path\": \"/root/gen-depth-fingerprint/data/seeds_{news,academ
…[truncated 2819 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 98 · 2026-05-20T05:07:55.170426+00:00_

1	% EMNLP 2026 ARR Submission — ACL 2023 Template
2	\documentclass[11pt]{article}
3	\usepackage[review]{acl}
4	\usepackage{times}
5	\usepackage{latexsym}
6	\usepackage{graphicx}
7	\usepackage{booktabs}
8	\usepackage{enumitem}
9	\usepackage{amsmath}
10	\usepackage{amssymb}
11	\usepackage{lineno}
12	\usepackage{placeins}
13	\usepackage{multirow}
14	\linenumbers
15	
16	\graphicspath{{../chart/}}
17	
18	\title{Depth Fingerprinting: Detecting Recursive Generation Depth\\in LLM Text Chains}
19	
20	\author{Anonymous}
21	
22	\begin{document}
23	\maketitle
24	
25	\input{abstract}
26	
27	\input{introduction}
28	\input{related_work}
29	\input{method}
30	\input{results}
31	
32	\input{discussion}
33	\input{conclusion}
34	\input{limitations}
35	\input{ethics}
36	
37	\bibliography{references}
38	
39	\appendix
40	
41	\noindent\textbf{Note:} Unless otherwise stated, appendix experiments use the original six-generator subset (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-1.7B/0.6B/8B).
42	Main paper results (\S\ref{sec:results}) use the full eight-generator set (adding Llama-3.2-3B and Mistral-7B-v0.3).
43	
44	\input{appendix_dataset_stats}
45	\FloatBarrier
46	
47	\section{Length Confound Analysis}
48	\label{app:length}
49	\input{appendix_length}
50	\FloatBarrier
51	
52	\section{Prompt Type Generalization}
53	\label{app:prompt-type}
54	\input{appendix_prompt_type}
55	\FloatBarrier
56	
57	\section{Finer-Grained Depth Classification}
58	\label{app:finer-depth}
59	\input{appendix_finer_depth}
60	\FloatBarrier
61	
62	\section{End-to-End Depth Classification (QLoRA)}
63	\label{app:qlora}
64	\input{appendix_qlora}
65	\FloatBarrier
66	
67	\section{Leave-One-Feature-Out Analysis}
68	\label{app:lofo}
69	\input{appendix_lofo}
70	\FloatBarrier
71	
72	\section{Confusion Matrix}
73	\label{app:confusion}
74	\input{appendix_confusion_matrix}
75	\FloatBarrier
76	
77	\section{Classifier Sensitivity}
78	\label{app:classifier}
79	\input{appendix_classifier}
80	\FloatBarrier
81	
82	\section{Robustness to Text Pertur
…[truncated 2608 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 99 · 2026-05-20T05:07:55.170583+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/limitations.tex"
  }
}
```

</details>

---

### Tool result

_source line 100 · 2026-05-20T05:07:55.170720+00:00_

1	\section*{Limitations}
2	\label{sec:limitations}
3	
4	All eight generators are base (pretrained) models.
5	This is a deliberate design choice: base models isolate the generation mechanism from instruction-tuning effects, enabling controlled study of recursive distributional drift.
6	However, web text is predominantly produced by instruction-tuned and RLHF-aligned models.
7	Preliminary instruct experiments confirm that depth signal degrades substantially under instruction tuning: OLMo-2-1B-Instruct drops to LOGO F1\,=\,0.338 (vs.\ 0.763 base) and Qwen3-0.6B with chat template to 0.667 (vs.\ 0.816 under a 7-generator split).
8	Length-matched analysis yields near-zero correlations ($|\rho| < 0.02$) and binary classification near chance (F1\,$\approx$\,0.5) for Qwen models, leaving interpretation ambiguous.
9	Extending depth fingerprinting to instruct models requires addressing these confounds (length regulation, format constraints, safety-driven distribution shaping) that instruction tuning introduces.
10	
11	Our experiments include generators up to 8.2B parameters (Qwen3-8B).
12	Depth signal persists at this scale (Qwen3-8B 3-class F1\,=\,0.714), but cross-scale transfer incurs a moderate gap vs.\ $\leq$2.8B generators (F1\,=\,0.77--0.81).
13	Frontier models (70B+) remain untested; their higher fluency may further compress feature margins.
14	
15	Differential depth response strength is prompt-type dependent: within-type 3-class F1 ranges from 0.78 (continuation) to 0.73 (elaboration), with inspired rewriting intermediate at 0.74 (Appendix~\ref{app:prompt-type}).
16	DDR is most reliably detected in continuation-style generation; near-paraphrastic settings approach the method's detection floor.
17	Cross-prompt-type transfer (LOPTO F1\,=\,0.753) confirms shared signal, yet additional prompt types (e.g., summarization, instruction following) and cross-generator $\times$ cross-prompt interactions remain untested.
18	
19	Our primary evaluation uses single-generator chains
…[truncated 2573 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 101 · 2026-05-20T05:07:55.170865+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/results.tex"
  }
}
```

</details>

---

### Tool result

_source line 102 · 2026-05-20T05:07:55.171022+00:00_

1	\section{Results}
2	\label{sec:results}
3	
4	\subsection{Depth Classification Performance}
5	\label{sec:results-classification}
6	
7	Generation depth is classifiable across diverse architectures: the 7-feature ensemble achieves 3-class LOGO F1\,=\,0.762 (95\% CI [0.758, 0.766]; $N$\,=\,37{,}058) across eight generators from five families (Table~\ref{tab:logo-results}).
8	Because gen-0 seeds are shared across generators (\S\ref{sec:generation}), gen-0 classification is near-perfect (per-class F1\,$\approx$\,0.94) and the 3-class metric is inflated by this overlap.
9	We therefore adopt leak-free binary F1 (gen-1 vs.\ gen-2+)\,=\,0.694, CI [0.688, 0.700], as the primary metric throughout; it excludes gen-0 entirely and is unaffected by seed sharing.
10	Per-generator binary F1 ranges from 0.633 (Mistral-7B) to 0.724 (Pythia-2.8B), with the primary difficulty being gen-1 vs.\ gen-2+ discrimination (Appendix~\ref{app:confusion}).
11	
12	\paragraph{Cross-model generalization.}
13	Cross-model chains (randomly selected generator per step) yield binary F1\,=\,0.830 (95\% CI [.818, .841]) under generator-level leave-one-out evaluation on the 5-generator subset for which cross-model chains were available (Pythia-2.8B/1B, OLMo-2-1B, Qwen3-0.6B/1.7B).\footnote{We corrected the cross-model chain evaluation from sample-level CV to generator-level LOGO for consistency with our main evaluation protocol. CIs are case-level bootstrap ($n$\,=\,2{,}000). The 5-generator result is not directly comparable to the 8-generator LOGO (binary F1\,=\,0.694) due to differing generator subsets.}
14	The higher cross-model binary F1 relative to the 8-generator LOGO (0.694) is not directly comparable: the cross-model evaluation uses a 5-generator subset, and generator heterogeneity in mixed chains may amplify depth-correlated distributional shifts.
15	A single-generator transfer analysis (Appendix~\ref{app:transfer}) provides evidence against this confound: classifiers trained on one generator trans
…[truncated 12827 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 103 · 2026-05-20T05:07:55.171177+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_model_detail.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/appendix_cross_model_detail.tex"
  }
}
```

</details>

---

### Tool call

_source line 104 · 2026-05-20T05:07:55.171304+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_3/projects/gen-depth-fingerprint/artifacts/_project/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 105 · 2026-05-20T05:07:55.171420+00:00_

1	This appendix reports per-generator breakdowns for the cross-model chain evaluation described in \S\ref{sec:results-classification}.
2	
3	\begin{table}[h]
4	\centering
5	\footnotesize
6	\begin{tabular}{lcccc}
7	\toprule
8	\textbf{Class} & \textbf{Prec.} & \textbf{Rec.} & \textbf{F1} & \textbf{95\% CI} \\
9	\midrule
10	gen-0   & 0.921 & 0.948 & 0.935 & [.923, .946] \\
11	gen-1   & 0.737 & 0.803 & 0.768 & [.748, .788] \\
12	gen-2+  & 0.842 & 0.742 & 0.789 & [.768, .809] \\
13	\midrule
14	\textbf{Macro} & --- & --- & \textbf{0.831} & [.817, .844] \\
15	\bottomrule
16	\end{tabular}
17	\caption{Cross-model chain per-class performance (generator-level leave-one-out, $N$\,=\,2{,}964, $n_{\text{generators}}$\,=\,5: Pythia-2.8B/1B, OLMo-2-1B, Qwen3-0.6B/1.7B). Macro F1\,=\,0.831 under class balancing; under natural class distribution, macro F1\,=\,0.789. Binary F1 (gen-1 vs.\ gen-2+)\,=\,0.830 (95\% CI [.818, .841], case-level bootstrap, $n$\,=\,2{,}000). Cross-model chains avoid the gen-0 seed sharing issue present in single-generator LOGO.}
18	\label{tab:cross-model-perclass}
19	\end{table}
20	

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 106 · 2026-05-20T05:07:55.171563+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Task Formulation}
5	\label{sec:task}
6	
7	Given a text $x$, the goal is to predict its \emph{generation depth} $d \in \{0, 1, 2{+}\}$, where $d{=}0$ denotes human-written text, $d{=}1$ denotes first-generation LLM output conditioned on human text, and $d{=}2{+}$ denotes text produced by recursively conditioning an LLM on its own prior output at least twice.
8	Formally, let $\mathcal{C}_0$ be a reference corpus of human-written text.
9	A generation chain of depth $k$ is defined recursively: $x^{(0)} \sim \mathcal{C}_0$, and $x^{(k)} = G(x^{(k-1)})$ for $k \geq 1$, where $G$ denotes stochastic LLM generation conditioned on its input.
10	We frame depth estimation as an ordinal classification task over three classes rather than binary real-vs-synthetic detection; this allows finer-grained provenance characterization.
11	Depths beyond 2 are merged into a single $2{+}$ class, consistent with monotonic feature convergence that compresses inter-class margins beyond depth 2 (\S\ref{sec:results-differential}).
12	
13	\subsection{Generation Chain Construction}
14	\label{sec:generation}
15	
16	We construct generation chains using eight generators spanning five model families: \textbf{Pythia} (2.8B, 1B) \cite{pythia}, \textbf{OLMo} (OLMo-2-1B) \cite{olmo}, \textbf{Qwen} (Qwen3-1.7B, Qwen3-0.6B, Qwen3-8B-Base) \cite{qwen3}, \textbf{Llama} (Llama-3.2-3B) \cite{llama3}, and \textbf{Mistral} (Mistral-7B-v0.3) \cite{mistral7b}.
17	This selection covers parameter scales from 0.6B to 8B and diverse pretraining corpora, which allows evaluation of cross-generator and cross-scale generalization.
18	
19	For each generator, we sample approximately 1{,}000 seed passages from English Wikipedia as $\mathcal{C}_0$.
20	The same pool of seed passages serves as gen-0 for all generators.
21	We use shared seeds across generators so that cross-generator comparisons control for input content and isolate the effect of the generation model from so
…[truncated 8137 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 107 · 2026-05-20T05:07:55.171733+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=4 count=1 2>/dev/null",
  "description": "Read bytes 20000-25000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=4 count=1 2>/dev/null",
    "description": "Read bytes 20000-25000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 108 · 2026-05-20T05:07:55.171882+00:00_

进度 340/500 seeds (68%)，当前 1542 行，预计 ~23:00 UTC 完成。GPU cuda:3 利用率 33%。\", \"conclusion\": \"success\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/qwen3-0.6b/generations_shard1.jsonl\", \"log_path\": \"/root/gen-depth-fingerprint/data/qwen3-0.6b/generations_shard1.jsonl\", \"completed_at\": \"2026-05-14T23:01:44.209Z\", \"metrics\": {\"records\": 2268, \"seeds\": 498, \"depth_dist\": {\"0\": 498, \"1\": 493, \"2\": 470, \"3\": 417, \"4\": 390}, \"file\": \"generations_shard1.jsonl\"}, \"parent\": \"plan-002\"}, \"plan-002-qwen06b-r2-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:35:10.950Z\", \"updated_at\": \"2026-05-17T02:56:23.413Z\", \"hypothesis\": \"跨家族泛化数据生成（Qwen3-0.6B shard0）：最小参数量(0.6B) Qwen 模型的 continuation 链，验证 depth signal 在极小模型中是否仍存在（小模型可能因容量不足而无法维持深层生成的分布稳定性）\", \"spec\": {\"command\": \"python generate_chain.py --model-name qwen3-0.6b --model-path /root/autodl-tmp/models/Qwen/Qwen3-0___6B-Base --input data/wiki_seed_1000.jsonl --shard-id 0 --num-shards 2 --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/gen-depth-fingerprint/data/qwen3-0.6b/generations_shard0.jsonl\", \"data_count\": 2500, \"model_name\": \"Qwen3-0.6B\", \"seed\": \"0-499\", \"pid\": \"117855\", \"gpu\": [\"cuda:2\"]}, \"notes\": \"Orphan 进程 PID 117855 存活，shard0 进度 350/500 seeds (70%)，当前 1593 行，预计 ~23:00 UTC 完成。GPU cuda:2 利用率 34%。\", \"conclusion\": \"success\", \"metrics\": {\"records\": 2270, \"seeds\": 498, \"depth_dist\": {\"0\": 498, \"1\": 493, \"2\": 468, \"3\": 423, \"4\": 388}, \"file\": \"generations_shard0.jsonl\"}, \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/qwen3-0.6b/generations_shard0.jsonl\", \"log_path\": \"N/A\", \"completed_at\": \"2026-05-14T23:00:55.097Z\", \"parent\": \"plan-002\"}, \"review-exp-c-overall-ci\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T12:22:37.037Z\", \"updated_at\": \"2026-05-17T02:56:15.141Z\", \"hypothesis\": \"6-generator LOGO 的 overal
…[truncated 2515 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 109 · 2026-05-20T05:07:55.172026+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=5 count=1 2>/dev/null",
  "description": "Read bytes 25000-30000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=5 count=1 2>/dev/null",
    "description": "Read bytes 25000-30000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 110 · 2026-05-20T05:07:55.172178+00:00_

mmand\": \"nohup /root/miniconda3/bin/python generate_chain.py --model-name qwen3-8b --model-path /root/autodl-tmp/models/Qwen/Qwen3-8B-Base/Qwen/Qwen3-8B-Base/ --input data/openwebtext_seeds.jsonl --shard-id 0 --num-shards 1 --device cuda:0 > /tmp/gen_large_model.log 2>&1 &\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 134817, \"data_path\": \"data/wiki_seed_1000.jsonl\", \"data_count\": 996, \"model_name\": \"Qwen3-8B-Base\", \"seed\": \"all\", \"log_path\": \"/tmp/gen_large_model.log\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/qwen3-8b/generations_shard0.jsonl\", \"output_path\": \"data/qwen3-8b/generations_shard0.jsonl\", \"estimated_duration_h\": 4, \"model_params\": \"8.2B\", \"fp16_vram_gb\": 16.1}, \"notes\": \"2026-05-15 04:25: ✅ 完整数据重算完成 (4409 records, 977 seeds)。与 82% 快照差异在统计噪声范围内：LOGO +0.0011, qwen8b held-out -0.0037。最终数字已确认，可用于论文。\", \"conclusion\": \"success\", \"metrics\": {\"total_records\": 4497, \"unique_seeds\": 995, \"depth_dist\": {\"0\": 995, \"1\": 979, \"2\": 937, \"3\": 831, \"4\": 755}, \"logo_6gen_avg_f1\": 0.7893, \"logo_per_generator\": {\"olmo-2-1b\": 0.7635, \"pythia-1b\": 0.8562, \"pythia-2.8b\": 0.8041, \"qwen3-0.6b\": 0.8243, \"qwen3-1.7b\": 0.8046, \"qwen3-8b\": 0.6832}, \"logo_qwen3_8b_held_out_f1\": 0.6832, \"logo_5gen_baseline_f1\": 0.8, \"spearman\": {\"hapax_ratio\": -0.5578, \"ttr\": -0.5419, \"entropy_mean\": -0.4754, \"entropy_min\": -0.3029, \"entropy_max\": 0.0946, \"tail_decay\": -0.0894, \"entropy_std\": -0.0755}, \"feature_importance\": {\"hapax_ratio\": 0.269, \"entropy_mean\": 0.1637, \"ttr\": 0.159, \"entropy_max\": 0.0634, \"entropy_std\": 0.0463, \"entropy_min\": 0.0153, \"tail_decay\": 0.0123}, \"revalidation_v2_vs_snapshot\": \"LOGO +0.0007 (0.7886→0.7893), qwen8b -0.0054 (0.6886→0.6832)\", \"revalidation_v2_conclusion\": \"complete_data_validates_snapshot_robustness\"}, \"completed_at\": \"2026-05-15T03:47:24.272Z\", \"parent\": \"plan-002\"}, \"plan-002-qwen17b-r2-s1\": {\"status
…[truncated 2806 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 111 · 2026-05-20T05:07:55.172323+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=6 count=1 2>/dev/null",
  "description": "Read bytes 30000-35000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=6 count=1 2>/dev/null",
    "description": "Read bytes 30000-35000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 112 · 2026-05-20T05:07:55.172473+00:00_

s\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T23:15:31.991817+00:00\"}]}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/qwen3-1.7b/generations_shard0.jsonl\", \"log_path\": \"~/runs/gen-depth-fingerprint/plan-002-qwen17b-r2-s0.log\", \"metrics\": {\"records\": 2291, \"seeds\": 498, \"depth_dist\": {\"0\": 498, \"1\": 492, \"2\": 468, \"3\": 435, \"4\": 398}, \"skipped\": 199, \"duration_s\": 4548.2, \"file_size_mb\": 2.5, \"file\": \"generations_shard0.jsonl\"}, \"completed_at\": \"2026-05-15T00:05:49.186Z\", \"hypothesis\": \"跨家族泛化数据生成（Qwen3-1.7B shard0）：Qwen 家族 1.7B 模型的 continuation 链 depth dynamics，验证中等规模非 Pythia 模型也产生可检测的 depth signal\", \"parent\": \"plan-002\"}, \"plan-002-olmo2-s1\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:09:46.880Z\", \"updated_at\": \"2026-05-17T02:55:54.134Z\", \"spec\": {\"command\": \"python generate_chain.py --model-name olmo-2-1b --shard-id 1 --num-shards 2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"108452\", \"log_path\": \"~/runs/gen-depth-fingerprint/plan-002-olmo2-s1.log\", \"submitted_at\": \"2026-05-14T20:09:46.862Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/gen-depth-fingerprint/data/wiki_seed_1000.jsonl\", \"data_count\": 1000, \"model_name\": \"allenai/OLMo-2-0425-1B\", \"seed\": 42, \"wall_clock_seconds\": 4242.5, \"gpu_hours\": 1.18}, \"reproduce\": {\"finished_at\": \"2026-05-14T21:18:05.854Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T21:18:09.081771+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"records\": 2334, \"seeds\": 498, \"skipped\": 70, \"wall_time_s\": 4081.2, \"depth_dist\": {\"gen0\": 498, \"gen1\": 494, \"gen2\": 470, \"gen3\": 444, \"gen4\": 428}, \"file\": \"generations_shard1.jsonl\", \"file_size_mb\": 2.57}, \"checkpoint_path\": \"/ro
…[truncated 2812 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 113 · 2026-05-20T05:07:55.172644+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=7 count=1 2>/dev/null",
  "description": "Read bytes 35000-40000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=7 count=1 2>/dev/null",
    "description": "Read bytes 35000-40000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 114 · 2026-05-20T05:07:55.172801+00:00_

onclusion\": \"success\", \"metrics\": {\"records\": 2269, \"seeds\": 498, \"skipped\": 100, \"wall_time_s\": 2247.6, \"depth_dist\": {\"gen0\": 498, \"gen1\": 496, \"gen2\": 455, \"gen3\": 422, \"gen4\": 398}, \"file\": \"data/pythia-1b/generations_shard1.jsonl\", \"file_size_mb\": 2.44}, \"completed_at\": \"2026-05-14T20:57:25.200Z\", \"hypothesis\": \"跨模型泛化数据生成（Pythia-1B shard1）：Pythia-1B continuation 链第二分片，与 shard0 合并后提供完整 ~995 seeds 的 depth 数据\", \"parent\": \"plan-002\"}, \"plan-002-pythia1b-s0\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T20:09:40.947Z\", \"updated_at\": \"2026-05-17T02:55:46.455Z\", \"spec\": {\"command\": \"python generate_chain.py --model-name pythia-1b --shard-id 0 --num-shards 2\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"108021\", \"log_path\": \"~/runs/gen-depth-fingerprint/plan-002-pythia1b-s0.log\", \"submitted_at\": \"2026-05-14T20:09:40.932Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/gen-depth-fingerprint/data/wiki_seed_1000.jsonl\", \"data_count\": 1000, \"model_name\": \"EleutherAI/pythia-1b\", \"seed\": 42, \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/pythia-1b/generations_shard0.jsonl\", \"wall_clock_seconds\": 2862.8, \"gpu_hours\": 0.8}, \"reproduce\": {\"finished_at\": \"2026-05-14T20:50:12.706Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T20:50:13.422601+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"records\": 2286, \"seeds\": 497, \"skipped\": 91, \"wall_time_s\": 2296.7, \"depth_dist\": {\"gen0\": 497, \"gen1\": 497, \"gen2\": 457, \"gen3\": 429, \"gen4\": 406}, \"file\": \"data/pythia-1b/generations_shard0.jsonl\", \"file_size_mb\": 2.5}, \"completed_at\": \"2026-05-14T20:57:23.757Z\", \"hypothesis\": \"跨模型泛化数据生成（Pythia-1B shard0）：同家族更大模型 Pythia-1B 的 continuation 链是否展现与 Pythia-2.8B 相似的 depth dynamics，验证 depth signal 
…[truncated 2722 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 115 · 2026-05-20T05:07:55.172953+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=8 count=1 2>/dev/null",
  "description": "Read bytes 40000-45000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=8 count=1 2>/dev/null",
    "description": "Read bytes 40000-45000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 116 · 2026-05-20T05:07:55.173102+00:00_

000\"]}, \"checkpoint_path\": \"/root/gen-depth-fingerprint/experiments/human_edit_robustness/llm_rephrase_results.json\", \"log_path\": \"/root/gen-depth-fingerprint/experiments/human_edit_robustness/llm_rephrase_results.json\", \"completed_at\": \"2026-05-17T01:04:28.657Z\", \"parent\": \"plan-010-robustness\"}, \"plan-015-v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:56:20.612Z\", \"updated_at\": \"2026-05-17T02:55:33.529Z\", \"spec\": {\"command\": \"PYTHONUNBUFFERED=1 HF_HUB_OFFLINE=1 CUDA_VISIBLE_DEVICES=2 python scripts/ordinal_baseline.py --device cuda:0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/gen-depth-fingerprint/data/\", \"data_count\": 0, \"model_name\": \"pythia-410m+pythia-160m\", \"seed\": 42, \"checkpoint_path\": \"N/A (analysis task)\", \"log_path\": \"/tmp/ordinal_baseline_v2.log\"}, \"conclusion\": \"success\", \"hypothesis\": \"Ordinal baseline bugfix + bootstrap CI: 修复 Binoculars denominator bug，验证 7-feature ensemble 显著优于所有单一检测器\", \"metrics\": {\"seven_feature_logo_f1\": 0.798, \"seven_feature_ci95\": [0.786, 0.799], \"avg_logprob_logo_f1\": 0.7653, \"avg_logprob_ci95\": [0.616, 0.82], \"ld_score_logo_f1\": 0.7212, \"ld_score_ci95\": [0.588, 0.77], \"fastdetectgpt_logo_f1\": 0.6269, \"fastdetectgpt_ci95\": [0.511, 0.762], \"binoculars_logo_f1\": 0.579, \"binoculars_ci95\": [0.405, 0.664], \"binoculars_bug_fixed\": true, \"ld_score_corrected_cv_f1\": 0.7925, \"bootstrap_7feat_vs_avglogprob\": {\"delta\": 0.039, \"p\": 0, \"significant\": true}, \"bootstrap_7feat_vs_fastdetectgpt\": {\"delta\": 0.067, \"p\": 0, \"significant\": true}}, \"completed_at\": \"2026-05-15T01:26:40.380Z\", \"parent\": \"plan-015\"}, \"plan-003-olmo2ref\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T00:09:31.145Z\", \"updated_at\": \"2026-05-17T02:55:33.041Z\", \"spec\": {\"command\": \"python extract_features_crossref.py --reference-model /root/autodl-tmp/models/olmo-2-1b-hf/allenai/OLMo-2-042
…[truncated 2764 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 117 · 2026-05-20T05:07:55.173247+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=9 count=1 2>/dev/null",
  "description": "Read bytes 45000-50000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=9 count=1 2>/dev/null",
    "description": "Read bytes 45000-50000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 118 · 2026-05-20T05:07:55.173399+00:00_

depth_distribution\": {\"0\": 995, \"1\": 995, \"2\": 959, \"3\": 944, \"4\": 934}, \"output_file\": \"/root/gen-depth-fingerprint/data/pythia-2.8b-inspired_rewriting/generations_shard0.jsonl\", \"file_size_mb\": 5.41, \"runtime_seconds\": 8584, \"speed_seeds_per_sec\": 0.12, \"depth_retention_d4_d0\": 0.939, \"vs_continuation\": \"retention 93.9% vs 83.1%, rewriting produces significantly more stable depth chains\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:00:25.058Z\", \"hypothesis\": \"Inspired rewriting 链数据生成：rewriting prompt 要求模型受启发重写而非逐字续写，预期 depth retention 介于 continuation 和 elaboration 之间，因为重写保留主题但改变表达\", \"parent\": \"plan-005\"}, \"plan-005-elab\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T03:28:45.680Z\", \"updated_at\": \"2026-05-17T02:55:17.294Z\", \"spec\": {\"command\": \"python generate_chain_prompt.py --model-name pythia-2.8b --prompt-type elaboration --input data/wiki_seed_1000.jsonl --shard-id 0 --num-shards 1 --device cuda:0\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"pid\": 164737, \"log_path\": \"/root/gen-depth-fingerprint/logs/plan-005-elab\", \"submitted_at\": \"2026-05-15T03:28:45.601Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/wiki_seed_1000.jsonl\", \"data_count\": 1000, \"model_name\": \"pythia-2.8b\", \"seed\": \"all\", \"prompt_type\": \"elaboration\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/pythia-2.8b-elaboration/generations_shard0.jsonl\", \"wall_clock_seconds\": 19266.7, \"gpu_hours\": 5.35}, \"reproduce\": {\"finished_at\": \"2026-05-15T05:58:50.421Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T05:58:51.901208+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"total_records\": 4946, \"unique_seeds\": 995, \"skipped\": 14, \"depth_distribution\": {\"0\": 995, \"1\": 995, \"2\": 989, \"3\": 986, \"4\": 981}, \"output
…[truncated 2766 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 119 · 2026-05-20T05:07:55.173546+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=10 count=1 2>/dev/null",
  "description": "Read bytes 50000-55000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=10 count=1 2>/dev/null",
    "description": "Read bytes 50000-55000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 120 · 2026-05-20T05:07:55.173715+00:00_

 \"autodl-5090\", \"data_path\": \"data/features.csv + data/generations.jsonl\", \"data_count\": 4609, \"model_name\": \"pythia-410m\", \"seed\": 42, \"pid\": 101585, \"log_path\": \"/tmp/plan-001-fix.log\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/results/ablation_results.json\"}, \"conclusion\": \"success\", \"metrics\": {\"full_macro_f1\": 0.8204, \"reference_only_f1\": 0.7187, \"surface_only_f1\": 0.7628, \"ref_vs_surf_bootstrap_ci\": \"[0.706,0.733] vs [0.747,0.774]\", \"h2_features\": \"entropy_mean, ttr, hapax_ratio\", \"h1_features\": \"tail_decay, entropy_std, entropy_max, entropy_min\", \"median_ppl_by_depth\": \"13.50, 4.96, 3.00, 2.07, 1.72\"}, \"completed_at\": \"2026-05-14T19:34:25.973Z\", \"hypothesis\": \"Feature ablation 修复验证：reference-only features (entropy系列+tail_decay) 独立于 surface features 仍能区分 depth，且两组特征的 bootstrap CI 不重叠，证明 differential response 和 lexical drift 是互补的独立信号源\", \"parent\": \"plan-001\"}, \"plan-010-robustness\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T22:09:57.049Z\", \"updated_at\": \"2026-05-16T22:11:48.657Z\", \"hypothesis\": \"Human edit robustness: depth fingerprint 在 5-20% random word replacement 下的 F1 退化测试，验证实际编辑场景（通常 < 5%）不影响检测\", \"conclusion\": \"success\", \"metrics\": {\"baseline_binary_f1\": 0.695, \"5pct_binary_f1\": 0.65, \"10pct_binary_f1\": 0.614, \"20pct_binary_f1\": 0.591, \"5pct_drop\": -0.046, \"10pct_drop\": -0.081, \"20pct_drop\": -0.104}, \"checkpoint_path\": \"/root/gen-depth-fingerprint/experiments/human_edit_robustness/robustness_results.json\", \"log_path\": \"/root/gen-depth-fingerprint/experiments/human_edit_robustness/\", \"spec\": {\"command\": \"python human_edit_robustness.py\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"data_path\": \"/root/gen-depth-fingerprint/data/detector_scores_8gen.csv\", \"data_count\": 5000, \"model_name\": \"Pythia-410M (reference)\", \"seed\": 42, \"perturbation_rates\": [0.05, 0.1, 0.2]}, \"completed_at\": \"2026-05-16
…[truncated 2713 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 121 · 2026-05-20T05:07:55.173886+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=11 count=1 2>/dev/null",
  "description": "Read bytes 55000-60000 of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=11 count=1 2>/dev/null",
    "description": "Read bytes 55000-60000 of registry file"
  }
}
```

</details>

---

### Tool result

_source line 122 · 2026-05-20T05:07:55.174092+00:00_

 \"/root/gen-depth-fingerprint/data/\"}, \"conclusion\": \"success\", \"metrics\": {\"seven_feature_logo_f1\": 0.798, \"seven_feature_ci\": [0.786, 0.799], \"avg_logprob_logo_f1\": 0.7653, \"avg_logprob_ci\": [0.616, 0.82], \"avg_logprob_spearman\": 0.7876, \"ld_score_logo_f1\": 0.7212, \"ld_score_ci\": [0.588, 0.77], \"ld_score_spearman\": 0.7943, \"ld_score_pre_fix\": 0.6854, \"fast_detect_gpt_logo_f1\": 0.6269, \"fast_detect_gpt_ci\": [0.511, 0.762], \"fast_detect_gpt_spearman\": 0.4325, \"binoculars_logo_f1\": 0.579, \"binoculars_ci\": [0.405, 0.664], \"binoculars_spearman\": 0.1989, \"binoculars_bug_confirmed\": true, \"binoculars_bug_fix\": \"denominator changed from CE(performer, obs_argmax) to CE(performer, shifted_ids)\", \"bootstrap_n\": 1000, \"bootstrap_delta_7feat_vs_avglogprob\": {\"delta\": 0.039, \"p\": 0, \"significant\": true}, \"bootstrap_delta_7feat_vs_fdgpt\": {\"delta\": 0.067, \"p\": 0, \"significant\": true}, \"best_single_detector\": \"Avg-LogProb (0.7653)\", \"seven_feature_advantage_pp\": 3.3}, \"completed_at\": \"2026-05-15T00:26:12.709Z\"}, \"plan-004-prep\": {\"status\": \"PREPARING\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:58:42.465Z\", \"updated_at\": \"2026-05-15T00:19:49.846Z\", \"hypothesis\": \"Downstream utility 准备：depth-stratified 数据集 + OLMo-1B fine-tuning 脚本（不开跑，等 Director 确认）\", \"conclusion\": \"success\", \"metrics\": {\"model\": \"OLMo-2-0425-1B (1485M)\", \"datasets\": {\"depth0_only\": {\"train\": 797, \"test\": 3138}, \"depth01\": {\"train\": 3951, \"test\": 3138}, \"all\": {\"train\": 12299, \"test\": 3138}, \"size_matched\": {\"train\": 3951, \"test\": 3138}, \"binary_filtered\": {\"train\": 3951, \"test\": 3138}}, \"dry_run_loss\": 2.18, \"script\": \"finetune_downstream.py\"}}, \"plan-003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:58:40.949Z\", \"updated_at\": \"2026-05-15T00:09:28.999Z\", \"hypothesis\": \"跨家族参考模型伪证化：用 OLMo-2-1B 和 Qwen3-0.6B 作参考模型提取特征，验证 differential d
…[truncated 2759 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 123 · 2026-05-20T05:07:55.174256+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=12 count=2 2>/dev/null",
  "description": "Read bytes 60000-end of registry file"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "dd if=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\" bs=5000 skip=12 count=2 2>/dev/null",
    "description": "Read bytes 60000-end of registry file"
  }
}
```

</details>

---

### Tool result

_source line 124 · 2026-05-20T05:07:55.174407+00:00_

.6b (cuda:2,3)\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/data/\", \"log_path\": \"/root/gen-depth-fingerprint/data/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T23:19:36.270Z\", \"metrics\": {\"total_records\": 18423, \"models\": 4, \"pythia_1b\": {\"records\": 4555, \"seeds\": 995, \"file\": \"data/pythia-1b/generations.jsonl\"}, \"olmo_2_1b\": {\"records\": 4713, \"seeds\": 995, \"file\": \"data/olmo-2-1b/generations.jsonl\"}, \"qwen3_0_6b\": {\"records\": 4538, \"seeds\": 996, \"depth_dist\": {\"gen0\": 996, \"gen1\": 986, \"gen2\": 938, \"gen3\": 840, \"gen4\": 778}, \"file\": \"data/qwen3-0.6b/generations.jsonl\"}, \"qwen3_1_7b\": {\"records\": 4617, \"seeds\": 996, \"depth_dist\": {\"gen0\": 996, \"gen1\": 983, \"gen2\": 941, \"gen3\": 875, \"gen4\": 822}, \"file\": \"data/qwen3-1.7b/generations.jsonl\"}}}, \"plan-001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:25:29.824Z\", \"updated_at\": \"2026-05-14T19:34:17.597Z\", \"hypothesis\": \"Feature ablation: 模型级特征（entropy系列+tail_decay）独立于表面特征仍能区分生成深度；H1/H2趋势分析确认特征随depth的变化模式；perplexity随depth显著变化\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/gen-depth-fingerprint && python ablation_analysis.py --parts A B C --device cuda:0\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"98324\", \"log_path\": \"/tmp/plan-001-fix.log\", \"submitted_at\": \"2026-05-14T18:25:56.326Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/gen-depth-fingerprint/results/ablation_results.json\", \"wall_clock_seconds\": 1685.0, \"gpu_hours\": 0.47}, \"reproduce\": {\"finished_at\": \"2026-05-14T18:51:40.563Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T18:51:41.308501+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"note\": \"initial_run_partia
…[truncated 1682 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 125 · 2026-05-20T05:07:55.174565+00:00_

called Bash

<details open><summary>🔧 Tool call — Bash</summary>

```json
{
  "command": "FILE=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"\n# Parse the JSON and extract all experiments with conclusion=success\npython3 -c \"\nimport json\n\nwith open('$FILE') as f:\n    raw = json.load(f)\n\ndata = json.loads(raw['result'])\nexperiments = data['data']['experiments']\n\nsuccess_exps = []\nfor exp_id, exp in experiments.items():\n    if exp.get('conclusion') == 'success':\n        success_exps.append((exp_id, exp))\n\n# Print count\nprint(f'Total experiments: {len(experiments)}')\nprint(f'Success experiments: {len(success_exps)}')\nprint()\n\nfor exp_id, exp in success_exps:\n    print(f'=== {exp_id} ===')\n    print(f'  hypothesis: {exp.get(\\\"hypothesis\\\", \\\"N/A\\\")}')\n    metrics = exp.get('metrics', {})\n    # Print key metrics (flatten top-level numeric values)\n    metric_strs = []\n    for k, v in metrics.items():\n        if isinstance(v, (int, float)):\n            metric_strs.append(f'{k}={v}')\n        elif isinstance(v, str) and len(v) < 80:\n            metric_strs.append(f'{k}={v}')\n    print(f'  metrics: {\\\" | \\\".join(metric_strs[:12])}')\n    print()\n\"\n",
  "description": "Parse JSON and extract all success experiments"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "tool_args": {
    "command": "FILE=\"/home/ubuntu/.claude-account-1/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-3-projects-gen-depth-fingerprint/1d18d25d-25e1-4c57-94d9-a15ab4822c5c/tool-results/mcp-agent-ml-research-read_registry-1779253272038.txt\"\n# Parse the JSON and extract all experiments with conclusion=success\npython3 -c \"\nimport json\n\nwith open('$FILE') as f:\n    raw = json.load(f)\n\ndata = json.loads(raw['result'])\nexperiments = data['data']['experiments']\n\nsuccess_exps = []\nfor exp_id, exp in experiments.items():\n    if exp.get('conclusion') == 'success':\n        success_exps.append((exp_id, exp))\n\n# Print count\nprint(f'Total experiments: {len(experiments)}')\nprint(f'Success experiments: {len(success_exps)}')\nprint()\n\nfor exp_id, exp in success_exps:\n    print(f'=== {exp_id} ===')\n    print(f'  hypothesis: {exp.get(\\\"hypothesis\\\", \\\"N/A\\\")}')\n    metrics = exp.get('metrics', {})\n    # Print key metrics (flatten top-level numeric values)\n    metric_strs = []\n    for k, v in metrics.items():\n        if isinstance(v, (int, float)):\n            metric_strs.append(f'{k}={v}')\n        elif isinstance(v, str) and len(v) < 80:\n            metric_strs.append(f'{k}={v}')\n    print(f'  metrics: {\\\" | \\\".join(metric_strs[:12])}')\n    print()\n\"\n",
    "description": "Parse JSON and extract all success experiments"
  }
}
```

</details>

---

### Tool result

_source line 126 · 2026-05-20T05:07:55.174778+00:00_

Total experiments: 42
Success experiments: 42

=== exp_056b_qlora_qwen_base ===
  hypothesis: Within-model QLoRA on Qwen3-1.7B base data establishes per-model baseline for instruct comparison; expected 3-class F1 comparable to pooled base QLoRA (0.905) with potential variance from smaller per-model dataset
  metrics: macro_f1_3class=0.904 | macro_f1_3class_std=0.0094 | macro_f1_5class=0.5544 | macro_f1_5class_std=0.0068 | binary_f1=0.8597 | binary_f1_std=0.0123 | n_samples=2291 | runtime_seconds=880.9 | note=completed before kill signal

=== exp_055b_qlora_olmo_base ===
  hypothesis: Within-model QLoRA on OLMo-2-1B base data establishes per-model baseline for instruct comparison; expected 3-class F1 comparable to pooled base QLoRA (0.905) with potential variance from smaller per-model dataset
  metrics: macro_f1_3class=0.8588 | macro_f1_3class_std=0.0036 | macro_f1_5class=0.5398 | macro_f1_5class_std=0.015 | binary_f1=0.7925 | binary_f1_std=0.0097 | n_samples=2379 | runtime_seconds=911.7 | note=completed before kill signal

=== exp_056_qlora_qwen_instruct ===
  hypothesis: QLoRA end-to-end classifier on Qwen3-1.7B-Instruct generation data recovers depth signal partially: 3-class F1 lower than base QLoRA (0.905) due to instruct-tuning compressing depth features, but higher than XGBoost on instruct features (0.732)
  metrics: macro_f1_3class=0.9066 | macro_f1_3class_std=0.0082 | macro_f1_5class=0.5514 | macro_f1_5class_std=0.0031 | binary_f1=0.8672 | binary_f1_std=0.0137 | n_samples=4963 | runtime_seconds=1880.5

=== exp_055_qlora_olmo_instruct ===
  hypothesis: QLoRA end-to-end classifier on OLMo-2-0425-1B-Instruct generation data recovers depth signal partially: 3-class F1 lower than base QLoRA (0.905) due to instruct-tuning compressing depth features, but higher than XGBoost on instruct features (0.575)
  metrics: macro_f1_3class=0.8881 | macro_f1_3class_std=0.0071 | macro_f1_5class=0.5976 | macro_f1_5class_std=0.0046 | binary_f1=0.8363 | binary_f1_std=0.0096 | n_s
…[truncated 13239 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Bash",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 127 · 2026-05-20T05:07:55.174992+00:00_

Here is the complete list of all 42 experiments with `conclusion=success`:

---

## All Successful Experiments (42/42)

| # | exp_id | Title / What it tested | Hypothesis (brief) | Key Metrics | Tags |
|---|--------|----------------------|---------------------|-------------|------|
| 1 | **mvp-001** | MVP: Pythia-2.8B depth classification | Pythia-410M reference features can distinguish gen-0/gen-1/gen-2+ in Pythia-2.8B continuation chains (target: 3-class F1 >= 0.45) | macro_f1=0.8408, binary_f1=0.8653, cv_macro_f1=0.806 | baseline, depth-classification, pythia |
| 2 | **plan-001** | Feature ablation (initial) | Model-level features (entropy+tail_decay) independently distinguish depth; perplexity changes significantly with depth | ablation_full_f1=0.82, surface_only=0.76, reference_only=0.72 | ablation, feature-importance |
| 3 | **plan-001-fix** | Feature ablation (bugfix) | Reference-only features independently distinguish depth; bootstrap CIs don't overlap between reference and surface features | full_f1=0.8204, reference_only=0.7187, surface_only=0.7628, median_ppl_by_depth: 13.50/4.96/3.00/2.07/1.72 | ablation, bootstrap-CI, dual-signal |
| 4 | **plan-002** | Cross-model generalization (data generation) | Depth features from Pythia-410M generalize across architectures (Pythia-1B, OLMo-2-1B, Qwen3-1.7B, Qwen3-0.6B) | total_records=18423, models=4 | cross-generator, data-generation |
| 5 | **plan-002-pythia1b-s0** | Pythia-1B shard0 generation | Same-family larger model shows similar depth dynamics as Pythia-2.8B | records=2286, seeds=497 | data-generation, pythia, scaling |
| 6 | **plan-002-pythia1b-s1** | Pythia-1B shard1 generation | Complete seed coverage for Pythia-1B | records=2269, seeds=498 | data-generation, pythia |
| 7 | **plan-002-olmo2-s0** | OLMo-2-1B shard0 generation | Non-Pythia architecture shows depth signal, verifying universality across training data and architecture | records=2379, seeds=497 | data-generation, olmo, cross-architecture |
| 8
…[truncated 9831 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Agent",
  "elapsed_ms": 16
}
```

</details>

---

### Tool result

_source line 128 · 2026-05-20T05:07:55.175287+00:00_

Here is the complete extraction from all 41 .tex files:

---

## 1. `table1.tex`
- **Exp IDs**: None
- **Key metrics**: LOGO Macro-F1 per generator: Pythia-1B 0.806, Mistral-7B 0.681; Average 8-gen 0.762, 95% CI [0.758, 0.766]
- **Keywords**: leave-one-generator-out (LOGO), 3-class depth classification, held-out generator
- **Tables/Figures**: `\label{tab:logo-results}` (Table: LOGO results, 8-gen, 3-class). NOTE: this standalone file is NOT \input'd by main.tex; the inline table in results.tex is authoritative.

## 2. `table2.tex`
- **Exp IDs**: None
- **Key metrics**: Full 7-feature LOGO F1 = 0.773; Surface only (2 features) = 0.688; Reference only (5 features) = 0.713; McNemar p < 0.001 for both subsets. Permutation importance: hapax_ratio 0.269, entropy_mean 0.164, ttr 0.159
- **Keywords**: feature group ablation, complementarity, 8-gen 10-fold CV, permutation importance, surface features, reference features
- **Tables/Figures**: `\label{tab:feature-ablation}` (Table: feature group ablation)

## 3. `table4.tex`
- **Exp IDs**: None
- **Key metrics**: Pythia-410M LOGO F1 = 0.803, Ent. Drift [-1.19, -1.40]; OLMo-2-1B LOGO F1 = 0.807, Ent. Drift [-0.61, -0.91]; Qwen3-0.6B LOGO F1 = 0.816, Ent. Drift [-0.96, -1.35]; F1 spread = 0.013
- **Keywords**: cross-family reference model validation, 5-gen LOGO subset, entropy drift, reference model choice
- **Tables/Figures**: `\label{tab:cross-ref}` (Table: cross-family reference models)

## 4. `appendix_qlora.tex`
- **Exp IDs**: None
- **Key metrics**: XGBoost 5-class F1 = 0.501 +/- 0.038, 3-class F1 = 0.789; QLoRA 5-class F1 = 0.583 +/- 0.010, 3-class F1 = 0.905 +/- 0.003; Per-class F1 (5-class): 0.999/0.796/0.413/0.259/0.447; Hyperparameter robustness: rank 32 seed 123 yields 5-class 0.587 +/- 0.005, 3-class 0.905 +/- 0.004
- **Keywords**: QLoRA, end-to-end depth classification, Qwen3-0.6B-Base, LoRA rank 16, learning rate 2e-4, 3 epochs, 5-class sequence classification, hyperparameter robustness, LoRA rank 32, seed 123, t
…[truncated 26390 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_audit_exp-data-utilization_20260520T050056",
  "tool": "Agent",
  "elapsed_ms": 16
}
```

</details>

---

### Assistant

_source line 129 · 2026-05-20T05:07:55.175564+00:00_

Now I have all 42 successful experiments and the complete paper content. Let me cross-reference systematically.

## 实验数据利用审计结果

### 方法
对每个 success 实验，匹配其关键指标数字、实验描述关键词是否出现在论文 tex 文件中。论文中不使用 exp_id 字符串，因此匹配基于数值和语义。

### 汇总

**38/42 实验已被引用**（直接引用或作为数据生成步骤被下游实验间接引用）

**4/42 实验未被引用**——均为被后续实验取代的早期/中间版本：

| exp_id | 实验名 | 当前引用状态 | 建议 |
|--------|--------|-------------|------|
| **mvp-001** | MVP: Pythia-2.8B within-model depth classification (F1=0.84) | 未引用。被 8-gen LOGO 评估取代。within-model 性能已被 transfer matrix 对角线覆盖（0.969-0.991） | **无需补充**。transfer matrix (appendix_transfer) 已展示 within-model 性能 |
| **plan-001** | Feature ablation (初版) | 未引用。被 plan-001-fix 取代，plan-001-fix 又被 8-gen 版本取代 | **无需补充**。8-gen feature ablation (table2/appendix_ablation) 已覆盖 |
| **plan-001-fix** | Feature ablation (修正版，F1=0.82, ppl\_by\_depth: 13.5/5.0/3.0/2.1/1.7) | 未引用。独特数据点是 explicit perplexity-by-depth 曲线，但概念上已被 entropy trend 分析覆盖 | **无需补充**。appendix\_feature\_distributions 的 DDR trend 图已展示同等信息 |
| **plan-015** | Ordinal baseline (含 Binoculars bug) | 未引用。被 plan-015-v2 (bugfix) 取代，v2 结果已在 results.tex baselines 表中 | **无需补充**。bugfix 版本已被引用 |

### 间接引用的数据生成实验（12个）

以下实验本身是数据生成步骤，其数据被下游评估实验使用，算间接引用：

- `plan-002` + 8个 shard (`plan-002-pythia1b-s0/s1`, `plan-002-olmo2-s0/s1`, `plan-002-qwen17b-r2-s0/s1`, `plan-002-qwen06b-r2-s0/s1`) → 被 `plan-002-eval` 使用
- `plan-003-olmo2ref`, `plan-003-qwen06bref` → 被 `plan-003` cross-ref 评估使用
- `plan-005-cont`, `plan-005-elab`, `plan-005-rewrite` → 被 `plan-005` prompt-type 评估使用
- `plan-004-prep` → 被 downstream fine-tuning 实验使用 (appendix\_downstream)

### 结论

**所有有独立分析价值的成功实验均已被论文引用。** 4个未引用实验都是被改进版本取代的早期迭代，其独特数据点已被后续实验的更全面版本覆盖。无需补充新的 appendix 内容。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_audit_exp-data-utilization_20260520T050056"
}
```

</details>

---
