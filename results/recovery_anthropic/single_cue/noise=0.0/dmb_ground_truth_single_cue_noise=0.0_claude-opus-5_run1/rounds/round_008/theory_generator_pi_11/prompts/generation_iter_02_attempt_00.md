# generation_iter_02_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a new theory and its model instantiation in the Decision Making (Binary Features) domain based on the feedback provided by an arbiter. The feedback contains diagnoses of mechanistic failures of the previous theory along with suggestions for a new theory family that overcomes those failures. The newly proposed theory and model should display human-like behavior when simulated on experiment(s). 
The goal of the theory generation process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across the majority of experiments. 
You will see a list of theories that have been proposed in the past but you should only use them as inspiration and not to choose from them. Propose a new theory that is different. 
If they fail to do so, you will receive feedback on their performance on the same experiment(s) and you will have to propose another new theory and model that meet the requirements, iterating until you succeed.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new theory and model that ignore the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

## ACCEPT GATE & LOSS TRAJECTORY — HOW THE LOOP HANDLES YOUR EDITS
This propose-loop has a programmatic accept gate: after every iteration the candidate's `aggregate_loss` is compared against the running-best loss; strict improvement -> ACCEPTED (the candidate becomes the new running-best base); otherwise -> REJECTED (the candidate is discarded and the base is unchanged). You do NOT need to manually "revert" a regressed edit — the gate already does that for you.

The block rendered below as `## PREVIOUS CANDIDATE (this loop)` is ALWAYS the running-best (last ACCEPTED) candidate, NEVER your most recent attempt if it was rejected. So:
  * Treat `## PREVIOUS CANDIDATE` as a known-good base. Build on it.
  * The `## LOSS TRAJECTORY` block tags every iteration ACCEPTED or REJECTED. Use this as ground truth on which past critic advice actually moved the loop forward and which didn't.
  * The `## PRIOR FEEDBACK ITERATIONS` block annotates each prior critique with the same ACCEPTED/REJECTED tag of the candidate it elicited. Down-weight critic advice whose previous candidates were REJECTED, and reinforce / extend advice whose candidates were ACCEPTED.
  * Treat the best ACCEPTED iteration's loss as a soft floor — the next edit should plausibly land at-or-below it, otherwise the gate will reject your attempt and the base stays put.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

## PARAMETER NOTATION
`parameters` is a JSON object mapping each parameter name (snake_case string) to a *string* value that specifies its domain. Every value MUST be a string — never a bare list, number, tuple, or expression. Use exactly one of these notations per parameter:

1. Continuous interval — square brackets, two numeric bounds:
   "[min, max]"
   Examples: "[0, 1]", "[1.0, 10.0]", "[10, 1000]"

2. Discrete set — curly braces, comma-separated values:
   "{v1, v2, ...}"
   Example: "{1, 2}"

3. Vector of intervals whose length is set by the experiment — a bracketed tuple repeated by a symbolic length variable:
   "[(min, max)] * length_var"
   Example: "[(0, 1)] * n_features"

4. Symbolic reference — a bare variable name (no brackets, no angle brackets), used when the parameter takes its value from an experiment-defined constant rather than a range:
   "variable_name"
   Example: "n_features"

Rules:
- Do not use parentheses for intervals; square brackets only. Tuples `(a, b)` are reserved for the vector-of-intervals notation in (3).
- Do not mix notations within a single value (e.g., no "[0, 1] or {2, 3}").
- Do not quote numbers inside the notation (write "[0, 1]", not "['0', '1']").
- Every parameter referenced by `predict` or `policy` must appear as a key in `parameters`, and vice versa.
- Notations 3 and 4 may ONLY reference the experiment-defined symbolic identifiers listed under "ALLOWED SYMBOLIC IDENTIFIERS" below. Do not invent new identifier names. If a parameter's shape doesn't fit any of those variables, fall back to a literal interval (notation 1) or discrete set (notation 2). Use these names so the model adapts to any experiment in this domain instead of hardcoding shapes.

## ALLOWED SYMBOLIC IDENTIFIERS (for notations 3 and 4 above)
- n_features: Number of expert ratings per option (LLM-proposed via `validities` length).
- validities: Per-expert validities (LLM-proposed; each in [0.5, 1.0]); fixed across all trials.

## AVAILABLE IMPORTS inside `predict` and `policy`
- numpy as np
- pandas as pd
- scipy and its submodules
- torch and torch.nn.functional as F
- sklearn and its submodules
- math, random, and other standard Python libraries

## RUNTIME CONTRACT (function signatures and argument shapes)
`predict(parameters, state, history) -> np.ndarray`:
- `parameters`: dict[str, value]. One sample drawn from your declared `parameters` ranges, applied for the entire subject run.
- `state`: the per-trial input delivered by the experiment (shape is domain-specific — see the experiment description above and the `history` key list below, which mirrors the per-trial variables carried in `state`). Convert to an array with `np.asarray(state)` if you need array ops.
- `history`: dict-of-lists for past trials in this subject's run, NOT a list-of-dicts. The per-trial keys are:
  Each value below is a Python list in trial order; entry `i` is the value for trial `i`. On the first trial all lists are empty.
  - `"option_a_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
  - `"option_b_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
  - `"response"`: 0 if subject chose A, 1 if subject chose B.
Iterating `for x in history:` iterates the dict KEYS (strings); to walk trials index the lists in lock-step, e.g. `for i in range(len(next(iter(history.values())))): ...`.
- Returns: 1-D `np.ndarray` of choice probabilities over the experiment's discrete action set, summing to 1.

`policy(probs) -> int`:
- Receives the probability vector produced by `predict`.
- Returns: integer index in `[0, len(probs))` identifying the chosen action. If you sample with `np.random.choice(..., p=probs)`, normalise first (`probs = np.asarray(probs, dtype=np.float64); probs /= probs.sum()`) to avoid the "probabilities do not sum to 1" ValueError from float drift.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_7`
- THEORY 2 = `pi_10`
- The recommendation below acts on THEORY 1 (= `pi_7`).

Replace pi_7 (MDSC-NV) entirely. Its two signature claims are falsified: (a) 'coalitions buy nothing / near-argmax relative doubt' is refuted by Exps 1 (.49), 15 (.55), 16 (.47) and by Exp 2's C-term; (b) the raw display-length lapse rho^(m-2) is refuted by the flat, high anchor-follow rates on long displays (Exp 2 T-term, Exps 17/18).

Propose instead a RELATIVE-SHARE GATING theory — call it SSG (Salience-Share Gating) — that is a strong competitor to pi_10 rather than a weak one:

1. Row salience over DISCRIMINATING rows only: s_j = (1-v_j)^gamma * exp(lam*j), gamma ~ 1.5-2.5, lam ~ 0.1-0.5 (weak recency; large lam only needed in the near-tied-validity designs of Exps 10/11).
2. GRADED MODE GATE driven by the salience SHARE of the top row, not an absolute validity threshold: pi_one = sigmoid((s_max/sum_j s_j - c)/w), with c ~ 0.55-0.75, w ~ 0.05-0.15. Intuition: a subject abandons integration only when one dissent is *conspicuously odder than everything else on the screen*. This reproduces pi_10's key successes — a .52 expert among .64-.96 experts has share ~.6-.8 -> one-reason, high and flat in coalition size (Exps 2-T, 17, 18); a .66/.68 expert among .64/.70/.72 experts has share ~.3-.4 -> compensatory, hence at/below chance against a coalition (Exps 1, 15, 16) — but WITHOUT the implausible knife edge, and it makes a distinct, testable prediction pi_10 cannot make: a .68 dissenter standing alone against a single .96 row should still be followed (its share is high), whereas pi_10 says compensatory there. It should also shrink the Exp-4 swing (least-valid .55 sits next to .60, so share is low, mode is mostly compensatory) which is pi_10's clearest quantitative miss.
3. One-reason limb: follow the top-salience row with fidelity (1-eps_t) degraded only by the size of the opposing coalition (rho_opp^(k_conf-1)), NOT by display length — matching the observed flatness.
4. Compensatory limb: divisively normalised anti-validity sum E = sum(sign_j * s_j)/(sigma + sum s_j), p = sigmoid(beta*E), with a mild conflict (not length) cost; calibrate so unanimous 5-6 row displays land near .74 (Exp 7) rather than at ceiling.
5. Keep the label-degeneracy/tally fallback only for exact repeats (tolerance .002) so the .004/.005-gap designs (Exps 10, 11) still run the salience rule with strong recency.

Target quantitative anchors for the new model: Exp 1 ~.49, Exp 2 (T-C) ~.32, Exp 15 ~.55, Exp 16 ~.47, Exp 17 ~.86, Exp 18 ~.83, Exp 7 ~.74, Exp 4 ~.17, Exp 13 ~.59, Exps 3/5/6/12/14 in the .15-.42 anti-validity range.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_10` (overall score: 0.936)

