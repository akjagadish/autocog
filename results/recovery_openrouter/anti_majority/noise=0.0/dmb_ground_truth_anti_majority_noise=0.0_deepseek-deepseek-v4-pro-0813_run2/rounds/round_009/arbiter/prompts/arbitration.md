# arbitration

## System Prompt

You are a renowned cognitive scientist arbitrating between two theories across multiple experiments in the Decision Making (Binary Features) domain.

Each experiment was proposed alongside a metric and an expected outcome. For each experiment you are shown the design, the metric, both theories' predicted metric values (from simulated data), and the observed metric value on real data. The two theories are tagged by stable labels (e.g. "pi_9" and "pi_10") and the same labels are reused on each experiment's predictions.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the arbitration is to surface theories that are task-invariant: that is, theories that can explain data across all experiments in the same domain. Perform a deep dive: which among the two theories better captures the observed data?Do not just look at the newest experiments, but look at all experiments together. If a theory is good at explaining all the data keep it. However, if the both theories are good at explaining some experiment but not all, then it might be a good idea to propose a completly new theory that can potentially explain all the data. It is often better to propose a new theory than to propose a new model. Even if one theory is clearly better than the other, instead of proposing a new model, you can propose a new theory that is a stronger competitor to the winning theory instead of proposing a new model. Only propose a new model if both theories are very good and you are confident that the new model will be better than the current one clearly distinguish the two theories.  Then issue a verdict: either "new_model" (keep the current theory description, but regenerate new predict / policy / parameter ranges such that they better capture the observed data across all experiments) or  "new_theory" (the current theory is degenerate; propose a brand-new theory that can better capture the observed data across all experiments). `target_theory_idx` is 1 if you are acting on the theory labelled "pi_9" (THEORY 1 below), or 2 if you are acting on the theory labelled "pi_10" (THEORY 2 below). Justify your choice.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## THEORY 1 — pi_9
Thresholded validity-weighted anti-validity with a zero-tally dead-zone repair and fragmented-evidence dilution. Each subject forms D = sum_j v_j^{gamma_i} (A_j - B_j). When |D| is below a subject-level ambiguity threshold theta_i, the validity signal is treated as ambiguous. If the unweighted tally is nonzero, choice is driven by that tally through omega_i with a single strong weight, exactly as in the accepted base. If the tally is exactly zero, choice remains graded via a small signed validity-derived anti-validity term psi_i * sign_i * D / (kappa_i + |D|), but this term is now diluted multiplicatively by exp(-rho_disc_i * max(0, n_disc - 2)), where n_disc is the number of discriminating features. This dilution suppresses responding for zero-tally rows with many simultaneously disagreeing features while leaving zero-tally rows with only two discriminating features untouched. When |D| >= theta_i, choice follows the mostly negative anti-validity transform sign_i * lambda_i * D / (tau_i + |D|) + bias_i. Choice probability is p(A) = lapse_i/2 + (1-lapse_i) * sigmoid(beta_i * S_i).

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np


