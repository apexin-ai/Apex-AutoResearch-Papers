# Research conversation: In the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/, find ALL \be

**Sign Misattribution in Step-Independent Agent RL: Dual Mechanism Diagnosis and Episode-Level Correction (July export snapshot)** · Conversation logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 33
- **Recorded user turns:** 1
- **Tool calls:** 12
- **Original source:** `logs/chats/exported-trajectories/account-2/agent-af017f6f4420a0870.jsonl`
- **Structured JSON:** [`5a8f0cf1ee3318909b16.json`](../../sessions/5a/5a8f0cf1ee3318909b16.json)

## How to read this transcript

`User` marks a recorded user-role instruction, `Assistant` marks an agent response, and the collapsible `Tool call` / `Tool result` blocks show the actions and observations between them. A user-role record may come from another agent or the runtime system; it is not an authorship label.

## Round 1

33 recorded events

### User

_source line 1 · 2026-05-24T14:56:28.034Z_

In the directory /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/, find ALL \begin{figure} and \begin{table} declarations across all .tex files. For each one, report:
1. Which file it's in
2. The line number
3. The placement specifier (e.g., [t], [h], [ht])
4. The caption or label to identify which figure/table it is
5. Any \FloatBarrier usage

Search breadth: very thorough

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": null,
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "fd7a8db5-daea-428e-8333-3cbb5cc8c7b3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 2 · 2026-05-24T14:56:30.164Z_

I'll conduct a thorough search for all figure and table declarations in the paper directory. Let me start by exploring the directory structure and then systematically search through all .tex files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "fd7a8db5-daea-428e-8333-3cbb5cc8c7b3",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb645x6UEDy8s8mQoVG",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "6e853f83-6ba8-41d0-a035-74226105f9a2",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_012rTxn9eV9eNPntBv6Xwmpi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 39661,
      "cache_read_input_tokens": 0,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 39661,
        "ephemeral_1h_input_tokens": 0
      },
      "output_tokens": 3,
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

_source line 3 · 2026-05-24T14:56:30.347Z_

<details open><summary>🔧 Tool call — Bash · `toolu_01XYybn84btQedzzeHYgdjqX`</summary>

