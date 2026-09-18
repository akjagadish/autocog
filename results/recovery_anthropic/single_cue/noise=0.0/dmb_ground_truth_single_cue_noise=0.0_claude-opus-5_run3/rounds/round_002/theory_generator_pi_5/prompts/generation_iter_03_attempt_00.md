# generation_iter_03_attempt_00

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
- THEORY 1 = `pi_4`
- THEORY 2 = `pi_3`
- The recommendation below acts on THEORY 1 (= `pi_4`).

Replace THEORY 1 with an 'anchored compensatory integration' theory that fuses the surviving parts of both incumbents and, critically, is calibrated to produce intermediate rates rather than ceiling/floor:

1. Cue weights are the PRODUCT of a validity term and an attention term: w_j ∝ (v_j - 0.5)^rho * a_j, with rho near 1 (mild compression/expansion allowed, ~0.8-1.4) so that a crowd of 3 mid cues can out-weigh a single .95 cue (needed for E4's .775 and E3's small positive contrast).
2. Attention term a_j = 1 + alpha * exp(-lambda * position_j) (or simply a boost on the first one or two screen positions), with alpha of moderate size (~0.5-1.5) and lambda ~0.5-1.5. This first-cue anchor must be strong enough to flip validity ties (E1's .82 toward the pos-0 side, E2's .84 toward the pos-0/pos-5 side) but NOT strong enough to override a large validity difference (E5/E6 must stay near .5). A small optional recency term is permissible but must be unimodal jitter, not a 35% discrete recency subpopulation — the low between-subject variance in E5/E6 (.0075-.023) rules out bimodality.
3. Evidence is summed over ALL cues and is NOT normalised by the discriminating weight: E = sum_j w_j (a_j - b_j). Choice = softmax(beta * E) with a lapse epsilon. Because E is unnormalised, cells where the top cue is nearly balanced against a two-cue crowd land near chance (E5 .52, E6 .51) while cells with a real margin land at .75-.90 (E2, E4) — this is the key property both incumbents got wrong in opposite directions.
4. No early stopping / no threshold rule, and no conclusion-graded commitment: the refuted prediction (unresolved trials tilt toward the OPPOSITE option) must be dropped. Confidence is purely margin-graded.
5. Parameter ranges should be chosen so that simulated metric values fall in the .55-.90 band for E1/E2, .45-.60 for E5/E6, .70-.85 for E4 and .03-.15 for E3 — i.e. the model should never predict values above ~.95 or below ~.10 on these designs.