**Description**
DTG-2R/OC-sharp (load-graded compensatory limb) — Doubt-Threshold-Gated one-reason choice with compensatory fallback, where the doubt gate is an ABSOLUTE and SHARP near-chance criterion, the one-reason limb is degraded by OPPOSITION rather than by raw display length, and the compensatory limb is degraded by DISPLAY LOAD more steeply than previously assumed. (1) One-reason adjudication is commanded only by an expert whose PRINTED validity is essentially a coin flip. The trigger is g_j = sigmoid((theta - v_j)/tau) evaluated only over rows that actually discriminate (P_trig = max_{j in disc} g_j), with theta ~ .558-.588 and tau ~ .006-.013. An expert at .52-.55 is 'newsworthy' (g >= .9) while an expert at .62-.68 is NOT (g <= .02): a merely mediocre expert is ordinary evidence, not a scandal demanding adjudication. Silent near-chance experts are irrelevant, so no null-verdict capture and no doubt-gradient leak are needed. (2) When a genuinely sub-threshold expert speaks, its verdict decides the trial essentially independently of how MANY higher-validity rows oppose it; among discriminating rows the consulted verdict is drawn from softmax(log g_j + mu*j), so the recency tilt mu only arbitrates BETWEEN near-chance rows. (3) Because a single row is consulted, merely scanning extra rows costs the one-reason limb almost nothing (rho_t ~ .985-1.0), but holding a genuine RIVAL COALITION does cost it: each minority row beyond the first charges rho_tc (~.62-.86). Hence a near-chance dissenter standing ALONE against 1-5 opposing rows is followed at ~.82-.86 flat in coalition size (Exps 15, 16), whereas BALANCED splits drift toward chance. (4) When no near-chance expert discriminates — including displays whose least valid dissenter is only mid-doubt (v ~ .58-.68) — evidence is compensatory: anti-validity, weakly recency-tilted weights w_j = (1-v_j)^gamma * exp(lam*j), divisively normalised to the loudest dissent, E = sum(s_j*what_j)/(sigma + sum(what_j)), p = sigmoid(beta*E). NEW, SHARPENED CLAIM: the compensatory rule is a genuinely effortful integration whose thread is lost quickly as the display lengthens — every discriminating row beyond the second multiplies the retained evidence by rho_m ~ .84-.93, appreciably steeper than the one-reason limb's near-free scan. This asymmetry is the theory's signature: one-reason choice is cheap to run on long displays and expensive only under opposition, whereas compensatory integration is expensive in sheer list length. Consequently long unanimous displays stay confident but clearly below ceiling (~.74-.76), and long conflict displays settle appreciably closer to chance than short ones, while short displays (m=2-3) are essentially unaffected. (5) If any two printed validities are within .002 the experts cannot be individuated, the doubt gate has no referent, and choice collapses to a graded unweighted row tally (exact coin flip on 1-1 splits). No feedback is given, so the rule is stationary across the block.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # DTG-2R/OC: Doubt-Threshold-Gated one-reason choice with compensatory fallback;
    # one-reason limb degraded by OPPOSITION (rho_tc) rather than by raw row count,
    # compensatory limb degraded by DISPLAY LOAD (rho_m)
    import numpy as np

    # ---------- parse the (2, n_features) stimulus robustly ----------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()
            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()
        else:
            vals = list(state.values())
            if len(vals) >= 2:
                a = np.asarray(vals[0], dtype=float).ravel()
                b = np.asarray(vals[1], dtype=float).ravel()
    if a is None or b is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 2 and arr.shape[0] == 2:
            a, b = arr[0].ravel(), arr[1].ravel()
        elif arr.ndim == 2 and arr.shape[1] == 2:
            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()
        elif arr.ndim == 1:
            h = arr.shape[0] // 2
            a, b = arr[:h], arr[h:2 * h]
        else:
            f = np.asarray(arr, dtype=float).reshape(2, -1)
            a, b = f[0].ravel(), f[1].ravel()

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float)[:n]
    b = np.asarray(b, dtype=float)[:n]

    # ---------- printed validities ----------
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is None:
        v = np.linspace(0.95, 0.55, n)
    else:
        v = np.asarray(v_raw, dtype=float).ravel()
        if v.size < n:
            v = np.concatenate([v, np.full(n - v.size, 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5, 0.9995)

    # ---------- parameters ----------
    theta = float(parameters['theta'])
    tau = float(max(float(parameters['tau']), 1e-4))
    mu = float(parameters['mu'])
    gamma = float(parameters['gamma'])
    lam = float(parameters['lam'])
    sigma = float(max(float(parameters['sigma']), 1e-6))
    beta = float(parameters['beta'])
    eps_t = float(np.clip(float(parameters['eps_t']), 0.0, 1.0))
    rho_t = float(np.clip(float(parameters['rho_t']), 1e-6, 1.0))
    rho_tc = float(np.clip(float(parameters['rho_tc']), 1e-6, 1.0))
    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))
    rho_m = float(np.clip(float(parameters['rho_m']), 1e-6, 1.0))
    rho_c = float(np.clip(float(parameters['rho_c']), 1e-6, 1.0))
    kappa = float(parameters['tally_kappa'])

    def sig(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # ---------- discriminating rows ----------
    diff = a - b
    disc = np.nonzero(diff != 0.0)[0]
    m = int(disc.size)
    if m == 0:
        return np.array([0.5, 0.5])
    signs = np.sign(diff[disc])
    n_a = float(np.sum(signs > 0.0))
    n_b = float(m) - n_a
    k_conf = int(min(n_a, n_b))

    # ---------- lapses ----------
    expo = max(m - 2, 0)
    keep_c = (1.0 - eps0) * (rho_m ** expo) * (rho_c ** k_conf)
    keep_c = float(min(max(keep_c, 0.0), 1.0))
    # one-reason limb: scanning extra rows is nearly free, holding a RIVAL
    # coalition is not -> charge rho_tc per minority row beyond the first
    keep_t = (1.0 - eps_t) * (rho_t ** expo) * (rho_tc ** max(k_conf - 1, 0))
    keep_t = float(min(max(keep_t, 0.0), 1.0))

    # ---------- label-degeneracy gate ----------
    degenerate = False
    if n > 1:
        vs = np.sort(v)
        if bool(np.any(np.diff(vs) < 2.0e-3)):
            degenerate = True

    if degenerate:
        p_core = sig(kappa * (n_a - n_b))
        p_a = 0.5 + keep_c * (p_core - 0.5)
        p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
        p = np.array([p_a, 1.0 - p_a], dtype=float)
        return p / p.sum()

    # ---------- absolute doubt trigger over DISCRIMINATING rows ----------
    zz = np.clip((v - theta) / tau, -60.0, 60.0)
    gtrig = 1.0 / (1.0 + np.exp(zz))          # = sigmoid((theta - v)/tau)
    gd = gtrig[disc]
    P_trig = float(np.clip(np.max(gd), 0.0, 1.0))

    # verdict of the consulted (near-chance) expert; recency tilt among them
    logs = np.log(np.clip(gd, 1e-300, None)) + mu * disc.astype(float)
    logs = logs - np.max(logs)
    s = np.exp(np.clip(logs, -700.0, 0.0))
    ssum = float(np.sum(s))
    if (not np.isfinite(ssum)) or ssum <= 0.0:
        s = np.full(m, 1.0 / m)
    else:
        s = s / ssum
    p_or_a = float(np.sum(s[signs > 0.0]))
    p_t = 0.5 + keep_t * (p_or_a - 0.5)

    # ---------- compensatory fallback (divisively normalised anti-validity) ----------
    logw = gamma * np.log(np.clip(1.0 - v, 1e-12, None)) + lam * np.arange(n, dtype=float)
    ld = logw[disc]
    ld = ld - np.max(ld)
    w = np.exp(np.clip(ld, -700.0, 0.0))
    wsum = float(np.sum(w))
    if (not np.isfinite(wsum)) or wsum <= 0.0:
        w = np.ones(m, dtype=float)
        wsum = float(m)
    E = float(np.sum(signs * w)) / (sigma + wsum)
    p_comp = sig(beta * E)
    p_c = 0.5 + keep_c * (p_comp - 0.5)

    # ---------- doubt-threshold-gated mixture ----------
    p_a = P_trig * p_t + (1.0 - P_trig) * p_c
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
    p = np.array([p_a, 1.0 - p_a], dtype=float)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0.0:
        return int(np.random.randint(len(probs)))
    probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- theta: [0.558, 0.588]
- tau: [0.006, 0.013]
- mu: [0.45, 0.95]
- gamma: [1.5, 2.3]
- lam: [0.0, 0.22]
- sigma: [0.40, 0.72]
- beta: [1.8, 2.6]
- eps_t: [0.20, 0.36]
- rho_t: [0.985, 1.00]
- rho_tc: [0.62, 0.86]
- eps0: [0.13, 0.27]
- rho_m: [0.84, 0.93]
- rho_c: [0.74, 0.90]
- tally_kappa: [0.6, 1.3]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2820 (var=0.0035) vs this=0.2522 (var=0.0026)
- Experiment 2: real=0.1744 (var=0.0127) vs this=0.3175 (var=0.0088)
- Experiment 3: real=0.2856 (var=0.0160) vs this=0.2650 (var=0.0064)
- Experiment 4: real=0.1500 (var=0.0194) vs this=0.1600 (var=0.0080)
- Experiment 5: real=0.7427 (var=0.0173) vs this=0.7707 (var=0.0058)
- Experiment 6: real=0.5067 (var=0.0112) vs this=0.5017 (var=0.0113)
- Experiment 7: real=0.4383 (var=0.0023) vs this=0.4500 (var=0.0038)
- Experiment 8: real=0.7697 (var=0.0057) vs this=0.7960 (var=0.0025)
- Experiment 9: real=0.8189 (var=0.0074) vs this=0.7953 (var=0.0023)
- Experiment 10: real=0.4178 (var=0.0051) vs this=0.4236 (var=0.0018)
- Experiment 11: real=0.5925 (var=0.0026) vs this=0.5946 (var=0.0036)
- Experiment 12: real=0.2608 (var=0.0079) vs this=0.2013 (var=0.0047)
- Experiment 13: real=0.5460 (var=0.0126) vs this=0.5080 (var=0.0118)
- Experiment 14: real=0.4675 (var=0.0144) vs this=0.5413 (var=0.0121)
- Experiment 15: real=0.8620 (var=0.0155) vs this=0.8087 (var=0.0029)
- Experiment 16: real=0.8260 (var=0.0180) vs this=0.8075 (var=0.0040)
- Experiment 17: real=0.4925 (var=0.0074) vs this=0.4906 (var=0.0058)
- Experiment 18: real=0.3183 (var=0.0405) vs this=0.3550 (var=0.0214)


---

### `pi_7` (overall score: 0.743)

**Description**
**MDSC-NV (sharpened) — Maximum-Doubt Single-Cue selection with Null-Verdict capture.**

Four claims; the mechanism family is unchanged from the accepted base, but one quantitative commitment is sharpened.

**(1) One-reason choice by MAXIMUM DOUBT (no summation).** On each trial the subject settles A-vs-B with the verdict of a SINGLE expert. Which expert is consulted is decided by *doubt*: a disagreement voiced by a near-chance expert (v≈.53) is a strange, newsworthy fact that has to be adjudicated, whereas a disagreement voiced by a near-certain expert (v≈.97) is discounted as a mere echo of the impression the subject already has. Salience is log u_j = delta*log(1-v_j) + lam*j and the consulted row is drawn from softmax(u). **The doubt gain is LARGER than previously assumed (delta ≈ 13-17, not 8-12): the doubt rule is essentially argmax, not a graded share.** This is the sharpened commitment. It matters wherever two moderately-doubtful rows are within ~0.4 log-validity of one another (e.g. v=.55 vs v=.70 rows two columns apart): a share-based rule lets the second-most-doubtful row steal ~18% of the verdict and blunts the choice, whereas the near-argmax rule leaves the display fully decided by the single most doubtful row. Coalitions still buy nothing: five agreeing rows never outvote one more-doubtful row, which is why choice is systematically anti-validity in every design where the printed labels are usable.

**(2) Reading position is a WEAK tie-breaker.** lam = pos_ratio*delta with pos_ratio ≈ 0.09-0.14 — an order of magnitude below the doubt term's dynamic range. Position therefore only arbitrates between rows whose stated validities are (nearly) *equal* — exactly the .955/.950/.945 and .958/.954/.950 designs, where it makes the last low-validity row win. Whenever validities genuinely differ, doubt beats recency: a low-validity EARLY column defeats a late .93/.99 column. Because delta is raised and pos_ratio held fixed, the *ratio* of doubt-range to positional gain is preserved, so all orderings in the corpus are unchanged.

**(3) NULL-VERDICT CAPTURE.** Doubt is a property of the *expert*, not of the disagreement, so attention is captured pre-attentively by the most doubtful expert **in the whole display**, before the subject checks whether that expert actually discriminates. With probability q (≈ .41, slightly higher than previously estimated) the subject simply goes with whoever captured attention; if that expert gave both products the same rating it returns no verdict, the subject has nothing to adjudicate and guesses. With probability 1-q the subject re-targets deliberately, restricting the doubt competition to the rows that differ. Sharp prediction: *holding the discriminating rows fixed, adding agreement on a MORE doubtful (lower-validity) row pushes choice toward chance*, whereas adding agreement on a high-validity row does nothing. Displays in which only two high/mid-validity rows disagree while the display's most doubtful expert stays silent are therefore near chance — no compensatory or one-reason model predicts that non-discriminating rows matter at all.

**(4) LABEL-DEGENERACY GATE (all-or-none) and LOAD LAPSE.** The doubt rule presupposes that each printed validity picks out one expert. If any label is printed twice (tolerance .002 — it must NOT fire for the .004/.005-gap designs) the experts are interchangeable, the doubt ordering is unavailable, and choice collapses to a graded unweighted row tally (exact coin flip on 1-1 splits). Independently, the more rows disagree the more often the subject loses the thread: p(guess) = 1-(1-eps0)*rho^(m-2), which compresses conflict displays toward chance and keeps even unanimous 6-row displays well below ceiling. Individual subjects differ mainly in how leaky (eps0, rho) and how capture-prone (q) they are, not in the doubt rule itself.

No feedback is given, so the rule is stationary across the block.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # MDSC-NV: Maximum-Doubt Single-Cue selection with Null-Verdict capture
    import numpy as np

    # ---------- parse the (2, n_features) stimulus robustly ----------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()
            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()
        else:
            vals = list(state.values())
            if len(vals) >= 2:
                a = np.asarray(vals[0], dtype=float).ravel()
                b = np.asarray(vals[1], dtype=float).ravel()
    if a is None or b is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 2 and arr.shape[0] == 2:
            a, b = arr[0].ravel(), arr[1].ravel()
        elif arr.ndim == 2 and arr.shape[1] == 2:
            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()
        elif arr.ndim == 1:
            h = arr.shape[0] // 2
            a, b = arr[:h], arr[h:2 * h]
        else:
            f = np.asarray(arr, dtype=float).reshape(2, -1)
            a, b = f[0].ravel(), f[1].ravel()

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float)[:n]
    b = np.asarray(b, dtype=float)[:n]

    # ---------- communicated validities (the printed labels) ----------
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is None:
        v = np.linspace(0.95, 0.55, n)
    else:
        v = np.asarray(v_raw, dtype=float).ravel()
        if v.size < n:
            v = np.concatenate([v, np.full(n - v.size, 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5, 0.9975)

    # ---------- parameters ----------
    delta = float(parameters['doubt_gain'])
    lam = float(parameters['pos_ratio']) * delta        # weak positional gain
    q = float(np.clip(float(parameters['capture']), 0.0, 1.0))
    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))
    rho = float(np.clip(float(parameters['rho']), 1e-6, 1.0))
    kap = float(parameters['tally_kappa'])

    # ---------- discriminating rows ----------
    diff = a - b
    disc = np.nonzero(diff != 0.0)[0]
    m = int(disc.size)
    if m == 0:
        return np.array([0.5, 0.5])
    fav_a = diff[disc] > 0.0
    n_a = float(np.sum(fav_a))
    n_b = float(m) - n_a

    # ---------- label-degeneracy gate (all-or-none, exact repetition) ----------
    degenerate = False
    if n > 1:
        vs = np.sort(v)
        if bool(np.any(np.diff(vs) < 2.0e-3)):
            degenerate = True

    if degenerate:
        # experts cannot be individuated -> unweighted graded row tally
        z = float(np.clip(kap * (n_a - n_b), -60.0, 60.0))
        p_core_a = 1.0 / (1.0 + np.exp(-z))
    else:
        # doubt salience over ALL rows
        logu = delta * np.log(np.clip(1.0 - v, 1e-12, None)) + lam * np.arange(n, dtype=float)

        lg = logu - np.max(logu)
        s = np.exp(lg)
        ssum = float(np.sum(s))
        s = s / ssum if (np.isfinite(ssum) and ssum > 0.0) else np.full(n, 1.0 / n)

        ld = logu[disc]
        ld = ld - np.max(ld)
        t = np.exp(ld)
        tsum = float(np.sum(t))
        t = t / tsum if (np.isfinite(tsum) and tsum > 0.0) else np.full(m, 1.0 / m)

        # (i) deliberate re-targeting: doubt competition among disagreeing rows
        p_rest_a = float(np.sum(t[fav_a]))

        # (ii) null-verdict capture: attention grabbed by the most doubtful
        #      expert in the whole display; if it is silent -> guess
        mask = np.zeros(n, dtype=bool)
        mask[disc] = True
        s_nondisc = float(np.sum(s[~mask]))
        s_disc = s[disc]
        p_glob_a = float(np.sum(s_disc[fav_a])) + 0.5 * s_nondisc

        p_core_a = q * p_glob_a + (1.0 - q) * p_rest_a

    # ---------- load-dependent lapse ----------
    expo = max(m - 2, 0)
    g = 1.0 - (1.0 - eps0) * (rho ** expo)
    g = float(min(max(g, 0.0), 1.0))

    p_a = 0.5 * g + (1.0 - g) * p_core_a
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0.0:
        return int(np.random.randint(len(probs)))
    probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- doubt_gain: [13.0, 17.0]
- pos_ratio: [0.09, 0.14]
- capture: [0.33, 0.49]
- eps0: [0.19, 0.29]
- rho: [0.77, 0.85]
- tally_kappa: [1.00, 1.40]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2820 (var=0.0035) vs this=0.2878 (var=0.0023)
- Experiment 2: real=0.1744 (var=0.0127) vs this=0.2300 (var=0.0149)
- Experiment 3: real=0.2856 (var=0.0160) vs this=0.2778 (var=0.0058)
- Experiment 4: real=0.1500 (var=0.0194) vs this=0.1500 (var=0.0133)
- Experiment 5: real=0.7427 (var=0.0173) vs this=0.7467 (var=0.0048)
- Experiment 6: real=0.5067 (var=0.0112) vs this=0.4817 (var=0.0130)
- Experiment 7: real=0.4383 (var=0.0023) vs this=0.4508 (var=0.0038)
- Experiment 8: real=0.7697 (var=0.0057) vs this=0.7686 (var=0.0034)
- Experiment 9: real=0.8189 (var=0.0074) vs this=0.7714 (var=0.0022)
- Experiment 10: real=0.4178 (var=0.0051) vs this=0.3878 (var=0.0029)
- Experiment 11: real=0.5925 (var=0.0026) vs this=0.6833 (var=0.0038)
- Experiment 12: real=0.2608 (var=0.0079) vs this=0.2592 (var=0.0042)
- Experiment 13: real=0.5460 (var=0.0126) vs this=0.6410 (var=0.0093)
- Experiment 14: real=0.4675 (var=0.0144) vs this=0.6388 (var=0.0149)
- Experiment 15: real=0.8620 (var=0.0155) vs this=0.7610 (var=0.0035)
- Experiment 16: real=0.8260 (var=0.0180) vs this=0.7245 (var=0.0054)
- Experiment 17: real=0.4925 (var=0.0074) vs this=0.6956 (var=0.0072)
- Experiment 18: real=0.3183 (var=0.0405) vs this=0.0125 (var=0.0220)


---

### `pi_8` (overall score: 0.734)

**Description**
**DTV-RG/CL — Doubt-Triggered one-reason with Rank-Geometric weighting, under a two-component (load + conflict) leak and a DECISIVE degenerate-label tally.**

The evidence rule is unchanged from the accepted base; two claims about *how the rule degrades* are sharpened.

