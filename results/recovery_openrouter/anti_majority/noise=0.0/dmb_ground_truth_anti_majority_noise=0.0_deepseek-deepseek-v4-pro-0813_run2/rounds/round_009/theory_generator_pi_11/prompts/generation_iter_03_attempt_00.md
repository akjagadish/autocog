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
- THEORY 1 = `pi_9`
- THEORY 2 = `pi_10`
- The recommendation below acts on THEORY 1 (= `pi_9`).

Replace pi_9 with an evidence-complexity-gated anti-validity theory. The new theory should keep pi_9's useful core: D = sum_j v_j^gamma * (A_j - B_j) with gamma > 0; score = sign * lambda * D / (tau + |D|) + bias; mostly anti-validity sign with a minority of validity-consistent subjects; lapse; and p(A) = lapse/2 + (1-lapse) * sigmoid(beta * score). It must completely remove the strong unweighted tally switch omega * T; at most a tiny tally leak with |eta| < 0.05 may remain. It must also avoid pi_10's negative or very sub-linear gamma tail. In place of the tally switch, modulate response gain by evidence fragmentation: multiply the score by exp(-rho * max(0, n_disc - 2)), where n_disc is the number of features where A_j != B_j. Suggested parameter ranges: gamma 1.0-2.5, tau 0.05-0.40, lambda 1.0-4.0, beta 2.0-5.0, rho 0.3-1.5, lapse 0.00-0.10, and p_positive 0.00-0.30. Under this theory Experiment 1 has D near zero and n_disc = 13, so dilution pushes all rows toward chance and the tally contrast metric is 0.000; Experiment 2 has n_disc = 2, so dilution is inactive and the same anti-validity core gives a high-validity choice rate near 0.35; large-D archive rows still produce strong logit variation, unlike pi_10's oversaturated mixture. Keep the stochastic choice policy unchanged.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_5` (overall score: 0.475)

**Description**
Compressive Negative Validity-Weighted integration with subject-level saturation (CNVW-tau). Each subject forms D = sum_j v_j^gamma_i * (A_j - B_j), where v_j are the instructed expert validities and gamma_i is a subject-level validity exponent. The weighted difference is passed through a strongly saturating bounded transform psi(D) = D / (tau_i + abs(D)), with a small subject-level half-saturation constant tau_i. Most subjects apply a negative sign, S_i = -lambda_i * psi(D) + bias_i, while a minority apply a positive sign. Choice probability is p(A) = epsilon_i/2 + (1 - epsilon_i) * sigmoid(beta_i * S_i). There is no feature-tally term and no conflict-gating interaction.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np

def predict(parameters, state, history):
    """Compressive negative validity-weighted integration with subject-level tau.

    D = sum_j v_j^gamma * (A_j - B_j)
    psi(D) = D / (tau + abs(D))
    S = sign * lambda * psi(D) + bias
    p(A) = lapse/2 + (1-lapse) * sigmoid(beta * S)

    Most subjects use sign = -1; a minority draw sign = +1.
    history is intentionally ignored because there is no feedback.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "CNVW-tau expects a (2, n_features) stimulus; "
            f"got shape {stim.shape}."
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f"validities length {v.size} does not match n_features {a.size}."
        )

    gamma = float(parameters["gamma"])
    lam = float(parameters["lambda"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    bias = float(parameters["bias"])
    p_positive = float(parameters["p_positive"])
    sign_draw = float(parameters["sign_draw"])
    tau = float(parameters["tau"])

    # Latent sign mixture: most subjects use negative-valence weighting;
    # a minority trust positive-valence evidence and get a positive sign.
    sign = 1.0 if sign_draw < p_positive else -1.0

    # Validity-weighted feature difference.
    d = float(np.dot(v ** gamma, a - b))

    # Subject-level strongly saturating bounded transform. The small
    # half-saturation constant tau forces most non-negligible validity-
    # weighted differences toward the sign bound, so sign and not
    # continuous magnitude drives the main choice contrast.
    psi = d / (tau + abs(d))

    score = sign * lam * psi + bias
    z = beta * score

    # Numerically stable sigmoid for p(A | score).
    if z >= 0.0:
        p_a_core = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        p_a_core = ez / (1.0 + ez)

    # Uniform lapse mixture over the two options.
    p_a = (1.0 - epsilon) * p_a_core + epsilon / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)

`policy(probs) -> int`:
import numpy as np

def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))

`parameters`:
- gamma: [1.5, 2.5]
- tau: [0.10, 0.25]
- lambda: [0.8, 2.0]
- beta: [0.8, 2.0]
- bias: [-0.25, 0.25]
- epsilon: [0.03, 0.10]
- p_positive: [0.03, 0.10]
- sign_draw: [0.0, 1.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.2852 (var=0.0363)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.2133 (var=0.0171)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.5467 (var=0.1673)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.5175 (var=0.0843)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0050 (var=0.0269)
- Experiment 6: real=0.0117 (var=0.0033) vs this=0.0663 (var=0.0100)
- Experiment 7: real=0.0064 (var=0.0161) vs this=0.0393 (var=0.0171)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.1742 (var=0.0110)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.4529 (var=0.1083)
- Experiment 10: real=0.0675 (var=0.0553) vs this=-0.0025 (var=0.0475)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.4985 (var=0.0248)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.3367 (var=0.0255)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=-0.1583 (var=0.0665)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.2444 (var=0.0354)
- Experiment 15: real=-0.0050 (var=0.0048) vs this=0.0158 (var=0.0031)
- Experiment 16: real=3.6952 (var=11.4034) vs this=0.4649 (var=0.1658)
- Experiment 17: real=0.0233 (var=0.0233) vs this=0.0000 (var=0.0080)
- Experiment 18: real=0.1600 (var=0.8156) vs this=0.1150 (var=0.1518)
- Experiment 19: real=0.0000 (var=0.0000) vs this=0.2800 (var=0.0183)
- Experiment 20: real=0.3500 (var=0.0094) vs this=0.4304 (var=0.0055)


---

### `pi_10` (overall score: 0.471)

**Description**
Gated compressive anti-validity with validity-curvature gain and sign-selectable dead-zone repair. Each subject forms D = sum_j v_j^gamma * (A_j - B_j), passes D through a saturating transform D/(tau + |D|), and mostly applies a negative validity-weighting sign. A subject-level threshold theta defines a mild dead zone around D=0: inside this zone the anti-validity score is attenuated and augmented by a bounded graded repair D/(kappa + |D|) whose sign is anti-validity for most subjects but validity-consistent for a minority; outside the zone the full compressive score plus bias is used. A two-component subject mixture provides moderate bulk responding with stronger validity curvature plus a near-deterministic tail with negative or sub-linear validity exponents. There is no strong unweighted tally switch and no fragmented-evidence dilution; only a small tally leak eta*T is retained.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            'GCAV expects a (2, n_features) stimulus; got shape '
            + str(stim.shape) + '.'
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters['validities'], dtype=float)
    if v.size != a.size:
        raise ValueError('validities length does not match n_features.')

    comp_draw = float(parameters['comp_draw'])
    p_tail = float(parameters['p_tail'])

    if comp_draw < p_tail:
        gamma = float(parameters['gamma_tail'])
        theta = float(parameters['theta_tail'])
        tau = float(parameters['tau_tail'])
        lam = float(parameters['lambda_tail'])
        beta = float(parameters['beta_tail'])
        bias = float(parameters['bias_tail'])
        rho = float(parameters['rho_tail'])
        c_repair = float(parameters['c_repair_tail'])
    else:
        gamma = float(parameters['gamma_bulk'])
        theta = float(parameters['theta_bulk'])
        tau = float(parameters['tau_bulk'])
        lam = float(parameters['lambda_bulk'])
        beta = float(parameters['beta_bulk'])
        bias = float(parameters['bias_bulk'])
        rho = float(parameters['rho_bulk'])
        c_repair = float(parameters['c_repair_bulk'])

    lapse = float(parameters['lapse'])
    eta = float(parameters['eta'])
    p_positive = float(parameters['p_positive'])
    sign_draw = float(parameters['sign_draw'])

    p_repair_positive = float(parameters['p_repair_positive'])
    repair_sign_draw = float(parameters['repair_sign_draw'])
    c_repair_pos = float(parameters['c_repair_pos'])
    kappa_repair = float(parameters['kappa_repair'])

    # Mostly negative validity-weighting sign.
    sign = 1.0 if sign_draw < p_positive else -1.0

    # Dead-zone repair sign is also mostly anti-validity, but a minority
    # receive a validity-consistent repair inside the dead zone.
    repair_sign = 1.0 if repair_sign_draw < p_repair_positive else -1.0

    diff = a - b
    D = float(np.dot(np.power(v, gamma), diff))
    T = float(np.mean(diff))

    sat = D / (tau + abs(D))
    core = sign * lam * sat + bias

    if abs(D) < theta:
        # Bounded graded repair, applied identically for all tallies.
        repair_sat = D / (kappa_repair + abs(D))
        if repair_sign > 0:
            repair = c_repair_pos * repair_sat
        else:
            repair = -c_repair * repair_sat
        score = rho * core + repair + eta * T
    else:
        score = core + eta * T

    z = beta * score

    # Numerically stable sigmoid for p(A | score).
    if z >= 0.0:
        p_a_core = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        p_a_core = ez / (1.0 + ez)

    # Uniform lapse mixture over the two options.
    p_a = (1.0 - lapse) * p_a_core + lapse / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)


`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))


`parameters`:
- comp_draw: [0.0, 1.0]
- p_tail: [0.12, 0.20]
- gamma_bulk: [1.30, 1.80]
- theta_bulk: [0.06, 0.28]
- tau_bulk: [0.80, 1.80]
- lambda_bulk: [1.00, 1.80]
- beta_bulk: [1.20, 2.50]
- bias_bulk: [-0.05, 0.05]
- rho_bulk: [0.10, 0.22]
- c_repair_bulk: [0.03, 0.10]
- gamma_tail: [-1.80, 0.50]
- theta_tail: [0.00, 0.08]
- tau_tail: [0.08, 0.30]
- lambda_tail: [1.50, 3.00]
- beta_tail: [4.00, 8.00]
- bias_tail: [-0.04, 0.04]
- rho_tail: [0.50, 0.80]
- c_repair_tail: [0.15, 0.45]
- p_positive: [0.02, 0.08]
- sign_draw: [0.0, 1.0]
- lapse: [0.01, 0.04]
- eta: [0.0, 0.04]
- p_repair_positive: [0.12, 0.25]
- repair_sign_draw: [0.0, 1.0]
- c_repair_pos: [0.20, 0.60]
- kappa_repair: [0.03, 0.10]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.3300 (var=0.0375)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.0387 (var=0.0345)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.2683 (var=0.2451)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.2400 (var=0.2617)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0700 (var=0.0217)
- Experiment 6: real=0.0117 (var=0.0033) vs this=0.0942 (var=0.0434)
- Experiment 7: real=0.0064 (var=0.0161) vs this=0.0259 (var=0.0370)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.2703 (var=0.0237)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.4175 (var=0.0333)
- Experiment 10: real=0.0675 (var=0.0553) vs this=0.0262 (var=0.0708)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.3600 (var=0.1011)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.1089 (var=0.0173)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=-0.3417 (var=0.0565)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.0889 (var=0.1086)
- Experiment 15: real=-0.0050 (var=0.0048) vs this=-0.0383 (var=0.0068)
- Experiment 16: real=3.6952 (var=11.4034) vs this=0.9173 (var=6.1326)
- Experiment 17: real=0.0233 (var=0.0233) vs this=-0.0087 (var=0.0095)
- Experiment 18: real=0.1600 (var=0.8156) vs this=-0.4050 (var=0.4260)
- Experiment 19: real=0.0000 (var=0.0000) vs this=0.0637 (var=0.0053)
- Experiment 20: real=0.3500 (var=0.0094) vs this=0.5673 (var=0.0258)


---

### `pi_8` (overall score: 0.377)

**Description**
Conflict-modulated continuous anti-validity with inverse-validity conflict counting and a tally-regularized response (CMCAV-iv). Subjects form a continuous validity-weighted difference D = sum_j v_j^gamma_i * (A_j - B_j), mostly apply a negative validity-weighting sign, and respond through a fluid evidence-gated continuous transform S_i = -lambda_i * G(C) * D / (kappa_i + abs(D) + r_i) + bias_i + w_t * T. There is no fixed threshold, no dead zone, and no single fixed half-saturation constant. The conflict gain G(C) depends on both concentration of the dominant validity-weighted contribution and an inverse-validity-weighted count of disagreeing features, so conflict from many low-validity cues strongly suppresses responding while concentrated high-validity evidence remains effective. A small unidirectional tally term T = (1/n) * sum_j (A_j - B_j) with negative weight supports count-driven anti-validity gradients.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    """Conflict-modulated continuous anti-validity with inverse-validity
    conflict counting and a single negative tally term (CMCAV-iv).

    D = sum_j v_j^gamma * (A_j - B_j)
    S = sign * lam * G(C) * D / (kappa + abs(D) + r)
        + bias + w_t * (1/n) * sum_j (A_j - B_j)

    G(C) uses a concentration-style conflict gain whose conflict
    denominator is an inverse-validity weighted count of disagreeing
    features, not a raw disagreement count.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "CMCAV-iv expects a (2, n_features) stimulus; "
            f"got shape {stim.shape}."
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f"validities length {v.size} does not match n_features {a.size}."
        )

    gamma = float(parameters["gamma"])
    lam = float(parameters["lam"])
    beta = float(parameters["beta"])
    bias = float(parameters["bias"])
    lapse = float(parameters["lapse"])
    kappa = float(parameters["kappa"])
    r = float(parameters["r"])
    p_positive = float(parameters["p_positive"])
    sign_draw = float(parameters["sign_draw"])

    rho = float(parameters["rho"])
    eta = float(parameters["eta"])
    conc_exp = float(parameters["conc_exp"])
    nu = float(parameters["nu"])
    xi = float(parameters["xi"])
    g_min = float(parameters["g_min"])
    g_range = float(parameters["g_range"])
    c_half = float(parameters["c_half"])
    w_t = float(parameters["w_t"])

    # Mostly negative validity-weighting sign.
    sign = 1.0 if sign_draw < p_positive else -1.0

    # Validity-weighted contributions.
    w = np.power(v, gamma)
    diff = a - b
    contrib = w * diff
    D = float(np.sum(contrib))

    mag = np.abs(contrib)
    M = float(np.sum(mag))
    disc_mask = mag > 1e-12

    # Concentration-style conflict gain.
    if M <= 1e-12:
        G = g_min + 0.5 * g_range
    else:
        dom_idx = int(np.argmax(mag))
        max_m = float(mag[dom_idx])
        v_dom = float(v[dom_idx])

        # Dominant share of total validity-weighted evidence.
        cohesion = max_m / M

        # Inverse-validity weighted disagreement count. High-validity
        # disagreeing cues are nearly free, while low-validity disagreeing
        # cues build conflict and suppress the gain.
        inv_validity = np.power(1.0 - v, eta)
        low_conflict = float(np.sum(inv_validity[disc_mask]))
        breadth = 1.0 + rho * low_conflict

        C = (cohesion ** conc_exp) * (v_dom ** nu)
        # Small residual coherence exponent so broad but internally
        # consistent evidence is not fully suppressed.
        C *= ((abs(D) / M) ** xi)
        C /= breadth
        C = float(np.clip(C, 0.0, 20.0))

        G = g_min + g_range * C / (c_half + C)

    G = float(np.clip(G, 0.0, 3.0))

    # Single negative tally term: p(A) is pushed against the count-based
    # validity direction regardless of D's sign.
    T = float(np.mean(diff))

    # Continuous anti-validity response: no fixed threshold and no one
    # fixed half-saturation constant.
    sat = D / (kappa + abs(D) + r)
    score = sign * lam * G * sat + bias + w_t * T
    z = beta * score

    # Numerically stable sigmoid.
    if z >= 0.0:
        p_a_core = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        p_a_core = ez / (1.0 + ez)

    p_a = (1.0 - lapse) * p_a_core + lapse / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)


