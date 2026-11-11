# Running the tests

These instructions are for contributors testing IntentBond itself.
To check your own project, follow [check a change](../README.md#check-a-change).

From the project checkout, in a Python virtual environment with Git and Java
available:

```sh
python3 -m pip install --require-hashes --only-binary=:all: -r requirements/ci.txt
python3 -m pip install --no-index --no-deps --no-build-isolation -e .
ib install-oft
ib install-alloy
python3 -m unittest discover -s tests -v
ruff check .
ruff format --check .
```

Tests run OFT, Alloy, Z3, and example test commands in temporary directories. Missing
pinned JARs fail the suite. To use existing JARs, set `INTENTBOND_OFT_JAR` and `INTENTBOND_ALLOY_JAR`
instead of running the respective installers. Alloy remains optional for application
projects that do not use model checking. Runner tests execute the real analyzer,
including counterexamples, impossible witnesses, missing commands and bad models.
Z3 tests additionally check native SMT-LIB replay, vacuous assumptions, `unknown`
results, bounded model construction, missing evidence and exact observations. Spacer tests validate induction queries,
portable Horn result polarity, reconstructed traces, vacuity, unknown outcomes,
malformed evidence and mutation counterexamples.

The [CI workflow](../.github/workflows/ci.yml) builds the source distribution and
then its wheel without build isolation, installs the wheel without dependency
resolution, and runs packaged tests/fixtures from a
separate working directory. It checks Python 3.11 and 3.12, packaged skill
references, lint, and the three language examples. Example smoke checks require
passing behavior, rejection of boundary and equality-only defects, and passing
restoration. The equality-only defect satisfies the boundary and translation
properties but violates the full expiration postcondition. Native logs and
evidence are retained as artifacts.
JavaScript dependencies and OFT downloads require network access. QuickCheck is
provisioned only in its dedicated disposable runner.

CI loads `-p intentbond.pytest_junit` with the pinned pytest 9.1.1 and validates
the resulting XML with `intentbond.testing.junit_counts`. The optional adapter
produces separate cases for subtests without weakening report completeness.
To reproduce that producer locally after installing the locked dependencies:

```sh
PYTEST_DISABLE_PLUGIN_AUTOLOAD=1 python -m pytest -p hypothesispytest -p intentbond.pytest_junit tests --junitxml=/tmp/intentbond-tests.xml -q
python -c 'from pathlib import Path; from intentbond.testing import junit_counts; print(junit_counts(Path("/tmp/intentbond-tests.xml")))'
```

Producer regression tests cover repeated subtest contexts, failures, runtime
exceptions, skips, setup/teardown errors, collection errors and omitted cases.
Revalidate or remove the version-specific adapter when upgrading pytest; an
upstream producer fix is preferable once available and verified.

The [property mutation checks](../.github/workflows/property-evaluation.yml) run
on manual dispatch, separately from the normal pull-request checks.

The [async lifecycle example](../examples/async-lifecycle) has a standalone offline
qualification command. CI executes it from the extracted source distribution with
the installed wheel and already-provisioned JAR. It verifies 754 retained case
records, both exact counter-reset regressions, legitimate alternatives, 12 repair
API controls, ordinary-plus-retention parity and pending semantic review. It needs
no model service, historical research directory or additional runtime dependency.
See its README for the single command and finite coverage bounds.

## Build a release from clean source

Build from the committed revision you intend to publish, using a fresh directory
so ignored `build/`, `dist/` and `*.egg-info/` from earlier work cannot enter
the distribution. Install the locked build dependencies above first.

```sh
IB_RELEASE_REV=$(git rev-parse HEAD)
IB_RELEASE_DIR=$(mktemp -d)
mkdir "$IB_RELEASE_DIR/source"
git archive "$IB_RELEASE_REV" | tar -x -C "$IB_RELEASE_DIR/source"
python3 -m build --no-isolation --outdir "$IB_RELEASE_DIR/dist" "$IB_RELEASE_DIR/source"
python3 -m zipfile -l "$IB_RELEASE_DIR"/dist/*.whl
tar -tzf "$IB_RELEASE_DIR"/dist/*.tar.gz
gitleaks dir --redact --max-archive-depth=2 "$IB_RELEASE_DIR/dist"
```

This builds the wheel through the source distribution, as CI does. Inspect the
file lists before uploading; the archive excludes uncommitted changes. Test the
installed wheel from outside the checkout using the CI procedure. Keep local
evidence and operational logs out of the release directory. Do not reuse or
publish an older in-tree build just because its version number matches.

## Dependency updates

CI installs exact Python versions and artifact hashes from
[`requirements/ci.txt`](../requirements/ci.txt), including build tools and
transitive dependencies. Published package metadata retains compatible ranges.
GitHub Actions use full commit SHAs; Python, Java, and Node tool versions are
also explicit. OS packages and the hosted runner image follow their upstream
distribution updates.

Regenerate locks with uv, then review the diff and run the checks above:

```sh
uv pip compile pyproject.toml requirements/ci.in --extra test --extra smt --python-version 3.11 --universal --generate-hashes --output-file requirements/ci.txt
uv pip compile pyproject.toml --python-version 3.11 --universal --generate-hashes --constraint requirements/ci.txt --output-file requirements/runtime.txt
uv pip compile examples/property-testing/python/requirements.in --python-version 3.11 --universal --generate-hashes --output-file examples/property-testing/python/requirements.txt
```

Existing locks retain selected versions. Use `--upgrade-package NAME` for an
intentional update, changing exact inputs in `requirements/ci.in` where needed.
Keep action version comments with their verified upstream SHAs. Changes to a
runtime lock consumed by IntentMade also need its dependency lock refreshed.

## Coverage

Execution-link tests exercise the existing session fixture and a real pytest
producer. They cover parameterized cases, deselection, skips, expected failures,
setup errors, invalid IDs/revisions, duplicate identities, unsupported retry
extensions, source mutation, and altered retained summaries. A passing suite
with an omitted linked test must report `not_observed`. Opt-in required-execution
tests cover rejection, deletion, skip policy, revision continuity, candidate
policy edits, and independent enforcement when verifying retained evidence.
The `test` extra installs
pytest and Hypothesis for development; neither is a ib runtime dependency.

Hypothesis properties cover JUnit completion, source identity, requirement
revisions and evidence freshness. They run under both unittest and pytest.
See [property test maintenance](property-evaluation.md) for commands, search
limits and mutation checks.

Recovery tests start with an unannotated project, exercise citation and editing
checks, run real OFT/test validation, apply the proposed patch in the fixture,
establish the adopted baseline, and check a subsequent change. They also cover
invented/missing citations, unresolved intent, behavior/document changes, missing
links/tools, failing existing tests and concurrent edits. Compatibility tests
cover JavaScript module annotations and adding OFT IDs/Needs to existing specification
prose while retaining original citations. Documentation tests cover cited rewrites,
moves/deletions and adoption in both recovery modes. Shared original-ID accounting,
revision, status and citation rules run once; split and merge rules use imported-item
fixtures directly. They reject undocumented changes, fabricated citations,
test assertion edits and weakened coverage floors. Actual semantic extraction quality
is not established by these deterministic fixtures.
Coverage-comment movement tests verify that generated IDs do not require mappings,
while explicitly named IDs remain accounted for. Duplicate original authored IDs
are exercised as a currently unsupported recovery case.
In-place tests cover reviewable checkout edits, retained originals/provenance,
dirty/staged/untracked work, branch and commit changes, concurrent edits, linked
Git worktrees, automatic storage discovery, schema 1 compatibility, and exclusion
of quoted historical annotations from live coverage under `.intentbond/recovery/`.
Adoption tests cover archiving records outside the checkout without committing
them, removing previously committed records, and checking and verifying the
adopted source. Earlier evidence must reject source changed by cleanup.
Both modes exercise adoption
and subsequent development. They do not measure how accurately an agent reconstructs requirements. Assess
that separately by reviewing the agent's proposed documentation against its sources.