**(1) Rank-geometric evidence, decided from the LEAST valid dissenting expert.** On each trial the subject lines the *discriminating* rows up in order of printed validity, least valid first, and sums their verdicts with a geometric discount: E = Σ_r s_r · φ^r (r = 0 for the least valid discriminating expert, s_r = ±1 its verdict); p(A) = σ(βE). Only the ORDER of the printed labels enters, never the size of the gaps, which is why the .955/.950/.945 and .958/.954/.950 families are still resolved almost deterministically in favour of the strictly least valid dissenter, and why coalitions of more valid experts normally buy nothing (though a large enough coalition can still overturn one doubtful voice).

**(2) The discount rate is set by the ABSOLUTE doubtfulness of the decisive voice.** One-reason choice is a *reaction to a near-chance expert*: φ = φ_lo + (φ_hi − φ_lo)·σ((v₀ − v_c)/w), with v₀ the validity of the least valid DISCRIMINATING expert, φ_lo ≈ .25 (take-the-least), φ_hi ≈ .88 (near tally), v_c ≈ .575, w ≈ .015. Below the trigger the display is settled by one strange dissent; above it nothing is newsworthy and the rows are weighted nearly equally.

**(3) No null-verdict capture.** Non-discriminating rows are strictly irrelevant whatever their validity; all pull toward chance comes from the leak in (4).

**(4) NEW — the leak has TWO separable sources, and dominance displays leak only through the first.** Losing the thread is driven (i) by sheer display load — how many rows have to be held while the ordering is run — and (ii) independently by *opposition*: every additional row that argues the other way adds a fresh occasion to lose track of which side one was on. p(guess) = 1 − (1−ε₀)·ρ_m^max(m−2,0)·ρ_c^min(n_A,n_B), with ρ_m ≈ .79 (load) and ρ_c ≈ .97 (opposition). The two terms are close to orthogonal in the corpus: unanimous (dominance) displays have min(n_A,n_B)=0 and therefore leak only by load, so they stay well above the balanced-conflict displays of the same size, whereas a 3-vs-3 display of six rows is markedly noisier than a 6-vs-0 display of six rows. This is a direct, testable clash both with a pure-load leak (which charges a 6-0 display exactly what it charges a 3-3 display) and with a pure-opposition leak (which would make unanimous displays near-perfect).

**(5) NEW — when labels are degenerate the fallback tally is DECISIVE, not tepid.** The doubt ordering presupposes that each printed validity picks out one expert. If any label is repeated (gap < .002) the columns are interchangeable and choice collapses to an unweighted row tally — but that tally is used with a steep slope (κ ≈ 1.6, not ≈ 0.85): having nothing else to go on, the subject commits hard to the vote margin. Hence 1-vs-1 splits under duplicated labels are an exact coin flip (no anti-validity, no recency), while 2-vs-0 and 4-vs-0 splits under duplicated labels are chosen at ~.83 and ~.95 before the leak — which is what keeps unanimous displays high and what makes a 2-vs-1 display under duplicated labels clearly favour the majority rather than hovering near chance.

No feedback is given, so the rule is stationary across the block.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # DTV-RG/CL: Doubt-Triggered one-reason with Rank-Geometric weighting,
    # two-component (load + conflict) leak, decisive degenerate-label tally
    import numpy as np

    # ---------- parse the (2, n_features) stimulus robustly ----------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()
            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()
        else:
            vals = list(state.values())
            if len(vals) >= 2:
                a = np.asarray(vals[0], dtype=float).ravel()
                b = np.asarray(vals[1], dtype=float).ravel()
    if a is None or b is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 2 and arr.shape[0] == 2:
            a, b = arr[0].ravel(), arr[1].ravel()
        elif arr.ndim == 2 and arr.shape[1] == 2:
            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()
        elif arr.ndim == 1:
            h = arr.shape[0] // 2
            a, b = arr[:h], arr[h:2 * h]
        else:
            f = np.asarray(arr, dtype=float).reshape(2, -1)
            a, b = f[0].ravel(), f[1].ravel()

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float)[:n]
    b = np.asarray(b, dtype=float)[:n]

    # ---------- communicated validities (the printed labels) ----------
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is None:
        v = np.linspace(0.95, 0.55, n)
    else:
        v = np.asarray(v_raw, dtype=float).ravel()
        if v.size < n:
            v = np.concatenate([v, np.full(n - v.size, 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5, 0.9995)

    # ---------- parameters ----------
    phi_lo = float(np.clip(float(parameters['phi_lo']), 1e-3, 0.999))
    phi_hi = float(np.clip(float(parameters['phi_hi']), 1e-3, 0.999))
    v_crit = float(parameters['v_crit'])
    v_width = float(max(float(parameters['v_width']), 1e-4))
    beta = float(parameters['beta'])
    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))
    rho_m = float(np.clip(float(parameters['rho_m']), 1e-6, 1.0))
    rho_c = float(np.clip(float(parameters['rho_c']), 1e-6, 1.0))
    kappa = float(parameters['tally_kappa'])

    def sig(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # ---------- discriminating rows ----------
    diff = a - b
    disc = np.nonzero(diff != 0.0)[0]
    m = int(disc.size)
    if m == 0:
        return np.array([0.5, 0.5])
    signs = np.sign(diff[disc])
    n_a = float(np.sum(signs > 0.0))
    n_b = float(m) - n_a

    # ---------- label-degeneracy gate (repeated printed labels) ----------
    degenerate = False
    if n > 1:
        vs = np.sort(v)
        if bool(np.any(np.diff(vs) < 2.0e-3)):
            degenerate = True

    if degenerate:
        # experts cannot be individuated -> decisive unweighted row tally
        p_core_a = sig(kappa * (n_a - n_b))
    else:
        # order discriminating rows by printed validity (ascending);
        # ties broken by reading position (later read = more decisive)
        order = np.lexsort((-disc.astype(float), v[disc]))
        idx_sorted = disc[order]
        s_sorted = signs[order]

        v0 = float(v[idx_sorted[0]])
        # doubt trigger: only a near-chance dissenter buys one-reason choice
        phi = phi_lo + (phi_hi - phi_lo) * sig((v0 - v_crit) / v_width)
        phi = float(np.clip(phi, 1e-4, 0.9999))

        r = np.arange(m, dtype=float)
        w = np.power(phi, r)
        E = float(np.sum(s_sorted * w))
        p_core_a = sig(beta * E)

    # ---------- two-component leak: display load x opposition ----------
    expo_m = max(m - 2, 0)
    k_conf = int(min(n_a, n_b))
    g = 1.0 - (1.0 - eps0) * (rho_m ** expo_m) * (rho_c ** k_conf)
    g = float(min(max(g, 0.0), 1.0))

    p_a = 0.5 * g + (1.0 - g) * p_core_a
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0.0:
        return int(np.random.randint(len(probs)))
    probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- phi_lo: [0.21, 0.29]
- phi_hi: [0.84, 0.92]
- v_crit: [0.570, 0.580]
- v_width: [0.013, 0.018]
- beta: [4.5, 5.5]
- eps0: [0.20, 0.28]
- rho_m: [0.76, 0.82]
- rho_c: [0.93, 1.00]
- tally_kappa: [1.30, 1.90]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.2820 (var=0.0035) vs this=0.2730 (var=0.0019)
- Experiment 2: real=0.1744 (var=0.0127) vs this=0.2117 (var=0.0142)
- Experiment 3: real=0.2856 (var=0.0160) vs this=0.2794 (var=0.0061)
- Experiment 4: real=0.1500 (var=0.0194) vs this=0.1217 (var=0.0081)
- Experiment 5: real=0.7427 (var=0.0173) vs this=0.7487 (var=0.0072)
- Experiment 6: real=0.5067 (var=0.0112) vs this=0.4725 (var=0.0109)
- Experiment 7: real=0.4383 (var=0.0023) vs this=0.4408 (var=0.0032)
- Experiment 8: real=0.7697 (var=0.0057) vs this=0.7611 (var=0.0025)
- Experiment 9: real=0.8189 (var=0.0074) vs this=0.7536 (var=0.0025)
- Experiment 10: real=0.4178 (var=0.0051) vs this=0.4492 (var=0.0019)
- Experiment 11: real=0.5925 (var=0.0026) vs this=0.6367 (var=0.0043)
- Experiment 12: real=0.2608 (var=0.0079) vs this=0.2729 (var=0.0043)
- Experiment 13: real=0.5460 (var=0.0126) vs this=0.2680 (var=0.0082)
- Experiment 14: real=0.4675 (var=0.0144) vs this=0.2313 (var=0.0086)
- Experiment 15: real=0.8620 (var=0.0155) vs this=0.7143 (var=0.0022)
- Experiment 16: real=0.8260 (var=0.0180) vs this=0.6770 (var=0.0061)
- Experiment 17: real=0.4925 (var=0.0074) vs this=0.3119 (var=0.0063)
- Experiment 18: real=0.3183 (var=0.0405) vs this=0.3800 (var=0.0208)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.0672 -> ACCEPTED
- iter 2: loss=0.0600 -> ACCEPTED
Running-best (last ACCEPTED) base: iter 2 at loss=0.0600 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """One-reason adherence on model-disagreement trials.

    For every trial we compute (a) the option favoured by the FIRST
    discriminating cue in validity order (features are listed in
    descending validity: 0.95, 0.85, 0.75, 0.65, 0.55) and (b) the option
    favoured by the unit-weight tally of feature-wise wins.  We keep only
    trials where these two disagree in direction OR where the tally is tied
    (so a counting rule must guess).  The metric is the proportion of such
    trials on which the subject picked the option favoured by the first
    discriminating cue.
    """
    hits = []
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = min(a.shape[0], b.shape[0])
        a = a[:n]
        b = b[:n]

        # first discriminating cue (features already in descending validity)
        first_winner = None
        for j in range(n):
            if a[j] > b[j]:
                first_winner = 0
                break
            if b[j] > a[j]:
                first_winner = 1
                break
        if first_winner is None:
            continue  # no cue discriminates: uninformative trial

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = None  # counting rule must guess

        if tally_winner is not None and tally_winner == first_winner:
            continue  # agreement control trial: not diagnostic

        try:
            r = int(resp)
        except (TypeError, ValueError):
            continue
        hits.append(1.0 if r == first_winner else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2820 (var=0.0035)
**Previous candidate values (this loop):**
  - iter 1: 0.2943 (var=0.0017) (Δ vs real +0.0123)
  - iter 2 (most recent): 0.2785 (var=0.0030) (Δ vs real -0.0035)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8515 (var=0.0078)
- pi_2: 0.1903 (var=0.0042)
- pi_3: 0.2870 (var=0.0019)
- pi_4: 0.2843 (var=0.0034)
- pi_5: 0.2722 (var=0.0027)
- pi_6: 0.2560 (var=0.0021)
- pi_7: 0.2878 (var=0.0023)
- pi_8: 0.2730 (var=0.0019)
- pi_9: 0.3068 (var=0.0031)
- pi_10: 0.2522 (var=0.0026)

### Experiment 2
**Design**
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.6, 0.93, 0.55, 0.87, 0.7, 0.78], dtype=float)

    def analyze(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        n = min(a.shape[0], b.shape[0])
        a = a[:n]
        b = b[:n]
        val = validities[:n] if validities.shape[0] >= n else np.arange(n, 0, -1, dtype=float)
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        margin = a_wins - b_wins
        if margin > 0:
            tally_winner = 0
        elif margin < 0:
            tally_winner = 1
        else:
            tally_winner = -1
        order = np.argsort(-val, kind='stable')
        ttb_winner = -1
        for j in order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        return margin, tally_winner, ttb_winner

    info = [analyze(r) for _, r in data.iterrows()]
    margins = np.array([x[0] for x in info], dtype=float)
    tally_w = np.array([x[1] for x in info], dtype=int)
    ttb_w = np.array([x[2] for x in info], dtype=int)
    resp = data['response'].to_numpy().astype(int)

    # Group 1: tally-tie trials where TTB is decisive (parameter-free for Tallying)
    tie_mask = (tally_w == -1) & (ttb_w >= 0)
    # Group 2: trials where tally margin is >= 2 AND TTB points the other way
    dis_mask = (np.abs(margins) >= 2) & (tally_w >= 0) & (ttb_w >= 0) & (tally_w != ttb_w)

    if tie_mask.sum() == 0 and dis_mask.sum() == 0:
        return float('nan')

    if dis_mask.sum() > 0:
        p_tally = float(np.mean(resp[dis_mask] == tally_w[dis_mask]))
    else:
        p_tally = 0.5
    if tie_mask.sum() > 0:
        p_ttb_tie = float(np.mean(resp[tie_mask] == ttb_w[tie_mask]))
    else:
        p_ttb_tie = 0.5

    return p_tally - p_ttb_tie

```

**Observed (real) value:** 0.1744 (var=0.0127)
**Previous candidate values (this loop):**
  - iter 1: 0.1822 (var=0.0079) (Δ vs real +0.0078)
  - iter 2 (most recent): 0.2031 (var=0.0098) (Δ vs real +0.0286)
**Other theories' values on this metric (for reference):**
- pi_2: 0.3828 (var=0.0220)
- pi_1: -0.7044 (var=0.0395)
- pi_3: 0.1722 (var=0.0132)
- pi_4: 0.1856 (var=0.0146)
- pi_5: 0.1956 (var=0.0184)
- pi_6: 0.1639 (var=0.0160)
- pi_7: 0.2300 (var=0.0149)
- pi_8: 0.2117 (var=0.0142)
- pi_9: 0.3256 (var=0.0184)
- pi_10: 0.3175 (var=0.0088)

### Experiment 3
**Design**
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 1, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V = np.array([0.68, 0.96, 0.52, 0.88, 0.58, 0.78], dtype=float)

    hits = 0.0
    n = 0.0
    for _, row in data.iterrows():
        try:
            a = np.asarray([float(x) for x in row['option_a_ratings']], dtype=float)
            b = np.asarray([float(x) for x in row['option_b_ratings']], dtype=float)
        except Exception:
            continue
        k = int(min(a.shape[0], b.shape[0]))
        if k == 0:
            continue
        a = a[:k]
        b = b[:k]
        if V.shape[0] >= k:
            v = V[:k]
        else:
            v = np.concatenate([V, np.full(k - V.shape[0], 0.55)])[:k]

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        # keep only unit-tally TIES with at least one discriminating cue
        if a_wins != b_wins or a_wins == 0:
            continue

        w = v ** 2.0
        d = float(np.sum(w * (a - b)))
        # discard tie trials whose validity-weighted margin is itself
        # near zero (no clear "higher-validity side" to predict)
        if abs(d) < 0.15:
            continue

        resp = row['response']
        try:
            resp = int(resp)
        except Exception:
            continue
        if resp not in (0, 1):
            continue

        chose_a = (resp == 0)
        picked_high_validity = chose_a if d > 0 else (not chose_a)
        hits += 1.0 if picked_high_validity else 0.0
        n += 1.0

    if n == 0:
        return 0.5
    return float(hits / n)
```

**Observed (real) value:** 0.2856 (var=0.0160)
**Previous candidate values (this loop):**
  - iter 1: 0.2433 (var=0.0030) (Δ vs real -0.0422)
  - iter 2 (most recent): 0.2344 (var=0.0051) (Δ vs real -0.0511)
**Other theories' values on this metric (for reference):**
- pi_3: 0.9389 (var=0.0016)
- pi_2: 0.5100 (var=0.0066)
- pi_1: 0.8522 (var=0.0137)
- pi_4: 0.3056 (var=0.0052)
- pi_5: 0.2767 (var=0.0068)
- pi_6: 0.2928 (var=0.0057)
- pi_7: 0.2778 (var=0.0058)
- pi_8: 0.2794 (var=0.0061)
- pi_9: 0.2956 (var=0.0037)
- pi_10: 0.2650 (var=0.0064)

### Experiment 4
**Design**
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    v = np.array([0.58, 0.97, 0.53, 0.80, 0.66, 0.90], dtype=float)
    w = v ** 2.0  # AVAI-style amplified weights (gamma=2)

    num = 0.0
    den = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.shape[0], b.shape[0], w.shape[0]))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        ww = w[:n]
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins != b_wins:
            continue  # not a tally tie
        d = float(np.sum(ww * (a - b)))
        if abs(d) < 0.30:
            continue  # tie trials whose weighted margin is negligible
        den += 1.0
        if d > 0:
            num += 1.0 if int(resp) == 0 else 0.0
        else:
            num += 1.0 if int(resp) == 1 else 0.0

    if den == 0:
        return 0.5
    return num / den
