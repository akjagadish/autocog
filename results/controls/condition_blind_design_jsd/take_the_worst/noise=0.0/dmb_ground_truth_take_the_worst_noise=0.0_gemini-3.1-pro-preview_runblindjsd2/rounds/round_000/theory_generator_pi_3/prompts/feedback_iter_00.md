# feedback_iter_00

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real (human / ground-truth) data, and the value it takes on the candidate's simulated data.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the feedback is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
Your task is to determine whether the candidate captures the human/real behavior well enough across these experiments. Return a verdict:
  * "continue"   — the candidate is good enough; carry on.
  * "regenerate" — the candidate fails to capture the empirical pattern; the proposing agent must produce a new candidate, taking your rationale into account.

Justify the verdict with a concrete diagnosis (which experiments fail, in what direction, what mechanism is likely missing or miscalibrated).

## SCOPE OF YOUR CRITIQUE — STAY INSIDE THE ARBITER'S MECHANISM FAMILY
When an "## ARBITER RECOMMENDATION" block is present below, the proposer was explicitly instructed to implement the mechanism family the arbiter prescribed. Your job is to grade FIT QUALITY *within that prescribed family*, not to relitigate which family should be used — that is the arbiter's call, made one level above this loop.

Concretely:
  * If the candidate misses the data, you may push for MINOR ADJUSTMENTS that keep the prescribed mechanism intact: tightening / widening parameter ranges, adding a temperature, swapping a normalization scheme, fixing a softmax / distance metric, re-balancing attention weights, fixing a learning-rate sign, correcting a bug in the gating or recurrence, etc.
  * You MUST NOT recommend switching to a different mechanism family. Such a switch is the arbiter's prerogative; recommending it here will mislead the proposer into oscillating between families across iterations.
  * Also grade FAITHFULNESS to the recommendation explicitly: if the candidate has clearly drifted into a different family than the one prescribed, say so in the rationale and ask for a return to the prescribed family — again, with minor adjustments, not a re-design.

## ACCEPT GATE — HOW THE LOOP DECIDES WHAT TO BUILD ON NEXT
This propose-loop has a programmatic accept gate. After every iteration the candidate's `aggregate_loss` is compared against the running-best loss (`accepted_loss`):
  * `loss < accepted_loss` → ACCEPTED. The candidate becomes the new running-best base; the next iteration's proposer will build on THIS candidate.
  * `loss >= accepted_loss` → REJECTED. The base is unchanged; the next iteration's proposer will build on the SAME `accepted` candidate again, with your new feedback on top. Rejected candidates are discarded — the loop guarantees the base never regresses, so you do NOT need to ask the proposer to "revert" anything; that already happens for free.

Two consequences for your verdict:
  * If the candidate you are grading was REJECTED by the gate, returning `"continue"` is silently downgraded to `"regenerate"` (returning a worse candidate would defeat the gate). Spend your rationale on a NEW direction the proposer should try on top of the unchanged accepted base, not on defending the rejected attempt.
  * If the candidate was ACCEPTED, you can return `"continue"` to stop the loop and ship this candidate, or `"regenerate"` to keep tuning further.