def predict(parameters, state, history):
    """Thresholded validity-weighted anti-validity with zero-tally dead-zone repair
    and fragmented-evidence dilution.

    D = sum_j v_j^gamma * (A_j - B_j)
    T = sum_j (A_j - B_j)
    n_disc = count of features where A_j != B_j

    If |D| < theta:
        if T == 0:
            dilution = exp(-rho_disc * max(0, n_disc - 2))
            score = psi * sign * D / (kappa_dead + |D|) * dilution
        else:
            score = omega * T
    Else:
        score = sign * lam * D / (tau + |D|) + bias

    p(A) = lapse/2 + (1 - lapse) * sigmoid(beta * score)

    history is intentionally ignored because the task provides no trial-by-trial
    correctness feedback.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "Thresholded anti-validity model expects a (2, n_features) stimulus; "
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
    theta = float(parameters["theta"])
    tau = float(parameters["tau"])
    lam = float(parameters["lam"])
    beta = float(parameters["beta"])
    bias = float(parameters["bias"])
    lapse = float(parameters["lapse"])
    omega_mag = float(parameters["omega_mag"])
    p_omega_positive = float(parameters["p_omega_positive"])
    omega_sign_draw = float(parameters["omega_sign_draw"])
    p_positive = float(parameters["p_positive"])
    sign_draw = float(parameters["sign_draw"])
    psi = float(parameters["psi"])
    kappa_dead = float(parameters["kappa_dead"])
    rho_disc = float(parameters["rho_disc"])

    # Mostly negative validity-weighting sign; a minority trust the
    # validity-weighted direction.
    sign = 1.0 if sign_draw < p_positive else -1.0

    # Subject-level tally weight, mostly positive but allowing a minority of
    # subjects to use the opposite tally sign.
    omega = omega_mag if omega_sign_draw < p_omega_positive else -omega_mag

    # Subject-level validity-weighted feature difference.
    w = np.power(v, gamma)
    diff = a - b
    D = float(np.dot(w, diff))

    # Unweighted tally difference used in the dead zone.
    T = float(np.sum(diff))

    # Number of discriminating features, used only in the zero-tally branch.
    n_disc = int(np.count_nonzero(diff))

    if abs(D) < theta:
        # Ambiguous validity signal.
        if abs(T) < 1e-12:
            # Zero-tally repair: equal raw counts no longer force p(A)=0.5.
            # A small signed validity-derived anti-validity term preserves
            # graded responding when the options differ only in which cue is
            # present.  This term is diluted by a factor that shrinks
            # exponentially with the number of discriminating features beyond
            # two, so multi-feature zero-tally rows stay near chance while
            # two-feature rows keep the graded contrast.
            sat_dead = D / (kappa_dead + abs(D))
            dilution = np.exp(-rho_disc * max(0.0, float(n_disc - 2)))
            score = psi * sign * sat_dead * dilution
        else:
            # Nonzero tally drives the ambiguous-regime choice.
            score = omega * T
    else:
        # Clear validity signal: mostly negative anti-validity response through
        # a moderately saturating continuous transform.
        sat = D / (tau + abs(D))
        score = sign * lam * sat + bias

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


## THEORY 2 — pi_10
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


## EXPERIMENT 1 (proposed by pi_9)

### DESIGN
**Validities (n_features=15):** [1.0, 0.99, 0.98, 0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 0.655, 0.655, 0.655, 0.655, 0.655, 0.655]

**Trial pairs (n=6):**
  trial 1: A=[1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  trial 2: A=[0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  trial 3: A=[0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]
  trial 4: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  trial 5: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 1, 0, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]
  trial 6: A=[0, 0, 0, 0, 0, 0, 0, 0, 0, 1, 1, 1, 1, 1, 1]  B=[0, 0, 1, 1, 1, 1, 1, 1, 1, 0, 0, 0, 0, 0, 0]

**Rationale:** This design isolates the advocated theory's strong unweighted-tally fallback inside its validity dead zone from the competing theory's weak tally leak. Fifteen experts are used: three very high validities (1.00, 0.99, 0.98), six low validities (0.50), and six mid validities (0.655). In the first three unique pairs, A wins exactly one high expert plus all six low experts while B wins all six mid experts, so the unweighted tally is T = +1. The validity-weighted difference is D = a^gamma + 6*0.5^gamma - 6*0.655^gamma. For a in {1.00, 0.99, 0.98} this D stays within about [-0.12, 0.08] over gamma in [1,3], i.e. below the advocated theory's smallest threshold theta = 0.15. Thus all TAVU subjects remain in the dead zone and respond to the nonzero tally, predicting the same high A-choice probability for rows 1-3 and the complementary low probability for their A/B mirrors (rows 4-6). The competing GCAV theory has no strong tally switch: its only tally term is eta*T with T = mean(diff) = +/-1/15, so even at eta = 0.04 that term is smaller than 0.003 score units. GCAV's D-based core/repair remains small for these D values, and its tail component (gamma_tail <= 0.5, including negative exponents) makes D strongly positive on T+ rows and strongly negative on T- rows, pulling its mixture toward chance or slightly opposite to TAVU. The high-validity staircase (1.00, 0.99, 0.98) shifts GCAV's D trajectory within T-sign while leaving TAVU's tally-driven prediction unchanged, giving a within-T-sign dissociation. Thus the critical pattern is a large T-driven A/B gap for TAVU versus a compressed D/repair-driven near-chance gap for GCAV.

**Computed schedule:** 6 unique pairs × 16 reps = 96 trials per subject.



### METRIC
Rationale:
For each subject, compute the excess tendency to choose A on positive-tally trials over negative-tally trials. The advocated theory places all designed rows in its ambiguity dead zone, so the strong tally switch makes p_pos - p_neg large and positive for the large majority of subjects with positive omega. The competing theory has only a weak tally leak and its anti-validity tail component tends to produce reversals, so its signed difference is near zero or negative. Lower-clamping at zero converts those reversals and near-chance differences into near-zero subject scores rather than allowing them to cancel or inflate the competing theory's metric. Averaging this clamped per-subject score gives a large stable contrast under the advocated theory and a much smaller, low-variance contrast under the competing theory.

Source:
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

### RESULTS
- Predicted under pi_9 (simulated): 0.6279 (var=0.0190)
- Predicted under pi_10 (simulated): 0.0637 (var=0.0053)
- Observed on real data: 0.0000 (var=0.0000)

## EXPERIMENT 2 (proposed by pi_10)

### DESIGN
**Validities (n_features=6):** [0.95, 0.8, 0.79, 0.78, 0.76, 0.5]

**Trial pairs (n=8):**
  trial 1: A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  trial 2: A=[1, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  trial 3: A=[1, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  trial 4: A=[1, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  trial 5: A=[1, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  trial 6: A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 1, 0, 0, 0]
  trial 7: A=[1, 0, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0, 0]
  trial 8: A=[1, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0]

**Rationale:** This design isolates the advocated GCAV theory's negative-exponent tail component against the competing TAVU theory's strictly positive gamma and zero-tally dead-zone behavior. Six experts are used. The highest-validity expert (0.95) and lowest-validity expert (0.50) are tied filler cues: in every row the 0.95 expert gives both products 1, the 0.50 expert gives both products 0, and all non-discriminating middle experts give both products 0. Thus every unique pair is a one-versus-one swap between two middle experts, so the unweighted tally T is exactly zero and the number of discriminating features is exactly two. This turns off TAVU's nonzero-tally fallback and leaves TAVU's fragmented-evidence dilution inactive, forcing TAVU into its zero-tally graded anti-validity branch. In the first four rows the higher-validity middle expert favors A: D values at gamma=2 are approximately 0.062, 0.047, 0.032, and 0.031, all far below TAVU's smallest threshold theta=0.15, so TAVU must predict p(A)<0.5 for all four positive rows. Under central TAVU parameters (gamma=2, kappa_dead=0.10, psi=1.15, beta=2.40, lapse=0.02) the predicted p(A) values are about [0.26, 0.30, 0.34, 0.35]. The GCAV bulk component also has D below its minimum dead-zone threshold of 0.06 (maximum bulk D across gamma 1.3-1.8 is only about 0.059), so the bulk anti-validity signal is rho-attenuated near chance. Crucially, GCAV's tail component may draw a negative validity exponent; with gamma_tail=-1 the same rows have negative tail D values, e.g. 0.80^-1 - 0.76^-1 = -0.066. The near-deterministic tail (beta 4-8) therefore chooses A with high probability, lifting the GCAV mixture above 0.5: approximately [0.56, 0.56, 0.55, 0.55]. This yields a signed dissociation on every positive row: GCAV predicts an A majority while TAVU predicts a B majority. The last four rows are exact A/B mirrors, giving the complementary signed predictions. Across the positive D staircase TAVU's p(A) moves monotonically downward as D increases, whereas GCAV remains roughly flat above chance. TAVU cannot produce this majority reversal because its gamma is constrained to positive values and its positive-sign minority is at most 10%; even at the upper p_positive bound the zero-tally branch aggregate stays below 0.5. The eight unique pairs repeat 12 times for the 96-trial budget.

**Computed schedule:** 8 unique pairs × 12 reps = 96 trials per subject.



### METRIC
Rationale:
This metric is the observed rate of choosing the option supported by the more valid of the two discriminating experts. In every designed pair the 0.95 and 0.50 experts are tied fillers and exactly two middle experts disagree, so this rate isolates whether choices follow or invert the communicated validity ordering of the only informative cues. TAVU's zero-tally anti-validity branch applies a mostly negative sign to D and must therefore favor the lower-validity expert on most trials, producing a high-validity choice rate near 0.31-0.35. GCAV's bulk component stays near chance, but its tail component frequently uses negative validity exponents; with the mostly negative sign, that reverses the anti-validity direction for these rows and pushes the high-validity choice rate above chance, around 0.55. The 12 repetitions of all 8 trial types keep the per-subject estimate tight while preserving the mean dissociation.

Source:
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


### RESULTS
- Predicted under pi_9 (simulated): 0.3577 (var=0.0098)
- Predicted under pi_10 (simulated): 0.5673 (var=0.0258)
- Observed on real data: 0.3500 (var=0.0094)

## PERFORMANCE FOR THESE TWO THEORIES ON OTHER EXPERIMENTS
### Experiment 3
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
**Predicted under pi_9:** -0.2940 (var=0.0957)
**Predicted under pi_10:** -0.3300 (var=0.0375)

### Experiment 4
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
**Predicted under pi_9:** -0.4117 (var=0.0732)
**Predicted under pi_10:** -0.0387 (var=0.0345)

### Experiment 5
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
**Predicted under pi_9:** 0.6733 (var=0.1841)
**Predicted under pi_10:** 0.2683 (var=0.2451)

### Experiment 6
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
**Predicted under pi_9:** 0.5533 (var=0.0659)
**Predicted under pi_10:** 0.2400 (var=0.2617)

### Experiment 7
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
**Predicted under pi_9:** 0.0308 (var=0.0177)
**Predicted under pi_10:** 0.0700 (var=0.0217)

### Experiment 8
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
**Predicted under pi_9:** 0.1904 (var=0.0279)
**Predicted under pi_10:** 0.0942 (var=0.0434)

### Experiment 9
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
**Predicted under pi_9:** 0.0824 (var=0.0136)
**Predicted under pi_10:** 0.0259 (var=0.0370)

### Experiment 10
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
**Predicted under pi_9:** 0.2794 (var=0.0126)
**Predicted under pi_10:** 0.2703 (var=0.0237)

### Experiment 11
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
**Predicted under pi_9:** 0.4575 (var=0.2080)
**Predicted under pi_10:** 0.4175 (var=0.0333)

### Experiment 12
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
**Predicted under pi_9:** 0.0050 (var=0.0442)
**Predicted under pi_10:** 0.0262 (var=0.0708)

### Experiment 13
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
**Predicted under pi_9:** 0.4440 (var=0.0082)
**Predicted under pi_10:** 0.3600 (var=0.1011)

### Experiment 14
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
**Predicted under pi_9:** 0.0511 (var=0.0071)
**Predicted under pi_10:** 0.1089 (var=0.0173)

### Experiment 15
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
**Predicted under pi_9:** -0.4600 (var=0.1151)
**Predicted under pi_10:** -0.3417 (var=0.0565)

### Experiment 16
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
**Predicted under pi_9:** 0.4044 (var=0.0170)
**Predicted under pi_10:** 0.0889 (var=0.1086)

### Experiment 17
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
**Predicted under pi_9:** -0.0021 (var=0.0062)
**Predicted under pi_10:** -0.0383 (var=0.0068)

### Experiment 18
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
**Predicted under pi_9:** 2.9995 (var=2.5515)
**Predicted under pi_10:** 0.9173 (var=6.1326)

### Experiment 19
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
**Predicted under pi_9:** 0.1933 (var=0.0105)
**Predicted under pi_10:** -0.0087 (var=0.0095)

### Experiment 20
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
**Predicted under pi_9:** 0.6925 (var=0.3139)
**Predicted under pi_10:** -0.4050 (var=0.4260)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of which theory better captured the observed data across both experiments, and why.
- verdict: Either 'new_model' (keep the same theory description, regenerate the predict / policy / parameter-ranges) or 'new_theory' (the current theory is degenerate; propose a brand-new theory).
- target_theory_idx: Which theory the verdict acts on: 1 or 2, matching THEORY 1 / THEORY 2. If verdict='new_model', this is the theory whose predict / policy / parameter-ranges should be regenerated (description preserved); if verdict='new_theory', this is the theory that will be replaced completely.
- recommendation: If verdict='new_model': how the current predict / policy / parameter-ranges should be revised. If verdict='new_theory': a sketch of the new theory that should be proposed and how it differs from both.


## Response

```json
{
  "interpretation": "Looking across all twenty experiments, neither theory is task-invariant. pi_9 has several near-exact fits in the archive, especially Experiment 2 (.358 vs observed .350), Experiment 6 (.553 vs .530), Experiment 16 (.404 vs .389), and Experiment 17 (-.002 vs -.005), and it is generally closer overall. But its self-designed critical test, Experiment 1, is catastrophic: pi_9's unweighted tally fallback predicts .628 while real subjects give 0.000 with zero between-subject variance. That directly falsifies the one mechanism that distinguishes pi_9, not merely a parameter miss. pi_10 matches Experiment 1 much better (.064) but fails its own critical Experiment 2 badly: its negative-exponent tail predicts .567 for high-validity choices while real subjects choose them only .350, and it also severely misses Experiments 6, 16, 18, and 20. The data across the two critical tests and the larger archive are most consistent with a moderate graded anti-validity signal on the validity-weighted difference D, whose strength is attenuated when many cues disagree. There is no evidence for a strong unweighted tally switch and no evidence for negative-exponent validity reversals.",
  "verdict": "new_theory",
  "target_theory_idx": 1,
  "recommendation": "Replace pi_9 with an evidence-complexity-gated anti-validity theory. The new theory should keep pi_9's useful core: D = sum_j v_j^gamma * (A_j - B_j) with gamma > 0; score = sign * lambda * D / (tau + |D|) + bias; mostly anti-validity sign with a minority of validity-consistent subjects; lapse; and p(A) = lapse/2 + (1-lapse) * sigmoid(beta * score). It must completely remove the strong unweighted tally switch omega * T; at most a tiny tally leak with |eta| < 0.05 may remain. It must also avoid pi_10's negative or very sub-linear gamma tail. In place of the tally switch, modulate response gain by evidence fragmentation: multiply the score by exp(-rho * max(0, n_disc - 2)), where n_disc is the number of features where A_j != B_j. Suggested parameter ranges: gamma 1.0-2.5, tau 0.05-0.40, lambda 1.0-4.0, beta 2.0-5.0, rho 0.3-1.5, lapse 0.00-0.10, and p_positive 0.00-0.30. Under this theory Experiment 1 has D near zero and n_disc = 13, so dilution pushes all rows toward chance and the tally contrast metric is 0.000; Experiment 2 has n_disc = 2, so dilution is inactive and the same anti-validity core gives a high-validity choice rate near 0.35; large-D archive rows still produce strong logit variation, unlike pi_10's oversaturated mixture. Keep the stochastic choice policy unchanged."
}
```

## Usage

```json
{
  "input_tokens": 24433,
  "output_tokens": 14002,
  "reasoning_tokens": 13320,
  "provider": "Baidu"
}
```
