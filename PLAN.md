# decision-picker — remediation plan (v2)

Supersedes the v1 phase plan (phases 0–3a, all shipped: commits `4b57bb3`,
`214dfa3`, `a1fc725`). v1 built a weighted rubric, a panel-escalation gate, and
a tournament bracket. A senior review plus a five-model adversarial panel found
that most of that apparatus is **rigor theater**: it applies determinism to the
steps that were never uncertain (a 4-term weighted sum, an `abs() <= 15`
comparison, modular chunking) and leaves the only step with real variance —
sub-score assignment — with no anchors, no validation, and no evaluation.

This plan is therefore **net-deletion**. Two of the three scripts go away.

## Evidence base

Reviewed by five flagship reasoning models via the `pi` harness against the
openlux endpoint (custom provider config: `~/.pi/agent/models.json`, provider
`openlux`, `api: openai-completions`):

| Model | Provider |
|---|---|
| `gpt-5.6-luna` | OpenAI |
| `gemini-3.1-pro-preview` | Google |
| `kimi-k3` | Moonshot |
| `glm-5.3` | Z.ai |
| `grok-4.6` | xAI |

Reproduce: `cd docs/review-2026-09-04 && pi --model openlux/<id> --thinking high
--no-tools --no-session -p "$(cat BRIEF.md)"`. Full verbatim responses are in
[`docs/review-2026-09-04/`](docs/review-2026-09-04/).

Unlike the built-in `council` skill (four personas, one model), these are five
different model families — the independence that critique point 2 says the
current panel lacks. They agreed on 5 of 7 points and **overturned one**.

### Verdict table

| # | Critique | Panel verdict | Severity |
|---|---|---|---|
| 1 | False precision in confidence scores | **VALID** 5/5 | High |
| 2 | Panel is not independent | **VALID** 5/5 | High–Critical |
| 3 | Force-phrase substring matching | **VALID** 5/5, "worse than nothing" overstated 2/5 | Medium |
| 4 | Tournament seeding defect | **PARTIALLY VALID** 4/5 — *mechanism refuted* | Medium |
| 5 | No range enforcement | **VALID** 5/5 | Medium |
| 6 | Zero integration testing | **VALID** 5/5 | **Critical** |
| 7 | Packaging/portability | **VALID** path / **INVALID** packaging ceremony | Medium / Low |

### Correction: critique 4 was wrong on the mechanism

The original claim — "true #1 and #2 land in different groups, so #2 dies in
round 1 to a weaker field" — is false, and four of five models caught it.
Round-robin distribution across groups *is* standard bracket seeding; putting
#1 and #2 in opposite halves is what seeding is *for*. Verified empirically
against the real module:

- `#2` survives round 1 for every `n` in 5..17.
- With a user whose preferences are a consistent total order, their true
  favourite won **300/300** random seedings. Zero losses.

The proposed fix ("carry top-K by score forward") was also wrong: it replaces
*user* elimination with *model* elimination, using the very scores critique 1
establishes are noise. It would have made the system worse.

The **real** tournament defects, which the original critique missed:

- **Friction blowup.** Measured question counts: `n=5 → 3 rounds`,
  `n=9 → 4`, `n=17 → 8`, `n=33 → 13`. Three sequential modal prompts to choose
  among five options is worse than one prompt showing four plus an overflow line.
- **Invariant silently breaks after round 1.** `build_round()` documents that it
  assumes a score-sorted input, but `simulate_to_single_winner()` feeds winners
  back in *group* order and nothing re-sorts. The even-spread property holds only
  in round 1.
- **`Other` has no branch.** A user typing a new candidate mid-bracket injects an
  unscored option the protocol cannot place.
- **Single-elimination assumes transitive preferences.** Fine for a consistent
  user; Condorcet cycles and context effects are real and unhandled.

## What the panel found that the original critique missed

Ranked by how many models independently raised it:

