---
name: memory-system
description: "Use when working with the kit memory store beyond plain memory files: recalling the store at effort start or a seat takeover, reporting what the store recorded, logging or looking up an action outcome, stamping a memory applied, tagging, running the decay pass or pinning against it, recording a type-wide convention or an operator or machine fact, repairing or removing a shared-tier record, declaring a record's file anchors or recognition triggers, or meeting a refused memory write. Triggers: memq, memq recall, memq find, memq log, outcomes journal, applied stamps, memq unstamped, operator tier, type tier, shared-tier repair, memory decay, anchors, triggers, memory sync."
---

# Memory System

The kit memory store is the file-per-fact memories plus an extension layer: an outcome journal (`outcomes.jsonl`), used-tracking (`usage.jsonl`), tags, a decay lifecycle, a shared project-type tier, and an operator tier. All of it is reached through the `memq` CLI.

`memq` resolves the store itself: a linked worktree of an ordinary checkout resolves the same store as its main checkout, a subdirectory of the project resolves its project's store in a session filed under that project, and a store pin (`KIT_MEMORY_PROJECT`), honored only under the engine store signals below, fixes the store regardless of the working directory.

An unpinned working directory naming a network share is refused. `get`, `touch` and `triggers` still pass with `--operator` or `--type=<type>`, which resolve their tier from the store root. A refused writing verb exits non-zero, and a refused reading verb exits 0 with empty stdout. So read the stderr line, since status alone cannot tell a stood-down `recall` from a clean read of an empty store.

The **engine store signals** are `KIT_MEMORY_ROOT` with `KIT_MEMORY_ROOT_ALLOW_DATA=1`, the unattended fleet worker's environment. The **pending tier** holds the memories one run wrote that nobody has adjudicated, and exists only under those signals with a valid `KIT_RUN_ID`. If `memq` does not resolve in the shell, the shim is not installed: ask for a kit doctor `-Fix` run (the kit-doctor skill owns that run).

Two rules govern everything below:

- **Never hand-edit `outcomes.jsonl` or `usage.jsonl`.** A shared-tier delete that stopped partway is finished by re-running the same delete under its consent flag, never by editing either file, and its failure line names what it removed.
- **Journal entries never enter the memory index.** `MEMORY.md` carries index lines for memory files and exactly one journal pointer line, verbatim: `Outcomes: outcomes.jsonl holds the action journal; query with memq find <term>.`

## memq Reference