```

**Observed (real) value:** 0.1500 (var=0.0194)
**Previous candidate values (this loop):**
  - iter 1: 0.1233 (var=0.0092) (Δ vs real -0.0267)
  - iter 2 (most recent): 0.1250 (var=0.0090) (Δ vs real -0.0250)
**Other theories' values on this metric (for reference):**
- pi_2: 0.4917 (var=0.0165)
- pi_3: 0.9850 (var=0.0010)
- pi_1: 0.8500 (var=0.0219)
- pi_4: 0.1583 (var=0.0128)
- pi_5: 0.1650 (var=0.0115)
- pi_6: 0.1450 (var=0.0086)
- pi_7: 0.1500 (var=0.0133)
- pi_8: 0.1217 (var=0.0081)
- pi_9: 0.1067 (var=0.0070)
- pi_10: 0.1600 (var=0.0080)

### Experiment 5
**Design**
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    correct = []
    for _, row in data.iterrows():
        try:
            a = np.asarray(list(row['option_a_ratings']), dtype=float).ravel()
            b = np.asarray(list(row['option_b_ratings']), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        d = a[:n] - b[:n]
        nz = d[d != 0.0]
        if nz.size == 0:
            continue
        # dominance trial: every discriminating cue favours the same option
        if not (np.all(nz > 0) or np.all(nz < 0)):
            continue
        dominant_is_a = bool(np.all(nz > 0))
        try:
            resp = int(row['response'])
        except Exception:
            continue
        chose_a = (resp == 0)
        correct.append(1.0 if (chose_a == dominant_is_a) else 0.0)

    if len(correct) == 0:
        return 0.5
    return float(np.mean(correct))
```

**Observed (real) value:** 0.7427 (var=0.0173)
**Previous candidate values (this loop):**
  - iter 1: 0.7653 (var=0.0048) (Δ vs real +0.0227)
  - iter 2 (most recent): 0.7527 (var=0.0051) (Δ vs real +0.0100)
**Other theories' values on this metric (for reference):**
- pi_3: 0.9847 (var=0.0005)
- pi_4: 0.7440 (var=0.0064)
- pi_1: 0.8340 (var=0.0138)
- pi_2: 0.8493 (var=0.0126)
- pi_5: 0.7427 (var=0.0074)
- pi_6: 0.7773 (var=0.0049)
- pi_7: 0.7467 (var=0.0048)
- pi_8: 0.7487 (var=0.0072)
- pi_9: 0.7473 (var=0.0050)
- pi_10: 0.7707 (var=0.0058)

### Experiment 6
**Design**
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    # design validities (fixed by the experimental design)
    v_design = np.array([0.95, 0.70, 0.55, 0.95, 0.70, 0.55], dtype=float)
    hits = 0
    n = 0
    for a_raw, b_raw, r in zip(data['option_a_ratings'],
                               data['option_b_ratings'],
                               data['response']):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        k = int(min(a.size, b.size))
        if k == 0:
            continue
        if v_design.size >= k:
            vv = v_design[:k]
        else:
            vv = np.linspace(0.95, 0.55, k)
        d = a[:k] - b[:k]
        idx = np.nonzero(d != 0.0)[0]
        if idx.size != 2:
            continue
        j1 = int(idx[0])
        j2 = int(idx[1])
        # the two discriminating cues must point to OPPOSITE options
        if d[j1] * d[j2] > 0:
            continue
        # and the LATER cue must be the LESS valid one
        if not (vv[j2] < vv[j1]):
            continue
        late_choice = 0 if d[j2] > 0 else 1  # 0 = A, 1 = B
        try:
            resp = int(r)
        except Exception:
            continue
        n += 1
        if resp == late_choice:
            hits += 1
    if n == 0:
        return float('nan')
    return float(hits) / float(n)
```

**Observed (real) value:** 0.5067 (var=0.0112)
**Previous candidate values (this loop):**
  - iter 1: 0.5200 (var=0.0097) (Δ vs real +0.0133)
  - iter 2 (most recent): 0.4925 (var=0.0110) (Δ vs real -0.0142)
**Other theories' values on this metric (for reference):**
- pi_4: 0.8367 (var=0.0052)
- pi_3: 0.0300 (var=0.0018)
- pi_1: 0.1550 (var=0.0169)
- pi_2: 0.4942 (var=0.0103)
- pi_5: 0.5083 (var=0.0072)
- pi_6: 0.5033 (var=0.0076)
- pi_7: 0.4817 (var=0.0130)
- pi_8: 0.4725 (var=0.0109)
- pi_9: 0.5208 (var=0.0068)
- pi_10: 0.5017 (var=0.0113)

### Experiment 7
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = []
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float).ravel()
        b = np.asarray(row['option_b_ratings'], dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        d = a[:n] - b[:n]
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue
        fav_a = d[disc] > 0.0
        # skip unanimous (dominance) displays: both theories agree there
        if fav_a.all() or (~fav_a).all():
            continue
        # option favoured by the LAST-READ (highest-index) discriminating row
        last_idx = disc[-1]
        late_option = 0 if d[last_idx] > 0.0 else 1
        try:
            resp = int(row['response'])
        except Exception:
            continue
        hits.append(1.0 if resp == late_option else 0.0)

    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.4383 (var=0.0023)
**Previous candidate values (this loop):**
  - iter 1: 0.4478 (var=0.0037) (Δ vs real +0.0094)
  - iter 2 (most recent): 0.4589 (var=0.0026) (Δ vs real +0.0206)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4711 (var=0.0034)
- pi_4: 0.7642 (var=0.0020)
- pi_1: 0.2703 (var=0.0046)
- pi_2: 0.3842 (var=0.0037)
- pi_3: 0.3467 (var=0.0009)
- pi_6: 0.4419 (var=0.0028)
- pi_7: 0.4508 (var=0.0038)
- pi_8: 0.4408 (var=0.0032)
- pi_9: 0.4628 (var=0.0033)
- pi_10: 0.4500 (var=0.0038)

### Experiment 8
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 1, 0, 0, 1, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Design validities (fixed by the experiment); fallback handles other lengths.
    V_DESIGN = np.array([0.955, 0.545, 0.950, 0.540, 0.945, 0.535], dtype=float)
    LAM = 1.6
    DELTA = 0.9

    hits = []
    for _, row in data.iterrows():
        try:
            a = np.asarray(list(row['option_a_ratings']), dtype=float).ravel()
            b = np.asarray(list(row['option_b_ratings']), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if V_DESIGN.size >= n:
            v = V_DESIGN[:n]
        else:
            v = np.concatenate([V_DESIGN, np.full(n - V_DESIGN.size, 0.545)])[:n]

        d = a - b
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue

        # salience of each discriminating row: recency x (1 - validity)
        j = disc.astype(float)
        logu = LAM * j + DELTA * np.log(np.clip(1.0 - v[disc], 1e-9, None))
        logu = logu - np.max(logu)
        u = np.exp(logu)
        top = disc[int(np.argmax(u))]
        top_owner_a = bool(d[top] > 0.0)  # True -> the salient row favours A

        n_a = int(np.sum(d[disc] > 0.0))
        n_b = m - n_a

        # include only trials where the row-count tally does NOT strictly
        # agree with the most salient (late / low-validity) discriminating row
        if n_a > n_b:
            majority_a = True
            tie = False
        elif n_b > n_a:
            majority_a = False
            tie = False
        else:
            majority_a = None
            tie = True
        if (not tie) and (majority_a == top_owner_a):
            continue

        try:
            resp = int(row['response'])
        except Exception:
            continue
        chose_a = (resp == 0)
        hits.append(1.0 if (chose_a == top_owner_a) else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.7697 (var=0.0057)
**Previous candidate values (this loop):**
  - iter 1: 0.8231 (var=0.0023) (Δ vs real +0.0534)
  - iter 2 (most recent): 0.8100 (var=0.0031) (Δ vs real +0.0403)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7326 (var=0.0025)
- pi_5: 0.4900 (var=0.0045)
- pi_1: 0.1511 (var=0.0123)
- pi_2: 0.3354 (var=0.0031)
- pi_3: 0.0803 (var=0.0009)
- pi_6: 0.7540 (var=0.0026)
- pi_7: 0.7686 (var=0.0034)
- pi_8: 0.7611 (var=0.0025)
- pi_9: 0.7766 (var=0.0030)
- pi_10: 0.7960 (var=0.0025)

### Experiment 9
**Design**
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V_DESIGN = np.array([0.958, 0.546, 0.954, 0.542, 0.950, 0.538], dtype=float)
    LAM = 1.5      # reading-order recency gain (shared by both accounts)
    GAM = 0.9      # oddness exponent on (1 - validity) (shared by both accounts)

    hits = 0.0
    tot = 0.0

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_raw, dtype=float).ravel()
            b = np.asarray(b_raw, dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if n == V_DESIGN.size:
            v = V_DESIGN.copy()
        else:
            v = np.linspace(0.95, 0.55, n)
        v = np.clip(v, 0.5, 0.995)

        diff = a - b
        disc = np.nonzero(diff != 0.0)[0]
        m = int(disc.size)
        if m < 2:
            continue
        signs = np.sign(diff[disc])
        # keep only CONFLICT displays (both options win at least one row)
        if np.all(signs > 0) or np.all(signs < 0):
            continue

        logw = GAM * np.log(np.clip(1.0 - v[disc], 1e-9, None)) + LAM * disc.astype(float)
        k = int(np.argmax(logw))
        favored_a = signs[k] > 0.0

        try:
            r = int(resp)
        except Exception:
            continue
        chose_a = (r == 0)
        hits += 1.0 if (chose_a == favored_a) else 0.0
        tot += 1.0

    if tot == 0.0:
        return float('nan')
    return float(hits / tot)
```

**Observed (real) value:** 0.8189 (var=0.0074)
**Previous candidate values (this loop):**
  - iter 1: 0.8278 (var=0.0021) (Δ vs real +0.0089)
  - iter 2 (most recent): 0.8314 (var=0.0019) (Δ vs real +0.0125)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4964 (var=0.0034)
- pi_6: 0.7364 (var=0.0031)
- pi_1: 0.1528 (var=0.0126)
- pi_2: 0.3228 (var=0.0037)
- pi_3: 0.0178 (var=0.0002)
- pi_4: 0.7092 (var=0.0034)
- pi_7: 0.7714 (var=0.0022)
- pi_8: 0.7536 (var=0.0025)
- pi_9: 0.7783 (var=0.0025)
- pi_10: 0.7953 (var=0.0023)

