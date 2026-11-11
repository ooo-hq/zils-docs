# Train from the Zils CLI

Install `@zils/cli` from npm using the
[developer-tools setup](developer-tools.md#install-from-npm). The CLI
defaults to the z3-mini founding baseline through its immutable d3-mini profile. Optional `--pool d3-lite`,
`--base-channel latest`, or `--model EXACT_PROFILE_ID` selects a qualified profile
advertised by the service. Service pool keys remain d3-lite, d3-nano, d3-mini, d3-flash and d3;
catalog membership alone does not mean a pool is available. Customer training runs on z3-mini.
Training execution remains in the hosted platform;
no GPU or model installation is needed on your laptop.

The public model line is **z3**. Existing API IDs, pool keys, downloaded artifacts
and pinned metadata keep their original `d3` identities. Pass the exact values
returned by discovery, including in `--pool` and `--model`; public z3 names are
not new API aliases. The founding mini baseline uses unchanged upstream weights.

## Sign in

```sh
zils login
```

Your browser opens Zils account sign-in and asks you to approve the CLI. Sign in
with Google or an email link; anyone can sign up. Keep the terminal open and open email links on the same
computer. The fixed local callback uses port **43187**; a remote/headless shell is
not supported by this flow. Sign-in expires after ten minutes.

The account session is saved privately to `~/.zils/config.account.json`, separate
from the inference key in `~/.zils/config.json`. Files use mode `0600` on POSIX;
on Windows, protect the directory with your account's filesystem permissions.
`ZILS_CONFIG_PATH` changes the key filename and derives the adjacent account file.
Tokens refresh under a process lock. An ambiguous refresh requires a fresh login.
Session writes are synchronized before refresh; a failed local state write stops
the exchange. POSIX filesystems must support directory synchronization. Windows
uses a write-through replacement; native Windows and power-loss testing remain
release checks.

For another deployment, set `ZILS_TRAINING_URL` **before signing in**. The default
is `https://training.zils.ai`. Changing that variable cannot send an existing
account token to a different service. `ZILS_BASE_URL` configures inference only.

Browser login does not issue an inference key. Use `zils login --api-key` to
privately enter an existing key, or `zils login --api-key -` to read from stdin.
`zils logout` removes both local credential types, retaining recovery receipts.
It does not revoke remote sessions/keys, delete jobs, or unset environment keys.

## Prepare splits from a spreadsheet or export

`zils train prepare` turns one file of past examples into the three splits. It
reads CSV, TSV, a JSON array of objects, or JSON Lines; export Excel sheets as
CSV first. It runs locally: no login, nothing sent.

```sh
zils train prepare tickets.csv --decide team --read message --read channel --group customer_id
```

- `--decide` is the column holding the right answer. It needs 2–255 different
  answers, and each answer needs examples from at least 3 separate cases.
- `--read` names a column the model reads; repeat it. Without it, every other
  column is read except ID-like columns (`id`, `*_id`, `uuid`, `key`) and columns
  that give the answer away. A column gives it away when its value fixes the
  answer in at least 95% of rows, like the agent who handled a ticket; the
  output lists these under `leaks`, and names them even when `--read` includes
  them. Leave out anything only known after the decision, such as a resolution
  time: `prepare` cannot tell those apart, so check what it reads.
- `--group` names the case each row belongs to (a customer, a thread), so
  related rows stay in one split. Without it, `prepare` uses a column named like
  a case (`conversation_id`, `thread_id`, `ticket_id`, `customer_id`, `case_id`
  and similar) when every row has a value and values repeat, and prints which
  column it used. If there is none, each row is its own case.
- `--name` and `--question` set the training name and the decision in words;
  `--out` sets the folder (default `zils-training/<name>`). Existing files are
  never overwritten.

`prepare` also reads decision logs written by `record` (see [fit](fit.md)): a
log file, or a folder with one log per episode. `--decide` picks the logged
question when there are several, and `--questions` reads its wording and options
from the file `zils fit scan` writes. Each episode stays in one split, the logged
state is kept as JSON, and repeats of an earlier situation are left out and
counted. `zils fit train` does this and submits in one step.

The rules match the zils.ai training page, so the same file gives the same
splits in both: one choice question per row, about 70/15/15 by rows, every
answer in all three splits, and identical rows refused. The command prints the
counts, the answers per split, the most training can cost, and the matching
`zils train submit` command. `--json` writes the same as JSON.

## Submit three reviewed splits

From the repository root, this synthetic example demonstrates the input format:

```sh
zils train submit --name ticket-routing \
  --train examples/training/train.jsonl \
  --calibration examples/training/calibration.jsonl \
  --test examples/training/test.jsonl \
  --min-accuracy 0.8 --min-brier-improvement 0.01 \
  --allow-training-data-export --json
```

This command creates a real job when connected to an enabled service. Run it only
when you intend to submit training. These tiny examples establish syntax, not
model quality; local tests do not spend credits or train on a live GPU.
The export flag explicitly permits training data to be copied to the workers that train the job.
Both quality thresholds are required; acceptance may produce no qualifying model.
Before creation, the CLI prints the active training account, service, files,
selected immutable model, thresholds and export consent to stderr. Submission uses that account's training
credit: $0.20 per million training tokens with a $2 minimum per run
([pricing](/getting-started/pricing)). JSON results remain on stdout.

Choose who trains the job with `--tier`:

- `--tier private` (the default when `--tier` is left out): paid, trained only
  on Zils workers.
- `--tier open`: free, trained by Zils network miners. They receive the
  training split and must delete it within 7 days of the job finishing; Zils
  cannot verify that they do. It also needs `--allow-open-tier-training`, your
  permission to send the training split to them. If the service does not offer
  the open tier yet, the CLI cancels the job before anything is uploaded or
  charged instead of training it as private.
  An account can start 3 open jobs in any 24 hours, each up to 5,000 examples
  and 5,000,000 training tokens, and the open tier as a whole has a daily limit; past either,
  train the job privately.
  An open-tier model is served by Zils and used through the API; it cannot be
  downloaded.

Add `--max-cost 5` to refuse a private job, before anything is sent, when it could
cost more than $5. Open jobs are free, so the limit does not apply to them. The service bills each train-split prompt token once at
$0.20 per million, never below $2. The CLI cannot count tokens without the
model's tokenizer, so it prices every train case at the 8,192-token cap: the
ceiling is `max($2, train cases × 8,192 × $0.20 / 1M)`, and the real charge is
usually far lower.

Each UTF-8 JSONL case requires `id`, `group_id`, `family`, `state`, `question`, and
`label`. Labels are strings: `"false"`/`"true"` for `noul`, a criterion key for
`choice`, or a zero-based index string for `score`. Questions support at most
255 outcomes. The server enforces the pinned model limits (z3-mini allows 8,192 input tokens); the CLI never truncates data.

IDs must be globally unique. Related source groups and identical state/question
pairs must stay in one split. Calibration and test families must match and occur
in training. Limits are 128 MiB per split and 128 KiB per case. Image cases,
invalid JSON, duplicate keys, and non-finite numbers are rejected before creating
a job. Private snapshots ensure uploaded bytes match the validated file hashes.

Selection is checked against fresh discovery before one create request. When
combined, pool, channel and exact profile must agree. The exact profile is frozen
in the local receipt and checked on creation, upload and resume; channel changes
do not change an existing job. Without pool discovery, the mini stable default
continues to work.

## Follow and recover a run

Copy the returned job UUID into `JOB_ID`:

```sh
zils train list --json
zils train status JOB_ID
zils train status JOB_ID --watch
```

Watch polls every five seconds until training completes or fails. Ctrl+C stops
watching without cancelling the job. An accepted result may still be activating;
a model ID appears only after API readiness is confirmed. A completed run can
also have `no_qualifying_model`, with no downloadable model.

If uploads stop, resume the **same** job with the unchanged source files:

```sh
zils train resume JOB_ID \
  --train examples/training/train.jsonl \
  --calibration examples/training/calibration.jsonl \
  --test examples/training/test.jsonl --json
```

Receipts under the private configuration directory's `training/` folder bind the
job to its account, service and exact input hashes. Resume requires that receipt;
it skips confirmed uploads and refreshes expired storage grants. It never creates
a replacement job. Successful submission removes owned dataset snapshots but
keeps the small receipt. Interrupted submissions retain snapshots privately.

If the create response is lost or fails, the CLI preserves a private `pending-*.json`
receipt without guessing a job ID. Run `zils train list` and inspect the website
before submitting again. A job discovered this way cannot automatically inherit
an unknown receipt; inspect or cancel that run explicitly. No mutation is retried
automatically. Private pending snapshots remain until you resolve the attempt.

## Download or cancel

```sh
zils train download JOB_ID --out ./accepted-model --json
zils train cancel JOB_ID
# Explicit confirmation for scripts:
zils train cancel JOB_ID --yes --json
```

Downloads require an accepted z3 result from a private job. Models trained on the open tier are served by Zils and used through the API; they cannot be downloaded. The CLI verifies provider/job/file
paths, release identity, model metadata and the backend-compatible checkpoint
SHA-256 before publishing four files to a **new** directory. Existing paths are
never overwritten. The filesystem must support hard links within the destination's
parent. Transfers are bounded to 512 MiB of checkpoint data plus a 1 MiB release
record. Files are saved privately. Verification does not execute model code.

Cancellation asks for confirmation in a terminal; scripts require `--yes`.
Already running workers may finish, and cancellation does not promise a refund
or undo costs already incurred. Use status to confirm the recorded outcome.

All commands accept `--json` and `--timeout SECONDS` (default 30). Download/upload
transfers also have a 120-second per-file ceiling. Results go to stdout; progress
and errors go to stderr. Exit codes are 0 for a completed CLI operation, 1 for a
service/transfer failure, 2 for invalid input/configuration, and 130 for Ctrl+C.
A completed CLI operation does not imply that training passed its quality targets.