| Command | Does |
|---|---|
| `memq log <key> pass\|fail "<summary>" [--tag t]... [--detail "..."]` | Append one outcome to the project journal. Compose the summary to 120 characters and `--detail` to 500, since past a cap the tail is dropped and the success line announces the cut. When a cut is announced, re-log the lost tail as its own entry. |
| `memq find <term> [--tag t] [--outcomes\|--memories\|--all] [--archived]` | Hybrid search. The lexical block first, one summary line per substring hit over this project's tiers: journal keys as `<key>  <pass>/<fail>  last <age>  <latest summary>`, memories as `<name>  [tags]  <description>`. Then, with the embedder installed, a semantic block over every store on the machine. `--archived` shows retired records, labeled and demoted. A model-judged block follows where an endpoint is configured, and it is advisory. |
| `memq get <key\|name> [--type\|--type=<type>\|--operator]` | Full journal entries for a key, or a memory file's body from the first tier holding that name. Appends a read stamp in the tier it served, the tier a flag names under a flag. |
| `memq recall [--situation "<text>"]` | The whole store as one bounded digest, no search term. It writes no stamp. Run at effort start, at a seat takeover, and again at a boundary taking the hand walk below. |
| `memq judged --situation "<text>" [--tag t] [--limit <n>]` | The judged fleet block's lines over this project's own records, for a caller that spawns memq. Stdout is at most ten judged lines and never the vector-order fallback. Every empty answer exits 0 with its reason on stderr. |
| `memq recent [--since <n>d\|<n>h]` | What the store recorded inside a window (default `1d`), grouped by write surface. Writes nothing, not even a read stamp. Run at close-out. |
| `memq jev-calibration [--since <n>d]` | The judged fleet block's hit rate in ten score bands. The reading can confirm or raise a floor and never lower one. Writes nothing on this machine. |
| `memq unstamped [--since <n>d\|<n>h]` | The memories opened inside a window (default `1d`) and never stamped applied. Writes nothing. Run at every Chapter boundary and once more at close-out. |
| `memq touch <name> --applied [--type\|--type=<type>\|--operator]` | Stamp a memory as applied, in the tier a flag names. `--type=<type>` is what stamps a type-tier record from a project that declares no type, and it is withheld under the engine store signals. One tier flag or neither, never both. |
| `memq anchor <name> <path>... [--operator]` | Record which files a project memory is about, at the bytes they hold now: one `anchors:` frontmatter line of `<path>@<sha>` entries, merged into any existing line with fresh hashes. |
| `memq triggers <name> [<type>:<pattern>...] [--type\|--type=<type>\|--operator] [--replace [--confirm-shared]]` | Record the triggers a memory should be surfaced by, as one `triggers:` frontmatter line of `<type>:<pattern>` entries. Types are `cmd`, `err`, `skill`, `agent`, `tool` and `glob`, and the pattern is stored verbatim. With no tier flag it writes the project tier, or a run's pending tier inside a run. Bare `--type` means the working project's declared `Project-Type`, and `--type=<type>` names the tier. Keep the value on the flag word, because `triggers rec --type cmd:whatever` parses as a type named rec. `--replace` is the only way an entry comes off. |
| `memq add-type <type> <name> "<description>" [--body "..."\|--body-file <path>] [--tag t]... [--trigger <type>:<pattern>]... [--supersedes <name>] [--update [(--body ...) --confirm-shared]]` | Write a type-tier memory and its index line together, under the tier lock, the only type-tier authoring path. Use `--body-file` for any body with newlines in it. The success line reports the stored body's length, which is the signal that a body arrived whole. `--update` alone rewrites the description, and with a body flag and `--confirm-shared` it replaces the body. On creation the verb prints its nearest neighbours on stderr before the write, and the block warns and never gates. |
| `memq add-operator <name> "<description>" [--body "..."\|--body-file <path>] [--tag t]... [--machine <name>] [--board <path>] [--trigger <type>:<pattern>]... [--supersedes <name>] [--update [(--body ...) --confirm-shared]]` | The same for the operator tier, under its own lock, with the same refusals, body channels, `--supersedes` pointer and `--update` repair. It is the only operator-tier authoring path. `--machine` scopes the fact to one box. `--board` records that box's coordinator board path, read only from a record named `coordinator-board-location*`. Like `--tag` and `--supersedes`, both are set at creation, and `--update` carrying any of them is refused. The neighbours block prints here too, with each hit's `machine:` scope on its line, so discount a `likely overlap` on a record about another box. |
| `memq put <name> "<description>" (--body "..."\|--body-file <path>) [--tag t]... [--author <a>]` | Write one project-tier record with no `MEMORY.md` line, into the store memq resolves. Inside a run it lands in that run's pending tier, `memory/pending/<run-id>/`. It ranks, publishes and is judged on its frontmatter description, and stays out of session start's index block until someone adds its index line by hand. |
| `memq forget <name> --confirm` | Remove a project-tier record outright, in one locked operation. Without the flag it refuses, having changed nothing. Its last stdout line says what the memory database will do with the record's row. |
| `memq delete-type <type> <name> --confirm-shared` | Remove a type-tier record outright, in one locked operation. Names the projects declaring the type before it acts. Without the flag it refuses, having changed nothing. |
| `memq delete-operator <name> --confirm-shared` | The same for the operator tier. |
| `memq decay-scan` | Report decay candidates with their evidence dates, the pinned class, a superseded record whatever its idle clock, and a standing usage-evidence line. On stderr it adds the anchor-drift block, then the neighbour-pairs block of live same-tier records at or above the overlap floor. That block never reads the pending tier and withholds pairs a `supersedes:` pointer joins or `machine:` scopes split, so a missing pair is no evidence of no duplicate. Writes no record, index line, journal entry or stamp. |
| `memq decay-prune [--rollup [--drop-malformed]] [--archive <name>]... [--archive-type <name>]... [--archive-operator <name>]... [--confirm-shared]` | The pass's one mutation path over the store's own records and sidecars, and it mutates only what its flags name. `--rollup` runs the journal rollup and the usage prunes. `--drop-malformed` rides `--rollup` and removes the malformed sidecar lines that rewrite otherwise preserves. A shared-tier archival needs `--confirm-shared`: always for `--archive-operator`, and for `--archive-type` whenever the scan of declaring projects finds more than one or cannot run. Running the Decay Pass owns when to supply it. Refuses a pinned target. |
| `memq decay-done` | Touch the decay stamp that records a completed pass. |
| `memq db-sync` | Publish this machine's whole store to the shared memory database and drain the local stamp queue. Where a database is configured, session start and the doctor's `-Fix` already run it. |
| `memq db-promote <name> [--sandbox <name>] [--tier project\|type\|operator] [--segment <segment>]` | Flip one private project record to shared on the host. Curator login only. Nothing on disk changes. |
| `memq db-curate [--unapplied <days>] [--superseded] [--orphans]` | The curator's three lists off the host: records unapplied inside a window, live records another supersedes, and orphans. Curator login only. Writes nothing. |