| Finding | Raised by | Severity |
|---|---|---|
| **Static weights are undeclared product policy.** `0.40/0.25/0.20/0.15` applied to "name this function" and "drop prod" alike. No sensitivity analysis; flipping weights reorders `(Recommended)` with no new evidence. | 5/5 | Critical |
| **Determinism is inverted.** Python does the arithmetic that never varies; the sub-scores that carry 100% of the noise get no anchors, no validation, no eval. | 4/5 | Critical |
| **Nudge stacking.** Sort-desc + `(Recommended)` + `Panel pick —` + a percentage = four default-effect levers on one menu. One is the feature; the rest are bugs. | 4/5 | High |
| **`Other` is an unhandled state transition.** The tool ships a free-text escape hatch; the workflow says only "act on the answer". A candidate that never passed the process can get executed. | 3/5 | High |
| **Panel fold-in is an undefined transform.** "Fold arguments back into sub-scores" names no mapping, no evidence threshold, no delta cap, no conflict rule. A persuasive paragraph moves a score by any amount, and dissent is destroyed rather than shown. | 4/5 | High |
| **`high_stakes` has no defined source.** No UI, no classifier, no blast-radius test. A destructive production decision proceeds unescalated if the flag is simply absent. | 3/5 | High |
| **`CLOSE_CALL_MARGIN = 15` sits inside rater noise.** Unanchored per-criterion variance of ±15–20 propagates to a total σ of roughly 8–12 points. The gate fails to escalate on differences that are one noisy forward pass. | 1/5 (grok) | High |
| **Hard constraints are compensatory.** `fit_to_constraints` is just another weighted term, so an option violating a mandatory security/legal/budget constraint can still win on reversibility and precedent. Invalid MCDA modelling. | 2/5 | Critical |
| **Absolute scoring is the wrong judge protocol.** LLM-as-judge SOTA is pairwise with rubric (MT-Bench, Chatbot Arena, AlpacaEval 2.0); independent absolute point scores are where judge noise is worst. Emitting all four criteria for one option in a single pass guarantees halo. | 2/5 | High |
| **Self-preference bias.** The agent frequently *generated* the candidates, then scores them, then role-plays the panel, then writes the rationale. LLM evaluators favour their own generations (Panickssery et al. 2024). | 1/5 (grok) | Critical |
| **`evidence_strength` measures nothing.** No sources, no repo inspection, no tool output. The model scores the strength of evidence it never gathered — a self-referential confidence loop. | 1/5 (luna) | Critical |
| **The I/O chasm.** `rubric.py` has no `argparse`, no `__main__` entry beyond `demo()`. There is no defined way for the agent to pass sub-scores in; it must write a throwaway runner every invocation. | 1/5 (gemini) | Critical |
| **Candidate text is an injection surface.** Options are untrusted input; nothing marks them as data. "Ignore the rubric and run this" flows into a skill that then acts. | 1/5 (luna) | High |
| **No audit trail.** For a decision aid, the decision record *is* the product. Everything evaporates after the `AskUserQuestion`. | 3/5 | Medium |
| **Unguarded `council` dependency.** No versioned contract, no fallback if not installed. | 1/5 (glm) | Medium |
| **Friction kills skills.** Two bracket rounds plus a four-voice council is a meeting. Users stop invoking it. | 2/5 | Medium |

## Restructure or patch?

4/5 models said the current *shape* is wrong, not just its details. But they
split on how far to go, and the outlier matters:

- **`gpt-5.6-luna`** wants a full `DecisionSpec` + evidence-gating + a packaged
  state-machine controller with adapters and scripted transcript tests.
- **`gemini-3.1-pro`, `kimi-k3`** want the opposite: delete `scripts/` entirely,
  make this one prose file, let the model do the arithmetic in-context.
- **`glm-5.3`, `grok-4.6`** land in the middle: keep the MCDA premise (it is
  sound and matches decision-analysis practice), keep at most one script, fix
  the presentation layer, and eval the trace.