### Experiment 10
**Design**
  A=[1, 0, 1, 0, 1]  B=[1, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    # Design validities (fixed by the experiment)
    v_default = np.array([0.53, 0.72, 0.86, 0.93, 0.99], dtype=float)

    def weights(n):
        if n <= v_default.size:
            v = v_default[:n]
        else:
            v = np.concatenate([v_default, np.full(n - v_default.size, 0.99)])
        v = np.clip(v, 0.5, 0.9995)
        logw = 0.9 * np.log(1.0 - v) + 1.5 * np.arange(n, dtype=float)
        logw = logw - np.max(logw)
        return np.exp(logw)

    wcache = {}
    hits = []
    for a_raw, b_raw, resp in zip(data['option_a_ratings'].values,
                                  data['option_b_ratings'].values,
                                  data['response'].values):
        try:
            a = np.asarray(list(a_raw), dtype=float).ravel()
            b = np.asarray(list(b_raw), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]
        d = a - b
        nA = int(np.sum(d > 0))
        nB = int(np.sum(d < 0))
        # keep only CONFLICT displays (both options favoured by at least one expert)
        if nA == 0 or nB == 0:
            continue
        if n not in wcache:
            wcache[n] = weights(n)
        w = wcache[n]
        S = float(np.sum(np.sign(d) * w))
        if S == 0.0:
            continue
        fav = 0 if S > 0 else 1  # response coding: 0 = A, 1 = B
        try:
            r = int(resp)
        except Exception:
            continue
        hits.append(1.0 if r == fav else 0.0)

    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.4178 (var=0.0051)
**Previous candidate values (this loop):**
  - iter 1: 0.4142 (var=0.0030) (Δ vs real -0.0036)
  - iter 2 (most recent): 0.4153 (var=0.0028) (Δ vs real -0.0025)
**Other theories' values on this metric (for reference):**
- pi_6: 0.7386 (var=0.0031)
- pi_5: 0.6297 (var=0.0048)
- pi_1: 0.6053 (var=0.0037)
- pi_2: 0.5439 (var=0.0033)
- pi_3: 0.7967 (var=0.0021)
- pi_4: 0.6303 (var=0.0046)
- pi_7: 0.3878 (var=0.0029)
- pi_8: 0.4492 (var=0.0019)
- pi_9: 0.4247 (var=0.0030)
- pi_10: 0.4236 (var=0.0018)

### Experiment 11
**Design**
  A=[1, 1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Design-fixed printed validities for this experiment
    v = np.array([0.55, 0.90, 0.75, 0.95, 0.68, 0.85], dtype=float)
    n = v.size
    j = np.arange(n, dtype=float)

    # MDSC-NV salience: near-argmax doubt rule (delta=15, lam=0.115*15)
    logu = 15.0 * np.log(np.clip(1.0 - v, 1e-12, None)) + 1.725 * j
    # SSI-DS+ compensatory summation weights (gamma=0.9, lam=1.5)
    w_ssi = np.power(np.clip(1.0 - v, 1e-12, None), 0.9) * np.exp(1.5 * j)

    hits = 0
    tot = 0
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_raw, dtype=float).ravel()
            b = np.asarray(b_raw, dtype=float).ravel()
        except Exception:
            continue
        if a.size != n or b.size != n:
            continue
        d = a - b
        disc = np.nonzero(d != 0.0)[0]
        if disc.size == 0:
            continue

        # MDSC-NV predicted winner: verdict of the single most doubtful
        # discriminating expert
        k = disc[int(np.argmax(logu[disc]))]
        pred_mdsc = 0 if d[k] > 0 else 1

        # SSI-DS+ predicted winner: sign of the weighted sum over all
        # discriminating rows (coalitions add, late rows dominate)
        E = float(np.sum(np.sign(d[disc]) * w_ssi[disc]))
        if E == 0.0:
            continue
        pred_ssi = 0 if E > 0 else 1

        if pred_ssi == pred_mdsc:
            continue  # non-diagnostic trial type

        tot += 1
        try:
            resp = int(r)
        except Exception:
            continue
        if resp == pred_mdsc:
            hits += 1

    if tot == 0:
        return 0.5
    return float(hits) / float(tot)
```

**Observed (real) value:** 0.5925 (var=0.0026)
**Previous candidate values (this loop):**
  - iter 1: 0.6083 (var=0.0031) (Δ vs real +0.0158)
  - iter 2 (most recent): 0.6117 (var=0.0027) (Δ vs real +0.0192)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6833 (var=0.0038)
- pi_6: 0.2583 (var=0.0034)
- pi_1: 0.1550 (var=0.0102)
- pi_2: 0.4058 (var=0.0050)
- pi_3: 0.1054 (var=0.0016)
- pi_4: 0.3046 (var=0.0036)
- pi_5: 0.2854 (var=0.0033)
- pi_8: 0.6367 (var=0.0043)
- pi_9: 0.6033 (var=0.0045)
- pi_10: 0.5946 (var=0.0036)

### Experiment 12
**Design**
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    V_DESIGN = np.array([0.51, 0.72, 0.80, 0.90, 0.95, 0.985], dtype=float)

    GAMMA = 0.90
    LAM = 1.50
    DELTA = 15.0
    LAM_M = 1.725

    hits = 0.0
    tot = 0.0

    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        try:
            a = np.asarray(list(a_raw), dtype=float).ravel()
            b = np.asarray(list(b_raw), dtype=float).ravel()
        except Exception:
            continue
        n = int(min(a.size, b.size))
        if n == 0:
            continue
        a = a[:n]
        b = b[:n]

        if n <= V_DESIGN.size:
            v = V_DESIGN[:n]
        else:
            v = np.concatenate([V_DESIGN, np.full(n - V_DESIGN.size, 0.985)])
        v = np.clip(v, 0.5, 0.9995)

        diff = a - b
        disc = np.nonzero(diff != 0.0)[0]
        if disc.size == 0:
            continue
        signs = np.sign(diff[disc])

        # --- SSI-DS+ side: max-normalised weighted SUM, late/high-validity dominated
        logw = GAMMA * np.log(np.clip(1.0 - v[disc], 1e-12, None)) + LAM * disc.astype(float)
        logw = logw - np.max(logw)
        w = np.exp(logw)
        E = float(np.sum(signs * w))
        if abs(E) < 1e-9:
            continue
        ssi_side = 1.0 if E > 0 else -1.0

        # --- MDSC-NV side: single most-doubtful DISCRIMINATING row decides
        sal = DELTA * np.log(np.clip(1.0 - v[disc], 1e-12, None)) + LAM_M * disc.astype(float)
        k = int(np.argmax(sal))
        mdsc_side = float(signs[k])
        if mdsc_side == 0.0:
            continue

        # keep only trials where the two accounts point to OPPOSITE options
        if mdsc_side == ssi_side:
            continue

        try:
            r = int(resp)
        except Exception:
            continue
        chose_a = (r == 0)
        ssi_favours_a = (ssi_side > 0)
        hits += 1.0 if (chose_a == ssi_favours_a) else 0.0
        tot += 1.0

    if tot == 0.0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.2608 (var=0.0079)
**Previous candidate values (this loop):**
  - iter 1: 0.1821 (var=0.0030) (Δ vs real -0.0787)
  - iter 2 (most recent): 0.2183 (var=0.0051) (Δ vs real -0.0425)
**Other theories' values on this metric (for reference):**
- pi_6: 0.7412 (var=0.0040)
- pi_7: 0.2592 (var=0.0042)
- pi_1: 0.8400 (var=0.0123)
- pi_2: 0.5587 (var=0.0027)
- pi_3: 0.8158 (var=0.0005)
- pi_4: 0.7417 (var=0.0031)
- pi_5: 0.7421 (var=0.0057)
- pi_8: 0.2729 (var=0.0043)
- pi_9: 0.2617 (var=0.0055)
- pi_10: 0.2013 (var=0.0047)

### Experiment 13
**Design**
  A=[1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 1]  B=[0, 1, 0, 1, 1]
  A=[0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = []
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n < 5:
            continue
        a = a[:n]
        b = b[:n]
        d = a - b
        disc = [int(i) for i in np.nonzero(d != 0.0)[0]]
        # require feature 0 (validity .68) to discriminate
        if 0 not in disc:
            continue
        # require the global doubt anchor, feature 3 (validity .52), to be SILENT
        if 3 in disc:
            continue
        fav_a = [i for i in disc if d[i] > 0.0]
        fav_b = [i for i in disc if d[i] < 0.0]
        if d[0] > 0.0:
            lone, other = fav_a, fav_b
            lone_is_a = True
        else:
            lone, other = fav_b, fav_a
            lone_is_a = False
        # exactly one dissenter (feature 0) against a coalition of >=2 more valid experts
        if len(lone) != 1 or len(other) < 2:
            continue
        try:
            resp = int(r)
        except Exception:
            continue
        chose_lone = (resp == 0) if lone_is_a else (resp == 1)
        hits.append(1.0 if chose_lone else 0.0)
    if len(hits) == 0:
        return float('nan')
    return float(np.mean(hits))
```

**Observed (real) value:** 0.5460 (var=0.0126)
**Previous candidate values (this loop):**
  - iter 1: 0.4570 (var=0.0133) (Δ vs real -0.0890)
  - iter 2 (most recent): 0.4530 (var=0.0101) (Δ vs real -0.0930)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6410 (var=0.0093)
- pi_8: 0.2680 (var=0.0082)
- pi_1: 0.1620 (var=0.0145)
- pi_2: 0.1700 (var=0.0205)
- pi_3: 0.0110 (var=0.0005)
- pi_4: 0.2580 (var=0.0097)
- pi_5: 0.2380 (var=0.0124)
- pi_6: 0.2580 (var=0.0074)
- pi_9: 0.4660 (var=0.0150)
- pi_10: 0.5080 (var=0.0118)

### Experiment 14
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    V = np.array([0.62, 0.78, 0.86, 0.93, 0.53, 0.97], dtype=float)
    ANCHOR = 4  # the .53 expert (below DTV's doubt trigger)
    hits = 0.0
    tot = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'].tolist(),
                                  data['option_b_ratings'].tolist(),
                                  data['response'].tolist()):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        n = int(min(a.size, b.size))
        if n != 6:
            continue
        diff = a[:6] - b[:6]
        disc = np.nonzero(diff != 0.0)[0]
        m = int(disc.size)
        if m < 3:
            continue
        # the globally most doubtful expert (.53) must be SILENT
        if ANCHOR in set(disc.tolist()):
            continue
        d = diff[disc]
        na = int(np.sum(d > 0.0))
        nb = m - na
        if min(na, nb) != 1 or max(na, nb) < 2:
            continue
        if na == 1:
            lone = int(disc[d > 0.0][0])
            fav = 0  # option A favoured by the lone dissenter
        else:
            lone = int(disc[d < 0.0][0])
            fav = 1
        # the lone dissenter must be the LEAST valid discriminating expert
        if abs(V[lone] - float(np.min(V[disc]))) > 1e-9:
            continue
        tot += 1.0
        if int(resp) == fav:
            hits += 1.0
    if tot < 1.0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.4675 (var=0.0144)
**Previous candidate values (this loop):**
  - iter 1: 0.5150 (var=0.0170) (Δ vs real +0.0475)
  - iter 2 (most recent): 0.5363 (var=0.0167) (Δ vs real +0.0687)
**Other theories' values on this metric (for reference):**
- pi_8: 0.2313 (var=0.0086)
- pi_7: 0.6388 (var=0.0149)
- pi_1: 0.1550 (var=0.0197)
- pi_2: 0.1313 (var=0.0107)
- pi_3: 0.0238 (var=0.0015)
- pi_4: 0.2812 (var=0.0111)
- pi_5: 0.2863 (var=0.0094)
- pi_6: 0.2313 (var=0.0138)
- pi_9: 0.5387 (var=0.0195)
- pi_10: 0.5413 (var=0.0121)

### Experiment 15
**Design**
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = 0.0
    tot = 0.0
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    ANCHOR = 3  # column with the lowest printed validity (0.55)
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        a = [int(x) for x in list(a_raw)]
        b = [int(x) for x in list(b_raw)]
        k = min(len(a), len(b))
        if k <= ANCHOR:
            continue
        if a[ANCHOR] == b[ANCHOR]:
            continue  # anchor silent -> not a coalition test
        n_a = 0
        n_b = 0
        for i in range(k):
            if a[i] > b[i]:
                n_a += 1
            elif b[i] > a[i]:
                n_b += 1
        anchor_favors_a = a[ANCHOR] > b[ANCHOR]
        opposing = n_b if anchor_favors_a else n_a
        if opposing < 1:
            continue  # pure dominance for the anchor side -> no coalition
        try:
            resp = int(r)
        except Exception:
            continue
        chose_a = (resp == 0)
        if chose_a == anchor_favors_a:
            hits += 1.0
        tot += 1.0
    if tot == 0.0:
        return float('nan')
    return float(hits / tot)
```

**Observed (real) value:** 0.8620 (var=0.0155)
**Previous candidate values (this loop):**
  - iter 1: 0.7070 (var=0.0034) (Δ vs real -0.1550)
  - iter 2 (most recent): 0.7497 (var=0.0038) (Δ vs real -0.1123)
**Other theories' values on this metric (for reference):**
- pi_7: 0.7610 (var=0.0035)
- pi_9: 0.4777 (var=0.0043)
- pi_1: 0.3003 (var=0.0058)
- pi_2: 0.2920 (var=0.0039)
- pi_3: 0.1703 (var=0.0013)
- pi_4: 0.2870 (var=0.0043)
- pi_5: 0.2827 (var=0.0026)
- pi_6: 0.2450 (var=0.0025)
- pi_8: 0.7143 (var=0.0022)
- pi_10: 0.8087 (var=0.0029)

### Experiment 16
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = 0.0
    n = 0.0
    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(list(a_raw), dtype=float).ravel()
        b = np.asarray(list(b_raw), dtype=float).ravel()
        k = int(min(a.size, b.size))
        if k < 6:
            continue
        # the near-chance anchor expert (column 0, validity .52) must discriminate
        if a[0] == b[0]:
            continue
        anchor_side = 0 if a[0] > b[0] else 1  # 0 == option A, 1 == option B
        # count late, mid-doubt rows (columns 3,4,5) that oppose the anchor
        opp = 0
        for j in (3, 4, 5):
            if a[j] == b[j]:
                continue
            fav = 0 if a[j] > b[j] else 1
            if fav != anchor_side:
                opp += 1
        if opp < 2:
            continue
        n += 1.0
        try:
            r = int(resp)
        except Exception:
            continue
        if r == anchor_side:
            hits += 1.0

    if n == 0.0:
        return 0.5
    return float(hits / n)

```

**Observed (real) value:** 0.8260 (var=0.0180)
**Previous candidate values (this loop):**
  - iter 1: 0.8395 (var=0.0031) (Δ vs real +0.0135)
  - iter 2 (most recent): 0.8225 (var=0.0035) (Δ vs real -0.0035)
**Other theories' values on this metric (for reference):**
- pi_9: 0.4215 (var=0.0085)
- pi_7: 0.7245 (var=0.0054)
- pi_1: 0.4340 (var=0.0037)
- pi_2: 0.2900 (var=0.0065)
- pi_3: 0.1700 (var=0.0026)
- pi_4: 0.3045 (var=0.0052)
- pi_5: 0.3325 (var=0.0058)
- pi_6: 0.3115 (var=0.0039)
- pi_8: 0.6770 (var=0.0061)
- pi_10: 0.8075 (var=0.0040)

### Experiment 17
**Design**
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 0, 1]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    hits = 0.0
    tot = 0.0
    for a_raw, b_raw, r in zip(data['option_a_ratings'], data['option_b_ratings'], data['response']):
        try:
            a = [int(x) for x in a_raw]
            b = [int(x) for x in b_raw]
        except Exception:
            continue
        if len(a) < 6 or len(b) < 6:
            continue
        # expert 4 (validity .52, the near-chance 'anchor') must be SILENT
        if a[4] != b[4]:
            continue
        # expert 5 (validity .66, mid-doubt) must discriminate
        d5 = a[5] - b[5]
        if d5 == 0:
            continue
        # there must be a genuine opposing coalition among the more valid experts 0..3
        opposed = False
        for j in range(4):
            dj = a[j] - b[j]
            if dj != 0 and (dj * d5) < 0:
                opposed = True
                break
        if not opposed:
            continue
        fav = 0 if d5 > 0 else 1  # option favoured by the .66 expert
        tot += 1.0
        try:
            rr = int(r)
        except Exception:
            continue
        if rr == fav:
            hits += 1.0
    if tot <= 0:
        return 0.5
    return float(hits / tot)