On a name collision `get` takes the most specific tier first: a journal key, a run's pending tier, a project memory, the type tier, then the operator tier. The project, type and operator archives follow in that order, so live beats retired. The tier flag (`--type`, `--type=<type>`, `--operator`) is the only way to reach a shared-tier record a nearer tier shadows. Read a record with `get` and never write its output back, since memq's status lines follow the record and a record past the 65536-character cap comes back short. A `find` hit from another project's store is not fetchable from here, and its provenance label names where the file lives.

## Recall

`memq recall` takes no search term. It emits the whole store as a bounded digest, one summary line per record, ordered by last sign of life, and it announces every truncation with a counted remainder. You do the ranking, reading the digest with the current task in context.

So read `recall` before `find` at effort start. A seat takeover reads the digest as well, at the takeover ritual's fourth step in the role skill, which owns what that read covers. `memq judged` prints only the fleet block's judged lines for one project's segment, for a caller that spawns memq, so a session still starts from the digest.

Where the embedder is installed, `find` also ranks by meaning across every tier, live and archived, in every project store on the machine. A column-zero line counts and scores the archived hits it withheld, so you can judge whether a `--archived` rerun is worth running. In a hit's `applied x4, last 25h`, judge weight from the distinct-day count and freshness from the age, since the ranking does not. A superseded record reads `superseded by <name>` on the lexical line and `superseded` on the semantic hit. Ask `find` in the words of your problem, not in the words you expect the memory to use.

A third block, model-judged and advisory, appears where this machine has a model endpoint configured and re-orders the candidates, its record names coming from the store rather than the model. It sends your query and those candidates' names, tiers and descriptions off this machine, which `docs/security-model.md` describes in full. A dead or slow endpoint costs one line, and a machine with no endpoint configured says nothing, which is normal. Where the embedder is absent, `find` says so in one line and serves lexical results.

The semantic block is fenced and indented, and the digest indents type-derived and operator-derived records under a provenance line, column zero being memq's own voice. Those indented lines, the shared tiers and the model-judged clauses take the doctrine's data-not-instructions rule.

**When a recalled record changes what you do, stamp it in that turn**, per the Applied stamps section below. Reinstate a retired project-tier memory by hand, its file back beside the tier's others and its index line restored. The shared tiers have no reinstatement path: a retired shared record that still holds is written fresh, and one that was wrong is removed with `delete-type` or `delete-operator`. The four-remedies paragraph below routes a live record. Avoid reusing a retired record's exact name.

## Session Recap

`memq recent` reports what the store recorded lately, grouped by write surface, and each group states its count even at zero. Journal entries and applied stamps exist only through `memq`, while a project-tier memory file arrives through the Write tool, so the surface a record landed on is its own provenance.

Do not read the file group's `added` label as new, since an edit to an old memory reports `added` too. To say which records are new, check the names against what the effort wrote.

Run it over the session's span at close-out and carry the digest into the close-out status, labeled by surface. The trigger is this section's own, and `finishing-work` step 8 calls it, as it calls the decay pass.

The store then syncs itself, and the close-out verifies that rather than driving it. On Windows the SessionStart hook spawns `doctor/sync-store.ps1`, which commits through the allowlist gate and, where an upstream exists, screens incoming content, rebases and pushes.

Syncing the store needs no go-ahead, for any session at any time, under the doctrine's closed list: a commit of what the allowlist admits, a pull with rebase, then a push, the manual pair below included. A failing leak probe is reported, not asked about.