This theory is a direct competitor to pi_3: it keeps a position effect but makes it a graded weight modifier on top of validity rather than the sole driver, and it removes the normalisation that forces pi_3 to ceiling everywhere.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_4` (overall score: 0.288)

**Description**
**Threshold-terminated compensatory integration with CONCLUSION-GRADED commitment.**

People treat expert ratings as evidence to be added up, not as a lexicographic hierarchy. Five claims:

1. **Cue weights depend ONLY on the communicated validity, never on where the rating sits on the screen.** The weight of expert j is a compressed, monotone function of its stated validity, w_j ∝ (v_j − 0.5)^rho, normalised to sum to 1. Compression (rho ≈ 1.25–1.45) lets a crowd of medium-validity experts out-vote or tie a single .95 expert.

2. **Integration is compensatory and additive, carried out incrementally in the order the ratings are displayed, and it can terminate early.** After each rating that actually discriminates, the decision maker performs a *best-case reversal check*: "could any single expert I have not yet read still overturn what I now believe?" The sufficiency bar is theta_k = phi · max_{j after the current screen position} w_j, and the probability of stopping is sigmoid(s·(|E_k|/theta_k − 1)). With phi ≈ 1 this is the rational rule "stop when no single remaining expert can reverse my lead". Nothing is discounted by position; position matters *only* through this truncation.

3. **NEW — confidence is conclusion-graded, not merely margin-graded.** Two psychologically distinct states can end a trial. (a) The reversal check *passes*: the person has reached a categorical conclusion ("nothing still unread can overturn this"), and choice is committed sharply — softmax on the raw margin with an amplified sharpness beta·kappa (kappa > 1). Crucially, *which* cue triggered the stop is then almost irrelevant: a mid-validity cue that has already cleared the sufficiency bar is followed about as decisively as the top cue is. (b) The list is *exhausted* without the check ever passing: the person never reached a conclusion and is left holding a raw, ungrounded residual margin; choice is then a shallow softmax on that margin with the ordinary beta, so unresolved trials sit close to chance and are only weakly tilted by the residual. Two trials with identical final margins therefore differ in decisiveness depending on whether the stopping criterion was ever met — the theory's sharpest new prediction.

4. **No renormalisation, no side bias, plus a lapse.** Evidence is never divided by the total discriminating weight (that would make one-cue and many-cue decisions equally confident); a lapse epsilon mixes in a uniform guess.

5. **Individual differences are unimodal jitter** in compression (rho), conservatism (phi), stopping sharpness (s), commitment amplification (kappa), residual sensitivity (beta) and lapse — no discrete strategy types, no primacy/recency "reader types".

Signature predictions: in a validity-sorted display the leading cue clears the bar immediately, search stops, and behaviour looks like Take-The-Best in BOTH conflict and agreement cells — and because stopping commitment is amplified, cells whose first cues tie and which stop on a *middle* cue are followed just as decisively, so the TTB-vs-tally contrast collapses to ≈0 instead of going negative. When the best expert is listed last, the bar stays high until a mid-validity crowd piles past it, search stops before the best expert is read, and behaviour looks like tallying. When a strong cue sits mid-list with another strong cue still unread, the check fails, integration runs to the end, and the shallow residual softmax leaves the choice near chance.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    # ------------------------------------------------------------------
    # 1. parse the trial stimulus into two rating vectors (screen order)
    # ------------------------------------------------------------------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(list(state['option_a_ratings']), dtype=float)
            b = np.asarray(list(state['option_b_ratings']), dtype=float)
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            arr = arr.reshape(2, -1)
        elif arr.ndim > 2:
            arr = arr.reshape(2, -1)
        if arr.shape[0] != 2:
            arr = arr.reshape(2, -1)
        a = arr[0].astype(float)
        b = arr[1].astype(float)

    a = np.ravel(a).astype(float)
    b = np.ravel(b).astype(float)
    n = int(min(a.shape[0], b.shape[0]))
    if n == 0:
        return np.array([0.5, 0.5])
    a = a[:n]
    b = b[:n]
    d = a - b

    # ------------------------------------------------------------------
    # 2. validity-only cue weights, compressed toward equality
    # ------------------------------------------------------------------
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        # fall back: assume display is validity-sorted, descending
        val = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.90])
    val = np.clip(val, 0.5 + 1e-6, 1.0)

    rho = float(parameters.get('rho', 1.35))
    rho = float(np.clip(rho, 0.1, 5.0))
    raw = np.clip(val - 0.5, 1e-9, None) ** rho
    tot = float(np.sum(raw))
    if not np.isfinite(tot) or tot <= 0:
        w = np.ones(n, dtype=float) / n
    else:
        w = raw / tot                      # weights sum to 1, position-free

    phi = float(np.clip(parameters.get('phi', 1.05), 0.05, 3.0))
    s = float(np.clip(parameters.get('s', 20.0), 0.1, 200.0))
    beta = float(np.clip(parameters.get('beta', 7.5), 0.0, 200.0))
    kappa = float(np.clip(parameters.get('kappa', 4.0), 1.0, 20.0))
    eps = float(np.clip(parameters.get('epsilon', 0.0), 0.0, 1.0))

    # ------------------------------------------------------------------
    # 3. incremental integration in screen order with graded stopping
    #    sufficiency bar = phi * (largest weight among cues NOT YET READ)
    #    i.e. "can any single remaining expert still overturn my lead?"
    #    Commitment is CONCLUSION-GRADED: a stop that passes the check is
    #    read out with sharpness beta*kappa; an exhausted list (no
    #    conclusion ever reached) is read out with the shallow beta.
    # ------------------------------------------------------------------
    disc = np.nonzero(np.abs(d) > 1e-12)[0]     # discriminating cues, in order
    if disc.size == 0:
        return np.array([0.5, 0.5])

    steps = w[disc] * np.sign(d[disc])
    cum = np.cumsum(steps)                      # margin after each new reason
    m = cum.shape[0]

    def _sig(x):
        return 1.0 / (1.0 + np.exp(-np.clip(x, -60.0, 60.0)))

    p_a = 0.0
    remain = 1.0
    for k in range(m):
        E = float(cum[k])
        if k < m - 1:
            idx = int(disc[k])
            if idx + 1 < n:
                suffix_max = float(np.max(w[idx + 1:]))
            else:
                suffix_max = 0.0
            theta_k = max(phi * suffix_max, 1e-12)
            q = _sig(s * (abs(E) / theta_k - 1.0))   # graded termination
            p_choice = _sig(beta * kappa * E)        # committed conclusion
        else:
            q = 1.0                                  # nothing left to read
            p_choice = _sig(beta * E)                # unresolved residual
        p_a += remain * q * p_choice
        remain *= (1.0 - q)
        if remain <= 1e-12:
            break
    if remain > 1e-12:                           # numerical remainder
        p_a += remain * _sig(beta * float(cum[-1]))

    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = (1.0 - eps) * p + eps * 0.5              # lapse, no side bias
    p = np.clip(p, 1e-12, None)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- rho: [1.25, 1.45]
- phi: [1.00, 1.12]
- s: [12.0, 30.0]
- beta: [5.0, 10.0]
- kappa: [3.0, 5.0]
- epsilon: [0.0, 0.06]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.0933 (var=0.0064) vs this=-0.0050 (var=0.0008)
- Experiment 2: real=0.7750 (var=0.0072) vs this=0.7860 (var=0.0029)
- Experiment 3: real=0.5175 (var=0.0233) vs this=0.5200 (var=0.0187)
- Experiment 4: real=0.5075 (var=0.0075) vs this=0.4906 (var=0.0065)
- Experiment 5: real=0.8200 (var=0.0126) vs this=0.3500 (var=0.0175)
- Experiment 6: real=0.8413 (var=0.0134) vs this=0.3312 (var=0.0055)


---

### `pi_3` (overall score: 0.164)

**Description**
**Serial-position–driven, primacy/recency-graded evidence accumulation ("read-order scanning").**

People do not re-sort the expert ratings by the stated validities before deciding. They inspect the ratings in the order in which they appear on the screen (reading order) and their attention decays sharply across that inspection sequence, so the evidence carried by a cue is discounted geometrically by its *serial position*, not by its validity. Stated validities exert only a weak, partial pull on the inspection order (parameter gamma, small).

Two further claims:

1. **The gradient is steep but graded.** Weights fall off as w_j = exp(-lambda * rank_j) with |lambda| well above zero, so decisions are usually driven by the first cue(s) that discriminate — near-lexicographic but not strictly all-or-none: when the leading cues tie, the next-inspected cues take over, and when several later cues line up they can occasionally overturn a leading cue if the gradient is shallow.

2. **The gradient has a sign: most readers are primacy-oriented, a substantial minority are recency-oriented.** Reading a short list produces either an anchoring-on-the-first-item strategy (primacy, lambda > 0) or a last-impression-counts strategy (recency, lambda < 0). The population is bimodal: about one third of subjects anchor on the *last-read* cue. Near-zero gradients (i.e., genuine equal-weight tallying) are essentially absent — people do not integrate all six/five cues equally.

Evidence is evaluated *relatively*: the signed weighted difference is normalised by the total weight of the cues that actually discriminate, so a decision based on one early cue is as confident as a decision based on many, and only genuinely near-balanced weighted evidence produces hesitation. Choice is a softmax on this relative evidence with inverse temperature beta, plus a lapse epsilon.

Because validity order and screen order coincide in a validity-sorted display but dissociate in a scrambled display, this theory predicts TTB-looking behaviour in the former and tally-looking behaviour in the latter — without either heuristic being the actual mechanism. The causal driver is *where the cue sits on the screen*.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    # ---- unpack the trial stimulus -> (2, n_features) ------------------
    if isinstance(state, dict):
        a = np.asarray(list(state.get('option_a_ratings', [])), dtype=float)
        b = np.asarray(list(state.get('option_b_ratings', [])), dtype=float)
        stim = np.vstack([a, b])
    else:
        stim = np.asarray(state, dtype=float)
        if stim.ndim == 1:
            stim = stim.reshape(2, -1)
        elif stim.ndim > 2:
            stim = stim.reshape(2, -1)
    if stim.shape[0] != 2:
        stim = stim.reshape(2, -1)

    a = stim[0].astype(float)
    b = stim[1].astype(float)
    n = a.shape[0]
    d = a - b

    # ---- inspection ranks: screen position, weakly pulled by validity --
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        # fallback: assume the display is already validity-sorted
        val = np.linspace(0.95, 0.55, n)

    order = np.argsort(-val, kind='stable')       # 0 = highest validity
    vrank = np.empty(n, dtype=float)
    vrank[order] = np.arange(n, dtype=float)
    pos = np.arange(n, dtype=float)               # reading-order index

    gamma = float(parameters.get('gamma', 0.0))
    gamma = min(max(gamma, 0.0), 1.0)
    rank = gamma * vrank + (1.0 - gamma) * pos

    # ---- signed attention gradient (primacy vs recency reader) --------
    lam_mag = float(parameters.get('lam', 2.0))
    orient = float(parameters.get('scan_orientation', 1.0))
    RECENCY_SHARE = 0.35                          # population constant
    lam = -lam_mag if orient < RECENCY_SHARE else lam_mag

    z = -lam * (rank - float(np.mean(rank)))      # centered for stability
    z = z - float(np.max(z))
    w = np.exp(z)

    # ---- relative (normalised) weighted evidence ----------------------
    num = float(np.sum(w * d))
    den = float(np.sum(w * np.abs(d)))
    if den <= 1e-12:
        S = 0.0                                   # nothing discriminates
    else:
        S = num / den                             # in [-1, 1]

    beta = float(parameters.get('beta', 6.0))
    eps = float(parameters.get('epsilon', 0.0))
    eps = min(max(eps, 0.0), 1.0)

    logits = np.array([beta * S, 0.0], dtype=float)
    logits = logits - np.max(logits)
    e = np.exp(logits)
    p = e / np.sum(e)

    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, 1.0)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- lam: [1.2, 3.5]
- gamma: [0.0, 0.25]
- beta: [4.0, 12.0]
- epsilon: [0.0, 0.10]
- scan_orientation: [0, 1]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.0933 (var=0.0064) vs this=0.1027 (var=0.0215)
- Experiment 2: real=0.7750 (var=0.0072) vs this=0.7780 (var=0.0646)
- Experiment 3: real=0.5175 (var=0.0233) vs this=0.0375 (var=0.0022)
- Experiment 4: real=0.5075 (var=0.0075) vs this=0.0269 (var=0.0009)
- Experiment 5: real=0.8200 (var=0.0126) vs this=0.9513 (var=0.0036)
- Experiment 6: real=0.8413 (var=0.0134) vs this=0.9694 (var=0.0014)


---

### `pi_2` (overall score: 0.051)

**Description**
People compare two options by counting, across all features, how often one option has a higher value than the other. The option that wins on more features is chosen. Tallying discards cardinal magnitudes — only the sign of each feature-wise comparison matters — so the heuristic is robust to monotone rescaling of individual features and cannot be swayed by a single large feature difference in the way Equal-Weight can. Ties on an individual feature contribute nothing to either count: that cue is simply treated as uninformative for the pair. No feature is privileged, in contrast to Take The Best; every cue contributes equally to the tally. When the two counts are equal the heuristic has no basis for preference and the learner must guess. Response noise enters through a softmax over the two tallies with inverse temperature beta (interpolating between fully deterministic choice at large beta and uniform guessing at beta = 0), plus an independent lapse that with probability epsilon replaces the softmax output with a uniform pick over the two options.


`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    # Paper-faithful Tallying heuristic (Dawes 1979; Gigerenzer &
    # Goldstein 1999). Stimulus is the pair of option feature vectors
    # for the current trial: array-like of shape (2, n_features),
    # with row 0 = option A, row 1 = option B. History is ignored.
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"Tallying expects a (2, n_features) stimulus; got shape {stim.shape}."
        )

    a, b = stim[0], stim[1]
    # Count strict feature-wise wins; ties contribute to neither option.
    a_wins = float(np.sum(a > b))
    b_wins = float(np.sum(b > a))
    scores = np.array([a_wins, b_wins])

    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])

    # Softmax with max-subtraction for numerical stability. When
    # a_wins == b_wins the softmax is exactly uniform regardless of
    # beta, which is the correct behavior for an undiscriminating
    # tally.
    z = beta * (scores - scores.max())
    e = np.exp(z)
    p_core = e / e.sum()

    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)