`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))


`parameters`:
- gamma: [1.6, 2.4]
- lam: [1.3, 2.2]
- beta: [1.5, 2.5]
- bias: [-0.06, 0.06]
- lapse: [0.03, 0.09]
- kappa: [0.02, 0.06]
- r: [0.00, 0.02]
- p_positive: [0.02, 0.10]
- sign_draw: [0.0, 1.0]
- w_t: [-0.32, -0.14]
- rho: [5.0, 8.0]
- eta: [1.5, 2.0]
- conc_exp: [1.4, 1.9]
- nu: [0.5, 1.0]
- xi: [0.0, 0.20]
- g_min: [0.02, 0.06]
- g_range: [2.5, 3.2]
- c_half: [0.4, 0.7]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.1426 (var=0.0094)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.2842 (var=0.0141)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.1861 (var=0.0264)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.3642 (var=0.0368)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0708 (var=0.0258)
- Experiment 6: real=0.0117 (var=0.0033) vs this=0.0067 (var=0.0116)
- Experiment 7: real=0.0064 (var=0.0161) vs this=-0.0098 (var=0.0279)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.0917 (var=0.0054)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.6133 (var=0.0696)
- Experiment 10: real=0.0675 (var=0.0553) vs this=-0.0037 (var=0.0121)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.2435 (var=0.0132)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.1200 (var=0.0219)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=-0.2817 (var=0.0855)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.2367 (var=0.0290)
- Experiment 15: real=-0.0050 (var=0.0048) vs this=0.1862 (var=0.0079)
- Experiment 16: real=3.6952 (var=11.4034) vs this=0.1757 (var=0.0202)
- Experiment 17: real=0.0233 (var=0.0233) vs this=0.1571 (var=0.0107)
- Experiment 18: real=0.1600 (var=0.8156) vs this=0.1300 (var=0.1868)
- Experiment 19: real=0.0000 (var=0.0000) vs this=0.0592 (var=0.0043)
- Experiment 20: real=0.3500 (var=0.0094) vs this=0.3673 (var=0.0138)


## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision — only ACCEPTED candidates have ever been used as the base for a subsequent iteration. Use this together with PRIOR FEEDBACK ITERATIONS below to grade which past critic advice actually paid off.

- iter 1: loss=0.1754 -> ACCEPTED
- iter 2: loss=0.2339 -> REJECTED
- iter 3: loss=0.1671 -> ACCEPTED
Running-best (last ACCEPTED) base: iter 3 at loss=0.1671 — this is the source shown verbatim below under `## PREVIOUS CANDIDATE (this loop)`. Push the next edit's loss strictly below that floor or the gate will reject it.

## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data):
    import numpy as np
    min_class = 12
    groups = {0: [], 1: []}
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=int)
        b = np.asarray(row['option_b_ratings'], dtype=int)
        if a[0] > b[0]:
            grp = 0
        elif b[0] > a[0]:
            grp = 1
        else:
            continue
        tally = int(np.sum(a > b) - np.sum(b > a))
        chose_a = 1.0 if int(row['response']) == 0 else 0.0
        groups[grp].append((tally, chose_a))
    parts = []
    for grp in (0, 1):
        vals = groups[grp]
        if not vals:
            parts.append(0.0)
            continue
        d_a = [d for d, y in vals if y == 1.0]
        d_b = [d for d, y in vals if y == 0.0]
        if len(d_a) < min_class or len(d_b) < min_class:
            parts.append(0.0)
        else:
            parts.append((np.mean(d_a) - np.mean(d_b)) / 6.0)
    return float(np.mean(parts))
```

**Observed (real) value:** -0.4323 (var=0.0402)
**Previous candidate values (this loop):**
  - iter 1: -0.0949 (var=0.0236) (Δ vs real +0.3375)
  - iter 2: -0.4833 (var=0.0993) (Δ vs real -0.0510)
  - iter 3 (most recent): -0.1919 (var=0.0368) (Δ vs real +0.2404)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0157 (var=0.0016)
- pi_2: 0.4517 (var=0.0090)
- pi_3: -0.5184 (var=0.0087)
- pi_4: -0.3839 (var=0.0765)
- pi_5: -0.2852 (var=0.0363)
- pi_6: -0.0094 (var=0.0045)
- pi_7: -0.3210 (var=0.0633)
- pi_7_1: -0.2989 (var=0.0305)
- pi_8: -0.1426 (var=0.0094)
- pi_9: -0.2940 (var=0.0957)
- pi_10: -0.3300 (var=0.0375)

### Experiment 2
**Design**
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    validities = np.array([0.9, 0.8, 0.65, 0.55, 0.5])
    cue_order = np.argsort(-validities, kind='stable')
    a_when_ttb_a = []
    a_when_ttb_b = []
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        ttb_winner = -1
        for j in cue_order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner == -1:
            continue
        chose_a = 1 if int(row['response']) == 0 else 0
        if ttb_winner == 0:
            a_when_ttb_a.append(chose_a)
        else:
            a_when_ttb_b.append(chose_a)
    if not a_when_ttb_a or not a_when_ttb_b:
        return 0.0
    return float(np.mean(a_when_ttb_a) - np.mean(a_when_ttb_b))
```