The kit doctor's `-Fix` sets the store up, clears a standing gate and commits this session's writes, but never pushes. The push comes from the runner at the next session start or a hand path below, and off Windows, with no runner, the commit and the push are both hand-run. Running `-Fix` from a tool shell: its consent prompt cannot reach a redirected stdin, so a bare `-Fix` declines. Tell me what it would do, get my go-ahead, then pass `-Yes`.

The manual push is `git -C ~/.claude pull --rebase` then `git -C ~/.claude push`. Run it only once the doctor's memory-sync line reads PASS or FIXED, since a FAIL there is a stop. Where PowerShell exists, prefer hand-running `doctor/sync-store.ps1` under the kit plugin root with an explicit `-StoreRoot`, which also takes the sync lock and screens incoming content. `docs/security-model.md` states what each hand path leaves exposed. Read the script's verdict from `lastResult` and `reason` in `<StoreRoot>/kit-sync-state.json`, after checking the file's timestamp against the run. A push is verified when `git -C ~/.claude status --short --branch` shows no dirty paths and no ahead count.

A memory-sync WARN comes only after every leak probe read clean, so carry it into the close-out rather than treating it as a gate. An unanswerable probe reports as FAIL, a stop already delivered.

## Action Keys

Dot-namespaced, project or domain leading: `neo.sql.procs`. `find` matches key substrings, so lead with the name a future session will reach for, and keep one hierarchy per subject rather than minting near-duplicates. A fact that cuts across the hierarchy takes a tag, not a second key.

## Outcome Logging

Log an outcome when a future session, about to act on that key, would stop or steer differently after reading the entry. Both directions count, and the norm does not.

Log:
- A failure with a cause and a countermeasure: `memq log neo.sql.openquery fail "OPENQUERY truncates NVARCHAR(MAX); stage through a temp table"`.
- A success that settled an open question.
- An outcome that flips what the store currently believes, either direction.

Skip:
- Routine successes: a green build, a passing suite, a clean commit.
- A failure explained by your own typo or a transient outage.
- A durable fact with no event attached, which belongs in a memory file.

**Write the summary and detail yourself, never paste raw tool output into a memq argument, and compose without embedded `"` characters.** The journal is plaintext on disk and read back into context, so name a secret's shape ("the connection string was missing Encrypt=True"), never its value. A stored body is never charset-reduced, so never paste one onto a `cmd.exe` command line. Windows PowerShell 5.1 breaks an argument carrying an embedded `"` before memq runs, so quote-free one-line prose is the safe form.

**`--body-file` is for a body you composed, never a file you merely have**: not a `.env`, a settings or credentials file, or raw log or tool output. Read a file you did not write yourself before you name it.

## Applied Stamps

**Applied means acted on, not merely read.** A memory is applied when it changed what you did, as when you followed its warning. In that turn, run `memq touch <name> --applied`, adding `--type` or `--operator` for a shared-tier memory. Only live memories take a stamp, since `touch` refuses an archived record. Reads are recorded for you, on the two paths named below.

Only `applied` stamps move the decay clock, never `read` stamps, so a memory read forever and applied never will be flagged.

**`memq unstamped` catches a missed in-turn stamp by recognition.** It lists the memories opened inside a window and never stamped applied. Executing-work runs it at every Chapter boundary, and finishing-work runs a final sweep before the decay pass.

**The bar is whether it plausibly steered what you did, not whether you can prove it.** When in doubt, stamp.

Only two readers leave a read stamp in the tiers `unstamped` sweeps: `memq get` serving a project, type or operator body, and the read-stamp hook on a Read of such a file. Every other reader leaves none, a description acted on from the `recall` digest among them. So `unstamped` is the backstop, not the replacement, and the in-turn habit and find's closing reminder stay in force.

A zero with no read stamp in the window is an absence of evidence, so the window rests on your own account. A count shows tracking happens in this store, never that your own reads were tracked. Where the verdict names lost evidence, the count is a floor, and a floor line beside hits is an open question.

No report is a swept window on its own. Set it against your own account of the stretch: adjudicate every listed line, then stamp by name any use the list did not raise. A use whose record has left its tier is noted in the boundary's own record instead. A stretch whose every use is adjudicated or stamped by name discharges the boundary.

