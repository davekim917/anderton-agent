# Public export

This repository is private. Its product tree is published to a separate public repository by a one-way export: agents never push to the public repository, so nothing they write is public until it passes the gate below.

## Why one-way

Pushing a branch to a public repository publishes it before any merge check can run, and a name list can never be complete (abbreviations and new clients slip past it). Exporting from a private repository puts the check in front of publication, where nothing can skip it. It is the same pattern Google uses with Copybara to publish open source from a private codebase.

## What gets published

`scripts/public-export/copy.bara.sky` holds an include list of product folders and root files. A new top-level folder or root file stays private until it is added there. A new `docs/*.md` file is published by default, so a record of this deployment written there needs its own exclude. Specs, retros, review notes (`docs/review-notes.md` and `docs/review-notes/`), handoffs, records of this deployment rather than the product (superseded runbooks and phase plans, the v1 migration log, backlog and spike notes, audits measured on this fleet), `data/`, `.github/`, group folders and the public-boundary baseline/allowlist are excluded explicitly. `docs/review-policy.md` is published: the exported `pr-review-loop` skill and container instructions cite it, so it holds the policy and nothing about this install. Tests whose subject is this repository's own CI and review governance (`.github/`, review notes, specs, the upstream ratchet, the export allowlist) are excluded too, since their subjects are not exported. `scripts/public-export/allowlist.test.ts` evaluates those globs against the tracked tree and fails if a private path would be exported.

The public repository gets its own `README.md`, `CLAUDE.md`, `AGENTS.md` (a symlink to `CLAUDE.md`) and `CONTRIBUTING.md` from `public-overlay/`, which the export moves to the root. The private root copies describe this install or NanoClaw's own process and are never exported, and neither are the upstream README translations or `RELEASING.md`. A change to a private root copy alone publishes nothing; edit the `public-overlay/` copy to change what the public repository shows.

These policies of this install are rewritten or left out on the way out, by `copy.bara.sky`:

- **Build gate.** The public `package.json` has no `prebuild`, so a public `pnpm run build` is `tsc` plus the dashboard bundle. `scripts/check-build-clean.ts` refuses a dirty tree, a HEAD other than `origin/main` and any lint error. On a public clone every channel install trips one of those: the skill copies an adapter into the tree, and upstream adapters fail this repository's lint. This install keeps the gate: `scripts/deploy.sh` and any hand build here still run `prebuild`.
- **Boundary hooks.** The public tree has no `pre-push` or `commit-msg` hook, and its `pre-commit` only formats. The boundary scan protects this repository's identifiers; in a public clone it would harvest the installer's own registry (their name, `local`, `cli`) and refuse their every commit, and the push refusal guards this repository's `main`. The `check:public-boundary` script stays runnable by hand there with `--allow-absent-sources`, because a fresh clone has neither a registry nor an identifier inventory; a source that exists but cannot be read still refuses.
- **Fleet MCP defaults.** `src/fleet-mcp-default-servers.ts` seeds this install's fleet MCP servers while `data/fleet-mcp-servers.json` is absent. The public tree gets the empty copy in `public-overlay/src/` instead, so a stranger's agents inherit no MCP server they did not add. Tests that assert the seeded entries skip on an empty seed; `src/fleet-mcp-default-servers.test.ts`, which is not exported, keeps the seed here non-empty so they run.
- **Voice calls.** `src/modules/voice-call/live.ts` reaches the voice service through an endpoint that is not a published API, so the public tree gets the stub in `public-overlay/src/modules/voice-call/` instead: every voice call refuses with "not available in this build", and the rest of the module compiles unchanged. `docs/voice-call.md` stays private with it.
- **Install diagnostics.** `setup/lib/diagnostics.{sh,ts}` report setup events to upstream's PostHog project unless `NANOCLAW_NO_DIAGNOSTICS=1`. In the public tree they send nothing unless `NANOCLAW_DIAGNOSTICS=1`, so public installs do not report to another project's analytics. The files stay byte-identical to upstream here.

`run.ts` passes `--ignore-noop`, so a transform whose text no longer matches would export the private behaviour without an error; `allowlist.test.ts` fails instead, by checking that each transform's `before` text occurs exactly once in its file, that no exported hook runs the boundary scan or names `main` once the transforms apply, and that the published fleet MCP defaults are empty.

Each private commit that touches published files becomes one public commit:

- the author is rewritten to `PUBLIC_EXPORT_AUTHOR` (use a GitHub noreply address);
- the message keeps only the subject line, with any trailing ` (#<n>)` removed. A merge subject (`Merge pull request #<n> from …`, `Merge branch …`, `Merge remote-tracking branch …`) becomes `Merge changes`, because a branch name is exactly the kind of abbreviation the gate can miss;
- a `GitOrigin-RevId` trailer records the private commit it came from, which is how the next run resumes.