**Observed (real) value:** -0.2650 (var=0.0713)
**Previous candidate values (this loop):**
  - iter 1: -0.2483 (var=0.0666) (Δ vs real +0.0167)
  - iter 2: -0.3104 (var=0.0296) (Δ vs real -0.0454)
  - iter 3 (most recent): -0.2646 (var=0.0768) (Δ vs real +0.0004)
**Other theories' values on this metric (for reference):**
- pi_2: -0.0083 (var=0.0072)
- pi_1: 0.6883 (var=0.0485)
- pi_3: -0.2804 (var=0.0079)
- pi_4: -0.3037 (var=0.0165)
- pi_5: -0.2133 (var=0.0171)
- pi_6: -0.2996 (var=0.0120)
- pi_7: -0.2604 (var=0.0412)
- pi_7_1: -0.1992 (var=0.0231)
- pi_8: -0.2842 (var=0.0141)
- pi_9: -0.4117 (var=0.0732)
- pi_10: -0.0387 (var=0.0345)

### Experiment 3
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    import pandas as pd

    df = data.copy()
    df["pair_key"] = df.apply(
        lambda r: (tuple(r["option_a_ratings"]), tuple(r["option_b_ratings"])),
        axis=1,
    )

    nwa_negative_pairs = [
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 0)),
        ((1, 1, 0, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
    ]
    nwa_positive_pairs = [
        ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 1), (1, 1, 0, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 0), (1, 1, 1, 0, 0, 0)),
    ]

    def p_a_for_key(d, key):
        mask = d["pair_key"] == key
        return 1.0 - float(d.loc[mask, "response"].mean())

    def subject_score(d):
        neg = [p_a_for_key(d, k) for k in nwa_negative_pairs]
        pos = [p_a_for_key(d, k) for k in nwa_positive_pairs]
        return sum([pos[i] - neg[i] for i in range(3)]) / 3.0

    scores = df.groupby("subject_id", sort=False).apply(subject_score)
    return float(scores.mean())

```

**Observed (real) value:** 0.3622 (var=0.0979)
**Previous candidate values (this loop):**
  - iter 1: 0.2094 (var=0.0934) (Δ vs real -0.1528)
  - iter 2: 0.7044 (var=0.4563) (Δ vs real +0.3422)
  - iter 3 (most recent): 0.3417 (var=0.1071) (Δ vs real -0.0206)
**Other theories' values on this metric (for reference):**
- pi_3: 0.8928 (var=0.0032)
- pi_2: 0.0017 (var=0.0075)
- pi_1: -0.7161 (var=0.0463)
- pi_4: 0.5850 (var=0.1060)
- pi_5: 0.5467 (var=0.1673)
- pi_6: 0.4500 (var=0.0174)
- pi_7: 0.5911 (var=0.1735)
- pi_7_1: 0.5539 (var=0.0612)
- pi_8: 0.1861 (var=0.0264)
- pi_9: 0.6733 (var=0.1841)
- pi_10: 0.2683 (var=0.2451)

### Experiment 4
**Design**
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    diffs = [tuple(int(x) - int(y) for x, y in zip(a, b)) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    choose_a = (data['response'].to_numpy(dtype=float) == 0).astype(float)
    high_keys = {(-1, -1, 1, 1), (-1, 1, -1, 1)}
    low_keys = {(1, 1, -1, -1), (1, -1, 1, -1)}
    high_mask = np.array([d in high_keys for d in diffs], dtype=bool)
    low_mask = np.array([d in low_keys for d in diffs], dtype=bool)
    if high_mask.sum() == 0 or low_mask.sum() == 0:
        return 0.0
    return float(choose_a[high_mask].mean() - choose_a[low_mask].mean())
```

**Observed (real) value:** 0.5300 (var=0.0883)
**Previous candidate values (this loop):**
  - iter 1: 0.2933 (var=0.2637) (Δ vs real -0.2367)
  - iter 2: 0.8583 (var=0.2181) (Δ vs real +0.3283)
  - iter 3 (most recent): 0.4783 (var=0.1541) (Δ vs real -0.0517)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0025 (var=0.0212)
- pi_3: 0.6125 (var=0.0127)
- pi_1: -0.6867 (var=0.0422)
- pi_4: 0.5467 (var=0.0492)
- pi_5: 0.5175 (var=0.0843)
- pi_6: 0.5700 (var=0.0173)
- pi_7: 0.5675 (var=0.2300)
- pi_7_1: 0.4750 (var=0.1189)
- pi_8: 0.3642 (var=0.0368)
- pi_9: 0.5533 (var=0.0659)
- pi_10: 0.2400 (var=0.2617)

### Experiment 5
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    pair_specs = {
        'cp': ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
        'ap': ((1, 0, 1, 1, 1, 1), (0, 1, 0, 0, 0, 0)),
        'cn': ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
        'an': ((0, 1, 0, 0, 0, 0), (1, 0, 1, 1, 1, 1)),
    }
    lookup = {v: k for k, v in pair_specs.items()}

    df = data.copy()
    df['_pair'] = [
        lookup.get((tuple(a), tuple(b)), 'other')
        for a, b in zip(df['option_a_ratings'], df['option_b_ratings'])
    ]
    df['_chose_a'] = (df['response'] == 0).astype(float)

    subject_effects = []
    for _, sub in df.groupby('subject_id'):
        means = sub.groupby('_pair')['_chose_a'].mean()
        if not {'cp', 'ap', 'cn', 'an'}.issubset(means.index):
            continue
        cp = means['cp']
        ap = means['ap']
        cn = means['cn']
        an = means['an']
        effect = (
            (abs(ap - 0.5) - abs(cp - 0.5))
            + (abs(an - 0.5) - abs(cn - 0.5))
        )
        subject_effects.append(effect)

    if not subject_effects:
        return float('nan')
    effects = np.asarray(subject_effects, dtype=float)
    if np.any(np.isnan(effects)):
        return float('nan')
    return float(effects.mean())
```

**Observed (real) value:** -0.0300 (var=0.0191)
**Previous candidate values (this loop):**
  - iter 1: 0.0083 (var=0.0234) (Δ vs real +0.0383)
  - iter 2: 0.0067 (var=0.0030) (Δ vs real +0.0367)
  - iter 3 (most recent): 0.0467 (var=0.0296) (Δ vs real +0.0767)
**Other theories' values on this metric (for reference):**
- pi_3: -0.0017 (var=0.0039)
- pi_4: 0.6350 (var=0.0201)
- pi_1: -0.0033 (var=0.0180)
- pi_2: 0.6083 (var=0.0361)
- pi_5: 0.0050 (var=0.0269)
- pi_6: 0.0075 (var=0.0255)
- pi_7: -0.0325 (var=0.0234)
- pi_7_1: 0.0233 (var=0.0179)
- pi_8: 0.0708 (var=0.0258)
- pi_9: 0.0308 (var=0.0177)
- pi_10: 0.0700 (var=0.0217)

### Experiment 6
**Design**
  A=[1, 0, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0]

**Metric**
```python
import numpy as np

def metric(data):
    v = np.array([0.95, 0.9, 0.85, 0.8, 0.6, 0.55, 0.5], dtype=float)

    a = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    b = np.asarray(data['option_b_ratings'].tolist(), dtype=float)
    z = (a - b).dot(v ** 2)

    resp = np.asarray(data['response'], dtype=float)

    low_mask = z < 0.5
    high_mask = z > 0.9

    lows = resp[low_mask]
    highs = resp[high_mask]

    if lows.size == 0 or highs.size == 0:
        return float('nan')

    p_a_low = float(np.mean(lows == 0))
    p_a_high = float(np.mean(highs == 0))

    return float(p_a_low - p_a_high)

```

**Observed (real) value:** 0.0117 (var=0.0033)
**Previous candidate values (this loop):**
  - iter 1: 0.0212 (var=0.0145) (Δ vs real +0.0096)
  - iter 2: 0.0404 (var=0.0021) (Δ vs real +0.0287)
  - iter 3 (most recent): 0.0650 (var=0.0214) (Δ vs real +0.0533)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0158 (var=0.0128)
- pi_3: 0.2812 (var=0.0041)
- pi_1: -0.0062 (var=0.0073)
- pi_2: 0.0254 (var=0.0198)
- pi_5: 0.0663 (var=0.0100)
- pi_6: -0.0083 (var=0.0131)
- pi_7: -0.0021 (var=0.0067)
- pi_7_1: 0.0592 (var=0.0113)
- pi_8: 0.0067 (var=0.0116)
- pi_9: 0.1904 (var=0.0279)
- pi_10: 0.0942 (var=0.0434)

### Experiment 7
**Design**
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.92, 0.84, 0.74, 0.62, 0.52], dtype=float)
    weights = validities ** 2.25

    a_rows = [np.asarray(r, dtype=float) for r in data['option_a_ratings']]
    b_rows = [np.asarray(r, dtype=float) for r in data['option_b_ratings']]
    if len(a_rows) == 0:
        return 0.0

    a = np.vstack(a_rows)
    b = np.vstack(b_rows)
    d = (a - b) @ weights

    resp = data['response'].to_numpy(dtype=float)
    sign_consistent = np.zeros(len(data), dtype=float)
    sign_consistent[(d > 0.0) & (resp == 1.0)] = 1.0
    sign_consistent[(d < 0.0) & (resp == 0.0)] = 1.0

    x = np.abs(d)
    xc = x - x.mean()
    denom = np.sum(xc * xc)
    if denom < 1e-12:
        return 0.0
    return float(np.sum(xc * sign_consistent) / denom)

```