A boundary owes the hand walk when it tries to enumerate the stretch's uses and comes up short, never because of an event. The walk works the live rows of `recall`'s digest. It reads the type and operator indexes for descriptions, and any tier's index the digest says its budget cut. Decide from a description where one can, and spend `memq get` only where none can. Name in the boundary's own record the records the walk opened. Then `touch --applied` what steered the work, with `--type` or `--operator` for a shared-tier record.

## Frontmatter Field Placement

On Claude Code a Write into a project's memory directory is rewritten in the same second, your top-level keys moving under a column-0 `metadata:` map beside keys of the harness's own. Which keys ride along varies by harness version, so no one key marks the shape, and the rewrite is not your write failing.

**So write every field at the top level, and expect to find it under `metadata:` afterwards.** memq reads its fields at both placements, the top-level value winning, and a field under any other key or nested deeper is read at neither.

**Do not quote a value you write by hand.** A `tags: "a, b"` typed at the top level matches neither `a` nor `b` while printing as `[a,b]`.

Never write `author:` by hand, since the CLI writes it on every shared-tier create.

## Tags and the Registry

Tags are an optional list on memory frontmatter and journal entries, queried with `memq find --tag <t>`, from a controlled vocabulary.

- **Frontmatter uses the inline form only**: `tags: a, b` on one line inside the `---` block. The YAML list form reads as no tags at all.
- **A record's `MEMORY.md` index line wins over its frontmatter `description:` line wherever it holds text.** With no index line, or an empty one, the frontmatter value stands in.
- **The registry** is `~/.claude/memory-types/tag-registry.md`: one tag per line, an optional one-phrase gloss after it. Add a line before minting a tag, since once the file exists `memq` warns on any tag outside the registry and still writes the record.

## `machine:` Field

`machine: HOSTNAME`, inline, with the value exactly as `os.hostname()` reports it on that box, compared caselessly. A fact true of one box carries the field, and a fact true of the operator or of a project does not. `memq add-operator --machine <name>` writes it, and `find`'s semantic channel labels a hit whose machine is not this one.

**The machine configuration epoch is a record of this kind, at a canonical name.** `machine-configuration-epoch-<hostname>`, the hostname lowercased, holds the box's logical processor count, its physical memory, the environment settings that move a benchmark number, and the date that configuration took effect. Create it with `memq add-operator machine-configuration-epoch-<hostname> "<description>" --body-file <path> --machine <HOSTNAME>`, the machine value spelled as `os.hostname()` reports it. Whoever observes a configuration change updates it in that turn with `memq add-operator machine-configuration-epoch-<hostname> "<description>" --body-file <path> --update --confirm-shared`, passing the description the record should keep, since the update rewrites it. Under the engine store signals `--body-file` and a body-carrying `--update` are refused, so a fleet worker reports a change on a box whose record exists and leaves the write to an attended session. A box with no epoch record may still get its first one there with `--body`.

**A recorded measurement is read against that date before it is leaned on.** Before using a durable figure whose value the box sets, such as a suite wall clock, compare the moment it was measured against the epoch record for the machine it ran on. A pass/fail count is a property of the tree that produced it, not the box, and does not expire at an epoch boundary. A figure is expired evidence when its moment predates the epoch, when it carries no moment, or when no epoch record at the canonical name covers its machine. Where none covers it, write that box's epoch record first, or state the figure unplaceable and name the epoch write as what would settle it.

An expired figure is re-measured and the fresh reading used, or stated as expired and unusable, naming what would produce the real one. It is never quoted as current, never carried into a comparison as though both readings shared a configuration, and never repeated onward.

## Operator Tier

`~/.claude/memory-operator/` holds facts true of the operator or of a machine rather than of one project or platform. It completes the routing ladder: journal, project, type, operator, doctrine.

**The routing test: would this fact be true in a project you have not opened yet, on any of your machines?** Yes is the operator tier. True of every project of a type but not beyond it is the type tier. About this codebase is the project tier. A fact true of one machine only still lives here, with a `machine:` field naming the box.

Author only through `memq add-operator`, never a direct Write into `memory-operator/`, since the tier's writes serialize under a lock the Write tool cannot take. Read the neighbours block the verb prints before the write lands. A `likely overlap` there is the store saying the fact may already be recorded, and the four-remedies paragraph below chooses the remedy. `add-operator` refuses an existing name and a description over the 120-character cap, never truncating it. See "Shared-Tier Repair and Removal" below.

