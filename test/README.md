# Tool tests

This directory contains the Haskell test suites, shell integration runners, and
Python assumption-audit checks for hs-to-rocq. The Coq 8.20 and Rocq 9.0 Make
wrappers share compiler fixtures in
[`examples/tests/`](../examples/tests/README.md). Base-dependent fixtures remain in
`examples/base-tests/`.

Run the commands below from the repository root.

## Haskell test suites

Run all three Cabal suites with either build tool:

```bash
stack test
# Or, with cabal-install:
cabal test all
```

Use the project's Haskell toolchain (currently GHC 9.10.3); Stack selects it
through `stack.yaml`. The build tool resolves the Haskell dependencies declared
in [`hs-to-rocq.cabal`](../hs-to-rocq.cabal). These suites do not need a Coq/Rocq
compiler, a generated base library, or a separately built translator executable.
The `ci-catalog` suite also requires Bash on `PATH`.

| Suite | Main file | Checks |
| --- | --- | --- |
| `edits` | [`test/Edits.hs`](Edits.hs) | Public edits parser and builder APIs, including syntax, configuration, precedence, and diagnostics. |
| `rocq-version` | [`test/RocqVersion.hs`](RocqVersion.hs) | Target-version parsing and AST/text namespace rewriting. |
| `ci-catalog` | [`test/CiCatalog.hs`](CiCatalog.hs) | Workflow/catalog agreement, `/ci-fix` delegation, failure propagation, Bash syntax, and catalog regressions. |

To focus on one suite:

| Stack | Cabal |
| --- | --- |
| `stack test hs-to-rocq:edits` | `cabal test edits` |
| `stack test hs-to-rocq:rocq-version` | `cabal test rocq-version` |
| `stack test hs-to-rocq:ci-catalog` | `cabal test ci-catalog` |

`CiCatalog` runs its complete self-tests with no arguments. It reads the
workflow, both command documents, and the pinned `ci-catalog-old-head.md`
fixture. Its guards and mutation tests cover the assumption runner's CI wiring,
compiler pins, pinned submodule setup, switch isolation, check ordering, and
unconditional failure propagation. Its shell regressions use stubbed tools;
they do not run the documented builds or regeneration. The `--self-test`
argument remains accepted for direct compatibility:

```bash
stack exec -- runghc -package=yaml test/CiCatalog.hs --self-test
```

## Shell integration checks

Shell runners are explicit checks, not part of `stack test` or `cabal test all`.
They require Bash and standard Unix utilities. The fake-tool harness also needs
Make, but no Haskell or Coq/Rocq toolchain:

```bash
bash test/harness.sh
```

The real-translator checks use Stack to invoke `hs-to-rocq`, so build the
executable with Stack first, even if you ran the Haskell suites with Cabal:

```bash
stack build
bash test/edits.sh
bash test/concurrent.sh
```

Neither script needs a Coq/Rocq compiler or a compiled base library:

- `edits.sh` checks translation output and rejection diagnostics. With no
  arguments it checks both targets; select one with
  `bash test/edits.sh --target-version 8.20` or `--target-version 9.0`.
- `concurrent.sh` runs translators concurrently with a shared Haskell dependency
  on both targets. It checks output files, the absence of shared GHC object
  artifacts by default, and the explicit GHC code-generation override.

The runners use temporary directories and remove them on exit. The
[coverage matrix](../examples/tests/README.md#edit-coverage-matrix) records the
edits API, CLI, and compiler witnesses and their limitations.

## Assumption-audit checks

Run the fingertree assumption-checker controls with Python 3.8+ and its standard
library only. This is a separate runner, not part of the Cabal suites:

```bash
python3 test/assumptions.py
```

The default mode runs **24 compiler-independent cases** against the theory and
priority-audit helpers. They check export inventories, report parsing, missing
or malformed reports, and exact dependency sets. CLI controls use a nonexistent
executable and fake compilers: the checker must fail when the compiler is
missing, prints a plausible report but exits nonzero, or exits zero without
reports.

To add real compiler controls, use Rocq 9.2:

```bash
# With Rocq 9.2 on PATH:
python3 test/assumptions.py --rocq rocq
# Or select an existing Rocq 9.2 opam switch:
opam exec --switch="${ROCQ92_SWITCH:?Select a Rocq 9.2 switch}" -- \
  python3 test/assumptions.py --rocq rocq
```

This adds **seven cases, for 31 total**. The fixtures under
[`test/assumptions/`](assumptions/) exercise direct and transitive dependencies
on an unexpected axiom, plus an independent closed proof. Both checkers must
accept the exact dependency sets and reject unexpected axioms; the theory CLI
must also reject a nonempty expectation for the closed control. Once `--rocq`
is requested, an unavailable or erroring compiler fails the runner rather than
skipping the real cases or reporting success.

The runner locates its helpers and fixtures relative to the script, independently
of the caller's working directory. All generated inputs, temporary manifests,
logs, and compiler products stay in temporary directories removed on exit.
Neither mode needs a generated base or built translator; the default mode also
needs no Coq/Rocq installation. These controls test the audit tools, not the
finger-tree proofs themselves; use the
[example checks](../examples/fingertree/README.md#build-and-check) for those.

## Compiler and base checks

Build the translator with Stack first. For each command, use the matching
Coq 8.20 or Rocq 9.0 environment with its Equations plugin installed:

```bash
make -C examples/tests
make -C examples/rocq9.0/tests
```

These shared compiler suites do not need the translated base library. Each
Make entry point also runs `edit-checks`: the `edits` Cabal suite via
`stack --allow-different-user test hs-to-rocq:edits`, followed by `test/edits.sh`
for that wrapper's target version. See the
[shared test guide](../examples/tests/README.md#run-the-tests) for focused Make
targets and expected-failure categories.

Base checks require the matching compiler and compiled base library; building
the base also requires the matching `coq_makefile`. Their existing Make entry
points include the relocated `test/deriving.sh` and `test/identity-traversal.sh`
runners:

```bash
# Coq 8.20; requires compiled base/
make -C examples/base-tests
# Rocq 9.0; compiles its base before running the checks
make -C examples/rocq9.0 base
```

The deriving runner also needs the Stack-built translator. The traversal runner
locates the repository relative to its script path and compiles
`examples/base-tests/IdentityTraversal.v`. The fake-tool harness exercises this
runner from the repository root and both Make caller directories with Git
rejecting repository access. See
[deriving and base integration](../examples/tests/README.md#deriving-and-base-integration)
for direct commands, prerequisites, and the scope of the assumption checks.

## Local CI and validation records

Use [`.claude/commands/ci.md`](../.claude/commands/ci.md) for the authoritative
seven-job catalog and compiler environments;
[`ci-fix.md`](../.claude/commands/ci-fix.md) adds repair guidance.
The existing `build-haskell` job runs the Haskell suites, then the harness,
concurrent translation, and default assumption-audit checks as separate steps.
The existing `test-rocq9` job keeps the Rocq 9.0 suite first, then uses an isolated
Rocq 9.2 switch for the real assumption controls, clean foundations, and full
fingertree checks. Both jobs install Python through the existing setup action.
See the catalog's [test-rocq9 section](../.claude/commands/ci.md#job-test-rocq9)
for the ordered commands and compiler pins. The workflow still has seven jobs;
expected-failure categories are unchanged, and every nonzero check status fails
its job.

The [historical validation records](../examples/tests/README.md#issue-228-validation)
remain scoped to their recorded revisions. This guide describes commands and
coverage, not a new verification result.
