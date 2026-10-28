# Changelog

All notable changes to Crypto Trading Lab are documented in this file.
The format is based on [Keep a Changelog](https://keepachangelog.com/),
and the project intends to follow
[Semantic Versioning](https://semver.org/) once it reaches 1.0
(current version: `0.0.0.dev0`).

Entries before this file existed live only in `git log --oneline`; the
list below starts at the repository review that created it. For the
per-chapter state of the specification, see [`ROADMAP.md`](ROADMAP.md).

## [Unreleased]

### Added

- **Monthly candles can be downloaded and validated.** `1M` joins the
  downloader's vocabulary, and `validate_candles` checks it by calendar
  month instead of by a fixed step: February is 28 days and August is 31,
  so the old arithmetic called one an overlap and the other a gap.
  `CALENDAR_INTERVALS` names the intervals that need the calendar path,
  and the 30-day entry in `TIMEFRAMES` is now arithmetic only (volume
  scaling, size estimates). This also fixed `DatasetValidation.ok`, which
  ignored `issues` entirely — an off-grid or overlapping series was
  reported as "ready for research" while its problems were printed
  nowhere, because the explanation only lists issues when `ok` is false.
- **The GUI timeframe dropdown offers the exchange's intervals.** The
  Historical Data screen listed the six intervals the downloader knew; it
  now lists all sixteen intervals Binance serves, fastest first (`1s` …
  `1M`), and the default stays `1h`. Offering `1s` also made a real
  footgun reachable: a 1-second
  download over the default five-year range is about 157 million candles,
  and the old guard only fired after walking two million of them page by
  page. A request now estimates its size first and raises
  `DownloadTooLarge` with a plain-language explanation before the first
  network call.
- **`paper-live` accepts every interval Binance streams, including `1s`.**
  The live path validated against the historical downloader's curated
  `TIMEFRAMES` table, so `--interval 1s` was refused even though the
  exchange serves it. The exchange's own vocabulary now lives in
  `BINANCE_INTERVALS` (`exchanges/binance/config.py`), and the downloader
  adopted it later the same day. Fixing the validation exposed a second, silent
  defect: the chapter-56 volume proxy read the same table, so an interval
  it did not know produced zero average daily volume, an empty synthetic
  book and a rejection of every order. `interval_seconds()` now derives the
  duration from the interval string, and a test pins a 1s session that
  fills instead of rejecting.
- **The live session says when a strategy never warmed up.** A short
  `paper-live` run can end before the strategy has seen enough candles to
  emit its first signal, and the empty journal then looked like a flat
  market. Strategies now declare `warmup_candles` (`ma_crossover` reports
  `slow + 1`, buy-and-hold 1, a strategy that does not declare one reports
  0 and gets no warning), `PaperSessionResult.warmup_candles` carries it,
  and a session that received fewer candles than that adds a sentence to
  its note explaining why nothing happened. The CLI prints a `Warm-up:`
  line next to `Candles received:`. The warning is an explanation only: it
  does not change the account, the journal or the risk gate.
- **A working Binance WebSocket feed, and paper trading over it (chapters
  26.2 and 27).** The client existed but could not do its job: `start()`
  blocked forever, so a caller could never stop it; the staleness check ran
  *after* a message arrived, which is the one case where staleness is not a
  problem; connection renewal logged a line and kept the dead socket open;
  duplicate detection keyed on the event time across all streams, so a kline
  and a trade in the same millisecond looked like duplicates; ticker streams
  were never dispatched; and an empty client spun the CPU. All of that is
  fixed: `start()` schedules the runner and returns, a watchdog detects
  silence on a timer, renewal really closes and reopens the socket,
  deduplication is per stream (klines key on the event time so forming and
  closed updates both survive), ticker messages reach their handlers, a
  broken handler no longer kills the feed, and `stop()` cancels the real
  tasks. `run_paper_session_live()` now runs a bounded session and returns a
  coherent result: it used to await the blocking `start()`, so the timeout
  never fired; it wrote the journal into the current working directory on
  every candle; and it reported a default `PaperSessionConfig` whatever the
  caller asked for. Signals are no longer evaluated while the feed is
  DEGRADED (chapter 27) — those candles are buffered and counted in the
  note. New `crypto-trading-lab paper-live` command. **Fixed on the way:**
  the risk manager added every order's notional to the current exposure, so
  a sell that closes a long was rejected for exceeding the exposure limit —
  the gate could block the order that reduces risk. Exposure is now computed
  from the position the order leaves behind. 26 new tests; baseline 782 →
  **807 passed, 2 skipped**. Chapter 27 is `[x]`; every connection state now
  links to a real section of `docs/en/user-guide/20-troubleshooting.md`, and
  a test fails if a link or its anchor stops resolving.


- **Drift reporting (chapter 63.2).** A paper session is now judged against
  what its backtest predicted, not just compared to it. `expected_ranges()`
  builds the band each metric should stay inside: the return band comes from
  resampling the backtest's own trades, anchored on the return the run
  actually realised (the bootstrap sees closed trades only, while the run
  also holds open positions); the drawdown band is anchored on the observed
  drawdown and widened by a 1.5x tolerance, because a trade-level bootstrap
  cannot see the drawdown that happens inside a trade and would otherwise
  report a band of zero for any profitable run. Every band states its
  `basis`. `drift_over_time()` splits both equity curves into equal slices,
  so a run that drifts away in its last third no longer hides behind an
  average. `assess_drift()` returns a `StrategyHealth` verdict — healthy,
  suspicious or degraded — using four per-metric verdicts that separate a
  normal tail (outside the band by less than half its width) from real
  degradation, and treats a result *better* than the band as a warning
  about the model rather than good news. Each dimension carries a list of
  likely causes to check. A backtest with fewer than two trades produces no
  band, and the run is reported as unvalidated rather than healthy. The
  Paper Trading screen renders the whole analysis after every session; the
  assessment never touches the risk manager. 12 new tests; baseline 770 →
  **782 passed, 2 skipped**. Documented in
  `docs/en/developers/live-vs-backtest-drift.md`.


- **Execution realism now feeds the backtest and the robustness report, not
  only paper trading (chapter 56.5).** `BacktestConfig` gained
  `execution_config` and `execution_seed`; when a configuration is set,
  fills come from the chapter 56 synthetic order book whose depth is the
  traded volume of the candles *before* the fill candle, so an order larger
  than the modelled liquidity is partially filled and an order with no
  depth is rejected instead of being assumed away. Every run records the
  model and the seed in `config_metadata`; the CLI names the model and
  reports rejections and partial fills. The cost-model path is numerically
  unchanged. In robustness, `sweep_costs` scales the execution model's own
  slippage assumptions when realism is on (it also stopped dropping
  `position_fraction` and `execution_config`), and `compare_execution_models`
  adds an `execution_impact` section — baseline versus realistic, with the
  delta in profit and return — to every `RobustnessReport`. The report
  states the direction caveat: the cost model applies a fixed adverse
  slippage while chapter 56 draws from a symmetric band, so the realistic
  arm can come out cheaper, and that is not evidence of safety. 15 new
  tests; baseline 755 → **770 passed, 2 skipped**. Chapter 56 is `[x]`.
  Documented in `docs/en/developers/cli.md` and
  `docs/en/developers/unwired-modules-audit.md`.

- **A working command-line interface (chapter 22), and the shared use-case
  layer behind it.** The five subcommands that printed one line and returned
  `0` now do real work: `database check` runs SQLite's
  `PRAGMA integrity_check` and prints the schema version plus every table's
  row count (a missing database is reported as missing, not "passed");
  `import-csv` validates the file with the chapter 28 parser and only then
  creates the database; `backtest` loads stored candles and runs the
  chapter 37 engine with the chapter 40 metrics from a JSON or YAML
  configuration; `glossary search` parses the beginner glossary; and
  `list-lessons` reads the curriculum. The new
  `src/crypto_trading_lab/application.py` holds the use cases, and
  `MainWindow.load_csv_file` now calls the same `import_csv_file` the CLI
  does, so the two front ends cannot drift apart. `doctor` gained the
  twelve checks chapter 22 lists — connectivity and clock drift behind
  `--network`, so the suite stays offline — and never reads a credential
  store. 47 new tests (`tests/test_cli.py`, `tests/test_application.py`);
  baseline 707 → **755 passed, 2 skipped**. Documented in
  `docs/en/developers/cli.md`. YAML configurations read through PyYAML:
  the Debian package now depends on `python3-yaml`, pip users get it from
  `requirements-all.txt` or the new `yaml` extra, and JSON needs nothing
  extra.

- **The console script actually dispatches now.** `[project.scripts]`
  pointed at the GUI function, so an installed `crypto-trading-lab` ignored
  every argument and opened a window — `crypto-trading-lab doctor` hung.
  It points at `crypto_trading_lab.__main__:main`, which runs the CLI when
  there are arguments, the GUI otherwise, and imports Qt only on the GUI
  path. Found while measuring a clean virtualenv; two subprocess tests in
  `tests/test_cli.py` keep it fixed.

- **`PyYAML` in the Debian package and in `requirements-all.txt`.**
  `debian/control` now depends on `python3-yaml` (runtime and build), and
  `requirements-all.txt` lists `PyYAML>=6.0` so a machine without Debian
  packages gets the YAML backtest path in one install. `pyproject.toml`
  gained a `yaml` extra for the same reason.

- **The dead `Experiments/` references are gone.** The kit was deleted on
  2026-10-16 but the README, the handoff and the virtualenv guide still
  linked to it, so `tools/check_doc_links.py` failed in CI. The three links
  now point at `requirements-all.txt` and the manual `cross-platform`
  workflow; the checker reports zero broken links.

- **A clean virtualenv is measured, not assumed.** Section 8 of
  `docs/en/developers/venv-setup.md` records a fresh
  `python3 -m venv .venv` built from `requirements-all.txt`: PyYAML 6.0.3,
  PyQt6 6.11.0, SQLAlchemy 2.1.6, pytest 9.1.1, **755 passed, 2 skipped**,
  exit 0 — the same numbers as the system Python.

- **`tools/check_doc_links.py`, and a CI step that runs it.** The test suite
  never reads the documentation, so nothing caught broken links: five had
  accumulated in the README, three pointing at an anchor that never existed
  and two broken by a heading rename. The checker validates both halves —
  that a linked file exists, and that a `#fragment` matches a heading in the
  target — using GitHub's slug algorithm, and it is worth noting why that
  algorithm is easy to get wrong: GitHub emits one hyphen per space and does
  not collapse runs, so `## Contributing — bring your AI agent` is
  `#contributing--bring-your-ai-agent`. A checker that collapses whitespace
  reported five false positives here and buried the three real failures.
  Stdlib only, offline, no dependency; it is also a line in the definition of
  done in `CONTRIBUTING.md`.

- **A "What you get out of it" section in the README's contribution
  pitch.** The pitch sold the *mechanics* — a written specification, small
  PRs, an offline suite — but never the *domain*: that a contributor
  implements purged cross-validation, the deflated Sharpe ratio and
  triple-barrier labelling against written definitions, with eight major
  reference projects already studied so they do not have to. It also states
  the credit terms plainly, which the README did not mention at all: no CLA,
  no copyright assignment, GPL-3.0, attribution kept in git and the
  CHANGELOG.
- **An honesty signal in "The rules that keep this repository honest".**
  The CHANGELOG records that the suite once printed "passed" and then
  segfaulted, that CI had never been able to pass, and that an audit found
  16 modules wired to nothing. Pointing at that is a stronger invitation
  than a claim of perfection, and it is checkable.

- **`reference-projects.md` Parts E–H, completing ROADMAP chapter 25.**
  The four remaining references under `external/` are now studied and
  documented to the same evidence standard as Parts A–D — every claim tied
  to a file path, with the searches behind each negative recorded:
  - **Part E — Freqtrade** (GPLv3, inspiration only). Signals-as-data
    enforced by construction, dry-run as a run mode rather than a fork, and
    a documented list of what it does *not* provide (no walk-forward, Monte
    Carlo, cross-validation, out-of-sample split, risk-based sizing, kill
    switch, strategy identity, or dataset identity in hyperopt records).
  - **Part F — Hummingbot** (Apache-2.0, adaptable). The thin-subclass
    connector base, a richer exchange-rule model than CCXT's, the
    client-order-tracker recovery machinery, and an order-book query that
    *reports* insufficient depth instead of extrapolating.
  - **Part G — Jesse** (MIT, adaptable). Its stationary-bootstrap rule
    significance test is the strongest statistical artifact in any
    reference and the one mechanism to adapt for 43.2.
  - **Part H — TA-Lib** (BSD-3-Clause, adaptable). A 201-function catalog
    with machine-readable naming, parameter ranges and a documented
    streaming API that answers chapter 31's open incremental-updates item.
- **Three advertised claims were corrected by per-feature verification**,
  which is exactly what chapter 25 demanded: Jesse's optimization is random
  search with Optuna used only as a trial store (not "Optuna-driven"), its
  significance test is a stationary bootstrap (not "random-entry variants"),
  and its indicator catalog is 174 modules (not "300+"). Hummingbot's own
  README also describes three directories that do not exist.
- **A cross-reference finding worth keeping**: none of the six trading
  frameworks studied enforces its own limits. Freqtrade's protections only
  lock new entries and are opt-in, Hummingbot's kill switch ships
  `KillSwitchDisabledMode()` by default, and Jesse's sizing helpers are
  optional calls a strategy can bypass. That is the gap chapters 58–59 exist
  to close, now recorded in chapter 25 itself.

- `tests/market_data/test_quality.py`: the Chapter 29 data-quality
  framework (`market_data/quality.py`) now has an offline test suite —
  validation, stale/frozen rules, volume anomalies, configuration and
  report serialization.
- `tests/ui/test_accessibility.py` now verifies that the tab order is
  actually applied, and that a cross-window call fails loudly.
- `CODE_OF_CONDUCT.md`, `CHANGELOG.md` and `.gitattributes` so a fork
  inherits community rules, a change history and consistent line
  endings.
- `invalid_count` is accepted by `create_quality_report()` and
  `validate_dataset_quality()`, so rejected raw rows are reported as an
  `INVALID_OHLCV` error instead of being dropped silently.
- Missing `__init__.py` files for `crypto_trading_lab.machine_learning`,
  `crypto_trading_lab.testing` and `crypto_trading_lab.monitoring`.
  Without them `setuptools.find_packages()` omitted those packages from
  a built distribution (27 → 30 packages discovered).
- The `integration` pytest marker is declared in `pyproject.toml`.
- `docs/en/developers/unwired-modules-audit.md`: a per-module audit of the
  16 modules that no product path imports, with an explicit
  delete / merge / wire disposition for each.
- The chapter-56 execution model is now wired into paper trading:
  `paper_session.run_paper_session` and `run_paper_session_live` call
  `simulate_market_order` for entries and exits. `PaperSessionConfig` and
  `LivePaperConfig` gained a `seed`, `execution_realism` gained
  `synthetic_order_book()` / `simulate_market_order()` and an injectable
  `random.Random`, and `tests/test_execution_realism.py` adds 15 tests.
- Chapter 53 reproducibility is now wired into research records:
  `ExperimentManager.create()` fills `code_hash` from the source and
  attaches a compact `environment` (Python, platform, git revision,
  dependency versions) to every `ExperimentRecord`, which round-trips
  through `update_status`, notes, tags and `save`/`load`.
  `reproducibility` gained `environment_summary()`,
  `capture_environment(include_packages=...)` and a cached dependency scan;
  `tests/test_reproducibility.py` adds 12 tests.
- Chapter 63 drift is now wired to the Paper Trading screen:
  `live_vs_backtest` gained `drift_report_from_results()` and
  `render_drift_report()`, and every paper session is compared with the
  same strategy's backtest at the same sizing. `BacktestConfig` gained
  `position_fraction` (default `1`, so existing backtests are unchanged);
  it is recorded in `metadata()` and `tests/test_live_vs_backtest.py` adds
  10 tests.
- Chapter 72 ethics now guards report generation: `reporting/ethics.py`
  holds `EthicsChecker` + `STANDARD_DISCLAIMERS`, and every HTML/CSV/JSON
  report carries the five mandatory disclaimers plus explicit
  **Assumptions** and **Limitations** sections. `audit_report_ethics()`
  raises `EthicsError` on a violation (missing disclaimer, profit-guarantee
  language) and attaches warnings for omissions;
  `tests/reporting/test_report_ethics.py` adds 11 tests.
- Chapter 60 position sizing is implemented and reachable:
  `robustness.kelly_fraction()`, `optimal_bet_size()` (half-Kelly by
  default, capped by `PositionSizingConfig`) and
  `position_size_from_trades()`, which derives the edge from the backtest's
  own trades and returns 0 **with a warning** when the sample is too small,
  degenerate or edgeless. `RiskOfRuinReport` gained
  `recommended_risk_per_trade` and `ResearchRun` carries it to the research
  output. `tests/backtesting/test_risk_of_ruin.py` adds 15 tests.
- `docs/en/developers/venv-setup.md`: the complete virtualenv guide —
  every dependency under its Debian **and** PyPI name, both venv routes
  (`--system-site-packages` over the Debian Qt stack, or fully isolated),
  run/test commands, troubleshooting, and how to decide whether `ccxt` is
  worth adopting. `pyproject.toml` gained the `pdf` extra, and
  `tools/evaluate_ccxt.py` is a read-only script that
  reports ccxt's coverage and whether the project's adapter accepts a real
  client. Section 7 of that guide records the **measured** evaluation: ccxt
  4.5.84, 104 exchanges, Binance and Coinbase both exposing the required
  surface, `fetch_candles()` returning normalised Decimal+UTC candles from
  **both** exchanges over the network, and the suite passing inside the venv
  (698 passed, 2 skipped). Verdict: ccxt is worth adopting for chapter 26.3
  because it is the only path to a second exchange.
- Cross-platform pip installation: the four runtime packages are now
  declared in `[project.dependencies]`, so a plain `pip install .` works on
  Linux, macOS and Windows instead of installing nothing; `keyring` moved to
  a `credentials` extra. The README gained per-platform tutorials (Linux,
  macOS, Windows) covering the PowerShell execution-policy error and its
  safe per-session fix, and clearly marking Windows/macOS as **not yet
  verified**. `.github/workflows/cross-platform.yml` runs the suite on
  Ubuntu, macOS and Windows — `workflow_dispatch` only, so it can never
  redden the default CI.
- `Experiments/`: a self-contained verification kit for machines without
  Debian packages. `requirements-all.txt` lists every dependency (including
  `ccxt`), `setup_windows.bat` and `run_verify.cmd` do the setup in `cmd.exe`
  so PowerShell's execution policy is never involved, `verify.py` runs twelve
  checks (imports, CSV import, backtest, paper trading, the offscreen Qt
  window, the ccxt adapter) with optional `--tests`, `--gui` and `--network`
  stages and writes `verify-report.md`, and `CHECKLIST.md` is a tick-box
  manual to fill in and return. A 400-candle sample dataset lets the whole
  pipeline be exercised with no network. The generated report is
  git-ignored.
- **Windows 10 verified (2026-10-01).** The kit was taken to a real
  Windows 10 machine (10.0.19045, AMD64) with Python **3.14.7** and
  every package installed from PyPI: the virtualenv and `pip install`
  worked, the PowerShell activation error appeared and the documented
  `Set-ExecutionPolicy -Scope Process -ExecutionPolicy Bypass` cleared
  it, the application window opened, CSV import / backtest / paper
  trading produced numbers *identical* to Debian, and `ccxt` reached
  the network. The raw PowerShell transcript is kept in
  `Experiments/20261001-resultado-de-la-instalacion-en-Windows-10.txt`.
  The run also exposed the segmentation fault fixed below. macOS
  remains unverified.

### Changed
- **Three internal README links were pointing at an anchor that does not
  exist.** They said `#what-is-not-verified` while the heading is "What is
  verified, and what is not". Renaming the `## Quick start` heading also
  silently broke the two `#quick-start` links to it. Neither kind of breakage
  fails anything: the test suite never reads the README, and a link checker
  that only verifies that files exist will not look inside `#fragments`.
  Both were found by writing the anchor check, and the corrected checker
  algorithm is recorded here because it is easy to get wrong: GitHub emits
  **one hyphen per space and does not collapse runs**, so
  "Contributing — bring your AI agent" becomes
  `#contributing--bring-your-ai-agent`, not `#contributing-bring-your-ai-agent`.
- **The README's install instructions are now one section instead of two.**
  A "Start here — pick your platform" block had been added near the top with
  Debian, macOS and Windows commands, but it duplicated what the Quick start
  and "Install with pip" sections already said further down. It has been
  removed and its two genuinely unique pieces folded into the Quick start,
  which is the section that survives.
- **The Quick start's `apt` list was installing too little to reach the
  baseline it advertises.** It promised `707 passed, 2 skipped` but omitted
  `python3-pytestqt` and `python3-pypdf`. Without `pytest-qt` the five
  accessibility tests **error** rather than skip — verified by disabling the
  plugin: `2 passed, 5 errors`, exit 1 — and without `pypdf` the chapter-41
  export test skips, making the count 3. Both packages are now in the list,
  and the section explains why each one matters, since neither failure looks
  like a missing dependency. The same `dev`+`pdf` pairing is now stated for
  the pip route, where installing `".[dev]"` alone has the identical effect.
- **ROADMAP chapter 25 (reference projects) is closed: `[x]`, 13 boxes
  ticked, 0 open.** It had been `[ ]` with every box reading as undone even
  though four studies were already concluded and documented
  (`reference-projects.md` Parts A–D), so a reader would have concluded that
  nothing had been studied. The remaining four were finished on 2026-10-15
  (Parts E–H), and the chapter's closing requirement — document the
  conclusions — is now met.
- **`external/` is therefore removable.** The chapter's deliverable is the
  study and its written conclusions, not the vendored copies; nothing in
  `src/`, `tests/`, `pyproject.toml` or `Makefile` references `external/`,
  and both CI workflows pass `submodules: false`. The 12 GB release
  procedure is in `reference-projects.md` → "Disk cost, and what can now be
  removed"; it was tested end-to-end and is reversible.
- **The disk cost of `external/` is documented and measured**: not 930 MB but
  **12 GB** — 11 GB of git object store, 8.5 GB of it `ccxt`. The README and
  `CONTRIBUTING.md` had invited contributors to run
  `git submodule update --init --recursive`, which downloads all of it; they
  now state the real size and recommend fetching only the reference a task
  is about.
- **macOS verification is deferred to the end of development** by the
  maintainer's decision, after Linux and Windows. The `README.md` (agent
  prompt, good-first-contributions, "What is not verified"), the
  `Experiments/` kit, `AGENT-HANDOFF.md`, the virtualenv guide and the
  manual `cross-platform` workflow all say so now, so a contributing agent
  does not pick macOS up as the next task and does not read a red macOS job
  as a blocker.
- The documented test baseline was refreshed from the stale `702`/`704` to
  the measured **707 passed, 2 skipped** in the `README.md` badge and
  tutorials, `AGENTS.md`, `AGENT-HANDOFF.md`, `CONTRIBUTING.md`, the pull
  request template, `docs/en/developers/`, the `Makefile` and the
  `tests.yml` comment. `AGENTS.md` rule 2 no longer claims that no virtual
  environment has ever been needed, which had been false since the extras
  (`ccxt`, `pypdf`, `keyring`, `aiohttp`, `websockets`) were documented.
- **The GitHub Actions were moved to Node 24**: `actions/checkout@v4` → `@v5`
  and `actions/setup-python@v5` → `@v6`. GitHub had started force-running the
  old majors on Node 24 and annotating every run with the deprecation. Run
  [38777456963](https://github.com/wachin/crypto-trading-lab/actions/runs/38777456963)
  verifies the bump: `707 passed, 2 skipped` and no annotations.
- **The `tests` workflow now passes on `main`.** It had never been able to:
  run
  [38772811163](https://github.com/wachin/crypto-trading-lab/actions/runs/38772811163)
  was the first green build, and
  [38777456963](https://github.com/wachin/crypto-trading-lab/actions/runs/38777456963)
  repeats it, reporting the same counts as Debian (SQLAlchemy 2.1.4, pypdf
  installed, so the chapter-41 export test runs instead of skipping).

### Fixed
- **`StrategyRegistry` wrote to disk as a side effect of being built.**
  Its constructor created `data/strategy_registry/registry.json` under the
  *current working directory* — including the source tree — and did it for
  every registry, even one only used to list strategies. It also had a
  `_load()` that was never called, so the persistence was write-only: the
  file was written on every `register()` and never read back. The
  constructor no longer touches the filesystem, the load path runs, and
  built-in strategies keep the Python factories that JSON cannot carry;
  entries restored from JSON come back as metadata only and
  `get_factory()` says so. `StrategyRegistry(storage_path=...)` is
  unchanged for callers.
- **The Backtesting Lab could run a backtest with `None`.** The new
  registry lookup replaced the old `NullStrategy()` fallback, so an
  unregistered or metadata-only strategy id reached
  `run_backtest(candles, None, config)` and failed far from the cause. The
  widget now stops with a message naming the problem, and only offers
  strategies that can actually be instantiated.
- The strategy selector lost its translatable labels when it started
  reading the registry: it showed the raw registry names ("Ma Crossover")
  built at runtime, which `pylupdate6` cannot extract. The labels are
  literal `self.tr()` strings again, with the registry name only as a
  fallback for strategies registered by other code (chapter 36).
- **The CI had never been able to pass.** `tests.yml` ran on
  `ubuntu-24.04`, whose `python3-sqlalchemy` is **1.4**, while the code
  needs 2.0 (`DeclarativeBase`): every build died with an `ImportError`
  during collection. The workflow now installs with pip in a venv, the
  path the README documents, and `cross-platform.yml` additionally runs
  Ubuntu, macOS and Windows manually.
- The manual `cross-platform` workflow itself failed on all three
  systems on its first run because it wrote `VENV_PY` to `$GITHUB_ENV`
  and then used `$VENV_PY` **in the same step** (GITHUB_ENV only applies
  to later steps), so the command expanded to nothing and exited 127.
- Both workflows installed `".[dev]"`, so the chapter 41 PDF export test
  was skipped in CI (`could not import 'pypdf'`) and the CI baseline no
  longer matched the documented one. They install `".[dev,pdf]"` now,
  the same set the README documents.
- `tests/exchanges/test_binance_adapter.py` reached the real Binance
  endpoint to prove that trading is refused when it is enabled, which
  made the suite fail with `HTTP 451` on GitHub's runners. It patches
  `_make_signed_request` instead; the whole suite now passes with a bogus
  proxy, which is the offline guarantee the project claims.

- **The test suite segfaulted when the interpreter exited.** Every test
  passed (`698 passed, 2 skipped`) and then the process died with SIGSEGV,
  so the exit code was non-zero and `make test`/CI reported failure. Found by
  the Windows 10 verification run and reproduced on Linux; the cause was
  `trading.py`: chapter 68's safety logic imported `PyQt6.QtCore`, and
  `RealTradingManager.deactivate()` called `self.__init__()` on a `QObject`,
  which is undefined behaviour with sip. The suite now exits `0`
  (707 passed, 2 skipped).
- `trading.py` no longer depends on Qt at all: `RealTradingManager` is a
  plain class, the UI subscribes through the existing `add_observer` API,
  and a regression test asserts that importing the module pulls in no
  `PyQt6`. That keeps chapter 68 safety logic importable headless, as
  chapter 6.1 requires.
- State changes now actually notify: `set_state()` was never called by the
  activation, suspension or deactivation paths, so the main window's
  "REAL TRADING" indicator could never update. Those paths call
  `set_state()` now, and observers receive `(state, message)`.
- `venv-setup.md` now explains the two messages a `pip install` prints
  inside a `--system-site-packages` venv: `Not uninstalling X … outside
  environment` (pip correctly refusing to modify the Debian packages) and
  `ERROR: pip's dependency resolver … weasyprint … html5lib` (a conflict in
  a *system* package this project does not use; the install still succeeds
  and pip exits 0).
- The documented test baseline had been left at **683 passed, 2 skipped**
  in ten places (the README badge and body, `AGENTS.md`,
  `AGENT-HANDOFF.md`, `CONTRIBUTING.md`, `Makefile`, the pull-request
  template and the developer docs) after the chapter-60 turn: a previous
  update used the wrong search value and silently changed nothing. It is
  **698 passed, 2 skipped**.
- `README.md` no longer states the blanket "No virtualenv, no `pip install`,
  no network"; the Debian-first default is unchanged, and the PyPI-only
  path is documented separately in `venv-setup.md`. `CONTRIBUTING.md` and
  `debian-dependencies.md` say the same thing instead of "no virtualenv".
- `render_pdf()` was broken: it called `PdfWriter._addObject` /
  `_writeObject` / `.stream`, private names that pypdf 5 removed, so every
  PDF export raised `AttributeError`. It now builds the document with the
  current API, escapes PDF string delimiters that a strategy name could
  inject, and returns bytes.
- The ethics checker only matched the underscore spelling of
  "out_of_sample", so the normal English "out-of-sample" was reported as
  missing.
- `live_vs_backtest.calculate_regime_drift()` put the **live** return into
  the backtest bucket, so per-regime drift was always exactly zero. It also
  silently truncated mismatched inputs; it now raises.
- `calculate_drift_metrics()` iterated a `set`, so metric order and the
  report were non-deterministic, and a zero backtest baseline was reported
  as "no drift" instead of material.
- `analyze_execution_drift()` computed fill rates with float division,
  leaking binary floating point into a money-adjacent report.
- The drift bridge cannot mistake position sizing for drift: the backtest
  engine invested 100 % of cash while the paper session uses
  `position_fraction`, so returns now require matched sizing and a mismatch
  is reported as a `SIZING MISMATCH` warning rather than a fake drift.
- `reproducibility.compute_code_hash()` walked the **relative** path
  `"src"`, so running the app or the tests from any other directory hashed
  nothing and returned the SHA-256 of the empty string (`e3b0c442…`). It is
  now cwd-independent.
- `capture_environment()` stored the **values** of every `CRYPTO_*` /
  `TRADING_*` environment variable, so an API key present in the
  environment would have been written in clear text into
  `experiments.json`. Variables whose name looks like a credential are now
  recorded as `***` (chapter 9 / threat model).
- `reproducibility` no longer uses the deprecated `pkg_resources`; the
  dependency scan uses `importlib.metadata` and is cached per process
  (~520 ms per call before).
- Chapter 56's model was inert: `paper_session` imported
  `simulate_execution` and never called it, so an `execution_config` only
  changed one `impact_factor` term and partial fills came from an
  **unseeded** `random.random()`, making paper-trading runs
  non-reproducible. Seeds now make a session reproducible, and an order
  larger than the modelled liquidity is partially filled or rejected
  instead of being assumed away.
- `simulate_execution` computed its slippage price and then discarded it,
  returning the raw book-ladder average and reporting market impact in the
  `slippage_bps` field. The slippage model now sets the price and the
  reported slippage.
- `calculate_slippage` could return **favourable** slippage — the random
  term could push the total negative, so a buy filled below mid. Slippage
  is now clamped to be adverse, as slippage is by definition.
- `run_paper_session_live` divided the P/L of a partial exit incorrectly
  and always recorded `entry.slippage = 0` because it read `position`
  after zeroing it.

- `create_quality_report()` raised `TypeError` because it indexed the
  `DataQualityReport` returned by `validate_dataset_quality()`
  (`report[0]`).
- `DataQualityValidator` no longer mislabels missing, duplicate or
  invalid-row counts as `GRID_ALIGNMENT` warnings; only genuinely
  off-grid timestamps get that code.
- Keyboard tab order set by `MainWindow` had no effect: it was applied
  before the buttons shared a top-level window, which Qt silently
  ignores. The call now runs after `setCentralWidget()`, and
  `AccessibilityHelper.set_tab_order()` raises `ValueError` instead of
  pretending when widgets live in different windows.
- `machine_learning/strategies.py` was deleted (see Removed); earlier in
  this batch it had an unused `scipy` import, a `NameError` in
  `evaluate_ensemble()` (`report` → `performance`) and duplicate `__all__`.
- `features.py` no longer declares `compute_asset_correlations()` with a
  bare `except:` next to an `import scipy.stats` the project does not
  ship (see Removed).
- `setup.py` duplicated metadata from `pyproject.toml` and disagreed
  with it (different dependencies, missing packages). It is now a
  metadata-free shim, and the license is declared with the SPDX
  expression `GPL-3.0-only` instead of the deprecated TOML table.
- `pyproject.toml` package data now includes the Learning Center
  tutorial figures, so an installed copy can display them.
- `media-generation/README.md` and `generate_tutorial_images.py` no
  longer hard-code the maintainer's `/home/wachin/...` path.
- Documented test baseline corrected to **698 passed, 2 skipped**
  across `README.md`, `AGENTS.md`, `AGENT-HANDOFF.md`,
  `CONTRIBUTING.md`, `Makefile`, the pull-request template and the
  developer docs. It had drifted between 229, 415, 522, 599 and 611.
- `AGENTS.md` "Current position" no longer claims the project is at
  chapter 40; that chapter is implemented.
- `ROADMAP.md` header rewritten as an English specification preamble
  instead of an audit report about a file that is not in the repository.

### Removed

- **`hypothesis` and `typeguard` are no longer declared dependencies.** Both
  sat in the `dev` extra and neither was used: no test imported them, pytest
  was never configured to activate them, and the ROADMAP names neither.
  `typeguard` was dropped outright — chapter 4.7 assigns type checking to
  `mypy`, which is static, and a second runtime checker has no home here.
  `hypothesis` may return: the README invites property-based tests, and a
  financial engine has invariants worth fuzzing (drawdown never negative, a
  strategy never exceeding its exposure cap, an equity curve round-tripping
  through the ledger). The reasoning lives in `venv-setup.md` rather than in
  `pyproject.toml` alone, so whoever picks that work up finds it.
- **`GENESIS.md`.** It was the Phase 0 bootstrap instruction written when
  the repository was empty, and every deliverable it ordered now exists
  (the dependency research, the architecture proposal, the threat model,
  the seven ADRs and the first beginner guides), so it had become a second,
  partly contradictory onboarding list: the README told contributors to
  read four files while `AGENTS.md` told agents to also read `GENESIS.md`.
  Two rules in it existed nowhere else and moved into `AGENTS.md` first —
  *silence is not approval*, and *build only what the task needs, never
  empty stubs mirroring the planned architecture* — along with the project's
  one-sentence creed. `AGENTS.md` rule 2 no longer points at it.
- Obsolete root-level scratch files (translation scripts, an orphan
  JSON Schema and internal audit/plan notes). They are preserved
  locally under `.scratch/`, which is git-ignored.
- The archived `numba-vs-decimal` benchmark script, which imported the
  deleted `performance/numba_accel` module. The decision record it
  supported is kept in `docs/en/developers/benchmarks/README.md`.
- Dead chapter-51 portfolio code that had been pasted into
  `market_data/features.py` (`portfolio_backtest`,
  `compute_asset_correlations`, `compute_portfolio_metrics` and three
  unused warning constants). It duplicated the tested `portfolio.py`,
  was imported nowhere, and its correlation function needed `scipy` plus
  a bare `except:`.
- Nine unwired modules that no product path and no test imported
  (2,317 lines). Each was either a duplicate of a tested module, a
  re-statement of a markdown document, or non-functional; every decision
  and its evidence is recorded in
  `docs/en/developers/unwired-modules-audit.md`:
  `benchmarking.py` (42), `live_monitoring.py` (62, non-functional),
  `research_notebooks.py` (54), `capital_protection.py` (61),
  `working_method.py` (70), `development_phases.py` (69, raised
  `KeyError`), `infrastructure/performance.py` (13),
  `ui/charts/qt_websocket_client.py` (4.2) and
  `machine_learning/strategies.py` (48).
  `ROADMAP.md` §4.4 item 3 was corrected accordingly.
- `research_ethics.py` (chapter 72), after merging its checker into
  `reporting/ethics.py`. The unused `EvidenceLevel`, `EvidenceLabel`,
  `generate_evidence_label`, `format_evidence_label`,
  `WarningType` and `EthicalWarning` were dropped instead of carried over
  as dead weight; the evidence ladder already lives in
  `reporting/report.py` and `ui/research/validity.py`.
- `risk_of_ruin.py` (chapter 60), after merging its Kelly sizing into
  `backtesting/robustness.py`. Its closed-form ruin formulas
  (`risk_of_ruin_binomial`, `risk_of_ruin_diffusion`),
  `capital_depletion_path` and `sequential_risk_of_ruin` were **not**
  ported: they mix units, multiply a per-trade expectancy by 100/50 and
  present it as an "expected/median drawdown", or return 0/1 while claiming
  to be a probability. The Monte-Carlo estimate that already exists is more
  defensible.
- The whole `exchanges/coinbase/` package (chapter 26.3): the native
  adapter and its endpoint config. Nothing imported either; the WebSocket
  client was a placeholder, `stop()` was declared twice so the synchronous
  definition silently overrode the async one, and the REST path recorded
  circuit-breaker *successes before the request*, so the breaker could never
  open. `ROADMAP.md` §26.3 and `docs/en/developers/live-trading-roadmap.md`
  were corrected to state that Coinbase is **not implemented**; the sandbox
  warning the config carried is preserved in the roadmap text.