**Observed (real) value:** 0.0064 (var=0.0161)
**Previous candidate values (this loop):**
  - iter 1: 0.0199 (var=0.0221) (Δ vs real +0.0135)
  - iter 2: 0.0080 (var=0.0008) (Δ vs real +0.0016)
  - iter 3 (most recent): 0.0183 (var=0.0151) (Δ vs real +0.0120)
**Other theories' values on this metric (for reference):**
- pi_3: 0.1683 (var=0.0061)
- pi_5: 0.0393 (var=0.0171)
- pi_1: -0.0904 (var=0.0098)
- pi_2: 0.0118 (var=0.0112)
- pi_4: 0.0529 (var=0.0066)
- pi_6: -0.0130 (var=0.0249)
- pi_7: -0.0377 (var=0.0119)
- pi_7_1: 0.0031 (var=0.0170)
- pi_8: -0.0098 (var=0.0279)
- pi_9: 0.0824 (var=0.0136)
- pi_10: 0.0259 (var=0.0370)

### Experiment 8
**Design**
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    validities = np.array([0.95, 0.9, 0.8, 0.6, 0.5], dtype=float)
    weights = validities ** 2.25

    subject_contrasts = []
    for _, subj in data.groupby('subject_id'):
        cons = []
        high_mask = []
        low_mask = []

        for _, row in subj.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            d = float(np.dot(weights, a - b))
            ad = abs(d)

            # Negative-validity prediction: choose B when A has larger
            # validity-weighted advantage, otherwise choose A.
            pred_neg = 1 if d > 0 else 0
            cons.append(1.0 if int(row['response']) == pred_neg else 0.0)
            high_mask.append(ad >= 0.90)
            low_mask.append(ad <= 0.25)

        cons = np.array(cons)
        high_mask = np.array(high_mask, dtype=bool)
        low_mask = np.array(low_mask, dtype=bool)

        if high_mask.sum() == 0 or low_mask.sum() == 0:
            subject_contrasts.append(0.0)
            continue

        raw_contrast = float(cons[high_mask].mean() - cons[low_mask].mean())
        # Absolute value aligns negative-sign and positive-sign subjects.
        subject_contrasts.append(abs(raw_contrast))

    if not subject_contrasts:
        return 0.0
    return float(np.mean(subject_contrasts))
```

**Observed (real) value:** 0.1200 (var=0.0096)
**Previous candidate values (this loop):**
  - iter 1: 0.1403 (var=0.0090) (Δ vs real +0.0203)
  - iter 2: 0.0683 (var=0.0023) (Δ vs real -0.0517)
  - iter 3 (most recent): 0.1289 (var=0.0059) (Δ vs real +0.0089)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1742 (var=0.0110)
- pi_3: 0.3681 (var=0.0125)
- pi_1: 0.0822 (var=0.0037)
- pi_2: 0.3414 (var=0.0202)
- pi_4: 0.3106 (var=0.0090)
- pi_6: 0.0919 (var=0.0049)
- pi_7: 0.1086 (var=0.0084)
- pi_7_1: 0.2039 (var=0.0121)
- pi_8: 0.0917 (var=0.0054)
- pi_9: 0.2794 (var=0.0126)
- pi_10: 0.2703 (var=0.0237)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.79], dtype=float)
    gamma = 2.0
    weights = validities ** gamma

    def d_sign(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        d = float(np.dot(weights, a - b))
        if d > 0.0:
            return 1
        if d < 0.0:
            return -1
        return 0

    signs = data.apply(d_sign, axis=1)
    p_a = 1.0 - data['response'].astype(float)

    neg_mean = p_a[signs == -1].mean()
    pos_mean = p_a[signs == 1].mean()

    return float(neg_mean - pos_mean)
```

**Observed (real) value:** 0.6008 (var=0.0611)
**Previous candidate values (this loop):**
  - iter 1: 0.5346 (var=0.2098) (Δ vs real -0.0662)
  - iter 2: 0.8183 (var=0.2752) (Δ vs real +0.2175)
  - iter 3 (most recent): 0.4842 (var=0.3942) (Δ vs real -0.1167)
**Other theories' values on this metric (for reference):**
- pi_6: 0.0171 (var=0.0067)
- pi_5: 0.4529 (var=0.1083)
- pi_1: -0.0108 (var=0.0045)
- pi_2: -0.4979 (var=0.0189)
- pi_3: 0.5787 (var=0.0079)
- pi_4: 0.6096 (var=0.1186)
- pi_7: 0.5908 (var=0.1650)
- pi_7_1: 0.4646 (var=0.0686)
- pi_8: 0.6133 (var=0.0696)
- pi_9: 0.4575 (var=0.2080)
- pi_10: 0.4175 (var=0.0333)

### Experiment 10
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    a_key = data["option_a_ratings"].apply(tuple)
    b_key = data["option_b_ratings"].apply(tuple)
    ones = (1, 1, 1, 1, 1)

    def anti_cue_rate(k):
        b_target = list(ones)
        b_target[k] = 0
        b_target = tuple(b_target)

        a_target = list(ones)
        a_target[k] = 0
        a_target = tuple(a_target)

        mask_b = (a_key == ones) & (b_key == b_target)
        mask_a = (a_key == a_target) & (b_key == ones)

        anti = np.concatenate([
            (data.loc[mask_b, "response"].to_numpy() == 1).astype(float),
            (data.loc[mask_a, "response"].to_numpy() == 0).astype(float),
        ])

        if anti.size == 0:
            return 0.5
        return float(anti.mean())

    r95 = anti_cue_rate(0)
    r92 = anti_cue_rate(1)
    r90 = anti_cue_rate(2)

    return r95 - 2.0 * r92 + r90

```

**Observed (real) value:** 0.0675 (var=0.0553)
**Previous candidate values (this loop):**
  - iter 1: 0.0050 (var=0.0079) (Δ vs real -0.0625)
  - iter 2: -0.0025 (var=0.0042) (Δ vs real -0.0700)
  - iter 3 (most recent): 0.0212 (var=0.0081) (Δ vs real -0.0463)
**Other theories' values on this metric (for reference):**
- pi_5: -0.0025 (var=0.0475)
- pi_6: 0.3900 (var=0.0990)
- pi_1: 0.0038 (var=0.0376)
- pi_2: -0.0063 (var=0.0516)
- pi_3: 0.0075 (var=0.0206)
- pi_4: -0.0288 (var=0.0177)
- pi_7: -0.0012 (var=0.0416)
- pi_7_1: 0.0112 (var=0.0581)
- pi_8: -0.0037 (var=0.0121)
- pi_9: 0.0050 (var=0.0442)
- pi_10: 0.0262 (var=0.0708)

### Experiment 11
**Design**
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    pos_pairs = {
        ((0, 1, 1, 0, 0, 0), (1, 0, 0, 0, 0, 1)),
        ((1, 0, 0, 0, 1, 0), (0, 1, 0, 0, 0, 1)),
        ((1, 0, 1, 0, 0, 0), (0, 1, 0, 0, 0, 1)),
        ((1, 1, 0, 0, 0, 0), (0, 0, 1, 0, 0, 1)),
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
    }
    neg_pairs = {
        ((1, 0, 0, 0, 0, 1), (0, 1, 1, 0, 0, 0)),
        ((0, 1, 0, 0, 0, 1), (1, 0, 0, 0, 1, 0)),
        ((0, 1, 0, 0, 0, 1), (1, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 1), (1, 1, 0, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
    }

    def pair_key(r):
        return (tuple(r['option_a_ratings']), tuple(r['option_b_ratings']))

    df = data.copy()
    df['_pair'] = df.apply(pair_key, axis=1)

    def subject_score(g):
        pos = g.loc[g['_pair'].isin(pos_pairs), 'response'].eq(0).mean()
        neg = g.loc[g['_pair'].isin(neg_pairs), 'response'].eq(0).mean()
        if pd.isna(pos) or pd.isna(neg):
            return np.nan
        return float(abs(neg - pos))

    scores = df.groupby('subject_id', sort=False).apply(subject_score).dropna()
    if scores.empty:
        return 0.0
    return float(scores.mean())

```

**Observed (real) value:** 0.3030 (var=0.0429)
**Previous candidate values (this loop):**
  - iter 1: 0.3600 (var=0.0604) (Δ vs real +0.0570)
  - iter 2: 0.9390 (var=0.0027) (Δ vs real +0.6360)
  - iter 3 (most recent): 0.4600 (var=0.0230) (Δ vs real +0.1570)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6370 (var=0.0065)
- pi_5: 0.4985 (var=0.0248)
- pi_1: 0.4260 (var=0.0186)
- pi_2: 0.0945 (var=0.0049)
- pi_3: 0.4940 (var=0.0078)
- pi_4: 0.4570 (var=0.0075)
- pi_6: 0.2820 (var=0.0122)
- pi_7_1: 0.4210 (var=0.0090)
- pi_8: 0.2435 (var=0.0132)
- pi_9: 0.4440 (var=0.0082)
- pi_10: 0.3600 (var=0.1011)