`policy(probs) -> int`:
def policy(probabilities):
    probabilities = probabilities / probabilities.sum()  # Ensure valid probabilities.
    return np.random.choice(len(probabilities), p=probabilities)


`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=0.0933 (var=0.0064) vs this=-0.6931 (var=0.0366)
- Experiment 2: real=0.7750 (var=0.0072) vs this=0.8660 (var=0.0083)
- Experiment 3: real=0.5175 (var=0.0233) vs this=0.1400 (var=0.0151)
- Experiment 4: real=0.5075 (var=0.0075) vs this=0.1450 (var=0.0133)
- Experiment 5: real=0.8200 (var=0.0126) vs this=0.4850 (var=0.0117)
- Experiment 6: real=0.8413 (var=0.0134) vs this=0.8825 (var=0.0110)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.2158 -> ACCEPTED
- iter 2: loss=0.2242 -> REJECTED
- iter 3: loss=0.2310 -> REJECTED
Running-best (last ACCEPTED) base: iter 1 at loss=0.2158 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    dis_hits = 0.0
    dis_n = 0.0
    agr_hits = 0.0
    agr_n = 0.0

    for a_raw, b_raw, resp in zip(data['option_a_ratings'],
                                  data['option_b_ratings'],
                                  data['response']):
        a = np.asarray(a_raw, dtype=float)
        b = np.asarray(b_raw, dtype=float)
        if a.shape != b.shape or a.size == 0:
            continue

        # Take-The-Best winner: features are listed in descending validity
        # order, so scan left to right for the first discriminating cue.
        ttb_winner = None
        for j in range(a.size):
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins == b_wins:
            continue  # tally-tie pairs excluded (uninformative for the contrast)
        tally_winner = 0 if a_wins > b_wins else 1

        try:
            r = int(resp)
        except (TypeError, ValueError):
            continue
        hit = 1.0 if r == ttb_winner else 0.0

        if tally_winner != ttb_winner:
            dis_hits += hit
            dis_n += 1.0
        else:
            agr_hits += hit
            agr_n += 1.0

    if dis_n == 0.0 or agr_n == 0.0:
        return float('nan')

    return float(dis_hits / dis_n - agr_hits / agr_n)
```

**Observed (real) value:** 0.0933 (var=0.0064)
**Previous candidate values (this loop):**
  - iter 1: -0.1600 (var=0.0029) (Δ vs real -0.2533)
  - iter 2: -0.1606 (var=0.0029) (Δ vs real -0.2540)
  - iter 3 (most recent): -0.0910 (var=0.0023) (Δ vs real -0.1844)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0038 (var=0.0080)
- pi_2: -0.6931 (var=0.0366)
- pi_3: 0.1027 (var=0.0215)
- pi_4: -0.0050 (var=0.0008)

### Experiment 2
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    validities = np.array([0.9, 0.6, 0.8, 0.55, 0.7, 0.95], dtype=float)

    n_match = 0.0
    n_total = 0.0

    for _, row in data.iterrows():
        a = np.asarray(list(row['option_a_ratings']), dtype=float)
        b = np.asarray(list(row['option_b_ratings']), dtype=float)
        n = a.shape[0]
        if validities.shape[0] == n:
            val = validities
        else:
            # fallback: assume given order is already descending validity
            val = np.arange(n, 0, -1, dtype=float)
        order = np.argsort(-val, kind='stable')

        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins == b_wins:
            continue
        tally_winner = 0 if a_wins > b_wins else 1
        margin = abs(a_wins - b_wins)
        if margin < 2:
            continue

        ttb_winner = None
        for j in order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue
        if ttb_winner == tally_winner:
            continue  # only conflict trials

        try:
            resp = int(row['response'])
        except (TypeError, ValueError):
            continue
        n_total += 1.0
        if resp == tally_winner:
            n_match += 1.0

    if n_total == 0:
        return float('nan')
    return float(n_match / n_total)
```

**Observed (real) value:** 0.7750 (var=0.0072)
**Previous candidate values (this loop):**
  - iter 1: 0.7220 (var=0.0034) (Δ vs real -0.0530)
  - iter 2: 0.6960 (var=0.0040) (Δ vs real -0.0790)
  - iter 3 (most recent): 0.6655 (var=0.0050) (Δ vs real -0.1095)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8660 (var=0.0083)
- pi_1: 0.1530 (var=0.0129)
- pi_3: 0.7780 (var=0.0646)
- pi_4: 0.7860 (var=0.0029)

### Experiment 3
**Design**
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Rate of choosing the option favoured by the HIGHEST-VALIDITY cue (screen
    # position 3, validity .95) on the 'double-dissociation' pairs, i.e. trials
    # where the two screen-extreme cues (positions 0 and 5) jointly favour one
    # option while the middle top-validity cue favours the other.
    num = 0.0
    den = 0.0
    num_all = 0.0
    den_all = 0.0
    a_col = data['option_a_ratings'].tolist()
    b_col = data['option_b_ratings'].tolist()
    r_col = data['response'].tolist()
    for a_raw, b_raw, r in zip(a_col, b_col, r_col):
        try:
            a = np.asarray(list(a_raw), dtype=float)
            b = np.asarray(list(b_raw), dtype=float)
        except Exception:
            continue
        if a.shape[0] < 6 or b.shape[0] < 6:
            continue
        d3 = a[3] - b[3]
        if d3 == 0:
            continue
        top_side = 0 if d3 > 0 else 1
        try:
            resp = int(r)
        except Exception:
            continue
        chose_top = 1.0 if resp == top_side else 0.0
        num_all += chose_top
        den_all += 1.0
        d0 = a[0] - b[0]
        d5 = a[5] - b[5]
        if d0 != 0 and d5 != 0:
            s0 = 1.0 if d0 > 0 else -1.0
            s5 = 1.0 if d5 > 0 else -1.0
            s3 = 1.0 if d3 > 0 else -1.0
            if s0 == s5 and s0 == -s3:
                num += chose_top
                den += 1.0
    if den > 0:
        return float(num / den)
    if den_all > 0:
        return float(num_all / den_all)
    return float('nan')
```

**Observed (real) value:** 0.5175 (var=0.0233)
**Previous candidate values (this loop):**
  - iter 1: 0.6475 (var=0.0197) (Δ vs real +0.1300)
  - iter 2: 0.4075 (var=0.0249) (Δ vs real -0.1100)
  - iter 3 (most recent): 0.4938 (var=0.0221) (Δ vs real -0.0237)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8562 (var=0.0143)
- pi_3: 0.0375 (var=0.0022)
- pi_2: 0.1400 (var=0.0151)
- pi_4: 0.5200 (var=0.0187)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0]  B=[0, 0, 0, 0, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    VAL = np.array([0.78, 0.60, 0.95, 0.88, 0.72], dtype=float)

    def ttb_winner(a, b, val):
        order = np.argsort(-val, kind='stable')
        for j in order:
            if a[j] > b[j]:
                return 0
            if b[j] > a[j]:
                return 1
        return None

    def scan_sign(d, lam):
        n = d.shape[0]
        pos = np.arange(n, dtype=float)
        z = -lam * (pos - pos.mean())
        z = z - z.max()
        w = np.exp(z)
        num = float(np.sum(w * d))
        den = float(np.sum(w * np.abs(d)))
        if den <= 1e-12:
            return 0.0
        return num / den

    hits = []
    for _, row in data.iterrows():
        try:
            a = np.asarray(list(row['option_a_ratings']), dtype=float)
            b = np.asarray(list(row['option_b_ratings']), dtype=float)
        except Exception:
            continue
        n = a.shape[0]
        if b.shape[0] != n or n == 0:
            continue
        val = VAL if n == VAL.shape[0] else np.linspace(0.95, 0.55, n)
        w_ttb = ttb_winner(a, b, val)
        if w_ttb is None:
            continue
        d = a - b
        s_prim = scan_sign(d, 2.0)    # primacy reader (lambda > 0)
        s_rec = scan_sign(d, -2.0)    # recency reader (lambda < 0)
        if abs(s_prim) < 0.15 or abs(s_rec) < 0.15:
            continue
        # scanner choice: S > 0 -> A (0), S < 0 -> B (1)
        c_prim = 0 if s_prim > 0 else 1
        c_rec = 0 if s_rec > 0 else 1
        # keep only cells where BOTH scanning orientations oppose TTB
        if c_prim == c_rec and c_prim != w_ttb:
            try:
                r = int(row['response'])
            except Exception:
                continue
            hits.append(1.0 if r == w_ttb else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))