Session start emits none of the tier's records, so reach it through `recall`, `find` and `get`, which keep every use visible to the stamps the decay clock runs on.

## Project-Type Tier

`~/.claude/memory-types/<type>/` holds memories shared by every project of a type, in the same file-per-fact format with its own `MEMORY.md`. A project opts in with a `Project-Type: <type>` line in the first ten lines of its memory `MEMORY.md`, and the session hook then emits the type index at session start.

**A fact belongs in the type tier only when it holds for every project of that type, not just the one that taught it**, on the routing test the operator tier section states. Starter types are `nextjs` and `dotnet`. Mint new ones freely through `add-type`, named for the platform or framework that dictates the conventions.

Author only through `memq add-type`. The frontmatter guard refuses a direct Write into `memory-types/`. Read the neighbours block the verb prints before the write lands. An overwrite takes an explicit request, under "Shared-Tier Repair and Removal" below.

## Memory Database Layer

A machine with `~/.claude/kit-memory-db.json` publishes its store to a shared database through `memq db-sync`. The markdown tiers stay the record, and the database is a derived copy no verb reads a body back from.

**The fleet memory block is the shared index's voice at session start and in `recall`, and a Jev config makes it a judged recollection.** That config is `~/.claude/kit-jev.json`, and with it TypeSafe's Jev, a model judge, scores the nearest records against the work in progress. Read the block's lines as records likely to change your next move. A line saying no fleet record bears on this project's recent work is a judged answer, not an outage. Where the judge stands down, the block falls back to the nearest-by-vector list and names why. Open a shown record with `memq get <name>`, never a Read of its file, since where the shell carries the session id `get` records that the shown record was read.

## Shared-Tier Repair and Removal

**A shared-tier write is not one-way.** Both shared tiers take a whole-body repair, a true delete and a recognition line stated whole (`memq triggers ... --replace`), under the same lock and `--confirm-shared` consent as their other shared work. Compose carefully because every project and machine sharing the tiers reads them, not because a mistake is permanent.

- **Repair** is `add-type <type> <name> "<description>" --body "..."` (or `--body-file <path>`) `--update --confirm-shared`, and the operator twin. It replaces the body whole, and the mandatory description rewrites the index line every project reads, so pass the one the record should keep. Repair refuses `--tag`, `--supersedes`, `--trigger` and, on the operator twin, `--machine`, so such a change is a delete and a fresh write. Triggers are the exception, which the triggers verb corrects in place.
- **Delete** is `delete-type <type> <name> --confirm-shared`, and the operator twin. In one locked operation it removes the record, its archived copy, its index lines and its usage stamps. Check the name before you confirm, because a name the tier does not hold is not refused. A delete of a record another machine has since modified stalls the sync until a human settles the git conflict in the store checkout.

**Four remedies, one per way a record goes bad, and routing between them is the whole point of holding them apart.** Delete is for the record that was **never true**: a mistake, a fact wrong when written, a body that says something you did not mean. Repair is for the record whose **fact is right and whose body is wrong**, so the text is replaced whole and the record keeps its name and history. Supersede is for the record that **was right and is stale now**: the fact has been overtaken, so a new record carries the answer and points back at the old one with `--supersedes`. Each read surface then labels and demotes the old record and nominates it for archive, though the session hook's `MEMORY.md` index shows its description unlabeled. Archive, which `decay-prune` performs, is for the record that **aged out**: it moves to the tier's `archive/`, off the live answers but still reachable by name.

Route by what went wrong, not by how much you dislike the record. The decay scan's neighbour-pairs block nominates unlinked live pairs that read as one fact and picks none of the four remedies, so which record was never true, stale or badly worded is your judgment over the two bodies. Reach for delete when you would be embarrassed to have another project read it, repair when only the wording failed, supersession when you are about to write the replacement, and archival when you no longer need it surfaced. A record carrying a credential, a connection string or anything needing rotation is a delete plus a rotation, whatever else is true of it. The deletion paragraph below says why even that is not a redaction.

**Deletion removes a record from the store, not from its history.** The shared tiers live in a git repository replicated to a private remote, so a deleted record's content stays in that history and on every machine that already pulled. Rotate anything it carried that it should not have, since the delete is not a redaction.

