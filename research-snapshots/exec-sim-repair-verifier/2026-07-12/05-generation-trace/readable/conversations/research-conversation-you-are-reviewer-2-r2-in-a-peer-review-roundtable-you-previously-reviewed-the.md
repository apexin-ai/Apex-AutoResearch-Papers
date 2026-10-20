# Research conversation: You are Reviewer 2 (R2) in a peer review roundtable. You previously reviewed the paper "Per-Test Classification for Code

**A Systematic Comparison of Execution-Free Verification Formulations for Code Repair (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 12
- **Recorded user turns:** 1
- **Tool calls:** 4
- **Original source:** `logs/chats/exported-trajectories/account-1/agent-adf9e97eee990f313.jsonl`
- **Structured JSON:** [`352450ba0af3833863e8.json`](../../sessions/35/352450ba0af3833863e8.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

12 recorded events

### User

_source line 1 · 2026-05-16T08:26:27.655Z_

You are Reviewer 2 (R2) in a peer review roundtable. You previously reviewed the paper "Per-Test Classification for Code Execution Simulation" focusing on **novelty and related work**, and gave it a **Weak Reject (3/6)**.

## Your Original Review (R2)

### Summary
The paper proposes per-test binary classification (CLS) as an alternative to CWM for execution-free code patch verification. The main finding is complexity-dependent: CLS and CWM are equivalent at function level but CWM catastrophically fails at repo level.

### Key Strengths You Noted
- S1: Honest framing, not overclaiming novelty
- S2: Related work has 22 references, more developed than initially appeared
- S3: Explicit positioning against LEVER and CodeT
- S4: Good NLP task-reformulation context
- S5: Transparent about mixed/negative results

### Key Weaknesses You Noted
- W1: Core idea is technically straightforward; LEVER already does classifier-based execution prediction
- W2: CWM comparison against LoRA 4B/8B reproduction, not original 32B
- W3: Missing PRM/ORM parallel, fault localization, SWE-Judge, RepoExec, etc.
- W4: VG-Search deserves deeper engagement
- W5: No discussion of concurrent work on execution-free verification scaling

Your scores: Novelty 2/5, Related Work 3/5, Significance 3/5, **Overall 3/6 (Weak Reject)**, Confidence 4/5.

---

## Reviewer 1's Review (R1: Methods + Experiments)

R1 also gave **Weak Reject (3/6)**.

### R1's Key Strengths
- S1: Careful controlled comparison design
- S2: Appropriate statistical methodology (clustered bootstrap, TOST, ICC)
- S3: Honest negative results
- S4: Oracle framework with testable predictions
- S5: Comprehensive ablations
- S6: Reproducibility infrastructure

### R1's Key Weaknesses
- W1: **Repo-level CWM comparison is fundamentally confounded** — cannot distinguish implementation failure from formulation failure. The 50-93% unparseable rate makes it not a meaningful comparison.
- W2: **Single-seed repo-level comparisons** — only seed42 for 4B and 8B CLS vs CWM. The second 4B seed (seed123) shows 75.33%, barely above majority, showing high instability.
- W3: **CWM 8B "degradation"** may be hyperparameter transfer failure — same LR/LoRA config for 4B and 8B.
- W4: **TOST ±2pp margin is arbitrary** — not justified why 2pp is practical equivalence. Mixed-precision seeds (3 bf16 + 2 NF4) introduce confound.
- W5: **Synthetic mutations ≠ real bugs** — narrow distribution of mutation types.
- W6: **No downstream validation** — re-repair pilot is underpowered (p=0.11, n=120, net +5).
- W7: **DeepSeek reversal undermines generalizability** — CWM is 0.7pp better on DeepSeek.

### R1's Questions
- Q1: Has CWM been tried with different formats, full fine-tuning, or longer generation?
- Q2: Why not use repo-level ICC for repo-level oracle analysis?
- Q3: What happens with TOST on bf16-only seeds?
- Q4: Learning rate discrepancy (code says 2e-4, paper says 5e-5)?
- Q5: DeepSeek reversal — multi-seed? Repo-level results?
- Q6: How were SWE-bench per-test labels constructed?

### R1's Scores
- Soundness: 3/5
- Empirical Rigor: 3/5
- Reproducibility: 4/5
- Overall: 3/6 (Weak Reject)
- Confidence: 4/5

---

## Your Task

React to R1's review. Consider:

1. **R1's repo-level confound critique (W1-W2)** — does this change how you view the paper's significance? You flagged the CWM comparison as unfair from a novelty perspective; R1 attacks it methodologically.
2. **The learning rate discrepancy** — is this a serious reproducibility concern?
3. **R1's point about TOST margin being arbitrary** — does this weaken Claim 2 more than you initially thought?
4. **The synthetic mutation concern** — you didn't flag this. Do you agree it's a weakness?
5. **R1 notes that repo-level seed123 CLS is only 75.33%** — does this instability concern you from a significance standpoint?
6. **Any points where you disagree with R1?**
7. **Does R1's review change your score or reasoning?**

Respond in 300-500 words with your reactions, highlighting agreements, disagreements, and any score adjustment.


<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "56caabaf-ab9c-4b84-b3a0-6c8eb12d6fab",
  "agentId": "adf9e97eee990f313",
  "type": "user",
  "uuid": "61371742-b963-4275-9787-4ed9b526bbd1",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Runtime record

_source line 2 · 2026-05-16T08:26:27.662Z_

```json
{
  "parentUuid": "61371742-b963-4275-9787-4ed9b526bbd1",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
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
  "uuid": "1422470d-f4a9-47f4-bc6a-8b4e64642f1c",
  "timestamp": "2026-05-16T08:26:27.662Z",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

---

### Assistant

_source line 3 · 2026-05-16T08:26:30.636Z_



I'll review the paper and R1's critique to give an informed response.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "1422470d-f4a9-47f4-bc6a-8b4e64642f1c",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vsmy2K8jR4vLTVnG1V",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2602a784-0458-4869-8d27-05662784b53f",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LrsTX8efRvZZ4jciZbHqJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7063,
      "cache_read_input_tokens": 8950,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7063,
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

_source line 4 · 2026-05-16T08:26:32.096Z_

<details open><summary>🔧 Tool call — Read · `toolu_01FAqgTXtE3u5maYaNhciS1Y`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2602a784-0458-4869-8d27-05662784b53f",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vsmy2K8jR4vLTVnG1V",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "66c818aa-a1a5-4817-a0a8-64837e0f50d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LrsTX8efRvZZ4jciZbHqJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7063,
      "cache_read_input_tokens": 8950,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7063,
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

_source line 5 · 2026-05-16T08:26:32.104Z_

<details><summary>↩ Tool result · `toolu_01FAqgTXtE3u5maYaNhciS1Y`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	We evaluate \cls{}, \cwm{}, and trajectory-level scoring (TRAJ) across model sizes and complexity levels.
5	
6	\subsection{Experimental Setup}
7	\label{sec:setup}
8	
9	\paragraph{Datasets.}
10	\emph{Function-level}: mutated variants from HumanEval~\cite{chen2021humaneval} and MBPP~\cite{austin2021mbpp} (five mutation types), labels verified by execution. 19,076 samples (train 15,290 / val 1,896 / test 1,890; pass:fail $\approx$ 52:48, majority baseline 51.75\%).
11	\emph{Repo-level}: per-test instances from SWE-bench Verified~\cite{chowdhury2024swebenchverified} mutants. ${\sim}$70K training samples; val ($n{=}9{,}335$) and test ($n{=}9{,}784$) have zero problem overlap (majority baseline 72.96\%). Val-based checkpoint selection follows standard practice~\cite{jimenez2024swebench}.
12	
13	\paragraph{Models and training.}
14	We fine-tune Qwen3-4B and Qwen3-8B~\cite{qwen2025qwen3} with LoRA~\cite{hu2022lora} (rank 16, 3 epochs) across five seeds. Seeds 42/123/456 use bfloat16; seeds 789/0 use NF4 quantization~\cite{dettmers2024qlora}. Our \cwm{} baseline is a LoRA fine-tuned variant for controlled comparison, not a reproduction of the 32B Code World Model~\cite{meta2025cwm}. Repo-level models use val-selected checkpoints. Zero-shot baselines use Qwen3-8B and Qwen3-32B (NF4) as LLM-as-judge.
15	
16	\paragraph{Statistics.}
17	Confidence intervals use clustered bootstrap~\cite{davison1997bootstrap} (114 problem clusters, 10K resamples); per-test vs.\ trajectory-level comparison uses TOST~\cite{schuirmann1987tost} ($\pm$2\pp{} margin). ICC~\cite{shrout1979icc} quantifies within-problem correlation. Oracle analysis uses SWE-bench Verified (500 instances).
18	
19	
20	\subsection{Function-Level Results}
21	\label{sec:func_results}
22	
23	Table~\ref{tab:main_results} reports function-level results across formulations.
24	
25	\begin{table}[t]
26	\centering
27	\small
28	\caption{Function-level per-test verification results on HumanEval+MBPP test set (1,890 samples). \cls{}: per-test binary classification; \cwm{}: execution output generation; TRAJ: trajectory-level scoring; ZS: zero-shot LLM-as-judge. Mean $\pm$ std over seeds reported where applicable.}
29	\label{tab:main_results}
30	\resizebox{\columnwidth}{!}{%
31	\setlength{\tabcolsep}{4pt}
32	\begin{tabular}{llcc}
33	\toprule
34	\textbf{Method} & \textbf{Model} & \textbf{Seeds} & \textbf{Accuracy (\%)} \\
35	\midrule
36	\cls{} (fine-tuned) & 4B & 5 & \textbf{88.43 $\pm$ 0.78} \\
37	\cwm{} (fine-tuned) & 4B & 5 & 87.19 $\pm$ 0.37 \\
38	TRAJ (fine-tuned) & 4B & 5 & 86.30 $\pm$ 0.97 \\
39	\midrule
40	ZS LLM-as-judge & 8B & 1 & 64.40 \\
41	ZS LLM-as-judge & 32B (NF4) & 1 & 71.69 \\
42	\bottomrule
43	\end{tabular}}
44	\end{table}
45	
46	Fine-tuned \cls{} achieves 88.43\% ($\pm$0.78), compared to 87.19\% ($\pm$0.37) for \cwm{} and 86.30\% ($\pm$0.97) for TRAJ. The \cls{}--\cwm{} gap is 1.24\pp{}, modest at this complexity level where generation is not yet bottlenecked by token budget or string complexity. Zero-shot baselines lag substantially (64.40\% at 8B, 71.69\% at 32B NF4), confirming that task-specific fine-tuning is necessary for reliable verification.
47	
48	
49	\subsection{Scaling Behavior}
50	\label{sec:scaling}
51	
52	Table~\ref{tab:scaling} compares \cls{} and \cwm{} at two model sizes using three matched seeds (42, 123, 456), all trained in full bfloat16 precision to ensure a controlled comparison.
53	
54	\begin{table}[t]
55	\centering
56	\small
57	\caption{Model-size scaling: \cls{} vs.\ \cwm{} accuracy (\%) at 4B and 8B. Three matched seeds in full precision. The \cls{}--\cwm{} gap widens from 1.18\pp{} to 2.43\pp{}.}
58	\label{tab:scaling}
59	\setlength{\tabcolsep}{4pt}
60	\begin{tabular}{llccccc}
61	\toprule
62	\textbf{Method} & \textbf{Size} & \textbf{s42} & \textbf{s123} & \textbf{s456} & \textbf{Mean} & \textbf{Gap} \\
63	\midrule
64	\cls{} & 4B & 87.83 & 89.52 & 87.88 & 88.41 & \multirow{2}{*}{1.18} \\
65	\cwm{} & 4B & 87.51 & 87.20 & 86.98 & 87.23 & \\
66	\midrule
67	\cls{} & 8B & \textbf{90.48} & 89.40 & 88.31 & \textbf{89.40} & \multirow{2}{*}{\textbf{2.43}} \\
68	\cwm{} & 8B & 87.67 & 86.98 & 86.24 & 86.96 & \\
69	\bottomrule
70	\end{tabular}
71	\end{table}
72	
73	At 4B, \cls{} and \cwm{} are separated by 1.18\pp{} on the matched three-seed subset. At 8B, the gap more than doubles to 2.43\pp{} (Figure~\ref{fig:scaling_gap}). Clustered bootstrap analysis yields a mean gap of 2.26\pp{} ($p = 0.0066$, 95\% CI $[1.80, 2.71]$), confirming the widening is not a sampling artifact.
74	
75	The asymmetry in scaling efficiency is striking: from 4B to 8B, \cls{} gains +0.99\pp{} (88.41 $\to$ 89.40) while \cwm{} loses $-$0.27\pp{} (87.23 $\to$ 86.96). The additional model capacity benefits classification---where the model needs only to discriminate pass from fail---but provides no measurable improvement for generation, where the model must additionally produce exact output strings. This pattern is consistent with the hypothesis that the string-prediction bottleneck, not model capacity, bounds \cwm{} accuracy. However, the \cwm{} regression ($-$0.27\pp{}) falls within seed noise (3-seed std ${\sim}$0.5\pp{}) and could reflect suboptimal hyperparameter transfer rather than a fundamental bottleneck. Whether this divergence amplifies at repository-level complexity is examined in \S\ref{sec:repo}.
76	
77	
78	\subsection{Per-Test vs.\ Trajectory-Level Equivalence}
79	\label{sec:equivalence}
80	
81	We compare \cls{} (aggregated via all-pass rule) against TRAJ on 523 variant-level instances across five seeds. The pooled gap is $-$0.45\pp{} (95\% CI [$-$1.71, +0.84]); the TOST equivalence test confirms statistical equivalence at $p = 0.007$ ($\pm$2\pp{} margin). Within-problem predictions are correlated (ICC $= 0.191$, $p < 0.0001$, DEFF $= 3.97$); all statistical tests use clustered bootstrap accordingly. Per-test classification thus provides diagnostic information---which specific tests fail---at no cost to variant-level accuracy.
82	
83	
84	\subsection{Accuracy-Utility Frontier}
85	\label{sec:oracle-results}
86	
87	Oracle analysis on SWE-bench Verified (500 instances) reveals that per-test advantage concentrates sharply: at $T = 1$ F2P tests (68.7\% of instances), per-test and trajectory-level are informationally equivalent. The advantage materializes at $T \geq 2$ (31.3\%), with $T = 2$ alone contributing 55.3\% of the total 10.93\pp{} block-correlated advantage. Pass-to-pass (P2P) regression is negligible (1.04\% mean, 0\% median), so the practical value concentrates in fail-to-pass discrimination. Full stratification and the i.i.d.\ vs.\ block-correlated comparison appear in Appendix~\ref{app:oracle}.
88	
89	
90	\subsection{Repo-Level Results}
91	\label{sec:repo}
92	
93	Table~\ref{tab:repo_level} compares \cls{} and \cwm{} on SWE-bench Verified per-test classification at repository-level complexity. All checkpoints are selected by validation accuracy; the test set ($n{=}9{,}784$) has zero problem overlap with validation. We report both overall accuracy (where unparseable outputs default to the majority class, pass) and parseable-only accuracy to disentangle generation quality from default assignment effects.
94	
95	\begin{table}[t]
96	\centering
97	\small
98	\caption{Repo-level per-test verification on SWE-bench Verified test set ($n{=}9{,}784$, val-selected checkpoints). Parse Acc: accuracy computed only on parseable outputs. Unparseable \cwm{} outputs default to pass (majority class, 72.96\%).}
99	\label{tab:repo_level}
100	\resizebox{\columnwidth}{!}{%
101	\setlength{\tabcolsep}{3pt}
102	\begin{tabular}{llcccccc}
103	\toprule
104	\textbf{Method} & \textbf{Size} & \textbf{Seed} & \textbf{Acc (\%)} & \textbf{Macro \fone{}} & \textbf{Unparse (\%)} & \textbf{Parse Acc (\%)} & \textbf{vs Maj.\ (\pp{})} \\
105	\midrule
106	\cls{} & 4B & 42 & \textbf{83.63} & 75.63 & 0.0 & --- & +10.67 \\
107	\cwm{} & 4B & 42 & 58.04 & 51.67 & 53.7 & 42.88 & $-$14.92 \\
108	\cwm{} & 4B & 123 & 59.09 & 43.43 & 67.2 & 42.68 & $-$13.87 \\
109	\midrule
110	\cls{} & 8B & 42 & 84.48 & 78.17 & 0.0 & --- & +11.52 \\
111	\cls{} & 8B & 123 & 85.60 & 78.38 & 0.0 & --- & +12.64 \\
112	\cwm{} & 8B & 42 & 65.17 & --- & 73.8 & 38.52 & $-$7.79 \\
113	\midrule
114	Majority & --- & --- & 72.96 & --- & --- & --- & --- \\
115	\bottomrule
116	\end{tabular}}
117	\end{table}
118	
119	\paragraph{Same-size gap magnitude.} The \cls{}--\cwm{} gap at 4B is 25.59\pp{} (\cls{} 83.63\% vs.\ \cwm{} 58.04\%, seed 42; Figure~\ref{fig:scaling_gap}); at 8B it is 19.31\pp{} (84.48\% vs.\ 65.17\%). Both gaps far exceed the function-level gap (1--2\pp{}, Table~\ref{tab:scaling}), confirming that the classification advantage is complexity-dependent. \cwm{} falls below the majority baseline at both scales ($-$14.92\pp{} at 4B, $-$7.79\pp{} at 8B), indicating negative utility.
120	
121	\paragraph{Overall accuracy is misleading.} The apparent \cwm{} ``improvement'' from 4B (58.04\%) to 8B (65.17\%) is an artifact of the default assignment protocol: unparseable outputs receive the majority-class label (pass, 72.96\% of the test set). As unparseable rate \emph{increases} from 53.7\% to 73.8\%, more predictions are replaced by this high-accuracy default, inflating overall accuracy. The parseable-only accuracy---which isolates actual generation quality---\emph{decreases} from 42.88\% (4B) to 38.52\% (8B), confirming that CWM generation degrades with scale at repository-level complexity.
122	
123	\paragraph{Generation quality degrades uniformly.} Per-mutation analysis of \cwm{} 8B reveals degradation across all categories relative to 4B. The gold mutation (unmodified code) is most striking: parse rate collapses from 43.5\% (4B) to 23.9\% (8B), with parseable accuracy at 16.5\%---far below the trivially-correct ``pass'' prediction. This indicates that even the simplest generation target (reproducing expected outputs for correct code) becomes harder at scale, consistent with a fundamental generation bottleneck rather than insufficient capacity. Detailed per-mutation breakdown appears in Appendix~\ref{app:repo_mutation}.
124	
125	\paragraph{Scaling evidence.} The correct scaling signal comes from function-level results (\S\ref{sec:scaling}), where the \cls{}--\cwm{} gap widens from 1.18\pp{} (4B) to 2.43\pp{} (8B, $p = 0.0066$) with controlled methodology (matched seeds, same precision, no default assignment). At repo-level, the primary claim is that absolute gap magnitude (19--26\pp{}) is an order of magnitude larger than at function level (1--2\pp{}), demonstrating complexity-dependent advantage.
126	
127	\paragraph{Sequence length.} A matched-context ablation confirms input context disparity explains $<$3\% of the \cls{}--\cwm{} gap: \cls{} 8B evaluated at \texttt{max\_seq\_length}$=$2,048 yields a matched-context gap of 25.00\pp{}, representing 98\% of the same-size 25.59\pp{} gap (Appendix~\ref{app:ablations}).
128	
129	\paragraph{Limitations.} The same-size 4B comparison uses a single seed; \cls{} 4B seed 123 (val-best ckpt-800) achieves only 75.33\% test accuracy (+2.4\pp{} above majority baseline), indicating that val-best selection at an early checkpoint (step 800) amplifies the val-test distribution shift observed across all configurations. The \cwm{} 8B comparison is also single-seed. The validation and test sets have zero problem overlap but differ in mutation type composition, introducing potential distribution shift. All repo-level results use val-selected checkpoints, and checkpoint selection variance could contribute to observed differences. Our training data is synthetically constructed from mutation operators rather than real developer patches; the synthetic-to-real transfer gap remains untested.
130	
131	
132	\subsection{Analysis}
133	\label{sec:analysis}
134	
135	\paragraph{(a) Error complementarity.}
136	\cls{} and \cwm{} make errors in opposite directions at function level. Among \cls{} errors (seed 42), 75.5\% are false negatives (FAIL $\to$ PASS), meaning the classifier tends to over-predict passing. Among \cwm{} errors, 83.1\% are false positives (PASS $\to$ FAIL), reflecting string-matching failures that incorrectly reject correct outputs. An oracle combination that takes the correct answer whenever either model is right achieves 90.63\% accuracy, a 3.12\pp{} improvement over \cls{} alone (87.51\%). This complementarity suggests that ensemble approaches combining classification and generation signals could yield further gains.
137	
138	\paragraph{(b) CWM error mode breakdown.}
139	Among unparseable \cwm{} outputs, 76.9\% contain no execution keywords; 22.9\% contain ambiguous co-occurring pass/fail keywords. Format compliance varies sharply across repositories (scikit-learn: near-zero unparseable; sphinx: 100\%), suggesting domain-specific code contexts prevent structured generation.
140	
141	\paragraph{(c) Relaxed matching does not rescue \cwm{}.}
142	Relaxed matching (tolerating format deviations, L0--L4) \emph{decreases} \cwm{} accuracy: 58.04\%$\to$56.98\% (seed 42) and 59.09\%$\to$55.91\% (seed 123). Unparseable predictions default to the majority class (pass, 72.96\%), which outperforms the model's own parseable predictions (42--53\%). The \cls{}--\cwm{} gap widens from 26\pp{} to 28\pp{}, ruling out the hypothesis that parsing strictness inflates the observed gap.
143	
144	\paragraph{(d) Variance compression.}
145	\cwm{}'s 5-seed standard deviation (0.37\pp{}) is lower than \cls{} (0.78\pp{}) and TRAJ (0.97\pp{}) at function level. This is consistent with the bottleneck hypothesis: if \cwm{} performance is capped by output-format constraints, seed-to-seed variability is compressed relative to formulations whose performance depends more on learned representations.
146	
147	\paragraph{(e) Per-test precision and recall.}
148	\cls{} achieves fail \fone{} 87.86\% (precision 82.75\%, recall 93.64\%) at seed 42, with 42.1\% of problems perfectly predicted. Multi-F2P instances (6--10 tests) reach 96.3\% accuracy, corroborating the oracle finding.
149	
150	\paragraph{(f) Block correlation.}
151	Within-problem errors are correlated (ICC $= 0.191$, DEFF $= 3.97$, 2.81$\times$ more all-correct problems than i.i.d.\ expectation). All tests use clustered bootstrap accordingly.
152	
153	\paragraph{(g) LoRA rank and majority voting.}
154	Doubling adapter capacity (rank 32) does not improve \cwm{} accuracy ($-$0.51\pp{}, within seed variance); majority voting ($K{=}3$) decreases accuracy ($-$0.68\pp{}). Both confirm the bottleneck is formulation-level, not capacity-level (Appendix~\ref{app:ablations}).
155	
156	\paragraph{(h) Per-mutation scaling patterns.}
157	Scaling benefits are highly non-uniform across mutation types (Appendix, Table~\ref{tab:mutation_breakdown}). \texttt{off\_by\_one} is the largest \cls{} scaling beneficiary: accuracy jumps from 58.5\% (4B) to 83.0\% (8B mean, $+$24.6\pp{}). In contrast, \texttt{boundary\_removal} is scale-invariant at ${\sim}$46\% across all seeds and sizes, identifying a difficulty ceiling independent of capacity. For \cwm{}, gold mutation parse rate collapses from 43.5\% (4B) to 23.9\% (8B) despite being the simplest target---all tests pass by construction---indicating that generation capability degrades even for trivially correct code at larger scale.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "66c818aa-a1a5-4817-a0a8-64837e0f50d2",
  "isSidechain": true,
  "promptId": "56caabaf-ab9c-4b84-b3a0-6c8eb12d6fab",
  "agentId": "adf9e97eee990f313",
  "type": "user",
  "uuid": "8eb20565-d6bb-416d-ac70-018cf18f6b41",
  "sourceToolAssistantUUID": "66c818aa-a1a5-4817-a0a8-64837e0f50d2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 6 · 2026-05-16T08:26:32.689Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CyEwP2SY2ecQWT5WhKyHtH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "8eb20565-d6bb-416d-ac70-018cf18f6b41",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vsmy2K8jR4vLTVnG1V",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "2875dca8-c6a5-42b9-b36e-29f0ca4a13cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LrsTX8efRvZZ4jciZbHqJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7063,
      "cache_read_input_tokens": 8950,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 7063,
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

_source line 7 · 2026-05-16T08:26:32.695Z_

<details><summary>↩ Tool result · `toolu_01CyEwP2SY2ecQWT5WhKyHtH`</summary>

```text
1	% Method section — EMNLP 2026 ARR submission
2	% Classification Succeeds Where Generation Stalls:
3	% Reformulating Execution Simulation for Code Repair Verification
4	
5	\section{Method}
6	\label{sec:method}
7	
8	Let $p$ denote a candidate patch and $T = \{t_1, \ldots, t_n\}$ its test suite, where each $t_i$ has label $y_i \in \{\text{\textsc{Pass}}, \text{\textsc{Fail}}\}$ from execution. Tests decompose into \emph{fail-to-pass} ($T_{\text{f2p}}$) and \emph{pass-to-pass} ($T_{\text{p2p}}$) subsets; a patch is correct iff $\forall\, t_i{:}\ y_i = \text{\textsc{Pass}}$. We compare three formulations for predicting correctness without execution.
9	
10	\subsection{Verification Formulations}
11	\label{sec:formulations}
12	
13	Let $c_p$ denote the code context (unified diff) of patch $p$.
14	
15	\paragraph{\cls{} (per-test classification).} $f(c_p, t_i) \rightarrow \hat{y}_i \in \{\text{\textsc{Pass}}, \text{\textsc{Fail}}\}$ predicts a single binary token per test (cross-entropy loss). Patch verdict: $\hat{y}_p = \bigwedge_{i} [\hat{y}_i = \text{\textsc{Pass}}]$. Cost: one token per test.
16	
17	\paragraph{\cwm{} (output generation).} $g(c_p, t_i) \rightarrow \hat{o}_i \in \Sigma^*$ generates the execution output string (language modeling loss). Verdict by exact match: $\hat{y}_i = \text{\textsc{Pass}}$ iff $\hat{o}_i = o_i^*$.\footnote{Exact string matching is conservative, consistent with \citet{meta2025cwm}. Semantic equivalences are not counted.} When the generated output is unparseable (i.e., does not conform to the expected structured format), the prediction defaults to the majority class verdict. Cost: $\sum_i |\hat{o}_i|$ tokens.
18	
19	\paragraph{\traj{} (trajectory-level).} $h(c_p, T) \rightarrow \hat{y}_p \in \{\text{\textsc{Resolved}}, \text{\textsc{Unresolved}}\}$ predicts a single patch verdict from all tests, providing no per-test signal. \traj{} serves as a granularity control: \cls{}--\traj{} differences reflect per-test decomposition value.
20	
21	\subsection{\cwm{} Failure Modes}
22	\label{sec:failure-modes}
23	
24	The generation formulation introduces three systematic failure modes absent in classification: (1)~\emph{token-budget exhaustion}---when $|o_i^*| > B$, truncation guarantees exact-match failure; (2)~\emph{string-value prediction errors}---semantically equivalent outputs differing in surface form (floating-point precision, dictionary ordering) produce false negatives; even under optimistic independence assumptions, a sequence of $L$ tokens each with accuracy $q$ yields correct-sequence probability $q^L$, making long outputs exponentially harder; (3)~\emph{format compliance collapse}---at repository-level complexity, the model fails to produce structured predictions entirely, even when the generation budget is sufficient. We hypothesize that the increased input complexity and multi-file context at repository level overwhelm the model's ability to maintain format adherence across the generation; per-repository unparseable rates support this (\S\ref{sec:analysis}). We adopt exact string matching following the original \cwm{} evaluation protocol \citep{meta2025cwm}. This is conservative but does not disadvantage \cwm{}: the dominant failure at repository scale is format non-compliance, where outputs are structurally unparseable regardless of matching strategy. Unparseable \cwm{} predictions---those that cannot be parsed into a structured verdict---default to the majority-class label (\textsc{Pass}), equivalent to the majority baseline prediction. This favors \cwm{} by assigning the statistically most likely label rather than penalizing format failures.
25	
26	\cls{} bypasses all three by construction: its single-token output cannot be truncated, requires no string matching, and is always parseable. Classification reduces the output space from $\Sigma^*$ to $\{\text{\textsc{Pass}}, \text{\textsc{Fail}}\}$---strictly lower output complexity, though the underlying reasoning need not be simpler. We hypothesize a \emph{complexity-dependent advantage}: both formulations perform comparably on simple code, but \cls{} gains as output complexity triggers \cwm{} failure modes.
27	
28	\subsection{Oracle Accuracy-Utility Framework}
29	\label{sec:oracle}
30	
31	Per-test granularity is valuable only when per-test predictions are sufficiently accurate and multiple tests provide partially independent signals. Consider a buggy patch with $k = |T_{\text{f2p}}|$ fail-to-pass tests. A per-test verifier with recall $r$ detects the bug if it identifies at least one failing test:
32	%
33	\begin{equation}
34	  P_{\text{detect}}(k) = 1 - (1 - r)^{k_{\text{eff}}}
35	  \label{eq:pdetect}
36	\end{equation}
37	%
38	where $k_{\text{eff}}$ is the effective number of independent tests. Let $a_h$ denote the trajectory-level detection accuracy; it is independent of $k$.
39	
40	\paragraph{Block-correlation model.} Per-test predictions within the same patch are correlated. We model this via the intraclass correlation coefficient $\rho$ \citep[ICC;][]{shrout1979icc}:
41	%
42	\begin{equation}
43	  k_{\text{eff}} = \frac{k}{1 + (k - 1)\rho}
44	  \label{eq:keff}
45	\end{equation}
46	%
47	When $\rho = 0$, $k_{\text{eff}} = k$ (full independence); when $\rho = 1$, $k_{\text{eff}} = 1$ (per-test collapses to trajectory-level). The per-test advantage relative to a trajectory-level baseline is $\Delta(k) = P_{\text{detect}}(k) - a_h$, and the expected population advantage is:
48	%
49	\begin{equation}
50	  \mathbb{E}[\Delta] = \sum_{k=1}^{K} P(|T_{\text{f2p}}| = k) \cdot \Delta(k)
51	  \label{eq:expected-advantage}
52	\end{equation}
53	
54	\paragraph{Testable predictions.} This yields three predictions validated in \S\ref{sec:experiments}: (1)~at $k = 1$, $\Delta \approx 0$; (2)~$\Delta(k)$ increases with $k$, dampened by $\rho > 0$; (3)~$\mathbb{E}[\Delta]$ concentrates in multi-F2P-test instances.
55	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "2875dca8-c6a5-42b9-b36e-29f0ca4a13cf",
  "isSidechain": true,
  "promptId": "56caabaf-ab9c-4b84-b3a0-6c8eb12d6fab",
  "agentId": "adf9e97eee990f313",
  "type": "user",
  "uuid": "0c99cad3-cfdc-46bc-857e-09b42910cc8f",
  "sourceToolAssistantUUID": "2875dca8-c6a5-42b9-b36e-29f0ca4a13cf",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 8 · 2026-05-16T08:26:33.230Z_

<details open><summary>🔧 Tool call — Read · `toolu_018ULoeXpRWfB1iwKhvkiM3v`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "0c99cad3-cfdc-46bc-857e-09b42910cc8f",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vsmy2K8jR4vLTVnG1V",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "74568f64-7bb7-46e5-9dfb-f7194acc2250",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LrsTX8efRvZZ4jciZbHqJ",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 7063,
      "cache_read_input_tokens": 8950,
      "output_tokens": 254,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 7063
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 2,
          "output_tokens": 254,
          "cache_read_input_tokens": 8950,
          "cache_creation_input_tokens": 7063,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 7063,
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

_source line 9 · 2026-05-16T08:26:33.236Z_

<details><summary>↩ Tool result · `toolu_018ULoeXpRWfB1iwKhvkiM3v`</summary>

```text
1	\documentclass[11pt]{article}
2	
3	% ACL style (review mode for anonymous ARR submission)
4	\usepackage[review]{acl}
5	
6	% Math
7	\usepackage{amsmath}
8	\usepackage{amssymb}
9	
10	% Tables
11	\usepackage{booktabs}
12	\usepackage{multirow}
13	\usepackage{tabularx}
14	
15	% Graphics
16	\usepackage{graphicx}
17	\graphicspath{{../../artifacts/}}
18	
19	% Lists
20	\usepackage{enumitem}
21	
22	% Custom commands
23	\newcommand{\cls}{\textsc{Cls}}
24	\newcommand{\cwm}{\textsc{Cwm}}
25	\newcommand{\traj}{\textsc{Traj}}
26	\newcommand{\fone}{F\textsubscript{1}}
27	\newcommand{\pp}{\,\text{pp}}
28	
29	\title{Classification Succeeds Where Generation Stalls:\\Reformulating Execution Simulation for Code Repair Verification}
30	\author{Anonymous}
31	
32	\begin{document}
33	\maketitle
34	
35	\input{abstract}
36	
37	\input{introduction}
38	
39	\begin{figure*}[t]
40	\centering
41	\includegraphics[width=\textwidth]{figures/paper/fig1_reformulation.pdf}
42	\caption{Three verification formulations. \textbf{Left:} \cls{} predicts binary pass/fail per test. \textbf{Center:} \cwm{} generates execution output, derives verdict by exact match. \textbf{Right:} Trajectory-level scoring predicts patch-level resolved/unresolved. \cls{} eliminates generation failure modes while preserving per-test diagnostic granularity.}
43	\label{fig:reformulation}
44	\end{figure*}
45	
46	\input{method}
47	
48	\input{experiments}
49	
50	\begin{figure}[t]
51	\centering
52	\includegraphics[width=\columnwidth]{figures/paper/fig2_scaling_gap.pdf}
53	\caption{Gap amplification from function-level to repo-level complexity. Function-level: \cls{}--\cwm{} gap is 1.24\pp{} at 4B (5 seeds), widening to 2.43\pp{} at 8B (3 seeds, bootstrap $p{<}.01$). Repo-level same-size 4B: the gap explodes to 25.59\pp{}, with \cwm{} falling below the majority baseline (72.96\%).}
54	\label{fig:scaling_gap}
55	\end{figure}
56	
57	
58	\input{related_work}
59	
60	\input{conclusion}
61	
62	\bibliography{references}
63	
64	\input{appendix}
65	
66	\end{document}
67	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "74568f64-7bb7-46e5-9dfb-f7194acc2250",
  "isSidechain": true,
  "promptId": "56caabaf-ab9c-4b84-b3a0-6c8eb12d6fab",
  "agentId": "adf9e97eee990f313",
  "type": "user",
  "uuid": "226eebb3-18da-4f61-a895-8e4cda524eb4",
  "sourceToolAssistantUUID": "74568f64-7bb7-46e5-9dfb-f7194acc2250",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Tool call

_source line 10 · 2026-05-16T08:26:37.483Z_

<details open><summary>🔧 Tool call — Read · `toolu_01MwGM8KSns7Vz1F8KuCtNtF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "226eebb3-18da-4f61-a895-8e4cda524eb4",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vtBuBZYy2R3nKeEhgq",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "c2991bab-6989-4122-beb2-3e350beb8ba8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AExj2ZcM9LT5TzqPrWfiEz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9296,
      "cache_read_input_tokens": 16013,
      "output_tokens": 92,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 9296
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 92,
          "cache_read_input_tokens": 16013,
          "cache_creation_input_tokens": 9296,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 9296,
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

_source line 11 · 2026-05-16T08:26:37.487Z_

<details><summary>↩ Tool result · `toolu_01MwGM8KSns7Vz1F8KuCtNtF`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{Execution Simulation for Code.}
5	Code World Models~\cite{meta2025cwm} mid-train a 32B LLM on execution traces to predict output strings, establishing the generation-based paradigm for execution-free code verification.
6	Self-Execution~\cite{maimon2026selfexecution} extends this with step-by-step trace prediction, demonstrating that simulation-based self-verification can improve code generation without external execution.
7	CodeMind~\cite{liu2024codemind} evaluates code reasoning along multiple dimensions including independent and dependent execution reasoning.
8	SolidCoder~\cite{lee2026solidcoder} bridges mental simulation and actual execution via concrete execution feedback.
9	Abdollahi et al.~\cite{abdollahi2025demystifying} identify systematic failure modes in LLM trace prediction, including position-dependent and cascading errors.
10	All share a generation formulation whose cost scales with output length and whose reliability degrades when outputs are complex---at repository-level complexity, we observe format compliance collapse (53--67\% unparseable outputs; \S\ref{sec:experiments}). We reformulate as per-test classification and show the advantage is complexity-dependent: negligible at function level but critical at repository scale.
11	
12	\paragraph{LLM-based Verification for Code Repair.}
13	SWE-RM~\cite{shum2025swerm} trains a 30B MoE reward model for trajectory-level execution-free patch ranking, achieving strong results on SWE-bench without test execution.
14	Patch Reasoner~\cite{xu2025patchreasoner} uses chain-of-thought reasoning for patch verification.
15	Snell et al.~\cite{snell2024scaling} show that test-time compute scaling via verification can outperform parameter scaling, establishing verification quality as a key lever for code generation improvement.
16	S*~\cite{li2025sstar} combines execution-grounded selection with model-based scoring for efficient test-time scaling.
17	VG-Search~\cite{chen2025vgsearch} studies how verification granularity affects compute-efficient scaling, finding that finer-grained verification can improve selection efficiency.
18	These works treat verification granularity as a design choice but do not compare the underlying \emph{formulation}---classification vs.\ generation---at controlled capacity. We formally compare per-test and trajectory-level granularity, showing statistical equivalence (TOST $p = 0.007$) with additional per-test diagnostic signals.
19	
20	\paragraph{Learned Code Verifiers.}
21	LEVER~\cite{ni2023lever} trains a classifier to re-rank code candidates by predicting execution correctness, learning verification from execution feedback.
22	CodeT~\cite{chen2023codet} generates auxiliary test cases and uses dual execution agreement---consensus between generated code and generated tests---as a verification signal.
23	Both methods leverage execution signals during training but target execution-free deployment, a goal shared by our classification formulation. Unlike LEVER's candidate-level ranking and CodeT's agreement-based filtering, we provide \emph{per-test} diagnostic verdicts that identify which specific tests fail, and systematically compare classification against generation on the same model, data, and compute budget, isolating the effect of task formulation.
24	
25	\paragraph{Automated Program Repair.}
26	SWE-bench~\cite{jimenez2024swebench} and SWE-bench Verified~\cite{chowdhury2024swebenchverified} provide standard benchmarks for repository-level repair, driving rapid progress in LLM-based program repair.
27	SWE-agent~\cite{yang2024sweagent} uses tool-augmented agents while Agentless~\cite{xia2024agentless} demonstrates a simpler localize--repair--validate pipeline that achieves competitive results.
28	Yang et al.~\cite{yang2025aprsurvey} survey the broader landscape of LLM-based program repair, identifying verification as a persistent bottleneck across approaches.
29	These systems rely on execution-based validation as the final filter, with verification cost scaling linearly in the number of candidates. Per-test classification provides failure-localized signals that could inform targeted re-repair---re-generating only the code responsible for a specific failing test---a capability absent from trajectory-level verifiers.
30	
31	\paragraph{Classification vs.\ Generation in NLP.}
32	Task framing affects model performance across NLP: T5~\cite{raffel2020t5} and BART~\cite{lewis2020bart} show generation--classification tradeoffs under controlled capacity, while SQuAD~\cite{rajpurkar2016squad} demonstrates that constraining output space (span extraction vs.\ generation) can simplify tasks without sacrificing quality. We extend this lens to code verification, identifying code complexity as the key moderator of the classification--generation tradeoff.
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c2991bab-6989-4122-beb2-3e350beb8ba8",
  "isSidechain": true,
  "promptId": "56caabaf-ab9c-4b84-b3a0-6c8eb12d6fab",
  "agentId": "adf9e97eee990f313",
  "type": "user",
  "uuid": "018a6bcb-9095-45c1-a2cc-9168ab5e2c76",
  "sourceToolAssistantUUID": "c2991bab-6989-4122-beb2-3e350beb8ba8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master"
}
```

</details>

---

### Assistant

_source line 12 · 2026-05-16T08:27:06.713Z_

Now I have a thorough understanding of the paper. Let me compose my R2 response to R1's review.

---

## R2 Response to R1's Review

**On the repo-level confound (R1 W1-W2):** R1's critique here is sharper than mine and I agree it is the most damaging point against the paper. I flagged the CWM comparison as unfair because it uses a LoRA 4B/8B reproduction rather than the original 32B; R1 goes further and argues the 50-93% unparseable rate makes the entire repo-level comparison uninformative as a scientific claim. I concur. The paper's headline result -- "25pp gap at repo level" -- is doing a lot of rhetorical work, but if the CWM baseline is essentially broken, this tells us nothing about whether classification is inherently superior to generation at scale. It tells us this particular LoRA fine-tuning recipe fails at generation for repo-level inputs. The authors do acknowledge this in their limitations paragraph, but the framing throughout the paper treats it as evidence for a "complexity-dependent advantage" rather than what it more parsimoniously is: an implementation failure.

**On seed instability (R1 W2):** The CLS 4B seed123 result of 75.33% (+2.4pp above majority) is alarming and I missed it. This means the paper's repo-level CLS numbers rest almost entirely on a single seed (seed42). Combined with R1's observation that the 8B CWM comparison is also single-seed, the repo-level story is underpowered to the point where I question whether it should be a central claim at all.

**On the learning rate discrepancy (R1 Q4):** Code says 2e-4, paper says 5e-5 -- this is a straightforward reproducibility defect. If the actual training used 2e-4 for both CLS and CWM, the CWM 8B "degradation" could easily be hyperparameter mismatch rather than a formulation bottleneck. R1 is right to flag this.

**On TOST margin (R1 W4):** I initially accepted Claim 2 (per-test vs trajectory equivalence) at face value. R1's point that the 2pp margin is unjustified and that mixing bf16/NF4 seeds introduces a confound is well-taken. The equivalence claim is only as strong as the margin choice, and 2pp feels suspiciously convenient -- just wide enough to capture the observed gap.

**On synthetic mutations (R1 W5):** I did not flag this, and I should have. Five mutation operators on HumanEval/MBPP is a narrow distribution. The paper's transfer claim to SWE-bench partially addresses this, but the SWE-bench data is also synthetically mutated, not real developer patches. The entire experimental pipeline operates in a synthetic-mutation bubble. I agree this is a weakness.

**Disagreements with R1:** Minor. R1 gives Reproducibility 4/5 despite the learning rate discrepancy, which seems generous. I also think R1 could have been harder on the DeepSeek reversal -- a result where CWM beats CLS on a different model family is not just a "generalizability concern," it potentially falsifies the core thesis that classification is inherently advantageous.

**Score adjustment:** R1's methodological critique of the repo-level results reinforces my skepticism from the novelty side. The paper's strongest claim (massive repo-level gap) is built on confounded, single-seed comparisons. I maintain my **Weak Reject (3/6)** but my confidence increases from 4/5 to 5/5. The function-level results are clean but incremental (1-2pp); the repo-level results are dramatic but unreliable. The paper falls between these two stories without convincingly delivering either.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "018a6bcb-9095-45c1-a2cc-9168ab5e2c76",
  "isSidechain": true,
  "agentId": "adf9e97eee990f313",
  "requestId": "req_011Cb5vtWBXZ65gsHvmhTy4x",
  "attributionAgent": "general-purpose",
  "type": "assistant",
  "uuid": "59d16c34-7dee-4395-889f-a8935fc20de8",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_16/projects/exec-sim-repair-verifier",
  "sessionId": "5dda3937-f1b2-4375-bd1e-e2d91b9b5207",
  "version": "2.1.126",
  "gitBranch": "master",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EknokQEnUPpDDDqay53Td4",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1303,
      "cache_read_input_tokens": 25309,
      "output_tokens": 905,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1303
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 1,
          "output_tokens": 905,
          "cache_read_input_tokens": 25309,
          "cache_creation_input_tokens": 1303,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1303,
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
