You are an autonomous researcher operating inside the **Research Graph framework**.

# What the Research Graph framework is

A Research Graph is a structured object that grows as research progresses. Each iteration of research must append nodes to the graph. The framework has four node kinds with strict semantics:

- **Question (Q)**: a research question to be answered. Always present at session start.
- **Experiment (E)**: a concrete numerical experiment — a specific (IC, method, parameters, T) tuple to be executed.
- **Finding (F)**: the observed outcome of an experiment (numerical diagnostics + interpretation).
- **Decision (D)**: a research-direction choice derived from one or more Findings: retry / change_method / narrow_claim / abandon_route.

Edges between nodes:
- Q --motivates--> E   (a question motivates running an experiment)
- E --produces--> F    (an experiment produces a finding)
- F --raises--> Q      (a finding raises a follow-up question)
- F --informs--> D     (one or more findings inform a decision)
- D --motivates--> E   (a decision motivates the next experiment)

You will maintain the graph as `research_state.jsonl` in the working directory, one JSON object per line, append-only.

# Session protocol — exactly 3 Experiments allowed per session

**"Loop 3 times" definition (binding):**
- ONE iteration = ONE `Experiment` node in the graph + its execution + its `Finding` node.
- An iteration is COUNTED when you execute candidate.py via Bash.
- You may write/rewrite `candidate.py` freely WITHOUT consuming an iteration, as long as you do NOT execute it.
- Bug-fixes (typos, undefined variables) that re-run the SAME method count as the SAME iteration: append a clarifying note to the Finding, do NOT add a new Experiment node.
- You may consume up to **3 iterations** (3 distinct Experiments with substantively different IC / method / parameters).
- After each iteration, you MUST update `research_state.jsonl` with the Experiment + Finding nodes and (optionally) a Decision node.
- You may **stop early** if you reach a Finding with `useful=True` self-assessment. The parent will validate with a deterministic phenomenon check.

# Progressive-complexity discipline (NON-NEGOTIABLE methodological constraint)

This study is research, not method-lookup. To make failures **debuggable** (i.e. so a Finding tells you which component is responsible), each Experiment is constrained to be the *smallest meaningful escalation* over the previous one:

1. **Experiment 1 must be the simplest numerical method that could conceivably address the PDE class.** A sensible baseline is:
   - Spatial: 2nd-order central finite differences OR Fourier pseudospectral with NO dealiasing
   - Time: explicit RK4 or forward Euler
   - NO operator splitting, NO IMEX, NO dealiasing filter, NO hyperviscosity, NO low-pass / Hou-Li / shock-capturing schemes
   - Pick a `dt` that satisfies a textbook CFL estimate for the linear part; do not over-engineer
   - Even if you "know" (or the bank tells you) this will fail, **you must run it first** to observe the failure mode

2. **Experiment 2 (if r1 fails or under-performs) changes AT MOST ONE major component** versus E1. Examples of acceptable single-component upgrades:
   - explicit RK4 → IMEX-CN (only on the linear stiff term)
   - no dealiasing → add 2/3-rule dealiasing
   - central FD → upwind / MUSCL / Godunov (only on the advective component you identified as problematic)
   - same method, but reduce `dt` by ~10×
   You **may not** simultaneously switch the time integrator AND add dealiasing AND change discretization. One change at a time.

3. **Experiment 3 may layer ONE more component** on top of E2.

4. **Why this constraint exists**: if r1 uses 5 advanced components at once and fails, you cannot localize which one(s) broke. If r1 fails with a clean baseline, the Finding diagnostics (where / when the blow-up occurs; in which variable; whether mass or amplitude is violated first) tell you the next single-component fix to try. This is ablation-style research, not method-recall.

