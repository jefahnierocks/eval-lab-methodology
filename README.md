# Agentic-Coding Evaluation Lab — Methodology

<!-- project-card: agentic-coding-evaluation-lab -->
### Agentic-Coding Evaluation Lab

Evidence-based evaluation for models and coding-agent configurations

**What is this?**
A model-evaluation framework for deciding whether a candidate model or coding-agent configuration
should replace the current default.

**What is it for?**
It replaces informal model selection with a repeatable, evidence-backed decision. The framework
tests reliability and task performance while checking that the comparison itself is valid.

**How is it used?**
A team evaluates the current and candidate systems on the same task set. The framework records the
raw outcomes, checks that the runs are comparable, applies predefined decision criteria, and
recommends either changing the default, retaining it, or withholding judgment when the evidence is
insufficient. That is the workflow this repository implements and demonstrates; its current
demonstrations use synthetic and representative data.

**Why does it matter?**
It helps prevent incomplete experiments, infrastructure problems, or attractive headline scores
from driving production model changes. It also produces a reproducible record that engineering,
safety, and model-risk reviewers can inspect.

**Evidence and status**
Published methodology and tested statistical and reporting code. Synthetic, representative, and
historical live evidence are kept strictly distinct. There is currently
no defensible powered real-model result and no promotion recommendation.