```

**Observed (real) value:** 0.4925 (var=0.0074)
**Previous candidate values (this loop):**
  - iter 1: 0.5206 (var=0.0060) (Δ vs real +0.0281)
  - iter 2 (most recent): 0.5606 (var=0.0065) (Δ vs real +0.0681)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6956 (var=0.0072)
- pi_10: 0.4906 (var=0.0058)
- pi_1: 0.4988 (var=0.0030)
- pi_2: 0.3175 (var=0.0067)
- pi_3: 0.3875 (var=0.0033)
- pi_4: 0.7712 (var=0.0079)
- pi_5: 0.7512 (var=0.0059)
- pi_6: 0.7525 (var=0.0064)
- pi_8: 0.3119 (var=0.0063)
- pi_9: 0.5931 (var=0.0080)

### Experiment 18
**Design**
  A=[1, 0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 1, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    ANCHOR = 4   # printed validity .52  (the only sub-.558 expert)
    SECOND = 5   # printed validity .68, last column (secondary doubt row)

    t_num = 0.0; t_den = 0.0   # anchor-follow rate on LONG, low-opposition displays
    c_num = 0.0; c_den = 0.0   # c5-follow rate when the .52 anchor is SILENT

    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()

    for a_, b_, r_ in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(a_, dtype=float).ravel()
            b = np.asarray(b_, dtype=float).ravel()
            r = int(r_)
        except Exception:
            continue
        if a.size < 6 or b.size < 6:
            continue
        d = a[:6] - b[:6]
        disc = np.nonzero(d != 0.0)[0]
        m = int(disc.size)
        if m == 0:
            continue
        nA = int(np.sum(d[disc] > 0.0))
        nB = m - nA
        kconf = min(nA, nB)
        chose_a = (r == 0)

        anchor_speaks = bool(np.any(disc == ANCHOR))
        second_speaks = bool(np.any(disc == SECOND))

        if anchor_speaks and m >= 4 and kconf <= 1:
            # long display, anchor either alone against a coalition or with everyone
            fav_a = (d[ANCHOR] > 0.0)
            t_den += 1.0
            if chose_a == fav_a:
                t_num += 1.0
        elif (not anchor_speaks) and second_speaks and kconf == 1:
            # anchor silent; is the .68 row the LONE dissenter on its side?
            fav_a_5 = (d[SECOND] > 0.0)
            side_count = nA if fav_a_5 else nB
            if side_count == 1:
                c_den += 1.0
                if chose_a == fav_a_5:
                    c_num += 1.0

    t_rate = (t_num / t_den) if t_den > 0 else 0.5
    c_rate = (c_num / c_den) if c_den > 0 else 0.5
    return float(t_rate - c_rate)
```

**Observed (real) value:** 0.3183 (var=0.0405)
**Previous candidate values (this loop):**
  - iter 1: 0.1742 (var=0.0168) (Δ vs real -0.1442)
  - iter 2 (most recent): 0.2500 (var=0.0173) (Δ vs real -0.0683)
**Other theories' values on this metric (for reference):**
- pi_10: 0.3550 (var=0.0214)
- pi_7: 0.0125 (var=0.0220)
- pi_1: -0.0267 (var=0.0062)
- pi_2: 0.1300 (var=0.0079)
- pi_3: 0.1117 (var=0.0039)
- pi_4: -0.2992 (var=0.0200)
- pi_5: -0.3408 (var=0.0161)
- pi_6: -0.3108 (var=0.0127)
- pi_8: 0.3800 (var=0.0208)
- pi_9: -0.0500 (var=0.0184)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
**SSG-2 — Salience-Share Gating with contrast-sharpened oddness and a near-flat opposition discount.**

The architecture is unchanged from SSG; two quantitative commitments are sharpened.

**(1) Two modes: adjudication vs. integration.** On a trial the subject either (i) lets ONE expert adjudicate the choice, or (ii) integrates all disagreeing rows. Which mode runs is decided neither by an absolute knife-edge on a single printed validity nor by display length, but by a RELATIVE quantity: the share of the display's total *oddness* that is owned by genuinely near-chance experts.

**(2) The oddness share, with a SHARPER contrast.** Each discriminating row has oddness o_j = (1-v_j)^gamma_s and a scandal value g_j = sigmoid((v_crit - v_j)/w_h), v_crit ~ .578 — the probability that this expert's dissent is heard as a *coin-flipper speaking up* rather than as ordinary evidence. The gate is
  share = Σ_j g_j·o_j / Σ_j o_j,  pi_one = (max_j g_j)·[f + (1-f)·sigmoid((share - c)/w)].
Adjudication requires BOTH that some expert be near-chance AND that near-chance experts own most of the display's oddness. **Sharpened claim: the oddness read-out is strongly contrast-enhanced (gamma_s ≈ 6.5-8.5, not ≈ 5).** Oddness is close to an ordinal 'who is the strangest expert on the screen' judgement rather than a graded intensity. The consequence is a *selective* dilution rule: a bystander only steals authority from a near-chance dissenter if it is itself nearly as odd (e.g. a .60 expert standing beside a .55 expert — the Exp-2 configuration, where the .55 row keeps only ~.74 of the oddness and must share the trial with integration), whereas mid-doubt bystanders that are clearly less strange (.62-.72 beside a .52/.55 anchor) barely dilute it at all, so the anchor keeps ~.8-.9 of the oddness and rules the trial. This is the claim that separates SSG-2 both from absolute-threshold gating (which never dilutes) and from linear-oddness share (which dilutes indiscriminately and therefore wrongly deflates the .52/.55-anchor designs).

**(3) The adjudicating row, and what degrades adjudication.** Among discriminating rows the consulted verdict is drawn from softmax(log g_j + mu·j): reading order arbitrates only BETWEEN co-scandalous rows (last-read wins) and can never lift an ordinary expert over a near-chance one. Adjudication is *free in display length* (one row is read) and is charged only by genuine OPPOSITION, and even that charge is now **near-flat** (rho_opp ≈ .88-.96 per minority row beyond the first): a near-chance dissenter standing against 1, 3 or 5 higher-validity rows is followed at essentially the same high rate; only balanced splits, where two rival coalitions must be held, cost anything appreciable. The overall fidelity of the one-reason limb is correspondingly slightly lower (eps_t ≈ .23-.33), so mean adjudication accuracy is preserved while its dependence on coalition size is flattened.

**(4) Integration is mild in doubt, strongly recency-tilted, and clearly non-deterministic.** When the gate is shut, evidence is integrated with weights w_j = (1-v_j)^gamma_w·exp(lam·j), gamma_w ≈ 1.45 much shallower than the gate's gamma_s and lam ≈ .22 much stronger than the consult tie-breaker: coalitions of moderately valid experts really do add up and late columns count more, so mid-doubt lone dissenters (.62-.72) land near chance against 2-3 opposing rows. Evidence is divisively normalised to the loudest dissent, E = Σ sign_j·ŵ_j/(sigma + Σ ŵ_j) with a LARGER floor sigma ≈ .52-.70: integration is an effortful, noisy accumulation, never a deterministic verdict, which keeps every compensatory metric off its ceiling/floor. It leaks with display load (rho_m per row past the second) and with opposition (rho_c per minority row), keeping unanimous 4-6 row displays confident but well below ceiling. When every discriminating expert agrees there is nothing to adjudicate, so pi_one = 0 and dominance displays are always integrated. If two printed validities are indistinguishable (gap < .002) the experts cannot be individuated, oddness has no referent, and choice collapses to a graded unweighted row tally (exact coin flip on 1-1 splits). No feedback is given, so the rule is stationary across the block.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # SSG: Salience-Share Gating
    import numpy as np

    # ---------- parse the (2, n_features) stimulus robustly ----------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()
            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()
        else:
            vals = list(state.values())
            if len(vals) >= 2:
                a = np.asarray(vals[0], dtype=float).ravel()
                b = np.asarray(vals[1], dtype=float).ravel()
    if a is None or b is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 2 and arr.shape[0] == 2:
            a, b = arr[0].ravel(), arr[1].ravel()
        elif arr.ndim == 2 and arr.shape[1] == 2:
            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()
        elif arr.ndim == 1:
            h = arr.shape[0] // 2
            a, b = arr[:h], arr[h:2 * h]
        else:
            f = np.asarray(arr, dtype=float).reshape(2, -1)
            a, b = f[0].ravel(), f[1].ravel()

    n = int(min(np.size(a), np.size(b)))
    if n == 0:
        return np.array([0.5, 0.5])
    a = np.asarray(a, dtype=float)[:n]
    b = np.asarray(b, dtype=float)[:n]

    # ---------- printed validities ----------
    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None
    if v_raw is None:
        v = np.linspace(0.95, 0.55, n)
    else:
        v = np.asarray(v_raw, dtype=float).ravel()
        if v.size < n:
            v = np.concatenate([v, np.full(n - v.size, 0.55)])
        v = v[:n]
    v = np.clip(v, 0.5, 0.9995)

    # ---------- parameters ----------
    gamma_s = float(parameters['gamma_s'])
    v_crit = float(parameters['v_crit'])
    w_h = float(max(float(parameters['w_h']), 1e-4))
    c_share = float(parameters['c_share'])
    w_share = float(max(float(parameters['w_share']), 1e-4))
    floor = float(np.clip(float(parameters['gate_floor']), 0.0, 1.0))
    mu = float(parameters['mu'])
    eps_t = float(np.clip(float(parameters['eps_t']), 0.0, 1.0))
    rho_opp = float(np.clip(float(parameters['rho_opp']), 1e-6, 1.0))
    gamma_w = float(parameters['gamma_w'])
    lam = float(parameters['lam'])
    sigma = float(max(float(parameters['sigma']), 1e-6))
    beta = float(parameters['beta'])
    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))
    rho_m = float(np.clip(float(parameters['rho_m']), 1e-6, 1.0))
    rho_c = float(np.clip(float(parameters['rho_c']), 1e-6, 1.0))
    kappa = float(parameters['tally_kappa'])

    def sig(x):
        x = float(np.clip(x, -60.0, 60.0))
        return 1.0 / (1.0 + np.exp(-x))

    # ---------- discriminating rows ----------
    diff = a - b
    disc = np.nonzero(diff != 0.0)[0]
    m = int(disc.size)
    if m == 0:
        return np.array([0.5, 0.5])
    signs = np.sign(diff[disc])
    n_a = float(np.sum(signs > 0.0))
    n_b = float(m) - n_a
    k_conf = int(min(n_a, n_b))

    # ---------- leak on the integration limb ----------
    keep_c = (1.0 - eps0) * (rho_m ** max(m - 2, 0)) * (rho_c ** k_conf)
    keep_c = float(min(max(keep_c, 0.0), 1.0))

    # ---------- label-degeneracy gate ----------
    degenerate = False
    if n > 1:
        vs = np.sort(v)
        if bool(np.any(np.diff(vs) < 2.0e-3)):
            degenerate = True

    if degenerate:
        p_core = sig(kappa * (n_a - n_b))
        p_a = 0.5 + keep_c * (p_core - 0.5)
        p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
        p = np.array([p_a, 1.0 - p_a], dtype=float)
        return p / p.sum()

    vd = v[disc]
    jd = disc.astype(float)

    # ---------- scandal values and sharpened oddness ----------
    zz = np.clip((v_crit - vd) / w_h, -60.0, 60.0)
    g = 1.0 / (1.0 + np.exp(-zz))                       # near-chance "scandal" weight
    log_g = -np.logaddexp(0.0, -zz)                     # stable log sigmoid
    log_o = gamma_s * np.log(np.clip(1.0 - vd, 1e-12, None))
    log_o_shift = log_o - np.max(log_o)
    o = np.exp(np.clip(log_o_shift, -700.0, 0.0))
    o_sum = float(np.sum(o))
    if (not np.isfinite(o_sum)) or o_sum <= 0.0:
        o = np.ones(m, dtype=float)
        o_sum = float(m)

    share = float(np.sum(g * o) / o_sum)
    g_share = sig((share - c_share) / w_share)
    P_trig = float(np.clip(np.max(g), 0.0, 1.0))

    # unanimous displays need no adjudication
    if k_conf == 0:
        pi_one = 0.0
    else:
        pi_one = P_trig * (floor + (1.0 - floor) * g_share)
    pi_one = float(np.clip(pi_one, 0.0, 1.0))

    # ---------- which row adjudicates (recency only breaks scandal ties) ----------
    sc = log_g + mu * jd
    sc = sc - np.max(sc)
    ww = np.exp(np.clip(sc, -700.0, 0.0))
    ws = float(np.sum(ww))
    if (not np.isfinite(ws)) or ws <= 0.0:
        ww = np.full(m, 1.0 / m)
    else:
        ww = ww / ws
    p_or_a = float(np.sum(ww[signs > 0.0]))
    fid = (1.0 - eps_t) * (rho_opp ** max(k_conf - 1, 0))
    fid = float(min(max(fid, 0.0), 1.0))
    p_one_a = 0.5 + fid * (p_or_a - 0.5)

    # ---------- integration limb ----------
    logw = gamma_w * np.log(np.clip(1.0 - vd, 1e-12, None)) + lam * jd
    logw = logw - np.max(logw)
    wi = np.exp(np.clip(logw, -700.0, 0.0))
    wsum = float(np.sum(wi))
    if (not np.isfinite(wsum)) or wsum <= 0.0:
        wi = np.ones(m, dtype=float)
        wsum = float(m)
    E = float(np.sum(signs * wi)) / (sigma + wsum)
    p_comp = sig(beta * E)
    p_c_a = 0.5 + keep_c * (p_comp - 0.5)

    # ---------- mixture ----------
    p_a = pi_one * p_one_a + (1.0 - pi_one) * p_c_a
    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))
    p = np.array([p_a, 1.0 - p_a], dtype=float)
    return p / p.sum()

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0.0:
        return int(np.random.randint(len(probs)))
    probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- gamma_s: [6.4, 8.6]
- v_crit: [0.572, 0.586]
- w_h: [0.010, 0.015]
- c_share: [0.69, 0.75]
- w_share: [0.040, 0.065]
- gate_floor: [0.33, 0.47]
- mu: [0.68, 0.92]
- eps_t: [0.23, 0.33]
- rho_opp: [0.88, 0.96]
- gamma_w: [1.32, 1.58]
- lam: [0.18, 0.26]
- sigma: [0.52, 0.70]
- beta: [2.15, 2.65]
- eps0: [0.22, 0.30]
- rho_m: [0.87, 0.93]
- rho_c: [0.73, 0.83]
- tally_kappa: [0.7, 1.3]
- validities: validities

`rationale`: MINIMAL DIFF: `predict`/`policy` are re-emitted byte-for-byte; only five parameter RANGES move. No mechanism, equation or name changes.

Diagnosis behind the edit. I traced the two big residuals (Exp 15 .707 vs .862; Exp 18 T−C .174 vs .318) through the code rather than accepting the critic's first-listed cause. In Exp 15 the anchor is almost always the LONE dissenter (k_conf = 1), so `rho_opp ** (k_conf-1) = 1` and the opposition discount is literally inert there — flattening rho_opp alone cannot fix Exp 15. What actually depresses it is the GATE: with gamma_s ≈ 5.5 the .55 anchor keeps only ~.66 of the display's oddness once mid-doubt bystanders (~.62/.70) also discriminate, so pi_one ≈ .5 and half the trial is surrendered to integration (0.5·0.875 + 0.5·0.55 ≈ .71 — exactly the observed .707). The same arithmetic explains Exp 18's deflated T-term.