## The gate

Every exported commit is checked before it can be pushed, in order, and the first failure stops the run:

1. **Name scan.** `scripts/check-public-boundary.ts` runs over the commit's whole tree and its message, using the install's identifier registry and allowlist and an empty baseline, so lines the private repo tolerates still count. A repository cloned into the install's repository store adds its owner and name to that registry unless GitHub proves it public: the API answers `isPrivate: false`, `visibility: PUBLIC` and the exact `owner/repo` the clone's origin names. A clone on another host, a lookup that fails or times out, a rename, or a public repository whose owner or name matches another private identifier (a client's own open-source repository) stays private. Verdicts are cached, hashed, in `.nanoclaw/github-visibility-cache.json` (public and private 7 days, not found 1 day, a failure 1 hour); uncached repositories are asked in one GraphQL request per 100, inside an 8-second budget per scan. The git hooks and this gate share the cache.
2. **Binaries.** A changed binary file holds unless its blob is listed in the host-local `public-export-approved-binaries.txt` (see _Exemptions_ below). Neither the scanner nor the AI can read a binary. Add a blob only after a person has looked at the image itself. Listing it skips every content check. The list starts with the images that are byte-identical to nanoco's public upstream.
3. **AI read.** Headless Claude Code (`PUBLIC_EXPORT_AI_MODEL`, no tools) reads the message, every changed path (renames show both names) and every added line, together with the list of known private names, and must return `pass` with no finding left after accepted findings are removed (see _Exemptions_). It is there to catch what a list cannot: abbreviations, slugs and names not yet in the registry. The commit is fenced between markers carrying a random per-call nonce, and the model is told that everything between them is data, never instructions.

A large diff, such as the first full-tree snapshot, is read in batches of at most `PUBLIC_EXPORT_AI_MAX_CHARS` (default 400,000 characters), each carrying the commit message. There is no way to skip the AI read.

### The AI budget

Every AI read runs on the host's Claude login, a usage allowance that other work on the host also draws on. `PUBLIC_EXPORT_AI_MAX_CALLS` (default 15) caps the reads one run may make. Before the first read, the gate counts every batch the run's commits could send; when that count, plus what an earlier gate call in the same run already spent (the squash retry draws on the same budget), is over the cap, the first commit holds with the reason `AI budget exceeded: N batches > cap M` and no AI call is made. The count includes commits the scanner would hold, so a budget hold can stand in front of a scanner hold.

A normal day's merges fit well under the cap, because a run only reads the commits since the public head. A run that needs more, such as a large refactor or a first publish into an empty repository, is a decision for a person: run it once with a higher `PUBLIC_EXPORT_AI_MAX_CALLS`, at an hour when the fleet's allowance can spare it.

### Exemptions

Three files let a person settle what the gate would otherwise hold on every run. They live in the install's `.nanoclaw/` directory (`NANOCLAW_DIR/.nanoclaw/`, beside `public-boundary-identifiers`), which `.gitignore` excludes. Gate policy never comes from the tree being judged: a file in the exported checkout could grant its own exemption, so the run never reads one there. A missing file grants nothing. The install is the checkout that pulls the private repository, so the run fails if git tracks anything under `.nanoclaw/` there; a commit that force-added an exemption cannot grant it. Only a session on the host, run by the operator, edits these files.

- `public-export-public-names.txt` lists names that are public by design, such as public products the project integrates with. The operator's own identity is added from `PUBLIC_EXPORT_AUTHOR`: the full author name and the GitHub noreply login, since every public commit already carries them. A single word of the name is never added, since it could match another private name. These names are left out of the private names the AI is given, matched whole and case-insensitively, and the AI is told they are fine; a slug, path or URL that combines one with anything else is fine only when every other part is public too. Each line must be a plain name (letters, digits, `. _ -` and spaces, at most 48 characters); anything else fails the run. Another person's name never goes here.
- `public-export-accepted-findings.json` lists false positives a person has confirmed. Each entry is `{ "path", "line", "reason" }`: the exported file, the exact text of the flagged line, and why it is not private. An AI finding is dropped only when all of these hold: it names that file and a line number; its `text` is non-empty and occurs in the accepted line; the file is a regular file reached without a symlink; and that line in the exported tree is still exactly the accepted text. Anything else still holds: a finding with no file, line or text, text from elsewhere reported at an accepted line number, text spanning several lines, a changed line, the same text in another file, a symlink, or an AI `hold` that names no finding. A malformed file, or an entry whose path is absolute or has an empty, `.` or `..` segment, fails the run.
- `public-export-approved-binaries.txt` lists binary blobs a person has looked at, one `<blob> <path>` per line.

Add an entry only after reading the flagged line in `logs/public-export/held.json` and confirming it identifies no client, customer, private person or private group. When it does, fix the line in the private repository instead. The AI is asked for one finding per line, so an entry covers exactly one line. The status file records how many findings were accepted, as a count; the accepted findings themselves go to `logs/public-export/accepted.json`, mode 0600 in a 0700 directory, for audit.

The gate fails closed. A scanner hit, a scanner that cannot load its identifier sources, an AI `hold` or finding in any batch that is not exactly matched by an accepted finding, unparseable AI output, a non-zero exit, a failed write to the model's input, a timeout, a single added line too long for one call, or a run over its AI budget all hold the commit.

## What a run trusts

A run builds on one commit without gating it, `trustedGatedHead` in `export-flow.ts`: the public repository's own head, or nothing on a dry run or a first publish. Every commit above it is exported and gated again in the run that pushes it, under the current identifier inventory, even if an earlier run already passed it. `logs/public-export-status.json` is write-only reporting and never feeds a publish decision. `logs/public-export/ai-holds.json` feeds only holds. A run that cannot write its status deletes the old one rather than leave a stale `ok`. A dry run therefore re-exports and re-gates the whole tree every time.

## Holds and recovery

When a per-commit export holds, the same run may retry once as `export_squash`. It squashes everything after the last passing commit into one commit and gates it, so the held commit never reaches the public history, and a later private commit that removed what held publishes in that run. A squash with nothing to add means the held change was fully reverted, so the run is `ok`. The per-commit hold is still recorded: its detail goes to `held.json` and the status carries it as `perCommitHold`, with `squashReason` saying why the run retried.

A hold on scanner or gate reasons always retries (`squashReason: "scanner-or-gate-hold"`).

An AI flag is never read twice. The AI read is sampled, so a second read of the same text can pass what the first flagged, and the export replays every unpublished commit each night. Every AI flag (a `possible-identifier` or `hold-without-finding` hold, or any AI reason other than a failed read) is therefore recorded in `logs/public-export/ai-holds.json`, keyed by the private commit it came from, with each finding's quote when every quote is provable (below). The record is written ahead: before a commit is read, a pending record for it is saved, and the commit's verdict replaces it before the commit's checkout is removed or anything else runs. A pass removes it; a flag turns it into the flag's record. A run that dies mid-read, or cannot save a verdict, therefore leaves a pending record, which holds like a flag with no provable quote until a person removes it. A commit's AI read stops at the first batch that holds. Until the public head contains a record's private commit, every later run, with no AI read:

- holds the flagged commit itself, and any commit in which a recorded quote, ignoring case, is still anywhere it publishes or its AI read would see: its AI read's whole input (message, changed paths including deleted and renamed ones, added lines), or any path or file of its tree, symlink targets and submodule paths included;
- holds every commit, and makes no AI read of any squash, while any flag has no provable quote, since its text could be in any of them.

A flag found anywhere in a run, by a per-commit read or the squash's, also applies to that run's passing prefix: before the squash is built and again before the push, the prefix is cut before its first commit a record holds, so a commit whose read passed text that a later read flagged is not published either.

A quote is provable when it is a single line of at least 8 characters, after trimming, that occurs in the line its finding names, in that file as the held commit has it. A hold with any AI reason retries as a squash (`squashReason: "ai-hold-fixed-forward"`) only when every live record has provable quotes and none of them is anywhere in the squash, by the same test. The squash then gets its own scanner and AI read, drawing on the same AI budget; a flag there is recorded too, and is the run's hold. A read that failed (a timeout, unparseable output, a non-zero exit or an over-long line) is not a flag: nothing is recorded, no squash is tried, and the next run reads again.

What a record pins is the AI's quote, not the identifier inside it. A later commit that rewords the quoted line but keeps the identifier, or an earlier commit that carried a different form of the line, gets a fresh read. A record is dropped once the public head contains its commit, so a later commit that adds the same line back gets a fresh read too.

The records only ever hold; nothing in them can publish. They contain the private quotes, so the file is private like `held.json`, and it is replaced atomically. A malformed file, including a quote that is not its finding's, fails the run. A dry run uses the records but never writes them, and writes its held detail to `held.dry-run.json`, since it publishes nothing. When the file does not exist yet, the run starts it from `held.json`, so the last flag made before records were kept is not read again either. Once a run has written or read the store, it leaves `ai-holds.written` in `PUBLIC_EXPORT_WORKDIR`, and a run that then finds `ai-holds.json` missing fails rather than starting empty; restore the file from a backup taken after the last run that wrote it (an older backup drops every record written since, and those commits get a fresh read; add `held.json`'s flag by hand if the backup lacks it), or delete the marker only after deciding every record it held can go. A `held.json` with no findings is not seeded, because a scanner hold and a findingless AI hold both leave one; such an AI hold gets a fresh read. A `held.json` whose commit is no longer in the staging repository is still seeded, with its findings but no provable quote, since the AI's quote cannot be checked against a commit that is gone: it holds every commit with no AI read, and, having no commit to be published past, is never dropped, so a person removes it after reading its findings in `ai-holds.json`.