```json
{
  "command": "find /home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/ -type f -name \"*.tex\" | head -20"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "6e853f83-6ba8-41d0-a035-74226105f9a2",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb645x6UEDy8s8mQoVG",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "c3d519f2-2b80-4556-b2b4-ddbd9771e3c3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_012rTxn9eV9eNPntBv6Xwmpi",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 39661,
      "cache_read_input_tokens": 0,
      "output_tokens": 138,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 39661
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 3,
          "output_tokens": 138,
          "cache_read_input_tokens": 0,
          "cache_creation_input_tokens": 39661,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 39661,
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

_source line 4 · 2026-05-24T14:56:30.580Z_

<details><summary>↩ Tool result · `toolu_01XYybn84btQedzzeHYgdjqX`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/method.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/conclusion.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/main.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/related_work.tex
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/theoretical_analysis.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c3d519f2-2b80-4556-b2b4-ddbd9771e3c3",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "984ac8f6-2642-4730-ad03-7212375da059",
  "sourceToolAssistantUUID": "c3d519f2-2b80-4556-b2b4-ddbd9771e3c3",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 5 · 2026-05-24T14:56:32.174Z_

Now let me search for all \begin{figure} and \begin{table} declarations across these files:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "984ac8f6-2642-4730-ad03-7212375da059",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6EQp7GHabtmLg762P",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "a8221409-e1c7-4670-8092-2579c88a2a43",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01AXaEttC6Sq2pY3zcL1BHGe",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1339,
      "cache_read_input_tokens": 39661,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1339,
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

_source line 6 · 2026-05-24T14:56:32.848Z_

<details open><summary>🔧 Tool call — Grep · `toolu_01GZbbvMbxPMdvmGvtp1whin`</summary>

```json
{
  "pattern": "\\\\begin\\{(figure|table)\\}",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper",
  "type": "tex",
  "output_mode": "content",
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "a8221409-e1c7-4670-8092-2579c88a2a43",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6EQp7GHabtmLg762P",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "74a0a94a-6858-4493-83ff-4510287780dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01AXaEttC6Sq2pY3zcL1BHGe",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 1339,
      "cache_read_input_tokens": 39661,
      "output_tokens": 188,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1339
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 188,
          "cache_read_input_tokens": 39661,
          "cache_creation_input_tokens": 1339,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1339,
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

_source line 7 · 2026-05-24T14:56:32.874Z_

<details><summary>↩ Tool result · `toolu_01GZbbvMbxPMdvmGvtp1whin`</summary>

```text
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/theoretical_analysis.tex:24:\begin{figure}[t]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex:31:\begin{table}[t]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex:67:\begin{figure}[t]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex:81:\begin{table}[t]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex:113:\begin{figure}[t]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:72:\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:105:\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:133:\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:170:\begin{figure}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:182:\begin{table}[h]
/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex:218:\begin{table}[h]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "74a0a94a-6858-4493-83ff-4510287780dd",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "cd86487b-5582-4599-808b-da5548c72e11",
  "sourceToolAssistantUUID": "74a0a94a-6858-4493-83ff-4510287780dd",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 8 · 2026-05-24T14:56:34.384Z_

Now let me read each of these files to get the full context with captions, labels, and any FloatBarrier usage:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "cd86487b-5582-4599-808b-da5548c72e11",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6QGPtgGrcq9r3nWDn",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "2f78092b-df19-425e-9b2b-e697ae9bacdc",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01GGww5SnaDPgwQo9Qcefmrm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 745,
      "cache_read_input_tokens": 41000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 745,
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

_source line 9 · 2026-05-24T14:56:34.730Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KzfcKZoRMhrLXDP4G6vyUL`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/theoretical_analysis.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "2f78092b-df19-425e-9b2b-e697ae9bacdc",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6QGPtgGrcq9r3nWDn",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "ee9c36a3-2a8b-4cbe-b719-49295f3630b7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01GGww5SnaDPgwQo9Qcefmrm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 745,
      "cache_read_input_tokens": 41000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 745,
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

_source line 10 · 2026-05-24T14:56:34.743Z_

<details><summary>↩ Tool result · `toolu_01KzfcKZoRMhrLXDP4G6vyUL`</summary>

```text
1	\section{Theoretical Analysis}
2	\label{sec:theory}
3	
4	Sign misattribution is the more fundamental failure mechanism because it causes active divergence, not merely slow convergence. We derive the probability of incorrect gradient direction below; full proofs appear in Appendix~\ref{app:theory_full}.
5	
6	\textbf{Definition 1} (Locally correct action). \textit{An action $a_t$ is \textbf{locally correct} if it would receive positive advantage under an oracle that observes the full episode history $h_t$ and has access to the true action-value function. Equivalently,\footnote{This equivalence is approximate; it holds exactly when all trajectories within an episode are equally likely under the reference policy, and approximately under the mild assumption that policy drift remains small during early training.} window $k$ contains locally correct actions if replacing them (holding all other windows fixed) would decrease the probability of episode success.}
7	
8	\textbf{Proposition 1.} \textit{Under step-independent training with binary episode reward $R_{\text{episode}} \in \{0, r_+\}$, the probability that window $k$'s advantage $\hat{A}_k$ has the correct sign (aligned with local action quality) approaches the base success rate $p$ as the number of rollouts $K$ per group increases.}
9	
10	\textit{Proof sketch.} In a failed episode ($R_{\text{episode}} = 0$), all windows receive $R_k = 0$. If any rollout in the group succeeded, $\mu > 0$, so every window in the failed episode receives $\hat{A}_k < 0$---including windows with locally correct actions. The probability of receiving the wrong sign in a failed episode is $1 - (1-p)^{K-1}$ (at least one group member succeeded). As $K$ grows, this approaches $1-p$, and the overall probability of correct sign approaches $p$. \hfill$\square$
11	
12	The key distinction is temporal. Information loss (M1) imposes a constant ceiling determined by $h$; sign misattribution (M2) is cumulative---each wrong-sign gradient step erodes policy competence below that ceiling. A wrong-sign gradient moves the optimizer \textit{away} from good policies; a reduced-magnitude gradient from discounting ($\gamma^{(N-k)}$) still points toward good policies. Sign errors produce active divergence; magnitude errors merely slow convergence (Appendix~\ref{app:sign_fundamental}).
13	
14	\textbf{Proposition 2.}\label{prop:correct_sign} \textit{Let $p$ denote the episode success rate and $K$ the number of rollouts per group. Under step-independent training with binary episode reward, the fraction of gradient updates with correct sign is upper bounded by:}
15	\begin{equation}
16	P(\text{correct} \mid \text{update}) \leq \frac{p}{1 - (1-p)^{K}}
17	\label{eq:correct_conditional}
18	\end{equation}
19	
20	\textit{Derivation.} Three mutually exclusive cases determine gradient direction for a window with locally correct actions: (1)~episode succeeded (probability $p$): correct sign; (2)~episode failed but group contains a success (probability $(1{-}p)[1{-}(1{-}p)^{K-1}]$): wrong sign; (3)~entire group failed (probability $(1{-}p)^K$): zero gradient. Conditioning on non-zero gradient (Cases 1 and 2) yields Equation~\ref{eq:correct_conditional}. The bound is tight when episode success implies all constituent windows are locally correct; in practice, successful episodes may contain suboptimal windows, so the true fraction of correctly signed updates may be lower.
21	
22	At $p{=}12.5\%$, $K{=}8$, this yields an upper bound of 19.1\% on correctly signed gradient updates (Figure~\ref{fig:theory_curve}). In the large-$K$ limit, $P(\text{correct} \mid \text{update}) \to p$: ${\sim}87.5\%$ of updates for locally correct windows point in the wrong direction.
23	
24	\begin{figure}[t]
25	\centering
26	\includegraphics[width=\columnwidth]{fig_theory_curve.pdf}
27	\caption{Upper bound on the probability of correct gradient sign as a function of episode success rate $p$ (Proposition~2). At typical agent task success rates ($p < 0.2$, shaded), the majority of gradient updates carry incorrect sign regardless of group size $K$. At ALFWorld's baseline ($p{=}12.5\%$, $K{=}8$), at most 19.1\% of updates are correct. The dashed diagonal shows the large-$K$ limit $P_{\text{correct}} \to p$.}
28	\label{fig:theory_curve}
29	\end{figure}
30	
31	\paragraph{Severity scales with task difficulty.} Sign misattribution becomes \textit{more} severe as the task gets harder (Equation~\ref{eq:correct_conditional}): at $p{=}50\%$, $P(\text{correct} \mid \text{update}) \leq 50.2\%$; at $p{=}5\%$, at most 14.9\% of updates are correct. Multi-turn agent tasks with low baseline success rates are precisely where credit assignment matters most, yet where step-independent training produces the worst gradient signal. Increasing $K$ does not help: more updates occur (fewer all-fail groups), but each remains equally likely to carry the wrong sign.
32	
33	\paragraph{Reward saturation.} When all $K$ rollouts receive the same binary reward, $\sigma = 0$ and $\hat{A}_k = 0$, producing zero gradient. At $p{=}12.5\%$, $K{=}8$, the all-fail probability is $(1{-}p)^K \approx 34.4\%$; combined with the negligible all-success case ($p^K < 10^{-7}$), roughly one-third of batches yield no gradient at all. This compounds sign misattribution: of the ${\sim}66\%$ of batches that produce a gradient, at most 19.1\% have the correct sign. The effective learning rate is at most $0.66 \times 0.19 \approx 12.5\%$ of nominal---well below the regime where convergence guarantees hold.
34	
35	\paragraph{Cumulative divergence.} Sign misattribution produces a systematic gradient bias. Let $\theta^*$ denote an optimal policy parameterization. At each update, the expected gradient under step-independent training is:
36	\begin{equation}
37	\mathbb{E}[\nabla_\theta \mathcal{L}] = P_c \cdot g_+ + (1 - P_c) \cdot g_-
38	\label{eq:biased_gradient}
39	\end{equation}
40	where $P_c = P(\text{correct} \mid \text{update})$, $g_+$ points toward $\theta^*$, and $g_-$ points away. At the observed step-5 snapshot, $|\hat{A}_{\text{correct}}|/|\hat{A}_{\text{wrong}}| \approx 1.32$; whether this ratio holds across training stages remains to be verified. The cumulative divergence argument holds whenever this ratio is finite, regardless of its exact value. When $P_c < 0.5$ (which holds for $p < 0.5$; Equation~\ref{eq:correct_conditional}), the expected gradient points weakly away from good policies. The cumulative effect of this directional bias, amplified by the M1--M2 positive feedback loop (Section~\ref{sec:dual_mechanism}), drives progressive policy degradation: information loss (M1) caps $p$; lower $p$ increases wrong-sign frequency under M2, which further depresses $p$, producing the empirically observed collapse.
41	
42	\paragraph{Extension to ternary reward.} Our experimental setting uses ternary reward ($r \in \{-0.1, 0, 1\}$) rather than binary. Under ternary reward with penalty rate $\alpha$ (fraction of actions receiving $r_-$), binary reward ($\alpha{=}0$) yields the tightest bound on sign misattribution. Increasing $\alpha$ introduces within-group variance among failed episodes that partially breaks the sign-outcome coupling: windows with valid actions in failed episodes may obtain positive advantage when penalty-induced variance shifts the group mean downward. The measured 52\% credit agreement at $\alpha{\approx}0.3$ is consistent with this monotonic relaxation from the binary worst case. A binomial test confirms that the binary upper bound (19.1\%) and the empirical rate (52.1\%) measure different quantities ($z = 45.9$, $p < 10^{-100}$); both are far below the level required for reliable policy improvement (Appendix~\ref{app:nonbinary_extension}).
43	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "ee9c36a3-2a8b-4cbe-b719-49295f3630b7",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "15eac481-ab1e-4208-8ac2-99d8abc178c2",
  "sourceToolAssistantUUID": "ee9c36a3-2a8b-4cbe-b719-49295f3630b7",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Tool call

_source line 11 · 2026-05-24T14:56:34.971Z_

<details open><summary>🔧 Tool call — Read · `toolu_01CdYY6b48HyxxsJVW4Tek3f`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "15eac481-ab1e-4208-8ac2-99d8abc178c2",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6QGPtgGrcq9r3nWDn",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "595bfff9-297e-4874-b865-1a484ea4361b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01GGww5SnaDPgwQo9Qcefmrm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 745,
      "cache_read_input_tokens": 41000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 745,
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

_source line 12 · 2026-05-24T14:56:34.978Z_

<details><summary>↩ Tool result · `toolu_01CdYY6b48HyxxsJVW4Tek3f`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	Step-independent training collapses while episode-level training succeeds; a partial factorial design separates the two mechanisms; and window size $h$ modulates severity.
5	
6	\subsection{Setup}
7	\label{sec:setup}
8	
9	We evaluate on ALFWorld~\cite{shridhar2021alfworld}, a text-based household environment with six task types requiring sequential reasoning over up to 50 steps. The environment provides ternary reward: $R \in \{r_-, 0, r_+\}$, where $r_- = -0.1$ per invalid action, $0$ for valid but unsuccessful actions, and $r_+$ for task success. Our theoretical analysis (Section~\ref{sec:theory}) assumes the simplified binary case ($R \in \{0, r_+\}$), which yields an upper bound on sign misattribution severity; Section~\ref{sec:sign_verification} validates this bound under both reward structures. The base policy is Qwen3-1.7B fine-tuned on expert demonstrations (SFT baseline: 12.5\% in-distribution). At this baseline success rate, Proposition~2 predicts the majority of gradient updates carry incorrect sign. All conditions use RAGEN~\cite{ragen2025} (v0.1, commit \texttt{3a6b48b})\footnote{Our implementation extends RAGEN v0.1 with episode-level training support. Code available upon acceptance.} with GRPO~\cite{shao2024deepseekmath} ($K{=}8$; full hyperparameters in Appendix~\ref{app:hyperparameters}). We report success rate on a 134-task OOD set (primary) and 32-task in-distribution set (secondary). Seed counts are noted per condition.
10	
11	\subsection{Partial Factorial Mechanism Separation}
12	\label{sec:factorial_experiments}
13	
14	We implement the partial factorial design from Section~\ref{sec:factorial_design} (3 of 4 cells; Cell~C excluded due to NaN instability) with two seeds per condition. Cell~C (full observation, step-level advantage) would isolate M2 without M1, but we encountered persistent training instability in this configuration (Appendix~\ref{app:cell_c}). Cell~C's NaN divergence, qualitatively different from Cell~A's gradual collapse, suggests that information loss may have an unintended stabilizing effect on gradient variance, and that the M1--M2 interaction may be non-additive (Section~\ref{sec:discussion}).
15	
16	\subsection{Results}
17	\label{sec:results}
18	
19	Cell~A collapses in two phases (Table~\ref{tab:main_results}): task success drops to 0\% while action validity initially remains high, then continued sign misattribution destroys even basic formatting. % exp_id: hsweep_h2_seed1, hsweep_h2_seed2
20	Cell~B eliminates sign misattribution while retaining information loss: training success improves, but OOD generalization (5.97\%) remains near the SFT baseline (6.72\%), confirming that removing M2 alone bounds learning without causing degradation.% exp_id: factorial_h2_episodeadv_seed1, factorial_h2_episodeadv_seed2
21	Cell~D is the only condition that substantially exceeds the SFT baseline, with monotonic OOD improvement across both seeds.% exp_id: exp029_episode_level, exp029_seed3_ood_v2
22	The A$\to$B comparison isolates M2; the B$\to$D comparison isolates M1. Both mechanisms are necessary to explain the full failure pattern (Figure~\ref{fig:hsweep}a).
23	
24	\begin{figure*}[t]
25	\centering
26	\includegraphics[width=\textwidth]{fig_training_dynamics.pdf}
27	\caption{(a)~Training dynamics across factorial conditions (metric type indicated in legend). Cell~A collapses within 5 steps; Cell~B shows bounded learning; Cell~D improves monotonically. (b)~Window size $h$ vs.\ success rate (single seed). $h{\leq}20$ bars use a 32-task in-distribution eval set; the episode-level bar uses a 134-task OOD set (dotted separator); magnitudes are not directly comparable across eval sets. A single-seed observation suggests a credit assignment threshold between $h{=}10$ and $h{=}20$. Hatched bars indicate collapsed conditions.}
28	\label{fig:hsweep}
29	\end{figure*}
30	
31	\begin{table}[t]
32	\centering
33	\caption{1.7B results on ALFWorld (OOD 134-task set, In-Dist 32-task set). All cells report best checkpoint per seed. Cell~A: 2 seeds, best checkpoint each (both 0\%). Cell~B: 2 seeds, best checkpoint each. Cell~D: 2 seeds, mean $\pm$ range. Cell~D mean OOD (17.2\%) is consistent with the 11-seed evaluation (Table~\ref{tab:seed_variability}). Full seed-level breakdown in Table~\ref{tab:seed_variability} (11 seeds) and Appendix Table~\ref{tab:additional_baselines}.}
34	\label{tab:main_results}
35	\resizebox{\columnwidth}{!}{%
36	\begin{tabular}{@{}llccc@{}}
37	\toprule
38	\textbf{Condition} & \textbf{Mechanisms} & \textbf{Best Step} & \textbf{In-Dist (\%)} & \textbf{OOD (\%)} \\
39	\midrule
40	SFT baseline & --- & --- & 12.50 & 6.72 \\
41	Cell A ($h{=}2$, step) & M1+M2 & 5 & 0 & 0 \\
42	Cell B ($h{=}2$, episode) & M1 only & 5 & 18.75 & 5.97 \\
43	Cell D (full, episode) & neither & 5 & \textbf{34.38} & \textbf{17.16} \\
44	\bottomrule
45	\end{tabular}}
46	% exp_id: hsweep_h2_seed1, factorial_h2_episodeadv_seed1, exp029_episode_level, exp029_seed3_v2
47	\end{table}
48	
49	\paragraph{Additional conditions.} Dense reward, REINFORCE++, and discount-factor sweep experiments all confirm that sign misattribution, not reward sparsity or discounting, drives the failure (Appendix~\ref{app:additional}).
50	
51	\paragraph{Window-size sweep.} Varying window size reveals a credit assignment threshold between $h{=}10$ and $h{=}20$ that separates collapse from recovery (Figure~\ref{fig:hsweep}b; single seed). Below this threshold, all conditions collapse to 0\%; above it, success rate increases monotonically with window size. This single-seed observation suggests a threshold effect; multi-seed verification is needed to confirm its location and robustness.% exp_id: h_sweep_series, exp029_seed1
52	\label{sec:results_hsweep}
53	
54	\subsection{Sign Misattribution Verification}
55	\label{sec:sign_verification}
56	
57	We distinguish three metrics that each capture a different aspect of credit assignment quality:
58	
59	\textit{(1) Sign-episode correlation}: whether advantage sign tracks episode outcome (success/failure). Under pure binary reward (penalty${=}0$), this correlation is near-perfect at 99.6\% ($270/271$ non-zero windows across three evaluation iterations; Figure~\ref{fig:sign_misattribution}), directly confirming M2: advantage sign is almost entirely determined by episode outcome, not local action quality.\footnote{The single discordant window (1/271) arises when a low-return successful episode is grouped with higher-return successes; GRPO normalization assigns negative advantage despite positive return. This is a group-composition edge case, not a violation of the theoretical mechanism.} This is by construction under binary reward, since all windows in a successful episode share the same positive return.% exp_id: binary_credit_agreement_iter0
60	
61	\textit{(2) Credit agreement rate}: whether advantage sign matches local action quality, operationalized through action validity as a proxy for local correctness (Definition~1). Under step-independent training with penalty reward ($h{=}2$, $n{=}3{,}000$ windows), only 52.07\% of windows with valid actions receive positive advantage, marginally above random chance ($p{=}0.025$ vs.\ 50\%; Cohen's $h = 2\arcsin\sqrt{0.5207} - 2\arcsin\sqrt{0.5} \approx 0.041$, below the 0.2 small-effect threshold), confirming that credit agreement is effectively at chance, consistent with the theoretical prediction of near-random sign assignment. This near-random credit agreement shows that advantage sign carries almost no information about local action quality. Under pure binary reward, credit agreement drops further to 28\% ($n{=}271$), below random chance---advantage sign systematically punishes valid actions in failed episodes. Penalty reward partially breaks sign-episode correlation by introducing within-group variance, but the resulting signal remains too weak for meaningful credit assignment. This operationalization is conservative: successful episodes may contain suboptimal windows, making our validity label an upper bound on true local correctness. Even under this generous criterion, credit agreement remains near-random, strengthening the diagnosis.% exp_id: 7b_cell_a_h2
62	
63	\textit{(3) $P(\text{correct} \mid \text{update})$}: the theoretical upper bound from Proposition~2 ($\leq$19.1\% at $p{=}12.5\%$, $K{=}8$). This bounds the fraction of non-zero gradient updates with correct sign, a different quantity from the credit agreement rate, which conditions on action validity rather than gradient participation. The two metrics are complementary: Proposition~2 bounds worst-case gradient quality; credit agreement measures empirical signal strength.
64	
65	Combined with $\gamma{=}1.0$ collapse (Appendix~\ref{app:additional}), these measurements are consistent with sign misattribution as a primary factor in training failure, though the credit agreement effect is substantively small ($+$2pp above random).
66	
67	\begin{figure}[t]
68	\centering
69	\includegraphics[width=\columnwidth]{fig_sign_misattribution.pdf}
70	\caption{Sign-episode correlation (binary reward, penalty${=}0$) vs.\ credit agreement rate (penalty reward). Under binary reward, advantage sign near-perfectly tracks episode outcome (99.6\%, $270/271$), confirming M2. Under penalty reward, credit agreement with local action quality drops to 52.1\% ($n{=}3{,}000$), near random chance (dashed line). These are distinct metrics: the former measures episode-level sign correlation, the latter measures local credit assignment quality.}
71	\label{fig:sign_misattribution}
72	\end{figure}
73	
74	\subsection{Episode-Level Training: Seed Variability}
75	\label{sec:seed_variability}
76	
77	Episode-level GRPO addresses the dual-mechanism failure, but training outcomes remain seed-dependent. We systematically evaluate $N{=}11$ random seeds under identical hyperparameters, revealing a $2{\times}2$ structure: \textit{training stability} (collapsed vs.\ non-collapsed) $\times$ \textit{OOD generalization} (stagnant vs.\ generalized).
78	
79	We define \textbf{collapsed} seeds as those where in-distribution success declines $>$50\% from peak and remains below baseline for $\geq$3 consecutive steps. \textbf{Non-collapsed} seeds are the complement. Among non-collapsed seeds, we further distinguish \textbf{generalized} (Fisher exact $p{<}0.01$ vs.\ SFT on the 134-task OOD set) from \textbf{stagnant} (not significant vs.\ SFT). Table~\ref{tab:seed_variability} reports results for each seed at its best-performing checkpoint.
80	
81	\begin{table}[t]
82	\centering
83	\caption{Episode-level GRPO across 11 seeds (134 OOD tasks, $\tau{=}0.4$, best checkpoint per seed). Category: C=Collapsed, S=Non-collapsed (stagnant), G=Generalized (Fisher exact $p{<}0.01$ vs.\ SFT). Wilson 95\% CI. SFT baseline: 6.72\% (9/134). Seed2 achieves $p{=}0.03$ (Fisher exact, two-sided), falling outside the conservative $p{<}0.01$ threshold, and is classified as Stagnant. Step-5 results for all seeds in Appendix~\ref{app:step5_unified}. Evaluation variance analysis (repeated runs, std$=$1.29pp) in Appendix~\ref{app:eval_variance}.}
84	\label{tab:seed_variability}
85	\resizebox{\columnwidth}{!}{%
86	\begin{tabular}{@{}llcccc@{}}
87	\toprule
88	\textbf{Seed} & \textbf{Step} & \textbf{Cat.} & \textbf{OOD (\%)} & \textbf{95\% CI} & \textbf{vs SFT} \\
89	\midrule
90	seed2048$^\ddagger$ & 5 & C & 8.21 & [4.6, 14.2] & NS \\
91	seed42$^\ddagger$ & 5 & C & 12.69 & [8.0, 19.4] & NS \\
92	seed8 & 5 & C & 11.94 & [7.5, 18.5] & NS \\
93	\midrule
94	seed200 & 5 & S & 10.45 & [6.3, 16.8] & NS \\
95	seed300 & 5 & S & 10.45 & [6.3, 16.8] & NS \\
96	seed100 & 5 & S & 11.19 & [6.9, 17.6] & NS \\
97	seed100 & 10 & S & 12.69 & [8.0, 19.4] & NS \\
98	seed2$^\ddagger$ & 15 & S & 15.67 & [10.5, 22.8] & $p{=}0.03$ \\
99	\midrule
100	seed1 & 5 & G$^\dagger$ & 23.88 & [17.4, 31.8] & $p{<}0.001$ \\
101	seed5 & 10 & G & 29.10 & [22.1, 37.3] & $p{<}0.001$ \\
102	seed6 & 15 & G & 29.10 & [22.1, 37.3] & $p{<}0.001$ \\
103	seed4 & 15 & G & 30.60 & [23.5, 38.7] & $p{<}0.001$ \\
104	\bottomrule
105	\end{tabular}}
106	\begin{flushleft}
107	\small $^\dagger$ RAGEN built-in eval; checkpoint unavailable for re-evaluation. \\
108	\small $^\ddagger$ OOD evaluated via RAGEN built-in eval; not independently re-evaluated under D134 protocol. \\
109	\small All results are single-run evaluations at $\tau{=}0.4$; see Limitations for eval variance discussion.
110	\end{flushleft}
111	\end{table}
112	
113	\begin{figure}[t]
114	\centering\vspace{-3pt}
115	\includegraphics[width=0.95\columnwidth]{fig_seed_variability.pdf}\vspace{-5pt}
116	\caption{OOD success rate across 11 episode-level GRPO seeds (Wilson 95\% CI). Seeds partition into \textit{Generalized} ($p{<}0.01$ vs.\ SFT), \textit{Stagnant} (stable, NS), and \textit{Collapsed} ($\times$). Avoiding collapse is necessary but not sufficient.}
117	\label{fig:seed_variability}\vspace{-8pt}
118	\end{figure}
119	
120	Three distinct outcomes emerge (Table~\ref{tab:seed_variability}, Figure~\ref{fig:seed_variability}): roughly a quarter of seeds collapse with response length inflation (Appendix~\ref{app:response_length}), a third are stagnant with OOD performance indistinguishable from SFT, and a third generalize with significant OOD improvement. No collapsed seed generalizes, and training duration does not explain the gap between stagnant and generalized seeds. Stable training is necessary but not sufficient; the mechanism driving seed-dependent transfer remains an open question (Section~\ref{sec:discussion}).% exp_id: exp029 multi-seed series
121	
122	\subsection{Cross-Scale and Cross-Environment Verification}
123	\label{sec:cross_scale}
124	
125	A single-seed 8B experiment confirms both failure and fix persist at scale: Cell~A collapses within two steps while Cell~D reaches 90.3\% OOD (Appendix~\ref{app:8b_results}); restricting to $h{=}2$ confirms severe information loss. The pathology is environment-general: step-independent training on ScienceWorld~\cite{wang2022scienceworld} also collapses to 0\% across all 15 steps with comparable M1 gap.% exp_id: 8b_cell_c_episode_v9d, 8b_v9d_ood_eval_v5, scienceworld_grpo_cell_a, sw_info_loss_bjb1
126	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "595bfff9-297e-4874-b865-1a484ea4361b",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "9bdee0ae-8872-42e8-ae78-2d0720933009",
  "sourceToolAssistantUUID": "595bfff9-297e-4874-b865-1a484ea4361b",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Tool call

_source line 13 · 2026-05-24T14:56:35.201Z_

<details open><summary>🔧 Tool call — Read · `toolu_01KYrwmbc9ATLX9Bujddg4YS`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9bdee0ae-8872-42e8-ae78-2d0720933009",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6QGPtgGrcq9r3nWDn",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "c40086b3-c7da-425f-9e6c-866a3573746c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01GGww5SnaDPgwQo9Qcefmrm",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 745,
      "cache_read_input_tokens": 41000,
      "output_tokens": 267,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 745
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 267,
          "cache_read_input_tokens": 41000,
          "cache_creation_input_tokens": 745,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 745,
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

_source line 14 · 2026-05-24T14:56:35.395Z_

<details><summary>↩ Tool result · `toolu_01KYrwmbc9ATLX9Bujddg4YS`</summary>

```text
1	\appendix
2	
3	\section{Theoretical Analysis: Full Derivations}
4	\label{app:theory_full}
5	
6	\subsection{Why Sign Misattribution is the Core Mechanism}
7	\label{app:sign_fundamental}
8	
9	The two mechanisms identified in Section~\ref{sec:dual_mechanism} operate at different layers and produce qualitatively different failures. Policy information loss (Mechanism 1) operates at the inference layer, restricting the observable context and establishing a structural performance ceiling that is constant across training. Sign misattribution (Mechanism 2) operates at the training layer, corrupting gradient directions and progressively degrading performance below this ceiling.
10	
11	\textit{Proof of Proposition 1.} Define ``correct sign'' as follows: for a window containing locally beneficial actions, the correct sign of $\hat{A}_k$ is positive (reinforcement); for a window containing locally detrimental actions, the correct sign is negative (suppression). Under binary reward, the return for window $k$ is $R_k = \gamma^{(N-k)} \cdot R_{\text{episode}}$ (Equation~\ref{eq:step_return}). In a failed episode ($R_{\text{episode}} = 0$), all windows receive $R_k = 0$ regardless of their local action quality. If the group contains at least one successful rollout, the group mean $\mu > 0$, and all windows in the failed episode receive negative advantages after normalization via Equation~\ref{eq:grpo_advantage}. This includes windows where the agent took locally correct actions. Now consider a window with locally correct actions. In a successful episode (probability $p$), the window receives positive $\hat{A}_k$, which is the correct sign. In a failed episode (probability $1 - p$), the window receives negative $\hat{A}_k$ whenever $\mu > 0$, which is the wrong sign. The probability that $\mu = 0$ (all $K$ rollouts in the group failed) is $(1-p)^K$, which shrinks exponentially with $K$. As $K$ grows, nearly every failed episode produces a non-zero group mean, and the window receives the wrong sign with probability approaching $1-p$. The probability of correct sign therefore approaches $p$. \hfill$\square$
12	
13	The distinction between sign error and magnitude error further clarifies why Mechanism 2 is catastrophic while Mechanism 1 is merely suboptimal. The discount factor $\gamma^{(N-k)}$ in Equation~\ref{eq:step_return} introduces magnitude decay across window positions: for an episode with $T=50$ steps and $h=2$, the first window ($k=1$) retains $\gamma^{N-1} = 0.95^{24} \approx 0.29$ of the terminal window's return. This attenuation reduces the gradient magnitude for early windows but preserves the gradient direction. A gradient with correct sign and reduced magnitude produces slow convergence, a condition recoverable through longer training. A gradient with wrong sign produces active divergence: the optimization pushes the policy away from good behaviors and toward bad ones.
14	
15	\subsection{Formal Probability Analysis}
16	\label{app:formal_probability}
17	
18	\textit{Derivation of Proposition 2.} For a window with locally correct actions, the gradient direction depends on $\text{sign}(\hat{A}_k)$, which depends on whether the episode succeeded and whether the group contains any successful rollouts. Three mutually exclusive cases arise.
19	
20	\textit{Case 1: Episode succeeded} (probability $p$). The window receives $R_k = \gamma^{(N-k)} \cdot r_+ > 0$. With at least one failed rollout in the group, $R_k > \mu$ after normalization, producing $\hat{A}_k > 0$.\footnote{The edge case where all $K$ rollouts succeed (probability $p^K$) is negligible at the baseline success rates considered ($p^8 < 10^{-7}$ at $p = 12.5\%$).} The gradient reinforces the window's actions. For a window with locally correct actions, this is the correct direction.
21	
22	\textit{Case 2: Episode failed, group contains at least one success} (probability $(1-p)[1 - (1-p)^{K-1}]$). The window receives $R_k = 0 < \mu$, producing $\hat{A}_k < 0$. The gradient suppresses the window's actions. For a window with locally correct actions, this is the wrong direction.
23	
24	\textit{Case 3: Episode failed, entire group failed} (probability $(1-p) \cdot (1-p)^{K-1} = (1-p)^{K}$). All returns are zero, so $\mu = 0$ and $\sigma = 0$. The advantage is zero, producing no gradient update.
25	
26	Summing Cases~1 and~3 yields $P(\text{correct sign or no update}) = p + (1-p)^{K}$. Since only Cases~1 and~2 produce non-zero gradients, the conditional probability follows as Equation~\ref{eq:correct_conditional}.
27	
28	\label{app:nonbinary_extension}
29	\textit{Two calibers of credit assignment failure.} Proposition~2 and the empirical credit agreement rate (Section~\ref{sec:sign_verification}) quantify different aspects of credit assignment failure under different reward structures; both confirm that advantage sign carries insufficient information about local action quality.
30	
31	\textit{Binary caliber} ($P(\text{correct} \mid \text{update}) \leq 19.1\%$). Under pure binary reward $R \in \{0, r_+\}$, the GRPO advantage $\hat{A}_k = R_k - \bar{R}_g$ has its sign entirely determined by episode outcome: all windows in a successful episode receive positive advantage, all windows in a failed episode receive negative advantage whenever the group contains at least one success. This near-deterministic sign-episode mapping---confirmed empirically at 99.6\% ($270/271$ windows; Section~\ref{sec:sign_verification})---means Proposition~2's upper bound applies directly: at most 19.1\% of non-zero gradient updates carry the correct sign.
32	
33	\textit{Penalty caliber} (credit agreement $= 52.1\%$). Introducing a format penalty $r_- = -0.1$ per invalid action breaks this deterministic mapping. Within a failed episode, windows with valid actions receive $R_k = 0$ while windows with invalid actions receive $R_k = -0.1h$. This intra-episode variance shifts $\bar{R}_g$ downward, allowing some valid-action windows in failed episodes to obtain $\hat{A}_k > 0$ despite overall failure. Credit agreement rises from 19.1\% to 52.1\%---but this is marginally above random chance (Cohen's $h = 0.041$, below the 0.2 small-effect threshold), carrying negligible information about local action quality.
34	
35	\textit{Complementary evidence.} The two calibers capture qualitatively different failure modes: 19.1\% reflects deterministic misattribution (advantage sign systematically tracks the wrong signal), while 52.1\% reflects near-random noise (advantage sign carries almost no local information). Both are far below the level required for policy improvement. The gap between them is itself informative: it quantifies how penalty-induced variance transforms the failure mode from systematic wrong-sign to random noise, without repairing credit assignment. A binomial test rejects $H_0{:}\, P = 0.191$ ($z = 45.9$, $p < 10^{-100}$), formally confirming that the two calibers measure different quantities.
36	
37	We evaluate these expressions at the empirical baseline of our experiments. At $p = 12.5\%$ and $K = 8$: $(1-p)^K = 0.875^8 \approx 0.344$, giving $P(\text{correct or no update}) \approx 0.469$. Of the 65.6\% of cases that produce a gradient update, only $P(\text{correct} \mid \text{update}) = 0.125 / 0.656 \approx 19.1\%$ have the correct sign. As $K$ increases to 16, $(1-p)^{K} \approx 0.118$, and $P(\text{correct} \mid \text{update}) \approx 14.2\%$. In the large-$K$ limit, $P(\text{correct} \mid \text{update}) \to p$, so approximately $1 - p = 87.5\%$ of all gradient updates for locally correct windows point in the wrong direction.
38	
39	\subsection{Why the Community Defaults to Step-Independent Training}
40	\label{app:why_defaults}
41	
42	If step-independent training is structurally flawed for multi-turn agents, why has it become the default? We identify six contributing factors.
43	
44	\textbf{1. Context length constraints.} Smaller language models (1B to 4B parameters) typically support context lengths of 2048 to 4096 tokens. Multi-turn episodes spanning 50 or more interaction steps easily exceed these limits. Step-independent windowing is a pragmatic response to a hardware constraint, not a deliberate algorithmic choice.
45	
46	\textbf{2. Token-level training inertia.} Language model training is organized around predicting the next token over fixed-length sequences. When multi-turn RL inherits this paradigm, the natural unit of optimization becomes a fixed-length window rather than a variable-length episode. The mismatch between token-level optimization and episode-level credit assignment goes unquestioned because it aligns with existing training infrastructure.
47	
48	\textbf{3. Inherited framework default.} The RAGEN framework~\cite{ragen2025} implements step-independent mode as its default configuration, not as one option among alternatives. Users inherit this choice without an explicit decision point, and default configurations propagate silently through downstream projects.
49	
50	\textbf{4. Memory and compute constraints.} Episode-level training requires processing $O(T)$ tokens per sequence, incurring $O(T^2)$ attention cost with full self-attention. Step-independent training reduces this to $O(h)$ tokens and $O(h^2)$ attention cost per window. The computational savings are immediate and measurable, while the credit assignment failure is subtle and deferred until training collapse occurs.
51	
52	\textbf{5. Reward shaping as apparent fix.} Dense reward shaping (per-step bonuses for intermediate goals) appears to address sparse reward problems. Our dense reward experiment (Section~\ref{sec:results_dense}) reveals a different failure mode: the agent maximizes format-level rewards (action validity rises from 60\% to 97.5\%) while task success remains at 0\%. Reward shaping does not resolve sign misattribution; it creates new optimization targets that the agent can game without solving the underlying task.
53	
54	\textbf{6. Absence of negative results.} When step-independent training fails, practitioners attribute the failure to insufficient hyperparameter tuning or the inherent difficulty of sparse rewards. Without published analyses that isolate the credit assignment mechanism as the root cause, the community cannot distinguish between ``this problem is hard'' and ``this training paradigm is broken for this class of problems.''
55	
56	\subsection{Connection to Classical Credit Assignment}
57	\label{app:classical_connection}
58	
59	Our findings connect to a long line of work on temporal credit assignment in reinforcement learning.
60	
61	\textbf{Temporal difference learning and eligibility traces.} Sutton's TD($\lambda$)~\cite{sutton1988td} provides a spectrum of credit assignment strategies parameterized by $\lambda \in [0,1]$. At $\lambda = 0$, credit is assigned via one-step bootstrapped returns. At $\lambda = 1$, TD($\lambda$) reduces to Monte Carlo returns. Step-independent training falls below this spectrum: windows are disconnected from each other, so temporal propagation of credit does not occur.
62	
63	\textbf{Generalized Advantage Estimation.} GAE($\lambda, \gamma$)~\cite{schulman2016gae} extends TD($\lambda$) with a separate discount factor. GAE(1, 1) produces undiscounted Monte Carlo returns and is equivalent to episode-level GRPO without a critic. The key difference is that GAE uses value function subtraction as the baseline, while GRPO uses group normalization.
64	
65	\textbf{REINFORCE.} Williams' REINFORCE algorithm~\cite{williams1992reinforce} computes policy gradients from complete episode returns with a learned baseline $b(s)$. Episode-level GRPO is equivalent to REINFORCE where the group mean $\mu$ replaces $b(s)$ and the group standard deviation $\sigma$ provides normalization. The algorithmic structure is not new. Our contribution is the diagnosis: the community's standard adaptation of this algorithm for multi-turn LLM agents (step-independent windowing) silently breaks the credit assignment structure that REINFORCE assumes.
66	
67	\textbf{Multi-agent credit assignment analogy.} Step-independent windows can be understood through cooperative multi-agent games. Each window acts as an independent ``agent'' sharing a team reward but optimized without knowledge of other windows' actions. The sign misattribution problem parallels team reward credit assignment in cooperative multi-agent RL: when the team fails, all agents receive identical penalties regardless of individual contribution. In multi-agent RL, this is a recognized problem with known solutions such as counterfactual baselines and value decomposition methods.
68	
69	\section{Hyperparameters}
70	\label{app:hyperparameters}
71	
72	\begin{table}[h]
73	\centering
74	\caption{Shared RL training hyperparameters across all conditions.}
75	\label{tab:hyperparameters_app}
76	\begin{tabular}{lc}
77	\toprule
78	Parameter & Value \\
79	\midrule
80	Group size $K$ & 8 \\
81	Learning rate & $1 \times 10^{-6}$ \\
82	KL penalty $\beta$ & 0.01 \\
83	Discount $\gamma$ & 0.95 \\
84	Invalid action penalty & 0.1 \\
85	Tasks per training step & 16 \\
86	Training steps & 15 \\
87	\bottomrule
88	\end{tabular}
89	\end{table}
90	
91	All 1.7B experiments were conducted on a single NVIDIA A100 80\,GB GPU. Each training run (15 steps, $K{=}8$ rollouts per task, 16 tasks per step) required approximately 6--8 GPU-hours. The 11-seed evaluation totaled ${\sim}$80 GPU-hours. The 8B experiment used 4$\times$ A100 80\,GB with Fully Sharded Data Parallel (FSDP), requiring ${\sim}$24 GPU-hours per run. ScienceWorld experiments used the same single-GPU setup as the 1.7B ALFWorld runs.
92	
93	\paragraph{SFT baseline.} The base policy was fine-tuned on 2{,}546 expert demonstrations from the ALFWorld training split following the protocol of RAGEN~\cite{ragen2025}, using learning rate $2 \times 10^{-5}$, batch size~16, and 3 epochs.
94	
95	\section{Cross-Scale and Cross-Environment Results}
96	\label{app:8b_results}
97	
98	\begin{figure*}[t]
99	\centering
100	\includegraphics[width=\textwidth]{fig_cross_scale.pdf}
101	\caption{(a)~Cross-scale verification (single seed): both collapse (Cell~A) and fix (Cell~D) are observed from 1.7B to 8B. The episode-level fix appears more effective at 8B (96.9\% vs.\ 34.4\% in-distribution). (b)~Information loss (M1) quantification (single seed each): restricting context to $h{=}2$ drops SFT performance by 37.5pp at 8B ALFWorld and 30.3pp on ScienceWorld.}
102	\label{fig:cross_scale}
103	\end{figure*}
104	
105	\begin{table}[h]
106	\centering
107	\caption{8B results on ALFWorld. SFT and $h{=}2$ use decoding temperature $\tau{=}0$; RL uses $\tau{=}0.4$. Cell~A: step~2 (post-collapse). Cell~D: step~10. Single seed. The primary comparison is Cell~A collapse (0\%) vs Cell~D success, which is independent of decoding temperature.}
108	\label{tab:8b_results}
109	\small
110	\begin{tabular}{@{}lcc@{}}
111	\toprule
112	\textbf{Method} & \textbf{In-Dist (\%)} & \textbf{OOD (\%)} \\
113	\midrule
114	SFT baseline & 68.75 & 80.60 \\
115	SFT $h{=}2$ & 31.25 & --- \\
116	Cell A: step-indep.\ ($h{=}2$) & 28.1 $\to$ 1.6 & --- \\
117	Cell D: episode-level & \textbf{96.88} & \textbf{90.30} \\
118	\bottomrule
119	\end{tabular}
120	% exp_id: 8b_cell_c_episode_v9d, 8b_v9d_ood_eval_v5
121	\end{table}
122	
123	\section{Additional Conditions}
124	\label{app:additional}
125	
126	All conditions use single seeds unless noted.
127	
128	\paragraph{Dense reward.} Step-independent $h{=}2$ with $+0.15$ per valid action. Action validity rises from 60\% to 97.5\% while task success remains 0\%; the agent games format-level rewards without solving tasks (Figure~\ref{fig:additional_conditions}b).
129	\label{sec:results_dense}
130	
131	\paragraph{REINFORCE++.} Episode-level with per-token running-mean baseline (no critic). REINFORCE++ matches the SFT baseline (12.50\%) without improvement, suggesting that per-token advantage normalization alone does not help when the per-token baseline lacks a learned value function. This is a preliminary comparison over 15 training steps; we cannot conclude that REINFORCE++ would fail with longer training or different hyperparameters. The result suggests that naive algorithm substitution without addressing M1/M2 is insufficient, but a definitive comparison would require matched compute budgets and hyperparameter sweeps. OOD evaluation was not conducted as REINFORCE++ showed no improvement over SFT on the in-distribution set.
132	
133	\begin{table}[h]
134	\centering
135	\caption{Additional baselines on ALFWorld (1.7B). Neither method improves over the SFT baseline on in-distribution tasks.}
136	\label{tab:additional_baselines}
137	\small
138	\begin{tabular}{@{}lccc@{}}
139	\toprule
140	\textbf{Method} & \textbf{Best Step} & \textbf{In-Dist (\%)} & \textbf{OOD (\%)} \\
141	\midrule
142	SFT baseline & --- & 12.50 & 6.72 \\
143	Dense reward ($h{=}2$) & 5 & 0 & 0 \\
144	REINFORCE++ & 5 & 12.50 & --- \\
145	\bottomrule
146	\end{tabular}
147	\end{table}
148	
149	\paragraph{Discount factor sweep.} $\gamma \in \{0.50, 0.80, 0.95, 1.00\}$ at $h{=}5$. All four collapse to 0\% within 5 steps, including $\gamma{=}1.0$ where no magnitude decay exists. This confirms sign misattribution, not discounting, is the operative mechanism (Figure~\ref{fig:additional_conditions}a).
150	
151	\paragraph{Cell~C attempt.}
152	\label{app:cell_c}
153	Cell~C (full observation + step-level advantage) would isolate M2 without M1. We attempted this configuration across six training runs with varying hyperparameters (KL penalty $\beta \in \{0.001, 0.01, 0.04\}$, learning rate $\in \{5{\times}10^{-7}, 10^{-6}\}$). All runs terminated due to training instability: KL divergence spiked above 10.0 within 2--3 steps, triggering NaN losses. We attribute this to the combination of full-length sequences ($>$4096 tokens) with step-level advantage normalization, which produces extreme advantage magnitudes at early window positions. Cell~C remains an important gap in the factorial; addressing it likely requires architectural changes (e.g., gradient clipping per window position) beyond the scope of this diagnostic study.
154	
155	\begin{figure*}[t]
156	\centering
157	\includegraphics[width=\textwidth]{fig_additional_conditions.pdf}
158	\caption{(a)~Standard remedies for step-independent training: dense reward shaping and discount factor $\gamma{=}1.0$ both collapse to 0\%; REINFORCE++ matches the SFT baseline without improvement. Only episode-level training (Cell~D) exceeds baseline. (b)~Dense reward gaming: action validity rises from 60\% to 97.5\% while task success remains 0\%; the agent maximizes format-level rewards without solving tasks.}
159	\label{fig:additional_conditions}
160	\end{figure*}
161	
162	\section{Method Selection Guide}
163	\label{app:method_selection}
164	
165	The M1/M2 diagnostic framework guides practitioners toward the appropriate fix without exhaustive ablation. If only M2 is active (sign misattribution with sufficient observation context, e.g., $h$ large enough to preserve task-relevant information), per-step credit methods---Turn-PPO~\cite{turnppo2025}, HCAPO~\cite{hcapo2026}, GiGPO~\cite{feng2025gigpo}---directly address the failure mode. If only M1 is active (information loss without sign corruption), increasing $h$ or switching to full-context encoding suffices. When both co-occur (the typical default configuration), episode-level methods address both simultaneously. Finer-grained credit methods should be applied only after establishing an episode-level baseline, as they assume correct gradient direction.
166	
167	\section{Response Length During Training}
168	\label{app:response_length}
169	
170	\begin{figure}[h]
171	\centering
172	\includegraphics[width=\columnwidth]{fig_response_length.pdf}
173	\caption{Response length over training for 7 seeds under episode-level GRPO. Collapsed seeds (red) exhibit length inflation to 14{,}000--16{,}000 tokens. Generalized seeds (green) maintain or reduce response length. Stagnant seed (orange, seed100) remains near the SFT initialization.}
174	\label{fig:response_length}
175	\end{figure}
176	
177	\section{Unified Step-5 Evaluation}
178	\label{app:step5_unified}
179	
180	To guard against cherry-picking of checkpoints, Table~\ref{tab:step5_unified} reports all 11 seeds at a fixed evaluation point (training step~5). OOD results are included only for seeds with checkpoints evaluated under the D134 protocol (Section~\ref{sec:setup}); remaining checkpoints were unavailable for post-hoc OOD evaluation.
181	
182	\begin{table}[h]
183	\centering
184	\caption{Episode-level GRPO: all 11 seeds at training step~5 (134 OOD tasks, 32 ID tasks, $\tau{=}0.4$). SFT baseline: 12.5\% ID, 6.72\% OOD. OOD results marked ``---'' indicate checkpoints unavailable for post-hoc evaluation on the 134-task OOD set. ID results marked ``---'' indicate step-5 validation metrics not recorded in training logs.}
185	\label{tab:step5_unified}
186	\small
187	\setlength{\tabcolsep}{4pt}
188	\begin{tabular}{@{}lcccc@{}}
189	\toprule
190	\textbf{Seed} & \textbf{Cat.} & \textbf{ID} & \textbf{OOD} & \textbf{vs SFT} \\
191	\midrule
192	seed2048 & C & --- & 8.21 & NS \\
193	seed8 & C & 28.13 & 11.94 & NS \\
194	seed42 & C & 9.38 & 12.69 & NS \\
195	\midrule
196	seed200 & S & --- & 10.45 & NS \\
197	seed300 & S & 25.00 & 10.45 & NS \\
198	seed100 & S & 31.25 & 11.19 & NS \\
199	seed2 & S & --- & --- & --- \\
200	\midrule
201	seed1 & G$^\dagger$ & --- & 23.88 & $p{<}0.001$ \\
202	seed4 & G & --- & --- & --- \\
203	seed5 & G & --- & --- & --- \\
204	seed6 & G & 21.88$^\ddagger$ & --- & --- \\
205	\bottomrule
206	\end{tabular}
207	\begin{flushleft}
208	\small $^\dagger$ RAGEN built-in eval; checkpoint unavailable for re-evaluation. \\
209	\small $^\ddagger$ Registry value 21.9\% (7/32); rounded to 21.88\% for consistency with 32-task denominator.
210	\end{flushleft}
211	\end{table}
212	
213	\section{Evaluation Variance Analysis}
214	\label{app:eval_variance}
215	
216	To quantify evaluation noise at $\tau{=}0.4$, we evaluate a single checkpoint (seed200, step~5) three times independently on the 134-task OOD set with different random seeds.
217	
218	\begin{table}[h]
219	\centering
220	\caption{Evaluation variance for a single checkpoint (seed200 step~5, 134 OOD tasks, $\tau{=}0.4$). Three independent runs yield std$=$1.29pp, an order of magnitude smaller than the inter-seed performance range in Table~\ref{tab:seed_variability} (8.2\%--30.6\%).}
221	\label{tab:eval_variance}
222	\small
223	\setlength{\tabcolsep}{3pt}
224	\begin{tabular}{@{}lcccc@{}}
225	\toprule
226	\textbf{Checkpoint} & \textbf{Runs} & \textbf{OOD (\%)} & \textbf{Std} & \textbf{Range} \\
227	\midrule
228	seed200 step~5 & 3 & 11.94 & 1.29 & 2.24 \\
229	\bottomrule
230	\end{tabular}
231	\end{table}
232	
233	The small standard deviation (1.29pp) confirms that the large inter-seed differences observed in Table~\ref{tab:seed_variability}---ranging from 8.2\% (collapsed) to 30.6\% (generalized)---reflect genuine training dynamics rather than evaluation noise. We note that this variance estimate is based on a stagnant seed (seed200); generalized seeds with higher success rates may exhibit different variance profiles due to the non-linear relationship between success rate and binomial variance.
234	
235	The classification threshold between stagnant and generalized seeds is based on Fisher's exact test at $p < 0.01$ vs.\ the SFT baseline; shifting to $p < 0.05$ would reclassify seed2 (the marginal case at $p = 0.03$) as generalized, changing the generalization rate from 36\% to 45\%.
236	
237	\paragraph{Training efficiency.} Episode-level training processes the same total tokens as step-independent training but in fewer, longer sequences. On our hardware (2$\times$ RTX PRO 6000, 1.7B model), step-independent training ($h{=}2$) completes 15 steps in approximately 10--12 hours; episode-level training takes comparable wall-clock time as the increased sequence length is offset by fewer padding tokens.
238	
239	\section{Early Training Signal Analysis}
240	\label{app:early_signal}
241	
242	We investigated whether early training signals (steps 1--3) can predict seed-level generalization outcomes. We analyze 12 seeds grouped into three outcome categories following the definitions in Section~\ref{sec:seed_variability}: Generalized ($n{=}4$), Stagnant ($n{=}4$), and Collapsed ($n{=}4$, including seed7, which received a subsequent KL penalty intervention and is excluded from Table~\ref{tab:seed_variability}; its pre-intervention training trajectory is used here). No standard training metric (reward, KL divergence, entropy, gradient norm, response length, or train success rate) showed statistically significant between-group differences in the first three training steps (all Welch $t$-test $p > 0.2$, $n = 4$ per group). Two of the four Collapsed seeds (seed7, seed8) exhibited among the \textit{highest} early rewards and train success rates, with their collapse manifesting only after step~5 through response length inflation or reward degradation.
243	
244	The strongest candidate predictor was the mutual information diversity estimate at step~1, which showed a large effect size (Cohen's $d = 1.11$) favoring Generalized over Collapsed seeds and a trending correlation with final OOD performance (Spearman $\rho = 0.43$, $p = 0.19$), but remained non-significant with the available sample size ($n = 4$ per group). These results suggest that seed-dependent outcomes are governed by mechanisms not captured by standard early training diagnostics, and that early stopping or seed selection based on initial step metrics would be unreliable.
245	
246	\section{Use of AI Assistants}
247	\label{app:ai-assistants}
248	
249	We used Claude (Anthropic) as an AI coding and writing assistant
250	throughout this work. Specifically:
251	\begin{itemize}
252	    \item \textbf{Code:} drafting experiment scripts, data-processing
253	    pipelines, and analysis utilities; debugging and refactoring.
254	    \item \textbf{Writing:} drafting and revising paper sections,
255	    polishing prose, and reformatting LaTeX.
256	    \item \textbf{Literature:} identifying potentially relevant papers to inform
257	    our literature review.
258	\end{itemize}
259	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "c40086b3-c7da-425f-9e6c-866a3573746c",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "7f9e8c08-e233-4eeb-acb5-1f1429161ebf",
  "sourceToolAssistantUUID": "c40086b3-c7da-425f-9e6c-866a3573746c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 15 · 2026-05-24T14:56:37.774Z_

Now let me search for FloatBarrier usage across all these files:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7f9e8c08-e233-4eeb-acb5-1f1429161ebf",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6b1ZAmgJiwhGeVXwj",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "9cd02e5b-d76e-4ad2-b974-6082017ab738",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_015fywCVjbQNkcxQSMvCy6nb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 15213,
      "cache_read_input_tokens": 41745,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 15213,
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

_source line 16 · 2026-05-24T14:56:39.874Z_

<details open><summary>🔧 Tool call — Grep · `toolu_015KzphkAMBeSX1ykvZF58Pz`</summary>

```json
{
  "pattern": "FloatBarrier",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper",
  "type": "tex",
  "output_mode": "content",
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "9cd02e5b-d76e-4ad2-b974-6082017ab738",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6b1ZAmgJiwhGeVXwj",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "7caaee17-ed4f-4cdf-a623-7bf1ecece9ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_015fywCVjbQNkcxQSMvCy6nb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 6,
      "cache_creation_input_tokens": 15213,
      "cache_read_input_tokens": 41745,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 15213,
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

_source line 17 · 2026-05-24T14:56:39.887Z_

<details><summary>↩ Tool result · `toolu_015KzphkAMBeSX1ykvZF58Pz`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7caaee17-ed4f-4cdf-a623-7bf1ecece9ad",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "7946b1ec-c7b5-45ed-ae60-67f6d2ed5ba2",
  "sourceToolAssistantUUID": "7caaee17-ed4f-4cdf-a623-7bf1ecece9ad",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 18 · 2026-05-24T14:56:41.601Z_

Now let me check the main.tex file to see if there are any global FloatBarrier usages:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "7946b1ec-c7b5-45ed-ae60-67f6d2ed5ba2",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6wfGnTzP34fQpApNu",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "b30821df-fad9-4904-9548-ea7f3cf50c71",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01CpamMQUjdHvYfPu1CQBegY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 296,
      "cache_read_input_tokens": 56958,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 296,
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

_source line 19 · 2026-05-24T14:56:41.798Z_

<details open><summary>🔧 Tool call — Read · `toolu_01DJHFuNft8NVS7zgdNa8xHZ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/main.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "b30821df-fad9-4904-9548-ea7f3cf50c71",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb6wfGnTzP34fQpApNu",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "d20aee3c-3d5c-4db4-af66-ae74a64c35f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01CpamMQUjdHvYfPu1CQBegY",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 296,
      "cache_read_input_tokens": 56958,
      "output_tokens": 114,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 296
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4,
          "output_tokens": 114,
          "cache_read_input_tokens": 56958,
          "cache_creation_input_tokens": 296,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 296,
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

_source line 20 · 2026-05-24T14:56:41.803Z_

<details><summary>↩ Tool result · `toolu_01DJHFuNft8NVS7zgdNa8xHZ`</summary>

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
12	\usepackage{amsmath}
13	\usepackage{amssymb}
14	\usepackage{amsthm}
15	\usepackage{enumitem}
16	
17	\setlength{\textfloatsep}{8pt plus 2pt minus 2pt}
18	\setlength{\floatsep}{8pt plus 2pt minus 2pt}
19	\setlength{\intextsep}{6pt plus 2pt minus 2pt}
20	
21	\title{Sign Misattribution in Step-Independent Agent RL:\\Dual Mechanism Diagnosis and Episode-Level Correction}
22	
23	\author{Anonymous}
24	
25	\begin{document}
26	\maketitle
27	
28	\begin{abstract}
29	Reinforcement learning for multi-turn LLM agents requires credit assignment across long interaction trajectories. The dominant training paradigm decomposes these trajectories into fixed-size windows optimized independently via Group Relative Policy Optimization (GRPO), yet this ubiquitous design choice has received little scrutiny. We identify a structural credit assignment pathology driven by two distinct mechanisms: \textit{policy information loss}, which truncates cross-window context and imposes a constant performance ceiling, and \textit{advantage sign misattribution}, which causes a substantial fraction of gradient updates for locally correct actions to carry incorrect sign. A partial factorial experiment (3 of 4 cells) isolates each mechanism: removing sign misattribution converts catastrophic collapse into bounded learning; removing information loss enables out-of-distribution (OOD) generalization. Direct sign measurement confirms the theoretical prediction, with credit agreement dropping to near-random levels. Episode-level GRPO, which treats the full trajectory as a single optimization sample, addresses both failure modes, yielding 17.2\% mean OOD success versus 6.7\% SFT baseline. However, a systematic multi-seed evaluation reveals that avoiding collapse is necessary but not sufficient: 73\% of seeds stabilize, yet only 36\% achieve statistically significant OOD transfer. Cross-scale verification at 8B parameters and cross-environment validation on ScienceWorld provide preliminary evidence that the pathology extends beyond our primary setting.
30	\end{abstract}
31	
32	\input{introduction}
33	\input{related_work}
34	\input{method}
35	\input{theoretical_analysis}
36	\input{experiments}
37	\input{discussion}
38	\input{conclusion}
39	
40	\section*{Limitations}
41	
42	Our experiments span two environments (ALFWorld, ScienceWorld) and two scales (1.7B, 8B); additional environments and scales would strengthen generality. The 8B and ScienceWorld results report single-seed runs due to computational constraints. Among 11 seeds at 1.7B, only 36\% achieve statistically significant OOD generalization; we cannot rule out that stagnant seeds would eventually generalize with substantially more training steps, though seed100's minimal improvement from step~5 to step~10 suggests the bottleneck is not simply training duration. The mechanism driving seed-dependent transfer remains an open question. We do not empirically reproduce concurrent methods (HCAPO, Turn-PPO, GiGPO); our comparisons are based on published results and post-hoc consistency analysis. All OOD evaluations use temperature $\tau{=}0.4$ with a single run per checkpoint. Controlled evaluation of the same checkpoint (3 independent runs at $\tau{=}0.4$ on 134 OOD tasks) yields a standard deviation of 1.29 percentage points, confirming that inter-seed differences in Table~\ref{tab:seed_variability} reflect genuine training dynamics rather than evaluation noise. For very long episodes ($T > 100$) or tasks with many independent sub-goals, uniform episode-level advantage may limit efficiency even though it preserves direction correctness.
43	
44	\bibliography{references}
45	
46	\clearpage
47	\input{appendix}
48	
49	\end{document}
50	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "d20aee3c-3d5c-4db4-af66-ae74a64c35f0",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "bffb7fd3-7cdb-4225-9b45-403e18a7fef5",
  "sourceToolAssistantUUID": "d20aee3c-3d5c-4db4-af66-ae74a64c35f0",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 21 · 2026-05-24T14:56:43.151Z_

Let me also check the other section files to ensure I haven't missed anything:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "bffb7fd3-7cdb-4225-9b45-403e18a7fef5",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb74jRRetGQd62HzzDW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "4feb7c7a-21a8-4d43-8c6b-f49f6fbe0edb",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016nxEfeCrAgSTc15V7eujxz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 57254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1215,
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

_source line 22 · 2026-05-24T14:56:43.931Z_

<details open><summary>🔧 Tool call — Read · `toolu_0118t2DQtwLQxxMkRvmoEPek`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "4feb7c7a-21a8-4d43-8c6b-f49f6fbe0edb",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb74jRRetGQd62HzzDW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "93a19527-dd5d-4960-b8ee-ced6c8ef9478",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016nxEfeCrAgSTc15V7eujxz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 57254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1215,
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

_source line 23 · 2026-05-24T14:56:43.940Z_

<details><summary>↩ Tool result · `toolu_0118t2DQtwLQxxMkRvmoEPek`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Reinforcement learning from sparse terminal reward has emerged as a promising paradigm for training LLM agents on multi-turn interactive tasks spanning 30--50 interaction steps~\cite{kim2025reflact,digiRL2024,wang2022scienceworld}. Group Relative Policy Optimization (GRPO)~\cite{shao2024deepseekmath}, with its critic-free design, has become the algorithm of choice. Yet a gap persists between the promise of RL-driven agent improvement and the reality of training outcomes: recent agent RL systems~\cite{ragen2025,selfguide2026,spear2025,feng2025gigpo} share a common, unscrutinized implementation pattern (decomposing trajectories into fixed-size windows, each optimized independently) and frequently report training instability without diagnosing its root cause.
5	
6	We show this \textit{step-independent} default introduces a fundamental credit assignment pathology. Step-independent training partitions trajectories into non-overlapping $h$-step windows, each optimized via GRPO. This produces a two-phase collapse: task success drops to 0\% while action validity initially remains high, then continued training destroys even basic formatting. Standard remedies (dense reward shaping, discount tuning) fail. Concurrent methods that improve per-step credit quality (GiGPO~\cite{feng2025gigpo}, GAGPO~\cite{gagpo2026}, Turn-PPO~\cite{turnppo2025}, HCAPO~\cite{hcapo2026}) address the credit assignment challenge through improved step-level mechanisms, validating that sign correctness is the critical factor. Our contribution is orthogonal: we formally diagnose \textit{why} the default windowing fails.
7	
8	We trace the collapse to two mechanisms at different layers. \textit{\textbf{Policy information loss}} (M1) operates at the inference layer: each window lacks access to earlier observations, imposing a constant performance ceiling. \textit{\textbf{Advantage sign misattribution}} (M2) operates at the training layer: under binary reward, the advantage sign reflects episode success rather than local action quality. Our theoretical analysis shows that a substantial fraction of gradient updates for locally correct actions carry incorrect sign (Section~\ref{sec:theory}), a prediction confirmed by direct measurement (Section~\ref{sec:sign_verification}). Sign errors, amplified by the M1--M2 feedback loop, cause progressive degradation rather than merely slow convergence. Our primary contribution is diagnostic: we identify, formalize, and empirically validate a previously uncharacterized pathology in the dominant training paradigm. Episode-level GRPO (not a new method, but the original GRPO design) addresses both mechanisms by treating the full trajectory as a single optimization sample, achieving substantial OOD improvement where step-independent collapses to 0\%, with preliminary evidence of persistence at 8B scale.
9	
10	Our contributions:
11	\begin{enumerate}[nosep,leftmargin=*]
12	\item \textbf{Dual mechanism diagnosis.} We formalize \textit{information loss} and \textit{sign misattribution} as distinct failure modes with different temporal behaviors (constant ceiling versus cumulative degradation) and derive closed-form expressions for the probability of incorrect gradient direction.
13	\item \textbf{Empirical validation.} We validate this diagnosis through a partial factorial experiment that isolates each mechanism, direct sign measurement confirms the theoretical prediction at near-random levels, and preliminary cross-scale (8B) and cross-environment (ScienceWorld) evidence supports generality. Episode-level training (reverting to GRPO's original design) addresses both mechanisms, but a systematic 11-seed evaluation reveals seed-dependent generalization: 73\% of seeds avoid collapse while only 36\% achieve statistically significant OOD improvement.
14	\end{enumerate}
15	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "93a19527-dd5d-4960-b8ee-ced6c8ef9478",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "38d91506-9f1d-47b7-be20-915ddd865921",
  "sourceToolAssistantUUID": "93a19527-dd5d-4960-b8ee-ced6c8ef9478",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Tool call

_source line 24 · 2026-05-24T14:56:44.205Z_

<details open><summary>🔧 Tool call — Read · `toolu_013vLeA1N2gei1XLioXF1yXn`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "38d91506-9f1d-47b7-be20-915ddd865921",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb74jRRetGQd62HzzDW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "863ddc57-08de-4c30-9b1a-f95148f9af5e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016nxEfeCrAgSTc15V7eujxz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 57254,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 1215,
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

_source line 25 · 2026-05-24T14:56:44.211Z_

<details><summary>↩ Tool result · `toolu_013vLeA1N2gei1XLioXF1yXn`</summary>

```text
1	\section{Method}
2	\label{sec:method}
3	
4	\subsection{Problem Formulation and GRPO}
5	\label{sec:problem_formulation}
6	
7	We model the multi-turn agent as a partially observable Markov decision process (POMDP)~\cite{kaelbling1998planning} where the policy $\pi_\phi(a_t \mid h_t)$ generates actions conditioned on interaction history $h_t = (o_1, a_1, \ldots, o_t)$. Episodes of $T$ steps terminate with binary reward $R \in \{0, r_+\}$ (our experiments use a penalty variant with $r_- = -0.1$ per invalid action; Section~\ref{sec:setup}). GRPO~\cite{shao2024deepseekmath} samples $K$ rollouts per task and computes group-relative advantages:
8	\begin{align}
9	\hat{A}_k &= \frac{R_k - \mu}{\sigma + \epsilon}, \notag \\
10	\mu &= \frac{1}{K}\sum_{j=1}^K R_j, \quad \sigma = \sqrt{\frac{1}{K}\sum_{j=1}^K (R_j - \mu)^2}
11	\label{eq:grpo_advantage}
12	\end{align}
13	GRPO is episode-level by design: each rollout receives one return and one advantage, with no inherent temporal discounting.
14	
15	\subsection{Step-Independent Windowing}
16	\label{sec:step_independent}
17	
18	Agent RL frameworks must reconcile GRPO's episode-level design with the memory constraints of long trajectories. RAGEN~\cite{ragen2025} introduces \textbf{step-independent training}: the trajectory is partitioned into non-overlapping $h$-step windows, each receiving a discounted return:
19	\begin{equation}
20	R_k = \gamma^{(N - k)} \cdot R_{\text{episode}}
21	\label{eq:step_return}
22	\end{equation}
23	where $N = \lceil T/h \rceil$ is the number of windows. Each window is optimized as an independent GRPO sample. This reduces sequence length from $O(T)$ to $O(h)$ and multiplies the effective batch size, but structurally alters credit assignment.
24	
25	\begin{figure*}[t]
26	\centering
27	\includegraphics[width=\textwidth]{fig_overview.pdf}
28	\caption{Step-independent windowing (left) partitions the trajectory into fixed windows, each optimized independently. This introduces two failure mechanisms: M1 (information loss) truncates context at window boundaries, and M2 (sign misattribution) assigns all windows the same advantage sign based on episode outcome. Episode-level training (right) treats the full trajectory as a single sample, eliminating both mechanisms.}
29	\label{fig:overview}
30	\end{figure*}
31	
32	\subsection{Dual Mechanism Analysis}
33	\label{sec:dual_mechanism}
34	
35	Two mechanisms jointly cause training failure under step-independent optimization.
36	
37	\subsubsection{Mechanism 1: Policy Information Loss}
38	\label{sec:m1_information_loss}
39	
40	Step-independent training truncates context at both inference and training time. The policy $\pi_\phi(a_t \mid h_{\text{window}_k})$ conditions on only the local $h$-step history, losing access to earlier observations. With $h{=}2$, a window at step~8 has no access to the outcome of an exploration action at step~4, so the policy cannot learn strategies spanning more than $h$ steps. This imposes a \textit{constant} performance ceiling: no amount of optimization can recover absent information.
41	
42	\subsubsection{Mechanism 2: Advantage Sign Misattribution}
43	\label{sec:m2_sign_misattribution}
44	
45	Group normalization under step-independent training produces advantages whose sign reflects the \textit{episode} outcome, not local action quality:
46	\begin{equation}
47	\text{sign}(\hat{A}_k) \approx \text{sign}(R_{\text{episode}} - \mu)
48	\label{eq:sign_correlation}
49	\end{equation}
50	In failed episodes ($R_{\text{episode}} = 0$), all windows receive negative advantages when $\mu > 0$, including windows with locally correct actions. Conversely, successful episodes reinforce all windows, including those with suboptimal actions. Unlike M1's constant ceiling, sign misattribution is \textit{cumulative}: each wrong-sign gradient step further erodes policy competence. The discount factor $\gamma^{(N-k)}$ introduces magnitude decay across positions, but sign errors are strictly more harmful: magnitude decay slows convergence, while sign errors cause active divergence.
51	
52	\subsection{Episode-Level Training}
53	\label{sec:episode_level}
54	
55	Episode-level training addresses both mechanisms by treating the complete trajectory as a single GRPO sample. The full history $h_t$ is available at every step (eliminating M1), and a single advantage $\hat{A}$ applies uniformly to all tokens (eliminating M2). Uniform reinforcement of successful trajectories preserves good sub-strategies; window-level sign errors actively destroy them. This is GRPO's original design; step-independent windowing is the deviation.
56	
57	\subsection{Partial Factorial Design}
58	\label{sec:factorial_design}
59	
60	To separate the two mechanisms, we design a $2 \times 2$ partial factorial varying observation scope and advantage granularity: \textbf{Cell~A} (truncated $h{=}2$ + step-level advantage; both mechanisms active), \textbf{Cell~B} (truncated $h{=}2$ + episode-level advantage; only M1 active), \textbf{Cell~D} (full trajectory + episode-level advantage; neither active), and \textbf{Cell~C} (full trajectory + step-level advantage; only M2 active). Cell~C encountered persistent numerical instability across six hyperparameter configurations (Appendix~\ref{app:cell_c}); we therefore evaluate a partial 3-of-4 factorial. Comparing A vs.\ B isolates sign misattribution; comparing B vs.\ D isolates information loss.
61	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "863ddc57-08de-4c30-9b1a-f95148f9af5e",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "ef9a6a64-bf99-4428-9f52-f260c8d6002f",
  "sourceToolAssistantUUID": "863ddc57-08de-4c30-9b1a-f95148f9af5e",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Tool call

_source line 26 · 2026-05-24T14:56:44.356Z_

<details open><summary>🔧 Tool call — Read · `toolu_011i1t4G4Eds1kb14diRbr8p`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "ef9a6a64-bf99-4428-9f52-f260c8d6002f",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb74jRRetGQd62HzzDW",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "afbc67c4-8d13-4740-bad5-23915b59e87c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_016nxEfeCrAgSTc15V7eujxz",
    "type": "message",
    "stop_reason": "tool_use",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 4,
      "cache_creation_input_tokens": 1215,
      "cache_read_input_tokens": 57254,
      "output_tokens": 255,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 1215
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 4,
          "output_tokens": 255,
          "cache_read_input_tokens": 57254,
          "cache_creation_input_tokens": 1215,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 1215,
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

_source line 27 · 2026-05-24T14:56:44.363Z_

<details><summary>↩ Tool result · `toolu_011i1t4G4Eds1kb14diRbr8p`</summary>

```text
1	\section{Related Work}
2	\label{sec:related_work}
3	
4	\paragraph{RL for multi-turn LLM agents.}
5	GRPO~\cite{shao2024deepseekmath}, PPO~\cite{schulman2017ppo}, and RLHF methods~\cite{ouyang2022instructgpt,rafailov2023dpo} have been extended to multi-turn agents~\cite{yao2023react,ragen2025} via step-independent windowing. Subsequent work improves algorithms~\cite{feng2025gigpo,dapo2025}, rewards~\cite{selfguide2026}, or pipelines~\cite{spear2025,digiRL2024}, but all assume windowing is benign.
6	
7	\paragraph{Credit assignment.}
8	Classical methods span bootstrapping~\cite{sutton1988td} to Monte Carlo~\cite{williams1992reinforce,schulman2016gae} (Appendix~\ref{app:classical_connection}). Step-independent GRPO inherits the worst of outcome-vs-process supervision~\cite{lightman2024lets}: coarse credit without correct direction. ArCHer~\cite{zhou2024archer}, VinePPO~\cite{kazemnejad2024vineppo}, PRIME~\cite{prime2025}, and VAPO~\cite{vapo2025} improve credit granularity; our analysis explains when such methods are safe (only after M2 is resolved). IRC~\cite{irc2026}, MC-GRPO~\cite{mcgrpo2026}, GRPO-$\lambda$~\cite{grpolambda2025}, and OAR~\cite{oar2026} corroborate our sign-level diagnosis. Turn-PPO~\cite{turnppo2025}, GAGPO~\cite{gagpo2026}, MT-GRPO~\cite{mtgrpo2025}, SWEET-RL~\cite{sweetrl2025}, iStar~\cite{istar2025}, and HCAPO~\cite{hcapo2026} propose finer-grained credit that addresses sign correctness.
9	
10	\paragraph{GRPO collapse phenomena.}
11	RAGEN-2~\cite{ragen2_2026}, GRPO-Collapse~\cite{grpocollapse2025}, RC-GRPO~\cite{rcgrpo2026}, and EDGE-GRPO~\cite{edgegrpo2025} address variance collapse. Our dual-mechanism diagnosis unifies these: reward variance collapse is a special case of reward saturation (Section~\ref{sec:theory}), and the death spiral follows from the M1--M2 vicious cycle.
12	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "afbc67c4-8d13-4740-bad5-23915b59e87c",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "e12d0067-73ed-4015-b6c9-3dc6bb5d24d0",
  "sourceToolAssistantUUID": "afbc67c4-8d13-4740-bad5-23915b59e87c",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 28 · 2026-05-24T14:56:45.509Z_

Let me check the remaining files as well:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "e12d0067-73ed-4015-b6c9-3dc6bb5d24d0",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb7FHRuUf8Y6Bs1tFPU",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "97c5d66e-60c1-4ff3-9e19-f1a716b4a149",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01YFwXiqzgjbpn1kFXLuL4Po",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 3554,
      "cache_read_input_tokens": 58469,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3554,
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

_source line 29 · 2026-05-24T14:56:46.412Z_

<details open><summary>🔧 Tool call — Read · `toolu_01PbYcc18DE3mkW1Esp1DEMh`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "97c5d66e-60c1-4ff3-9e19-f1a716b4a149",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb7FHRuUf8Y6Bs1tFPU",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "7efcc671-aa13-43ea-bac1-6e4735a6af42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01YFwXiqzgjbpn1kFXLuL4Po",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 3554,
      "cache_read_input_tokens": 58469,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3554,
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

_source line 30 · 2026-05-24T14:56:46.418Z_

<details><summary>↩ Tool result · `toolu_01PbYcc18DE3mkW1Esp1DEMh`</summary>

```text
1	\section{Discussion}
2	\label{sec:discussion}
3	
4	\paragraph{Generality.}
5	Sign misattribution arises whenever three properties co-occur: step-level windowing, sparse binary reward, and group-relative normalization---theoretically sufficient within any group-relative framework (Section~\ref{sec:theory}), though verified only on GRPO with ALFWorld and ScienceWorld. M1 and M2 interact: M1 lowers $p$, increasing wrong-sign updates under M2, which further degrades $p$ (Appendix~\ref{app:why_defaults}).
6	
7	\paragraph{Mechanism interaction and seed dependence.}
8	Cell~C (full trajectory + step-level advantage) produces NaN instability rather than gradual collapse, suggesting M1 may unintentionally stabilize training by limiting gradient variance. Multi-seed evaluation reveals bimodal OOD transfer---with training duration unable to explain the gap (seed100: $+$1.5pp step~5$\to$10), pointing to initialization sensitivity (Appendix~\ref{app:early_signal}).
9	
10	\paragraph{Concurrent methods.}
11	HCAPO~\cite{hcapo2026} and GiGPO~\cite{feng2025gigpo} succeed with the same $h{=}2$ that causes Cell~A collapse by replacing step-level advantage with finer-grained credit, directly eliminating M2 while preserving M1. Our framework provides a consistent post-hoc explanation: HCAPO's 91.4\% (7B) and GiGPO's 90.2\% are consistent with M2 being the primary bottleneck at sufficient scale, where M1's ceiling permits strong performance. We emphasize these are post-hoc consistency analyses based on published results, not predictions; we do not reproduce these methods (see also Limitations).
12	
13	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "7efcc671-aa13-43ea-bac1-6e4735a6af42",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "d3dbcc1a-d849-401c-a309-2a6020b273f8",
  "sourceToolAssistantUUID": "7efcc671-aa13-43ea-bac1-6e4735a6af42",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Tool call

_source line 31 · 2026-05-24T14:56:46.612Z_

<details open><summary>🔧 Tool call — Read · `toolu_01Lq1VsJ7uCQB2zUja5MFmcq`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "d3dbcc1a-d849-401c-a309-2a6020b273f8",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb7FHRuUf8Y6Bs1tFPU",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "69d67268-0c2a-4229-a25d-56b5acbf5c61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01YFwXiqzgjbpn1kFXLuL4Po",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 3554,
      "cache_read_input_tokens": 58469,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 3554,
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

_source line 32 · 2026-05-24T14:56:46.621Z_

<details><summary>↩ Tool result · `toolu_01Lq1VsJ7uCQB2zUja5MFmcq`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	Step-independent training fails through two mechanisms: information loss imposes a constant performance ceiling while sign misattribution causes cumulative degradation. Episode-level GRPO validates the diagnosis by addressing both, though only 36\% of seeds achieve significant OOD generalization. This finding applies to GRPO-style methods under step-level windowing, sparse reward, and group-relative normalization (Section~\ref{sec:dual_mechanism}), verified on GRPO in ALFWorld and ScienceWorld.
5	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "parentUuid": "69d67268-0c2a-4229-a25d-56b5acbf5c61",
  "isSidechain": true,
  "promptId": "9e5a129d-fa4d-4565-9dc1-2bc8ba040f44",
  "agentId": "af017f6f4420a0870",
  "type": "user",
  "uuid": "708bb85e-cbee-4f34-9c32-f3521f66496b",
  "sourceToolAssistantUUID": "69d67268-0c2a-4229-a25d-56b5acbf5c61",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren"
}
```

</details>

---

### Assistant

_source line 33 · 2026-05-24T14:57:10.823Z_

Perfect! Now I have comprehensive information about all figures and tables. Let me compile the complete report:

## Complete Report: All \begin{figure} and \begin{table} Declarations

Based on my thorough search of all .tex files in `/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/docs/paper/`, here is the complete inventory:

### FIGURES

**1. File: theoretical_analysis.tex**
   - **Line:** 24
   - **Placement specifier:** `[t]`
   - **Caption/Label:** "Upper bound on the probability of correct gradient sign as a function of episode success rate $p$ (Proposition~2)... At ALFWorld's baseline ($p{=}12.5\%$, $K{=}8$), at most 19.1\% of updates are correct."
   - **Label reference:** `fig:theory_curve`
   - **FloatBarrier usage:** None detected

**2. File: experiments.tex**
   - **Line:** 67
   - **Placement specifier:** `[t]`
   - **Caption/Label:** "Sign-episode correlation (binary reward, penalty${=}0$) vs.\ credit agreement rate (penalty reward). Under binary reward, advantage sign near-perfectly tracks episode outcome (99.6\%, $270/271$), confirming M2. Under penalty reward, credit agreement with local action quality drops to 52.1\% ($n{=}3{,}000$), near random chance (dashed line)."
   - **Label reference:** `fig:sign_misattribution`
   - **FloatBarrier usage:** None detected

**3. File: experiments.tex**
   - **Line:** 24
   - **Placement specifier:** `[t]` (note: this is a figure* environment with `[t]`)
   - **Caption/Label:** "(a)~Training dynamics across factorial conditions (metric type indicated in legend). Cell~A collapses within 5 steps; Cell~B shows bounded learning; Cell~D improves monotonically. (b)~Window size $h$ vs.\ success rate (single seed)... Hatched bars indicate collapsed conditions."
   - **Label reference:** `fig:hsweep`
   - **FloatBarrier usage:** None detected

**4. File: appendix.tex**
   - **Line:** 170
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "Response length over training for 7 seeds under episode-level GRPO. Collapsed seeds (red) exhibit length inflation to 14{,}000--16{,}000 tokens. Generalized seeds (green) maintain or reduce response length. Stagnant seed (orange, seed100) remains near the SFT initialization."
   - **Label reference:** `fig:response_length`
   - **FloatBarrier usage:** None detected

**5. File: appendix.tex**
   - **Line:** 98
   - **Placement specifier:** `[t]` (figure* environment)
   - **Caption/Label:** "(a)~Cross-scale verification (single seed): both collapse (Cell~A) and fix (Cell~D) are observed from 1.7B to 8B. The episode-level fix appears more effective at 8B (96.9\% vs.\ 34.4\% in-distribution). (b)~Information loss (M1) quantification (single seed each): restricting context to $h{=}2$ drops SFT performance by 37.5pp at 8B ALFWorld and 30.3pp on ScienceWorld."
   - **Label reference:** `fig:cross_scale`
   - **FloatBarrier usage:** None detected

**6. File: method.tex**
   - **Line:** 25
   - **Placement specifier:** `[t]` (figure* environment)
   - **Caption/Label:** "Step-independent windowing (left) partitions the trajectory into fixed windows, each optimized independently. This introduces two failure mechanisms: M1 (information loss) truncates context at window boundaries, and M2 (sign misattribution) assigns all windows the same advantage sign based on episode outcome. Episode-level training (right) treats the full trajectory as a single sample, eliminating both mechanisms."
   - **Label reference:** `fig:overview`
   - **FloatBarrier usage:** None detected

**7. File: appendix.tex**
   - **Line:** 155
   - **Placement specifier:** `[t]` (figure* environment)
   - **Caption/Label:** "(a)~Standard remedies for step-independent training: dense reward shaping and discount factor $\gamma{=}1.0$ both collapse to 0\%; REINFORCE++ matches the SFT baseline without improvement. Only episode-level training (Cell~D) exceeds baseline. (b)~Dense reward gaming: action validity rises from 60\% to 97.5\% while task success remains 0\%; the agent maximizes format-level rewards without solving tasks."
   - **Label reference:** `fig:additional_conditions`
   - **FloatBarrier usage:** None detected

### TABLES

**1. File: experiments.tex**
   - **Line:** 31
   - **Placement specifier:** `[t]`
   - **Caption/Label:** "1.7B results on ALFWorld (OOD 134-task set, In-Dist 32-task set). All cells report best checkpoint per seed. Cell~A: 2 seeds, best checkpoint each (both 0\%). Cell~B: 2 seeds, best checkpoint each. Cell~D: 2 seeds, mean $\pm$ range. Cell~D mean OOD (17.2\%) is consistent with the 11-seed evaluation (Table~\ref{tab:seed_variability})... Full seed-level breakdown in Table~\ref{tab:seed_variability} (11 seeds) and Appendix Table~\ref{tab:additional_baselines}."
   - **Label reference:** `tab:main_results`
   - **FloatBarrier usage:** None detected

**2. File: experiments.tex**
   - **Line:** 81
   - **Placement specifier:** `[t]`
   - **Caption/Label:** "Episode-level GRPO across 11 seeds (134 OOD tasks, $\tau{=}0.4$, best checkpoint per seed). Category: C=Collapsed, S=Non-collapsed (stagnant), G=Generalized (Fisher exact $p{<}0.01$ vs.\ SFT)... SFT baseline: 6.72\% (9/134)... Step-5 results for all seeds in Appendix~\ref{app:step5_unified}."
   - **Label reference:** `tab:seed_variability`
   - **FloatBarrier usage:** None detected

**3. File: appendix.tex**
   - **Line:** 72
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "Shared RL training hyperparameters across all conditions."
   - **Label reference:** `tab:hyperparameters_app`
   - **FloatBarrier usage:** None detected

**4. File: appendix.tex**
   - **Line:** 105
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "8B results on ALFWorld. SFT and $h{=}2$ use decoding temperature $\tau{=}0$; RL uses $\tau{=}0.4$. Cell~A: step~2 (post-collapse). Cell~D: step~10. Single seed. The primary comparison is Cell~A collapse (0\%) vs Cell~D success, which is independent of decoding temperature."
   - **Label reference:** `tab:8b_results`
   - **FloatBarrier usage:** None detected

**5. File: appendix.tex**
   - **Line:** 133
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "Additional baselines on ALFWorld (1.7B). Neither method improves over the SFT baseline on in-distribution tasks."
   - **Label reference:** `tab:additional_baselines`
   - **FloatBarrier usage:** None detected

**6. File: appendix.tex**
   - **Line:** 182
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "Episode-level GRPO: all 11 seeds at training step~5 (134 OOD tasks, 32 ID tasks, $\tau{=}0.4$). SFT baseline: 12.5\% ID, 6.72\% OOD. OOD results marked ``---'' indicate checkpoints unavailable for post-hoc evaluation on the 134-task OOD set."
   - **Label reference:** `tab:step5_unified`
   - **FloatBarrier usage:** None detected

**7. File: appendix.tex**
   - **Line:** 218
   - **Placement specifier:** `[h]`
   - **Caption/Label:** "Evaluation variance for a single checkpoint (seed200 step~5, 134 OOD tasks, $\tau{=}0.4$). Three independent runs yield std$=$1.29pp, an order of magnitude smaller than the inter-seed performance range in Table~\ref{tab:seed_variability} (8.2\%--30.6\%)."
   - **Label reference:** `tab:eval_variance`
   - **FloatBarrier usage:** None detected

### SUMMARY

- **Total figures:** 7
- **Total tables:** 7
- **FloatBarrier usage:** No \FloatBarrier commands detected anywhere in the paper
- **Placement specifiers used:** `[t]` (top) for main text figures/tables, `[h]` (here) for appendix floats
- **Files containing floats:** experiments.tex (3), appendix.tex (7), theoretical_analysis.tex (1), method.tex (1)

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "parentUuid": "708bb85e-cbee-4f34-9c32-f3521f66496b",
  "isSidechain": true,
  "agentId": "af017f6f4420a0870",
  "requestId": "req_011CbMb7RsALDMcMgrvQtfNg",
  "attributionAgent": "Explore",
  "type": "assistant",
  "uuid": "3ed793d5-8881-4d46-8ee2-dd608bc8d984",
  "userType": "external",
  "entrypoint": "sdk-cli",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_1/projects/cost-verify-agent-rl/.claude/sessions/director_fd480a9c",
  "sessionId": "49a1b433-ab87-4540-bf0c-d46597468d5d",
  "version": "2.1.126",
  "gitBranch": "HEAD",
  "slug": "wobbly-knitting-wren",
  "message": {
    "model": "claude-haiku-4-5-20251001",
    "id": "msg_01ThAssaNAUeZPWkZSWJotm5",
    "type": "message",
    "stop_reason": "end_turn",
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 5,
      "cache_creation_input_tokens": 833,
      "cache_read_input_tokens": 62023,
      "output_tokens": 2418,
      "server_tool_use": {
        "web_search_requests": 0,
        "web_fetch_requests": 0
      },
      "service_tier": "standard",
      "cache_creation": {
        "ephemeral_1h_input_tokens": 0,
        "ephemeral_5m_input_tokens": 833
      },
      "inference_geo": "",
      "iterations": [
        {
          "input_tokens": 5,
          "output_tokens": 2418,
          "cache_read_input_tokens": 62023,
          "cache_creation_input_tokens": 833,
          "cache_creation": {
            "ephemeral_5m_input_tokens": 833,
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