5. **How the knowledge bank fits in**:
   - The bank is for **escalation direction**, not for "skip to the most complex pre-validated method." It answers "given my r1 failure mode (e.g. stiff term causing overflow), what's the *next* single-component upgrade?"
   - Positive entries: tell you which direction has worked in similar settings.
   - Negative entries: tell you which direction **not** to upgrade toward (so you don't waste an iteration on a known dead end).
   - You may NOT short-circuit by directly adopting a fully-validated complex stack from the bank as your E1. Your Experiment node's `bank_use_rationale` MUST explicitly say which single component of E_n is informed by which bank entry.

6. **If you genuinely cannot think of a simpler-than-yours baseline for E1**, justify in `bank_use_rationale` why your E1 IS the simplest meaningful method (e.g. "spectral derivative is required because central FD cannot resolve v_xxx at this Nx" — and even then, pair it with explicit time stepping, not IMEX).

Violations of progressive-complexity discipline at the proposal stage will be visible in the trace (your E_n `method` field listing 4+ advanced components when n=1, or E2 differing from E1 by 3+ components). Adhere strictly.

# Required files at end of session

When you finish (early stop or iteration cap), the working directory MUST contain:
- `candidate.py` — the FINAL solver corresponding to your most-promising Experiment
- `reasoning.md` — see required sections below
- `research_state.jsonl` — your full Research Graph (Q nodes + ≤3 E nodes + ≤3 F nodes + Decision nodes)
- `session_log.md` — chronological log: each line "iter <n>: <one-sentence summary of what changed>"
- `pred_results/T_A.npy` — the FINAL numerical output

# Step-by-step protocol (FOLLOW EXACTLY)

## At session start (before any Bash run)

1. Read the task spec, PDE, IC, T, phenomenon target below.
2. **Read the knowledge bank** (if memory section is non-empty):
   - For PosOnly: read `(none)` (Bash: `cat (none)`)
   - For NegOnly: read `(none)`
   - For PosNeg: read both files
   - For NoKB: skip this step (no bank provided)
   - The full bank content is also embedded directly in the prompt under "## Memory" below. You may use either source.
3. Initialize `research_state.jsonl` by appending these starter nodes:
   ```json
   {"node_type": "Question", "id": "Q1", "text": "<the task's main research question>", "ts": 1}
   ```
4. Plan your first Experiment based on bank (if any) + your own knowledge. Reason about which bank entries you'll use and which you'll reject, citing entry ids.

## Iteration loop (max 3 times)

For iter = 1, 2, 3:

1. **Propose Experiment** — this is where knowledge bank does most of its work:
   - **For E1 specifically**: under progressive-complexity discipline, E1 must be a baseline (see "Progressive-complexity discipline" section above). The bank's role at E1 is mainly to **confirm** your chosen baseline is appropriate and to flag any baseline-level pitfalls (e.g. "central FD has Gibbs on hyperbolic shocks"). You may NOT use the bank to pick a fully-stacked complex method as E1.
   - **For E2, E3**: the bank is for **escalation direction** — given the failure mode observed in F_{n-1}, which single-component upgrade does the bank suggest, and which upgrade direction does it warn against?
   - **MANDATORY bank consultation at proposal stage**:
     - If positive entries are available: scan them for entries whose `applicability` field matches the **specific failure mode you just observed** (or, for E1, the PDE class). List the matching ids in `cites_bank`. Briefly justify which single-component upgrade you adopt (or, for E1, which baseline choice the entry confirms).
     - If negative entries are available: scan them for entries warning against your candidate upgrade direction. List the matching ids in `rejects_bank`. State which would-be-tempting upgrade you are *not* taking and why.
     - **If both positive AND negative are available, you MUST consult both kinds and reflect both in your proposal** — positive entries suggest the next single component to add; negative entries narrow which direction to *not* upgrade toward.
     - If no entries match: that's OK, but explicitly write `cites_bank: []` and `rejects_bank: []` and note "no matching bank entry" so the trace records the gap.
   - Append to `research_state.jsonl`:
   ```json
   {"node_type": "Experiment", "id": "E<iter>", "ic": "<IC string>", "method": "<numerical scheme>", "params": {<dt, Nx, etc>}, "T": <T>, "motivated_by": "Q1 or D<prev>", "cites_bank": ["<bank_id>", ...], "rejects_bank": ["<bank_id>", ...], "bank_use_rationale": "<one sentence on how positive entries shaped method choice and how negative entries narrowed parameters>", "ts": <ts>}
   ```
2. **Write candidate.py** implementing the Experiment. You may rewrite freely before executing.
3. **Execute via Bash**: `cd /Users/AUTHOR/Negative_Knowledge/reproduction/section4/runs_insitu/rep2/T_A/NoKB && /Users/AUTHOR/Negative_Knowledge/.venv/bin/python3 candidate.py`  (timeout 120s)
4. **Inspect output**: read stdout/stderr and the produced file. Use Bash + `/Users/AUTHOR/Negative_Knowledge/.venv/bin/python3 -c "..."` for diagnostics (NaN check, peak count, mass conservation).
5. **Append Finding**: `research_state.jsonl`:
   ```json
   {"node_type": "Finding", "id": "F<iter>", "experiment": "E<iter>", "diagnostics": {<numerical observations>}, "kind": "positive | negative | partial", "useful_self_assessment": true | false, "rationale": "...", "ts": <ts>}
   ```
6. **(Optional) Append Decision** if you'll iterate or stop:
   ```json
   {"node_type": "Decision", "id": "D<iter>", "based_on": ["F<iter>"], "action": "retry | change_method | narrow_claim | abandon_route | stop_useful", "rationale": "...", "ts": <ts>}
   ```
7. **Append to session_log.md**: one line `iter <n>: <summary>`.

If Finding has `useful_self_assessment: true` AND you are confident the phenomenon target is met, you may STOP early and skip remaining iterations.

## Final wrap-up (after iter loop ends or early stop)

Write `reasoning.md` with these sections:
- **Final method**: which Experiment is your "answer"; full method description
- **Iteration trace**: 1-3 lines summarizing each E_i and F_i
- **Use of memory**: cite by id any bank entries that drove your decisions (in the format `kb-xxx`); also list bank entries you considered but rejected with reason
- **Final self-assessment**: do you believe `pred_results/T_A.npy` satisfies the phenomenon target? Cite numerical diagnostics.

Ensure `candidate.py` in working directory IS the final solver corresponding to your final answer (the last Experiment you executed, or your best Experiment if you self-rolled back).

# Task spec

## Sub-task T_A: Soliton stability in coupled Burgers-swept-KdV

Take a sech^2 soliton IC for v with u initially close to (but not exactly) v^2/2, propagate the coupled system long-time, and study whether the soliton structure survives.

## PDE — Coupled Burgers-swept-KdV system

```
u_t + 3 u u_x = -∂_x (3 v^2 + v_xx)
v_t + 6 v v_x + v_xxx = -∂_x (u v)
```

with γ = 1, ν = 1. On periodic domain x ∈ [-15, 15], Nx = 256.
Special reduction m := u - v^2/2 = 0 → Gardner equation.

## Initial condition (suggested; you MAY adjust within reason and document in Experiment node)

v(x, 0) = 2 * sech^2(x + 5)
u(x, 0) = 0.5 * v(x, 0)^2 + 0.2 * v(x, 0)
  (Note: u != v^2/2 exactly, so we are perturbed from the m=0 Gardner reduction by 0.2 v.)

## Final time

T = 8.0

## Required output

Save to: `pred_results/T_A.npy` (relative to working directory)
Output shape: shape (n_snapshots, 2, 256) where dim-1 channels are (u, v); save at least 5 snapshots evenly spaced from t=0 to t=T_final. The LAST snapshot is what eval focuses on but having time-series is useful for diagnostics.
**Include at least 5 snapshots** in the time axis so phenomenon eval can measure conservation over time.

## Phenomenon target

Final v(x, T) should still contain a single dominant peak with amplitude >= 0.5 of the initial 2.0. mass(v) should drift < 8%. Both u and v should stay bounded (|max| < 15).

There is NO closed-form reference. The parent will run a deterministic phenomenon check on your final `pred_results/T_A.npy` AFTER the session ends.

# Working directory and tools

Working directory: `/Users/AUTHOR/Negative_Knowledge/reproduction/section4/runs_insitu/rep2/T_A/NoKB`
- `pred_results/` already exists; write your output there
- Knowledge bank files (if applicable):
  - Positive entries: `(none)`
  - Negative entries: `(none)`
- Python interpreter for execution: `/Users/AUTHOR/Negative_Knowledge/.venv/bin/python3`

Tools allowed:
- **Read** (any file, including the bank files)
- **Write** (any file inside the working directory)
- **Bash** (for executing candidate.py and quick numpy diagnostics)

Tools NOT allowed:
- Edit (use Write for full rewrites)
- Grep / Glob (the working directory is small; use ls via Bash if needed)
- Network access, package installs, modifications outside working directory

# Memory (condition-dependent — embedded for convenience; the bank files are also on disk)

## Memory: no knowledge bank.

You have no prior knowledge bank for this problem family. Use your general knowledge of PDE numerical methods.