### Experiment 12
**Design**
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    v = np.array([0.92, 0.92, 0.65, 0.65, 0.7, 0.6, 0.5, 0.5], dtype=float)
    df = data.copy()

    def _d(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        return float(np.sum((v ** 2.0) * (a - b)))

    df['__d'] = df.apply(_d, axis=1)
    df['__pa'] = 1.0 - df['response'].astype(float)

    out = []
    for _, sub in df.groupby('subject_id', sort=False):
        orient = sub[sub['__d'].abs() >= 0.16]
        small = sub[(sub['__d'].abs() > 0.03) & (sub['__d'].abs() < 0.16)]
        if len(orient) == 0 or len(small) == 0:
            continue

        p_pos_orient = orient.loc[orient['__d'] > 0, '__pa'].mean()
        p_neg_orient = orient.loc[orient['__d'] < 0, '__pa'].mean()
        if pd.isna(p_pos_orient) or pd.isna(p_neg_orient):
            continue

        p_pos_small = small.loc[small['__d'] > 0, '__pa'].mean()
        p_neg_small = small.loc[small['__d'] < 0, '__pa'].mean()
        if pd.isna(p_pos_small) or pd.isna(p_neg_small):
            continue

        if p_neg_orient >= p_pos_orient:
            step = p_neg_small - p_pos_small
        else:
            step = p_pos_small - p_neg_small

        out.append(float(np.clip(step, 0.0, 1.0)))

    if not out:
        return float('nan')
    return float(np.mean(out))
```

**Observed (real) value:** 0.0356 (var=0.0037)
**Previous candidate values (this loop):**
  - iter 1: 0.1089 (var=0.0212) (Δ vs real +0.0733)
  - iter 2: 0.7667 (var=0.0183) (Δ vs real +0.7311)
  - iter 3 (most recent): 0.1111 (var=0.0138) (Δ vs real +0.0756)
**Other theories' values on this metric (for reference):**
- pi_5: 0.3367 (var=0.0255)
- pi_7: 0.5667 (var=0.0157)
- pi_1: 0.0500 (var=0.0053)
- pi_2: 0.0500 (var=0.0074)
- pi_3: 0.1756 (var=0.0288)
- pi_4: 0.2911 (var=0.0172)
- pi_6: 0.0667 (var=0.0098)
- pi_7_1: 0.0889 (var=0.0111)
- pi_8: 0.1200 (var=0.0219)
- pi_9: 0.0511 (var=0.0071)
- pi_10: 0.1089 (var=0.0173)

### Experiment 13
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.96, 0.94, 0.9, 0.8, 0.6, 0.6], dtype=float)

    def subject_contrast(group: pd.DataFrame) -> float:
        rows = []
        for _, row in group.iterrows():
            a = tuple(int(x) for x in row['option_a_ratings'])
            b = tuple(int(x) for x in row['option_b_ratings'])
            a_arr = np.array(a, dtype=float)
            b_arr = np.array(b, dtype=float)
            d_ref = float(np.dot(validities ** 2.0, a_arr - b_arr))
            pair = tuple(sorted((a, b)))
            orient = 0 if a < b else 1
            rows.append((pair, orient, abs(d_ref), 1.0 - float(row['response'])))

        recs = pd.DataFrame(rows, columns=['pair', 'orient', 'd_ref_abs', 'p_a'])
        means = recs.groupby(['pair', 'orient'])['p_a'].mean().reset_index()

        def gap_fn(s):
            vals = list(s)
            if len(vals) < 2:
                return float('nan')
            return abs(vals[0] - vals[1])

        gaps = means.groupby('pair')['p_a'].apply(gap_fn)
        d_ref = recs.groupby('pair')['d_ref_abs'].first()

        low = gaps[d_ref < 0.15]
        high = gaps[d_ref > 0.22]
        if low.empty or high.empty:
            return float('nan')
        return float(high.mean() - 2.0 * low.mean())

    per_subject = data.groupby('subject_id').apply(subject_contrast)
    return float(per_subject.mean())

```

**Observed (real) value:** -0.5133 (var=0.1804)
**Previous candidate values (this loop):**
  - iter 1: -0.3433 (var=0.0966) (Δ vs real +0.1700)
  - iter 2: -0.6633 (var=0.0661) (Δ vs real -0.1500)
  - iter 3 (most recent): -0.1567 (var=0.0718) (Δ vs real +0.3567)
**Other theories' values on this metric (for reference):**
- pi_7_1: 0.1783 (var=0.0467)
- pi_5: -0.1583 (var=0.0665)
- pi_1: -0.7567 (var=0.0822)
- pi_2: -0.5517 (var=0.0341)
- pi_3: -0.1083 (var=0.0701)
- pi_4: -0.0517 (var=0.0622)
- pi_6: -0.4200 (var=0.1072)
- pi_7: -0.1233 (var=0.0845)
- pi_8: -0.2817 (var=0.0855)
- pi_9: -0.4600 (var=0.1151)
- pi_10: -0.3417 (var=0.0565)

### Experiment 14
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

_V = np.array([0.95, 0.87, 0.75, 0.68, 0.65, 0.62, 0.61, 0.60, 0.60], dtype=float)
_GAMMA = 2.0
_LOW_LO = 0.015
_LOW_HI = 0.15
_HIGH_CUT = 0.17

def metric(data):
    if data.empty:
        return 0.0

    values = []
    for _, sub in data.groupby('subject_id', sort=False):
        a = np.array(sub['option_a_ratings'].tolist(), dtype=float)
        b = np.array(sub['option_b_ratings'].tolist(), dtype=float)
        d = (a - b).dot(_V ** _GAMMA)

        pa = (sub['response'].to_numpy(dtype=float) == 0.0).astype(float)

        pos_low = (d > _LOW_LO) & (d < _LOW_HI)
        neg_low = (d < -_LOW_LO) & (d > -_LOW_HI)
        if pos_low.sum() == 0 or neg_low.sum() == 0:
            continue

        contrast = float(pa[neg_low].mean() - pa[pos_low].mean())

        high_pos = pa[d > _HIGH_CUT]
        high_neg = pa[d < -_HIGH_CUT]
        if high_pos.size > 0 and high_neg.size > 0:
            hp = float(high_pos.mean())
            hn = float(high_neg.mean())
            if hp - hn > 0.0:
                contrast = -contrast

        values.append(contrast)

    if not values:
        return 0.0
    return float(np.mean(values))
```

**Observed (real) value:** 0.3889 (var=0.0632)
**Previous candidate values (this loop):**
  - iter 1: 0.5911 (var=0.0544) (Δ vs real +0.2022)
  - iter 2: 0.7067 (var=0.0178) (Δ vs real +0.3178)
  - iter 3 (most recent): 0.4611 (var=0.0260) (Δ vs real +0.0722)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2444 (var=0.0354)
- pi_7_1: 0.0022 (var=0.0196)
- pi_1: 0.6922 (var=0.0530)
- pi_2: -0.0156 (var=0.0177)
- pi_3: 0.1011 (var=0.0282)
- pi_4: 0.1178 (var=0.0185)
- pi_6: 0.0500 (var=0.0899)
- pi_7: 0.4067 (var=0.0180)
- pi_8: 0.2367 (var=0.0290)
- pi_9: 0.4044 (var=0.0170)
- pi_10: 0.0889 (var=0.1086)

### Experiment 15
**Design**
  A=[1, 1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[1, 1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[1, 0, 1, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

K1 = ((1, 1, 0, 1, 0, 1), (0, 1, 0, 1, 0, 1))
K2 = ((0, 1, 1, 1, 1, 0), (0, 0, 0, 1, 1, 0))
K3 = ((1, 0, 0, 0, 0, 1), (1, 1, 1, 0, 0, 1))
K4 = ((0, 1, 0, 1, 0, 1), (1, 1, 0, 1, 0, 1))
K5 = ((1, 0, 1, 1, 1, 0), (1, 0, 1, 0, 1, 0))
K6 = ((1, 1, 0, 0, 1, 1), (1, 1, 0, 0, 0, 0))
K7 = ((0, 1, 1, 1, 0, 0), (0, 1, 1, 1, 1, 1))
K8 = ((1, 0, 1, 0, 1, 0), (1, 0, 1, 1, 1, 0))

POSITIVE_D = {K1, K2, K5, K6}
NEGATIVE_D = {K3, K4, K7, K8}
CONCENTRATED = {K1, K4, K5, K8}
DIFFUSE = {K2, K3, K6, K7}
TARGET = CONCENTRATED | DIFFUSE


def _one_subject(s):
    conc = []
    diff = []
    all_anti = []

    for _, row in s.iterrows():
        a = tuple(int(v) for v in row['option_a_ratings'])
        b = tuple(int(v) for v in row['option_b_ratings'])
        key = (a, b)
        if key not in TARGET:
            continue

        resp = int(row['response'])
        if key in POSITIVE_D:
            anti = 1.0 if resp == 1 else 0.0
        else:
            anti = 1.0 if resp == 0 else 0.0

        all_anti.append(anti)
        if key in CONCENTRATED:
            conc.append(anti)
        else:
            diff.append(anti)

    if not conc or not diff:
        return float('nan')

    raw = float(np.mean(conc) - np.mean(diff))
    overall_anti = float(np.mean(all_anti))
    orient = 1.0 if overall_anti >= 0.5 else -1.0
    return orient * raw


def metric(data):
    vals = data.groupby('subject_id', sort=False).apply(_one_subject)
    return float(np.nanmean(vals))
```

**Observed (real) value:** -0.0050 (var=0.0048)
**Previous candidate values (this loop):**
  - iter 1: -0.0129 (var=0.0013) (Δ vs real -0.0079)
  - iter 2: -0.0088 (var=0.0005) (Δ vs real -0.0038)
  - iter 3 (most recent): 0.0033 (var=0.0007) (Δ vs real +0.0083)
**Other theories' values on this metric (for reference):**
- pi_8: 0.1862 (var=0.0079)
- pi_5: 0.0158 (var=0.0031)
- pi_1: 0.0046 (var=0.0042)
- pi_2: -0.0146 (var=0.0047)
- pi_3: -0.0062 (var=0.0069)
- pi_4: -0.0108 (var=0.0024)
- pi_6: -0.0113 (var=0.0135)
- pi_7: -0.0129 (var=0.0040)
- pi_7_1: 0.0058 (var=0.0060)
- pi_9: -0.0021 (var=0.0062)
- pi_10: -0.0383 (var=0.0068)

### Experiment 16
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    df = data.copy()
    df['a_sum'] = df['option_a_ratings'].apply(lambda x: int(np.sum(x)))
    df['b_sum'] = df['option_b_ratings'].apply(lambda x: int(np.sum(x)))
    df['tally'] = df['a_sum'] - df['b_sum']

    # The four unique pair types are fully determined by their
    # unweighted tally difference in this design.
    row_map = {-2: 1, -1: 2, 1: 3, 2: 4}
    df['row'] = df['tally'].map(row_map)

    subject_scores = []
    for sid, sdf in df.groupby('subject_id'):
        logits = []
        for r in range(1, 5):
            mask = sdf['row'] == r
            n = int(mask.sum())
            if n == 0:
                logits.append(0.0)
                continue

            n_a = int((mask & (sdf['response'] == 0)).sum())
            p_a = (n_a + 1.0) / (n + 2.0)
            p_a = min(max(p_a, 0.025), 0.975)
            logits.append(float(np.log(p_a / (1.0 - p_a))))

        subject_scores.append(float(np.var(np.asarray(logits))))

    return float(np.mean(subject_scores)) if subject_scores else 0.0
```

**Observed (real) value:** 3.6952 (var=11.4034)
**Previous candidate values (this loop):**
  - iter 1: 0.9916 (var=1.8552) (Δ vs real -2.7036)
  - iter 2: 4.3872 (var=8.6414) (Δ vs real +0.6920)
  - iter 3 (most recent): 0.5695 (var=0.5357) (Δ vs real -3.1257)
**Other theories' values on this metric (for reference):**
- pi_5: 0.4649 (var=0.1658)
- pi_8: 0.1757 (var=0.0202)
- pi_1: 3.3137 (var=5.6460)
- pi_2: 3.0912 (var=6.0805)
- pi_3: 0.1269 (var=0.0121)
- pi_4: 0.1809 (var=0.0204)
- pi_6: 0.6399 (var=0.1904)
- pi_7: 0.9564 (var=0.4665)
- pi_7_1: 0.1115 (var=0.0115)
- pi_9: 2.9995 (var=2.5515)
- pi_10: 0.9173 (var=6.1326)

### Experiment 17
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    r1 = ((1, 0, 0, 0, 0, 0, 0, 0), (0, 1, 0, 0, 0, 0, 0, 0))
    r2 = ((1, 0, 0, 0, 1, 0, 0, 0), (0, 1, 0, 0, 0, 1, 0, 0))
    r3 = ((0, 0, 1, 0, 0, 0, 0, 0), (0, 0, 0, 1, 0, 0, 0, 0))
    r4 = ((0, 0, 1, 0, 1, 0, 0, 0), (0, 0, 0, 1, 0, 1, 0, 0))
    r5 = ((0, 1, 0, 0, 0, 0, 0, 0), (1, 0, 0, 0, 0, 0, 0, 0))
    r6 = ((0, 1, 0, 0, 0, 1, 0, 0), (1, 0, 0, 0, 1, 0, 0, 0))
    r7 = ((0, 0, 0, 1, 0, 0, 0, 0), (0, 0, 1, 0, 0, 0, 0, 0))
    r8 = ((0, 0, 0, 1, 0, 1, 0, 0), (0, 0, 1, 0, 1, 0, 0, 0))

    wanted = {
        r1: ('b1', 0),
        r2: ('f1', 0),
        r3: ('b2', 0),
        r4: ('f2', 0),
        r5: ('b1m', 1),
        r6: ('f1m', 1),
        r7: ('b2m', 1),
        r8: ('f2m', 1),
    }

    labels = set(v[0] for v in wanted.values())

    def one_subject(df):
        stats = {label: [0, 0] for label in labels}
        for _, row in df.iterrows():
            key = (tuple(row['option_a_ratings']), tuple(row['option_b_ratings']))
            if key in wanted:
                label, target_resp = wanted[key]
                stats[label][0] += 1
                if row['response'] == target_resp:
                    stats[label][1] += 1

        p = {}
        for label, (n, a) in stats.items():
            p[label] = (a / n) if n > 0 else 0.5

        orient_n = stats['b1'][0] + stats['b1m'][0]
        orient_a = stats['b1'][1] + stats['b1m'][1]
        orient_p = (orient_a / orient_n) if orient_n > 0 else 0.5
        if orient_p == 0.5:
            s_global = 0.0
        else:
            s_global = 1.0 if orient_p < 0.5 else -1.0

        def e(orient_label, basic_test_label, frag_test_label):
            if p[orient_label] == 0.5:
                return 0.0
            s = 1.0 if p[orient_label] < 0.5 else -1.0
            return s * (p[frag_test_label] - p[basic_test_label])

        d1a = e('b1', 'b1m', 'f1m')
        d1b = e('b1m', 'b1', 'f1')
        d2a = s_global * (p['f2'] - p['b2'])
        d2b = s_global * (p['f2m'] - p['b2m'])

        return 0.25 * (d1a + d1b + d2a + d2b)

    values = [one_subject(g) for _, g in data.groupby('subject_id', sort=False)]
    return float(np.mean(values)) if values else 0.0
```

**Observed (real) value:** 0.0233 (var=0.0233)
**Previous candidate values (this loop):**
  - iter 1: 0.2492 (var=0.0133) (Δ vs real +0.2258)
  - iter 2: 0.0208 (var=0.0033) (Δ vs real -0.0025)
  - iter 3 (most recent): 0.1313 (var=0.0133) (Δ vs real +0.1079)
**Other theories' values on this metric (for reference):**
- pi_9: 0.1933 (var=0.0105)
- pi_5: 0.0000 (var=0.0080)
- pi_1: 0.0075 (var=0.0071)
- pi_2: 0.0004 (var=0.0076)
- pi_3: -0.0008 (var=0.0076)
- pi_4: -0.0162 (var=0.0112)
- pi_6: 0.0371 (var=0.0073)
- pi_7: -0.0125 (var=0.0078)
- pi_7_1: -0.0008 (var=0.0093)
- pi_8: 0.1571 (var=0.0107)
- pi_10: -0.0087 (var=0.0095)

### Experiment 18
**Design**
  A=[0, 1, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0, 1]
  A=[0, 1, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    t5_a = (0, 0, 1, 0, 0, 0, 0)
    t5_b = (0, 0, 0, 1, 0, 0, 0)
    t6_a = (0, 1, 1, 0, 0, 0, 0)
    t6_b = (1, 0, 0, 0, 0, 0, 0)
    t9_a = (0, 0, 0, 1, 0, 0, 0)
    t9_b = (0, 0, 1, 0, 0, 0, 0)
    t10_a = (1, 0, 0, 0, 0, 0, 0)
    t10_b = (0, 1, 1, 0, 0, 0, 0)

    a_key = data['option_a_ratings'].apply(tuple)
    b_key = data['option_b_ratings'].apply(tuple)

    def prop_a(ta, tb):
        mask = (a_key == ta) & (b_key == tb)
        sub = data.loc[mask, 'response']
        if len(sub) == 0:
            return 0.0
        return float(1.0 - sub.mean())

    p5 = prop_a(t5_a, t5_b)
    p9 = prop_a(t9_a, t9_b)
    p6 = prop_a(t6_a, t6_b)
    p10 = prop_a(t10_a, t10_b)

    return float((p5 - p9) + (p6 - p10))

```

**Observed (real) value:** 0.1600 (var=0.8156)
**Previous candidate values (this loop):**
  - iter 1: 0.2025 (var=0.4049) (Δ vs real +0.0425)
  - iter 2: 0.2350 (var=0.4604) (Δ vs real +0.0750)
  - iter 3 (most recent): 0.2125 (var=0.2302) (Δ vs real +0.0525)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1150 (var=0.1518)
- pi_9: 0.6925 (var=0.3139)
- pi_1: -1.3825 (var=0.1965)
- pi_2: 0.6950 (var=0.0720)
- pi_3: 0.1275 (var=0.1328)
- pi_4: 0.1550 (var=0.1422)
- pi_6: 0.5725 (var=0.1194)
- pi_7: 0.2650 (var=0.3248)
- pi_7_1: 0.0225 (var=0.1373)
- pi_8: 0.1300 (var=0.1868)
- pi_10: -0.4050 (var=0.4260)

### Experiment 19
**Design**
  A=[1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    subject_scores = []
    for _, sub in data.groupby('subject_id', sort=False):
        a = np.asarray(sub['option_a_ratings'].tolist(), dtype=float)
        b = np.asarray(sub['option_b_ratings'].tolist(), dtype=float)
        tallies = (a - b).sum(axis=1)
        choose_a = (sub['response'].to_numpy(dtype=float) == 0.0).astype(float)
        pos = tallies > 0.5
        neg = tallies < -0.5
        if not (np.any(pos) and np.any(neg)):
            continue
        p_pos = float(np.mean(choose_a[pos]))
        p_neg = float(np.mean(choose_a[neg]))
        subject_scores.append(max(0.0, p_pos - p_neg))
    if not subject_scores:
        return 0.0
    return float(np.mean(subject_scores))
```

**Observed (real) value:** 0.0000 (var=0.0000)
**Previous candidate values (this loop):**
  - iter 1: 0.0400 (var=0.0050) (Δ vs real +0.0400)
  - iter 2: 0.4775 (var=0.0587) (Δ vs real +0.4775)
  - iter 3 (most recent): 0.0362 (var=0.0031) (Δ vs real +0.0362)
**Other theories' values on this metric (for reference):**
- pi_9: 0.6279 (var=0.0190)
- pi_10: 0.0637 (var=0.0053)
- pi_1: 0.6829 (var=0.0641)
- pi_2: 0.7000 (var=0.0303)
- pi_3: 0.1029 (var=0.0073)
- pi_4: 0.1617 (var=0.0111)
- pi_5: 0.2800 (var=0.0183)
- pi_6: 0.0192 (var=0.0019)
- pi_7: 0.3588 (var=0.0335)
- pi_7_1: 0.0313 (var=0.0029)
- pi_8: 0.0592 (var=0.0043)

### Experiment 20
**Design**
  A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.95, 0.80, 0.79, 0.78, 0.76, 0.50], dtype=float)
    rows = data[['option_a_ratings', 'option_b_ratings', 'response']].dropna().copy()
    if rows.empty:
        return float('nan')

    a = np.vstack([np.asarray(x, dtype=float) for x in rows['option_a_ratings'].tolist()])
    b = np.vstack([np.asarray(x, dtype=float) for x in rows['option_b_ratings'].tolist()])
    weighted = (a - b).dot(validities)

    resp = rows['response'].to_numpy(dtype=float)
    high_choice = np.where(
        weighted > 0.0,
        1.0 - resp,
        np.where(weighted < 0.0, resp, np.nan)
    )

    valid = high_choice[np.isfinite(high_choice)]
    if valid.size == 0:
        return float('nan')
    return float(valid.mean())

