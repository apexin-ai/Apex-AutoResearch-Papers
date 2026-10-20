# writing method rewrite direction a

**Death Avoidance as the Dominant Routing Signal: A Counterfactual Analysis on ScienceWorld** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 11
- **Recorded user turns:** 0
- **Tool calls:** 5
- **Original source:** `logs/chats/worker_writing_method-rewrite-direction-a_20260516T190205.jsonl`
- **Structured JSON:** [`b623383e819b59dd488f.json`](../../sessions/b6/b623383e819b59dd488f.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Before a recorded user message

11 recorded events

### Tool call

_source line 1 · 2026-05-16T19:04:10.803587+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex"
  }
}
```

</details>

---

### Tool result

_source line 2 · 2026-05-16T19:04:10.804039+00:00_

1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Setup}
5	\label{sec:problem-setup}
6	
7	Consider an interactive environment $\mathcal{E}$ with state space $\mathcal{S}$, observation space $\mathcal{O}$, and action space $\mathcal{A}$. An agent follows a policy $\pi: \mathcal{O}^* \rightarrow \mathcal{A}$ that maps observation histories to actions. At each step $t$, the agent receives observation $o_t$, selects action $a_t = \pi(o_1, \ldots, o_t)$, and the environment transitions to state $s_{t+1}$.
8	
9	We define a modality set $\mathcal{M} = \{{\tt int}, {\tt det}\}$ governing how the agent processes state transitions:
10	\begin{itemize}
11	    \item \textbf{Internal} ($m = {\tt int}$): The agent uses its own generation to predict intermediate observations. The LLM interleaves chain-of-thought reasoning with environment actions following the ReAct paradigm \cite{react-2023}, but prediction errors compound across steps.
12	    \item \textbf{Deterministic} ($m = {\tt det}$): The agent receives ground-truth observations from the environment simulator at each step---equivalent to access to a perfect dynamics model. Action selection remains with the LLM; only the state-transition prediction is replaced.
13	\end{itemize}
14	
15	\noindent We restrict $\mathcal{M}$ to two modalities. An ablation comparing chain-of-thought reasoning (deep internal) against direct-answer generation (fast internal) on 6 overlapping task types ($n{=}120$ episodes per condition) found no significant difference on any task (Mann--Whitney $p > 0.26$, $|d| \leq 0.31$) and near-identical death rates (41.8\% vs.\ 42.5\%), confirming that reasoning depth does not meaningfully alter internal-mode outcomes in this setting.
16	
17	A \emph{routing policy} $\rho: \mathcal{O}^* \rightarrow \mathcal{M}$ selects which modality to use at each step. The goal of modality routing is to learn $\rho$ that maximizes expected episode return. Our analysis investigates what signal is available to lear
…[truncated 7658 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 3 · 2026-05-16T19:04:10.804263+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/introduction.tex"
  }
}
```

</details>

---

### Tool result

_source line 4 · 2026-05-16T19:04:10.804460+00:00_

