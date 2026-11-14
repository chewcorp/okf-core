# AGENTS.md

This file is contributor guidance for humans and LLM coding agents working
inside the `okf-core` repository. It is not a prompt template for projects that
consume `okf-core`.

## Developer Setup

- Always develop and run tests within a local virtual environment named `.venv` to prevent package pollution.
- Note: Developer environment bootstrapping (`just install`) requires Python 3.11+ to utilize the standard library's `tomllib` and avoid dependency workarounds in development. Runtime compatibility for consuming projects still fully supports Python 3.10+.
- Install [`just`](https://just.systems/) for a simpler command surface. If unavailable, use the manual steps below instead.
- Bootstrap the environment and dependencies using:
  ```sh
  just install
  ```
  This creates `.venv` and installs the package with test dependencies. `just` recipes invoke the venv Python directly so no manual activation is needed for `just fmt`, `just test`, etc. For interactive use (e.g. a Python shell), activate with `source .venv/bin/activate`. Equivalent manual steps:
  ```sh
  python3 -m venv .venv
  source .venv/bin/activate
  python -m pip install -e ".[test,dev]"
  ```

## Project Shape

- Implement `okf-core` as a Python package.
- Use `src/okf_core` for package code.
- Use `tests` for pytest coverage.
- Keep the package usable as a library first, with CLI behavior layered on top.
- Use `okf-core.toml` as the default project configuration convention.

## Design Constraints

- Keep `okf-core` aligned with the public OKF v0.2 specification:
  https://github.com/GoogleCloudPlatform/knowledge-catalog/blob/main/okf/SPEC.md
- For spec-sensitive work, cache the spec content to `.agent-cache/SPEC.md`
  if it is not already present, then consult that local copy while working.
  `.agent-cache/` is local agent/development state and must not be committed.
- Use the upstream reference path implementation as context for concept ID and
  path behavior:
  https://github.com/GoogleCloudPlatform/knowledge-catalog/blob/main/okf/src/enrichment_agent/bundle/paths.py
- Treat these OKF v0.2 sections as authoritative for current MVP behavior:
  Section 2 Terminology, Section 3 Bundle structure, Section 3.1 Reserved
  filenames, Section 4 Concept documents, Section 4.1 Frontmatter, Section 5
  Provenance/trust/lifecycle, Section 6 Cross-linking and paths, Section 7
  Actor convention, Section 8 Index files, Section 9 Log files, Section 11
  Conformance, and Section 12 Versioning.
- Behavior must always be capable of reduction to the base OKF specification.
  No extension introduced by this repository should be mandatory, or
  fundamentally change base OKF concepts such as bundle, concept ID, reserved
  files, or frontmatter tolerance.
- Keep behavior configurable and layout-agnostic so different repositories can
  use different OKF roots, document taxonomies, and path conventions.
- **Progressive Disclosure:** Design user/agent interfaces and documentation (such as the `orient` guide) to prioritize progressive disclosure. Focus orientation texts on the absolute essentials required to get started (e.g., core concept structure, discovery/listing/validation), and provide discovery pointers (such as command `--help` menus and README references) for advanced options and configuration, rather than duplicating comprehensive details inline.
- Do not reinvent mature infrastructure. Prefer well-supported Python libraries
  for parsing, validation, CLI surfaces, plugin/hook dispatch, and workflow
  orchestration when they fit the project constraints. Build `okf-core` code
  where OKF-specific behavior is the value.
- Do not add mandatory direct LLM API calls, funded API token requirements, or
  hosted model dependencies.
- Treat agent-facing examples for consuming projects as optional templates only.
  Keep them outside this root `AGENTS.md`, for example under
  `examples/agent-instructions/`.
- Preserve unknown OKF frontmatter fields unless a change explicitly targets
  them.
- Keep OKF consumption and conformance permissive even when a focused mutation
  API supports only a documented subset of replacement values. Preserve
  untargeted valid frontmatter, and report unsupported requested mutations as
  operation errors rather than document or bundle conformance failures.
- Prefer deterministic parsing, validation, indexing, graph, and patch logic
  over agent interpretation.
- Keep agent runtimes and workflow orchestrators optional. For example,
  LangGraph may be an integration target for consuming projects, but should not
  become a required core dependency unless a future issue explicitly justifies
  that tradeoff.
- Avoid over-engineering type/schema validation within core validation APIs. Core validation must focus on base OKF conformance (like the `type` string) and simple presence/non-emptiness checks for profile-required fields, leaving rich type/schema enforcement to the consuming project or custom workflow hooks.
- **Opt-in Bundle Extensions:** Any non-standard or tool-specific configuration settings (such as `stable_id_field`) must be restricted to bundle-level configuration and explicitly excluded from `ProjectDefaults`. This ensures that global defaults remain strictly compliant with the base OKF specification, and any extensions must be opted-into explicitly per bundle.
- **`pluggy` hook naming convention:** All hook names must follow the `okf_verb_noun` pattern.
  Use `start`/`end`/`abort` as the verb for whole-phase lifecycle hooks (called once at the
  beginning/end/failure of a scan or graph build transaction, e.g. `okf_start_scan`,
  `okf_end_graph`). Use `fetch` as the verb for substitution/caching hooks (which return
  a value or `None` to bypass core computation, e.g. `okf_fetch_scan_concept`,
  `okf_fetch_moved_concept_path`). Use `enter`/`exit`
  as the verb for per-item observation hooks (called symmetrically for observation/metrics,
  always firing, e.g. `okf_enter_scan_concept`, `okf_exit_resolve_links`).
- **Surface problems explicitly; never fail silently.** When a function
  encounters input it cannot process (malformed data, spec violations, missing
  required fields), expose the problem through a structured return channel.
  Preferred channels in order:
  1. **Named-dataclass return** — for functions that produce collections or
     generated output. Mirrors `scan_bundle`'s `BundleManifest` pattern: return
     a frozen dataclass with named fields (e.g. `.body` and `.problems`, or
     `.concepts` and `.problems`) so callers access results by name and the
     return type can gain fields without breaking call sites. Use when the
     caller should always see what was skipped, even if they choose not to act
     on it.
  2. **Raised exception** — for functions where any failure makes the result
     meaningless (e.g. `parse_concept_document`, `load_config`). Use a
     domain-specific exception type already established in the module.
  3. **Callback / hook** — only when the caller explicitly opts in and
     silent-skip on no-callback is documented and acceptable.
  Do not use `logging.warning()`, `warnings.warn()`, or `print()` as the
  primary problem channel — they are invisible to library callers and
  untestable without patching.

## Decision Records

Before starting design or architecture work — anything that chooses a
direction rather than just implementing an already-decided one — read
`docs/decisions/README.md` and scan the ADRs it indexes. They record
decisions that were expensive to reach once and should not be re-litigated
from scratch on every issue that touches the same territory (e.g. the
serialization-engine direction in ADR-0001/ADR-0002). An implementation that
contradicts an accepted ADR is a review finding
(`.claude/agents/milestone-reviewer.md`'s ADR-divergence check), not a
matter of implementor discretion; a `PROPOSED` (not yet `ACCEPTED`) ADR
section is documented direction, not yet binding.

**One sanctioned Markdown engine (#199):** `src/okf_core/markdown_engine.py`
is the one place where Markdown-significant-character escaping/unescaping and
Markdown-it token parsing/rendering happen. `patching.py`, `logs.py`, and
`index.py` all read/write Markdown-side content through it (its shared
`MARKDOWN` parser instance, `render_markdown_tokens`/`render_inline_children`/
`render_span`, and the `link_children`/`text_children` builders) rather than
each carrying its own escaping rule set or hand-rolled inline-token
reconstitution — the four independent implementations this replaced
(`index.py`'s `_md_escape`, the retired `_markdown_inline.py`'s
`_escape_title`, and `logs.py`'s pair of input-rejecting guards) are the
concrete "N places to re-fix one design
decision" problem this rule exists to prevent. This does not mean a single
shared block-walk across formats: `logs.py`'s date-sectioned entry state
machine and `index.py`'s heading-sectioned entry walk remain separate,
format-specific structural parsers (their shapes genuinely differ) —
`markdown_engine.py`'s scope is the parse/render/escape primitives beneath
that structural layer, not the structural layer itself. A new hand-rolled
escaping or ad-hoc Markdown-source-reconstitution helper anywhere else in
the codebase is an architecture finding in review, not a matter of
implementor discretion.

## Code Structure

These rules exist to stop cyclomatic complexity from accumulating in the first
place, rather than being refactored out later (as the v0.5.1 sweep — #118,
#120–#122, #124 — had to do). They interact with the complexity budget in
Testing Guidelines: code written this way stays under the C901 threshold
naturally.

- **Collector loops delegate per-item work.** A loop that walks a collection
  accumulating results and problems should call a per-item helper returning
  `(result | None, problem | None)` (or a small result/problems tuple); the
  loop body itself only dispatches hooks and appends. The "surface problems
  explicitly" rule above means per-item processing legitimately carries several
  `except`/validation arms — put those branches in the helper, not the loop.
  Exemplars: `_resolve_entry_links` and `_collect_linked_pairs_and_prose` in
  `graph.py`, `_find_stable_id_conflicts` in `manifest.py`.
- **A comment introducing a block is a function name in disguise.** If a block
  under a stage comment (e.g. `# Check for duplicate stable IDs`) has its own
  local state and reports into a shared `problems` list, write it as a named
  helper returning its results and let the enclosing function orchestrate.
  Structure multi-stage pipelines as orchestrator + stage helpers from the
  first draft — not as a refactor after the function is already over budget.
  Exemplars: `_group_entries` / `_load_directory_metadata` /
  `_subdirectory_entries` under `generate_index` in `index.py`.
- **CLI commands are thin adapters**: option parsing and validation, one or two
  library calls, then output formatting and exit codes. Any traversal,
  matching, or content-generation loop growing inside a `cli.py` command body
  belongs in a library module or a module-level helper with explicit
  parameters — history shows CLI-embedded logic ends up needed by the library
  anyway (`entries_for_directory` had to be extracted from `index_cmd` when
  `move_concept` needed it, #69).
- **Check complexity at draft time.** Run
  `python -m ruff check --select C901 <touched files>` as soon as a first
  draft compiles, while restructuring is cheap — do not discover it at
  `just ci` time and bolt on a `noqa`.

## Changelog

The project uses `CHANGELOG.md` at the repo root following the [Keep a Changelog](https://keepachangelog.com/en/1.1.0/) format.

- The `[Unreleased]` section at the top accumulates entries for work merged to `main` but not yet tagged. Add entries there as features and fixes land, not at release time.
- On release, rename `[Unreleased]` to the new version with its date (e.g. `## [0.5.0] - 2026-09-01`), add a fresh empty `[Unreleased]` section above it, and add a comparison link at the bottom of the file.
- Use the standard Keep a Changelog categories within each version block: `### Added`, `### Changed`, `### Deprecated`, `### Removed`, `### Fixed`, `### Security`. Only include a category heading if it has entries.
- Each entry should be a single bullet naming the feature or fix, the public API surface affected if any, and the closing issue number in parentheses.
- Do not restate what the diff already shows. An entry should give a reader enough context to understand what changed and why it matters, not describe the implementation.

## Delivery Rules

- Tests are mandatory for delivered behavior.
- User-facing behavior changes must update `README.md`, `src/okf_core/orientation.py`,
  any affected CLI command help strings, and function docstrings in the same commit.
  After editing any of these, search for all references to the changed functionality,
  commands, or parameters across `README.md`, `AGENTS.md`, `src/okf_core/orientation.py`,
  CLI help strings, and module/function docstrings to ensure nothing is left stale and
  all documentation remains explicitly aligned.
- After editing `README.md`, review the document as a whole so it stays accurate
  and internally consistent.
- After editing `AGENTS.md`, review the affected section as a whole for internal
  consistency (e.g. a sentence that says X is required should not be immediately
  followed by instructions for when X is unavailable).
- Updates to `main` must happen through pull requests only.
- Do not close story issues until the implementation PR has been approved by a
  human and merged.
- Do not try to align pull request numbers with issue numbers. GitHub assigns
  them from one shared sequence, and issues and PRs do not have a stable
  one-to-one relationship. Link work explicitly with `Closes #N`, `Refs #N`, or
  `Part of #N` in PR bodies instead.
- Copilot review can supplement human review, but it does not replace the human
  approval requirement.

## Automated Agent Rules

> **These rules apply to automated agents (e.g. Claude, Copilot) only.**
> Human contributors are not subject to these constraints and may use normal
> Git and GitHub workflows at their discretion.

- **Do not merge pull requests.** The human reviewer merges manually after
  approving. Do not call any merge API or CLI command on a PR.
- **Do not force-push** (`git push --force` or `--force-with-lease`). If a
  branch needs updating, push new commits instead.
- **Start each issue on its own branch**, created fresh from `origin/main`:
  ```sh
  git fetch origin main
  git checkout -b <branch-name> origin/main
  ```
  Do not reuse or extend an existing feature branch for a different issue.

## Testing Guidelines

- **Decompose Tests**: Avoid monolithic "happy-path" tests that assert multiple independent configurations in a single test case. Decompose them into focused, single-responsibility tests to prevent assertion shadowing.
- **Utilize Parameterization**: Prefer `pytest.mark.parametrize` to cleanly cover variations of configurations, inputs, and boundaries rather than duplicating test structures.
- **Ensure Negative Coverage**: Every feature or parsing capability must have explicit negative tests verifying failure modes, such as:
  - Incorrect data/config types (e.g., list vs. string).
  - Malformed file inputs or config structures (e.g. invalid syntax).
  - Explicit error handling checks (asserting that `ConfigError` or expected domain exceptions are raised).
- **Round-Trip Property Tests for Markdown Interpolation**: Any function that interpolates a dynamic value into Markdown link/reference syntax must have a `hypothesis`-based round-trip property test — parse-generate-reparse and assert the recovered *value* matches the value that went in (a semantic/data-model comparison, not a byte-for-byte comparison of the surrounding document) — covering markdown-significant characters (`[`, `]`, `(`, `)`, unbalanced parens, backslashes, double quotes), not just hand-picked examples. Hand-picked examples miss adjacency effects between these characters that only a generated-input fuzz reliably reaches. See `tests/test_index_span.py` and `tests/test_log_writing.py` for the pattern, and grep the current codebase for `@given`/`hypothesis` usage in `tests/` for the current set of functions this rule already applies to — that set changes as code moves, so it is not enumerated here (#173; generalized by #193 so this rule survives the round-trip refactor tracked by ADR-0001/ADR-0002 without naming functions that may be renamed, merged, or replaced).
- **Characterization-First for Parsing/Serialization Deletions**: Any PR that
  deletes or replaces parsing or serialization code must land its
  characterization baseline (tests pinning the current, observable behavior
  before the change) in that same PR or an earlier one — never after the
  deletion, when there is nothing left to characterize against. The PR
  description or commit message must explicitly name which of the retired
  assertions were *drift oracles* (they verified "has behavior changed from
  a known-good snapshot," useful for catching accidental regressions during
  the transition) versus *correctness oracles* (they encoded the actual
  contract the new code must still satisfy) — collapsing that distinction is
  exactly how a byte-identity contract nobody actually required got baked in
  as if it were load-bearing (see ADR-0001 for the concrete case this rule
  generalizes from).
- **Freeze Time for Date/Time-Boundary Tests**: Any test exercising date/time-boundary logic (e.g. "what date does this default to today") must freeze time explicitly, e.g. via `freezegun.freeze_time`, rather than relying on the real `datetime.now()`/`date.today()` at test-run time — a test that snapshots the real clock before and after the call under test only suppresses flakiness near a day rollover, it doesn't verify the boundary itself; see `test_plan_uses_real_today_by_default` in `tests/test_log_writing.py` for the pattern (#174).
- **Enforce Code Formatting**: Run code formatting with `black` on the codebase prior to executing tests and before pushing/submitting code changes:
  ```sh
  just fmt
  # or without just:
  black src tests
  ```
- **Static Analysis**: During development, use `just lint` to run ruff and mypy, and `just lint-actions` to run actionlint on workflow files:
  ```sh
  just lint          # ruff + mypy
  just lint-actions  # actionlint (skipped automatically in Claude cloud instances)
  # or without just (requires venv activated or using venv binaries directly):
  python -m ruff check src tests .github/scripts/
  python -m mypy src tests .github/scripts/ --ignore-missing-imports
  .venv/bin/actionlint .github/workflows/*.yml
  ```
  `ruff` checks Python style and common bugs in the codebase and scripts, including cyclomatic complexity (`C901`, `max-complexity = 14`) and unused function/method arguments (`ARG`, with `ignore-variadic-names` so a `*args`/`**kwargs` catch-all isn't flagged); `mypy` checks types; `actionlint` validates GitHub Actions workflow YAML. `actionlint` is in the `.[actionlint]` optional dep group (installed automatically by `just install` unless a system `actionlint` is found on PATH). Note: `just lint` does not include the Black formatting check — use `just ci` before pushing.
- **Complexity budget**: New or modified functions must stay at or under cyclomatic complexity 14 (enforced by `ruff`'s `C901`). Do not add `# noqa: C901` to new code — refactor instead, following the Code Structure section above (which is designed to keep new code under this budget from the first draft). If a function's complexity is genuinely essential (e.g. a hand-rolled parser/state machine where splitting would only relocate shared mutable state, not reduce it), a `# noqa: C901` is acceptable but must carry an inline comment naming the specific constraint — a bare `# noqa: C901` is not. As of this writing there are no `# noqa: C901` suppressions in `src/` (verify with `grep -rn "noqa: C901" src/` before assuming otherwise) — the check has stayed satisfied by refactoring rather than by suppression, and any new suppression should be treated as the exception, not the norm.
- **GitHub scripts**: Python files under `.github/scripts/` must have unit tests in `tests/` where feasible. Prefer testing pure functions directly without network calls by passing a stub or fake for any `_api`-style dependency.
- **Branch coverage and the coverage-diff gate**: `pytest`/`just test` stay plain and fast — coverage is not collected on every run. `[tool.coverage.run]` in `pyproject.toml` enables branch coverage (`branch = true`, `source = ["src/okf_core"]`) for the explicit coverage runs below, which measure whether both arms of a conditional were exercised, not just that the line was reached — line coverage alone can hide an untested `except`/`else` branch. A dedicated `coverage-diff` GitHub Actions job (`.github/workflows/test.yml`, PRs only, single run on Python 3.11) runs `pytest --cov=okf_core --cov-branch --cov-report=xml` followed by `diff-cover coverage.xml --compare-branch=origin/<base-ref> --fail-under=90`. `diff-cover` scopes its check to lines the PR actually added or changed (new/changed lines in the diff against the PR's base branch), not the whole-codebase aggregate, so an old, already-uncovered file doesn't block an unrelated PR — but new code must be covered. The 90% floor is a starting point, not a fixed target; revisit it if it proves too strict or too lax in practice. Reproduce it locally with:
  ```sh
  just coverage-diff
  # or without just:
  pytest --cov=okf_core --cov-branch --cov-report=xml
  diff-cover coverage.xml --compare-branch=origin/main --fail-under=90
  ```
  `just coverage-diff` compares against `origin/main` and skips gracefully (rather than failing) when there's no comparable base to diff against, e.g. running it locally while already on `main` itself.
- **Before pushing**, always run `just ci` — it is the definitive local equivalent of the full CI pipeline:
  ```sh
  just ci
  # or without just:
  black --check src tests && python -m ruff check src tests .github/scripts/ && python -m mypy src tests .github/scripts/ --ignore-missing-imports && .venv/bin/actionlint .github/workflows/*.yml && pytest
  ```
- Use `just test-matrix` to run the full pytest suite locally across all Python versions configured in the GHA workflow matrix (e.g. 3.10, 3.11, 3.12, 3.13) via Docker:
  ```sh
  just test-matrix
  # or without just:
  python .github/scripts/run_local_matrix.py
  ```
  This parses the workflow matrix from `.github/workflows/test.yml` and spins up containerized pytest checks to detect version incompatibilities before raising a pull request.

<!-- minime-cook-block v2 (source: chewcorp/minime-coder docs/cook-block.md; copy verbatim) -->
## Cook rules

- Post your plan, then keep building in the same session. Do not wait for a "go". Exception: where this repo's AGENTS.md or plan skill requires human sign-off for a change's tier, wait for that sign-off on that change only.
- If something blocks you, comment on the PR (or the Linear card if there is no PR yet). Say what blocks you, the options, and which one you recommend. Then carry on with every part that is not blocked. Never end a session on a question you only asked yourself.
- Answer every review finding on the GitHub PR, as a reply in its thread. Linear gets one line at most.
- Resolve a thread only when you fixed what it raised. To decline, reply with the reason and leave the thread unresolved.
- Bot review cap: at most 3 push rounds that answer bot findings. After round 3, stop pushing, and reply to any new bot finding that it is held for Russell. Comments from Russell are always acted on and don't count toward the cap.
- Do not merge.
- If this repo's AGENTS.md lacks the marker line above, first open a separate PR that adds this block verbatim, then branch the story from that PR.
<!-- /minime-cook-block -->