```

**Observed (real) value:** 0.3500 (var=0.0094)
**Previous candidate values (this loop):**
  - iter 1: 0.3588 (var=0.0550) (Δ vs real +0.0088)
  - iter 2: 0.1983 (var=0.0120) (Δ vs real -0.1517)
  - iter 3 (most recent): 0.3692 (var=0.0178) (Δ vs real +0.0192)
**Other theories' values on this metric (for reference):**
- pi_10: 0.5673 (var=0.0258)
- pi_9: 0.3577 (var=0.0098)
- pi_1: 0.8475 (var=0.0096)
- pi_2: 0.4892 (var=0.0026)
- pi_3: 0.4681 (var=0.0030)
- pi_4: 0.4533 (var=0.0034)
- pi_5: 0.4304 (var=0.0055)
- pi_6: 0.5277 (var=0.0021)
- pi_7: 0.3540 (var=0.0075)
- pi_7_1: 0.5110 (var=0.0021)
- pi_8: 0.3673 (var=0.0138)

## PREVIOUS CANDIDATE (this loop)
The RUNNING-BEST (last ACCEPTED) candidate in this critique loop — i.e. the source the loop's accept gate kept as the best base so far. If your most recent attempt was REJECTED by the gate, this is NOT that attempt; it is the previously-accepted base the gate rolled back to. Iterate on this source — the next critic feedback should be applied on top of it.

**Description**
Evidence-complexity-gated compressive anti-validity integration with a small negative unweighted-tally leak (ECAVI-leak). Subjects form a validity-weighted difference D = sum_j v_j^gamma (A_j - B_j), pass it through a soft-sign transform D/(tau + |D|), and mostly apply an anti-validity sign. The evidence signal is multiplicatively gated by fragmentation, exp(-rho * max(0, n_disc - 2)), so trials with many disagreeing expert cues dilute toward chance, while low-fragmentation trials retain the anti-validity gradient. A small negative unweighted-tally leak keeps some count-based structure on fragmented displays without becoming a strong switch. A minority of subjects remain validity-consistent. Choices are stochastic through a lapse-mixture sigmoid.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    """Evidence-complexity-gated compressive anti-validity integration
    with a small negative unweighted-tally leak.

    D = sum_j v_j^gamma * (A_j - B_j)
    psi(D) = D / (tau + abs(D))
    score = (sign * lambda * psi(D) + bias) * exp(-rho * max(0, n_disc - 2))
            + eta * mean(A_j - B_j)
    p(A) = lapse/2 + (1 - lapse) * sigmoid(beta * score)

    Most subjects use sign = -1; a minority draw sign = +1.
    history is ignored because there is no trial-by-trial feedback.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            'ECAVI-leak expects a (2, n_features) stimulus; got shape '
            + str(stim.shape) + '.'
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters['validities'], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f'validities length {v.size} does not match n_features {a.size}.'
        )

    gamma = float(parameters['gamma'])
    tau = float(parameters['tau'])
    lam = float(parameters['lambda'])
    beta = float(parameters['beta'])
    rho = float(parameters['rho'])
    lapse = float(parameters['lapse'])
    bias = float(parameters['bias'])
    p_positive = float(parameters['p_positive'])
    sign_draw = float(parameters['sign_draw'])
    eta = float(parameters['eta'])

    # Latent sign mixture: most subjects invert validity-weighted evidence;
    # a minority use validity-consistent responding.
    sign = 1.0 if sign_draw < p_positive else -1.0

    diff = a - b

    # Validity-weighted feature difference.
    D = float(np.dot(np.power(v, gamma), diff))

    # Evidence fragmentation gate: number of disagreeing features beyond two.
    n_disc = int(np.count_nonzero(diff))
    gain = float(np.exp(-rho * max(0.0, float(n_disc) - 2.0)))

    # Compressive evidence transform.
    psi = D / (tau + abs(D))

    # Small negative unweighted tally leak; this is not a strong switch.
    T = float(np.mean(diff))

    score = (sign * lam * psi + bias) * gain + eta * T
    z = float(beta * score)

    # Numerically stable sigmoid for p(A | score).
    if z >= 0.0:
        p_a_core = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        p_a_core = ez / (1.0 + ez)

    # Uniform lapse mixture over the two options.
    p_a = (1.0 - lapse) * p_a_core + lapse / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)


`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0 or not np.isfinite(p).all():
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))