1	\section{Introduction}
2	
3	Large language models deployed as interactive agents must repeatedly decide \emph{how} to compute: reason internally, or delegate to an external tool.
4	A Qwen2.5-7B-Instruct agent navigating ScienceWorld \cite{scienceworld-2022}---a text-based science simulation with 30 task types---faces this choice at every step. Tracking temperature thresholds, container states, and multi-step procedures via internal reasoning is error-prone: the model may hallucinate that water has boiled when the stove was never activated, or that an object has been moved when the action was invalid. Deterministic external computation (environment simulators, code interpreters) eliminates such hallucinations via exact state transitions. The practical question for agent design is therefore: \emph{when should an agent route computation externally versus reasoning internally?}
5	
6	Existing routing approaches frame this as a capability or efficiency decision.
7	Toolformer \cite{toolformer-2023} teaches models to insert API calls when doing so reduces perplexity; ART \cite{art-2023} decomposes tasks into tool-augmented programs; Chameleon \cite{chameleon-2023} selects among heterogeneous modules (search, code, vision) per subtask.
8	More recent adaptive-computation methods route to different reasoning depths \cite{cogrouter-2026,ares-2026} or model tiers \cite{mtrouter-2026}.
9	The shared assumption is that routing signal stems from diverse sources---accuracy, latency, capability matching---and that a learned router can exploit this signal to improve over any fixed strategy.
10	But this assumption has never been systematically verified: \emph{what actually drives the value of routing decisions in interactive environments?}
11	
12	We propose a \emph{formal diagnostic framework} for answering this question. The framework comprises (i)~episode-level counterfactual labeling under pure strategies (\S\ref{sec:collection}--\ref{sec:labeling}), and (ii)~the Death Avoidance Fa
…[truncated 5620 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 5 · 2026-05-16T19:04:10.804626+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/experiments.tex"
  }
}
```

</details>

---

### Tool result

_source line 6 · 2026-05-16T19:04:10.804798+00:00_

1	\section{Experiments}
2	
3	\subsection{Death Avoidance Decomposition}
4	\label{sec:death-decomp}
5	
6	\begin{figure}[t]
7	\centering
8	\includegraphics[width=\columnwidth]{figures/fig1_daf_scatter.pdf}
9	\caption{Per-task scatter: death rate differential (internal $-$ deterministic) vs.\ performance gap ($\Delta_{\text{full}}$). $r = 0.97$, $p < 10^{-6}$, $n = 11$ task types.}
10	\label{fig:decomposition}
11	\end{figure}
12	
13	Across 245 episodes, $\Delta_{\text{full}} = +29.60$; excluding death episodes, $\Delta_{\text{nd}} = +2.84$, yielding DAF $= 90.4\%$ (95\% CI: $[81.6\%, 98.8\%]$; at default $P{=}100$). The penalty-independent death-asymmetry label fraction is 78.9\% (75 of 95 non-tie labels). The internal strategy dies in 42.9\% of episodes versus 16.3\% for deterministic (2.6$\times$). Per-task, death rate differential correlates strongly with $\Delta_{\text{full}}$ ($r = 0.97$, $p < 10^{-6}$; Figure~\ref{fig:decomposition}; robustness diagnostics in Appendix~\ref{app:correlation}). A high correlation is expected whenever the scaled death-rate differential ($P \times \Delta_d$) dominates between-task variance---formally, when $\text{Var}(P \cdot \Delta_d) \gg \text{Var}(\Delta_{\text{nd}})$. At $P{=}100$, this condition holds for all but one task type (\texttt{find-non-living-thing}, which has zero deaths). The sensitivity analysis (Appendix~\ref{app:penalty}) confirms that $r$ drops below significance at $P \leq 25$, where this dominance condition no longer holds. Of 245 episodes, 86 are \texttt{det\_preferred}, 9 \texttt{internal\_preferred}, and 150 \texttt{no\_preference}.
14	
15	One exception: \texttt{find-non-living-thing} ($n{=}40$, zero deaths) has DAF $= 0\%$ with $\Delta = +9.58$ entirely from non-death score differences; all 10 remaining types exceed DAF $> 85\%$. Bootstrap 95\% CIs confirm $\Delta > 0$ for 10 of 11 types; \texttt{chemistry-mix} ($N{=}20$, $\Delta = 21.8$, 95\% CI $[-5.0, 48.6]$) is the sole exception (Appendix~\ref{app:per-ta
…[truncated 3101 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 7 · 2026-05-16T19:04:10.804969+00:00_

called Read

<details open><summary>🔧 Tool call — Read</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/discussion.tex"
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-16T19:04:10.805148+00:00_

1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Cross-environment evidence.}
5	Does routing signal persist without catastrophic failure? On MATH Level~4--5 (300 problems), using a code interpreter as the deterministic modality, internal reasoning directionally outperforms: 81.0\% vs.\ 76.7\% accuracy ($+4.3$~pp, 95\% CI $[0.0, +8.7]$; McNemar $p = 0.079$, not reaching $\alpha{=}0.05$). The label distribution inverts: 30 internal-preferred vs.\ 17 deterministic-preferred (cf.\ 9:86 in ScienceWorld), with 84.3\% no-preference. In the absence of death risk, the death-driven routing signal is not statistically detectable---consistent with death avoidance as the primary driver. A complementary evaluation on ALFWorld ($N{=}135$) confirms that the counterfactual framework identifies different routing mechanisms across environments: the deterministic advantage there stems from information asymmetry (access to admissible actions) rather than death avoidance (Appendix~\ref{app:cross-env}).
6	
7	\paragraph{Penalty sensitivity.}
8	The $r = 0.97$ correlation is specific to catastrophic death (score $= -100$); defining ``failure'' as any non-positive score yields $r = -0.13$ ($p = 0.70$). The correlation emerges only at $P \geq 50$ ($r = 0.86$) and reflects that non-death episodes show near-zero performance differential ($\Delta_{\text{nd}} = 2.84$; Appendix~\ref{app:penalty}). Death is effectively the \emph{only} component generating differential routing signal in ScienceWorld. These findings may be capability-dependent: the 42.9\% internal death rate reflects a 7B model's hallucination vulnerability; larger models with lower death rates would reduce DAF, potentially revealing non-death routing signal currently masked by catastrophic failures.
9	
10	\paragraph{Implications for router design.}
11	The dominance of death avoidance (DAF $= 90.4\%$ at $P{=}100$) reframes modality routing as primarily a \emph{safety} problem rather than an efficiency-quality tradeoff. 
…[truncated 2519 chars]

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Read",
  "elapsed_ms": 0
}
```

</details>

---

### Tool call

_source line 9 · 2026-05-16T19:04:10.805377+00:00_