```

**Observed (real) value:** 0.5075 (var=0.0075)
**Previous candidate values (this loop):**
  - iter 1: 0.4619 (var=0.0075) (Δ vs real -0.0456)
  - iter 2: 0.4225 (var=0.0108) (Δ vs real -0.0850)
  - iter 3 (most recent): 0.5938 (var=0.0114) (Δ vs real +0.0863)
**Other theories' values on this metric (for reference):**
- pi_3: 0.0269 (var=0.0009)
- pi_1: 0.8475 (var=0.0132)
- pi_2: 0.1450 (var=0.0133)
- pi_4: 0.4906 (var=0.0065)

### Experiment 5
**Design**
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = 0
    tot = 0
    for _, row in data.iterrows():
        try:
            a = np.asarray([int(v) for v in row['option_a_ratings']], dtype=float)
            b = np.asarray([int(v) for v in row['option_b_ratings']], dtype=float)
        except Exception:
            continue
        if a.shape[0] != 5 or b.shape[0] != 5:
            continue
        d = a - b
        # target cell: d = +-[1,-1,-1,1,0]  (pairs 1 and 2)
        pattern_ok = (
            abs(d[4]) < 1e-9
            and abs(abs(d[0]) - 1.0) < 1e-9
            and abs(abs(d[1]) - 1.0) < 1e-9
            and abs(abs(d[2]) - 1.0) < 1e-9
            and abs(abs(d[3]) - 1.0) < 1e-9
            and abs(d[0] - d[3]) < 1e-9
            and abs(d[1] - d[2]) < 1e-9
            and abs(d[0] + d[1]) < 1e-9
        )
        if not pattern_ok:
            continue
        try:
            resp = int(row['response'])
        except Exception:
            continue
        if resp not in (0, 1):
            continue
        # side supported by expert positions 0 and 3 (the first- and last-
        # discriminating cues); opposed by positions 1 and 2
        favored_is_a = d[0] > 0
        chose_favored = (resp == 0) if favored_is_a else (resp == 1)
        hits += 1 if chose_favored else 0
        tot += 1

    if tot == 0:
        return float('nan')
    return float(hits) / float(tot)

```

**Observed (real) value:** 0.8200 (var=0.0126)
**Previous candidate values (this loop):**
  - iter 1: 0.7738 (var=0.0123) (Δ vs real -0.0462)
  - iter 2: 0.7388 (var=0.0109) (Δ vs real -0.0812)
  - iter 3 (most recent): 0.8125 (var=0.0095) (Δ vs real -0.0075)
**Other theories' values on this metric (for reference):**
- pi_4: 0.3500 (var=0.0175)
- pi_3: 0.9513 (var=0.0036)
- pi_1: 0.8250 (var=0.0169)
- pi_2: 0.4850 (var=0.0117)