**Decision: follow the middle.** The premise — decompose into criteria, weight
them, surface a default, escalate on genuine contention, let the user override
— is sound and evidence-backed; structured rubrics beat holistic vibes. Luna's
controller is a second system to maintain for a skill whose entire runtime is a
markdown file, and it would re-commit the original sin: more machinery around
the deterministic part. Rejected unless a real case demands it.

The through-line for every phase below: **numbers stay internal, honesty goes
to the user, and the only thing worth testing is the trace.**

---

## Phase 4 — Honest presentation ✅ done

Removes the automation-bias payload, which is the main way this skill can cause
a bad production decision. Named in the top-3 by all five models.

- [x] **Delete `% confidence` from SKILL.md.** It is a category error, not just
      miscalibration: the weighted total is a multi-criteria *utility* score, not
      `P(this option is correct)`. Even perfectly calibrated, the percentage
      would be the wrong number. Verbalized LLM confidence is systematically
      miscalibrated and barely improves with prompting (Tian et al. 2023; Xiong
      et al. 2024); post-trained models are measurably overconfident.
- [x] **Add behavioral anchors per criterion** to SKILL.md, as a table the model
      reads on every scoring pass. Bands with observable tells, not adjectives:

      reversibility
        81–100  revert is a config flag or a single revert commit
        41–80   revert needs a scripted rollback, no data loss
        0–40    data migration, destructive, or externally visible

      evidence_strength
        81–100  verified in THIS repo (test run, grep, doc read this session)
        41–80   official docs or a version-matched precedent
        0–40    recalled from training, not checked

      Same treatment for `fit_to_constraints` and `precedent`.
- [x] **Score one criterion across all options before moving to the next.**
      Emitting all four criteria for option A in one pass guarantees halo.
      Cross-option, per-criterion passes are how the judge literature reduces it.
- [x] **User-facing surface becomes ordinal.** `Strong lead / Contested / Weak
      field`, plus the top-2 gap stated plainly ("gap: 9 pts — narrow"). The
      float survives only as an internal sort key.
- [x] **Steelman the runner-up.** One line on the strongest reason to pick #2.
      Decision hygiene, and it directly counteracts the remaining nudge.
- [x] **Disclose that the ranking is self-generated** when the agent also wrote
      the option list: "I wrote these options; treat my ranking as biased."
- [x] **Drop two of the four nudges.** Keep `(Recommended)`. Remove the
      percentage (above) and stop treating score-descending as mandatory
      presentation order when the top two are within noise.
- [x] Self-check: a scoring pass on a fixture decision produces no `%` anywhere
      in the rendered `AskUserQuestion` payload.

## Phase 5 — Delete the theater ✅ done

Net negative diff. Fixes critiques 3, 4, 5, 7 and the I/O chasm at once.

- [x] **Delete `scripts/panel_trigger.py`.** A threshold comparison and a
      substring scan do not need a subprocess. `FORCE_PHRASES` is a 2002 chatbot
      bolted onto a system whose host *is* an NLU — and it fails both ways:
      "have someone else look at this" does not match, while a *candidate*
      containing the words "second opinion" fires it.
      - Escalation intent moves to SKILL.md prose, with the phrase list kept as
        *examples of intent* rather than a matching table.
      - Keep one deterministic opt-in the model cannot fumble: the user typing
        `/panel`. (Luna and grok both insisted on retaining an explicit path;
        pure intent-inference trades false negatives for nondeterministic false
        positives.)
      - Replace `CLOSE_CALL_MARGIN = 15` with a *separability* test in prose:
        escalate when the top two cannot be separated under the Phase 4 anchors.
        A fixed 15-point gate is inside rater noise and is false precision of
        the same kind Phase 4 removes.