**The unattended vector gets a bounded subset of this CLI.** Under the engine store signals memq runs under the prompt-free grant in `hooks/memq-grant.js`, which owns the list of withheld shapes. A withheld shape is not denied but silent, and with nobody there to approve it the command is lost. So a fleet worker leaves a withheld shape to an attended session, such as `find`, `--type=<type>`, a delete, a body-carrying update, `--body-file`, `--supersedes`, `--trigger`, `triggers`, `anchor` or `--rollup`.

## `supersedes:` Field

The flag on the two shared-tier verbs is one way to write the field. The project tier gets it by hand: a project memory is an ordinary file you write with the Write tool, so its `supersedes:` line is authored like its `tags:` and `pinned:` lines. Every read surface treats a project-tier pointer exactly as a shared-tier one.

Its grammar is the one `pinned:` and `tags:` answer to:

- Written where every memq field is written, per the placement rule above, which `hooks/memory-frontmatter-guard.js` checks on a Write, an Edit or a MultiEdit. In a file the guard never saw, a `supersedes:` under any other key is not the field, and it fails silently.
- One name, matching the record-name charset, naming a live record of the same tier. Two names point nowhere.
- Same tier only: a project memory names a project memory. There is no cross-tier pointer.

## `anchors:` Field

A memory frontmatter field naming the files a record is about, at the bytes they held when it was written. It is one line of comma-separated `<path>@<sha>` entries, each path repo-relative, written where every field is written, per the placement rule above. It answers whether the code a memory describes is still the code that taught it.

**Write it with `memq anchor <name> <path>...`, never by hand.** In a linked worktree, anchors hash the main checkout's files and are no check on the worktree's own edits, so re-anchor from the main checkout once the merge has landed.

`memq decay-scan`, `memq get` and `memq recall` report drift, `recall` with a `[drift]` token on a drifted record and `[drift?]` on one it could not verify. The SessionStart hook's last line counts it. A quiet session start is no proof of a clean check, so run `memq decay-scan` when you need the answer.

**A drift line means the memory is unverified, not wrong.** A file the record names holds different bytes than when the record was written, and no surface has read the record's prose or the file's. Settle the one naming a memory you are about to rely on, and sweep the rest at the Chapter boundary where `memq unstamped` already runs. Re-read the anchored file first, then the record against it, then route the record through the four remedies above. Never delete a memory on a drift line alone.

To correct a record, read its file with the Read tool and rewrite it with the Write tool, carrying its whole frontmatter block across, since a dropped field loses its effect silently. Once the record is right, re-run `memq anchor` over the same paths, since correcting the prose re-hashes nothing. Supersede it with a replacement carrying a `supersedes: <name>` line. Retire it with `decay-prune --archive <name>`. Remove it outright with `memq forget <name> --confirm`, and rotate any secret it carried.

## `triggers:` Field

A memory frontmatter field naming the deterministic signals a record should be recognized by, so a session that does not know to ask still meets the memory when its work touches that subject. It is one line of comma-separated `<type>:<pattern>` entries: `triggers: cmd:git stash, err:module not found, glob:plugins/claude-kit/hooks/*.js`. Line discipline and placement follow `tags:`.

Six types, and the type is what says how the pattern is read: `cmd:<pattern>` against a Bash command, `err:<pattern>` against a failed call's output, `skill:<name>` for a skill invocation, `agent:<type>` for an agent dispatch, `tool:<name>` for a tool name, and `glob:<path-glob>` for a path.

**Write it through the CLI, never by hand: `memq triggers <name> <type>:<pattern>...` on a record that exists, or `--trigger <type>:<pattern>` on the `add-type` or `add-operator` that creates one.** `--replace` is how a wrong declaration is corrected, narrowed, respelled or withdrawn without deleting the record. On the type or operator tier, or a pinned project store, it takes `--confirm-shared`, since a replace states the line whole. A write that adds an entry moves the record's mtime, and on a shared tier that postpones the record's archival for every project and machine reading it. So declare a trigger on a shared-tier record because the recognition is worth having, not to keep a record alive.

**A `cmd:` pattern names the shape of the command, never the invocation that carried a secret.** A pattern is published as a body is, synced and embedded. A credential that reached a trigger line is rotated, per the deletion rule above.

