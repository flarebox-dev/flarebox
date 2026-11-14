# Testing

[CI](../.github/workflows/ci.yml) runs every test suite on each pull request, in the merge queue and on `main`. The [property battery](#the-property-battery-runs-nightly-and-on-demand) runs the property tests at high case counts every night and when you start it. The [heavy tests workflow](#heavy-tests-run-on-github-actions) runs one package's tests on Ubuntu and macOS as many times as you ask. To run the Rust checks that CI runs:

```sh
cargo fmt --all --check
cargo clippy --workspace --all-targets --locked --features koidrive-cli/test-install-inventory -- -D warnings
cargo test --workspace --locked --features koidrive-cli/test-install-inventory
```

## CI runs these jobs

Each job runs on Ubuntu, and the jobs marked macOS run on macOS. A change whose files are all under `site/` skips the build and test jobs.

| Job | What it checks | Run it locally |
|---|---|---|
| `rust` | Workspace fmt, clippy and tests, and the property-persistence check | The commands above and the [property-persistence check](#property-tests) below |
| `server` | Type checks, the Worker's Vitest suite, and the unit tests of the deploy-test scripts | In `server/`: `pnpm install --frozen-lockfile`, `pnpm typecheck`, `pnpm test`, then `pnpm exec vitest run --config scripts/deploy-test/vitest.config.ts run.unit e2e.unit load.unit bench.unit` |
| `server deploy check` | A copy of `server/` deploys on its own (a dry run, then `wrangler dev` and a claim), and the server bundle that the CLI embeds packs cleanly | `node server/scripts/check-deploy.mjs` |
| `net integration`, `driver integration`, `cli integration`, `ffi integration` | The tests whose `#[ignore]` reason says they need the Worker, against the Worker under `wrangler dev` | After `pnpm install` in `server/`: `core/net/scripts/integration-test.sh`, `core/driver/scripts/integration-test.sh`, `cli/scripts/integration-test.sh` or `core/ffi/scripts/integration-test.sh` |
| `spec` | `buf lint`, generated code that matches `spec/proto`, and no breaking change against the base | In `spec/`: `buf lint`, then `buf generate` and check that `git status` shows no change |
| `comments` | The change adds no code comments outside the allowed kinds | `python3 scripts/check-new-comments.py origin/main HEAD` |
| `macos app` (macOS) | The app builds, the Swift bindings' tests pass, and an unsigned disk image packages and verifies | In `apps/macos/`: `scripts/build-ffi.sh`, then `swift test --package-path KoidriveFFI` |
| `runner hook` (macOS) | The self-hosted runners' job-started hook and its installer | `.github/runner/test-job-started.sh` and `.github/runner/test-install-hook.sh` |

On a pull request, CI adds macOS jobs only where a change needs them. `rust (macos)` and `macos app` run when the change touches a file that builds or behaves differently on macOS, as `scripts/macos-changes.sh` lists them. `runner hook` runs when it touches `.github/runner/`. Every macOS job, `server (macos)` and `spec (macos)` included, runs when it touches `ci.yml`. The merge queue runs every macOS job, and a push to `main` runs each one the merge queue did not pass on the same commit. The macOS jobs run on GitHub-hosted runners unless the `MACOS_RUNS_ON` variable selects the [self-hosted runners](../.github/runner/README.md).

One test in `cli/tests/server.rs` also needs a systemd user instance. The `cli integration` job starts one, and locally the test is skipped unless `KOIDRIVE_TEST_SYSTEMD=1` is set.

Two other workflows run on pull requests. [CLI distribution](../.github/workflows/release-cli.yml) builds the CLI tarballs, tests the installer and installs the CLI from a local Homebrew tap. [DCO](../.github/workflows/dco.yml) checks the `Signed-off-by` line of every commit.

## Some tests run only on request

`cargo test` skips a test marked `#[ignore]`. Each ignore reason says how to run the test:

- The integration tests that need a Worker run through the scripts in the table above.
- `upload_benchmark` in `core/net/tests/upload_bench.rs` runs in the [deploy test's bench mode](deploy-test.md#modes), or against a local Worker with `KOIDRIVE_BENCH_MIB=64`.
- The timing probe in `core/fs/tests/ignore.rs` runs with `cargo test -p koidrive-fs --release --test ignore -- --ignored`.
- Two tests in `core/sim/tests/devices.rs` are known failures: the property `devices_converge_across_server_restores` and the fixed schedule `a_resend_applied_before_a_delete_built_without_it_yields_to_it`. The fix for each removes its `#[ignore]`.

## Property tests

The property tests use [proptest](https://docs.rs/proptest/1.12.0/proptest/). They are the `proptest!` blocks in the integration tests of `core/chunk`, `core/engine`, `core/ignore` and `core/sim`, and in the unit tests of `core/driver/src/engine.rs` and `core/net/src/session/tests.rs`. The largest is the interleaving property in `core/sim/tests/engine_sync.rs`. Each block sets its own case count. Two environment variables override every block:

- `PROPTEST_CASES`: the number of cases each property runs.
- `PROPTEST_RNG_SEED`: a fixed seed, a whole number. The same seed, case count and commit give the same cases. Without it, each run picks a random seed.

The properties run in one of two modes, set by `KOIDRIVE_PROPTEST_DETERMINISTIC` (`true` or `false`, unset means `false`):

- Exploring (`false`): each run picks a random seed, so every run tries new cases. Pull requests, pushes to `main`, the property battery and local runs use this mode.
- Deterministic (`true`): every property starts from seed 0, so the same commit runs the same cases on every run. The merge queue uses this mode, so a known bug on `main` that a random seed happens to reach does not remove an unrelated pull request from the queue.

Both modes replay the saved cases first. `PROPTEST_RNG_SEED` overrides seed 0, and `PROPTEST_CASES` overrides the case count in both modes. `ci.yml` sets the variable once for the whole workflow, to `true` only for `merge_group` events.

When a property fails, proptest prints the shrunk input. The shared configuration saves its `cc` line and a single-line `# shrinks to` description in a `<suite>.cases/cc-<seed>.txt` file, for example under `core/sim/tests/engine_sync.cases/`. Later runs replay saved cases first. Replay a failure by its `cc` line rather than by `PROPTEST_RNG_SEED`. Commit the case file with the fix so it keeps being checked.

Every property block uses `koidrive_test_support::regression_config`. CI checks this with:

```sh
cargo run --manifest-path scripts/check-proptest-persistence/Cargo.toml --locked --
```

The loader also reads legacy `.proptest-regressions` files. To move their lines into case files, run `python3 scripts/split-proptest-regressions.py <legacy-file>`.

### Several devices

`core/sim/tests/devices.rs` runs two or three devices against one reference server while effects fail, messages are lost, repeated or reordered, commits are refused, and devices crash between store transactions or in the middle of an effect (`core/sim/src/world`). Its properties come in pairs:

- `devices_lose_no_write...` fails when a write is lost, or when the engine, the store or the server refuses a state.
- `devices_converge...` also fails when a device does not reach the server's tree once the faults stop, or when a commit makes a change that the user of its device never made.

The plain pair runs without server losses. The `..._across_server_restores` pair adds servers restored from backups, and the `..._across_rewinds_and_rollbacks` pair adds rewinds, copied stores and rolled-back stores. `cargo test` and the battery run all six except `devices_converge_across_server_restores`. To print the state after every step of one test:

```sh
KOIDRIVE_SIM_TRACE=1 cargo test -p koidrive-sim --test devices <test name> -- --nocapture
```

Add `--ignored` to run an ignored test.

## The property battery runs nightly and on demand

The [property battery](../.github/workflows/property-battery.yml) runs every property test at a high case count on GitHub Actions. It runs every night on `main` with 24 shards of 8192 cases. To start it for a branch, use `scripts/battery.sh`. It needs [gh](https://cli.github.com/) signed in to an account that can run workflows on the repository:

```sh
scripts/battery.sh                         # the current branch, as pushed
scripts/battery.sh --cases 16384 --shards 48 feat/my-branch
scripts/battery.sh --filter a_device --wait
```

The script prints the run URL and returns. With `--wait` it follows the run and exits with its result.

| Option | Workflow input | Default |
|---|---|---|
| `REF` | The branch or tag to test | The current branch |
| `--cases N` | `cases`, the `PROPTEST_CASES` of each shard | 8192 |
| `--shards N` | `shards`, at most 256 | 24 |
| `--filter TEXT` | `filter`, a test name filter as for `cargo test` | None |
| `--mutations` | `mutations`, which also runs the [mutation set](#the-mutation-set) | Off |

The build job compiles every test binary that contains a `proptest!` block, including blocks pulled in with `mod` or `include!` and library unit tests. It fails if a `proptest!` block is in no binary or if the filter selects no test. Each shard then runs those binaries with its own seed, `PROPTEST_RNG_SEED` = run ID × 1000 + shard number, so every run covers new cases. A shard fails if a binary runs a different number of tests than it lists. The summary job lists each shard's seed, result and log.

The workflow runs on the ref it tests, with that ref's own copy of the workflow file, so the ref must contain it. A branch's battery can then write only that branch's Actions cache, never `main`'s.

### When a shard fails

The shard's job summary prints one command per failing test target, for example:

```sh
git checkout <commit> && PROPTEST_CASES=8192 PROPTEST_RNG_SEED=<seed> cargo test --locked -p koidrive-sim --test engine_sync
```

The command reproduces the failure locally. The `failure-shard-<k>` artifact holds the seed, the commands, the test logs and any new `*.cases/cc-<seed>.txt` files, including their `# shrinks to` descriptions. Copy the case files into the same paths in the checkout, then run the failing property with `PROPTEST_CASES=0` to replay saved cases without generating random cases.

## Heavy tests run on GitHub Actions

The [heavy tests workflow](../.github/workflows/heavy-tests.yml) runs one package's tests on GitHub-hosted Ubuntu and macOS runners, once or many times. Use it for long property runs, simulation sweeps and checks for flaky tests, rather than a local machine. Start it from `main` with [gh](https://cli.github.com/) and name the branch, tag or commit to test in `ref`:

```sh
gh workflow run heavy-tests.yml --ref main -f ref=feat/my-branch -f crate=koidrive-sim -f test=engine_sync -f cases=4096
gh workflow run heavy-tests.yml --ref main -f ref=feat/my-branch -f crate=koidrive-driver -f filter=watcher -f repeat=20 -f os=macos
gh run list --workflow heavy-tests.yml --limit 1   # the run's ID, for gh run watch <id>
```

| Input | What it sets | Default |
|---|---|---|
| `ref` | The branch, tag or commit to test | The ref the run starts from |
| `crate` | The package, as for `cargo test -p` | Required |
| `test` | One integration test target, as for `cargo test --test` | Every target of the package |
| `filter` | A test name filter, as for `cargo test` | Every test |
| `cases` | `PROPTEST_CASES` | Each property's own count |
| `repeat` | How many times each OS runs the selection, 1 to 100 | 1 |
| `seed` | `PROPTEST_RNG_SEED` of the first run; run k uses seed + k - 1 | Run ID × 1000 |
| `features` | Cargo features, comma-separated, such as `koidrive-engine/serde` | None |
| `ignored` | Also runs the tests marked `#[ignore]` | Off |
| `os` | `both`, `ubuntu` or `macos` | `both` |

The workflow tests one commit: it resolves `ref` once, so both operating systems test the same code even if the branch moves. Each OS job builds the tests once and then runs them `repeat` times. Its summary has one row per run with the seed, the result and the passed, failed and ignored counts, then the failing tests with the number of runs each failed in, and a command that reproduces a run from its seed. The log of the job's `Run the tests` step ends with the same summary, so `gh run view <run-id> --log` shows it too. A run whose test binary crashes, or that runs no test, counts as not finished cleanly. The job fails unless every run passed, and stops after 340 minutes. Each run starts from the case files in the commit: the job moves the case files a run saves into the `heavy-tests-<OS>` artifact under `regressions/run-<k>/`, so a later run never replays them and a run's seed reproduces it on a clean checkout. The artifact also holds the summary and each run's log. To replay a saved case, copy its file to the same path and run the test with `PROPTEST_CASES=0`.

To compare a fix with the code before it, start two runs with the same `seed` and `repeat`: one with `ref` set to the commit before the fix and one with the fix. While the properties' strategies are the same, run k of each tests the same cases.

## The mutation set

`scripts/engine-mutations.sh` lists mutations of the engine's commit and effects code that the tests must catch, each a perl substitution in one file. `scripts/mutations.sh` checks every selector, then runs an unmodified baseline before applying mutations one at a time. Each mutation runs the commit tests (`cargo test -p koidrive-engine --test commit`), the interleaving property (`cargo test -p koidrive-sim --test engine_sync`), both, or the tests of several devices (`cargo test -p koidrive-sim --test devices`). Each selected suite runs once, with the same fixed seed and checked-in case files as the baseline. The default property case count is 4096. The script restores the source and fixtures after each mutation and prints failure logs and generated cc cases before cleanup. A mutation fails the run when:

- no test catches it (`SURVIVED`),
- its pattern no longer matches the source (`STALE`), or
- the mutated code does not compile (`BROKEN`).

When the code a mutation targets changes, update the mutation. When the code is removed, remove the mutation too.

The battery runs the set with `--mutations`, spread over up to as many jobs as there are shards. The script edits files and restores them with git, so it refuses a checkout with uncommitted changes. To run it locally:

```sh
scripts/mutations.sh               # every mutation
scripts/mutations.sh --shard 0/4   # every fourth mutation, starting with the first
```

`MUTATION_CASES` sets the property case count. `MUTATION_SEED` sets one unsigned 64-bit seed for the baseline and every mutation, defaulting to `0`. The hosted mutation jobs use seed `0` too; shard numbers do not change it.