### Experiment 6
**Design**
  A=[1, 0, 1, 1, 0, 1]  B=[1, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 1, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    hits = 0
    n = 0
    for _, row in data.iterrows():
        try:
            a = np.asarray([int(v) for v in row['option_a_ratings']], dtype=float)
            b = np.asarray([int(v) for v in row['option_b_ratings']], dtype=float)
        except Exception:
            continue
        if a.shape[0] != b.shape[0] or a.shape[0] < 6:
            continue
        d = a - b
        disc = [int(i) for i in np.nonzero(np.abs(d) > 1e-9)[0]]
        target = None
        # Class (2): d nonzero at {0,2,5}, first and last agree, mid-list top cue opposes
        if disc == [0, 2, 5]:
            if d[0] == d[5] and d[2] == -d[0]:
                target = 0 if d[0] > 0 else 1
        # Class (3): d nonzero at {0,1,2,5}, three cues agree, single top cue opposes
        elif disc == [0, 1, 2, 5]:
            if d[0] == d[1] == d[5] and d[2] == -d[0]:
                target = 0 if d[0] > 0 else 1
        if target is None:
            continue
        n += 1
        try:
            resp = int(row['response'])
        except Exception:
            continue
        if resp == target:
            hits += 1
    if n == 0:
        return 0.5
    return float(hits) / float(n)

```

**Observed (real) value:** 0.8413 (var=0.0134)
**Previous candidate values (this loop):**
  - iter 1: 0.3337 (var=0.0099) (Δ vs real -0.5075)
  - iter 2: 0.3906 (var=0.0074) (Δ vs real -0.4506)
  - iter 3 (most recent): 0.0912 (var=0.0050) (Δ vs real -0.7500)
**Other theories' values on this metric (for reference):**
- pi_3: 0.9694 (var=0.0014)
- pi_4: 0.3312 (var=0.0055)
- pi_1: 0.1388 (var=0.0136)
- pi_2: 0.8825 (var=0.0110)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
**Anchored compensatory integration with convex diagnosticity weighting ("the loud first expert, the discounted weak experts").**

People do not run a lexicographic search and they do not stop early; they read every rating and add up the evidence. Three claims specify how the addition is weighted:

1. **Diagnosticity is read convexly, not linearly.** The subjective pull of expert *j* is a *super-linear* function of how far its stated validity is from a coin flip: d_j = (v_j - 0.5)^rho with rho clearly above 1 (~2.2-2.8). Psychologically, people treat a .95 expert as a *near-oracle* and treat .55-.65 experts as nearly worthless noise rather than as fractional votes. This is the standard extremity/certainty distortion applied to communicated reliabilities. Consequence: a crowd of two *mid* cues does **not** automatically out-weigh one near-oracle (this is what makes cells like ".95 alone vs .78+.72" land near chance), yet a crowd of three *high* cues (.9,.8 plus a primacy boost) still does beat the .95 cue (compensatory behaviour survives where the crowd is genuinely strong).

2. **Screen position is a graded attention multiplier, not a search order.** The rating that is read first is rehearsed longest and becomes the anchor for the running impression: a_j = 1 + alpha*exp(-lambda*j), alpha ~1.4-2.2, lambda ~1. The final cue weight is the PRODUCT w_j ∝ d_j * a_j. The anchor is strong enough to break a validity *tie* between two equally weighty cue sets (so the pos-0 side wins ~.8 of the time when weights are balanced) and to make a validity-sorted display look Take-The-Best-like, but it is *not* strong enough to overturn a genuine diagnosticity gap (a mid-validity first cue still loses to a late near-oracle). There is no recency subpopulation and no discrete strategy types — individual differences are unimodal jitter in rho, alpha, lambda, sensitivity and lapse.

3. **Evidence is summed over all cues and read out on an absolute margin.** E = sum_j ŵ_j (a_j - b_j) with ŵ = w / sum(w) (a fixed rescaling, NOT a division by the discriminating weight). Choice = logistic(beta*E) plus a lapse. Because the margin is absolute, a trial in which one strong cue is nearly balanced by a two-cue crowd sits near chance, while a trial with a real weight margin sits at .75-.90; confidence is purely margin-graded and never conclusion-graded, so nothing pushes unresolved trials toward the *opposite* option.

Signature predictions: validity-sorted displays look near-lexicographic in both conflict and agreement cells (small position-driven contrast); scrambled displays where the near-oracle is listed last look tally-like; designs that pit a near-oracle against exactly-balancing mid cues sit at chance with *within-subject* (not between-subject) stochasticity; and screen-extreme crowds win only when their summed convex diagnosticity, boosted by the primacy anchor, actually exceeds the oracle's.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    import numpy as np

    # ------------------------------------------------------------------
    # 1. unpack the trial stimulus into two rating vectors (screen order)
    # ------------------------------------------------------------------
    a = None
    b = None
    if isinstance(state, dict):
        if 'option_a_ratings' in state and 'option_b_ratings' in state:
            a = np.asarray(list(state['option_a_ratings']), dtype=float)
            b = np.asarray(list(state['option_b_ratings']), dtype=float)
    if a is None:
        arr = np.asarray(state, dtype=float)
        if arr.ndim == 1:
            arr = arr.reshape(2, -1)
        elif arr.ndim > 2:
            arr = arr.reshape(2, -1)
        if arr.shape[0] != 2:
            arr = arr.reshape(2, -1)
        a = arr[0].astype(float)
        b = arr[1].astype(float)

    a = np.ravel(a).astype(float)
    b = np.ravel(b).astype(float)
    n = int(min(a.shape[0], b.shape[0]))
    if n == 0:
        return np.array([0.5, 0.5])
    a = a[:n]
    b = b[:n]
    d = a - b

    if not np.any(np.abs(d) > 1e-12):
        return np.array([0.5, 0.5])

    # ------------------------------------------------------------------
    # 2. communicated validities -> convex diagnosticity
    # ------------------------------------------------------------------
    val = parameters.get('validities', None)
    try:
        val = np.asarray(val, dtype=float).ravel()
    except Exception:
        val = None
    if val is None or val.shape[0] != n:
        # fallback: assume the display is validity-sorted, descending
        val = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.90])
    val = np.clip(val, 0.5 + 1e-6, 1.0)

    rho = float(np.clip(parameters.get('rho', 2.5), 0.1, 8.0))
    alpha = float(np.clip(parameters.get('alpha', 1.8), 0.0, 6.0))
    lam = float(np.clip(parameters.get('lam', 1.1), 0.01, 6.0))
    beta = float(np.clip(parameters.get('beta', 7.0), 0.0, 200.0))
    eps = float(np.clip(parameters.get('epsilon', 0.05), 0.0, 1.0))

    diag = np.power(np.clip(val - 0.5, 1e-12, None), rho)      # convex diagnosticity

    # ------------------------------------------------------------------
    # 3. graded primacy attention multiplier (screen-position anchor)
    # ------------------------------------------------------------------
    pos = np.arange(n, dtype=float)
    att = 1.0 + alpha * np.exp(-lam * pos)

    w = diag * att
    tot = float(np.sum(w))
    if (not np.isfinite(tot)) or tot <= 0:
        w = np.ones(n, dtype=float) / n
    else:
        w = w / tot            # fixed rescaling only (NOT per-trial normalisation)

    # ------------------------------------------------------------------
    # 4. unnormalised additive evidence over ALL cues; margin-graded choice
    # ------------------------------------------------------------------
    E = float(np.sum(w * d))

    z = np.clip(beta * E, -60.0, 60.0)
    p_a = 1.0 / (1.0 + np.exp(-z))

    p = np.array([p_a, 1.0 - p_a], dtype=float)
    p = (1.0 - eps) * p + eps * 0.5
    p = np.clip(p, 1e-12, None)
    p = p / p.sum()
    return p

`policy(probs) -> int`:
def policy(probs):
    import numpy as np
    probs = np.asarray(probs, dtype=np.float64)
    probs = np.clip(probs, 0.0, None)
    s = probs.sum()
    if not np.isfinite(s) or s <= 0:
        probs = np.ones_like(probs) / len(probs)
    else:
        probs = probs / s
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- rho: [2.2, 2.8]
- alpha: [1.4, 2.2]
- lam: [0.9, 1.3]
- beta: [6.0, 8.5]
- epsilon: [0.02, 0.08]
- validities: validities

`rationale`: **What the two incumbents got wrong, mechanistically.** pi_3 (pure position scanning with normalisation by the discriminating weight) is right that a first-position anchor exists (it alone reproduces the small positive TTB-contrast in E1 and the tally-rate in E2), but because it ignores validity and renormalises every trial it goes to ceiling everywhere: it predicts .04 and .03 where humans are at .52 and .51 (E3, E4) and .95/.97 where humans are at .82/.84. pi_4 (validity-only weights + early stopping + conclusion-graded commitment) is right that validity magnitudes matter (it nails E1-E4) but, having no position term at all, it picks the *wrong side* in exactly the two cells where the screen-extreme cues carry the day (E5 .35 vs .82; E6 .33 vs .84). Neither is experiment-invariant; each is catastrophically wrong on the other's home turf.

**The fusion.** I implement the arbiter's prescribed family literally: cue weight = (validity term) x (attention term), evidence summed over all cues, NO normalisation by the discriminating weight, no early stopping, no conclusion-graded commitment, margin-graded logistic choice with a lapse, and unimodal parameter jitter only (no 35% recency subpopulation). That combination is exactly what makes intermediate rates possible: the same beta produces ~.5 when a near-oracle is nearly balanced by a crowd and ~.8 when a real weight margin exists.

**One calibrated departure from the arbiter's numbers, with reasons.** The arbiter suggested rho ~0.8-1.4. Working the arithmetic through with the *known* validity vectors shows rho near 1 cannot survive: in E4 (validities .78/.60/.95/.88/.72) linear weighting makes the two-cue crowd (.28+.22=.50) beat both the .95 cue (.45) and the .88 cue (.38), and adding *any* pos-0 anchor drives the metric to .17-.33 (pi_3's failure mode) instead of the observed .5075; in E1 it produces a -.5 to -.7 contrast (pi_2's failure mode). Convex diagnosticity, rho~2.5, fixes both while *preserving* compensatory behaviour where the crowd is genuinely strong. Hand-computed predictions for the parameter centre (rho=2.5, alpha=1.8, lambda=1.1, beta=7, eps=.05): E2 = .72 (real .775), E4 = .46 (real .5075), E1 contrast = -.18 (real .093), and with plausible reconstructions of the unpublished validity vectors E5 = .81 (real .82) and E6 = .80 (real .84) — i.e. the two cells that destroyed pi_4 are now recovered without destroying the four cells pi_4 got right. Crucially, no cell is predicted above ~.95 or below ~.10, so the worst-case per-experiment error is bounded (~.25) instead of the ~.5 catastrophes both incumbents incurred; the model is therefore far more experiment-invariant even where the design's validities are unknown to me.

**Why the anchor is graded rather than lexicographic.** alpha~1.8 with lambda~1.1 gives the first-listed cue roughly a 2.8x attention multiplier that decays to ~1.2 by position 2. Multiplied by convex diagnosticity this (i) flips balanced-weight ties toward the pos-0 side (E5, E6), (ii) makes a validity-sorted list behave near-lexicographically so the conflict/agreement contrast stays small (E1), (iii) still lets a late-listed near-oracle beat a single mid first cue (keeps E3/E4 near chance rather than at floor), and (iv) lets a three-cue high-validity crowd out-vote the .95 expert listed last (E2). Individual differences enter only as unimodal jitter in rho, alpha, lambda, beta and the lapse, consistent with the low, near-binomial between-subject variances observed.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate is faithful to the arbiter's prescribed family (validity-term \u00d7 attention-term product weights, summed unnormalised evidence, softmax + lapse, unimodal jitter, no early stopping, no conclusion-graded commitment) and it clearly beats both incumbents on breadth: it avoids the ceiling/floor catastrophes of pi_3 (E3 .04, E4 .03) and the wrong-side catastrophe of pi_4 on E5 (.35 vs .82). E2 (.722 vs .775), E4 (.462 vs .508) and E5 (.774 vs .820) are all within ~.05 of the human values, which is exactly the intermediate-rate calibration the arbiter asked for. Two cells still fail. (i) E6 is a .51 miss in the pi_4 direction: the candidate chooses the mid-list top-validity cue's side (target rate .334) where humans overwhelmingly go with the screen-extreme crowd (.841). This is a direct consequence of the departure from the arbiter's rho range \u2014 rho\u22482.5 makes the near-oracle so dominant that neither the {pos0,pos5} pair nor even the {pos0,pos1,pos5} three-cue crowd can out-weigh it, despite the primacy multiplier. (ii) E1's contrast is -.16 vs +.093, i.e. the model is more tally-like on conflict trials than humans (pi_4 got -.005, pi_3 got +.10). (iii) E3 is .648 vs .518 \u2014 the model over-weights the mid-list .95 cue there too, the same rho symptom. Notably, the rho and edge-attention knobs move E3, E6 and E5 in the *same* helpful direction, so this is a tractable in-family recalibration rather than a structural failure.
Rationale: The candidate was ACCEPTED and should remain the base \u2014 do not restructure it, and stay in the prescribed anchored-compensatory family (product weights, unnormalised sum, margin-graded logistic + lapse). But one cell (E6, error .51) dominates the aggregate loss and it is fixable with the exact knob the candidate deliberately over-shot: convex diagnosticity. Concrete requests: (1) Pull rho back toward the arbiter's band \u2014 try rho \u2208 [1.2, 1.9] rather than [2.2, 2.8]. At rho\u22482.5 the .95 cue is ~4\u00d7 a .78 cue, which is why a three-cue crowd (E6 class {0,1,5} vs {2}) still loses and why E3 sits at .65 instead of .52. Lowering rho raises E6 toward .84 and lowers E3 toward .52 simultaneously; the cost on E4 (currently .462, would drift lower) is bounded and much smaller than the E6 gain, so protect E4 by not going below rho\u22481.2. (2) Make the attention term an EDGE profile rather than pure primacy: att_j = 1 + alpha*exp(-lam*j) + gamma*exp(-mu*(n-1-j)) with a small last-position bump gamma \u2208 [0.2, 0.7], mu \u2248 1. This is still a graded attention multiplier (in-family; the arbiter explicitly permitted a small unimodal recency component) and it is the cheapest way to get E6 class-2 ({pos0,pos5} vs mid-list top cue) and E5 (pos0+pos3 vs pos1+pos2) up without touching the validity term. Keep gamma small so E1 and E4 do not degrade. (3) Keep alpha at the upper end (~1.8-2.4) with lam ~1.0 so that lowering rho does not make E1's contrast even more negative \u2014 the target for E1 is roughly 0 to +.10, and the model is currently at -.16 because late low-validity cues carry too much aggregate weight on conflict trials; a stronger, more sharply decaying primacy multiplier is the in-family lever for that. (4) Re-check that beta stays in a range where E2 lands .75-.85 and E4/E3 stay in .45-.60 \u2014 no cell above ~.92 or below ~.10. Do not add strategy subpopulations, early stopping, or per-trial normalisation.

**Outcome of this advice:** iter 1 candidate loss=0.2158 -> iter 2 candidate loss=0.2242 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: Iter 2 is a strict regression (0.2242 vs 0.2158) and the gate rejected it, so the base is still iter 1. The diagnosis is clean: the added recency term (gamma·exp(-mu·(n-1-j))) bought only +0.057 on E6 (.334 → .391, still a .45 error) while degrading every other cell — E2 .722→.696, E4 .462→.422, E5 .774→.739, and it overshot E3 from +.130 error to -.110 error. Net negative. So the last-position bump is not the right lever, and my iter-1 push in that direction was wrong; I will not repeat it. The structural picture from the accepted base is unchanged and informative. The candidate is faithful to the arbiter's family (product of a convex validity term and a positional attention term, unnormalised summed evidence, margin-graded logistic + lapse, unimodal jitter, no early stopping, no conclusion-graded commitment), and it is the only theory on the board that avoids catastrophic misses in BOTH directions (pi_3 is at ceiling on E5/E6 but floors E3/E4; pi_4 inverts E5). Its one dominating failure is E6: humans go with the screen-extreme crowd against the mid-list top-validity cue at .841, the model goes the opposite way at .33-.39. E3 is the same qualitative cell (edge cues vs mid-list .95) but humans there sit at chance (.518), and in the accepted base the model is .648 — i.e. E3 has ~.13 of slack in the SAME direction that E6 needs a huge move. E1 (-.16 vs +.093) is also a same-direction miss: the model is too tally-like on conflict trials, which a stronger/sharper first-position anchor would correct. The knob that moves E6 up, E3 down, E1 up, E2 up and E5 up simultaneously is the strength and sharpness of the primacy multiplier applied to a still-convex diagnosticity — E4 (currently .462 vs .508) is the only cell that pays.
Rationale: Stay inside the arbiter's anchored-compensatory family (product weights d_j·a_j, unnormalised sum over all cues, logistic on the absolute margin + lapse, unimodal jitter). Build on the ACCEPTED iter-1 base, not on iter 2. Concrete, minimal-diff requests: (1) DROP the recency term (set gamma = 0 / delete it). My iter-1 request for an edge profile was tested and rejected by the gate: it moved E6 by only .06 while costing .03-.06 each on E2, E4, E5 and flipping E3's sign of error. Do not retry it. (2) Instead, strengthen and sharpen the PRIMACY anchor, which I did not push hard last time: alpha from ~2.0 up to ~3.0-4.0 with lam ~1.2-1.7 (currently 1.7-2.3 / 0.95-1.30). Hand-check the direction before committing: a sharper decay leaves the mid-list top cue (E6 pos2, E3 pos3, E4 pos2/pos3) with essentially no attentional boost while pos0 is multiplied 4-5x, which (a) raises E6 toward .5-.7 because pos0 is on the crowd's side in BOTH scored classes, (b) pulls E3 down from .648 toward the observed .518, (c) pushes E1's conflict-minus-agreement contrast up from -.16 toward the observed +.09 (conflict trials' TTB winner is the pos-0 side), (d) raises E2's tally-winner rate on the rows where the crowd occupies pos0-pos2 and the .95 oracle sits at pos5, and (e) raises E5, whose target side contains pos0. (3) Nudge rho down only slightly, to ~[1.9, 2.4], as an intermediate step between the accepted [2.2,2.8] and my earlier (untested) [1.2,1.9] — enough extra crowd weight to keep E6 moving without collapsing E4. Do not go below ~1.8 in one step; the proposer's own arithmetic shows E4 and E1 break at rho≈1.5. (4) Treat E4 as the guard rail: it currently sits .046 below the human value and both knobs push it lower. Accept at most ~.08 total degradation on E4 (i.e. keep it >= .43) and back alpha off if it falls further; also keep E2 >= .70 and E5 >= .77. (5) Sanity-check that the true per-experiment validity vector is actually reaching predict() for E6 and E3 (the `validities` parameter), rather than the descending-linspace fallback — a silent fallback on a scrambled display would by itself explain a .45 miss and would make all of the above tuning moot. (6) No strategy subpopulations, no early stopping, no per-trial normalisation by the discriminating weight, and keep every simulated cell inside .10-.93.

**Outcome of this advice:** iter 2 candidate loss=0.2242 -> iter 3 candidate loss=0.2310 -> the gate marked it REJECTED.

### Iteration 3 (most recent — address this)
Verdict: regenerate
Interpretation: Iter 3 is another strict regression (0.2310 vs the accepted 0.2158) and was rejected by the gate, so the base is still iter 1. The per-cell breakdown is informative: the broad recency lobe plus the much higher beta (14-24 vs 6-8.5) did improve E1 (-.160 \u2192 -.091 vs real +.093), E3 (.648 \u2192 .494 vs .518) and E5 (.774 \u2192 .813 vs .820), but it destroyed the two cells that were already carrying the loss: E6 collapsed from .334 to .091 against a real value of .841 (a .75 error, by far the largest single miss on the board), and E2 slid from .722 to .666 (real .775). The E6 collapse falsifies the proposer's own arithmetic: they argued a broad recency lobe would lift the pos0/pos5 crowd in E6, but with rho\u22482.4 the mid-list .95 cue has diagnosticity .45^2.4 \u2248 .25 while a .6 cue has .1^2.4 \u2248 .004 \u2014 a ~60x ratio that no attention multiplier of size 2-3 can overcome. Raising beta then simply sharpened the already wrong-signed evidence toward 0. So the positional-attention lobes are NOT the binding constraint on E6/E3; the convex diagnosticity exponent is. Note also that the candidate has drifted from the arbiter's explicit prescription: the recommendation asked for rho \u2248 0.8-1.4 precisely so that 'a crowd of 3 mid cues can out-weigh a single .95 cue', and every iteration of this loop has instead run rho \u2248 2.2-2.8, i.e. the opposite sign of curvature. That single unfaithful choice mechanically guarantees the E6 (.09-.39 vs .84) and E1 (negative contrast) failures, and it is the one lever that has never actually been tested.
Rationale: The candidate was REJECTED, so build again on the accepted iter-1 base, staying strictly inside the arbiter's anchored-compensatory family (product weights w_j \u221d (v_j-0.5)^rho \u00b7 a_j, unnormalised sum over all cues, logistic on the absolute margin + lapse, unimodal jitter, no early stopping, no per-trial normalisation, no conclusion-graded commitment). Concrete, minimal-diff requests, chosen to avoid repeating advice the gate has already killed:

(1) FIX THE FAITHFULNESS DRIFT ON rho \u2014 this is the priority and it is the only knob never actually tried. The arbiter prescribed rho \u2248 0.8-1.4; every iteration has used rho \u2248 2.2-2.8. Set rho \u2208 [0.8, 1.3]. At rho\u22481 the ratio between a .95 cue and a .60 cue is 4.5:1 rather than ~60:1, so a two- or three-cue edge crowd with a modest primacy boost can genuinely balance or beat the mid-list near-oracle. This is exactly what E6 (real .841, model .09-.39) and E3 (real .518 = chance, model .49-.65) require, and it moves both in the right direction simultaneously. Do NOT compensate by re-inflating alpha.

(2) UNDO the beta escalation. Return beta to roughly the accepted-base band (~6-10). The high beta in iter 3 is what turned a modest wrong-signed margin in E6 into a floor value of .09; with lower rho the E6 margin flips sign, but until it does, keep beta low enough that no simulated cell leaves the .12-.90 band. Combined with lapse \u03b5 \u2248 .05-.10, this preserves the intermediate rates the arbiter asked for.

(3) DROP the recency lobe (gamma = 0) or cap it at gamma \u2264 0.25 with mu \u2265 1. I asked for a recency bump in iter 1 (rejected) and the proposer widened it in iter 3 (rejected again). Two independent tests say this lever costs more on E2/E4 than it buys anywhere. Do not retry it in any broad form.

(4) Keep the primacy anchor MODERATE: alpha \u2208 [1.4, 2.0], lam \u2208 [1.0, 1.4]. I oscillated on this (iter 1: raise to 1.8-2.4; iter 2: raise to 3.0-4.0, rejected; iter 3 lowered to 1.1-1.7, rejected), so settle in the middle. With rho near 1 the anchor no longer needs to be huge to flip validity ties in E1/E5, and a huge anchor was already shown to break E4.

(5) Guard rails to hand-check before submitting (use the true per-experiment `validities`, and verify the descending-linspace fallback in predict() is never triggered \u2014 a silent fallback on E6/E3's scrambled displays would by itself explain the E6 miss): E6 \u2265 .60 (target .84), E2 \u2208 [.72, .85], E5 \u2208 [.75, .88], E3 \u2208 [.42, .60], E4 \u2208 [.43, .58], E1 contrast \u2208 [-.05, +.15]. E6 alone is worth ~.7 of error \u2014 accept a few hundredths of degradation on E4/E5 to buy it, but reject any configuration that pushes E2 below .70.

No strategy subpopulations, no early stopping, no threshold rule, no per-trial normalisation \u2014 stay in the prescribed family; the fix here is a parameter-range correction back toward the arbiter's own specification, not a redesign.

**Outcome of this advice:** iter 3 candidate loss=0.2310 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
## THEORY

**Anchored compensatory integration with SUPRA-ADDITIVE CORROBORATION ("a chorus is worth more than the sum of its voices").**

This keeps the accepted base intact — cue weight = convex diagnosticity × primacy-attention, evidence summed over all cues, no normalisation by discriminating weight, no early stopping, margin-graded logistic + lapse — and adds the one thing the base is missing:

**Corroboration is supra-additive.** People do not simply add up the weights of the experts on each side. Having *several independent experts converge on the same option* is itself a qualitative signal ("they agree"), so each side's summed support is multiplied by a mildly convex function of the *number* of experts backing it: `Score_A = (Σ_{j:a_j>b_j} ŵ_j) · k_A^delta`, `Score_B = (Σ_{j:b_j>a_j} ŵ_j) · k_B^delta`, with `delta ≈ 0.2–0.4`. Evidence is `E = Score_A − Score_B`, choice is `logistic(beta·E)` with a lapse.

Why this is the right knob, mechanistically. The two big residual failures of the base model (E6 at .33 vs .84; E3 at .65 vs .52) are both cells where a *lone* near-oracle cue is opposed by two or three weaker cues; the two cells the base gets right (E4 ≈ .5, E5 ≈ .8) are cells where either the crowd is only a pair of strong cues or the two sides have *equal* numbers of cues. Flattening the validity exponent (rho → ~1, as previously advised) moves all of these together and therefore cannot separate them — it buys E6 only by destroying E1, E3 and E4 (E1's contrast goes to −.28, E4 to ~.2). The corroboration exponent separates them: it is *silent* when the two sides have equal counts (E5, and all validity-tie cells), it fires exactly when a numerical crowd faces a lone oracle (E6 classes 2/3, E2's tally-conflict rows, E3), and it leaves the validity gradient — which E1 and E5 need in order to look near-lexicographic in a validity-sorted display — completely intact.

Individual differences remain unimodal jitter (rho, alpha, lam, delta, beta, lapse); there are no strategy subpopulations, no threshold rule, no conclusion-graded commitment.

## MINIMAL EDIT

Only two lines of the accepted `predict` change: the single line `E = float(np.sum(w * d))` is replaced by the side-split corroboration computation, and one parameter (`delta`) is added. Everything else (parsing, validity fallback, convex diagnosticity, primacy attention, fixed rescaling, logistic read-out, lapse, `policy`) is re-emitted verbatim.

```json
{
  "theory": "Anchored compensatory integration with supra-additive corroboration. (1) Diagnosticity is read convexly: the subjective pull of expert j is d_j = (v_j - 0.5)^rho with rho ~2.3-2.7, so a .95 expert is treated as a near-oracle and .55-.65 experts as near-noise. (2) Screen position is a graded attention multiplier, not a search order: a_j = 1 + alpha*exp(-lam*j) with alpha ~1.5-2.1, lam ~0.9-1.3; the cue weight is the PRODUCT w_j proportional to d_j * a_j, rescaled once to sum to 1 (never renormalised per trial). The first-read cue is rehearsed longest and anchors the running impression, which breaks validity ties toward the pos-0 side and makes a validity-sorted display look Take-The-Best-like, but it cannot overturn a genuine diagnosticity gap. (3) NEW: corroboration is supra-additive. People do not merely add the weights on each side; several independent experts converging on the same option is itself a qualitative signal ('they agree'). Each side's summed support is multiplied by a mildly convex function of the NUMBER of experts backing it: Score_A = (sum of w_j over cues favouring A) * k_A^delta, Score_B likewise, with delta ~0.2-0.4. Evidence E = Score_A - Score_B is read out on the ABSOLUTE margin: choice = logistic(beta*E) plus a lapse epsilon, no early stopping, no threshold rule, no conclusion-graded commitment. (4) The corroboration exponent is exactly silent when the two sides have equal cue counts (so equal-count conflict cells and validity ties are untouched), and fires only when a numerical crowd faces a lone high-validity cue - which is why the same model can keep a near-lexicographic look in validity-sorted displays (top cue first, anchored, wins) while letting a three-cue chorus out-vote a mid-list near-oracle in scrambled displays. (5) Individual differences are unimodal jitter in rho, alpha, lam, delta, beta and lapse: no strategy subpopulations, no primacy/recency reader types.",
  "predict": "def predict(parameters, state, history):\n    import numpy as np\n\n    # ------------------------------------------------------------------\n    # 1. unpack the trial stimulus into two rating vectors (screen order)\n    # ------------------------------------------------------------------\n    a = None\n    b = None\n    if isinstance(state, dict):\n        if 'option_a_ratings' in state and 'option_b_ratings' in state:\n            a = np.asarray(list(state['option_a_ratings']), dtype=float)\n            b = np.asarray(list(state['option_b_ratings']), dtype=float)\n    if a is None:\n        arr = np.asarray(state, dtype=float)\n        if arr.ndim == 1:\n            arr = arr.reshape(2, -1)\n        elif arr.ndim > 2:\n            arr = arr.reshape(2, -1)\n        if arr.shape[0] != 2:\n            arr = arr.reshape(2, -1)\n        a = arr[0].astype(float)\n        b = arr[1].astype(float)\n\n    a = np.ravel(a).astype(float)\n    b = np.ravel(b).astype(float)\n    n = int(min(a.shape[0], b.shape[0]))\n    if n == 0:\n        return np.array([0.5, 0.5])\n    a = a[:n]\n    b = b[:n]\n    d = a - b\n\n    if not np.any(np.abs(d) > 1e-12):\n        return np.array([0.5, 0.5])\n\n    # ------------------------------------------------------------------\n    # 2. communicated validities -> convex diagnosticity\n    # ------------------------------------------------------------------\n    val = parameters.get('validities', None)\n    try:\n        val = np.asarray(val, dtype=float).ravel()\n    except Exception:\n        val = None\n    if val is None or val.shape[0] != n:\n        # fallback: assume the display is validity-sorted, descending\n        val = np.linspace(0.95, 0.55, n) if n > 1 else np.array([0.90])\n    val = np.clip(val, 0.5 + 1e-6, 1.0)\n\n    rho = float(np.clip(parameters.get('rho', 2.5), 0.1, 8.0))\n    alpha = float(np.clip(parameters.get('alpha', 1.8), 0.0, 6.0))\n    lam = float(np.clip(parameters.get('lam', 1.1), 0.01, 6.0))\n    beta = float(np.clip(parameters.get('beta', 7.0), 0.0, 200.0))\n    eps = float(np.clip(parameters.get('epsilon', 0.05), 0.0, 1.0))\n    delta = float(np.clip(parameters.get('delta', 0.30), 0.0, 2.0))\n\n    diag = np.power(np.clip(val - 0.5, 1e-12, None), rho)      # convex diagnosticity\n\n    # ------------------------------------------------------------------\n    # 3. graded primacy attention multiplier (screen-position anchor)\n    # ------------------------------------------------------------------\n    pos = np.arange(n, dtype=float)\n    att = 1.0 + alpha * np.exp(-lam * pos)\n\n    w = diag * att\n    tot = float(np.sum(w))\n    if (not np.isfinite(tot)) or tot <= 0:\n        w = np.ones(n, dtype=float) / n\n    else:\n        w = w / tot            # fixed rescaling only (NOT per-trial normalisation)\n\n    # ------------------------------------------------------------------\n    # 4. supra-additive corroboration: each side's summed support is\n    #    multiplied by a mildly convex function of the NUMBER of experts\n    #    backing it.  Silent when the two sides have equal counts.\n    #    Evidence is still an ABSOLUTE (unnormalised) margin.\n    # ------------------------------------------------------------------\n    pos_mask = d > 1e-12\n    neg_mask = d < -1e-12\n    s_a = float(np.sum(w[pos_mask] * np.abs(d[pos_mask])))\n    s_b = float(np.sum(w[neg_mask] * np.abs(d[neg_mask])))\n    k_a = float(np.count_nonzero(pos_mask))\n    k_b = float(np.count_nonzero(neg_mask))\n    f_a = (k_a ** delta) if k_a > 0.0 else 0.0\n    f_b = (k_b ** delta) if k_b > 0.0 else 0.0\n    E = s_a * f_a - s_b * f_b\n\n    z = np.clip(beta * E, -60.0, 60.0)\n    p_a = 1.0 / (1.0 + np.exp(-z))\n\n    p = np.array([p_a, 1.0 - p_a], dtype=float)\n    p = (1.0 - eps) * p + eps * 0.5\n    p = np.clip(p, 1e-12, None)\n    p = p / p.sum()\n    return p",
  "policy": "def policy(probs):\n    import numpy as np\n    probs = np.asarray(probs, dtype=np.float64)\n    probs = np.clip(probs, 0.0, None)\n    s = probs.sum()\n    if not np.isfinite(s) or s <= 0:\n        probs = np.ones_like(probs) / len(probs)\n    else:\n        probs = probs / s\n    return int(np.random.choice(len(probs), p=probs))",
  "parameters": {
    "rho": "[2.3, 2.7]",
    "alpha": "[1.5, 2.1]",
    "lam": "[0.9, 1.3]",
    "delta": "[0.20, 0.40]",
    "beta": "[6.0, 8.5]",
    "epsilon": "[0.02, 0.08]",
    "validities": "validities"
  },
  "rationale": "MINIMAL DIFF: the accepted iter-1 source is re-emitted verbatim except that the single evidence line `E = float(np.sum(w * d))` is replaced by a side-split score with a corroboration exponent, and one parameter (`delta`) is added; rho/alpha/lam/beta/epsilon ranges are essentially unchanged (rho merely narrowed to [2.3,2.7]).\n\nWHY I DID NOT FOLLOW THE 'rho -> [0.8,1.3]' REQUEST. I worked the arithmetic through with the validity vectors that are actually recoverable from the metrics (E2 = [.9,.6,.8,.55,.7,.95], E4 = [.78,.60,.95,.88,.72]) and with vectors for E1/E3/E5/E6 back-solved so that the accepted base reproduces its own reported outputs (E1 -.16, E3 .648, E5 .774, E6 .334 -- my hand computations reproduce all four to within a few hundredths, which validates the reconstruction). At rho = 1.2 with alpha = 1.6 the predicted cells are: E1 contrast -.28 (real +.093), E2 .78 (real .775), E3 .21 (real .518), E4 .21 (real .508), E5 .71 (real .82), E6 .76 (real .841). Total absolute error 1.175 vs the base's 1.036 -- the E6 gain is fully paid for by E1, E3 and E4. Flattening the validity exponent moves E3, E4 and E6 *together*, so it cannot separate the cells that must move (E6, E3) from the cells that must stay put (E4, E1, E5). That is why every rho-flattening variant, tested or hand-computed, is loss-neutral at best.\n\nTHE ACTUAL BINDING PROBLEM. E4 row 1 (crowd .78@pos0 + .72@pos4 vs lone .95@pos2, humans at chance .5075) and E6 class 2 (crowd @pos0 + @pos5 vs lone .95@pos2, humans .841 for the crowd) are the *same* structure with opposite human outcomes, and E6's crowd is the weaker one in validity (pi_4's .331 forces that conclusion). No monotone weight function of validity x position can fit both. What distinguishes them is the *count* configuration across the design: E6's scored cells include a genuine 3-vs-1 chorus and its 2-vs-1 cell sits right at the model's indifference point, whereas E4's cells are 2-vs-1 with the crowd already slightly ahead on weight. A supra-additive corroboration exponent is the only lever that is silent on equal-count cells (E5's 2-vs-2, all validity ties), mild on 2-vs-1 cells, and strong on 3-vs-1 and 4-vs-1 cells.\n\nHAND-CHECKED PREDICTIONS at the centre of the ranges (rho 2.5, alpha 1.8, lam 1.1, beta 7.25, eps .05, delta .30): E1 contrast -.169 (base -.157), E2 .757 (base .722, real .775), E3 .50 (base .648, real .518), E4 .34 (base .462, real .508), E5 .87 (base .84, real .82), E6 .55 (base .334, real .841). Sum of absolute errors falls from 1.036 to ~0.84, i.e. the two large-leverage cells (E6 -.22, E3 -.11) improve and E2 improves, against bounded costs on E4 (+.12), E1 (+.01) and E5 (+.02). Crucially the sign of the E6 and E3 movements is guaranteed by construction (the crowd side always has more cues than the lone oracle), so the direction of the edit does not depend on my reconstructed validity vectors -- only its magnitude does. delta is capped at 0.4 because at delta = .45 E3 overshoots past chance and E1's contrast degrades; at delta = .2 the E6 gain halves. No strategy subpopulations, no recency lobe (two rejections), no beta escalation (rejected), no per-trial normalisation, no early stopping -- every simulated cell stays inside .15-.98."
}
```
```

## Usage

```json
{
  "input_tokens": 30479,
  "output_tokens": 88849
}
```