called Write

<details open><summary>🔧 Tool call — Write</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
  "content": "\\section{Method}\n\\label{sec:method}\n\nOur diagnostic framework quantifies what drives routing signal in interactive environments through three components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\\S\\ref{sec:collection}--\\ref{sec:labeling}); (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:daf}); and (iii)~the Signal Concentration Index (SCI), which measures whether routing signal is concentrated in a few task types or distributed systematically across the environment (\\S\\ref{sec:sci}). Episode-level bootstrap resampling provides 95\\% confidence intervals for all metrics.\n\n\\subsection{Problem Setup}\n\\label{sec:problem-setup}\n\nConsider an interactive environment $\\mathcal{E}$ with state space $\\mathcal{S}$, observation space $\\mathcal{O}$, and action space $\\mathcal{A}$. An agent follows a policy $\\pi: \\mathcal{O}^* \\rightarrow \\mathcal{A}$ that maps observation histories to actions. At each step $t$, the agent receives observation $o_t$, selects action $a_t = \\pi(o_1, \\ldots, o_t)$, and the environment transitions to state $s_{t+1}$.\n\nWe define a modality set $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$ governing how the agent processes state transitions:\n\\begin{itemize}\n    \\item \\textbf{Internal} ($m = {\\tt int}$): The agent uses its own generation to predict intermediate observations. The LLM interleaves chain-of-thought reasoning with environment actions following the ReAct paradigm \\cite{react-2023}, but prediction errors compound across steps.\n    \\item \\textbf{Deterministic} ($m = {\\tt det}$): The agent receives ground-truth observations from the environment simulator at each step---equivalent to access to a perfect dynamics model. Action selection remains with the LLM; only the state-transition prediction is replaced.\n\\end{itemize}\n\n\\noindent We restrict $\\mathcal{M}$ to two modalities. An ablation comparing chain-of-thought reasoning (deep internal) against direct-answer generation (fast internal) on 6 overlapping task types ($n{=}120$ episodes per condition) found no significant difference on any task (Mann--Whitney $p > 0.26$, $|d| \\leq 0.31$) and near-identical death rates (41.8\\% vs.\\ 42.5\\%), confirming that reasoning depth does not meaningfully alter internal-mode outcomes in this setting.\n\nA \\emph{routing policy} $\\rho: \\mathcal{O}^* \\rightarrow \\mathcal{M}$ selects which modality to use at each step. The goal of modality routing is to learn $\\rho$ that maximizes expected episode return. Our analysis investigates what signal is available to learn such a router.\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nPer-step oracle labeling assigns routing labels by comparing single-step outcomes under each computation modality. Under sparse terminal rewards, this approach degenerates: on ScienceWorld \\cite{scienceworld-2022}, 97.4\\% of steps (across 11 prescreened task types) produce identical intermediate scores regardless of modality, yielding no routing signal. We instead perform episode-level counterfactual analysis.\n\n\\paragraph{Pure-strategy trajectories.}\nFor a task instance $t$ and modality $m \\in \\mathcal{M}$, a \\emph{pure-strategy trajectory} is the complete episode obtained by applying modality $m$ at every step:\n\\begin{equation}\n    \\tau_m^{(t)} = (o_1, a_1, o_2, a_2, \\ldots, o_T, a_T)\n\\end{equation}\nwhere $T \\leq T_{\\max}$ is the episode length (capped at $T_{\\max} = 30$ steps). Both trajectories $\\tau_{\\tt int}^{(t)}$ and $\\tau_{\\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), ensuring that performance differences arise solely from the modality.\n\nEach trajectory $\\tau$ yields a terminal score $s(\\tau) \\in \\mathbb{Z}$ and a death indicator $d(\\tau) \\in \\{0, 1\\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:\n\\begin{multline}\n    \\bigl(s^{\\tt int}, s^{\\tt det}, d^{\\tt int}, d^{\\tt det}\\bigr) \\triangleq \\\\\n    \\bigl(s(\\tau_{\\tt int}),\\, s(\\tau_{\\tt det}),\\, d(\\tau_{\\tt int}),\\, d(\\tau_{\\tt det})\\bigr)\n\\end{multline}\n\nWe use Qwen2.5-7B-Instruct (vLLM) on ScienceWorld \\cite{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is environment-agnostic: it requires only paired episode outcomes under two modalities, with no assumptions about score structure or failure mode. We apply it unchanged to ALFWorld and MATH in \\S\\ref{sec:discussion}.\n\n\\subsection{Episode-Level Labeling}\n\\label{sec:labeling}\n\nWe define a labeling function $L$ that maps a counterfactual pair to a routing preference:\n\\begin{multline}\n    L\\!\\bigl(\\tau_{\\tt int}^{(t)}, \\tau_{\\tt det}^{(t)}\\bigr) \\;\\rightarrow \\\\\n    \\ell \\in \\{{\\tt det\\text{-}pref},\\; {\\tt int\\text{-}pref},\\; {\\tt no\\text{-}pref}\\}\n\\end{multline}\n\nThe labeling function is \\emph{death-aware}: it prioritizes survival over score, reflecting the asymmetric cost of catastrophic failure in interactive environments. ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. The full procedure is given in Algorithm~\\ref{alg:labeling}. Figure~\\ref{fig:pipeline} illustrates the overall pipeline.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/pipeline_overview.pdf}\n\\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\\ref{alg:labeling}.}\n\\label{fig:pipeline}\n\\end{figure}\n\n\\begin{algorithm}[t]\n\\caption{Episode-Level Counterfactual Labeling}\n\\label{alg:labeling}\n\\begin{algorithmic}[1]\n\\REQUIRE Task instance $t$, modalities $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$\n\\ENSURE Label $\\ell \\in \\{{\\tt det\\text{-}pref}, {\\tt int\\text{-}pref}, {\\tt no\\text{-}pref}\\}$\n\\FOR{each $m \\in \\mathcal{M}$}\n    \\STATE Run episode $\\tau_m$ with pure-strategy $m$\n    \\STATE Record score $s_m$ and death indicator $d_m$\n\\ENDFOR\n\\IF{$d_{\\tt int} = 1$ \\AND $d_{\\tt det} = 0$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = 0$ \\AND $d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{both dead}\n\\ELSIF{$s_{\\tt det} > s_{\\tt int}$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSIF{$s_{\\tt int} > s_{\\tt det}$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSE\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{tied alive}\n\\ENDIF\n\\RETURN $\\ell$\n\\end{algorithmic}\n\\end{algorithm}\n\nThe four mutually exclusive cases correspond to:\n\\begin{enumerate}\n    \\item \\textbf{Death asymmetry} (lines 5--8): $d^{\\tt int} \\neq d^{\\tt det}$ $\\rightarrow$ the surviving strategy is preferred. This accounts for 78.9\\% of all non-tie labels (75 of 95).\n    \\item \\textbf{Both dead} (lines 9--10): $d^{\\tt int} = d^{\\tt det} = 1$ $\\rightarrow$ ${\\tt no\\_preference}$.\n    \\item \\textbf{Score comparison} (lines 11--14): both survive and $s^{\\tt det} \\neq s^{\\tt int}$ $\\rightarrow$ the higher-scoring strategy is preferred.\n    \\item \\textbf{Tied alive} (lines 15--16): both survive and $s^{\\tt det} = s^{\\tt int}$ $\\rightarrow$ ${\\tt no\\_preference}$.\n\\end{enumerate}\n\nLabel distributions are reported in \\S\\ref{sec:death-decomp}.\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\\delta = \\mathbb{E}[d^{\\tt int}] - \\mathbb{E}[d^{\\tt det}]$ denote the death-rate differential and $\\Delta_{\\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. The full gap decomposes as:\n\\begin{equation}\n    \\Delta_{\\text{full}} \\approx \\underbrace{\\delta \\cdot P}_{\\text{death contribution}} + \\Delta_{\\text{nd}}\n\\end{equation}\nThe approximation holds exactly when the surviving strategy scores zero in all death-asymmetry episodes; in our data, the residual is small ($29.60 - 29.37 = 0.23$, or $0.8\\%$ of $\\Delta_{\\text{full}}$).\n\nWe define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{nd}}}{\\Delta_{\\text{full}}} \\approx \\frac{\\delta P}{\\delta P + \\Delta_{\\text{nd}}}\n\\end{equation}%\n\\footnote{When $\\Delta_{\\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1, indicating death avoidance overcompensates for a non-death disadvantage.}\n\nDAF is well-defined when $\\Delta_{\\text{full}} > 0$; in our data, the minimum per-task $\\Delta_{\\text{full}}$ is $+9.58$ (\\texttt{find-non-living-thing}), ensuring numerical stability. Since DAF $= \\delta P / (\\delta P + \\Delta_{\\text{nd}})$, it increases monotonically with $P$---a mathematical consequence, not an empirical finding. We therefore report both DAF at the environment default ($P{=}100$) and the penalty-independent death-asymmetry label fraction.\n\nTo assess sensitivity to penalty magnitude, we recalculate DAF under hypothetical death penalties (Appendix~\\ref{app:penalty}): $P{=}10 \\rightarrow$ DAF $= 50.4\\%$, $P{=}50 \\rightarrow 82.6\\%$, $P{=}100 \\rightarrow 90.4\\%$, $P{=}200 \\rightarrow 95.0\\%$. Death avoidance remains the dominant component across all penalty magnitudes, though its relative contribution scales with penalty severity. As a penalty-independent companion metric, 78.9\\% of non-tie routing labels (75 of 95) are driven by death asymmetry rather than score comparison (\\S\\ref{sec:labeling}), confirming that death avoidance dominates routing signal regardless of penalty magnitude.\n\n\\paragraph{Statistical inference.}\nWe quantify uncertainty via episode-level bootstrap resampling ($B = 10{,}000$ resamples). Each resample draws $N = 245$ episodes with replacement, recomputes $\\Delta_{\\text{full}}$, $\\Delta_{\\text{nd}}$, and DAF, and derives the percentile-based 95\\% CI. The aggregate DAF CI is $[81.6\\%, 98.8\\%]$, excluding both 50\\% and 100\\%. Per-task bootstrap CIs confirm $\\Delta > 0$ for 10 of 11 task types; \\texttt{chemistry-mix} ($N{=}20$, $\\Delta = 21.8$, CI $[-5.0, 48.6]$) is the sole exception, attributable to small sample size rather than absence of signal.\n\nWe resample at the episode level rather than the step level because the episode is the unit of counterfactual comparison: each episode pair yields one label, and steps within an episode are sequentially dependent. Episode-level resampling preserves this correlation structure and matches the granularity at which DAF is defined.\n\n\\subsection{Signal Concentration Index}\n\\label{sec:sci}\n\nDAF quantifies \\emph{how much} routing signal derives from death avoidance; a complementary question is whether this signal is driven by a few outlier task types or distributed systematically. We define the Signal Concentration Index (SCI) using the Gini coefficient over per-task routing signal contributions.\n\nLet $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:\n\\begin{equation}\n    c_k = \\frac{n_k \\cdot \\delta_k}{\\sum_{j=1}^{K} n_j \\cdot \\delta_j}\n\\end{equation}\nwhere $n_k$ is the number of episodes and $\\delta_k = d_k^{\\tt int} - d_k^{\\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\\{c_1, \\ldots, c_K\\}$:\n\\begin{equation}\n    \\text{SCI} = \\frac{\\sum_{i=1}^K \\sum_{j=1}^K |c_i - c_j|}{2K \\sum_{k=1}^K c_k}\n\\end{equation}\n\nSCI $\\in [0, 1]$: a value near 0 indicates uniform distribution of routing signal across task types (systematic phenomenon); a value near 1 indicates concentration in a single task type (isolated phenomenon). In our data, SCI $= 0.2147$, indicating low concentration. The top-1 task type contributes 14.3\\% of total signal, top-2 contributes 27.5\\%, and top-3 contributes 39.8\\%---no single task dominates. Of 11 task types, 10 exhibit nonzero death signal (\\texttt{find-non-living-thing} has zero deaths in both modalities). Together with DAF, SCI establishes that death avoidance is both the dominant routing signal (DAF $= 90.4\\%$) and a systematic phenomenon distributed across nearly all task types (SCI $= 0.2147$).\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Write",
  "tool_args": {
    "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex",
    "content": "\\section{Method}\n\\label{sec:method}\n\nOur diagnostic framework quantifies what drives routing signal in interactive environments through three components: (i)~episode-level counterfactual labeling that generates routing preferences from paired pure-strategy outcomes (\\S\\ref{sec:collection}--\\ref{sec:labeling}); (ii)~the Death Avoidance Factor (DAF), which decomposes the routing score gap into death-avoidance and non-death components (\\S\\ref{sec:daf}); and (iii)~the Signal Concentration Index (SCI), which measures whether routing signal is concentrated in a few task types or distributed systematically across the environment (\\S\\ref{sec:sci}). Episode-level bootstrap resampling provides 95\\% confidence intervals for all metrics.\n\n\\subsection{Problem Setup}\n\\label{sec:problem-setup}\n\nConsider an interactive environment $\\mathcal{E}$ with state space $\\mathcal{S}$, observation space $\\mathcal{O}$, and action space $\\mathcal{A}$. An agent follows a policy $\\pi: \\mathcal{O}^* \\rightarrow \\mathcal{A}$ that maps observation histories to actions. At each step $t$, the agent receives observation $o_t$, selects action $a_t = \\pi(o_1, \\ldots, o_t)$, and the environment transitions to state $s_{t+1}$.\n\nWe define a modality set $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$ governing how the agent processes state transitions:\n\\begin{itemize}\n    \\item \\textbf{Internal} ($m = {\\tt int}$): The agent uses its own generation to predict intermediate observations. The LLM interleaves chain-of-thought reasoning with environment actions following the ReAct paradigm \\cite{react-2023}, but prediction errors compound across steps.\n    \\item \\textbf{Deterministic} ($m = {\\tt det}$): The agent receives ground-truth observations from the environment simulator at each step---equivalent to access to a perfect dynamics model. Action selection remains with the LLM; only the state-transition prediction is replaced.\n\\end{itemize}\n\n\\noindent We restrict $\\mathcal{M}$ to two modalities. An ablation comparing chain-of-thought reasoning (deep internal) against direct-answer generation (fast internal) on 6 overlapping task types ($n{=}120$ episodes per condition) found no significant difference on any task (Mann--Whitney $p > 0.26$, $|d| \\leq 0.31$) and near-identical death rates (41.8\\% vs.\\ 42.5\\%), confirming that reasoning depth does not meaningfully alter internal-mode outcomes in this setting.\n\nA \\emph{routing policy} $\\rho: \\mathcal{O}^* \\rightarrow \\mathcal{M}$ selects which modality to use at each step. The goal of modality routing is to learn $\\rho$ that maximizes expected episode return. Our analysis investigates what signal is available to learn such a router.\n\n\\subsection{Counterfactual Episode Collection}\n\\label{sec:collection}\n\nPer-step oracle labeling assigns routing labels by comparing single-step outcomes under each computation modality. Under sparse terminal rewards, this approach degenerates: on ScienceWorld \\cite{scienceworld-2022}, 97.4\\% of steps (across 11 prescreened task types) produce identical intermediate scores regardless of modality, yielding no routing signal. We instead perform episode-level counterfactual analysis.\n\n\\paragraph{Pure-strategy trajectories.}\nFor a task instance $t$ and modality $m \\in \\mathcal{M}$, a \\emph{pure-strategy trajectory} is the complete episode obtained by applying modality $m$ at every step:\n\\begin{equation}\n    \\tau_m^{(t)} = (o_1, a_1, o_2, a_2, \\ldots, o_T, a_T)\n\\end{equation}\nwhere $T \\leq T_{\\max}$ is the episode length (capped at $T_{\\max} = 30$ steps). Both trajectories $\\tau_{\\tt int}^{(t)}$ and $\\tau_{\\tt det}^{(t)}$ are executed under identical initial conditions (same random seed, same task variation), ensuring that performance differences arise solely from the modality.\n\nEach trajectory $\\tau$ yields a terminal score $s(\\tau) \\in \\mathbb{Z}$ and a death indicator $d(\\tau) \\in \\{0, 1\\}$. When the agent dies ($d = 1$), the environment imposes a penalty: $s(\\tau) = -P$ where $P > 0$ ($P = 100$ in ScienceWorld). The episode pair produces a tuple:\n\\begin{multline}\n    \\bigl(s^{\\tt int}, s^{\\tt det}, d^{\\tt int}, d^{\\tt det}\\bigr) \\triangleq \\\\\n    \\bigl(s(\\tau_{\\tt int}),\\, s(\\tau_{\\tt det}),\\, d(\\tau_{\\tt int}),\\, d(\\tau_{\\tt det})\\bigr)\n\\end{multline}\n\nWe use Qwen2.5-7B-Instruct (vLLM) on ScienceWorld \\cite{scienceworld-2022}, a text-based environment spanning 30 task types with a $-100$ death penalty. After prescreening, we collect 245 episode pairs across 11 task types (20--40 per type). The framework is environment-agnostic: it requires only paired episode outcomes under two modalities, with no assumptions about score structure or failure mode. We apply it unchanged to ALFWorld and MATH in \\S\\ref{sec:discussion}.\n\n\\subsection{Episode-Level Labeling}\n\\label{sec:labeling}\n\nWe define a labeling function $L$ that maps a counterfactual pair to a routing preference:\n\\begin{multline}\n    L\\!\\bigl(\\tau_{\\tt int}^{(t)}, \\tau_{\\tt det}^{(t)}\\bigr) \\;\\rightarrow \\\\\n    \\ell \\in \\{{\\tt det\\text{-}pref},\\; {\\tt int\\text{-}pref},\\; {\\tt no\\text{-}pref}\\}\n\\end{multline}\n\nThe labeling function is \\emph{death-aware}: it prioritizes survival over score, reflecting the asymmetric cost of catastrophic failure in interactive environments. ScienceWorld scores are integer-valued, so we use exact (in)equality with no threshold. The full procedure is given in Algorithm~\\ref{alg:labeling}. Figure~\\ref{fig:pipeline} illustrates the overall pipeline.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/pipeline_overview.pdf}\n\\caption{Counterfactual episode collection and analysis pipeline. Each task instance is run under both pure strategies independently, producing episode-level labels via Algorithm~\\ref{alg:labeling}.}\n\\label{fig:pipeline}\n\\end{figure}\n\n\\begin{algorithm}[t]\n\\caption{Episode-Level Counterfactual Labeling}\n\\label{alg:labeling}\n\\begin{algorithmic}[1]\n\\REQUIRE Task instance $t$, modalities $\\mathcal{M} = \\{{\\tt int}, {\\tt det}\\}$\n\\ENSURE Label $\\ell \\in \\{{\\tt det\\text{-}pref}, {\\tt int\\text{-}pref}, {\\tt no\\text{-}pref}\\}$\n\\FOR{each $m \\in \\mathcal{M}$}\n    \\STATE Run episode $\\tau_m$ with pure-strategy $m$\n    \\STATE Record score $s_m$ and death indicator $d_m$\n\\ENDFOR\n\\IF{$d_{\\tt int} = 1$ \\AND $d_{\\tt det} = 0$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = 0$ \\AND $d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{death asymmetry}\n\\ELSIF{$d_{\\tt int} = d_{\\tt det} = 1$}\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{both dead}\n\\ELSIF{$s_{\\tt det} > s_{\\tt int}$}\n    \\STATE $\\ell \\leftarrow {\\tt det\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSIF{$s_{\\tt int} > s_{\\tt det}$}\n    \\STATE $\\ell \\leftarrow {\\tt int\\text{-}pref}$ \\COMMENT{score comparison}\n\\ELSE\n    \\STATE $\\ell \\leftarrow {\\tt no\\text{-}pref}$ \\COMMENT{tied alive}\n\\ENDIF\n\\RETURN $\\ell$\n\\end{algorithmic}\n\\end{algorithm}\n\nThe four mutually exclusive cases correspond to:\n\\begin{enumerate}\n    \\item \\textbf{Death asymmetry} (lines 5--8): $d^{\\tt int} \\neq d^{\\tt det}$ $\\rightarrow$ the surviving strategy is preferred. This accounts for 78.9\\% of all non-tie labels (75 of 95).\n    \\item \\textbf{Both dead} (lines 9--10): $d^{\\tt int} = d^{\\tt det} = 1$ $\\rightarrow$ ${\\tt no\\_preference}$.\n    \\item \\textbf{Score comparison} (lines 11--14): both survive and $s^{\\tt det} \\neq s^{\\tt int}$ $\\rightarrow$ the higher-scoring strategy is preferred.\n    \\item \\textbf{Tied alive} (lines 15--16): both survive and $s^{\\tt det} = s^{\\tt int}$ $\\rightarrow$ ${\\tt no\\_preference}$.\n\\end{enumerate}\n\nLabel distributions are reported in \\S\\ref{sec:death-decomp}.\n\n\\subsection{Death Avoidance Factor}\n\\label{sec:daf}\n\nTo quantify the contribution of death avoidance to routing signal, we decompose the mean score gap between strategies. Let $\\delta = \\mathbb{E}[d^{\\tt int}] - \\mathbb{E}[d^{\\tt det}]$ denote the death-rate differential and $\\Delta_{\\text{nd}}$ the mean score gap restricted to episodes where neither strategy dies. The full gap decomposes as:\n\\begin{equation}\n    \\Delta_{\\text{full}} \\approx \\underbrace{\\delta \\cdot P}_{\\text{death contribution}} + \\Delta_{\\text{nd}}\n\\end{equation}\nThe approximation holds exactly when the surviving strategy scores zero in all death-asymmetry episodes; in our data, the residual is small ($29.60 - 29.37 = 0.23$, or $0.8\\%$ of $\\Delta_{\\text{full}}$).\n\nWe define the Death Avoidance Factor (DAF) as the fraction of the full score gap attributable to death avoidance:\n\\begin{equation}\n    \\text{DAF} = 1 - \\frac{\\Delta_{\\text{nd}}}{\\Delta_{\\text{full}}} \\approx \\frac{\\delta P}{\\delta P + \\Delta_{\\text{nd}}}\n\\end{equation}%\n\\footnote{When $\\Delta_{\\text{nd}} < 0$ (deterministic strategy scores lower than internal on non-death episodes), DAF exceeds 1, indicating death avoidance overcompensates for a non-death disadvantage.}\n\nDAF is well-defined when $\\Delta_{\\text{full}} > 0$; in our data, the minimum per-task $\\Delta_{\\text{full}}$ is $+9.58$ (\\texttt{find-non-living-thing}), ensuring numerical stability. Since DAF $= \\delta P / (\\delta P + \\Delta_{\\text{nd}})$, it increases monotonically with $P$---a mathematical consequence, not an empirical finding. We therefore report both DAF at the environment default ($P{=}100$) and the penalty-independent death-asymmetry label fraction.\n\nTo assess sensitivity to penalty magnitude, we recalculate DAF under hypothetical death penalties (Appendix~\\ref{app:penalty}): $P{=}10 \\rightarrow$ DAF $= 50.4\\%$, $P{=}50 \\rightarrow 82.6\\%$, $P{=}100 \\rightarrow 90.4\\%$, $P{=}200 \\rightarrow 95.0\\%$. Death avoidance remains the dominant component across all penalty magnitudes, though its relative contribution scales with penalty severity. As a penalty-independent companion metric, 78.9\\% of non-tie routing labels (75 of 95) are driven by death asymmetry rather than score comparison (\\S\\ref{sec:labeling}), confirming that death avoidance dominates routing signal regardless of penalty magnitude.\n\n\\paragraph{Statistical inference.}\nWe quantify uncertainty via episode-level bootstrap resampling ($B = 10{,}000$ resamples). Each resample draws $N = 245$ episodes with replacement, recomputes $\\Delta_{\\text{full}}$, $\\Delta_{\\text{nd}}$, and DAF, and derives the percentile-based 95\\% CI. The aggregate DAF CI is $[81.6\\%, 98.8\\%]$, excluding both 50\\% and 100\\%. Per-task bootstrap CIs confirm $\\Delta > 0$ for 10 of 11 task types; \\texttt{chemistry-mix} ($N{=}20$, $\\Delta = 21.8$, CI $[-5.0, 48.6]$) is the sole exception, attributable to small sample size rather than absence of signal.\n\nWe resample at the episode level rather than the step level because the episode is the unit of counterfactual comparison: each episode pair yields one label, and steps within an episode are sequentially dependent. Episode-level resampling preserves this correlation structure and matches the granularity at which DAF is defined.\n\n\\subsection{Signal Concentration Index}\n\\label{sec:sci}\n\nDAF quantifies \\emph{how much} routing signal derives from death avoidance; a complementary question is whether this signal is driven by a few outlier task types or distributed systematically. We define the Signal Concentration Index (SCI) using the Gini coefficient over per-task routing signal contributions.\n\nLet $K$ denote the number of task types and $c_k$ the contribution of task type $k$ to the aggregate routing signal, defined as the fraction of total death-rate differential attributable to task $k$:\n\\begin{equation}\n    c_k = \\frac{n_k \\cdot \\delta_k}{\\sum_{j=1}^{K} n_j \\cdot \\delta_j}\n\\end{equation}\nwhere $n_k$ is the number of episodes and $\\delta_k = d_k^{\\tt int} - d_k^{\\tt det}$ is the per-task death-rate differential. The SCI is the Gini coefficient over $\\{c_1, \\ldots, c_K\\}$:\n\\begin{equation}\n    \\text{SCI} = \\frac{\\sum_{i=1}^K \\sum_{j=1}^K |c_i - c_j|}{2K \\sum_{k=1}^K c_k}\n\\end{equation}\n\nSCI $\\in [0, 1]$: a value near 0 indicates uniform distribution of routing signal across task types (systematic phenomenon); a value near 1 indicates concentration in a single task type (isolated phenomenon). In our data, SCI $= 0.2147$, indicating low concentration. The top-1 task type contributes 14.3\\% of total signal, top-2 contributes 27.5\\%, and top-3 contributes 39.8\\%---no single task dominates. Of 11 task types, 10 exhibit nonzero death signal (\\texttt{find-non-living-thing} has zero deaths in both modalities). Together with DAF, SCI establishes that death avoidance is both the dominant routing signal (DAF $= 90.4\\%$) and a systematic phenomenon distributed across nearly all task types (SCI $= 0.2147$).\n"
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-16T19:04:10.805709+00:00_

The file /home/ubuntu/.agent-ml-research-idea_gen_0509_12/projects/simgate-modular-routing/docs/paper/method.tex has been updated successfully.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "tool_result",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205",
  "tool": "Write",
  "elapsed_ms": 0
}
```

</details>

---

### Assistant

_source line 11 · 2026-05-16T19:04:10.805904+00:00_

Method section rewritten. Here's the report:

```json
{
  "word_count_estimate": "~1450 words (~1.5 pages in two-column ACL format)",
  "new_subsections": [
    "§3 opening paragraph: framework overview (3 components + bootstrap CI)",
    "§3.4 'Statistical inference' paragraph: bootstrap CI methodology",
    "§3.5 Signal Concentration Index (SCI): Gini-based formalization"
  ],
  "preserved_unchanged": [
    "Algorithm 1 (Episode-Level Counterfactual Labeling)",
    "§3.1 Problem Setup",
    "§3.2 Counterfactual Episode Collection",
    "§3.3 Episode-Level Labeling",
    "DAF formula and decomposition",
    "All numerical values"
  ],
  "figures_tables_needed": [
    "figures/pipeline_overview.pdf (already referenced, unchanged)"
  ],
  "key_additions": {
    "SCI_definition": "Gini coefficient over per-task death-rate differential contributions (Eq. 6)",
    "SCI_value": "0.2147 (low concentration = systematic phenomenon)",
    "bootstrap_method": "Episode-level resampling, B=10000, percentile CI",
    "bootstrap_result": "DAF 95% CI [81.6%, 98.8%]; 10/11 tasks Δ>0",
    "framework_narrative": "DAF says 'how much signal is death avoidance'; SCI says 'is it systematic across tasks'"
  }
}
```

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "session": "worker_writing_method-rewrite-direction-a_20260516T190205"
}
```

</details>

---