`parameters`:
- gamma: [1.0, 2.5]
- tau: [0.20, 0.35]
- lambda: [1.5, 2.5]
- beta: [2.5, 3.5]
- rho: [0.30, 0.60]
- lapse: [0.00, 0.05]
- p_positive: [0.00, 0.30]
- sign_draw: [0.0, 1.0]
- bias: [-0.04, 0.04]
- eta: [-0.04, -0.02]
- validities: validities

`rationale`: This is a minimal edit of the accepted ECAVI base. It adds a small negative unweighted-tally leak (eta in [-0.04, -0.02]) while keeping |eta| < 0.05, as the most recent feedback requested to recover Exp1 and contribute to Exp16/Exp17. The fragmentation gate is retained exactly as in the base: no gain floor, n_disc0 = 2, exponential decay with rho now 0.30-0.60 so fragmented trials actually dilute toward chance. Response gain is reduced by narrowing lambda to 1.5-2.5, beta to 2.5-3.5, and tau to 0.20-0.35, which should prevent the ceiling effects (Exp3, Exp4, Exp9, Exp11, Exp12, Exp14) that caused the previous over-softened candidate to be rejected. Bias and lapse are tightened for more consistent subject-level behavior. No mechanistic family change is introduced.

## PRIOR FEEDBACK ITERATIONS
The critic's verdicts on each previous in-loop candidate, in order. Each block ends with an **Outcome of this advice** line saying whether the candidate the proposer produced AFTER this advice was ACCEPTED (loss strictly beat the running best) or REJECTED (the gate discarded it). Address the most recent iteration's feedback in your next edit, but down-weight past advice whose candidates were REJECTED.

### Iteration 1
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed ECAVI architecture: validity-weighted compressive evidence, anti-validity sign mixture, lapse, stochastic choice, and an exponential fragmentation gate with no strong tally switch. It matches several near-zero or sign-based metrics well, including Exp2, 5, 6, 7, 8, 10, 11, 15, 18, and 20. However, systematic misses remain on the larger structured contrasts. Exp1 is the clearest failure: real -0.4323 versus simulated -0.0949; the gate pushes all n_disc=6 rows toward chance, but humans still show a strong tally-related contrast. Exp3 (0.3622 vs 0.2094), Exp4 (0.5300 vs 0.2933), and Exp13 (-0.5133 vs -0.3433) are consistently under-shot by 30-45%, all designs where the fragmentation gate is active on moderate disagreement counts. Exp14 is over-shot when the gate is inactive (0.3889 vs 0.5911). Exp16 has a large failure in logit spread: 3.6952 real versus 0.9916 simulated, indicating modeled choices are too compressed across tally rows. Exp17 (0.0233 vs 0.2492) shows the gate manufacturing a fragmentation effect that human data do not contain. The per-subject variance is also too high in several experiments, e.g. Exp4 0.2637 vs 0.0883 and Exp9 0.2098 vs 0.0611. Overall the current parameter distribution is miscalibrated rather than the mechanism family being wrong.
Rationale: Keep the ECAVI family but retune the fragmentation gate and compression. First, soften the gate substantially: raise the threshold n_disc0 from 2 closer to 3-4 and lower rho into roughly [0.05, 0.35], or replace the pure exponential with a floor such as gain = max(0.35, exp(-rho * max(0, n_disc - n_disc0))) so moderate disagreements of 4-6 cues retain real structure and Exp17's spurious basic-versus-fragmented contrast shrinks toward zero. Second, restore a very small unweighted tally leak within the arbiter's bound |eta| < 0.05, with a sign tuned on Exp1, likely negative or anti-tally given the -0.4323 contrast, because the compressed validity term alone cannot recover this metric; use eta near the upper allowed magnitude to also improve Exp16's logit spread. Third, increase large-D logit variation without reintroducing the tally switch: widen tau toward 0.3-0.8 so the soft-sign is less saturated for typical D values and/or push beta and lambda to their upper recommended values such as beta 4-5 and lambda 3-4, while checking Exp14 to avoid over-strength. A narrower p_positive or lower lapse may also help restore per-subject consistency. Do not switch mechanism families; these are parameter-range and gain-shape adjustments inside the prescribed ECAVI structure.

**Outcome of this advice:** iter 1 candidate loss=0.1754 -> iter 2 candidate loss=0.2339 -> the gate marked it REJECTED.

### Iteration 2
Verdict: regenerate
Interpretation: The candidate remains inside the prescribed evidence-complexity-gated anti-validity family, but the current parameterization is strongly over-calibrated. It made real progress on a few previously weak experiments: Exp1 moved from -0.095 to -0.483 against a real value of -0.432, Exp16 logit spread moved from 0.99 to 4.39 against 3.70, and Exp17 moved from 0.249 to 0.021 against 0.023. Several near-zero metrics also remain good, including Exp5, Exp6, Exp7, Exp15, and Exp18. However, the same retuning causes severe over-shooting or under-shooting on the large structured effects. Exp3 is now 0.704 vs real 0.362, Exp4 is 0.858 vs 0.530, Exp9 is 0.818 vs 0.601, Exp11 is 0.939 vs 0.303, Exp12 is 0.767 vs 0.036, Exp14 is 0.707 vs 0.389, Exp19 is 0.478 vs 0.000, and Exp20 is 0.198 vs 0.350. This is the signature of too much response gain on weakly/moderately dissimilar displays and not enough dilution on highly fragmented displays. The gain floor of 0.30-0.60, n_disc0 of 3-4, and rho of 0.05-0.35 effectively disable the intended fragmentation gate on exactly the fragmented rows it was meant to push toward chance; Exp19 with very high disagreement still produces a large contrast. The upward shift in lambda and beta also makes small-D trials too informative, which drives the Exp12 and Exp14 failures and the near-ceiling values in Exp11. Between-subject variance is also miscalibrated in several places, e.g. Exp3 var 0.456 vs 0.098 and Exp4 var 0.218 vs 0.088, consistent with strongly separated anti-sign and positive-sign subjects operating at too high a slope.
Rationale: The previous push to soften the gate and increase lambda/beta was followed but the resulting candidate was rejected by the accept gate, so do not continue in that direction. On top of the accepted base, keep the useful anti-tally leak, since it rescued Exp1 and contributed to Exp16 and Exp17, but retune the gain and gate toward an intermediate calibration. First, set n_disc0 back to 2, move rho into roughly 0.30-0.60, and remove or sharply cap the constant gain floor near 0.05 so fragmented trials actually get diluted; this should fix Exp19 and reduce the spurious contrast in Exp12 without fully returning to the earlier over-diluted version, because the anti-tally leak now provides structure in Exp1 and Exp16. Second, pull lambda down to about 1.5-2.5 and beta down to about 2.5-3.5, keeping tau around 0.20-0.35. This directly attacks the ceiling effects in Exp3, Exp4, Exp9, Exp11, Exp12, and Exp14, and should push Exp20 back toward 0.35. Third, keep eta inside the allowed small range but pin it near -0.03 rather than letting it sample all the way to -0.05, so it remains a leak and not a second strong source of contrast. Finally, tighten the bias/lapse ranges and consider only a small upward nudge of p_positive if Exp20 remains too anti after lowering the response slope. Do not switch mechanism families; this is a return of the gating parameters toward the prescribed ranges and a reduction of the score scale, interpolating between the accepted base and the rejected over-softened version rather than repeating either extreme.