## Decay Lifecycle

A memory's idle clock runs from the freshest of its file mtime, its `created:` date and its newest `applied` stamp. Summarizing condenses the body and keeps the index description. Archiving moves the record and its index line to the tier's `archive/`.

**Use extends the thresholds, and never confers permanence.** A memory is a summarize candidate after 30 idle days and an archive candidate after 60, each extended by 30 per distinct applied day, the extension capped at 365. Crossing a threshold nominates and never retires.

### Pinning

A `pinned: YYYY-MM-DD` top-level line makes a memory never a decay candidate, and makes `decay-prune` refuse it. The frontmatter block must close with its `---` within the first 40 lines.

**A pin is a judgment act, and the tally is evidence for it, never its trigger.** Set one in the turn a memory proves structurally load-bearing, or at a decay pass on a candidate that must not age out. Revoke it by deleting the line.

No memq path writes or removes `pinned:`. So a shared-tier pin is the operator's own edit made outside the harness, since the frontmatter guard refuses the write tools there. That edit is the one exception to the bar on hand-editing a shared tier. A pin binds the decay pass and nothing else: the delete verbs still remove a pinned record, so never use a delete verb to clear a pin.

### Scan Evidence Line

Every `decay-scan` prints a usage-evidence line per tier on stderr, so read it beside the candidates on stdout. `usage evidence: none (no usage.jsonl)` on a store you know has been used means the sidecar is gone, so investigate rather than archive. A torn line, one the scan skipped as malformed inside a sidecar, has one exit, `decay-prune --rollup --drop-malformed`. That flag is invocation-wide, so it drops malformed lines from every tier the pass reaches.

### Running the Decay Pass

The rollup and the usage prunes run only under `--rollup`. An archive flag alone moves what it names and touches nothing else.

`created: YYYY-MM-DD` is an author-asserted sign of life. The clock takes the freshest evidence, so the field can defer decay when file times understate recency and never ages a memory faster than its mtime. Write it at the top level like every other field here.

The pass runs at close-out, called from `finishing-work` step 8, and never unprompted outside one. It is due when the decay stamp is older than 14 days, or absent (a store where no pass has ever run is due, not exempt). The run: `decay-scan` reports, your judgment picks, `decay-prune --rollup` with the archive flags mutates, `decay-done` stamps. The summarize edit is the pass's only hand edit, and only on the project tier. A shared-tier candidate is summarized through the shared-tier repair path above.

`--confirm-shared` is one flag for the whole invocation, never one per target. The operator tier's gate is unconditional, so give any operator-tier archive its own `decay-prune` call and run the type-tier archive in a separate call without the flag. Add `--confirm-shared` to that type-tier call only once the refusal has named the projects the retirement would reach. Where the refusal says the scan of declaring projects could not be established, the reach is unknown, so ask the operator rather than add the flag. `--rollup` rides exactly one of the calls, the project tier's. Under the engine store signals the grant covers bare `decay-prune` and its archive flags but not `--rollup`, so a pass there archives what it names and leaves the rollup to an attended session.

## Search Before Writing

A project-tier memory arrives through the Write tool, into the memory write destination the SessionStart hook names, which writes the indexed record whose `MEMORY.md` line you write beside it, or through `memq put`, which writes the unindexed one. Neither path prints the shared-tier verbs' neighbours block, so run `memq find` in the words of the fact before either write. Under the engine store signals `find` is withheld, so that search is an attended session's. Read a lexical hit as an overlap candidate on its own, since a record the lexical block listed shows no semantic score. `hooks/memory-frontmatter-guard.js` refuses a malformed project-tier frontmatter block and any Write, Edit or MultiEdit into either shared tier.

## Known Limits

- A type tier is reachable only through a project declaring it with a `Project-Type` line. Re-add the line in some project of that type before running a pass over it.
- No memq command recovers a wedged type lock at `~/.claude/memory-types/<type>/store.lock`. Confirm no writer is live, then delete that entry by hand.
- A project store syncs under its flattened path, so a project tier resolves on another machine only where that project sits at the identical path.
- Two kit paths commit the store, and both go through the same leak probes: the background sync runner the SessionStart hook spawns on Windows, and the kit doctor's `-Fix`. Nothing else does, which is why the close-out relies on one of those rather than a bare `git add`.