## LEARN FROM YOUR OWN PAST ADVICE
When a "## YOUR PRIOR CRITIQUES" block is present below, each prior iteration ends with an "Outcome of your advice" line that says whether the next candidate the proposer produced was ACCEPTED (your advice helped — its loss strictly beat the running best) or REJECTED (your advice didn't help — the proposer discarded the result and reset to the previous accepted base). This is the loop's ground-truth signal on whether *your own previous critique was good*. Use it explicitly:
  * If a previous piece of advice was ACCEPTED, it is OK to repeat / extend it. Reinforce in the same direction.
  * If a previous piece of advice was REJECTED, do NOT repeat the same recommendation; in your new rationale, briefly acknowledge that the previous push in that direction was rejected by the gate and try a different in-family knob (or a smaller step in the same direction) instead.
  * If you find yourself oscillating (e.g. iter 1 said "increase α", iter 2 said "decrease α", iter 3 about to say "increase α" again), STOP and recommend a value between the two flanking iterations instead.
  * The "## LOSS TRAJECTORY" block at the top of the user prompt summarises the same information at the loop level — consult it before issuing a new regenerate-with-direction recommendation.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## ARBITER RECOMMENDATION (mechanism family the proposer was told to implement)
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_1`
- THEORY 2 = `pi_2`
- The recommendation below acts on THEORY 1 (= `pi_1`).

Replace Theory 1 (Take The Best) with a Weighted Additive (WADD) model. While Tallying assumes all features are weighted equally, a Weighted Additive model assumes that subjects integrate all features but weight them by their given validities. This provides a compensatory alternative to Tallying that still utilizes the explicit validity information provided in the instructions.


## CANDIDATE THEORY
People use a Weighted Additive (WADD) strategy to compare options. They compute a subjective value for each option by summing its feature values weighted by their explicit validities. Decisions are made probabilistically using a softmax function over these values, with occasional random lapses.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, stimulus, history):
    import numpy as np
    stim = np.asarray(stimulus, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(f"WADD expects a (2, n_features) stimulus; got shape {stim.shape}.")
    
    a, b = stim[0], stim[1]
    val = np.asarray(parameters["validities"], dtype=float)
    
    score_a = np.sum(a * val)
    score_b = np.sum(b * val)
    scores = np.array([score_a, score_b])
    
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    
    z = beta * (scores - np.max(scores))
    e = np.exp(z)
    p_core = e / np.sum(e)
    
    n_opts = p_core.shape[0]
    return (1.0 - epsilon) * p_core + epsilon * (np.ones(n_opts) / n_opts)

`policy(probs) -> int`:
def policy(probabilities):
    import numpy as np
    p = np.asarray(probabilities, dtype=float)
    p /= p.sum()
    return int(np.random.choice(len(p), p=p))

`parameters`:
- beta: [0.1, 20.0]
- epsilon: [0.0, 0.5]
- validities: validities

`rationale`:
Implements the Weighted Additive (WADD) model as prescribed by the arbiter. By weighting each feature by its given validity, WADD integrates all available information in a compensatory manner. This contrasts with Take The Best, which only uses the single most valid discriminating cue, and Tallying, which ignores validity magnitudes.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1 (current candidate you are grading): loss=0.3741 -> ACCEPTED
Running-best (last accepted) base: iter 1 at loss=0.3741.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 1, 0, 1]  B=[1, 0, 1, 1]
  A=[0, 0, 0, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 0, 0]  B=[1, 1, 1, 0]
  A=[1, 0, 0, 1]  B=[1, 1, 0, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[1, 1, 1, 1]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]
  A=[0, 0, 1, 0]  B=[0, 0, 0, 1]
  A=[1, 0, 1, 1]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 0]  B=[0, 0, 1, 1]
  A=[0, 0, 0, 1]  B=[1, 1, 1, 1]
  A=[1, 0, 0, 0]  B=[1, 1, 1, 0]
  A=[0, 1, 0, 0]  B=[0, 0, 0, 0]
  A=[1, 0, 1, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 0, 0]  B=[0, 1, 1, 1]

**Metric**
```python
P_REF = {'((1, 0, 0, 0), (1, 1, 1, 1))|0': 0.8544303797468354, '((1, 0, 0, 0), (1, 1, 1, 1))|1': 0.8515850144092219, '((1, 1, 0, 1), (1, 0, 1, 1))|0': 0.8507135016465422, '((1, 1, 0, 1), (1, 0, 1, 1))|1': 0.8616422947131609, '((1, 0, 0, 0), (1, 1, 1, 0))|0': 0.8434684684684685, '((1, 0, 0, 0), (1, 1, 1, 0))|1': 0.8585526315789473, '((1, 1, 1, 0), (0, 0, 1, 1))|0': 0.18723404255319148, '((1, 1, 1, 0), (0, 0, 1, 1))|1': 0.13909774436090225, '((0, 0, 0, 1), (1, 1, 0, 0))|0': 0.8309278350515464, '((0, 0, 0, 1), (1, 1, 0, 0))|1': 0.84106463878327, '((0, 0, 0, 1), (1, 1, 1, 1))|0': 0.8507042253521127, '((0, 0, 0, 1), (1, 1, 1, 1))|1': 0.8477064220183487, '((0, 1, 0, 0), (1, 1, 1, 0))|0': 0.8584070796460177, '((0, 1, 0, 0), (1, 1, 1, 0))|1': 0.8328358208955224, '((1, 0, 1, 0), (0, 0, 0, 0))|0': 0.1354625550660793, '((1, 0, 1, 0), (0, 0, 0, 0))|1': 0.13452914798206278, '((1, 0, 1, 1), (0, 0, 0, 0))|0': 0.1414048059149723, '((1, 0, 1, 1), (0, 0, 0, 0))|1': 0.15550239234449761, '((0, 1, 1, 1), (1, 0, 1, 1))|0': 0.8586309523809523, '((0, 1, 1, 1), (1, 0, 1, 1))|1': 0.8572695035460993, '((0, 1, 1, 1), (1, 1, 0, 0))|0': 0.8174442190669371, '((0, 1, 1, 1), (1, 1, 0, 0))|1': 0.8569242540168325, '((1, 1, 0, 0), (0, 1, 1, 1))|0': 0.1520935960591133, '((1, 1, 0, 0), (0, 1, 1, 1))|1': 0.1417004048582996, '((0, 1, 0, 0), (0, 0, 0, 0))|0': 0.1292817679558011, '((0, 1, 0, 0), (0, 0, 0, 0))|1': 0.12960893854748604, '((1, 0, 0, 1), (1, 1, 0, 1))|0': 0.8486547085201793, '((1, 0, 0, 1), (1, 1, 0, 1))|1': 0.8458149779735683, '((0, 0, 1, 0), (0, 0, 0, 1))|0': 0.17146974063400577, '((0, 0, 1, 0), (0, 0, 0, 1))|1': 0.13471971066907776}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.1278 (var=0.0018)
**Candidate (simulated) value:** 0.0549 (var=0.0005)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0007 (var=0.0002)
- pi_2: 0.0710 (var=0.0005)

### Experiment 2
**Design**
  A=[1, 1, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 0, 0, 0]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[1, 1, 0, 1]
  A=[0, 0, 1, 1]  B=[0, 1, 1, 0]
  A=[0, 0, 1, 1]  B=[0, 1, 0, 0]
  A=[1, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[1, 1, 1, 1]  B=[1, 1, 0, 1]
  A=[1, 1, 1, 0]  B=[0, 0, 1, 0]
  A=[1, 0, 1, 0]  B=[0, 0, 1, 1]
  A=[0, 1, 1, 1]  B=[1, 0, 1, 0]
  A=[1, 1, 0, 0]  B=[1, 0, 1, 1]
  A=[1, 1, 1, 1]  B=[1, 1, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 0, 0, 0]
  A=[1, 1, 1, 1]  B=[0, 1, 0, 1]
  A=[0, 1, 0, 0]  B=[0, 1, 0, 1]
  A=[1, 1, 1, 1]  B=[1, 0, 0, 0]

**Metric**
```python
P_REF = {'((0, 0, 1, 1), (0, 1, 0, 0))|0': 0.15658362989323843, '((0, 0, 1, 1), (0, 1, 0, 0))|1': 0.15976331360946747, '((1, 1, 0, 0), (1, 0, 1, 1))|0': 0.85766092475068, '((1, 1, 0, 0), (1, 0, 1, 1))|1': 0.8407460545193687, '((1, 1, 1, 0), (0, 0, 1, 0))|0': 0.14026602176541716, '((1, 1, 1, 0), (0, 0, 1, 0))|1': 0.14285714285714285, '((1, 0, 0, 0), (0, 0, 0, 0))|0': 0.1414496833216045, '((1, 0, 0, 0), (0, 0, 0, 0))|1': 0.16358839050131926, '((0, 0, 0, 0), (0, 1, 0, 1))|0': 0.8337531486146096, '((0, 0, 0, 0), (0, 1, 0, 1))|1': 0.852882703777336, '((0, 1, 0, 0), (0, 1, 0, 1))|0': 0.8533834586466166, '((0, 1, 0, 0), (0, 1, 0, 1))|1': 0.8027522935779816, '((1, 1, 1, 1), (1, 1, 0, 1))|0': 0.13660179640718562, '((1, 1, 1, 1), (1, 1, 0, 1))|1': 0.1810344827586207, '((1, 1, 1, 1), (0, 1, 0, 1))|0': 0.12374042724707779, '((1, 1, 1, 1), (0, 1, 0, 1))|1': 0.13941018766756033, '((0, 0, 1, 1), (0, 1, 1, 0))|0': 0.5021645021645021, '((0, 0, 1, 1), (0, 1, 1, 0))|1': 0.4897260273972603, '((0, 1, 0, 0), (1, 1, 0, 1))|0': 0.8671428571428571, '((0, 1, 0, 0), (1, 1, 0, 1))|1': 0.835, '((1, 1, 1, 1), (1, 1, 0, 0))|0': 0.12324324324324325, '((1, 1, 1, 1), (1, 1, 0, 0))|1': 0.136, '((1, 1, 1, 1), (1, 0, 0, 0))|0': 0.1130820399113082, '((1, 1, 1, 1), (1, 0, 0, 0))|1': 0.13870246085011187, '((0, 1, 1, 1), (1, 0, 1, 0))|0': 0.1437837837837838, '((0, 1, 1, 1), (1, 0, 1, 0))|1': 0.1382857142857143, '((1, 0, 1, 0), (0, 0, 1, 1))|0': 0.512396694214876, '((1, 0, 1, 0), (0, 0, 1, 1))|1': 0.5260196905766527}
def metric(data):
    import numpy as np
    def jsd2(p, q):
        # Jensen-Shannon divergence (nats) between Bernoulli(p), Bernoulli(q)
        v = 0.0
        for x, y in ((1.0 - p, 1.0 - q), (p, q)):
            m = 0.5 * (x + y)
            if x > 0:
                v += 0.5 * x * np.log(x / m)
            if y > 0:
                v += 0.5 * y * np.log(y / m)
        return float(v)
    sums, counts = {}, {}
    for _, subj in data.groupby('subject_id', sort=False):
        a = list(subj['option_a_ratings'])
        b = list(subj['option_b_ratings'])
        r = subj['response'].to_numpy(dtype=int)
        for t in range(1, len(r)):
            key = str((tuple(a[t]), tuple(b[t]))) + '|' + str(int(r[t-1]))
            sums[key] = sums.get(key, 0) + int(r[t])
            counts[key] = counts.get(key, 0) + 1
    num = den = 0.0
    for k, n in counts.items():
        num += n * jsd2(sums[k] / n, P_REF.get(k, 0.5))
        den += n
    return float(num / den) if den else 0.0

```

**Observed (real) value:** 0.0115 (var=0.0003)
**Candidate (simulated) value:** 0.0064 (var=0.0001)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0008 (var=0.0001)
- pi_1: 0.0303 (var=0.0002)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The proposed Weighted Additive (WADD) model faithfully implements the arbiter's recommendation. The model calculates the subjective value of each option by summing its features weighted by their explicit validities, followed by a softmax choice rule with an epsilon lapse rate. The aggregate loss decreased and the candidate was accepted by the gate. The fit values (0.0549 on Exp 1, 0.0064 on Exp 2) show that this compensatory strategy captures a substantial portion of the variance in human behavior without requiring single-cue determinism (as in Take The Best) or ignoring validities (as in Tallying).",
  "verdict": "continue",
  "rationale": "The candidate successfully implements the prescribed WADD mechanism, utilizing the explicit validities in a compensatory manner. The parameter ranges for beta and epsilon are appropriate, the softmax and lapse mechanisms are correctly implemented, and the candidate was accepted by the gate. No further in-family adjustments are strictly necessary."
}
```

## Usage

```json
{
  "prompt_token_count": 6931,
  "candidates_token_count": 215,
  "total_token_count": 7645
}
```