**Outcome of this advice:** iter 2 candidate loss=0.2339 -> iter 3 candidate loss=0.1671 -> the gate marked it ACCEPTED.

### Iteration 3 (most recent — address this)
Verdict: regenerate
Interpretation: The candidate is faithful to the prescribed evidence-complexity-gated anti-validity family: it keeps the validity-weighted compressive core, the exponential fragmentation gate on n_disc, a mostly anti-validity sign mixture, lapse, stochastic choice, and only a small negative unweighted-tally leak. It also implements the most recent calibration move correctly: n_disc0 = 2, no gain floor, rho 0.30-0.60, reduced lambda/beta, and a small negative eta. Many experiments now fit well: Exp2 is essentially exact (-0.2646 vs -0.2650), Exp3 (-0.0206), Exp4 (-0.0517), Exp7 (+0.0120), Exp8 (+0.0089), Exp14 (+0.0722), Exp15 (+0.0083), Exp18 (+0.0525), Exp19 (+0.0362), and Exp20 (+0.0192) are all close. This is clearly the best overall calibration so far, consistent with the accepted loss of 0.1671.

However, the failures are not random noise. They form a coherent pattern: heavily fragmented rows that nonetheless carry large validity or tally structure are being over-diluted, while some low-to-moderate evidence rows remain too steep. Exp16 is the most severe miss: the per-subject logit variance is 0.5695 against 3.6952 observed, meaning the model compresses choices across the four tally rows almost to chance. Exp1 is still too weak at -0.1919 vs -0.4323, and Exp13 has regressed to -0.1567 vs -0.5133. Both are designs where the diagnostic rows have n_disc of 3 or more and nonzero tally structure, so the pure exponential gate deletes exactly the structure the data demand. At the same time, Exp17 remains too positive (+0.1079), Exp11 is over by +0.1570, Exp12 is over by +0.0756, and Exp9 is under by -0.1167 with excessive subject variance (0.3942 vs 0.0611). So the gate-to-leak balance is still miscalibrated rather than the mechanism family being wrong.
Rationale: Regenerate, but with a narrow in-family edit. Do not repeat the earlier rejected direction of globally softening the gate or raising lambda/beta; the current low-gain calibration is the accepted base and has fixed several previous over-shoots. The key new move should be to restore structure specifically on fragmented trials by making the small tally leak fragmentation-contingent. Keep the score as (sign * lambda * D/(tau + |D|) + bias) * exp(-rho * max(0, n_disc - 2)) + eta_eff * T, but change eta_eff from a constant to eta_eff = clip(eta * (1 + kappa * max(0, n_disc - 2)), -0.05, 0.05), with eta sampled around -0.035 to -0.05 and kappa around 0.15-0.35. This directly targets Exp1, Exp13, and Exp16, where the important rows have n_disc >= 3 and nonzero tally differences; it honors the arbiter's tiny-leak bound |eta_eff| <= 0.05; and it leaves equal-tally fragmented pairs such as Exp17 untouched because T is zero there. Exp19 should remain near zero because the leak is anti-tally and the metric clips negative tally contrasts at zero. Keep lambda, beta, tau, and rho near their current ranges while applying this leak change. Additionally, narrow p_positive to roughly 0.00-0.20 and consider lapse up to 0.08 if Exp17 or Exp12 remain too steep; this should also reduce the excessive subject variance in Exp9 without reintroducing the rejected high-gain over-shoot pattern. Do not switch mechanism families.

**Outcome of this advice:** iter 3 candidate loss=0.1671 -> next candidate accept-status=PENDING (this is the advice you are addressing now).


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
  "theory": "Evidence-complexity-gated compressive anti-validity integration with a fragmentation-contingent unweighted-tally leak (ECAVI-fl). Subjects form D = sum_j v_j^gamma (A_j - B_j), pass it through a soft-sign compressive transform D/(tau + |D|), and mostly invert validity-weighted evidence. The response is multiplicatively diluted by evidence fragmentation, exp(-rho * max(0, n_disc - 2)), so heavily fragmented displays move toward chance. A small anti-tally leak is retained but its strength grows only on fragmented displays: eta_eff = clip(eta * (1 + kappa * max(0, n_disc - 2)), -0.05, 0.05), with |eta_eff| <= 0.05, so it remains a leak and not a tally switch. A minority of subjects remain validity-consistent. Choices are stochastic through a lapse-mixture sigmoid.",
  "predict": "import numpy as np\n\n\ndef predict(parameters, state, history):\n    '''Evidence-complexity-gated compressive anti-validity integration\n    with a fragmentation-contingent tally leak.\n\n    D = sum_j v_j^gamma * (A_j - B_j)\n    psi(D) = D / (tau + abs(D))\n    gain = exp(-rho * max(0, n_disc - 2))\n    eta_eff = clip(eta * (1 + kappa * max(0, n_disc - 2)), -0.05, 0.05)\n    score = (sign * lambda * psi(D) + bias) * gain + eta_eff * T\n    p(A) = lapse/2 + (1 - lapse) * sigmoid(beta * score)\n\n    Most subjects use sign = -1; a minority draw sign = +1.\n    history is ignored because there is no trial-by-trial feedback.\n    '''\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            'ECAVI-fl expects a (2, n_features) stimulus; got shape '\n            + str(stim.shape) + '.'\n        )\n\n    a = stim[0]\n    b = stim[1]\n\n    v = np.asarray(parameters['validities'], dtype=float)\n    if v.size != a.size:\n        raise ValueError(\n            f'validities length {v.size} does not match n_features {a.size}.'\n        )\n\n    gamma = float(parameters['gamma'])\n    tau = float(parameters['tau'])\n    lam = float(parameters['lambda'])\n    beta = float(parameters['beta'])\n    rho = float(parameters['rho'])\n    lapse = float(parameters['lapse'])\n    bias = float(parameters['bias'])\n    p_positive = float(parameters['p_positive'])\n    sign_draw = float(parameters['sign_draw'])\n    eta = float(parameters['eta'])\n    kappa = float(parameters['kappa'])\n\n    # Latent sign mixture: most subjects invert validity-weighted evidence;\n    # a minority use validity-consistent responding.\n    sign = 1.0 if sign_draw < p_positive else -1.0\n\n    diff = a - b\n\n    # Validity-weighted feature difference.\n    D = float(np.dot(np.power(v, gamma), diff))\n\n    # Evidence fragmentation gate: number of disagreeing features beyond two.\n    n_disc = int(np.count_nonzero(diff))\n    gain = float(np.exp(-rho * max(0.0, float(n_disc) - 2.0)))\n\n    # Compressive evidence transform.\n    psi = D / (tau + abs(D))\n\n    # Unweighted tally for the small anti-tally leak.\n    T = float(np.mean(diff))\n\n    # Fragmentation-contingent tally leak. It stays tiny (|eta_eff| <= 0.05)\n    # but is allowed to strengthen on heavily fragmented displays.\n    eta_eff = float(np.clip(\n        eta * (1.0 + kappa * max(0.0, float(n_disc) - 2.0)),\n        -0.05, 0.05\n    ))\n\n    score = (sign * lam * psi + bias) * gain + eta_eff * T\n    z = float(beta * score)\n\n    # Numerically stable sigmoid for p(A | score).\n    if z >= 0.0:\n        p_a_core = 1.0 / (1.0 + np.exp(-z))\n    else:\n        ez = np.exp(z)\n        p_a_core = ez / (1.0 + ez)\n\n    # Uniform lapse mixture over the two options.\n    p_a = (1.0 - lapse) * p_a_core + lapse / 2.0\n    p_a = float(np.clip(p_a, 0.0, 1.0))\n\n    return np.array([p_a, 1.0 - p_a], dtype=float)\n",
  "policy": "import numpy as np\n\n\ndef policy(probs):\n    p = np.asarray(probs, dtype=float)\n    if p.sum() <= 0.0 or not np.isfinite(p).all():\n        p = np.ones_like(p) / len(p)\n    else:\n        p = p / p.sum()\n    return int(np.random.choice(len(p), p=p))\n",
  "parameters": {
    "gamma": "[1.0, 2.5]",
    "tau": "[0.20, 0.35]",
    "lambda": "[1.5, 2.5]",
    "beta": "[2.5, 3.5]",
    "rho": "[0.30, 0.60]",
    "lapse": "[0.00, 0.08]",
    "p_positive": "[0.00, 0.20]",
    "sign_draw": "[0.0, 1.0]",
    "bias": "[-0.04, 0.04]",
    "eta": "[-0.05, -0.035]",
    "kappa": "[0.15, 0.35]",
    "validities": "validities"
  },
  "rationale": "This is the minimal in-family edit requested by the most recent feedback. The accepted base kept a constant small anti-tally leak, which under-supplied structure on heavily fragmented displays. The edit makes the leak fragmentation-contingent through eta_eff = clip(eta * (1 + kappa * max(0, n_disc - 2)), -0.05, 0.05), with eta in [-0.05, -0.035] and kappa in [0.15, 0.35]. This restores anti-tally structure specifically on the fragmented rows that drive Exp1, Exp13, and Exp16, while honoring the arbiter's bound |eta_eff| <= 0.05 and leaving low-fragmentation and zero-tally fragmented pairs much less affected. The fragmentation gate, compressive core, sign mixture, and stochastic choice policy are otherwise unchanged. p_positive is narrowed to 0.00-0.20 and lapse is widened to 0.00-0.08 as suggested to reduce over-steep low-evidence contrasts and excessive subject variance without reintroducing the previously rejected high-gain calibration."
}
```

## Usage

```json
{
  "input_tokens": 37608,
  "output_tokens": 6703,
  "reasoning_tokens": 4989,
  "provider": "Baidu"
}
```
