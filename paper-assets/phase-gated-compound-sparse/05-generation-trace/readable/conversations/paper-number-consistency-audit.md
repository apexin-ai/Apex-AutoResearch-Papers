# paper number consistency audit

**Phase-Modulated Compound Sparsity Severity in 7B-Scale Mathematical Reasoning Models** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 56
- **Recorded user turns:** 0
- **Tool calls:** 28
- **Original source:** `logs/chats/worker_paper_number_consistency_audit_20260514T101321.jsonl`
- **Structured JSON:** [`d7a2cc4b10bc0f4260c2.json`](../../sessions/d7/d7a2cc4b10bc0f4260c2.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

56 recorded events

### Tool call

_source line 1 · 2026-05-14T10:22:49.189074+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/abstract.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-14T10:22:49.189740+00:00_

1	\begin{abstract}
2	Compound sparsity---simultaneously pruning attention heads and evicting KV cache entries---is essential for efficient LLM inference but produces super-additive quality degradation whose structure is poorly understood.
3	Prior work treats compound interaction magnitude as approximately constant across the generation process.
4	We show that this assumption is wrong: compound sparsity severity is an emergent phase-strategy interaction that varies by over an order of magnitude across reasoning phases.
5	
6	We evaluate compound sparsity on DeepSeek-R1-Distill-Qwen-7B and Qwen2.5-7B-Instruct (both Qwen2 architecture, 7B parameters) using 50 MATH-500 problems, measuring the Interaction Index---a super-additivity metric---across quantile-segmented reasoning phases at sparsity levels $s \in \{0.15, 0.20, 0.25, 0.30\}$.
7	Under importance-based KV cache eviction, the median Interaction Index difference between low-sparsity and high-sparsity reasoning phases increases monotonically from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$, with paired Cohen's $d_z$ growing from $0.44$ (small) to $0.80$ (large); Bonferroni-corrected permutation tests yield $p < 0.005$ at all four sparsity levels.
8	Random eviction produces no significant phase modulation in 7/8 conditions; the single exception (Qwen $s{=}0.30$, $p{=}0.012$) shows negligible effect size ($d_z{=}{-}0.04$), confirming that the severity gradient is strategy-specific, not an inherent property of compound sparsity.
9	At $s{=}0.25$, a crossover emerges: importance-based eviction outperforms random in high-sparsity phases ($\widetilde{\mathrm{II}} = 0.032$ vs.\ $0.818$) yet underperforms in low-sparsity phases ($\widetilde{\mathrm{II}} = 7.196$ vs.\ $1.363$)---a qualitative reversal in strategy ranking.
10	The pattern replicates on Qwen2.5-7B-Instruct at $s \geq 0.20$ ($d_z \geq 0.55$; Spearman $\rho = 1.0$ across sparsity levels; gradient permutation $p = 0.043$).
11	
12	We propose entropy-discrimination
…[truncated 417 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-14T10:22:49.190066+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-14T10:22:49.190360+00:00_

1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Long-context language models place acute pressure on the key--value (KV) cache, which grows linearly with sequence length and dominates inference memory at scale \cite{kwon2023vllm, pope2023efficiently}.
5	Two complementary responses have emerged: \emph{attention head pruning}, which removes structurally redundant heads \cite{voita2019heads, michel2019sixteen}, and \emph{KV cache eviction}, which discards low-importance token positions from the cache \cite{snapkv-neurips2024, adakv-neurips2025}.
6	Deploying both simultaneously---\emph{compound sparsity}---is attractive because the compression gains multiply, but the resulting quality degradation can be super-additive: the joint loss exceeds the sum of individual losses \cite{spark-aaai2026, slim-icml2025}.
7	
8	Prior work has characterized compound interaction as a property of the sparsity level---higher sparsity yields more interaction---but treats the interaction magnitude as roughly constant across the generation process \cite{spark-aaai2026, unicomp-2026}.
9	This assumption is problematic for reasoning-capable models, whose generations are structurally heterogeneous: a single chain-of-thought trace alternates between phases of broadly distributed attention (exploratory reasoning) and phases of sharply concentrated attention (structured computation) \cite{thinkv-iclr2026, decision-repr-transition-2026}.
10	If compound interaction severity varies across these phases, then a uniform sparsity budget---the standard deployment practice---may be safe in one phase yet destructive in another.
11	
12	We investigate whether compound sparsity severity is modulated by reasoning phase and eviction strategy.
13	Our central finding is that it is, and strongly so: under importance-based KV cache eviction, the Interaction Index---a measure of super-additive compound degradation---is concentrated in the low-sparsity phase (where attention distributes broadly) and largely abs
…[truncated 3627 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-14T10:22:49.192807+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/results.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/results.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-14T10:22:49.193278+00:00_

1	
2	\section{Results}
3	\label{sec:results}
4	
5	We present our empirical findings in five parts: strategy-dependent compound severity (\S\ref{sec:strategy-severity}), phase-modulated amplification (\S\ref{sec:phase-amplification}), the phase-strategy crossover (\S\ref{sec:crossover}), cross-model replication (\S\ref{sec:cross-model}), and statistical validation (\S\ref{sec:stat-validation}).
6	
7	
8	\subsection{Experimental Overview}
9	\label{sec:exp-overview}
10	
11	We evaluate compound sparsity on DeepSeek-R1-Distill-Qwen-7B using a 50-problem stratified subset of MATH-500 (\S\ref{sec:dataset}). For each problem, we measure perplexity under four conditions---dense, attention-only pruning, KV-only eviction, and compound (both)---at sparsity levels $s \in \{0.15, 0.20, 0.25, 0.30\}$. We compare importance-based and random eviction strategies (\S\ref{sec:sparsity-config}), and segment each generated sequence into high-, mid-, and low-sparsity reasoning phases via quantile-based attention sparsity partitioning (\S\ref{sec:phase-seg}). The interaction index (II, Eq.~\ref{eq:ii}) quantifies compound super-additivity, and the severity gradient ($G$, Eq.~\ref{eq:gradient}) captures phase-dependent amplification.
12	Models are evaluated in \texttt{bfloat16} precision (\S\ref{sec:experimental-setup}). Full experimental details appear therein.
13	
14	
15	\subsection{Strategy-Dependent Severity (C1)}
16	\label{sec:strategy-severity}
17	
18	The compound severity difference reveals a stark dependence on eviction strategy. Table~\ref{tab:aggregate-ii} reports the median compound severity difference $\Delta = \widetilde{\mathrm{II}}_{\textit{low}} - \widetilde{\mathrm{II}}_{\textit{high}}$ across 50 problems for each strategy and sparsity level. Under importance-based eviction, compound sparsity produces substantial super-additive degradation that grows with sparsity: $\Delta$ increases from $0.39$ at $s{=}0.15$ to $14.59$ at $s{=}0.30$, a $37{\times}$ amplification. Under rand
…[truncated 20029 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-14T10:22:49.193583+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/analysis.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-14T10:22:49.193904+00:00_

1	
2	\section{Analysis: Mechanisms of Phase-Modulated Severity}
3	\label{sec:analysis}
4	
5	The results in \S\ref{sec:results} reveal a striking asymmetry: importance-based eviction exhibits $69$--$274{\times}$ severity amplification in low-sparsity phases (Table~\ref{tab:main-results}), while random eviction remains flat at ${\sim}1{\times}$ across all phases. % exp_id: bf16_importance_s015..s030; G=69,103,222,274
6	Why is compound severity phase-modulated for one strategy but not the other? We identify two mechanisms. \emph{Discrimination collapse}---a systematic reduction in the discriminative power of KV importance scores under head pruning---is the primary mechanism, robustly observed across both models and all tested conditions. A secondary \emph{entropy redistribution} pattern is consistent for DeepSeek but only partially replicates on Qwen, indicating model-dependent modulation.
7	
8	\subsection{Discrimination Collapse Under Head Pruning}
9	\label{sec:discrimination-collapse}
10	
11	The KV importance score (Eq.~\ref{eq:kv-importance}) aggregates attention mass across surviving heads. When head pruning reduces the number of contributing heads, the cumulative importance distribution becomes more uniform: the gap between highly-attended and rarely-attended positions shrinks. We quantify this effect through two complementary metrics applied to the per-position importance distribution.
12	
13	The \textbf{Gini coefficient} measures inequality in the importance distribution ($\mathrm{Gini}{=}0$: perfectly uniform; $\mathrm{Gini}{=}1$: maximally concentrated). The \textbf{coefficient of variation} (CV) captures relative dispersion. A decrease in either metric after pruning indicates reduced discriminative power.
14	
15	We observe discrimination collapse across both models in all tested conditions (Table~\ref{tab:discrimination-metrics}). Under importance-based eviction, the Gini delta is negative at every sparsity level for both DeepSeek ($-0.030$ to $-0.081$) and Q
…[truncated 7728 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-14T10:22:49.194173+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-14T10:22:49.198932+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{On the predictability of phase-modulated severity.}
5	One might argue that the qualitative direction of our findings is intuitive: in low-sparsity phases, attention distributes broadly across many tokens, so importance scores carry less discriminative signal, and importance-based eviction should degrade.
6	We do not dispute this intuition.
7	The surprise lies in the quantitative structure of the interaction, which is not predictable from first principles alone.
8	
9	First, the \emph{magnitude} of the severity gradient---$69$--$274{\times}$ amplification across sparsity levels (Table~\ref{tab:main-results})---far exceeds what a naive ``less discriminative $\Rightarrow$ somewhat worse'' argument would predict. % exp_id: bf16_importance_s015..s030; source: experiment_summary_table.json; G=low/high=69,103,222,274.
10	A reviewer expecting a $2$--$3\times$ effect would find two-orders-of-magnitude amplification difficult to anticipate without measurement.
11	Second, the gradient is \emph{phase-specific}: compound interaction concentrates in low-sparsity phases while high-sparsity phases exhibit near-zero compound interaction ($\widetilde{\mathrm{II}}_{\text{high}} < 0.06$ at $s \leq 0.30$; at $s = 0.35$, high-phase II rises to 0.105, indicating the onset of compound interaction even in high-sparsity phases at extreme pruning rates). % exp_id: bf16_importance_s015..s030, bf16_ds_imp_s035; high-phase medians: 0.006, 0.015, 0.032, 0.053; s035 II_high=0.1051
12	This asymmetry means that importance-based eviction is not uniformly fragile---it is selectively fragile in a phase-dependent manner.
13	Third, and most strikingly, a \emph{crossover} emerges: at $s{=}0.25$, importance-based eviction \emph{outperforms} random eviction in high-sparsity phases (median severity $0.032$ vs.\ $0.818$) yet \emph{underperforms} in low-sparsity phases ($7.196$ vs.\ $1.363$---a ${>}5{\times}$ severity inflation relative to random).
…[truncated 13807 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 4
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-14T10:22:49.199350+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_11/projects/phase-gated-compound-sparse/artifacts/_project/paper/conclusion.tex"
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-14T10:22:49.199674+00:00_

1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	We presented an empirical investigation of how compound sparsity severity---the super-additive interaction between attention head pruning and KV cache eviction---varies across reasoning phases and eviction strategies in 7B-parameter language models. Our central finding is that compound severity is not a fixed property of the sparsity level but an emergent phase-strategy interaction whose magnitude spans over an order of magnitude within a single generation.
5	
6	Our contributions, mapped to confirmed claims, are:
7	\begin{enumerate}[nosep,leftmargin=*]
8	    \item \textbf{Strategy dependence (C1).} Compound severity depends qualitatively on the eviction strategy: importance-based eviction produces phase-modulated interaction (median phase difference $0.39$--$14.59$), while random eviction shows no significant phase modulation in 7/8 conditions (the sole exception---Qwen $s{=}0.30$, $p{=}0.012$, $d_z{=}{-}0.04$---has negligible effect size).
9	
10	    \item \textbf{Phase modulation (C2).} Under importance-based eviction, the median Interaction Index difference between low- and high-sparsity phases increases monotonically with sparsity (Bonferroni-corrected $p < 0.005$ at all four levels), with paired effect sizes growing from $d_z{=}0.44$ (small) to $d_z{=}0.80$ (large).
11	
12	    \item \textbf{Phase-strategy crossover (C3).} At $s{=}0.25$, importance-based eviction simultaneously outperforms random in high-sparsity phases ($\widetilde{\mathrm{II}} = 0.032$ vs.\ $0.818$) and underperforms in low-sparsity phases ($\widetilde{\mathrm{II}} = 7.196$ vs.\ $1.363$)---a qualitative reversal in strategy ranking.
13	
14	    \item \textbf{Sub-exponential growth (C6).} The severity gradient grows with sparsity but at a decelerating rate, suggesting a natural ceiling on phase-dependent amplification.
15	
16	    \item \textbf{Cross-model replication (C5).} The monotonic gradient replicates on Qwen2.5-7B-Instruct at $s \geq 0.2
…[truncated 2081 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-14T10:22:49.199956+00:00_

called ToolSearch

<details open><summary>🔧 Tool call — ToolSearch</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only",
  "max_results": "1"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "ToolSearch",
  "tool_args": {
    "query": "select:mcp__agent-ml-research__ssh_read_only",
    "max_results": "1"
  }
}
```

</details>

---

### Tool result

_source line 14 · 2026-05-14T10:22:49.200176+00:00_



<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "ToolSearch",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 15 · 2026-05-14T10:22:49.202508+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/experiment_summary_table.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/experiment_summary_table.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 16 · 2026-05-14T10:22:49.202829+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/cohens_d_bf16.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/cohens_d_bf16.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-14T10:22:49.203070+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"cat: /root/autodl-tmp/pacs/analysis/experiment_summary_table.json: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 1.72}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 18 · 2026-05-14T10:22:49.203290+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/cohens_d_bf16_qwen.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/cohens_d_bf16_qwen.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-14T10:22:49.203531+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"cat: /root/autodl-tmp/pacs/analysis/cohens_d_bf16.json: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.51}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-14T10:22:49.203752+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/permutation_test_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/permutation_test_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-14T10:22:49.204014+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"cat: /root/autodl-tmp/pacs/analysis/cohens_d_bf16_qwen.json: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.54}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 22 · 2026-05-14T10:22:49.204210+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"cat: /root/autodl-tmp/pacs/analysis/permutation_test_results.json: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.5}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 23 · 2026-05-14T10:22:49.206683+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/cross_model_analysis.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/cross_model_analysis.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-14T10:22:49.206943+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/bootstrap_ci_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/bootstrap_ci_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 25 · 2026-05-14T10:22:49.207175+00:00_

{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"cat: /root/autodl-tmp/pacs/analysis/cross_model_analysis.json: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.46}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 26 · 2026-05-14T10:22:49.207516+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"importance\\\": {\\n    \\\"s015\\\": {\\n      \\\"gradient\\\": 12.8187,\\n      \\\"ci_low\\\": 10.3755,\\n      \\\"ci_high\\\": 15.7738,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 2.626986,\\n      \\\"II_high_median\\\": 0.204934\\n    },\\n    \\\"s020\\\": {\\n      \\\"gradient\\\": 28.6941,\\n      \\\"ci_low\\\": 23.2095,\\n      \\\"ci_high\\\": 35.3321,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 9.562646,\\n      \\\"II_high_median\\\": 0.333262\\n    },\\n    \\\"s025\\\": {\\n      \\\"gradient\\\": 52.8791,\\n      \\\"ci_low\\\": 43.069,\\n      \\\"ci_high\\\": 64.6714,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 30.903183,\\n      \\\"II_high_median\\\": 0.584412\\n    },\\n    \\\"s030\\\": {\\n      \\\"gradient\\\": 74.8352,\\n      \\\"ci_low\\\": 52.4935,\\n      \\\"ci_high\\\": 105.2683,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 44.632448,\\n      \\\"II_high_median\\\": 0.59641\\n    }\\n  },\\n  \\\"random\\\": {\\n    \\\"s015\\\": {\\n      \\\"gradient\\\": 1.1398,\\n      \\\"ci_low\\\": 0.9055,\\n      \\\"ci_high\\\": 1.4358,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 0.183077,\\n      \\\"II_high_median\\\": 0.160628\\n    },\\n    \\\"s025\\\": {\\n      \\\"gradient\\\": 0.9708,\\n      \\\"ci_low\\\": 0.8608,\\n      \\\"ci_high\\\": 1.0951,\\n      \\\"n_segments\\\": 965,\\n      \\\"n_low\\\": 454,\\n      \\\"n_high\\\": 511,\\n      \\\"II_low_median\\\": 2.914616,\\n      \\\"II_high_median\\\": 3.002378\\n    }\\n  },\\n  \\\"comparison\\\": {\\n    \\\"importance_gradient_t
…[truncated 568 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 27 · 2026-05-14T10:22:49.207839+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "find /root/autodl-tmp/pacs/analysis/ -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "find /root/autodl-tmp/pacs/analysis/ -name \"*.json\" -type f",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 28 · 2026-05-14T10:22:49.208082+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/pacs/analysis/bootstrap_ci_results.json\\n/root/autodl-tmp/pacs/analysis/bootstrap_gradient_results.json\\n/root/autodl-tmp/pacs/analysis/bootstrap_results_full.json\\n/root/autodl-tmp/pacs/analysis/v6_analysis_results.json\\n/root/autodl-tmp/pacs/analysis/mid_sparsity_gap_raw.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.44}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 29 · 2026-05-14T10:22:49.208334+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "find /root/autodl-tmp/pacs/ -name \"experiment_summary_table*\" -o -name \"cohens_d*\" -o -name \"permutation_test*\" -o -name \"cross_model*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "find /root/autodl-tmp/pacs/ -name \"experiment_summary_table*\" -o -name \"cohens_d*\" -o -name \"permutation_test*\" -o -name \"cross_model*\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-14T10:22:49.210707+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/pacs/paper/figures/cohens_d_6point.pdf\\n/root/autodl-tmp/pacs/paper/figures/cohens_d_6point.png\\n/root/autodl-tmp/pacs/pacs/analysis/permutation_test.py\\n/root/autodl-tmp/pacs/pacs/analysis/__pycache__/permutation_test.cpython-312.pyc\\n/root/autodl-tmp/pacs/analysis/cross_model_analysis.py\\n/root/autodl-tmp/pacs/artifacts/permutation_test_median_verification.json\\n/root/autodl-tmp/pacs/figures/cohens_d_6point.pdf\\n/root/autodl-tmp/pacs/figures/cohens_d_6point.png\\n/root/autodl-tmp/pacs/analysis_output/permutation_test_results.json\\n/root/autodl-tmp/pacs/analysis_output/cohens_d_bf16.json\\n/root/autodl-tmp/pacs/analysis_output/cohens_d_bf16_qwen.json\\n/root/autodl-tmp/pacs/analysis_output/cross_model_analysis.json\\n/root/autodl-tmp/pacs/analysis_output/experiment_summary_table.json\\n/root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000.json\\n/root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000_6point.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 2
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-14T10:22:49.210998+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/experiment_summary_table.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/experiment_summary_table.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 32 · 2026-05-14T10:22:49.211476+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"description\\\": \\\"4x4 experiment summary: 2 models x 2 masking methods x 4 sparsity levels\\\",\\n  \\\"models\\\": [\\n    \\\"DeepSeek-R1-Distill-Qwen-7B\\\",\\n    \\\"Qwen2.5-7B-Instruct\\\"\\n  ],\\n  \\\"masking_methods\\\": [\\n    \\\"importance\\\",\\n    \\\"random\\\"\\n  ],\\n  \\\"sparsity_levels\\\": [\\n    \\\"s015\\\",\\n    \\\"s020\\\",\\n    \\\"s025\\\",\\n    \\\"s030\\\"\\n  ],\\n  \\\"experiments\\\": {\\n    \\\"bf16_importance_s015\\\": {\\n      \\\"median_high\\\": 0.005752,\\n      \\\"median_mid\\\": 0.080738,\\n      \\\"median_low\\\": 0.398291,\\n      \\\"median_diff\\\": 0.392539,\\n      \\\"pass_fail\\\": \\\"PASS\\\",\\n      \\\"model\\\": \\\"DeepSeek-R1-Distill-Qwen-7B\\\",\\n      \\\"masking\\\": \\\"importance\\\",\\n      \\\"sparsity\\\": 0.15,\\n      \\\"cohens_d_imp_vs_rand\\\": 0.4416,\\n      \\\"cohens_d_interpretation\\\": \\\"small\\\",\\n      \\\"permutation_p_diff\\\": 0.0007999200079992001\\n    },\\n    \\\"bf16_importance_s020\\\": {\\n      \\\"median_high\\\": 0.014513,\\n      \\\"median_mid\\\": 0.202695,\\n      \\\"median_low\\\": 1.496254,\\n      \\\"median_diff\\\": 1.481741,\\n      \\\"pass_fail\\\": \\\"PASS\\\",\\n      \\\"model\\\": \\\"DeepSeek-R1-Distill-Qwen-7B\\\",\\n      \\\"masking\\\": \\\"importance\\\",\\n      \\\"sparsity\\\": 0.2,\\n      \\\"cohens_d_imp_vs_rand\\\": 0.5195,\\n      \\\"cohens_d_interpretation\\\": \\\"medium\\\",\\n      \\\"permutation_p_diff\\\": 0.00019998000199980003\\n    },\\n    \\\"bf16_importance_s025\\\": {\\n      \\\"median_high\\\": 0.032363,\\n      \\\"median_mid\\\": 1.118069,\\n      \\\"median_low\\\": 7.195958,\\n      \\\"median_diff\\\": 7.163595,\\n      \\\"pass_fail\\\": \\\"PASS\\\",\\n      \\\"model\\\": \\\"DeepSeek-R1-Distill-Qwen-7B\\\",\\n      \\\"masking\\\": \\\"importance\\\",\\n      \\\"sparsity\\\": 0.25,\\n      \\\"cohens_d_imp_vs_rand\\\": 0.6831,\\n   
…[truncated 6946 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 33 · 2026-05-14T10:22:49.211762+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_bf16.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_bf16.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 34 · 2026-05-14T10:22:49.212052+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"s015\\\": {\\n    \\\"d\\\": 0.4416,\\n    \\\"ci_low\\\": 0.3548,\\n    \\\"ci_high\\\": 0.7836,\\n    \\\"n\\\": 49,\\n    \\\"n_skipped\\\": 1,\\n    \\\"mean_diff\\\": 0.756804,\\n    \\\"std_diff\\\": 1.713645,\\n    \\\"interpretation\\\": \\\"small\\\"\\n  },\\n  \\\"s020\\\": {\\n    \\\"d\\\": 0.5195,\\n    \\\"ci_low\\\": 0.4319,\\n    \\\"ci_high\\\": 0.9011,\\n    \\\"n\\\": 49,\\n    \\\"n_skipped\\\": 1,\\n    \\\"mean_diff\\\": 2.281612,\\n    \\\"std_diff\\\": 4.391892,\\n    \\\"interpretation\\\": \\\"medium\\\"\\n  },\\n  \\\"s025\\\": {\\n    \\\"d\\\": 0.6831,\\n    \\\"ci_low\\\": 0.5576,\\n    \\\"ci_high\\\": 0.8634,\\n    \\\"n\\\": 49,\\n    \\\"n_skipped\\\": 1,\\n    \\\"mean_diff\\\": 11.386171,\\n    \\\"std_diff\\\": 16.667836,\\n    \\\"interpretation\\\": \\\"medium\\\"\\n  },\\n  \\\"s030\\\": {\\n    \\\"d\\\": 0.8031,\\n    \\\"ci_low\\\": 0.6659,\\n    \\\"ci_high\\\": 1.0191,\\n    \\\"n\\\": 49,\\n    \\\"n_skipped\\\": 1,\\n    \\\"mean_diff\\\": 22.939045,\\n    \\\"std_diff\\\": 28.561912,\\n    \\\"interpretation\\\": \\\"large\\\"\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.46}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 35 · 2026-05-14T10:22:49.212289+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_bf16_qwen.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_bf16_qwen.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 36 · 2026-05-14T10:22:49.214654+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"model\\\": \\\"Qwen2.5-7B-Instruct\\\",\\n  \\\"s015\\\": {\\n    \\\"d\\\": 0.2811,\\n    \\\"ci_low\\\": -0.0063,\\n    \\\"ci_high\\\": 0.5967,\\n    \\\"n\\\": 46,\\n    \\\"n_skipped\\\": 4,\\n    \\\"mean_diff\\\": 0.081723,\\n    \\\"std_diff\\\": 0.290711,\\n    \\\"interpretation\\\": \\\"small\\\"\\n  },\\n  \\\"s020\\\": {\\n    \\\"d\\\": 0.5494,\\n    \\\"ci_low\\\": 0.2263,\\n    \\\"ci_high\\\": 1.0204,\\n    \\\"n\\\": 46,\\n    \\\"n_skipped\\\": 4,\\n    \\\"mean_diff\\\": 0.282519,\\n    \\\"std_diff\\\": 0.514196,\\n    \\\"interpretation\\\": \\\"medium\\\"\\n  },\\n  \\\"s025\\\": {\\n    \\\"d\\\": 0.8894,\\n    \\\"ci_low\\\": 0.6906,\\n    \\\"ci_high\\\": 1.1981,\\n    \\\"n\\\": 46,\\n    \\\"n_skipped\\\": 4,\\n    \\\"mean_diff\\\": 1.51605,\\n    \\\"std_diff\\\": 1.704563,\\n    \\\"interpretation\\\": \\\"large\\\"\\n  },\\n  \\\"s030\\\": {\\n    \\\"d\\\": 1.022,\\n    \\\"ci_low\\\": 0.8639,\\n    \\\"ci_high\\\": 1.3275,\\n    \\\"n\\\": 46,\\n    \\\"n_skipped\\\": 4,\\n    \\\"mean_diff\\\": 4.01389,\\n    \\\"std_diff\\\": 3.927559,\\n    \\\"interpretation\\\": \\\"large\\\"\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 2
}
```

</details>

---

### Tool call

_source line 37 · 2026-05-14T10:22:49.214932+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool call

_source line 38 · 2026-05-14T10:22:49.215130+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/cross_model_analysis.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/cross_model_analysis.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 39 · 2026-05-14T10:22:49.215598+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"description\\\": \\\"Paired permutation test: importance vs random masking II gradients\\\",\\n  \\\"config\\\": {\\n    \\\"seed\\\": 42,\\n    \\\"n_permutations\\\": 10000,\\n    \\\"epsilon\\\": 0.01,\\n    \\\"statistics\\\": [\\n      \\\"ratio\\\",\\n      \\\"difference\\\"\\n    ],\\n    \\\"primary_statistic\\\": \\\"median\\\",\\n    \\\"auxiliary_statistic\\\": \\\"mean\\\"\\n  },\\n  \\\"sparsity_levels\\\": {\\n    \\\"s015\\\": {\\n      \\\"n_problems_importance\\\": 50,\\n      \\\"n_problems_random\\\": 50,\\n      \\\"n_common\\\": 50,\\n      \\\"n_filtered_eps\\\": 17,\\n      \\\"n_paired\\\": 32,\\n      \\\"importance_gradient_median\\\": 0.596768832028174,\\n      \\\"importance_gradient_mean\\\": 9.787015626368108,\\n      \\\"importance_gradient_std\\\": 43.53400222124559,\\n      \\\"random_gradient_median\\\": 0.5565379302334723,\\n      \\\"random_gradient_mean\\\": 0.9930012122830651,\\n      \\\"random_gradient_std\\\": 3.1961680899723275,\\n      \\\"gradient_ratio\\\": 1.0722877985653636,\\n      \\\"gradient_ratio_mean\\\": 9.85599564764501,\\n      \\\"permutation_test\\\": {\\n        \\\"statistic\\\": \\\"ratio\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 0.23465156166529522,\\n        \\\"p_value\\\": 0.8704129587041296,\\n        \\\"ci_95_low\\\": -2.7500759776627635,\\n        \\\"ci_95_high\\\": 5.508591798034095,\\n        \\\"observed_mean_diff\\\": 8.794014414085042,\\n        \\\"p_value_mean\\\": 0.2920707929207079,\\n        \\\"bonferroni_p\\\": 1.0,\\n        \\\"bonferroni_p_mean\\\": 1.0\\n      },\\n      \\\"wilcoxon_test\\\": {\\n        \\\"statistic\\\": 237.0,\\n        \\\"p_value\\\": 0.6247301651164889,\\n        \\\"effect_size_r\\\": 0.08924949315246573\\n      },\\n      \\\"n_paired_difference\\\": 49,\\n      \\\"importance_difference_median\\\": 0.35075673366298554,\\n      \\\"importance_diff
…[truncated 7844 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool result

_source line 40 · 2026-05-14T10:22:49.216031+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"description\\\": \\\"Cross-model analysis: concordance of compound interaction severity across DeepSeek-R1-Distill-Qwen-7B and Qwen2.5-7B-Instruct\\\",\\n  \\\"note\\\": \\\"cross-model (shared Qwen2ForCausalLM architecture), not cross-architecture\\\",\\n  \\\"importance_median_diffs\\\": {\\n    \\\"deepseek\\\": {\\n      \\\"s015\\\": 0.392539,\\n      \\\"s020\\\": 1.481741,\\n      \\\"s025\\\": 7.163595,\\n      \\\"s030\\\": 14.586064\\n    },\\n    \\\"qwen\\\": {\\n      \\\"s015\\\": 0.038565,\\n      \\\"s020\\\": 0.234979,\\n      \\\"s025\\\": 1.267732,\\n      \\\"s030\\\": 2.943093\\n    }\\n  },\\n  \\\"random_median_diffs\\\": {\\n    \\\"deepseek\\\": {\\n      \\\"s015\\\": 0.009572,\\n      \\\"s020\\\": -0.01555,\\n      \\\"s025\\\": 0.544512,\\n      \\\"s030\\\": 1.538314\\n    },\\n    \\\"qwen\\\": {\\n      \\\"s015\\\": 0.04971,\\n      \\\"s020\\\": 0.128948,\\n      \\\"s025\\\": 0.659798,\\n      \\\"s030\\\": 2.418272\\n    }\\n  },\\n  \\\"cohens_d_trend\\\": {\\n    \\\"deepseek\\\": {\\n      \\\"s015\\\": 0.4416,\\n      \\\"s020\\\": 0.5195,\\n      \\\"s025\\\": 0.6831,\\n      \\\"s030\\\": 0.8031\\n    },\\n    \\\"qwen\\\": {\\n      \\\"s015\\\": 0.2811,\\n      \\\"s020\\\": 0.5494,\\n      \\\"s025\\\": 0.8894,\\n      \\\"s030\\\": 1.022\\n    },\\n    \\\"deepseek_monotonic\\\": {\\n      \\\"monotonic_increasing\\\": true,\\n      \\\"strictly_increasing\\\": true\\n    },\\n    \\\"qwen_monotonic\\\": {\\n      \\\"monotonic_increasing\\\": true,\\n      \\\"strictly_increasing\\\": true\\n    },\\n    \\\"spearman_rho\\\": 1.0,\\n    \\\"spearman_p\\\": 0.0\\n  },\\n  \\\"importance_monotonicity\\\": {\\n    \\\"deepseek\\\": {\\n      \\\"monotonic_increasing\\\": true,\\n      \\\"strictly_increasing\\\": true\\n    },\\n    \\\"qwen\\\": {\\n      \\\"monotonic_increasing\\\": true,\\n      \\\"strictly_increasing\\\": true\\n    }\\n  },\\n  \\\"ra
…[truncated 3193 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 41 · 2026-05-14T10:22:49.216343+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "python3 -c \"import json; d=json.load(open('/root/autodl-tmp/pacs/analysis_output/permutation_test_results.json')); p=d['sparsity_levels']['s020']['permutation_test_difference']; print(json.dumps(p, indent=2))\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "python3 -c \"import json; d=json.load(open('/root/autodl-tmp/pacs/analysis_output/permutation_test_results.json')); p=d['sparsity_levels']['s020']['permutation_test_difference']; print(json.dumps(p, indent=2))\"",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 42 · 2026-05-14T10:22:49.218717+00:00_

{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 2
}
```

</details>

---

### Tool call

_source line 43 · 2026-05-14T10:22:49.218967+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 44 · 2026-05-14T10:22:49.219237+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"method\\\": \\\"per-problem Cohen d (ii_low vs ii_high), bootstrap CI B=10000\\\",\\n  \\\"deepseek\\\": {\\n    \\\"s015\\\": {\\n      \\\"d\\\": 0.606769,\\n      \\\"ci_lo\\\": 0.4787,\\n      \\\"ci_hi\\\": 1.0404\\n    },\\n    \\\"s020\\\": {\\n      \\\"d\\\": 0.725045,\\n      \\\"ci_lo\\\": 0.5969,\\n      \\\"ci_hi\\\": 1.2356\\n    },\\n    \\\"s025\\\": {\\n      \\\"d\\\": 0.953449,\\n      \\\"ci_lo\\\": 0.7739,\\n      \\\"ci_hi\\\": 1.2056\\n    },\\n    \\\"s030\\\": {\\n      \\\"d\\\": 1.126291,\\n      \\\"ci_lo\\\": 0.9308,\\n      \\\"ci_hi\\\": 1.4185\\n    }\\n  },\\n  \\\"qwen\\\": {\\n    \\\"s015\\\": {\\n      \\\"d\\\": 0.37054,\\n      \\\"ci_lo\\\": -0.0279,\\n      \\\"ci_hi\\\": 0.7776,\\n      \\\"marginal\\\": true\\n    },\\n    \\\"s020\\\": {\\n      \\\"d\\\": 0.722424,\\n      \\\"ci_lo\\\": 0.2786,\\n      \\\"ci_hi\\\": 1.3411,\\n      \\\"marginal\\\": false\\n    },\\n    \\\"s025\\\": {\\n      \\\"d\\\": 1.232921,\\n      \\\"ci_lo\\\": 0.9571,\\n      \\\"ci_hi\\\": 1.6499,\\n      \\\"marginal\\\": false\\n    },\\n    \\\"s030\\\": {\\n      \\\"d\\\": 1.439424,\\n      \\\"ci_lo\\\": 1.2167,\\n      \\\"ci_hi\\\": 1.8673,\\n      \\\"marginal\\\": false\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 45 · 2026-05-14T10:22:49.219514+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "grep -A 20 \"s020\" /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "grep -A 20 \"s020\" /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 46 · 2026-05-14T10:22:49.219761+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"    \\\"s020\\\": {\\n      \\\"n_problems_importance\\\": 50,\\n      \\\"n_problems_random\\\": 50,\\n      \\\"n_common\\\": 50,\\n      \\\"n_filtered_eps\\\": 11,\\n      \\\"n_paired\\\": 38,\\n      \\\"importance_gradient_median\\\": 11.676684977968467,\\n      \\\"importance_gradient_mean\\\": 25.6617110440837,\\n      \\\"importance_gradient_std\\\": 111.99765730889607,\\n      \\\"random_gradient_median\\\": 0.8380166571731968,\\n      \\\"random_gradient_mean\\\": 3.145713409754399,\\n      \\\"random_gradient_std\\\": 12.005068047794579,\\n      \\\"gradient_ratio\\\": 13.933714655930988,\\n      \\\"gradient_ratio_mean\\\": 8.157676082160082,\\n      \\\"permutation_test\\\": {\\n        \\\"statistic\\\": \\\"ratio\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 11.795171331924799,\\n        \\\"p_value\\\": 0.0734926507349265,\\n        \\\"ci_95_low\\\": -3.9243610036966072,\\n        \\\"ci_95_high\\\": 45.25946663746516,\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.47}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 47 · 2026-05-14T10:22:49.220018+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000_6point.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/cohens_d_paired_b10000_6point.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 48 · 2026-05-14T10:22:49.220276+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"method\\\": \\\"per-problem Cohen d (ii_low vs ii_high), bootstrap B=10000\\\",\\n  \\\"deepseek\\\": {\\n    \\\"s010\\\": {\\n      \\\"d\\\": 0.503977,\\n      \\\"marginal\\\": true,\\n      \\\"note\\\": \\\"median_diff CI includes 0, perm_p=0.15\\\"\\n    },\\n    \\\"s015\\\": {\\n      \\\"d\\\": 0.606769\\n    },\\n    \\\"s020\\\": {\\n      \\\"d\\\": 0.725045\\n    },\\n    \\\"s025\\\": {\\n      \\\"d\\\": 0.953449\\n    },\\n    \\\"s030\\\": {\\n      \\\"d\\\": 1.126291\\n    },\\n    \\\"s035\\\": {\\n      \\\"d\\\": 1.145462\\n    }\\n  },\\n  \\\"qwen\\\": {\\n    \\\"s010\\\": {\\n      \\\"d\\\": -0.063647,\\n      \\\"note\\\": \\\"d<0, importance slightly worse than random at s=0.10\\\"\\n    },\\n    \\\"s015\\\": {\\n      \\\"d\\\": 0.37054,\\n      \\\"marginal\\\": true,\\n      \\\"note\\\": \\\"median_diff CI includes 0\\\"\\n    },\\n    \\\"s020\\\": {\\n      \\\"d\\\": 0.722424\\n    },\\n    \\\"s025\\\": {\\n      \\\"d\\\": 1.232921\\n    },\\n    \\\"s030\\\": {\\n      \\\"d\\\": 1.439424\\n    },\\n    \\\"s035\\\": {\\n      \\\"d\\\": 1.544366\\n    }\\n  }\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 49 · 2026-05-14T10:22:49.222658+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "grep -A 10 \"permutation_test_difference\" /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "grep -A 10 \"permutation_test_difference\" /root/autodl-tmp/pacs/analysis_output/permutation_test_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 50 · 2026-05-14T10:22:49.222960+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"      \\\"permutation_test_difference\\\": {\\n        \\\"statistic\\\": \\\"difference\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 0.36782994048141904,\\n        \\\"p_value\\\": 0.0007999200079992001,\\n        \\\"ci_95_low\\\": 0.18715387629447566,\\n        \\\"ci_95_high\\\": 0.6231596244200248,\\n        \\\"observed_mean_diff\\\": 2.9120728811672767,\\n        \\\"p_value_mean\\\": 9.999000099990002e-05,\\n        \\\"bonferroni_p\\\": 0.0031996800319968005,\\n        \\\"bonferroni_p_mean\\\": 0.00039996000399960006\\n--\\n      \\\"permutation_test_difference\\\": {\\n        \\\"statistic\\\": \\\"difference\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 0.9651554485592588,\\n        \\\"p_value\\\": 0.00019998000199980003,\\n        \\\"ci_95_low\\\": 0.6889939139581746,\\n        \\\"ci_95_high\\\": 1.492634259272749,\\n        \\\"observed_mean_diff\\\": 3.8261187124945497,\\n        \\\"p_value_mean\\\": 0.00029997000299970003,\\n        \\\"bonferroni_p\\\": 0.0007999200079992001,\\n        \\\"bonferroni_p_mean\\\": 0.0011998800119988001\\n--\\n      \\\"permutation_test_difference\\\": {\\n        \\\"statistic\\\": \\\"difference\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 3.3362211771301897,\\n        \\\"p_value\\\": 0.00019998000199980003,\\n        \\\"ci_95_low\\\": 1.6615969526524204,\\n        \\\"ci_95_high\\\": 6.636183397132511,\\n        \\\"observed_mean_diff\\\": 14.25540462324718,\\n        \\\"p_value_mean\\\": 9.999000099990002e-05,\\n        \\\"bonferroni_p\\\": 0.0007999200079992001,\\n        \\\"bonferroni_p_mean\\\": 0.00039996000399960006\\n--\\n      \\\"permutation_test_difference\\\": {\\n        \\\"statistic\\\": \\\"difference\\\",\\n        \\\"n_permutations\\\": 10000,\\n        \\\"observed_median_diff\\\": 9.852666623213569,\\n        \\
…[truncated 472 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 51 · 2026-05-14T10:22:49.223259+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis/bootstrap_results_full.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis/bootstrap_results_full.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 52 · 2026-05-14T10:22:49.223729+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"per_strategy\\\": {\\n    \\\"importance\\\": {\\n      \\\"0.15\\\": {\\n        \\\"gradient\\\": 14.2728,\\n        \\\"gradient_95ci\\\": [\\n          12.1182,\\n          17.4163\\n        ],\\n        \\\"mann_whitney_U\\\": {\\n          \\\"U\\\": 215044.0,\\n          \\\"p\\\": 2.97805594692458e-116,\\n          \\\"r_rb\\\": -0.8539\\n        },\\n        \\\"cohens_d\\\": 0.7073,\\n        \\\"phase_medians\\\": {\\n          \\\"high\\\": 0.207262,\\n          \\\"mid\\\": 0.716574,\\n          \\\"low\\\": 2.958196\\n        },\\n        \\\"phase_means\\\": {\\n          \\\"high\\\": 0.311765,\\n          \\\"mid\\\": 1.3052,\\n          \\\"low\\\": 8.851299\\n        },\\n        \\\"pairwise_tests\\\": {\\n          \\\"low vs mid\\\": {\\n            \\\"U\\\": 136674.0,\\n            \\\"p\\\": 8.498644032990309e-42,\\n            \\\"r_rb\\\": -0.5399\\n          },\\n          \\\"mid vs high\\\": {\\n            \\\"U\\\": 163644.0,\\n            \\\"p\\\": 1.0024964735227983e-60,\\n            \\\"r_rb\\\": -0.6381\\n          },\\n          \\\"low vs high\\\": {\\n            \\\"U\\\": 215044.0,\\n            \\\"p\\\": 2.97805594692458e-116,\\n            \\\"r_rb\\\": -0.8539\\n          }\\n        },\\n        \\\"pairwise_cohens_d\\\": {\\n          \\\"low vs mid\\\": 0.5823,\\n          \\\"mid vs high\\\": 0.812,\\n          \\\"low vs high\\\": 0.7073\\n        }\\n      },\\n      \\\"0.2\\\": {\\n        \\\"gradient\\\": 30.8526,\\n        \\\"gradient_95ci\\\": [\\n          25.2851,\\n          41.2825\\n        ],\\n        \\\"mann_whitney_U\\\": {\\n          \\\"U\\\": 226011.0,\\n          \\\"p\\\": 5.884220586697296e-143,\\n          \\\"r_rb\\\": -0.9484\\n        },\\n        \\\"cohens_d\\\": 0.4916,\\n        \\\"phase_medians\\\": {\\n          \\\"high\\\": 0.352513,\\n          \\\"mid\\\": 1.51018,\\n          \\\"low\\\": 10.875949\\n        }
…[truncated 7773 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 53 · 2026-05-14T10:22:49.224098+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "find /root/autodl-tmp/pacs/ -name \"*bootstrap*\" -name \"*.json\" -type f",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "find /root/autodl-tmp/pacs/ -name \"*bootstrap*\" -name \"*.json\" -type f",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 54 · 2026-05-14T10:22:49.224346+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/pacs/analysis/bootstrap_ci_results.json\\n/root/autodl-tmp/pacs/analysis/bootstrap_gradient_results.json\\n/root/autodl-tmp/pacs/analysis/bootstrap_results_full.json\\n/root/autodl-tmp/pacs/analysis_output/rebootstrap_b10000_results.json\\n/root/autodl-tmp/pacs/results/rebootstrap_analysis/rebootstrap_results.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 55 · 2026-05-14T10:22:49.226711+00:00_

called mcp__agent-ml-research__ssh_read_only

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only</summary>

```json
{
  "server": "westd-22162",
  "command": "cat /root/autodl-tmp/pacs/analysis_output/rebootstrap_b10000_results.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "tool_args": {
    "server": "westd-22162",
    "command": "cat /root/autodl-tmp/pacs/analysis_output/rebootstrap_b10000_results.json",
    "account": "root"
  }
}
```

</details>

---

### Tool result

_source line 56 · 2026-05-14T10:22:49.227034+00:00_

{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"bf16_ds_imp_s015\\\": {\\n    \\\"model\\\": \\\"DeepSeek\\\",\\n    \\\"sparsity\\\": \\\"0.15\\\",\\n    \\\"old_n_bootstrap\\\": 1000,\\n    \\\"new_n_bootstrap\\\": 10000,\\n    \\\"n_paired\\\": 49,\\n    \\\"median_diff\\\": 0.323579,\\n    \\\"permutation_p\\\": 0.0,\\n    \\\"cohens_d\\\": 0.606769,\\n    \\\"bootstrap_ci_95\\\": [\\n      0.198824,\\n      0.471566\\n    ],\\n    \\\"wilcoxon_p\\\": 0.0\\n  },\\n  \\\"bf16_ds_imp_s020\\\": {\\n    \\\"model\\\": \\\"DeepSeek\\\",\\n    \\\"sparsity\\\": \\\"0.2\\\",\\n    \\\"old_n_bootstrap\\\": 1000,\\n    \\\"new_n_bootstrap\\\": 10000,\\n    \\\"n_paired\\\": 49,\\n    \\\"median_diff\\\": 1.15202,\\n    \\\"permutation_p\\\": 0.0,\\n    \\\"cohens_d\\\": 0.725045,\\n    \\\"bootstrap_ci_95\\\": [\\n      0.655454,\\n      1.256001\\n    ],\\n    \\\"wilcoxon_p\\\": 0.0\\n  },\\n  \\\"bf16_ds_imp_s025\\\": {\\n    \\\"model\\\": \\\"DeepSeek\\\",\\n    \\\"sparsity\\\": \\\"0.25\\\",\\n    \\\"old_n_bootstrap\\\": 1000,\\n    \\\"new_n_bootstrap\\\": 10000,\\n    \\\"n_paired\\\": 49,\\n    \\\"median_diff\\\": 3.968568,\\n    \\\"permutation_p\\\": 0.0,\\n    \\\"cohens_d\\\": 0.953449,\\n    \\\"bootstrap_ci_95\\\": [\\n      2.829037,\\n      5.291756\\n    ],\\n    \\\"wilcoxon_p\\\": 0.0\\n  },\\n  \\\"bf16_ds_imp_s030\\\": {\\n    \\\"model\\\": \\\"DeepSeek\\\",\\n    \\\"sparsity\\\": \\\"0.3\\\",\\n    \\\"old_n_bootstrap\\\": 1000,\\n    \\\"new_n_bootstrap\\\": 10000,\\n    \\\"n_paired\\\": 49,\\n    \\\"median_diff\\\": 9.943595,\\n    \\\"permutation_p\\\": 0.0,\\n    \\\"cohens_d\\\": 1.126291,\\n    \\\"bootstrap_ci_95\\\": [\\n      8.391554,\\n      16.652865\\n    ],\\n    \\\"wilcoxon_p\\\": 0.0\\n  },\\n  \\\"bf16_qw_imp_s015\\\": {\\n    \\\"model\\\": \\\"Qwen\\\",\\n    \\\"sparsity\\\": \\\"0.15\\\",\\n    \\\"old_n_bootstrap\\\": 1000,\\n    \\\"new_n_bootstrap\\\": 10000,\\n    \\\"n_paired\\\": 46,\\n    \\\"me
…[truncated 1602 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_paper_number_consistency_audit_20260514T101321",
  "tool": "mcp__agent-ml-research__ssh_read_only",
  "elapsed_ms": 0
}
```

</details>

---