Edit 1 — gamma_s [4.6,6.4] → [6.4,8.6]. Contrast-sharpening the oddness read-out makes dilution SELECTIVE rather than indiscriminate: a .62/.70 bystander's oddness falls from .25/.11 to .13/.04 of the anchor's, so the .52/.55 anchor's share rises .66→.77-.85 and pi_one ≈ .85-.93 (Exp 15 → ~.81, Exp 18-T → ~.84). Crucially it does NOT undo the Exp-2 dilution that this family was built for: there the diluter is a .60 expert, whose oddness is still ~.4 of the .55 expert's even at gamma_s = 8, so share stays ≈ .74 and a substantial slice of Exp 2 remains compensatory (T−C rises only ~.04, from .182 toward ~.22). Exps 8/9/10/11/12 have share ≈ 1 already and are untouched by this knob.

Edit 2 — gate_floor [0.28,0.42] → [0.33,0.47] (the critic's adjustment 2, applied on the floor rather than on c_share so that the g-weighted share definition and its Exp-2/Exp-4 benefits are preserved exactly, as the critic insisted).

Edit 3 — sigma [0.44,0.56] → [0.52,0.70] (the critic's adjustment 3). Softening the divisive normaliser, not beta/gamma_w/lam, leaves Exps 10/11/14 where they already fit while pulling the over-deterministic compensatory metrics toward the data: Exp 12 .182→~.21 (real .261), Exp 3 .243→~.26 (.286), Exp 13 .457→~.48 (.546), Exp 5 .765→~.75 (.743), Exp 4 .123→~.13 (.150), and — importantly for the T−C gap — it lowers Exp 18's C-term (a lone late .68 dissenter is currently followed at ~.63) without touching Exps 13/14, which pin that quantity near .47-.55.

Edits 4/5 — rho_opp [0.83,0.93] → [0.88,0.96] with a compensating eps_t [0.20,0.30] → [0.23,0.33]. This is the critic's adjustment 1 in the exact form requested: mean one-reason fidelity is held where it already fits while its dependence on coalition size is flattened. The pair is self-financing — the eps_t rise removes the ~.05 overshoot on Exp 8 (.823 vs .770) and Exp 9, and helps Exp 12, while the flatter discount protects the k_conf = 2-3 trials of Exps 16/18 from that same rise.

Expected net: Exp 15 .71→~.81, Exp 18 .17→~.24, Exp 13 +.02, Exp 12 +.03, Exp 8 −.01 error, against a bounded ~.04 cost on Exp 2 and ~.02 on Exp 16 — a roughly 2:1 reduction in summed squared residual versus the accepted base.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: SSG is a genuine improvement over both pi_7 and pi_10 on the pooled set: it nails Exp 1 (.294 vs .282), Exp 2's T
inus C term (.182 vs .174 
inus pi_10's biggest miss of .3175 is closed), Exp 4 (.123 vs .150), Exps 5/6/7 within ~.02, Exps 10/11 (.414/.608 vs .418/.593), Exp 14 (.515 vs .468) and Exp 17 (.521 vs .493). The oddness-share redefinition (share = \u03a3 g_j o_j / \u03a3 o_j) clearly does the work the arbiter asked for: co-scandalous displays (Exps 8/9) stay one-reason, and the .55 bystander dilution kills the Exp-2 over-prediction. Faithfulness to the prescribed RELATIVE-SHARE GATING family is good 
inus the gate is a graded sigmoid on a share quantity, the one-reason limb is degraded by opposition only (not display length), and the compensatory limb is divisively normalised as specified. The residual misses are concentrated in the adjudication limb's *level*, not its logic: Exp 15 is .707 vs .862 (under by .155) and Exp 18's T
inus C is .174 vs .318 (under by .144), both of which pi_10 fits better (.809 / .355); Exp 13 is .457 vs .546 (under by .09). Simultaneously the model slightly OVER-shoots the near-degenerate one-reason designs (Exp 8 .823 vs .770, Exp 9 .828 vs .819) and UNDER-shoots two anti-validity/compensatory metrics (Exp 12 .182 vs .261, Exp 3 .243 vs .286). Read together, these say: the total amount of one-reason fidelity is roughly right, but it is distributed wrongly across opposition-coalition sizes (too steep a rho_opp discount, which is exactly what depresses the .55/.52-anchor follow rates in Exps 15/18 where the anchor faces 2
inus3 opposing rows), and the compensatory limb is a touch too deterministic.
Rationale: The candidate was ACCEPTED (loss 0.0672, new running best), so the base is safe 
inus but two experiments are still off by ~.15 in a systematic, diagnosable direction, and the fix is a pure in-family re-calibration, not a redesign. Keep the SSG architecture exactly as written (oddness-share gate, log-sigmoid scandal, opposition-only degradation, divisively normalised integration, degeneracy fallback) and adjust three knobs:

1. FLATTEN the opposition discount. rho_opp is currently [0.83, 0.93]; against the 2
inus3-row coalitions in Exps 15/16/18 this compounds to ~.7
inus.86 and is the direct cause of Exp 15 = .707 (real .862) and the deflated T-term of Exp 18. The arbiter's point 3 explicitly asks for a nearly FLAT one-reason limb; push rho_opp to ~[0.93, 0.99] (or replace the geometric power by a saturating discount such as rho_opp^sqrt(k_conf-1)). Because Exps 8/9 are currently over-predicted by ~.05, pay for the extra flatness with a small compensating rise in eps_t (e.g. [0.24, 0.32]) rather than by shrinking it 
inus that keeps the mean one-reason fidelity where it already fits and only re-shapes its dependence on coalition size. Net expected effect: Exp 15 up ~.10, Exp 18 T up, Exps 8/9 down ~.03, Exp 17 roughly unchanged (the .66 row is not scandalous so the gate stays shut).

2. Slightly widen the gate for lone near-chance anchors. Exp 13 (.457 vs .546) and the Exp-18 T-term both involve a single low-validity dissenter that humans follow more often than SSG does. Lower c_share to ~[0.64, 0.72] and/or raise gate_floor to ~[0.34, 0.50], leaving w_share as is. Do NOT touch the g-weighted share definition 
inus it is what buys Exp 2 and Exp 4, the two places pi_10 fails.

3. Soften the integration limb marginally. Exps 12 (.182 vs .261) and 3 (.243 vs .286) are both under-shot in the anti-validity direction, i.e. the compensatory choice is too deterministic. Raise sigma to ~[0.55, 0.75] or drop beta to ~[1.8, 2.3]; do not change gamma_w/lam, which are currently delivering Exps 10/11/14 almost exactly.

Avoid over-correcting Exp 18's C-term by weakening the mid-doubt lone dissenter: Exps 13/14 pin that quantity near .47
inus.55, so the T
inus C gap must be closed from the T side (flat opposition discount), not by suppressing C.

If these three adjustments do not improve aggregate loss, the fallback is to keep only adjustment (1) 
inus the opposition-flatness is the single best-supported deviation, being the only one that explains Exp 15, Exp 18-T and Exp 8/9 simultaneously.

**Outcome of this advice:** iter 1 candidate loss=0.0672 -> iter 2 candidate loss=0.0600 -> the gate marked it ACCEPTED.

### Iteration 2 (most recent — address this)
Verdict: regenerate
Interpretation: SSG-2 (iter 2) is the best member of the family so far and was ACCEPTED (0.0672 -> 0.0600). The sharpened oddness contrast did what it was advertised to do: Exp 15 rose .707 -> .750, Exp 18's T-C rose .174 -> .250, Exp 12 rose .182 -> .218, Exp 8 came down .823 -> .810, and Exps 1 (.279 vs .282), 4 (.125 vs .150), 5 (.753 vs .743), 6 (.493 vs .507), 10 (.415 vs .418), 11 (.612 vs .593) and 16 (.8225 vs .826) are essentially on target. Faithfulness to the arbiter's RELATIVE-SHARE GATING prescription is intact: graded sigmoid gate on an oddness share, opposition-only (near-flat) degradation of the one-reason limb, divisively normalised compensatory limb, degeneracy/tally fallback for exact repeats. No family drift.

The residuals are now small but structured, and they cluster in two places. (a) The .55 anchor still under-adjudicates: Exp 15 = .750 vs .862 (-.112). Note that in Exp 15 the anchor is almost always the lone dissenter (k_conf = 1), so rho_opp is inert there — the limiting quantity is P_trig = max_j g_j itself. With v_crit = .578 and w_h = .0125, g(.55) = sigmoid(.028/.0125) = .90, which hard-caps pi_one at .90 and therefore caps the predicted follow rate near .78-.80 even before any dilution. The .52 anchor designs (Exp 16 = .8225 vs .826) fit precisely because g(.52) ~ 1. So the miss is a *scandal-function calibration* miss at v = .55, not a share or opposition miss.

(b) The recency tilt of the integration limb has the wrong sign relative to the data for mid-doubt lone dissenters. Real: Exp 13 (early .68 dissenter) = .546 > Exp 17 (last-column .66 dissenter) = .493 ~ Exp 14 (.468). Model: Exp 13 = .453 < Exp 17 = .561 > Exp 14 = .536. The ordering is inverted, and the three errors (-.093, +.068, +.069) are all attributable to lam = .18-.26 over-weighting late columns. The same over-weighted late .68 row inflates Exp 18's C-term and thus keeps T-C at .250 instead of .318, and it pushes Exp 7 (.459 vs .438) and Exp 14 up. Fixing lam is therefore a single knob that pays off on four experiments at once.

(c) Minor: Exps 3 (.234 vs .286) and 12 (.218 vs .261) remain slightly too anti-validity-deterministic, and Exps 8/9 (+.040/+.013) are still a touch too last-row-deterministic among co-scandalous rows.
Rationale: The candidate was ACCEPTED, so keep it as the base; but three cheap, non-overlapping in-family recalibrations remain, and one of them (recency) is diagnosably mis-signed rather than merely mis-scaled. Keep predict/policy exactly as written (oddness-share gate, log-sigmoid scandal, opposition-only near-flat discount, divisive normalisation, degeneracy fallback) and move only parameter ranges:

1. NEW, highest-value knob — reduce the integration recency lam from [0.18, 0.26] to ~[0.10, 0.17]. Justification above: the model currently ranks late mid-doubt dissenters above early ones (Exp 17 .561 > Exp 13 .453) while humans do the opposite (.493 vs .546). Expected: Exp 13 up ~.05, Exp 17 down ~.05, Exp 14 down ~.04, Exp 7 down ~.02 toward .438, and Exp 18's C-term falls so T-C rises toward .29. Watch Exp 10 (.418) and Exp 11 (.593), which are recency-sensitive — if they degrade by more than ~.02, stop at lam ~ .17 rather than going lower. Do NOT compensate by changing gamma_w, which is currently delivering Exps 10/11/14.

2. Raise g(.55) toward 1 so the .55 anchor can actually adjudicate: tighten w_h from [0.010, 0.015] to ~[0.008, 0.011] and/or nudge v_crit from [0.572, 0.586] to ~[0.578, 0.588]. This lifts P_trig for Exp 15 from ~.90 to ~.96-.98 (Exp 15 -> ~.80) while *increasing* the dilution of the .60 bystander in Exp 2 (g(.60) .15 -> ~.18), which is welcome because Exp 2 now overshoots (+.029). Do not touch c_share/w_share/gate_floor — the g-weighted share definition and the floor are what buy Exps 2 and 4, and I do not want to relitigate the gate threshold after last round's gate_floor move already landed.

3. Small continuation of the (previously ACCEPTED) sigma direction: sigma [0.52, 0.70] -> ~[0.58, 0.78]. It moved Exp 12 .182 -> .218 and Exp 3 up last round; another modest step should close most of the remaining -.04/-.05 on Exps 12/3 and lift Exp 4 (.125 -> ~.14, real .150) while nudging Exp 5 down (.753 -> ~.748, real .743). Keep beta unchanged so the direction is unambiguous.

4. Optional, only if the above leave headroom: lower mu from [0.68, 0.92] to ~[0.52, 0.76] to trim the +.040 overshoot on Exp 8 and +.013 on Exp 9 — mu only arbitrates BETWEEN co-scandalous rows, so this cannot touch the single-anchor designs (Exps 13-18).

Explicitly do NOT touch rho_opp again. I pushed it flatter last round and it is now inert on the experiment it was supposed to fix (Exp 15 is k_conf = 1); further flattening would only perturb Exps 16/18 with no upside. Likewise do not attack Exp 18's gap from the C side by suppressing mid-doubt dissenters outright — Exps 13/14 pin that quantity at .47-.55; the gap must close via the lam fix (which lowers C for the *last-column* .68 row specifically) plus the Exp-15-style P_trig fix on the T side.

**Outcome of this advice:** iter 2 candidate loss=0.0600 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL — MINIMAL-DIFF EDIT (do NOT rewrite from scratch)
The RUNNING-BEST (last ACCEPTED) candidate is shown verbatim above under `## PREVIOUS CANDIDATE (this loop)`. This is the base the loop's accept gate is currently keeping; the most recent critic feedback (see `## PRIOR FEEDBACK ITERATIONS`) should be applied on top of it. Apply the SMALLEST edit that addresses the critic's diagnosis while staying inside the arbiter's prescribed mechanism family:
  - Re-emit the previous source verbatim, then change ONLY the lines needed to address the critic (a parameter range, a normalization, a softmax temperature, an attention scheme, a gating term, a buggy indexing line, etc.).
  - Keep all unaffected functions, equations, parameter names, and the overall mechanism intact.
  - Do NOT rewrite `predict` / `policy` end-to-end if a few lines would do, and do NOT switch mechanism families — that is the arbiter's decision, not yours in this loop.
  - Briefly explain the minimal edit in `rationale`.
If you genuinely believe a larger rewrite is required, you may do one, but justify in `rationale` why the minimal-diff path was insufficient.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- theory: The theoretical claim this theory makes about cognition.
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this theory design; used to explain why this theory is better then the previous ones.


## Response

```json
{
  "theory": "**SSG-3 — Salience-Share Gating with a sharpened scandal threshold and a weak integration recency.**\n\nThe architecture is identical to SSG-2; three quantitative commitments are sharpened and one is corrected in sign-strength.\n\n**(1) Two modes: adjudication vs. integration.** On every trial the subject either lets ONE expert adjudicate the choice or integrates all disagreeing rows. Mode is decided by a RELATIVE quantity — the share of the display's total *oddness* owned by genuinely near-chance experts — not by display length nor by an absolute knife edge.\n\n**(2) The scandal function is sharper and centred slightly higher.** Each discriminating row has oddness o_j = (1-v_j)^gamma_s (gamma_s ≈ 6.4-8.6, a contrast-enhanced, nearly ordinal 'who is the strangest expert here' read-out) and a scandal value g_j = sigmoid((v_crit - v_j)/w_h). **Sharpened claim: the boundary between 'ordinary mediocre expert' and 'coin-flipper speaking up' is crisper than previously assumed (w_h ≈ .008-.011, v_crit ≈ .576-.586).** The consequence is that a .55 expert is heard as fully scandalous (g ≈ .96-.99), not as a borderline case, so the .55-anchor designs adjudicate at essentially the same rate as the .52-anchor designs; meanwhile a .60 expert is still firmly non-scandalous (g ≈ .10-.15), so it dilutes the near-chance anchor's share of oddness without ever commanding the trial itself. The gate is share = Σ_j g_j·o_j / Σ_j o_j and pi_one = (max_j g_j)·[f + (1-f)·sigmoid((share - c)/w)]: adjudication requires BOTH that some expert be near-chance AND that near-chance experts own most of the display's oddness.\n\n**(3) The adjudicating row, and what degrades adjudication.** Among discriminating rows the consulted verdict is drawn from softmax(log g_j + mu·j): reading order only arbitrates BETWEEN co-scandalous rows and can never lift an ordinary expert over a near-chance one. **The positional tie-break among co-scandalous rows is moderate (mu ≈ .55-.80), not near-deterministic:** when three experts are all coin-flippers, the last-read one usually but not always wins. Adjudication is free in display length and is charged only by genuine OPPOSITION, and even that charge is near-flat (rho_opp ≈ .88-.96 per minority row beyond the first).\n\n**(4) Integration is mild in doubt and only WEAKLY recency-tilted.** When the gate is shut, evidence is integrated with w_j = (1-v_j)^gamma_w·exp(lam·j) with gamma_w ≈ 1.45 and **lam ≈ .10-.17 — appreciably weaker than the adjudication tie-break.** Position therefore biases integration only slightly: an early mid-doubt lone dissenter (.68 in column 0) is followed about as often as, indeed slightly more often than, a late one (.66-.68 in the last column), because its low validity, not its position, is what buys it weight. Evidence is divisively normalised to the loudest dissent, E = Σ sign_j·ŵ_j/(sigma + Σ ŵ_j) with a LARGE floor sigma ≈ .58-.78: integration is an effortful, noisy accumulation that never reaches a deterministic verdict, which keeps every compensatory metric off its ceiling and floor. It leaks with display load and with opposition. When all discriminating experts agree there is nothing to adjudicate (pi_one = 0). If two printed validities are indistinguishable (gap < .002) oddness has no referent and choice collapses to a graded unweighted row tally. No feedback is given, so the rule is stationary across the block.",
  "predict": "def predict(parameters, state, history):\n    # SSG: Salience-Share Gating\n    import numpy as np\n\n    # ---------- parse the (2, n_features) stimulus robustly ----------\n    a = None\n    b = None\n    if isinstance(state, dict):\n        if 'option_a_ratings' in state and 'option_b_ratings' in state:\n            a = np.asarray(state['option_a_ratings'], dtype=float).ravel()\n            b = np.asarray(state['option_b_ratings'], dtype=float).ravel()\n        else:\n            vals = list(state.values())\n            if len(vals) >= 2:\n                a = np.asarray(vals[0], dtype=float).ravel()\n                b = np.asarray(vals[1], dtype=float).ravel()\n    if a is None or b is None:\n        arr = np.asarray(state, dtype=float)\n        if arr.ndim == 2 and arr.shape[0] == 2:\n            a, b = arr[0].ravel(), arr[1].ravel()\n        elif arr.ndim == 2 and arr.shape[1] == 2:\n            a, b = arr[:, 0].ravel(), arr[:, 1].ravel()\n        elif arr.ndim == 1:\n            h = arr.shape[0] // 2\n            a, b = arr[:h], arr[h:2 * h]\n        else:\n            f = np.asarray(arr, dtype=float).reshape(2, -1)\n            a, b = f[0].ravel(), f[1].ravel()\n\n    n = int(min(np.size(a), np.size(b)))\n    if n == 0:\n        return np.array([0.5, 0.5])\n    a = np.asarray(a, dtype=float)[:n]\n    b = np.asarray(b, dtype=float)[:n]\n\n    # ---------- printed validities ----------\n    v_raw = parameters.get('validities', None) if hasattr(parameters, 'get') else None\n    if v_raw is None:\n        v = np.linspace(0.95, 0.55, n)\n    else:\n        v = np.asarray(v_raw, dtype=float).ravel()\n        if v.size < n:\n            v = np.concatenate([v, np.full(n - v.size, 0.55)])\n        v = v[:n]\n    v = np.clip(v, 0.5, 0.9995)\n\n    # ---------- parameters ----------\n    gamma_s = float(parameters['gamma_s'])\n    v_crit = float(parameters['v_crit'])\n    w_h = float(max(float(parameters['w_h']), 1e-4))\n    c_share = float(parameters['c_share'])\n    w_share = float(max(float(parameters['w_share']), 1e-4))\n    floor = float(np.clip(float(parameters['gate_floor']), 0.0, 1.0))\n    mu = float(parameters['mu'])\n    eps_t = float(np.clip(float(parameters['eps_t']), 0.0, 1.0))\n    rho_opp = float(np.clip(float(parameters['rho_opp']), 1e-6, 1.0))\n    gamma_w = float(parameters['gamma_w'])\n    lam = float(parameters['lam'])\n    sigma = float(max(float(parameters['sigma']), 1e-6))\n    beta = float(parameters['beta'])\n    eps0 = float(np.clip(float(parameters['eps0']), 0.0, 1.0))\n    rho_m = float(np.clip(float(parameters['rho_m']), 1e-6, 1.0))\n    rho_c = float(np.clip(float(parameters['rho_c']), 1e-6, 1.0))\n    kappa = float(parameters['tally_kappa'])\n\n    def sig(x):\n        x = float(np.clip(x, -60.0, 60.0))\n        return 1.0 / (1.0 + np.exp(-x))\n\n    # ---------- discriminating rows ----------\n    diff = a - b\n    disc = np.nonzero(diff != 0.0)[0]\n    m = int(disc.size)\n    if m == 0:\n        return np.array([0.5, 0.5])\n    signs = np.sign(diff[disc])\n    n_a = float(np.sum(signs > 0.0))\n    n_b = float(m) - n_a\n    k_conf = int(min(n_a, n_b))\n\n    # ---------- leak on the integration limb ----------\n    keep_c = (1.0 - eps0) * (rho_m ** max(m - 2, 0)) * (rho_c ** k_conf)\n    keep_c = float(min(max(keep_c, 0.0), 1.0))\n\n    # ---------- label-degeneracy gate ----------\n    degenerate = False\n    if n > 1:\n        vs = np.sort(v)\n        if bool(np.any(np.diff(vs) < 2.0e-3)):\n            degenerate = True\n\n    if degenerate:\n        p_core = sig(kappa * (n_a - n_b))\n        p_a = 0.5 + keep_c * (p_core - 0.5)\n        p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))\n        p = np.array([p_a, 1.0 - p_a], dtype=float)\n        return p / p.sum()\n\n    vd = v[disc]\n    jd = disc.astype(float)\n\n    # ---------- scandal values and sharpened oddness ----------\n    zz = np.clip((v_crit - vd) / w_h, -60.0, 60.0)\n    g = 1.0 / (1.0 + np.exp(-zz))                       # near-chance \"scandal\" weight\n    log_g = -np.logaddexp(0.0, -zz)                     # stable log sigmoid\n    log_o = gamma_s * np.log(np.clip(1.0 - vd, 1e-12, None))\n    log_o_shift = log_o - np.max(log_o)\n    o = np.exp(np.clip(log_o_shift, -700.0, 0.0))\n    o_sum = float(np.sum(o))\n    if (not np.isfinite(o_sum)) or o_sum <= 0.0:\n        o = np.ones(m, dtype=float)\n        o_sum = float(m)\n\n    share = float(np.sum(g * o) / o_sum)\n    g_share = sig((share - c_share) / w_share)\n    P_trig = float(np.clip(np.max(g), 0.0, 1.0))\n\n    # unanimous displays need no adjudication\n    if k_conf == 0:\n        pi_one = 0.0\n    else:\n        pi_one = P_trig * (floor + (1.0 - floor) * g_share)\n    pi_one = float(np.clip(pi_one, 0.0, 1.0))\n\n    # ---------- which row adjudicates (recency only breaks scandal ties) ----------\n    sc = log_g + mu * jd\n    sc = sc - np.max(sc)\n    ww = np.exp(np.clip(sc, -700.0, 0.0))\n    ws = float(np.sum(ww))\n    if (not np.isfinite(ws)) or ws <= 0.0:\n        ww = np.full(m, 1.0 / m)\n    else:\n        ww = ww / ws\n    p_or_a = float(np.sum(ww[signs > 0.0]))\n    fid = (1.0 - eps_t) * (rho_opp ** max(k_conf - 1, 0))\n    fid = float(min(max(fid, 0.0), 1.0))\n    p_one_a = 0.5 + fid * (p_or_a - 0.5)\n\n    # ---------- integration limb ----------\n    logw = gamma_w * np.log(np.clip(1.0 - vd, 1e-12, None)) + lam * jd\n    logw = logw - np.max(logw)\n    wi = np.exp(np.clip(logw, -700.0, 0.0))\n    wsum = float(np.sum(wi))\n    if (not np.isfinite(wsum)) or wsum <= 0.0:\n        wi = np.ones(m, dtype=float)\n        wsum = float(m)\n    E = float(np.sum(signs * wi)) / (sigma + wsum)\n    p_comp = sig(beta * E)\n    p_c_a = 0.5 + keep_c * (p_comp - 0.5)\n\n    # ---------- mixture ----------\n    p_a = pi_one * p_one_a + (1.0 - pi_one) * p_c_a\n    p_a = float(min(max(p_a, 1e-9), 1.0 - 1e-9))\n    p = np.array([p_a, 1.0 - p_a], dtype=float)\n    return p / p.sum()",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    s = probs.sum()\n    if not np.isfinite(s) or s <= 0.0:\n        return int(np.random.randint(len(probs)))\n    probs = probs / s\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "gamma_s": "[6.4, 8.6]",
    "v_crit": "[0.576, 0.586]",
    "w_h": "[0.008, 0.011]",
    "c_share": "[0.69, 0.75]",
    "w_share": "[0.040, 0.065]",
    "gate_floor": "[0.33, 0.47]",
    "mu": "[0.55, 0.80]",
    "eps_t": "[0.23, 0.33]",
    "rho_opp": "[0.88, 0.96]",
    "gamma_w": "[1.32, 1.58]",
    "lam": "[0.10, 0.17]",
    "sigma": "[0.58, 0.78]",
    "beta": "[2.15, 2.65]",
    "eps0": "[0.22, 0.30]",
    "rho_m": "[0.87, 0.93]",
    "rho_c": "[0.73, 0.83]",
    "tally_kappa": "[0.7, 1.3]",
    "validities": "validities"
  },
  "rationale": "MINIMAL DIFF: `predict` and `policy` are re-emitted byte-for-byte; only five parameter RANGES move, exactly the four the critic prioritised (lam, w_h, v_crit, sigma) plus the optional mu trim. No mechanism, equation or name changes; the g-weighted oddness-share gate, c_share/w_share/gate_floor, rho_opp, gamma_w, beta, eps_t and the degeneracy fallback are untouched as instructed.\n\nEdit 1 (highest value) — lam [0.18, 0.26] -> [0.10, 0.17]. The critic's sign diagnosis is verifiable in the code: in the integration limb the late-column exponential currently dominates the shallow gamma_w = 1.45 doubt term (exp(.22*5) = 3.0 versus an oddness ratio of only ~2 between a .68 and a .93 row), so a last-column mid-doubt dissenter outweighs an early one. That inverts the human ordering Exp 13 (.546, early .68) > Exp 17 (.493, last-column .66) ~ Exp 14 (.468), which the model currently renders as .453 < .561 > .536. Halving lam brings exp(lam*5) from 3.0 down to ~1.9, so position becomes a tilt rather than the dominant term: Exp 13 up ~.05, Exps 17/14 down ~.05/.04, Exp 7 down ~.02 toward .438, and — critically — Exp 18's C-term (a lone LAST-column .68 dissenter) falls, lifting T-C from .250 toward ~.29 without touching the T-side. I stopped at .17 at the top of the range rather than going lower precisely because Exps 10 (.415 vs .418) and 11 (.612 vs .593) are recency-sensitive and currently on target; the interval still contains values close to the old lower edge so the sampler can protect them.\n\nEdit 2 — w_h [0.010, 0.015] -> [0.008, 0.011] and v_crit [0.572, 0.586] -> [0.576, 0.586]. This is the Exp-15 fix, and the diagnosis is arithmetic, not hand-waving: pi_one is hard-capped by P_trig = max_j g_j, and at v_crit = .578, w_h = .0125 we have g(.55) = sigmoid(2.24) = .90, capping the predicted anchor-follow rate near .78-.80 while the data say .862. With v_crit ~ .581, w_h ~ .0095, g(.55) = sigmoid(3.3) = .96-.98, lifting Exp 15 to ~.82-.83, while g(.52) stays ~1 so Exp 16 (.8225 vs .826) is unchanged. The same tightening makes the non-scandalous side crisper: g(.60) in Exp 2 stays ~.13-.18, so the .55 row's dilution by the .60 bystander is preserved or slightly strengthened — welcome, since Exp 2 now overshoots by +.029. I deliberately raised v_crit less than the critic suggested (.586 top rather than .588) to keep g(.58) from creeping toward scandal status in Exps 3/4, which are already slightly over-anti-validity.\n\nEdit 3 — sigma [0.52, 0.70] -> [0.58, 0.78]. A continuation of the previously ACCEPTED direction: softening only the divisive floor (beta, gamma_w, lam-shape untouched) pulls the over-deterministic compensatory metrics toward the data — Exp 12 .218 -> ~.245 (real .261), Exp 3 .234 -> ~.255 (.286), Exp 4 .125 -> ~.14 (.150) — while nudging Exp 5 .753 -> ~.748 (.743). Because it is a pure scale on the evidence ratio it cannot re-order any experiment, so the risk is bounded.\n\nEdit 4 — mu [0.68, 0.92] -> [0.55, 0.80]. mu arbitrates ONLY between co-scandalous rows, so this is inert on every single-anchor design (Exps 11, 13-18) and acts exclusively on the .535/.540/.545 and .538/.542/.546 families, trimming the remaining +.040 on Exp 8 and +.013 on Exp 9 by letting the softmax spread a little over the three coin-flippers instead of near-argmaxing the last one.\n\nI explicitly did NOT touch rho_opp (inert on Exp 15, where k_conf = 1), c_share/w_share/gate_floor (they buy Exps 2 and 4), or gamma_w (it delivers Exps 10/11/14), per the critic's standing constraints. Expected net: Exp 15 +.07, Exp 13 +.05, Exp 18 +.04, Exp 12 +.03, Exp 3 +.02, Exps 8/17/14/7/2 each -.02 to -.05 error, for a clear reduction in summed squared residual below the 0.0600 floor."
}
```

## Usage

```json
{
  "input_tokens": 63048,
  "output_tokens": 9145
}
```