[Explore the methodology, worked examples, and evidence →](https://jefahnierocks.github.io/eval-lab-methodology/)
<!-- /project-card -->

- **Status:** Prototype — public methodology and verification code; repository-versioned, with no distributed release
- **Evidence:** Synthetic and representative examples, plus one confounded historical smoke summary — no scientifically sound real-model comparison
- **Decision:** No promotion recommendation — the draft evidence contract recomputes `NOT_EVALUABLE`, meaning no scientific conclusion can be drawn from its evidence
- **Demonstrates:** Independent evaluation reporting that refuses to report a result rather than guess when the evidence is insufficient, on synthetic evidence
- **Does not demonstrate:** Performance of any real model
- **Relevant to:** Model testing, challenger evaluation, and model-risk review

This repository is a methodology and verification project; it is not an operational benchmark,
model leaderboard, or deployment service.

## What I built

- A dependency-free Python core with Wilson intervals, a seeded percentile bootstrap, a two-sided
  paired sign test, and a superiority-by-margin helper.
- Evidence Contract `1.1.0` and a parameterized Quarto report for historical and synthetic examples.
- A frozen identity-domain v1 field set, canonicalization rule, and cross-implementation vector.
- An executable experimental methods note with committed, byte-checked synthetic results.
- A content-free E4 corpus-construction contract and E2 exact leading-rule/base-grid manifest that
  regenerate byte-for-byte without authoring records or producing operating-characteristic
  results.
- Evidence contract `2.0.0-draft.1` — a draft evidence and reporting contract that validates a
  synthetic registration-to-report join, independently recomputes the result, and refuses
  mismatched or incomplete evidence.
- Recursive evidence-input scanning in the parameterized report path and a separately bound
  publication-safety scanner for the evidence contract.

The public core's historical superiority helper returns true only when the bootstrap confidence
interval lower bound is strictly greater than the supplied margin. That implementation is preserved
for reproducibility; it is not the selected rule for future powered campaigns.

## What this demonstrates

- A separate verifier recomputes a published result from the frozen evidence bytes and refuses on
  any mutation, mismatch, or missing prerequisite — demonstrated on synthetic evidence.
- The reporting layer declines to make a model decision when the study design is incomplete: with
  no approved statistical method, replication policy, or minimum useful improvement, the only
  outcome it can produce is `NOT_EVALUABLE`, meaning no scientific conclusion can be drawn.
- The synthetic example reports regenerate deterministically from committed evidence bytes, so a
  technical reviewer can rerun them and reproduce every published number in them.

## Why it matters

In a company model-testing workflow, the same pattern can prevent an incomplete experiment, an
infrastructure problem, or an attractive headline score from triggering a change from the current
model to a challenger. It also creates an auditable record explaining why no decision was made and
what evidence is still required — the record engineering, safety, and model-risk reviewers need in
order to trust or challenge an evaluation.

## What it does not demonstrate

- No admitted successor enforcing test, replicate policy, or minimum practically important benefit.
  E2 has an equal-class estimand and exact leading-rule candidate for calibration, but that is not
  a powered-method selection or evidence that the rule controls the intended heterogeneous null.
- No validated operating characteristics for the intended class-balanced design.
- No operational registration signer, trusted timestamp path, or production owner-receipt join.
- No validated grader study, no public-safe validity evidence for the governed 40-task suite, no
  A/A calibration, and no powered campaign.
- No evidence that a candidate model or harness improves real task performance.

## Evidence and reproduction

- [Source repository](https://github.com/jefahnierocks/eval-lab-methodology)
- [Methodology site](https://jefahnierocks.github.io/eval-lab-methodology/)
- [Experimental inference note](reports/experimental-inference-note.qmd)
- [Refusal example](reports/contract-v2-not-evaluable.qmd)
- [Identity-domain specification](identity-domain.qmd)
- [Delivery manifest](evidence/contract-v2/delivery-manifest.v1.json)
- [Candidate calibration protocol family](docs/preregistrations/calibration-sap.md)
- [E4/E2 offline calibration freeze](analysis/calibration-freeze.v1.json)
- [Roadmap](PLAN.md)

The repository contains two historical worked examples:

- a representative, stubbed-harness refusal example that demonstrates plumbing only; and
- a four-task, two-replicate live smoke run with a known transport confound.

Neither is a current statistical result. The smoke artifact retains summary values rather than the
raw per-attempt outcomes needed for independent interval recomputation. Their recorded values are
historical artifacts, not evidence for model selection.

The candidate calibration family incorporates the reviewed statistical design decisions. Its E4
construction schema/checks and E2 leading-rule/base-grid generator are repository-versioned as a
synthetic, content-free design artifact. The family remains unregistered and non-authorizing: no
corpus, observation, grader admission, operating-characteristic result, or scientific verdict is
present, and remaining result-producing and operational prerequisites must be completed before a
study can begin.

### Verify locally

The project pins Python 3.13.15, uv 0.13.0, and Gitleaks 8.30.1 in `.mise.toml`.
The gate and report renderer share one Quarto selector. It first honors explicit
`QUARTO`, then `.cache/tools/quarto-<version>/bin/quarto` for the version in
`.quarto-version`, then `PATH` when no explicit or local installation exists.
Each selection must report the exact pinned version. An invalid explicit or present
local choice fails without fallback; no tool is downloaded or installed. The owner
prepares the exact release or sets `QUARTO=/path/to/quarto`. Evidence validation
with `--validate-only` requires no Quarto. The dependency audit requires a separate
prepared pip-audit 2.10.1 environment (`uv venv --python 3.13.15 .cache/pip-audit`,
then `uv pip install --python .cache/pip-audit/bin/python pip-audit==2.10.1`), or
`PROJECT_PIP_AUDIT_PYTHON`; it still queries the advisory service. With the prepared
tools available, run:

```bash
mise exec -- uv sync --frozen --no-install-project --extra dev --extra report
mise exec -- python3 scripts/check_agent_contract.py
mise exec -- uv run --frozen --no-sync bash scripts/run-merge-gate.sh
```

Stage only the files owned by the change before the final validation so new files
enter the index-based security checks. The script refuses missing or mismatched
Python, uv, Quarto, or Gitleaks versions. It scans all reachable Git history and
separate staged/unstaged tracked changes with native Gitleaks rules, rejects private
directory paths in the index, and withholds scanner finding contents. No scanner
policy file or finding waiver is accepted. Project-managed tool caches stay under
ignored `.cache/` and the virtual environment under `.venv/`, with one explicit
owner-approved exception: on macOS, Quarto 1.10.18 itself may read and write only
`~/Library/Caches/quarto` during the existing source-validation gate. The owner
approved this exact exception on 2026-10-14. It allows no agent cache browsing or
cleanup, `HOME` or global configuration changes, host installation, credentials,
deployment or publication. The [pinned upstream cache implementation](https://github.com/quarto-dev/quarto-cli/blob/v1.10.18/src/core/appdirs.ts)
was checked on 2026-10-14; `XDG_CACHE_HOME` does not override its macOS path.

CI installs the same pinned tools and invokes the same merge-gate script, covering
security, Ruff, tests, exact-result checks, a known-vulnerability audit, wheel
containment, evidence validation, and site/report rendering before publication.
The repository provisionally adopts the Jefahnierocks child-repo baseline 0.1.0 at
the owner-confirmed Governed tier. The only unmet rule is a producer-approved
public-safe host-contract binding. See `AGENTS.md` for boundaries and `STATUS.md`
for source status. This source adoption does not authorize publication or establish
runtime admission.

## Technical details

### Status by surface

| Surface | Status | Claim boundary |
|---|---|---|
| Statistical core `0.2.0` | Repository-versioned; wheel builds locally; not tagged or published to a package registry | Preserves historical estimators and a superiority component; not authorized for a new powered claim |
| Experimental inference note | Published synthetic decision input | No successor method is selected |
| Evidence contract `2.0.0-draft.1` | Immutable repository-only draft with a frozen delivery manifest | Synthetic conformance only; recomputes `NOT_EVALUABLE`; no operational authority |
| E4/E2 offline calibration freeze | Repository-only schema, exact-rule candidate, scenario generator, and byte-checked synthetic manifest | No authored corpus or result; unregistered and non-authorizing |
| Identity domain v1 | Frozen structural specification and conformance vector | Matching hashes are necessary, not sufficient, for numerical comparability |
| Real campaign evidence | One historical four-task smoke summary with a transport confound; raw attempt records are not published | Not independently recomputable, not a benchmark, and not a scientifically sound, adequately powered comparison |

There is currently no defensible powered real-model result and no promotion recommendation. See
[STATUS.md](STATUS.md) for the readiness boundary and remaining work.

### Evidence and provenance rules

- Published numbers must trace to committed evidence bytes, with the retained raw-versus-summary
  boundary stated.
- Synthetic, representative, smoke, and measured evidence remain distinct.
- A copied fact retains its originating observer and receipt; copying never upgrades provenance.
- Missing or contradictory inputs produce refusal, not a best-effort decision.
- The parameterized evidence-report path recursively re-scans evidence inputs; the evidence
  contract checks its bound public payload separately. Neither control is a whole-repository
  scanner.

### Identity-domain scope

Identity-domain equality prevents known stack changes from being silently read as model effects. The
v1 preimage includes runtime, image, hardware, model-artifact, and launch fields. It does not prove
that all residual serving state is controlled. Prefix-cache state, batch context, session position,
decoding parameters, harness version, and other unrecorded state can still affect numerics. A
matching v1 hash is therefore a necessary admission check, not a complete reproducibility guarantee.
The frozen source's broader historical wording is corrected in [ERRATA.md](ERRATA.md); v1 bytes and
the conformance vector remain unchanged.

Frozen v1 constants and the conformance vector are never changed in place. A wider field set requires
a new schema version.

### Evidence-contract delivery mechanics

The evidence-contract verifier and report renderer are under `analysis/contract_v2/`. They are deliberately
outside the installable `0.2.0` wheel. The delivery manifest pins their source commit and tree,
relative layout, dependencies, file digests, aggregate digests, conformance fixture, and golden
report. Downstream consumers must verify those exact bytes and preserve the layout.

### Repository boundary

This public repository owns infra-agnostic methods, schemas, independent recomputation, sanitized
reports, and public specifications. Private systems own task fixtures, execution, model transport,
editing, deployment lifecycle, operational traces, and evidence custody. Private identifiers,
endpoints, credentials, raw model responses, and task fixtures do not belong here.

### Next milestones

1. Select and justify the successor scientific design, including its assumptions and operating
   characteristics.
2. Complete operational owner contracts and registration verification outside this repository.
3. Validate the grader, task suite, dependence assumptions, and apparatus noise floor.
4. Run a registered, powered local campaign and publish a sanitized independently recomputable
   report.

## License

Apache-2.0. See [LICENSE](LICENSE).
