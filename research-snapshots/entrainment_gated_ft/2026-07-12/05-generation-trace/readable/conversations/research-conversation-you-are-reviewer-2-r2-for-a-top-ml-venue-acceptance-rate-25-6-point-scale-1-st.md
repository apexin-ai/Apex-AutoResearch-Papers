# Research conversation: You are Reviewer 2 (R2) for a top ML venue (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 2=Reject, 3=Weak Rejec

**Aggregate Equivalence̸=Behavioral Equivalence: Per-Example Multiplicity in Hybrid Linear Recurrent Models (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 26
- **Recorded user turns:** 1
- **Tool calls:** 11
- **Original source:** `logs/chats/exported-trajectories/account-3/agent-a69bd62d2c8fcf417.jsonl`
- **Structured JSON:** [`30e32ee63cad6e2be645.json`](../../sessions/30/30e32ee63cad6e2be645.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

26 recorded events

### User

_source line 1 · 2026-05-16T02:54:20.552Z_

You are Reviewer 2 (R2) for a top ML venue (acceptance rate ~25%, 6-point scale: 1=Strong Reject, 2=Reject, 3=Weak Reject, 4=Weak Accept, 5=Accept, 6=Strong Accept).

Your focus: **Novelty and Related Work**.

## Paper Summary

Title: "Compounding Failures in Per-Head KV Cache Quantization: An Empirical Analysis of When Non-Uniform Allocation Helps"

The paper studies per-head mixed-precision KV cache quantization on hardware-aligned bit-widths {2,4,8,16}. Three contributions claimed:
1. Compounding effect characterization: first quantitative mapping of 2-bit compounding in per-head KV cache quantization
2. Cardinality constraint as universal fix: ≤k heads at 2-bit prevents compounding, makes solver choice irrelevant
3. When does non-uniform help: only 1/8 architectures benefits at 4× compression; 2-metric diagnostic (9/9 correct)

## Full Paper Content

### Abstract
Per-head mixed-precision KV cache quantization promises better quality-compression tradeoffs than uniform bit-width assignment. On hardware-aligned {2,4,8,16}, 2-bit distortions compound non-additively through the residual stream, causing all tested unconstrained solvers to over-allocate 2-bit heads and underperform uniform 4-bit across 8 diverse architectures (degradation 1.07×–3.31×). A simple cardinality constraint (≤k heads at 2-bit) prevents compounding across all tested architectures. Constrained greedy and MCKP produce identical bit allocations (Δ=0.0000). Under 4× compression, only 1/8 architectures benefits from non-uniform allocation. A 2-metric diagnostic (9/9 correct) gives practitioners a simple check. At 8× compression, constraint reduces degradation from 45.9× to 5.9× on Qwen2.5-7B.

### Introduction
- KV cache is bottleneck for long-context LLM serving
- Per-head mixed-precision proposed to improve quality-compression tradeoff
- Hardware supports only {2,4,8,16} — large gap between 2 and 4
- Discovery: 2-bit distortions compound non-additively; per-head profiling predicts PPL~11 but actual is 32-37 (3× error)
- All unconstrained solvers over-allocate 2-bit, worse than uniform 4-bit across all 8 architectures

Three contributions:
1. Compounding effect characterization — "first quantitative mapping"
2. Cardinality constraint — "universal fix" (with qualifier "across all tested architectures")
3. When non-uniform helps — 1/8 architectures, diagnostic 9/9 correct

Differentiation from RateQuant: (a) RateQuant on consecutive {2,...,6} with polymatroid structure; here {2,4,8,16} breaks it; (b) RateQuant acknowledges compounding in Appendix M but doesn't characterize or fix; (c) first systematic study of when non-uniform helps

### Related Work (Section 2)
- **KV Cache Quantization**: KIVI [2] (uniform per-channel, asymmetric K/V), KVQuant [1] (per-channel sensitivity-aware, non-uniform codebooks), QAQ [3] (attention-aware, quality-adaptive)
- **Mixed-Precision Allocation**: RateQuant [4] (rate-distortion formulation, continuous closed-form + discrete greedy, provably optimal on consecutive integers; on non-consecutive {2,4,8,16} polymatroid breaks; acknowledges compounding in Appendix M but no characterization/mitigation)
- **Compounding Effects**: Non-additive error accumulation known in weight quantization [5], but per-head KV cache compounding through residual stream not systematically studied

Only 5 references cited.

### Method (Section 3)
- MCKP formulation with cardinality constraint ∑1[b_h=2] ≤ k
- Per-head sensitivity profiling (distortion delta)
- Applicability diagnostic: top-5% concentration ≳0.50 AND t1/t5 ≲0.70

### Key Results
- Table 1: Compounding sweep on Qwen2.5-7B showing superlinear growth
- Table 2: Cross-architecture — only Qwen benefits (+27.3%), Llama +0.2%, Mistral −0.5%
- Table 4: Solver equivalence — constrained greedy = constrained MCKP (identical allocations)
- Table 6: Budget sweep — benefit amplifies with compression (0% at 2×, 29.4% at 4×, 45.9× at 8×)
- Table 13: Downstream — only Qwen positive (+2.60pp); Yi −0.77pp, Llama −0.99pp, Mistral −0.48pp, Gemma-2 +0.14pp
- Table 14: Runtime — 8.5% throughput overhead for mixed-precision

### Limitations (stated)
- 7B-14B scale only
- Multi-seed CI incomplete
- 8.5% throughput overhead
- Diagnostic from n=9

## Review Context (for understanding novelty claims)

Key context from review planning:
- RateQuant Appendix M already acknowledges compounding → novelty discount
- Compounding observation valued as empirical contribution but not novel discovery
- Constraint viewed by some as "obvious hyperparameter tuning" rather than principled contribution
- 1/8 downstream benefit seen as "this only works on Qwen"
- Diagnostic n=9 only observation, not independent claim
- Paper needs reframing as empirical analysis paper
- Solver equivalence is the strongest single experiment — proves "constraint is the contribution, not the solver"
- But this raises: "if a simple cardinality constraint is all you need, is that sufficient contribution for a main conference paper?"

## Your Review Task

Evaluate the paper on:
1. **Novelty**: How novel are the contributions relative to prior work, especially RateQuant? Is the compounding characterization truly "first"? Is the cardinality constraint a genuine contribution or hyperparameter tuning?
2. **Related work completeness**: Are important baselines and prior work missing? Is the differentiation from RateQuant fair and accurate?
3. **Contribution significance**: Is the paper's contribution sufficient for a top venue? Is it an analysis paper or a methods paper?
4. **Framing and positioning**: Is the paper honestly positioned? Are claims appropriately scoped?
5. **Impact and practical value**: Would practitioners find this useful?

Produce your review in this format:
```
## R2 Review: Novelty and Related Work

### Summary
[2-3 sentences]

### Strengths
[Numbered list, be specific]

### Weaknesses
[Numbered list, be specific. Label each as Major or Minor]

### Questions for Authors
[Numbered list]

### Novelty Assessment
[Detailed analysis of each claimed contribution's novelty]

### Related Work Gaps
[Missing citations, unfair comparisons, etc.]

### Framing Issues
[Where does the paper mis-position itself?]

### Overall Assessment
Score: X/6
Confidence: X/5
[2-3 sentence justification]
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "b94c995b-3c24-43f0-be23-b34e0d97de53",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-16T02:54:20.556Z_

```json
{
  "parentUuid": "b94c995b-3c24-43f0-be23-b34e0d97de53",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
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
  "uuid": "8493b0af-e552-411e-aec4-985442d7ab05",
  "timestamp": "2026-05-16T02:54:20.556Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Tool call

_source line 3 · 2026-05-16T02:54:25.383Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Gtv7d66CCUqhJuJBmbrrGm`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8493b0af-e552-411e-aec4-985442d7ab05",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VYsZRqMLZ2er6jTBSf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "3bcb41a0-e1ea-42d1-8148-ced38f092736",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qLj2zxaEGMfquEaYkbQu5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7611,
      "cache_read_input_tokens": 9330,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7611,
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

_source line 4 · 2026-05-16T02:54:25.389Z_

<details><summary>↩ Tool result · `toolu_01Gtv7d66CCUqhJuJBmbrrGm`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Per-head mixed-precision quantization of the KV cache is a natural strategy for reducing memory during LLM inference: assign fewer bits to insensitive heads and more bits to sensitive ones, achieving lower perplexity than uniform quantization at the same average bit-width.
5	Recent work on KV cache quantization explores both uniform schemes~\cite{liu2024kivi,hooper2024kvquant,lin2024qserve,he2024zipcache} and token-level mixed-precision approaches~\cite{ge2024fastgen,lei2026arkv}, while complementary methods reduce cache size through eviction~\cite{zhang2023h2o,li2024snapkv}.
6	RateQuant~\cite{zuo2026ratequant} formalizes per-head allocation as a rate-distortion optimization and shows that greedy allocation is optimal when bit-widths are consecutive integers $\{2,3,4,5,6\}$, exploiting the polymatroid structure of the feasible set (their Proposition~6).
7	
8	In practice, hardware-efficient inference requires bit-widths drawn from $\{2, 4, 8, 16\}$---the formats natively supported by modern accelerators.
9	On this non-consecutive set, the polymatroid structure breaks down, and greedy is no longer provably optimal.
10	One might expect that exact MCKP solvers would fill this gap.
11	They do not.
12	On Qwen2.5-7B at $4\times$ compression, unconstrained greedy achieves 32.45 PPL and unconstrained MCKP achieves 36.92---both \emph{far worse} than uniform 4-bit (15.45).
13	The optimization does not merely underperform; it fails catastrophically.
14	
15	The issue traces not to solver suboptimality but to a violation of the additive distortion assumption.
16	Both solvers assign 68--75 of 112 KV heads to 2-bit, where per-head quantization errors compound through the residual stream.
17	The additive model predicts $\sim$11 PPL; the actual PPL is $3$--$4\times$ higher, because 2-bit distortions are orders of magnitude larger than 4-bit and compound super-linearly when many heads are quantized simultaneously.
18	
19	This observation points to a minimal intervention: cap the number of 2-bit assignments.
20	We add a single cardinality constraint $\sum_h \mathbb{1}[b_h{=}2] \leq k$ to the standard MCKP formulation (\S\ref{sec:method}).
21	On Qwen2.5-7B, setting $k{=}8$ (7\% of heads) yields 10.91 PPL---a 29.4\% reduction over uniform 4-bit.
22	The constraint works by forcing the solver to use 2-bit only on the least-sensitive heads, while redistributing the freed budget to protect sensitive heads at 8-bit or 16-bit.
23	This is not a heuristic patch: the constraint directly addresses the identified failure mode and is compatible with any solver.
24	The constraint is beneficial even on flat-distribution architectures: on Gemma-2-9B, unconstrained MCKP assigns 31.5\% of heads to 2-bit, producing a moderate $1.47\times$ degradation; the constraint reduces this to within 0.5\% of uniform.
25	
26	A surprising consequence is that the cardinality constraint renders solver choice irrelevant.
27	Constrained greedy and MCKP produce identical allocations across all tested architectures (112/112 heads on Qwen, 256/256 on Llama, 255/256 on Mistral), enabling practitioners to use the simpler $O(H \log H)$ greedy algorithm.
28	A per-layer brute-force oracle confirms near-optimality: the maximum gap is 0.02 PPL, 0.4\% of the total improvement (\S\ref{sec:solver_equiv}).
29	
30	However, non-uniform allocation does not help universally.
31	On the remaining eight models---including Qwen2.5-14B, where the $3.4\times$ increase in head count dilutes spread into flat---constrained MCKP provides no meaningful improvement.
32	The difference traces to the \emph{distribution shape} of head sensitivity, not GQA ratio or model scale alone: Qwen-7B's Layer-0 heads form a cluster of high sensitivity across multiple bitwidths (``spread''); Yi-1.5, CodeLlama, and Llama have dominant outliers (``spike''); Gemma-2, Mistral, Phi-3-medium, Qwen-14B, and Pythia show near-uniform or diluted sensitivity (``flat'').
33	
34	This motivates a question prior work does not address: \emph{when} should a practitioner use per-head mixed-precision quantization?
35	We propose a joint empirical decision rule based on concentration and distribution shape (\S\ref{sec:heterogeneity}) that correctly classifies all nine evaluated models (9/9), including a within-family scale contrast.
36	Yi-1.5 is a critical test: its concentration ($0.71$) exceeds Qwen-7B's, but its single-outlier spike has no cross-bitwidth gradient, so MCKP cannot redistribute budget.
37	
38	Our contributions are:
39	\begin{enumerate}[nosep]
40	\item We identify 2-bit distortion compounding as a major contributing factor in the degradation observed under unconstrained per-head KV cache quantization on hardware-aligned bit-widths, and show that a single cardinality constraint on 2-bit assignments suffices to prevent it, reducing Qwen2.5-7B PPL from 32--37 (unconstrained) to 10.91 (constrained) at $4\times$ compression (\S\ref{sec:compounding}, \S\ref{sec:experiments}).
41	
42	\item RateQuant~\cite{zuo2026ratequant} formalized per-head MCKP and proved greedy optimality for consecutive integer bit-widths. Our algorithmic contribution is a single cardinality constraint (Eq.~\ref{eq:constraint}); the scientific contribution is the systematic finding that this constraint suffices to prevent compounding, yet eight of nine tested models do not benefit from non-uniform allocation---the constraint renders solver choice irrelevant, with constrained greedy and MCKP producing equivalent allocations across all tested architectures (\S\ref{sec:solver_equiv}).
43	
44	\item We provide an empirical characterization of head sensitivity heterogeneity across nine models, revealing three distribution shapes (spread, spike, flat) that predict allocation benefit. Concentration and $t_1/t_5$ ratio correctly classify all nine models (9/9), though the spread pattern is observed in only one model ($N{=}1$, Qwen2.5-7B); the suggested thresholds should be treated as preliminary (\S\ref{sec:heterogeneity}).
45	\end{enumerate}
46	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "3bcb41a0-e1ea-42d1-8148-ced38f092736",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "7ba8489d-e8e0-4cbb-aab6-fa93c4e32487",
  "sourceToolAssistantUUID": "3bcb41a0-e1ea-42d1-8148-ced38f092736",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-16T02:54:25.869Z_

<details open><summary>🔧 Tool call — Read · `toolu_01UcYCH9sp19kN5uKwacWebN`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7ba8489d-e8e0-4cbb-aab6-fa93c4e32487",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VYsZRqMLZ2er6jTBSf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "89b5eed2-8c1f-4bfc-8e67-31aaa04cb125",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qLj2zxaEGMfquEaYkbQu5",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7611,
      "cache_read_input_tokens": 9330,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7611,
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

_source line 6 · 2026-05-16T02:54:25.875Z_

<details><summary>↩ Tool result · `toolu_01UcYCH9sp19kN5uKwacWebN`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Formulation}
5	\label{sec:formulation}
6	
7	We formulate per-head KV cache quantization as a constrained optimization problem.
8	Let $h \in \{1,\ldots,H\}$ index the KV heads across all layers, $b_h \in \mathcal{B}$ the bit-width assigned to head $h$, and $\mathcal{B} = \{2, 4, 8, 16\}$ the set of hardware-aligned bit-widths.
9	Each head $h$ has a profiled distortion function $d_h(b)$, the PPL increase when head $h$ is quantized to $b$ bits.
10	Given a memory budget ratio $R$ (e.g., $R = 0.25$ for $4\times$ compression), we seek the allocation that minimizes total distortion:
11	\begin{equation}
12	\label{eq:objective}
13	\min_{\{b_h\}} \sum_{h=1}^{H} d_h(b_h) \quad \text{s.t.} \quad \frac{1}{H \cdot 16}\sum_{h=1}^{H} b_h \leq R.
14	\end{equation}
15	
16	This is a multiple-choice knapsack problem (MCKP): each head selects one bit-width from $\mathcal{B}$ to minimize total distortion under a budget.
17	RateQuant~\cite{zuo2026ratequant} solves this for consecutive bit-widths $\{2,3,4,5,6\}$, where the polymatroid structure of the feasible set guarantees that greedy allocation is optimal (their Proposition 6).
18	Hardware-aligned bit-widths $\{2,4,8,16\}$ are non-consecutive; the gaps break this structure, and greedy is no longer guaranteed to match the MCKP optimum.
19	Moreover, as we show in \S\ref{sec:compounding}, the objective itself is not well-behaved: distortions from 2-bit heads compound non-additively, making unconstrained optimization unreliable.
20	
21	\subsection{PPL-based Per-Head Profiling}
22	\label{sec:profiling}
23	
24	We use symmetric per-channel quantization with per-head granularity: each KV head is independently quantized to one of the candidate bit-widths $\mathcal{B} = \{2, 4, 8, 16\}$, without per-token scaling.
25	We profile each head by quantizing it to each $b \in \mathcal{B}$ while keeping all other heads at bf16, and measuring the resulting PPL increase $d_h(b)$ on a calibration set of 64 sequences $\times$ 2048 tokens from WikiText-2 train.
26	This yields a distortion table of $H \times |\mathcal{B}|$ entries that serves as input to the solver.
27	
28	The optimization in Eq.~\eqref{eq:objective} relies on an additive distortion assumption: the total PPL degradation from a mixed-precision allocation is approximately $\sum_h d_h(b_h)$.
29	This holds when per-head distortions are small and independent---a reasonable approximation for 4-bit and 8-bit quantization, where individual head distortions are typically below 0.1 PPL.
30	At 2-bit, however, individual distortions are orders of magnitude larger, and the additive assumption breaks down.
31	
32	\subsection{Compounding Effect}
33	\label{sec:compounding}
34	
35	When many heads are simultaneously quantized to 2-bit, per-head distortions compound non-additively: truncation errors from multiple 2-bit heads accumulate through the residual stream, and once their count exceeds the network's capacity to compensate, PPL degrades super-linearly.
36	
37	Unconstrained solvers are blind to this effect because the additive objective underestimates the cost of large-scale 2-bit assignment.
38	On Qwen2.5-7B, unconstrained greedy assigns 68 heads to 2-bit and achieves 32.45 PPL; unconstrained MCKP assigns 75 heads and achieves 36.92---both far worse than uniform 4-bit (15.45).
39	Standard-resolution profiling detects non-zero $d_h(2)$ for only 37 of 112 heads; the remaining 75 heads have $d_h(2) \approx 0$, so most 2-bit assignments appear free to the additive objective.
40	The resulting additive prediction is $\sum_h d_h(b_h) + \text{baseline} \approx 11$ PPL---$3\text{--}4\times$ lower than the actual 32--37 PPL, because the compounding interaction between simultaneously quantized heads is invisible to per-head profiling.
41	
42	This compounding is specific to 2-bit quantization and is \emph{super-additive}: quantizing the top-$k$ most sensitive heads to 2-bit simultaneously produces PPL $1.56\times$ the sum of their individual distortions at $k{=}8$, growing to $4.89\times$ at $k{=}64$.
43	A random-$k$ control confirms that sensitivity ordering matters: at $k{=}64$, random selection yields 55.94 PPL vs.\ 22.95 for top-$k$, because random draws are more likely to include high-distortion heads that amplify compounding.
44	At 4-bit and above, per-head distortions are small enough that additivity holds even when all heads share the same bit-width (uniform 4-bit achieves 15.45 PPL, close to the sum-of-distortions prediction).
45	The qualitative difference arises because 2-bit quantization has far larger per-head distortion, saturating the error tolerance of the residual stream.
46	
47	The relationship between $k$ and PPL is U-shaped (Figure~\ref{fig:compounding}, Appendix~\ref{sec:compounding_appendix}): at $k{=}0$ (uniform 4-bit), PPL is 15.45; allowing a few 2-bit heads reduces PPL by freeing budget for 8-bit heads on sensitive positions, reaching a minimum of 10.89 at $k{=}8$; beyond $k{=}8$, compounding drives PPL upward.
48	
49	\subsection{Cardinality Constraint}
50	\label{sec:cardinality}
51	
52	The compounding effect motivates a simple addition to Eq.~\eqref{eq:objective}: a cardinality constraint on 2-bit assignments.
53	\begin{equation}
54	\label{eq:constraint}
55	\sum_{h=1}^{H} \mathbb{1}[b_h = 2] \leq k.
56	\end{equation}
57	
58	The constraint parameter $k$ is selected by a small-scale sweep on calibration data: solve the constrained problem for each candidate $k$, evaluate calibration PPL, and pick the value at the minimum of the U-shaped curve (Figure~\ref{fig:compounding}).
59	For Qwen2.5-7B with 112 KV heads, $k{=}8$ ($\sim$7\% of heads).
60	
61	The constraint is a single linear inequality, compatible with any solver---greedy, MCKP, or integer linear programming---and adds negligible overhead to the optimization.
62	
63	One might expect Layer-0 heads to require explicit protection.
64	On Qwen2.5-7B, however, the profiler assigns very high 2-bit distortion to Layer-0 heads (L0H0: $+$31.9\%, L0H2: $+$23.2\%, L0H3: $+$11.7\% relative to bf16), so no solver would assign them 2-bit under any reasonable budget.
65	Running the solver with and without manual Layer-0 exclusion produces identical allocations; no manual rule is needed.
66	
67	\paragraph{Restoring additivity.}
68	The additive objective treats per-head distortions as independent, but 2-bit compounding violates this once many 2-bit heads coexist.
69	Restricting 2-bit heads to $k \ll H$ pushes the allocation back into a near-additive regime where the profiler's prediction agrees with measured PPL.
70	For Qwen2.5-7B, $k{=}8$ ($\sim$7\% of heads) is few enough that compounding contributes negligibly, consistent with the U-shaped curve minimum (Figure~\ref{fig:compounding}).
71	This explains the constrained--unconstrained gap in Table~\ref{tab:solver_equiv}: constrained greedy operates inside the additive regime (10.91 PPL, matching the ${\approx}11$ additive estimate), while unconstrained solvers extrapolate outside it and miss true PPL by $3\text{--}4\times$.
72	
73	\subsection{Solver Equivalence}
74	\label{sec:solver_equiv}
75	
76	\begin{table}[t]
77	\centering
78	\small
79	\caption{Solver comparison on Qwen2.5-7B at $4\times$ compression. Unconstrained solvers over-allocate 2-bit heads and fail catastrophically. The cardinality constraint ($k{\leq}8$) makes greedy and MCKP produce identical allocations.\protect\footnotemark}
80	\label{tab:solver_equiv}
81	\begin{tabular}{llcccc}
82	\toprule
83	Solver & Constraint & PPL & \multicolumn{3}{c}{Bit distribution} \\
84	 & & & 2-bit & 4-bit & 8/16-bit \\
85	\midrule
86	Greedy & None & 32.45 & 68 & 30 & 14 \\
87	MCKP & None & 36.92 & 75 & 33 & 4 \\
88	Greedy & $k{\leq}8$ & 10.91 & 8 & 100 & 4 \\
89	MCKP & $k{\leq}8$ & 10.91 & 8 & 100 & 4 \\
90	Uniform & --- & 15.45 & 0 & 112 & 0 \\
91	\bottomrule
92	\end{tabular}
93	\end{table}
94	\footnotetext{Constrained results use high-resolution profiling; unconstrained rows use standard-resolution profiling to illustrate the failure mode (the exact PPL is irrelevant---any unconstrained allocation fails catastrophically).}
95	
96	With the cardinality constraint, greedy and MCKP produce identical results (Table~\ref{tab:solver_equiv}): same PPL (10.91), same bit distribution on Qwen2.5-7B.
97	
98	\paragraph{Empirical observation.}
99	When $k \ll H$ and the top-$k$ heads ranked by marginal benefit $d_h(4) - d_h(2)$ contain no ties, constrained greedy and MCKP produce identical per-head allocations.
100	The constraint restricts the feasible set so that the only decision is which $k$ heads to assign 2-bit; the marginal-benefit ordering determines this uniquely, so greedy's local choice coincides with the global optimum.
101	We verify this across three architectures: Qwen2.5-7B (112/112 heads identical), Llama-3.1-8B (256/256), Mistral-7B-v0.3 (255/256; the single difference is a zero-distortion tie with no PPL impact).
102	Without the constraint, greedy cascades into excessive 2-bit allocation, as each additional 2-bit head looks locally beneficial but contributes to compounding.
103	Practitioners can therefore use the simpler $O(H \log H)$ greedy algorithm without sacrificing optimality.
104	
105	A per-layer brute-force oracle on Qwen2.5-7B confirms near-optimality: of 8 layers with non-trivial allocations, MCKP matches the oracle on 5; the remaining 3 have a maximum gap of 0.018 PPL (0.4\% of the total improvement), closing the optimality chain from greedy through MCKP to brute-force.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "89b5eed2-8c1f-4bfc-8e67-31aaa04cb125",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "cde96c64-2c64-41e4-a82b-055df5496531",
  "sourceToolAssistantUUID": "89b5eed2-8c1f-4bfc-8e67-31aaa04cb125",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-16T02:54:26.080Z_

<details open><summary>🔧 Tool call — Read · `toolu_01LSsJxiZPX9ximEQS6qLMPn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cde96c64-2c64-41e4-a82b-055df5496531",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VYsZRqMLZ2er6jTBSf",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6fb9c70f-6e51-4d34-8953-454b8dd81096",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017qLj2zxaEGMfquEaYkbQu5",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 7611,
      "cache_read_input_tokens": 9330,
      "output_tokens": 222,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7611
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 222,
          "cache_read_input_tokens": 9330,
          "cache_creation_input_tokens": 7611,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7611,
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

_source line 8 · 2026-05-16T02:54:26.085Z_

<details><summary>↩ Tool result · `toolu_01LSsJxiZPX9ximEQS6qLMPn`</summary>

```text
1	Across nine models spanning 1.4B--14B parameters and seven architecture families (MHA through GQA 8:1), we find that per-head non-uniform KV cache quantization on hardware-aligned bit-widths $\{2,4,8,16\}$ provides negligible improvement over uniform 4-bit for eight of nine models.
2	The sole exception is Qwen2.5-7B, where a cardinality-constrained solver achieves 10.91 perplexity at $4\times$ compression---a 29.4\% reduction over uniform 4-bit (15.45)---while unconstrained solvers degrade catastrophically (32--37 PPL) due to 2-bit distortion compounding through the residual stream.
3	The benefit depends not on GQA ratio or model scale, but on whether sensitivity heterogeneity is \emph{spread} across multiple heads with cross-bitwidth gradients---a pattern observed in only one model ($N{=}1$) in our study.
4	On the remaining eight models---including Qwen2.5-14B, where scaling dilutes the spread pattern---non-uniform allocation provides no meaningful benefit: Yi-1.5-9B has the highest concentration tested (0.71, exceeding Qwen-7B's 0.61) yet gains nothing, because its single-outlier ``spike'' has no cross-bitwidth gradient.
5	The cardinality constraint prevents catastrophic over-allocation on Qwen-7B and moderate degradation on flat models (Gemma-2: unconstrained $1.47\times$ degradation reduced to within 0.5\% of uniform), while rendering solver choice irrelevant---constrained greedy and MCKP produce identical allocations---enabling a simple $O(H\log H)$ greedy algorithm.
6	We characterize sensitivity heterogeneity across all nine models using concentration and distribution shape ($t_1/t_5$ ratio), identifying three patterns (spread, spike, flat) that correctly predict allocation benefit (9/9); the thresholds are preliminary, as only one model exhibits the spread pattern.
7	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6fb9c70f-6e51-4d34-8953-454b8dd81096",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "21524eeb-611a-4e55-816c-2928e1398c50",
  "sourceToolAssistantUUID": "6fb9c70f-6e51-4d34-8953-454b8dd81096",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-16T02:54:34.206Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CtQMeoL1PZ3qdGd5v92ojR`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "21524eeb-611a-4e55-816c-2928e1398c50",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VZGtPJPgKaD9oGsaYH",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "a6c23855-1133-41a9-8f7a-717efed4dd35",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PiEXdVfb53QS9Xz1LMLWeN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6609,
      "cache_read_input_tokens": 16941,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6609,
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

_source line 10 · 2026-05-16T02:54:34.212Z_

<details><summary>↩ Tool result · `toolu_01CtQMeoL1PZ3qdGd5v92ojR`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	\paragraph{Models.}
8	We evaluate eight models spanning six architecture families and diverse attention configurations:
9	\textbf{Qwen2.5-7B} (GQA 7:1, 28 layers $\times$ 4 KV heads = 112),
10	\textbf{Qwen2.5-14B} (GQA 5:1, 48 $\times$ 8 = 384),
11	\textbf{Yi-1.5-9B} (GQA 8:1, 48 $\times$ 4 = 192),
12	\textbf{Llama-3.1-8B} (GQA 4:1, 32 $\times$ 8 = 256),
13	\textbf{Mistral-7B-v0.3} (GQA 4:1, 32 $\times$ 8 = 256, sliding window attention),
14	\textbf{Gemma-2-9B} (GQA 2:1, 42 $\times$ 8 = 336, \texttt{head\_dim}=256, attention logit softcapping),
15	\textbf{Phi-3-medium-14B} (GQA 4:1, 40 $\times$ 10 = 400),
16	and \textbf{Pythia-1.4B} (MHA 1:1, 24 $\times$ 16 = 384).
17	This selection spans GQA ratios from 1:1 (MHA) to 8:1 and covers standard, sliding-window, softcapped, and multi-head attention.
18	
19	\paragraph{Evaluation.}
20	We report perplexity (PPL, $\downarrow$) on the WikiText-2 test split (298{,}938 tokens) under bf16 inference with stride 512.
21	For downstream evaluation, we use ARC-Challenge, HellaSwag, PIQA, and WinoGrande under 0-shot prompting.
22	
23	\paragraph{Profiling.}
24	Per-head sensitivity is measured by independently quantizing each head to each candidate bit-width in $\{2, 4, 8, 16\}$ and recording the PPL increase over the bf16 baseline.
25	All results use high-resolution profiling (64 sequences $\times$ 2048 tokens from WikiText-2 train); Appendix~\ref{sec:profiling_resolution} compares against standard-resolution profiling (16 seq $\times$ 512 tok).
26	
27	\paragraph{Compression and constraint.}
28	The default target is 4$\times$ compression (average 4 bits, budget ratio 0.25).
29	The cardinality constraint limits 2-bit assignments to at most $k$ heads, where $k$ is selected via the compounding sweep described in \S\ref{sec:method} ($k{=}8$ for Qwen-7B and Qwen-14B, $k{=}2$ for Yi-1.5 and Llama, $k{=}2$ for Mistral, $k{=}8$ for Gemma-2, Phi-3-medium, and Pythia).
30	
31	\paragraph{Baselines.}
32	We compare against:
33	(1)~uniform 4-bit quantization;
34	(2)~unconstrained greedy allocation (RateQuant-style~\cite{zuo2026ratequant});
35	(3)~unconstrained MCKP allocation;
36	(4)~an L0-random heuristic that assigns Layer-0 heads to 8-bit and $k$ random non-Layer-0 heads to 2-bit, with remaining heads at 4-bit (5 seeds; we report mean$\pm$std and median);
37	and (5)~a naive positional heuristic that assigns Layer-0 to 8-bit and the $k$ deepest heads to 2-bit.
38	
39	\subsection{Main Results}
40	\label{sec:main_results}
41	
42	\begin{table}[t]
43	\centering
44	\small
45	\caption{PPL ($\downarrow$) on WikiText-2 at 4$\times$ compression. Unconstrained failure: catastrophic on Qwen-7B ($3.3\times$ bf16), severe on Pythia ($1.9\times$), moderate on Gemma-2 ($1.5\times$), mild on remaining incl.\ Qwen-14B (${\sim}1.1\times$). Greedy and MCKP columns are both unconstrained; identical allocations on 6/8 models (equivalence verified experimentally on Qwen-7B and Qwen-14B; Qwen-14B and Pythia Greedy values inferred via this equivalence). Best constrained result per model in \textbf{bold}. $^*$BOS-corrected.}
46	\label{tab:main_results}
47	\begin{tabular}{lccccc}
48	\toprule
49	Model & Baseline & Uniform & \multicolumn{2}{c}{Unconstrained} & Ours \\
50	\cmidrule(lr){4-5}
51	 & (bf16) & (4-bit) & Greedy & MCKP & (Constr.) \\
52	\midrule
53	Qwen2.5-7B      & 9.81  & 15.45 & 32.45 & 36.92 & \textbf{10.91} \\
54	Qwen2.5-14B     & 6.87  & 7.20  & 7.69  & 7.69  & 7.22 \\
55	Yi-1.5-9B       & 7.02  & 7.22  & 7.56  & 7.56  & 7.22 \\
56	Llama-3.1-8B    & 8.09  & 8.47  & 8.63  & 8.63  & \textbf{8.45} \\
57	Mistral-7B-v0.3 & 7.04  & 7.13  & 7.57  & 7.60  & 7.13 \\
58	Gemma-2-9B$^*$  & 6.03  & 6.17  & 8.85  & 8.85  & 6.20 \\
59	Phi-3-medium-14B & 5.64 & 5.80  & 6.07  & 6.07  & 5.81 \\
60	Pythia-1.4B     & 16.49 & 24.29 & 31.54 & 31.54 & 24.45 \\
61	\bottomrule
62	\end{tabular}
63	\end{table}
64	
65	On Qwen2.5-7B, constrained MCKP achieves 10.91 PPL, a 29.4\% reduction over uniform 4-bit (15.45).
66	Without the constraint, both greedy (32.45) and MCKP (36.92) perform \emph{worse} than uniform---a catastrophic failure from excessive 2-bit assignments compounding across layers.
67	Across 3 calibration seeds, constrained MCKP yields mean PPL 10.99$\pm$0.06 with 90.2\% three-way allocation agreement, confirming profiling stability.
68	
69	On Llama-3.1-8B, the result is essentially indistinguishable from uniform (8.45 vs.\ 8.47, $\Delta < 0.02$ PPL).
70	Hires profiling reveals concentration $0.57$ (comparable to Qwen's $0.61$) but a spike pattern ($t_1/t_5{=}0.85$) dominated by a single head (L2H5), leaving no cross-bitwidth gradient to exploit.
71	
72	On Yi-1.5-9B, constrained MCKP ($k{=}2$) matches uniform (7.22); despite the highest concentration tested (0.71), sensitivity is dominated by a single outlier (L4H3, $t_1/t_5{=}0.90$), a spike pattern with no cross-bitwidth gradient.
73	On Mistral-7B-v0.3, constrained MCKP ($k{=}2$) matches uniform (7.13 vs.\ 7.13); near-zero sensitivity differences and sliding-window attention leave no room for reallocation gains.
74	
75	On Gemma-2-9B$^*$ (GQA 2:1), constrained MCKP ($k{=}8$) achieves 6.20 PPL vs.\ uniform 6.17 ($+$0.4\%).
76	Despite flat sensitivity (concentration 0.23), unconstrained MCKP degrades to 8.85 ($1.47\times$ bf16) from 31.5\% 2-bit over-allocation; the constraint reduces this to 8 heads, confirming universal over-allocation prevention.
77	
78	On Phi-3-medium-14B (GQA 4:1), constrained MCKP ($k{=}8$) achieves 5.81 PPL vs.\ uniform 5.80, consistent with its flat sensitivity profile (concentration 0.17); unconstrained MCKP degrades mildly to 6.07 ($1.08\times$ bf16). %exp_id=phi3_medium_constrained_mckp
79	
80	Unconstrained failure severity tracks heterogeneity shape: \emph{catastrophic} on Qwen-7B ($3.3\times$ bf16, 60\% heads at 2-bit), \emph{severe} on Pythia ($1.9\times$), \emph{moderate} on Gemma-2 ($1.47\times$), and \emph{mild} on remaining models (${\sim}1.07$--$1.12\times$) including Qwen-14B ($1.12\times$, 20\% 2-bit)---the within-family contrast directly reflects shape (spread vs.\ flat).
81	See Appendix~\ref{sec:allocation_appendix} (allocation visualization) and Appendix~\ref{sec:budget_sweep} (budget sweep) for additional detail.
82	
83	MCKP consistently outperforms random L0-constrained allocation and naive positional baselines across all three tested models (median gap 5--16\%; Table~\ref{tab:heuristic} in Appendix~\ref{sec:heuristic_appendix}).
84	
85	\paragraph{Comparison with KIVI.}
86	KIVI~\cite{liu2024kivi} uses asymmetric per-channel quantization with per-token scaling, applied uniformly across all heads.
87	At 4-bit ($r{=}0$), KIVI achieves near-lossless PPL (9.91 on Qwen, 8.14 on Llama vs.\ 9.81/8.09 bf16), while our symmetric scheme yields 15.45 and 8.47---a gap from the quantization method, not allocation.
88	Within the symmetric scheme, constrained MCKP reduces Qwen from 15.45 to 10.91 ($-$4.54 PPL) by reallocating bits across heads; on Llama (spike), the gain is negligible ($-$0.02).
89	The two approaches are orthogonal and composable: KIVI selects the per-channel scheme, our method selects the per-head bit-width.
90	However, composability does not imply additive benefit: on Qwen, KIVI+MCKP achieves 9.90 PPL---identical to KIVI alone (9.90; MCKP alone: 10.89), as the per-channel method subsumes the head-level reallocation signal.
91	Per-head allocation provides independent value in symmetric-only deployment environments---common in hardware accelerators that lack per-channel asymmetric support---where it is the sole degree of freedom for exploiting sensitivity heterogeneity.
92	
93	\subsection{Cross-Architecture Compounding}
94	\label{sec:compounding_cross}
95	
96	\begin{figure}[t]
97	\centering
98	\includegraphics[width=\columnwidth]{figures/fig_compounding_curves.pdf}
99	\caption{Compounding effect across architectures. As the number of 2-bit heads ($k$) increases, PPL degradation follows architecture-dependent trajectories: Llama (spike, $c{=}0.57$) explodes to $1519\times$ at $k{=}256$ due to a single extreme-sensitivity head compounding through the residual stream; Qwen (spread, $c{=}0.61$) degrades $10\times$; Mistral (flat, $c{=}0.24$) remains most resilient ($6.4\times$). All three stay near-baseline for $k{\leq}8$, validating the cardinality constraint regime. Qwen saturates at $k{\approx}96$ due to its 112 KV heads (maximum ${\sim}96$ eligible for 2-bit assignment).}
100	\label{fig:compounding_cross}
101	\end{figure}
102	
103	Figure~\ref{fig:compounding_cross} shows the compounding sweep across three architectures representing the three sensitivity patterns.
104	At small $k$ (${\leq}8$), all models tolerate 2-bit assignments with minimal PPL increase (${\leq}2.5\%$ over baseline), confirming that the cardinality constraint ($k{=}2$--$8$) operates in the near-additive regime regardless of architecture.
105	
106	Beyond $k{=}8$, divergence is stark.
107	Llama (spike pattern) remains stable through $k{=}32$ (PPL $9.05$, $1.12\times$ baseline) but explodes at $k{=}128$ ($40.21$) and $k{=}256$ ($1519$, $188\times$ baseline)---the single extreme-sensitivity head (L2H5) amplifies compounding once enough surrounding heads are also degraded.
108	Qwen (spread pattern) rises earlier, reaching $23.22$ at $k{=}64$ ($2.4\times$) and $98.75$ at $k{=}256$ ($10.1\times$), as its cluster of Layer-0 sensitive heads compound non-additively at moderate $k$.
109	Mistral (flat pattern) is the most resilient: PPL stays below $8$ through $k{=}64$ and reaches only $45.28$ at $k{=}256$ ($6.4\times$), consistent with its near-uniform sensitivity distribution offering no single failure mode.
110	
111	These curves directly motivate architecture-specific $k$ selection: the compounding onset ($k$ at which PPL exceeds $1.5\times$ baseline) is ${\sim}32$ for Qwen, ${\sim}64$ for Llama, and ${\sim}128$ for Mistral, with the optimal constrained $k$ lying well below each onset.
112	
113	\subsection{Downstream Evaluation}
114	\label{sec:downstream}
115	
116	\begin{table}[t]
117	\centering
118	\small
119	\caption{0-shot accuracy change (Ours $-$ Uniform, pts) at 4$\times$ compression. Qwen values are mean over 3 calibration seeds ($\pm$1$\sigma$). Qwen shows gains on HS/PIQA/WG; the remaining models show near-neutral change, tracking PPL results.}
120	\label{tab:downstream}
121	\begin{tabular}{lccccc}
122	\toprule
123	Model & ARC-C & HS & PIQA & WG & Avg \\
124	\midrule
125	Qwen2.5-7B        & $+$0.0{\scriptsize$\pm$0.4} & $+$4.1{\scriptsize$\pm$0.2} & $+$2.0{\scriptsize$\pm$0.2} & $+$1.6{\scriptsize$\pm$1.2} & $+$1.9 \\
126	Yi-1.5-9B        & $-$2.1 & $-$0.4 & $+$0.0 & $+$0.3 & $-$0.5 \\
127	Llama-3.1-8B     & $-$0.8 & $+$0.0 & $-$0.1 & $+$0.5 & $-$0.1 \\
128	Mistral-7B       & $+$0.0 & $+$0.0 & $-$0.1 & $-$0.1 & $+$0.0 \\
129	Gemma-2-9B       & $-$0.1 & $+$0.0 & $+$0.4 & $+$0.6 & $+$0.2 \\
130	\bottomrule
131	\end{tabular}
132	\end{table}
133	
134	On Qwen, constrained MCKP improves average 0-shot accuracy by 1.9 pts over uniform (mean over 3 seeds, $\pm$1$\sigma$ in Table~\ref{tab:downstream}), with the largest gains on HellaSwag ($+$4.1) and PIQA ($+$2.0).
135	The four non-spread models show near-neutral average change (Yi $-$0.5, Llama $-$0.1, Mistral $+$0.0, Gemma-2 $+$0.2 pts); Mistral is effectively unchanged across all tasks, consistent with its flat sensitivity profile.
136	ARC-Challenge shows the largest per-task sensitivity across all models (Yi $-$2.1, Llama $-$0.8, Gemma-2 $-$0.1 pts), consistent with multi-step reasoning where KV cache errors accumulate across longer inference chains.
137	Cross-dataset (Appendix~\ref{sec:cross_dataset}, ${>}96\%$ bit-assignment agreement across WikiText-2/C4) and long-context (Appendix~\ref{sec:long_context}, Qwen uniform $11.15\times$ bf16 at 8K vs.\ MCKP $1.23\times$) analyses confirm allocation robustness.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "a6c23855-1133-41a9-8f7a-717efed4dd35",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "dcf14832-8fcb-4b53-a73d-6b14cde5cb4a",
  "sourceToolAssistantUUID": "a6c23855-1133-41a9-8f7a-717efed4dd35",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-16T02:54:35.161Z_

<details open><summary>🔧 Tool call — Read · `toolu_015jxCzoRurgfeTsnKmzsAGH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "dcf14832-8fcb-4b53-a73d-6b14cde5cb4a",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VZGtPJPgKaD9oGsaYH",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "f644bd63-beb1-4dea-9ede-56adc313e46c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PiEXdVfb53QS9Xz1LMLWeN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6609,
      "cache_read_input_tokens": 16941,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6609,
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

_source line 12 · 2026-05-16T02:54:35.167Z_

<details><summary>↩ Tool result · `toolu_015jxCzoRurgfeTsnKmzsAGH`</summary>

```text
1	\section{Analysis}
2	\label{sec:analysis}
3	
4	\subsection{Heterogeneity Characterization}
5	\label{sec:heterogeneity}
6	
7	The benefit of non-uniform allocation depends on how unevenly head sensitivities are distributed.
8	We quantify this with a \emph{top-5\% concentration metric}: sort per-head 2-bit distortions $d_h(2)$ in descending order and compute the fraction of total distortion contributed by the top 5\% of heads.
9	High concentration indicates that a few heads are disproportionately sensitive; low concentration indicates near-uniform sensitivity.
10	
11	Table~\ref{tab:heterogeneity} summarizes the results across nine models at $4\times$ compression.
12	The central finding is that MCKP benefit requires \emph{spread heterogeneity}---multiple heads with cross-bitwidth sensitivity gradients---rather than sensitivity concentrated in a single outlier at one bitwidth.
13	
14	Qwen2.5-7B exemplifies the spread pattern (top-5\% concentration 0.61, $t_1/t_5{=}0.57$), with Layer-0 heads contributing the majority of total 2-bit distortion across multiple bitwidths.
15	Constrained MCKP reduces degradation from $+$5.64 PPL (uniform) to $+$1.10 PPL, a 29.4\% improvement over uniform 4-bit. %exp_id=qwen_constrained_mckp
16	
17	Yi-1.5-9B is a critical counterexample: despite the highest concentration tested ($0.71$, exceeding Qwen's $0.61$), constrained MCKP matches uniform ($+$0.20 vs.\ $+$0.20). %exp_id=yi15_hires_constrained_mckp
18	Yi-1.5's sensitivity is dominated by a single extreme outlier: Layer-4 Head-3 ($d_h(2){=}13.12$, second-ranked head: $0.55$, a $24\times$ gap; $t_1/t_5{=}0.90$). %exp_id=yi15_hires_profiling
19	Critically, L4H3's 4-bit and 8-bit deltas are ${\approx}\,0$, so upgrading it from 2-bit to 4-bit removes the distortion, but budget freed by downgrading other heads has nowhere useful to go---a ``spike'' pattern with sensitivity at only one bitwidth.
20	In contrast, Qwen's Layer-0 heads exhibit non-zero deltas at multiple bitwidths (e.g., L0H0: 2-bit delta ${=}6.74$, with positive 4-bit and 8-bit deltas), giving the solver a multi-bitwidth gradient across several heads---a ``spread'' pattern enabling meaningful reallocation. %exp_id=qwen_hires_profiling
21	
22	Llama-3.1-8B has concentration $0.57$---comparable to Qwen's $0.61$---yet its spike pattern ($t_1/t_5{=}0.85$), dominated by a single head (L2H5), yields allocation indistinguishable from uniform ($+$0.36 vs.\ $+$0.38), demonstrating that concentration alone is insufficient without spread structure. %exp_id=llama_hires_bf16_2bitonly %exp_id=llama_hires_constrained
23	CodeLlama-7B reinforces this: the highest concentration tested ($0.80$) with an extreme spike ($t_1/t_5{=}0.81$, L1H1 contributes $81\%$ of top-5 delta, $11.3\times$ the second-ranked head) confirms that even very high concentration yields no benefit when dominated by a single outlier. %exp_id=codellama_hires_profiling
24	Mistral-7B-v0.3 ($t_1/t_5{=}0.41$) and Gemma-2-9B ($t_1/t_5{=}0.38$) both exhibit flat distributions with low concentration ($0.24$ and $0.23$), leaving no reliable signal; constrained MCKP is slightly worse than uniform in both cases ($+$0.13 vs.\ $+$0.10 for Mistral; $+$0.16 vs.\ $+$0.14 for Gemma-2). %exp_id=mistral_c4_cross_dataset %exp_id=gemma2_full_pipeline
25	
26	Pythia-1.4B extends the evaluation to MHA (1:1 ratio, 384 heads).
27	Low concentration ($0.24$) and $t_1/t_5{=}0.28$ place it in the flat category; constrained MCKP confirms this ($+$7.96 vs.\ uniform $+$7.80, $+$0.7\%). %exp_id=pythia14b_constrained_pipeline
28	
29	Phi-3-medium-14B (GQA 4:1, 400 heads) has the lowest concentration in our test set ($0.17$) with $t_1/t_5{=}0.24$; the joint rule classifies it as flat, confirmed by evaluation (constrained $+$0.18 vs.\ uniform $+$0.16 PPL). %exp_id=phi3_medium_hires_profiling_v2 %exp_id=phi3_medium_constrained_mckp
30	
31	\paragraph{Scale-dependent concentration dilution.}
32	Qwen2.5-14B (GQA 5:1, 384 heads) provides a within-family comparison: $t_1/t_5$ is similar (0.57 vs.\ 0.68), but concentration drops from 0.61 (7B) to 0.33 (14B)---diluted by $3.4\times$ more heads into the flat regime.
33	Sensitivity is dominated by a single head (L0H5, $d_h(2){=}1.845$; second-ranked: $0.237$, a $7.8\times$ gap), but 384 heads dilute cumulative signal below the concentration threshold.
34	Concentration, not within-head structure, is thus the primary discriminator: the rule correctly identifies Qwen-7B as the single model$\times$scale combination where non-uniform allocation helps.
35	
36	\begin{table}[t]
37	\centering
38	\small
39	\caption{Head sensitivity heterogeneity and constrained allocation benefit at $4\times$ compression. $t_1/t_5$: ratio of the most sensitive head's 2-bit distortion to the sum of the top-5\% of heads' distortions (low${=}$spread, high${=}$spike); the percentage threshold ensures comparability across models with different head counts (112--400). $^*$BOS-corrected.}
40	\label{tab:heterogeneity}
41	\begin{tabular}{lcccccc}
42	\toprule
43	Model & GQA & Top-5\% & $t_1/t_5$ & $\Delta$ PPL & $\Delta$ PPL & Shape \\
44	 & Ratio & Conc. & & (Uniform) & (Ours) & \\
45	\midrule
46	Qwen2.5-7B & 7:1 & 0.61 & 0.57 & $+$5.64 & $+$1.10 & Spread \\
47	Qwen2.5-14B & 5:1 & 0.33 & 0.68 & $+$0.33 & $+$0.35 & Flat \\
48	Yi-1.5-9B & 8:1 & 0.71 & 0.90 & $+$0.20 & $+$0.20 & Spike \\
49	Llama-3.1-8B & 4:1 & 0.57 & 0.85 & $+$0.38 & $+$0.36 & Spike \\
50	Mistral-7B-v0.3 & 4:1 & 0.24 & 0.41 & $+$0.10 & $+$0.10 & Flat \\
51	Gemma-2-9B$^*$ & 2:1 & 0.23 & 0.38 & $+$0.14 & $+$0.16 & Flat \\
52	Phi-3-medium-14B & 4:1 & 0.17 & 0.24 & $+$0.16 & $+$0.18 & Flat \\
53	CodeLlama-7B & 1:1 & 0.80 & 0.81 & --- & --- & Spike \\
54	Pythia-1.4B & 1:1 & 0.24 & 0.28 & $+$7.80 & $+$7.96 & Flat \\
55	\bottomrule
56	\end{tabular}
57	\end{table}
58	
59	The per-head heatmap (Figure~\ref{fig:heatmap}, Appendix~\ref{sec:heatmap_appendix}) confirms this visually: Qwen's Layer-0 heads show high distortion while mid-to-deep layers are near-zero (spread); Yi-1.5 shows a single bright spot at Layer-4 Head-3 (64\% of total delta) with the remaining 191 heads near-uniform (spike); Gemma-2 and Mistral show uniformly low distortion.
60	
61	\subsection{Empirical Decision Rule}
62	\label{sec:diagnostic}
63	
64	MCKP benefit requires not just high concentration but a specific \emph{shape}---spread heterogeneity across multiple heads with cross-bitwidth sensitivity gradients.
65	This motivates a joint empirical decision rule for deciding when non-uniform allocation is worthwhile.
66	Given the profiling results from \S\ref{sec:profiling}, compute the top-5\% concentration and $t_1/t_5$ ratio, then select:
67	\begin{itemize}[nosep]
68	\item \textbf{Spread} (concentration $\geq 0.50$ \emph{and} $t_1/t_5 \leq 0.70$): non-uniform recommended. Qwen-7B (0.61, $t_1/t_5{=}0.57$): $-$29.4\% PPL.
69	\item \textbf{Spike} ($t_1/t_5 > 0.70$ \emph{and} concentration $\geq 0.25$): use uniform. A dominant outlier with no cross-bitwidth gradient cannot be exploited. Yi-1.5 (0.71, 0.90), CodeLlama (0.80, 0.81), and Llama (0.57, 0.85): no benefit.
70	\item \textbf{Flat} (concentration $< 0.25$, or concentration $\in [0.25, 0.50)$ with $t_1/t_5 \leq 0.70$): use uniform. Too little cumulative delta for meaningful reallocation. Mistral (0.24), Gemma-2 (0.23), Phi-3-medium (0.17), Qwen-14B (0.33), and Pythia (0.24): no benefit or counterproductive.
71	\end{itemize}
72	
73	Both conditions are needed: CodeLlama ($0.80$), Llama ($0.57$), and Yi-1.5 ($0.71$) all exceed the concentration threshold yet show no MCKP benefit; their spike shapes ($t_1/t_5 \geq 0.70$) correctly override.
74	A concentration-only rule would misclassify all three as spread; $t_1/t_5$ is the critical second discriminator.
75	The rule correctly classifies all nine evaluated models (9/9), including the within-family scale contrast (Qwen-7B spread vs.\ 14B flat) and two MHA architectures (CodeLlama-7B spike, Pythia-1.4B flat).
76	Only Qwen-7B exhibits the spread pattern ($N{=}1$); the suggested thresholds should be treated as preliminary until confirmed on additional models.
77	The rule reuses profiling data already required by the solver and adds no overhead.
78	
79	\paragraph{Why is Qwen-7B the only spread model?}
80	We offer two non-exclusive hypotheses, both requiring further validation.
81	First, Qwen-7B's high GQA ratio (7:1) means each KV head aggregates attention from 7 query heads, potentially driving greater functional specialization and thus larger inter-head sensitivity differences.
82	However, Yi-1.5 (8:1) and Qwen-14B (5:1) have comparable or higher GQA ratios yet do not exhibit spread, so GQA ratio alone is insufficient.
83	Second, scale-dependent concentration dilution may play a role: Qwen-14B (same architecture family, $3.4\times$ more heads) dilutes into the flat regime despite similar within-head structure ($t_1/t_5$ 0.68 vs.\ 0.57).
84	This suggests that increasing head count may systematically reduce concentration, making spread less likely at larger scales---a hypothesis consistent with the Qwen-7B/14B contrast but requiring evaluation on additional model families and scales.
85	
86	Additional analyses---granularity tradeoff (Appendix~\ref{sec:granularity}), aggressive compression, profiling resolution and stability, per-layer optimality, and KV separation---are in Appendices~\ref{sec:granularity}--\ref{sec:kv_separation}.
87	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "f644bd63-beb1-4dea-9ede-56adc313e46c",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "7cbae0b0-b7b9-451e-ae31-daaa39410d74",
  "sourceToolAssistantUUID": "f644bd63-beb1-4dea-9ede-56adc313e46c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-16T02:54:35.258Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Bz47KSZU8JDK8RvetvXaRL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7cbae0b0-b7b9-451e-ae31-daaa39410d74",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VZGtPJPgKaD9oGsaYH",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "6abab693-09b9-4d2c-8638-bb5486a7febd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PiEXdVfb53QS9Xz1LMLWeN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6609,
      "cache_read_input_tokens": 16941,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 6609,
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

_source line 14 · 2026-05-16T02:54:35.264Z_

<details><summary>↩ Tool result · `toolu_01Bz47KSZU8JDK8RvetvXaRL`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	Per-head mixed-precision KV cache quantization over hardware-aligned bit-widths \{2, 4, 8, 16\} requires a cardinality constraint on 2-bit assignments to prevent non-additive distortion compounding.
4	On Qwen2.5-7B, limiting 2-bit heads to $k{\leq}8$ reduces PPL from 15.45 (uniform 4-bit) to 10.91 ($-$29.4\%) at $4\times$ compression, while making solver choice irrelevant: constrained greedy and MCKP produce identical allocations across all tested architectures.
5	Whether non-uniform allocation helps depends on the \emph{shape} of head sensitivity heterogeneity---spread patterns (Qwen-7B, $t_1/t_5{=}0.57$) yield large gains, while spike (Yi-1.5, CodeLlama, Llama) and flat (Mistral, Gemma-2, Phi-3-medium, Qwen-14B, Pythia) patterns show no benefit.
6	An empirical characterization based on concentration and $t_1/t_5$ ratio correctly predicts allocation benefit for all nine evaluated models (9/9), including a within-family scale contrast where Qwen-14B's spread dilutes into flat.
7	Extending to 70B+ models, production inference engines, and per-side K/V cardinality constraints (Appendix~\ref{sec:kv_separation}) are natural next steps.
8	
9	\section*{Limitations}
10	
11	\paragraph{$N{=}1$ spread.}
12	The spread pattern is observed in only one model (Qwen2.5-7B); the decision rule thresholds (concentration $\geq 0.50$, $t_1/t_5 \leq 0.70$) are calibrated on nine models with a single positive example and should be treated as a preliminary observation rather than a validated classifier.
13	
14	\paragraph{Model scale.}
15	The largest model evaluated is 14B parameters (384 heads). The Qwen-7B/14B contrast suggests that concentration dilutes with increasing head count, which may make spread less likely at larger scales; this trend is a hypothesis, not a confirmed finding.
16	
17	\paragraph{Runtime.}
18	All latency measurements use PyTorch-level per-head \texttt{quantize}/\texttt{dequantize} dispatch and do not represent optimized CUDA kernel performance. The overhead reported in Appendix~\ref{sec:runtime} is an upper bound on the mixed-precision penalty; production inference engines with fused attention kernels would likely narrow this gap. No real-kernel latency benchmarks are reported.
19	
20	\paragraph{Downstream scope.}
21	Downstream evaluation covers four 0-shot classification tasks (ARC-C, HellaSwag, PIQA, WinoGrande). For HellaSwag, we report raw accuracy (\texttt{acc}) rather than length-normalized accuracy (\texttt{acc\_norm}). Generation tasks (summarization, translation, long-form QA) are not evaluated, and no confidence intervals are reported for the current single-seed results.
22	
23	\paragraph{Calibration domain.}
24	Cross-dataset stability is verified only between WikiText-2 and C4 (96--97\% bit-assignment agreement); other domains (code, dialogue, multilingual) are untested.
25	
26	\paragraph{Long-context.}
27	Long-context evaluation extends only to 8K tokens; deployment scenarios at 32K--128K context lengths are not tested.
28	
29	\paragraph{Missing direct competitors.}
30	No existing tool performs per-head mixed-precision KV cache quantization on hardware-aligned bit-widths, precluding direct comparison with an established baseline at the same granularity.
31	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "6abab693-09b9-4d2c-8638-bb5486a7febd",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "66661898-d361-4298-8091-b4b7317606f3",
  "sourceToolAssistantUUID": "6abab693-09b9-4d2c-8638-bb5486a7febd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-16T02:54:39.223Z_

Now let me check the related work section and references more carefully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "66661898-d361-4298-8091-b4b7317606f3",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VZxD1RL9sEnhWdKfKg",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "1a5da2e6-e3f6-40c9-95fa-7941feb716f9",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018gtAwzT7d8P7XChFP7814C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9584,
      "cache_read_input_tokens": 23550,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9584,
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

_source line 16 · 2026-05-16T02:54:41.504Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01DcZcfVfvP8a351p2ypYksM`</summary>

```json
{
  "pattern": "\\\\bibitem|@article|@inproceedings",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper",
  "output_mode": "files_with_matches"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1a5da2e6-e3f6-40c9-95fa-7941feb716f9",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VZxD1RL9sEnhWdKfKg",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "fa48e2e4-4251-4878-8eb1-4752abcb49b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018gtAwzT7d8P7XChFP7814C",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9584,
      "cache_read_input_tokens": 23550,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 9584,
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

_source line 17 · 2026-05-16T02:54:41.525Z_

<details><summary>↩ Tool result · `toolu_01DcZcfVfvP8a351p2ypYksM`</summary>

```text
Found 4 files
docs/paper/main.bbl
docs/paper/references.bib
docs/paper/references.bib.prev
docs/paper/acl_natbib.bst
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "fa48e2e4-4251-4878-8eb1-4752abcb49b3",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "0f20fdb8-2c22-471a-92ad-80ae62e70fe0",
  "sourceToolAssistantUUID": "fa48e2e4-4251-4878-8eb1-4752abcb49b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 18 · 2026-05-16T02:54:45.422Z_

<details open><summary>🔧 Tool call — Read · `toolu_014YzkMfP6Z2zePqLS2ThhNt`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/main.bbl"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0f20fdb8-2c22-471a-92ad-80ae62e70fe0",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VaRAEu72fMSq45iH6y",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2801beec-807f-4c68-b65d-1cb2898b6920",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DfBcJWMx7B4PiNWTm6CjMe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 205,
      "cache_read_input_tokens": 33134,
      "output_tokens": 86,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 205
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 86,
          "cache_read_input_tokens": 33134,
          "cache_creation_input_tokens": 205,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 205,
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

_source line 19 · 2026-05-16T02:54:45.428Z_

<details><summary>↩ Tool result · `toolu_014YzkMfP6Z2zePqLS2ThhNt`</summary>

```text
1	\begin{thebibliography}{31}
2	\providecommand{\natexlab}[1]{#1}
3	
4	\bibitem[{Dong et~al.(2020)Dong, Yao, Cai, Arfeen, Gholami, Mahoney, and
5	  Keutzer}]{dong2020hawqv2}
6	Zhen Dong, Zhewei Yao, Yaohui Cai, Daiyaan Arfeen, Amir Gholami, Michael~W.
7	  Mahoney, and Kurt Keutzer. 2020.
8	\newblock \href {https://arxiv.org/abs/1911.03852} {{HAWQ-V2}: {Hessian} aware
9	  trace-weighted quantization of neural networks}.
10	\newblock In \emph{NeurIPS 2020}.
11	
12	\bibitem[{Dong et~al.(2019)Dong, Yao, Gholami, Mahoney, and
13	  Keutzer}]{dong2019hawq}
14	Zhen Dong, Zhewei Yao, Amir Gholami, Michael~W. Mahoney, and Kurt Keutzer.
15	  2019.
16	\newblock \href {https://arxiv.org/abs/1905.03696} {{HAWQ}: {Hessian} aware
17	  quantization of neural networks with mixed-precision}.
18	\newblock In \emph{ICCV 2019}.
19	
20	\bibitem[{Duanmu et~al.(2024)Duanmu, Yuan, Li, Duan, Zhang, and
21	  Lin}]{duanmu2024skvq}
22	Haojie Duanmu, Zhihang Yuan, Xiuhong Li, Jiangfei Duan, Xingcheng Zhang, and
23	  Dahua Lin. 2024.
24	\newblock \href {https://arxiv.org/abs/2405.06219} {{SKVQ}: Sliding-window key
25	  and value cache quantization for large language models}.
26	\newblock \emph{Preprint}, arXiv:2405.06219.
27	\newblock ArXiv preprint.
28	
29	\bibitem[{Feng et~al.(2025)Feng, Lv, Cao, Xie, and Zhou}]{feng2025adakv}
30	Yuan Feng, Junlin Lv, Yukun Cao, Xike Xie, and S.~Kevin Zhou. 2025.
31	\newblock \href {https://arxiv.org/abs/2407.11550} {{Ada-KV}: Optimizing {KV}
32	  cache eviction by adaptive budget allocation}.
33	\newblock In \emph{NeurIPS 2025}.
34	
35	\bibitem[{Fu et~al.(2025)Fu, Cai, Sid-Lakhdar, Zhao, and Peng}]{fu2025headkv}
36	Yu~Fu, Zefan Cai, Abdelrahman Sid-Lakhdar, Wayne~Xin Zhao, and Richard Peng.
37	  2025.
38	\newblock \href {https://arxiv.org/abs/2410.19258} {Not all heads matter: A
39	  head-level {KV} cache compression method with integrated retrieval and
40	  reasoning}.
41	\newblock In \emph{ICLR 2025}.
42	
43	\bibitem[{Ge et~al.(2024)Ge, Zhang, Liu, Zhang, Han, and Gao}]{ge2024fastgen}
44	Suyu Ge, Yunan Zhang, Liyuan Liu, Minjia Zhang, Jiawei Han, and Jianfeng Gao.
45	  2024.
46	\newblock \href {https://arxiv.org/abs/2310.01801} {Model tells you what to
47	  discard: Adaptive {KV} cache compression for {LLMs}}.
48	\newblock In \emph{ICLR 2024}.
49	
50	\bibitem[{Haeri~Boroujeni et~al.(2026)Haeri~Boroujeni, Mehrabi, Woods,
51	  Hillesheim, and Razi}]{haeriboroujeni2026dontwaste}
52	Sayed~Pedram Haeri~Boroujeni, Niloufar Mehrabi, Patrick Woods, Gabriel
53	  Hillesheim, and Abolfazl Razi. 2026.
54	\newblock \href {https://arxiv.org/abs/2604.04722} {Don't waste bits!
55	  {Adaptive} {KV}-cache quantization for lightweight on-device {LLMs}}.
56	\newblock In \emph{CVPR 2026}.
57	
58	\bibitem[{He et~al.(2024)He, Zhang, Wu, Liu, Zhou, and Zhuang}]{he2024zipcache}
59	Yefei He, Luoming Zhang, Weijia Wu, Jing Liu, Hong Zhou, and Bohan Zhuang.
60	  2024.
61	\newblock \href {https://arxiv.org/abs/2405.14256} {{ZipCache}: Accurate and
62	  efficient {KV} cache quantization with salient token identification}.
63	\newblock In \emph{NeurIPS 2024}.
64	
65	\bibitem[{Hooper et~al.(2024)Hooper, Kim, Mohammadzadeh, Mahoney, Shao,
66	  Keutzer, and Gholami}]{hooper2024kvquant}
67	Coleman Hooper, Sehoon Kim, Hiva Mohammadzadeh, Michael~W. Mahoney,
68	  Yakun~Sophia Shao, Kurt Keutzer, and Amir Gholami. 2024.
69	\newblock \href {https://arxiv.org/abs/2401.18079} {{KVQuant}: Towards 10
70	  million context length {LLM} inference with {KV} cache quantization}.
71	\newblock In \emph{NeurIPS 2024}.
72	
73	\bibitem[{Kang et~al.(2024)Kang, Zhang, Kundu, Jeong, Liu, Krishna, and
74	  Zhao}]{kang2024gear}
75	Hao Kang, Qingru Zhang, Souvik Kundu, Geonhwa Jeong, Zaoxing Liu, Tushar
76	  Krishna, and Tuo Zhao. 2024.
77	\newblock \href {https://arxiv.org/abs/2403.05527} {{GEAR}: An efficient {KV}
78	  cache compression recipe for near-lossless generative inference of {LLM}}.
79	\newblock \emph{Preprint}, arXiv:2403.05527.
80	\newblock ArXiv preprint.
81	
82	\bibitem[{Kim et~al.(2024)Kim, Hooper, Gholami, Dong, Li, Shen, Mahoney, and
83	  Keutzer}]{kim2024squeezellm}
84	Sehoon Kim, Coleman Hooper, Amir Gholami, Zhen Dong, Xiuyu Li, Sheng Shen,
85	  Michael~W. Mahoney, and Kurt Keutzer. 2024.
86	\newblock \href {https://arxiv.org/abs/2306.07629} {{SqueezeLLM}:
87	  Dense-and-sparse quantization}.
88	\newblock In \emph{ICML 2024}.
89	
90	\bibitem[{Lei and Ilager(2026)}]{lei2026arkv}
91	Jianlong Lei and Shashikant Ilager. 2026.
92	\newblock \href {https://arxiv.org/abs/2603.08727} {{ARKV}: Adaptive and
93	  resource-efficient {KV} cache management under limited memory budget for
94	  long-context inference in {LLMs}}.
95	\newblock \emph{Preprint}, arXiv:2603.08727.
96	\newblock ArXiv preprint.
97	
98	\bibitem[{Li et~al.(2025{\natexlab{a}})Li, Liu, Wu, Nie, and
99	  Wang}]{li2025kvmix}
100	Fei Li, Song Liu, Weiguo Wu, Shiqiang Nie, and Jinyu Wang. 2025{\natexlab{a}}.
101	\newblock \href {https://arxiv.org/abs/2506.08018} {{KVmix}: Gradient-based
102	  layer importance-aware mixed-precision quantization for {KV} cache}.
103	\newblock \emph{Preprint}, arXiv:2506.08018.
104	\newblock ArXiv preprint.
105	
106	\bibitem[{Li et~al.(2024)Li, Huang, Yang, Venkitesh, Locatelli, Ye, Cai, Lewis,
107	  and Chen}]{li2024snapkv}
108	Yuhong Li, Yingbing Huang, Bowen Yang, Bharat Venkitesh, Acyr Locatelli,
109	  Hanchen Ye, Tianle Cai, Patrick Lewis, and Deming Chen. 2024.
110	\newblock \href {https://arxiv.org/abs/2404.14469} {{SnapKV}: {LLM} knows what
111	  you are looking for before generation}.
112	\newblock In \emph{NeurIPS 2024}.
113	
114	\bibitem[{Li et~al.(2025{\natexlab{b}})Li, Shen, Tang, Luo, and
115	  Dai}]{li2025kvtuner}
116	Zhongzhi Li, Yuhan Shen, Yixuan Tang, Jian Luo, and Yonggang Dai.
117	  2025{\natexlab{b}}.
118	\newblock \href {https://arxiv.org/abs/2502.04420} {{KVTuner}:
119	  Sensitivity-aware layer-wise mixed-precision {KV} cache quantization for
120	  efficient and nearly lossless {LLM} inference}.
121	\newblock In \emph{ICML 2025}.
122	
123	\bibitem[{Lin et~al.(2025)Lin, Tang, Yang, Zhang, Xiao, Gan, and
124	  Han}]{lin2024qserve}
125	Yujun Lin, Haotian Tang, Shang Yang, Zhekai Zhang, Guangxuan Xiao, Chuang Gan,
126	  and Song Han. 2025.
127	\newblock \href {https://arxiv.org/abs/2405.04532} {{QServe}: {W4A8KV4}
128	  quantization and system co-design for efficient {LLM} serving}.
129	\newblock In \emph{MLSys 2025}.
130	
131	\bibitem[{Liu et~al.(2025)Liu, Li, Yang, Zhao, Zhou, Song, Dai, Yan, Yang, and
132	  Wang}]{liu2025pmkvq}
133	Tengxuan Liu, Shiyao Li, Jiayi Yang, Tianchen Zhao, Feng Zhou, Xiaohui Song,
134	  Guohao Dai, Shengen Yan, Huazhong Yang, and Yu~Wang. 2025.
135	\newblock \href {https://arxiv.org/abs/2505.18610} {{PM-KVQ}: Progressive
136	  mixed-precision {KV} cache quantization for long-cot {LLMs}}.
137	\newblock \emph{Preprint}, arXiv:2505.18610.
138	\newblock ArXiv preprint.
139	
140	\bibitem[{Liu et~al.(2023)Liu, Desai, Liao, Wang, Xie, Xu, Kyrillidis, and
141	  Shrivastava}]{liu2024scissorhands}
142	Zichang Liu, Aditya Desai, Fangshuo Liao, Weitao Wang, Victor Xie, Zhaozhuo Xu,
143	  Anastasios Kyrillidis, and Anshumali Shrivastava. 2023.
144	\newblock \href {https://arxiv.org/abs/2305.17118} {Scissorhands: Exploiting
145	  the persistence of importance hypothesis for {LLM} {KV} cache compression at
146	  test time}.
147	\newblock In \emph{NeurIPS 2023}.
148	
149	\bibitem[{Liu et~al.(2024)Liu, Yuan, Jin, Zhong, Xu, Braverman, Chen, and
150	  Hu}]{liu2024kivi}
151	Zirui Liu, Jiayi Yuan, Hongye Jin, Shaochen Zhong, Zhaozhuo Xu, Vladimir
152	  Braverman, Beidi Chen, and Xia Hu. 2024.
153	\newblock \href {https://arxiv.org/abs/2402.02750} {{KIVI}: A tuning-free
154	  asymmetric 2bit quantization for {KV} cache}.
155	\newblock In \emph{ICML 2024}.
156	
157	\bibitem[{Michel et~al.(2019)Michel, Levy, and Neubig}]{michel2019sixteen}
158	Paul Michel, Omer Levy, and Graham Neubig. 2019.
159	\newblock \href {https://arxiv.org/abs/1905.10650} {Are sixteen heads really
160	  better than one?}
161	\newblock In \emph{NeurIPS 2019}.
162	
163	\bibitem[{Sharma et~al.(2025)Sharma, Ding, Li, Dani, and
164	  Zhang}]{sharma2025minikv}
165	Akshat Sharma, Hangliang Ding, Jianping Li, Neel Dani, and Minjia Zhang. 2025.
166	\newblock \href {https://arxiv.org/abs/2411.18077} {{MiniKV}: Pushing the
167	  limits of 2-bit {KV} cache via compression and system co-design for efficient
168	  long context inference}.
169	\newblock In \emph{Findings of ACL 2025}.
170	
171	\bibitem[{Shutova et~al.(2025)Shutova, Malinovskii, Egiazarian, Kuznedelev,
172	  Mazur, Surkov, Ermakov, and Alistarh}]{shutova2025aquakv}
173	Alina Shutova, Vladimir Malinovskii, Vage Egiazarian, Denis Kuznedelev, Denis
174	  Mazur, Nikita Surkov, Ivan Ermakov, and Dan Alistarh. 2025.
175	\newblock \href {https://arxiv.org/abs/2501.19392} {Cache me if you must:
176	  Adaptive key-value quantization for large language models}.
177	\newblock In \emph{ICML 2025}.
178	
179	\bibitem[{Su et~al.(2025)Su, Chen, Shen, Wei, Li, Yu, and
180	  Yuan}]{su2025rotatekv}
181	Zunhai Su, Zhe Chen, Wang Shen, Hanyu Wei, Linge Li, Huangqi Yu, and Kehong
182	  Yuan. 2025.
183	\newblock \href {https://arxiv.org/abs/2501.16383} {{RotateKV}: Accurate and
184	  robust 2-bit {KV} cache quantization for {LLMs} via outlier-aware adaptive
185	  rotations}.
186	\newblock In \emph{IJCAI 2025}.
187	
188	\bibitem[{Voita et~al.(2019)Voita, Talbot, Moiseev, Sennrich, and
189	  Titov}]{voita2019analyzing}
190	Elena Voita, David Talbot, Fedor Moiseev, Rico Sennrich, and Ivan Titov. 2019.
191	\newblock \href {https://arxiv.org/abs/1905.09418} {Analyzing multi-head
192	  self-attention: Specialized heads do the heavy lifting, the rest can be
193	  pruned}.
194	\newblock In \emph{ACL 2019}.
195	
196	\bibitem[{Wang et~al.(2019)Wang, Liu, Lin, Lin, and Han}]{wang2019haq}
197	Kuan Wang, Zhijian Liu, Yujun Lin, Ji~Lin, and Song Han. 2019.
198	\newblock \href {https://arxiv.org/abs/1811.08886} {{HAQ}: Hardware-aware
199	  automated quantization with mixed precision}.
200	\newblock In \emph{CVPR 2019}.
201	
202	\bibitem[{Xia et~al.(2025)Xia, Wu, Li, Wu, Wang, Wang, Li, Singhal, Shah,
203	  Ariyak, Zhuang, Zhou, Athiwaratkun, Zheng, and Song}]{xia2025kitty}
204	Haojun Xia, Xiaoxia Wu, Jisen Li, Robert Wu, Junxiong Wang, Jue Wang, Chenxi
205	  Li, Aman Singhal, Alay~Dilipbhai Shah, Alpay Ariyak, Donglin Zhuang, Zhongzhu
206	  Zhou, Ben Athiwaratkun, Zhen Zheng, and Shuaiwen~Leon Song. 2025.
207	\newblock \href {https://arxiv.org/abs/2511.18643} {{Kitty}: Accurate and
208	  efficient 2-bit {KV} cache quantization with dynamic channel-wise precision
209	  boost}.
210	\newblock \emph{Preprint}, arXiv:2511.18643.
211	\newblock ArXiv preprint.
212	
213	\bibitem[{Xiao et~al.(2024)Xiao, Tian, Chen, Han, and
214	  Lewis}]{xiao2024streamingllm}
215	Guangxuan Xiao, Yuandong Tian, Beidi Chen, Song Han, and Mike Lewis. 2024.
216	\newblock \href {https://arxiv.org/abs/2309.17453} {Efficient streaming
217	  language models with attention sinks}.
218	\newblock In \emph{ICLR 2024}.
219	
220	\bibitem[{Yang et~al.(2024)Yang, Han, Gao, Hu, Zhang, and
221	  Zhao}]{yang2024pyramidinfer}
222	Dongjie Yang, Xiaodong Han, Yan Gao, Yao Hu, Shilin Zhang, and Hai Zhao. 2024.
223	\newblock \href {https://arxiv.org/abs/2405.12532} {{PyramidInfer}: Pyramid
224	  {KV} cache compression for high-throughput {LLM} inference}.
225	\newblock In \emph{Findings of ACL 2024}.
226	
227	\bibitem[{Zhang et~al.(2025)Zhang, Zeng, Peng, Zhuang, and
228	  Chen}]{zhang2025mixkvq}
229	Tao Zhang, Ziqian Zeng, Hao Peng, Huiping Zhuang, and Cen Chen. 2025.
230	\newblock \href {https://arxiv.org/abs/2512.19206} {{MixKVQ}: Query-aware
231	  mixed-precision {KV} cache quantization for long-context reasoning}.
232	\newblock \emph{Preprint}, arXiv:2512.19206.
233	\newblock ArXiv preprint.
234	
235	\bibitem[{Zhang et~al.(2023)Zhang, Sheng, Zhou, Chen, Zheng, Cai, Song, Tian,
236	  R{\'{e}}, Barrett, Wang, and Chen}]{zhang2023h2o}
237	Zhenyu Zhang, Ying Sheng, Tianyi Zhou, Tianlong Chen, Lianmin Zheng, Ruisi Cai,
238	  Zhao Song, Yuandong Tian, Christopher R{\'{e}}, Clark Barrett, Zhangyang
239	  Wang, and Beidi Chen. 2023.
240	\newblock \href {https://arxiv.org/abs/2306.14048} {{H2O}: Heavy-hitter oracle
241	  for efficient generative inference of large language models}.
242	\newblock In \emph{NeurIPS 2023}.
243	
244	\bibitem[{Zuo et~al.(2026)Zuo, Zhou, Cong, Xi, and Leung}]{zuo2026ratequant}
245	Fei Zuo, Zikang Zhou, Hao Cong, Xiaoyan Xi, and Ho~Fai Leung. 2026.
246	\newblock \href {https://arxiv.org/abs/2605.06675} {{RateQuant}: Optimal
247	  mixed-precision {KV} cache quantization via rate-distortion theory}.
248	\newblock \emph{Preprint}, arXiv:2605.06675.
249	\newblock ArXiv preprint.
250	
251	\end{thebibliography}
252	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2801beec-807f-4c68-b65d-1cb2898b6920",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "deb5a8f9-e501-484e-b0ec-9f2ec4d80b1a",
  "sourceToolAssistantUUID": "2801beec-807f-4c68-b65d-1cb2898b6920",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 20 · 2026-05-16T02:54:56.009Z_

<details open><summary>🔧 Tool call — Glob · `toolu_011TiLYwcrzbAPGC7rJS2yAZ`</summary>

```json
{
  "pattern": "**/related*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "deb5a8f9-e501-484e-b0ec-9f2ec4d80b1a",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VahfBUmAypjfvtT2hm",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "252dc9cd-f435-4980-bd6b-db0f6b65c27b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014xfxBcKFZvR9Gi64XfU1E4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5842,
      "cache_read_input_tokens": 33339,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5842,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 40,
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

_source line 21 · 2026-05-16T02:54:56.034Z_

<details><summary>↩ Tool result · `toolu_011TiLYwcrzbAPGC7rJS2yAZ`</summary>

```text
docs/paper/related_work.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "252dc9cd-f435-4980-bd6b-db0f6b65c27b",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "8ff7ac04-e25d-4eff-b897-ea61903fad61",
  "sourceToolAssistantUUID": "252dc9cd-f435-4980-bd6b-db0f6b65c27b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 22 · 2026-05-16T02:54:56.728Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01H55tqRMojiiSFy63i5AfcB`</summary>

```json
{
  "pattern": "\\\\section\\{Related",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8ff7ac04-e25d-4eff-b897-ea61903fad61",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VahfBUmAypjfvtT2hm",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "708b4bfa-5380-4438-8db0-0a4787493e99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014xfxBcKFZvR9Gi64XfU1E4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5842,
      "cache_read_input_tokens": 33339,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 5842,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 40,
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

_source line 23 · 2026-05-16T02:54:56.744Z_

<details><summary>↩ Tool result · `toolu_01H55tqRMojiiSFy63i5AfcB`</summary>

```text
docs/paper/related_work.tex:1:\section{Related Work}\label{sec:related_work}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "708b4bfa-5380-4438-8db0-0a4787493e99",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "b2549e53-ffdf-4b30-8aa6-7eb0102efbc4",
  "sourceToolAssistantUUID": "708b4bfa-5380-4438-8db0-0a4787493e99",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-16T02:55:00.960Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KbqzPGeqeLEqjF7daugEp8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b2549e53-ffdf-4b30-8aa6-7eb0102efbc4",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VbYrP3DrzaMoqfjRnE",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "03aa88bd-7d2c-40f1-8bc3-e2d6b8983a2d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HcUCYgxqoTqgyP641EvsmC",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 402,
      "cache_read_input_tokens": 39181,
      "output_tokens": 87,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 402
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 87,
          "cache_read_input_tokens": 39181,
          "cache_creation_input_tokens": 402,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 402,
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

_source line 25 · 2026-05-16T02:55:00.976Z_

<details><summary>↩ Tool result · `toolu_01KbqzPGeqeLEqjF7daugEp8`</summary>

```text
1	\section{Related Work}\label{sec:related_work}
2	
3	\paragraph{KV Cache Quantization.}
4	Uniform-precision methods quantize the KV cache at a single bit-width across all heads, using techniques such as asymmetric per-channel/per-token schemes~\cite{liu2024kivi,hooper2024kvquant}, quantization--serving co-design~\cite{lin2024qserve}, salient-token identification~\cite{he2024zipcache}, low-rank plus sparse correction~\cite{kang2024gear}, sliding-window adaptation~\cite{duanmu2024skvq}, rotation-based outlier smoothing for robust 2-bit~\cite{su2025rotatekv}, 2-bit with adaptive token retention~\cite{sharma2025minikv}, and adapter-based inter-layer prediction at 2--2.5 bits~\cite{shutova2025aquakv}.
5	We extend the design space to per-head non-uniform allocation over hardware-aligned bit-widths $\{2,4,8,16\}$.
6	Our per-head bit-width allocation is orthogonal to per-channel quantization schemes such as KIVI: KIVI determines \emph{how} each head is quantized (asymmetric per-channel scaling), while our method determines \emph{at what precision} (bit-width selection across heads).
7	The two can be composed, though the per-channel method dominates when available (\S\ref{sec:main_results}); per-head allocation provides independent value in symmetric-only environments where per-channel asymmetric quantization is unavailable.
8	
9	\paragraph{KV Cache Eviction.}
10	Complementary to quantization, eviction methods reduce cache size by discarding tokens---retaining heavy-hitters~\cite{zhang2023h2o}, per-head important tokens~\cite{li2024snapkv,ge2024fastgen}, persistent-importance tokens~\cite{liu2024scissorhands}, attention sinks~\cite{xiao2024streamingllm}, or progressively fewer tokens in deeper layers~\cite{yang2024pyramidinfer}.
11	Recent per-head eviction methods allocate non-uniform budgets across heads based on retrieval-vs-reasoning importance~\cite{fu2025headkv} or adaptive optimization extending SnapKV/PyramidKV~\cite{feng2025adakv}, confirming that head-level heterogeneity is exploitable for eviction; our work shows it is equally exploitable for quantization.
12	
13	
14	\paragraph{Mixed-Precision Quantization (Weights).}
15	Mixed-precision allocation has a long history at the weight level.
16	HAWQ~\cite{dong2019hawq} and HAWQ-V2~\cite{dong2020hawqv2} use second-order (Hessian-based) sensitivity to assign per-layer bit-widths, with V2 introducing block-wise trace-weighted scoring and Pareto-frontier selection; HAQ~\cite{wang2019haq} learns an allocation by reinforcement learning under hardware-aware latency/energy constraints.
17	These methods operate on weights, where per-layer distortions are approximately additive and sensitivity varies smoothly across layers.
18	KV cache quantization presents a qualitatively different challenge: 2-bit head distortions compound super-additively through the residual stream (\S\ref{sec:compounding}), a phenomenon absent in weight quantization where each layer's parameters are independently quantized.
19	Our primary contribution is not the allocation algorithm itself---any MCKP or greedy solver suffices---but the diagnosis and fix of this compounding effect via cardinality constraints, and the characterization of when non-uniform allocation is beneficial (\S\ref{sec:heterogeneity}).
20	
21	\paragraph{Mixed-Precision Rate-Distortion Allocation.}
22	RateQuant~\cite{zuo2026ratequant} formulates per-head bit-width selection as an MCKP and proves greedy optimality for consecutive bit-widths $\{2,\ldots,6\}$ via the polymatroid structure, which relies on the assumption that per-head distortions decompose additively into the global objective---valid when adjacent bit-widths differ by a single bit so that quantization noise stays in the small-perturbation regime.
23	On hardware-aligned $\{2,4,8,16\}$, the 4$\times$ gap between 2-bit and 4-bit drives 2-bit distortion to compound super-additively, breaking the polymatroid structure and the additivity assumption with it.
24	Concretely, running RateQuant's greedy algorithm (Algorithm~1) directly on $\{2,4,8,16\}$ yields 32.45 PPL on Qwen2.5-7B at $4\times$ compression---catastrophically worse than uniform 4-bit (15.45)---whereas our cardinality constraint on simultaneously active 2-bit heads recovers 10.91 PPL at the same average bit-width.
25	The constraint is the minimal fix that restores the additive regime in which RateQuant's polymatroid argument applies.
26	Related mixed-precision KV-cache work operates at coarser granularity---layer-level via gradient-based sensitivity~\cite{li2025kvmix} or Pareto search over hardware-friendly precision pairs~\cite{li2025kvtuner}, block-level via progressive decoding-step quantization for long-CoT reasoning~\cite{liu2025pmkvq}, channel-level via dynamic precision boost on sensitive Key channels~\cite{xia2025kitty}, token-level via a learned on-device controller~\cite{haeriboroujeni2026dontwaste}, memory-budget-level~\cite{lei2026arkv}---at the weight level~\cite{kim2024squeezellm}, or dynamically at inference time~\cite{zhang2025mixkvq}; our allocation is static and per-head.
27	
28	\paragraph{Attention Head Analysis.}
29	Prior work studies head redundancy and pruning~\cite{voita2019analyzing,michel2019sixteen}, focusing on which heads can be removed entirely.
30	Our analysis asks a different question: which heads are sensitive to \emph{quantization}, and how heterogeneous that sensitivity is across architectures---a property that determines whether non-uniform allocation is beneficial (\S\ref{sec:heterogeneity}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "03aa88bd-7d2c-40f1-8bc3-e2d6b8983a2d",
  "isSidechain": true,
  "promptId": "1a07757b-162d-45e7-9136-009268fc7328",
  "agentId": "a69bd62d2c8fcf417",
  "type": "user",
  "uuid": "a00f1fe7-8c06-4924-857b-cb2eac0c5a3d",
  "sourceToolAssistantUUID": "03aa88bd-7d2c-40f1-8bc3-e2d6b8983a2d",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 26 · 2026-05-16T02:56:15.575Z_

Now I have a comprehensive understanding of the paper. Let me produce the review.

## R2 Review: Novelty and Related Work

### Summary
The paper empirically characterizes 2-bit distortion compounding in per-head KV cache quantization on hardware-aligned bit-widths {2,4,8,16}, proposes a cardinality constraint as a fix, and develops a 2-metric diagnostic for when non-uniform allocation helps. Across nine models, only Qwen2.5-7B benefits meaningfully, making this predominantly a negative result paper with one positive case.

### Strengths

1. **Solver equivalence is a genuinely illuminating experiment.** Showing that constrained greedy and MCKP produce identical allocations (verified at per-head level across 3 architectures, confirmed by brute-force oracle with max gap 0.02 PPL) is a strong empirical contribution that crystallizes the insight: "the constraint, not the solver, is what matters."

2. **Honest scoping and appropriate caveats.** The paper explicitly states N=1 for the spread pattern, calls thresholds "preliminary," notes Qwen-14B dilution as a hypothesis, and avoids overclaiming. The limitations section is thorough. This is refreshingly candid for a venue submission.

3. **Systematic cross-architecture evaluation.** Nine models across seven architecture families (MHA through GQA 8:1), including within-family scale contrast (Qwen-7B vs. 14B), is a rigorous experimental setup. The Yi-1.5 counterexample (high concentration but spike pattern) is particularly well-chosen.

4. **KIVI comparison is fair and informative.** The paper explicitly notes that KIVI subsumes the head-level reallocation signal and that their approach provides independent value only in symmetric-only environments. This is honest positioning that builds trust.

5. **Related work section is comprehensive and well-structured.** The paper cites 31 references spanning KV cache quantization, eviction, weight mixed-precision, and attention head analysis. Differentiation from RateQuant is detailed and technically precise (polymatroid breakdown on non-consecutive bitwidths).

### Weaknesses

1. **(Major) Novelty of the compounding observation is overstated.** RateQuant Appendix M already acknowledges compounding on non-consecutive bitwidths. The paper's claim of "first quantitative mapping" is technically defensible (RateQuant acknowledged but did not characterize), but the core observation---that 2-bit errors compound super-additively---is not surprising given the residual stream architecture and the known error accumulation literature in weight quantization. The U-shaped curve is a direct consequence of the trivial tradeoff: more 2-bit heads = more budget for high-bit heads on sensitive positions vs. compounding penalty. The paper systematizes this rather than discovers it.

2. **(Major) The cardinality constraint is a hyperparameter cap, not a principled contribution.** Adding a constraint sum(1[b_h=2]) <= k and sweeping k on calibration data is standard hyperparameter tuning. The paper attempts to elevate this to a "method contribution" but it is essentially: "don't put too many heads at 2-bit." Any practitioner who observed degradation would try this. The paper's value lies in showing *why* this is necessary and *when* it helps, not in the constraint itself.

3. **(Major) Only 1/9 models benefit, raising the question of practical relevance.** The paper's strongest result (29.4% PPL reduction on Qwen-7B) applies to exactly one model. The diagnostic classifying 9/9 models is a correct classification of a nearly trivial split (8 negatives, 1 positive). A constant predictor returning "no benefit" achieves 8/9. The practical message is: "don't bother with per-head mixed-precision on hardware-aligned bitwidths unless your model is Qwen-7B-like." While this negative result has informational value, it significantly diminishes the method's impact.

4. **(Major) Missing comparison with QAQ.** The introduction mentions QAQ (quality-adaptive quantization) as prior work, but it does not appear in the bibliography or experiments. QAQ performs attention-aware mixed-precision at a token level; a comparison would clarify the granularity tradeoff. Similarly, the paper mentions FastGen but only in the eviction context; FastGen also does attention-aware mixed-precision (importance-only heads get low precision).

5. **(Minor) The diagnostic is not independently validated.** The 2-metric rule is fit on all 9 models with no held-out set. With N=1 positive example, the thresholds (concentration >= 0.50, t1/t5 <= 0.70) are essentially drawn around Qwen-7B. The paper acknowledges this but still claims "9/9 correct" as if it were a predictive result rather than a descriptive one.

6. **(Minor) Lack of theoretical grounding for compounding.** The paper characterizes compounding empirically (U-shaped curve, super-additive factors) but provides no analysis of *why* the residual stream amplifies 2-bit errors specifically. A simple analytical model (e.g., error propagation through L layers with M 2-bit heads) would strengthen the contribution from "we observed this" to "we understand this."

7. **(Minor) KIVI composability result undermines the paper.** On Qwen, KIVI+MCKP = KIVI alone (9.90 PPL). This means that in any deployment where asymmetric per-channel quantization is available (the common case for modern inference engines), the per-head allocation adds nothing. The paper's value is restricted to "symmetric-only deployment environments," which the paper itself notes is a niche.

### Questions for Authors

1. RateQuant Appendix M acknowledges compounding on non-consecutive bitwidths. What specifically does your characterization add beyond their acknowledgment? Can you articulate what a practitioner would learn from your Tables 1-2 that they could not infer from RateQuant's disclosure?

2. If the cardinality constraint is the fix, why is sweeping k on calibration data any different from standard hyperparameter tuning (e.g., choosing a learning rate)? What makes this a "method contribution" rather than a "tuning recipe"?

3. Given that only Qwen-7B benefits: if a practitioner has already profiled their model and found it is not "spread," the recommendation is simply "use uniform 4-bit." Is the diagnostic providing actionable information beyond "run the profiler and check if non-uniform helps on your calibration set"?

4. The KIVI composability result shows per-head allocation provides zero benefit when per-channel asymmetric quantization is available. What fraction of production deployment environments are realistically "symmetric-only"?

5. Have you tested the diagnostic thresholds on any model *after* they were determined? E.g., DeepSeek-V2 (MLA), Mixtral (MoE), or Command-R?

### Novelty Assessment

**Contribution 1 (Compounding characterization):** Moderate novelty. The phenomenon is not new (RateQuant Appendix M, weight quantization literature), but the systematic quantification across architectures with the U-shaped curve, super-additive factors, and architecture-dependent onset points adds empirical value. The "first quantitative mapping" claim is technically correct but overstates the conceptual novelty. This is a careful measurement, not a discovery.

**Contribution 2 (Cardinality constraint):** Low novelty. The constraint sum(1[b_h=2]) <= k is the obvious response to observing that too many 2-bit heads cause degradation. The paper's genuine contribution here is the *solver equivalence* result showing the constraint makes solver choice irrelevant---this is non-obvious and empirically validated. But the constraint itself is a hyperparameter.

**Contribution 3 (When non-uniform helps):** Moderate novelty in framing, low novelty in content. The spread/spike/flat taxonomy is useful descriptively but is derived from and validated on the same 9 models. With N=1 positive, it is a case study rather than a generalizable finding. The question "when does per-head allocation help" is the right question and is under-explored in the literature, giving the paper positioning value.

### Related Work Gaps

1. **QAQ (Zhang et al., 2024)** is mentioned in the introduction summary but absent from the bibliography. This is a mixed-precision KV cache method that should be discussed.

2. **MiKV / Per-head eviction quantization hybrids** --- works that combine quantization and eviction at head granularity should be discussed to clarify the boundary.

3. **No discussion of calibration sensitivity in mixed-precision.** The Hessian-based weight quantization literature (HAWQ, HAWQ-V2) extensively discusses how sensitivity estimates can be unreliable; the parallel to per-head profiling unreliability (the core failure mode here) is underexplored.

4. **Missing AQLM/QuIP# family.** While these are weight quantization methods, their treatment of non-additive quantization error (via codebook optimization) is conceptually related to the compounding phenomenon described here.

5. The paper cites KVTuner (Li et al., 2025, ICML) which performs layer-level mixed-precision KV cache quantization. The relationship deserves more discussion: why is per-head better or worse than per-layer for exploiting heterogeneity?

### Framing Issues

1. **Methods paper vs. analysis paper ambiguity.** The paper presents a "method" (cardinality constraint) but its main value is empirical analysis (compounding characterization, 1/8 benefit, diagnostic). The contribution list mixes these. The paper would be stronger if it committed to being an analysis/empirical study paper with the constraint as a diagnostic tool rather than a method.

2. **"Universal fix" language is misleading.** The constraint prevents compounding, yes, but on 8/9 models it merely matches uniform---it doesn't "fix" anything because there was nothing to fix (the flat/spike models don't over-allocate much in the first place). The term "universal fix" implies universal benefit; "universal safety mechanism" would be more accurate.

3. **The 29.4% improvement headline number applies to one model.** The abstract and introduction lead with this number, creating an expectation that the method broadly helps. A more honest lead would be: "We find that per-head mixed-precision on hardware-aligned bitwidths rarely helps, and characterize why."

4. **Symmetric-only deployment niche is not well-motivated.** The paper positions its contribution for "symmetric-only deployment environments" but does not quantify how common these are or name specific hardware that lacks per-channel asymmetric support.

### Overall Assessment
Score: 3/6
Confidence: 4/5

The paper is a thorough empirical study with honest scoping and rigorous experiments, but its novelty is limited: the compounding observation is a careful measurement of a known phenomenon, the cardinality constraint is hyperparameter tuning, and the method helps only 1/9 tested models (further undermined by KIVI composability showing zero benefit when asymmetric quantization is available). The solver equivalence result and the "when does non-uniform help" framing are the strongest intellectual contributions, but they are primarily negative results. For a top venue, this paper needs either (a) a principled theoretical explanation of compounding that enables prediction without profiling, (b) demonstration that the diagnostic generalizes to held-out architectures at scale, or (c) a broader set of models where the method provides benefit. As it stands, the paper's core message---"per-head mixed-precision on {2,4,8,16} rarely helps; here's why and here's how to tell"---is valuable but incremental for a main conference.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a00f1fe7-8c06-4924-857b-cb2eac0c5a3d",
  "isSidechain": true,
  "agentId": "a69bd62d2c8fcf417",
  "requestId": "req_011Cb5VbrD9qj1xH9FFMet8k",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "0341e0dc-e942-490b-af2b-0ef92aa19eef",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_2/projects/ratekv",
  "sessionId": "f6b0b3c4-17a1-4fb2-92fd-0f4f71a4e809",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ErYcx4Aon7MFdKjTCRF8LC",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1668,
      "cache_read_input_tokens": 39583,
      "output_tokens": 2798,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1668
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 2798,
          "cache_read_input_tokens": 39583,
          "cache_creation_input_tokens": 1668,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1668,
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