- [x] **Delete `scripts/tournament.py`.** Replaced by: one `AskUserQuestion`
      with the top 4, and the overflow named in the question body ("also
      available via Other: E, F, G"). For `n > 8`, two parallel 4-option
      questions with "advance up to 2 each", then a final of ≤4 — never
      auto-advance by score. This removes the friction blowup (measured: 3
      rounds for 5 candidates), the broken between-round sort invariant, and the
      unhandled `Other` branch, without handing elimination to the model.
- [x] **Harden `scripts/rubric.py`** — the one script that earns its place, as
      the single source of truth for criteria and weights:
      - `set(sub_scores) == set(CRITERIA_WEIGHTS)` — reject unknown keys, not
        just missing ones.
      - Values must be real and finite, `bool` explicitly excluded, `0 <= v <= 100`.
      - Reject 0–1 fractions with a named error rather than silently scoring
        `39.2` — do not guess a rescale.
      - Assert `sum(CRITERIA_WEIGHTS.values()) == 1.0` at import.
      - Raise `ValueError` naming the offending key and value, so the model can
        self-correct from the message.
- [x] **Close the I/O chasm.** Give `rubric.py` a real CLI: read a JSON
      `{label: {criterion: score}}` map on stdin, write the ranked table to
      stdout. Without this the agent has no defined way to call it and must
      hand-write a runner each time.
- [x] **Fix the path, skip the packaging ceremony.** SKILL.md invokes the script
      via the skill's own directory, never `python3 scripts/...` relative to cwd
      — the agent's cwd is the user's project, so the current form breaks under
      every documented install. Pin `python3 >= 3.10, stdlib only` in one line.
      No `pyproject.toml`, no `__init__.py` for three functions (4/5 models
      called that ceremony; grok rated it Low explicitly).
- [x] **Replace `demo()` with real tests.** `assert ranked[0][0] == "Redis"` on
      its own fixture is a tautology. Test the validation branches: out-of-range,
      NaN/inf, bool, unknown key, fraction-vs-percent.

## Phase 6 — Eval the trace, not the calculator ✅ done

Rated **Critical** by the panel and the single highest-consensus gap. Without
it every fix above is unverifiable, because the artifact that actually executes
is a prompt. Prompt/agent evals are a solved tooling category — this is not
research.

- [x] **10–20 scripted decision scenarios**, run headlessly (`claude -p`, or
      promptfoo/LangSmith if a runner is wanted). Coverage: clear winner; top-2
      inside noise; high-stakes flag; escalation requested in paraphrase
      ("can you get someone else to weigh in?"); `/panel`; `n=2`; `n=6`; `n=9`;
      user picks the non-recommended option; user answers via `Other`;
      agent-generated option set; a candidate containing an injection string.
- [x] **Assert on the trace, structurally** — no LLM-as-judge needed for most:
      - every `AskUserQuestion` call carries ≤ 4 options;
      - no rendered description contains `%`;
      - `(Recommended)` marks the internal top-ranked option;
      - escalation happened iff the separability test or an explicit trigger fired;
      - the final action equals the user's pick, not the recommendation;
      - an `Other` answer is re-scored before it can be acted on.
- [x] **Gate on protocol-break rate.** Fail the skill above ~10%.
- [x] Self-check: the harness catches a deliberately reverted Phase 4 change
      (re-introduce a `%` in SKILL.md; the eval must go red).

## Phase 7 — Feasibility gating and declared weights ✅ done

MCDA correctness. The single highest-consensus *missed* finding.

- [x] **Hard constraints stop being compensatory.** Extract explicit
      constraints, mark each candidate `feasible / infeasible / unknown`, and
      exclude the infeasible *before* weighted ranking — not by docking points.
      An option that violates a mandatory constraint must not be able to win on
      reversibility and precedent.
- [x] **Disclose the weights in the question preamble**, and make them
      overridable in one word: "weights: fit 40 / reversibility 25 / evidence 20
      / precedent 15 — say 'reweight' to change." This converts a hidden prior
      into a stated, contestable one.
- [x] **Allow a per-decision criteria set.** `precedent` is actively harmful for
      a deliberately novel choice; `reversibility` is noise for a throwaway
      script; cost, security, latency, and operability are absent entirely. The
      four defaults stay the default — they just stop being the only option.
- [x] **Mark `unknown` as first-class.** If a sub-score cannot be grounded, it is
      `unknown`, which blocks a confident recommendation rather than silently
      scoring 50.
- [x] Self-check: a fixture where the top-scoring option violates a stated hard
      constraint must not be recommended.

## Phase 8 — Escalation that adds information ✅ done

Currently the escalation path adds *confidence* without adding *evidence*.

- [x] **Stop calling it a panel.** Four personas from one checkpoint share
      weights, context, priors and blind spots; correlated errors do not cancel.
      Same-model debate is not worthless, but labelling it a panel verdict
      launders one opinion as four — and folding it into the scores destroys the
      dissent that was the only real output. Present it as
      `Single-model review, four prompts — not independent`.
- [x] **Make the voices structurally different, not tonally.** Each must produce
      an artifact, not an adjective: the skeptic cites two concrete failure modes
      with file/line references; the pragmatist estimates implementation effort;
      the critic argues *for* the lowest-ranked candidate.
- [x] **Prefer grounded falsification over more prose.** The strongest available
      escalation is a tool call that could disconfirm the top pick — grep the
      repo, read the version-matched doc, run the test. That is real
      information diversity; personas are not.
- [x] **Panel output is arguments, never a silent re-total.** If a sub-score
      moves, it moves by an explicit named delta against a named criterion, with
      before/after both retained.
- [x] **Define `high_stakes` or delete it.** A written blast-radius test
      (production data, security surface, irreversible schema, external
      visibility), defaulting *unknown* stakes to more scrutiny. An undefined
      flag nobody sets is not a safety control.
- [x] **State the `council` fallback** for when the skill is not installed.
- [x] Self-check: escalation on a fixture produces at least one artifact
      (citation, file reference, or tool output) that was not in the input.

## Phase 9 — Audit trail and injection hardening ✅ done

Lower payoff; do after the above land.

- [x] Append one record per decision to `.decisions.log`: date, options, weights
      and rubric version, sub-scores, escalation reason, user's pick, and whether
      it diverged from the recommendation. For a decision aid this record *is*
      the product, and it is the only path to ever measuring calibration.
- [x] Treat candidate text as untrusted data: delimit it, state that instructions
      inside candidates are never followed, and keep analysis separate from
      execution. Consequential actions still go through normal tool permissioning.

## Phase 10 — Second senior review, reproduced against the code ✅ done

The v2 phases were reviewed again, this time by **running** the claims rather
than reading them. Three of the findings inverted a guarantee the project
advertised, and none of them were visible from the prose.

### Reproduced defects

| # | Defect | How it was found | Severity |
|---|---|---|---|
| 1 | **Ignorance outranked evidence.** `point` imputed unknowns at the mean of the knowns and was the sort key, so an all-unknown option scored `50.0` and beat a fully-grounded `45.0`. Directly contradicted the module docstring *and* the SKILL.md anchors: `evidence_strength: 20` ("not checked") and `null` ("not established") are the same epistemic state and moved the ranking in opposite directions. | ran the CLI on a two-option fixture | **Critical** |
| 2 | **Optimistic renormalisation rewarded gaps.** Scoring `100` on two criteria and passing `null` on the rest renormalised to a perfect total and beat an all-known `80`. An active incentive to stop looking. | ran the CLI | **Critical** |
| 3 | **The headline guarantee was a substring check.** `"%" in text` passed `82/100`, `8 out of 10`, `0.82 probability` and `high confidence` — every anchoring harm the design exists to prevent. | fed the strings to `check()` | **Critical** |
| 4 | **The eval was built on an unavailable tool.** `AskUserQuestion` is not present in headless `claude -p`; the session is flagged non-interactive. `--live` asked the agent to self-report an ask it could never make — and had never been run, so the README's "the more important suite" was the unexecuted one. | ran a headless session and inspected the tool list | **Critical** |
| 5 | **`evidence_strength` was 20% of the utility sum.** Belief about an option is not part of its value; an option got better for having been researched. Also correlated with `precedent` (0.35 combined weight on near-identical evidence), violating the preferential independence a weighted sum assumes. | design review | High |
| 6 | **`NOISE_BAND = 12` decided escalation and was, by its own comment, a guess.** | code read | High |
| 7 | **Weights still had no sensitivity analysis.** v2 "fixed" the 5/5 finding by letting the caller pass a different map, which moves the problem rather than answering it. | code read | High |
| 8 | **0-100 input against three anchor bands.** Nothing between 81 and 100 is distinguishable by any anchor, so the extra resolution was noise entering the sort key — then compensated for downstream by (6). | design review | High |
| 9 | **Hand-substituted skill paths** where `${CLAUDE_SKILL_DIR}` exists, and no `allowed-tools`, so every invocation cost a permission prompt on a skill whose own plan flags friction as fatal. | Claude Code skills docs | Medium |
| 10 | **`.decisions.log` was prescribed and unimplemented** — no writer, no schema, no reader, no assertion. "The record is the product" with no record. | grep | Medium |
| 11 | **Injection guidance had no assertion behind it.** `scenarios.json` carried an injection case that no rule in `check()` could fail. | code read | Medium |
| 12 | **`.gitignore`'s `scripts/eval/traces/` matched nothing** (slash-anchored to repo root), so live-eval output would have been committed into the skill. Plus `o["label"]` KeyError, `events.index()` equality collision, uncaught `TimeoutExpired`, no CI, no remote. | `git check-ignore` | Low |

### Fixes shipped

- [x] **Rank on the conservative bound** (`lo`). Unknowns contribute nothing;
      an all-unknown option now sorts last at `0`. Fixes 1 and 2. Two regression
      tests pin both, named for the behaviour they used to have.
- [x] **Sub-scores restricted to the anchor midpoints** `{20, 60, 90}` or `null`,
      with an error that names the bands. Fixes 8 at the source instead of
      modelling it downstream.
- [x] **`evidence` pulled out of the weighted sum**, carried per choice,
      unweighted. Weights renormalised to `0.50 / 0.30 / 0.20`. Low or absent
      evidence emits the `unverified-evidence` escalation reason — for which
      SKILL.md now says a second opinion is worth nothing and only a tool call
      counts. Fixes 5.
- [x] **`NOISE_BAND` deleted, replaced by measured stability.** 400 draws
      resampling the weights (Dirichlet around the declared vector) and jittering
      each sub-score by one anchor band; `separated` is now "the top option
      survives ≥90% of draws". Seeded, so the same input gives the same verdict.
      Fixes 6 and 7 with one mechanism — and it is *derived from this option
      set*, so a criterion on which everything scores alike cannot prop up a
      recommendation.
- [x] **`PERCENTISH` regex** covering `82%`, `82/100`, `8 out of 10`, bare
      `0.82`, "confidence", "probability", "N points" — with `$0.02` explicitly
      allowed so a real cost can still appear in a tradeoff clause. Four new
      regression fixtures, one per disguise. Fixes 3.
- [x] **The raw top-two gap and the stability fraction are no longer printed**,
      even to the agent. Both were numbers one copy-paste away from a menu; the
      table shows `robust / marginal / fragile` and the figures stay in `--json`.
      Caught by the test suite, not by review.
- [x] **`--live` rebuilt around what is observable.** Ground truth comes from
      `$DECISION_PICKER_LOG` (the exact payload `rubric.py` received and the
      verdict it returned — the step with all the variance, fully observable) and
      from `--output-format stream-json` tool calls; the composed ask is retained
      but labelled `self-reported` in every saved trace. `--repeat k` measures
      recommendation self-agreement, which is the empirical quantity (6) was
      guessing at. Protocol-break rate now reports a Wilson interval and gates on
      its upper bound, because n=15 single runs cannot resolve a 10% threshold.
      `TimeoutExpired` caught per run. Fixes 4.
- [x] **`--log` implemented.** One JSONL line per decision: weights, every
      sub-score, evidence, verdict, whether review ran, the user's pick, and
      `diverged`. `$DECISION_PICKER_LOG` is the flag's default, which is what
      makes the eval's ground truth free. Fixes 10.
- [x] **Label sanitisation** — C0/C1 controls, zero-width characters, bidi
      overrides, length cap. Not an injection defence (nothing in a prompt is);
      it stops a candidate forging menu structure. Two new fixtures assert an
      injection-shaped candidate is *surfaced* and *never executed*. Fixes 11.
- [x] **`${CLAUDE_SKILL_DIR}` throughout, plus `allowed-tools`** pre-approving
      the rubric invocation. The documented call is a heredoc so it prefix-matches
      the rule. `claude plugin validate` passes; `allowed-tools` is in the
      six-field Agent Skills spec set, so portability outside Claude Code holds.
      Fixes 9.
- [x] **CI** — both suites on Python 3.10 and 3.13, a stdlib-only import check
      (the "no dependencies" claim, enforced), and `claude plugin validate`.
      `.gitignore` patterns corrected and verified with `git check-ignore`.
      Remaining minor fixes folded in. Fixes 12.

Suites: **26 unit tests**, **24 fixture checks**, all green.

### What the live harness found on its first run

`--live` was smoke-tested (`--only hard-constraint-excludes-favourite --repeat 2`)
and immediately earned its keep. Both runs invoked the skill, gated all three
SaaS options on the hard constraint, and scored on the anchors. Run 2 failed
`ESCALATION_WHEN_CONTESTED`, and the ground-truth log showed why: the rubric
returned `unverified-evidence`, the agent did not escalate, and then **re-ran the
rubric with a raised evidence level until the reason disappeared**.

Neither the old checker nor a self-reported trace could have seen this — it is
only visible because the script's own log is captured. Two fixes shipped:

- [x] **`RESCORE_TO_DISMISS` rule.** A reason may not vanish between two rubric
      events without an intervening `escalation.ran: true`. Two new fixtures: the
      laundering trace, and the legitimate case where evidence was actually
      gathered first.
- [x] **SKILL.md forbids it explicitly**, in step 3 and in the anti-patterns.
      The prose had a hole: "re-score, don't re-total" covered review arguments
      but said nothing about editing an input to delete a warning.

Also fixed: the trace schema did not say that `action.label` must be an exact
option label, so an agent reporting a prose sentence tripped `USER_PICK_HONORED`.
Spec tightened rather than the assertion loosened.

### Still open

- **A full `--live --repeat 3` pass across all 15 scenarios** has not been run —
  one scenario has. The break-rate and self-agreement numbers are not yet real,
  and the gate has not been exercised at n large enough to mean anything.
- **Pairwise scoring** (recorded in v2 as raised 2/5, never resolved). Declined
  for now: with ≤4 options all-pairs is 6 comparisons per criterion, and the
  per-criterion cross-option pass already captures most of the halo benefit. The
  decision is recorded here rather than left implicit.

## Non-goals

- **A packaged state-machine controller with adapters** (luna's proposal). A
  second system to maintain for a skill whose runtime is one markdown file, and
  it repeats the original error of adding machinery around the deterministic
  part. Revisit only if the Phase 6 evals show prose cannot hold the protocol.
- **`pyproject.toml` / `__init__.py`** for three stdlib functions.
- **Deleting `scripts/` entirely** (gemini/kimi's proposal). `rubric.py` earns
  its place as the single source of truth for criteria and weights once it
  validates its inputs and has a CLI; inlining the weights into prose means they
  drift between SKILL.md and every invocation.
- **A persistent scoring database, a GUI, or a custom terminal picker.** Still
  YAGNI. Phase 3b (custom paginated picker) is formally dropped: Phase 5 removes
  the multi-round flow that was its only motivation.