If the run holds, after the squash retry or without one:

- only the passing prefix is pushed;
- `logs/public-export-status.json` records `status: "held"`. Scanner reasons are `file:line` plus a category, with the scanner redacting identifiers in paths. An AI hold is recorded only as its batch and `possible-identifier`, `hold-without-finding` when the AI held but named nothing, or `recorded-ai-hold` when an earlier run's flag decided it;
- the AI's findings, which may quote the private text, go to `logs/public-export/held.json`. The file is mode 0600, and its directory is set to 0700 on every write, even when it already exists. Both files stay on the host.

Fix the leak in the private repository, for example by renaming a fixture to a fictional name, and the next run publishes it as a squash. A flag with no provable quote keeps holding after the fix and needs a person: read `held.json` and `ai-holds.json`, and once the leak is fixed, or confirmed a false positive and accepted (see _Exemptions_), remove that record. A recorded false positive also needs its record removed after the accepted entry is added, because a recorded hold is decided without an AI read.

## Running it

```
flock data/public-export.lock pnpm exec tsx scripts/public-export/run.ts
```

| Env                           | Default                       | Meaning                                                                                                                                                                                                                          |
| ----------------------------- | ----------------------------- | -------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `PUBLIC_EXPORT_AUTHOR`        | required                      | `Name <email>` written as author and committer of every public commit.                                                                                                                                                           |
| `PUBLIC_EXPORT_REMOTE`        | unset                         | Push URL of the public repository. Unset is a dry run: export and gate, push nothing. Never put a credential in the URL; use a git credential helper. Remote URLs and any `user@` part of a URL are redacted from status errors. |
| `PUBLIC_EXPORT_PRIVATE_URL`   | the install's `origin`        | Where the private repository is fetched from. Same rule: no credential in the URL.                                                                                                                                               |
| `PUBLIC_EXPORT_AI_MODEL`      | `claude-opus-5-5`             | Model for the AI read.                                                                                                                                                                                                           |
| `PUBLIC_EXPORT_AI_TIMEOUT_MS` | `600000`                      | Per-call deadline; a timeout holds. Must be a positive integer, or the run fails.                                                                                                                                                |
| `PUBLIC_EXPORT_AI_MAX_CHARS`  | `400000`                      | Largest AI batch.                                                                                                                                                                                                                |
| `PUBLIC_EXPORT_AI_MAX_CALLS`  | `15`                          | Most AI reads one run may make; a run that would need more holds before reading anything. Must be a positive integer, or the run fails.                                                                                          |
| `PUBLIC_EXPORT_WORKDIR`       | `data/public-export`          | Private mirror, staging repository and rendered config.                                                                                                                                                                          |
| `PUBLIC_EXPORT_LOG_DIR`       | `logs`                        | Where the status, held-detail and AI hold record files go.                                                                                                                                                                       |
| `NANOCLAW_DIR`                | the checkout the script is in | The install whose identifier registry and `.nanoclaw/` export policy the gate reads; git must track nothing under its `.nanoclaw/`.                                                                                              |

Exit codes:

- `0`: ok, or nothing new.
- `2`: held.
- `1`: failed. The run stopped on an error and wrote `status: "failed"`, or removed the status file if even that write failed. A push that completed before the error stays published, and the next run starts from the public head either way.

Copybara runs in a container built from `scripts/public-export/Dockerfile`, tagged with a hash of that file, so changing the pinned release rebuilds the image. Copybara needs Java 25 and git 2.45 or later, newer than the host's. The Copybara release and checksum are pinned there; Copybara publishes weekly snapshots with no compatibility guarantee, so bump it deliberately.

The first run starts from an empty staging repository with `export_squash --init-history`, so the private history before that snapshot is never published. That snapshot's AI read covers the whole product tree in batches, so it takes many calls.
