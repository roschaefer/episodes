# git-splice: design

`git-splice` keeps folders of a monorepo in sync with their own upstream
repositories, in both directions. Switching branches in the monorepo
switches the branch every folder syncs with.

## Principles

- **Let Git do the work.** Bash and Git, nothing to compile. Wherever Git
  can do a job, the tool calls Git: `git config` parses the state file,
  `cherry-pick` merges, `commit-tree` rebuilds, `log --left-right` compares.
  The tool's own code connects these, and stays small.
- **Changes cross the splice, commits don't.** The monorepo and each
  upstream keep separate histories. Upstream commits never become
  ancestors of the monorepo's commits, and the monorepo's merges and side
  branches never reach upstream.
- **The folder carries its own state.** A splice is a folder with a
  committed `.splice` file. Nothing about it lives in `.git/config`, so a
  clone of the monorepo has every splice, and `git mv` moves one.
- **Store as little as possible, derive the rest.** `.splice` holds the
  URL and the upstream commit the folder last matched, never a monorepo
  SHA. Where the last sync happened in the monorepo, and whether a push is
  needed, are worked out from history each time. Nothing a rebase or squash
  merge does can make them stale, and commands only inspect history since
  the last sync.
- **Deterministic rebuilds.** The same history always rebuilds into the
  same upstream commits, byte for byte. That makes status computable
  without storing anything about earlier pushes, and lets a second push
  fast-forward over the first.
- **Branches follow the monorepo.** On `feature-x`, every splice syncs with
  its upstream's `feature-x`. No branch is fixed per folder.
- **Name the target when writing, show everything when looking.** Commands
  that change the monorepo or an upstream need a path or `--all`.
  Commands that only look cover every splice.
- **Refuse rather than guess.** With unrelated histories, or a path that
  can't be a ref name, the tool stops and says what to do.
- **Weigh every fix against its complexity.** An easy, safe fix goes in.
  A rare case gets documented, or an issue labelled
  [`edge case`](https://github.com/roschaefer/git-splice/issues?q=label%3A%22edge+case%22). An extreme one is ignored.

## The sync point

Like a subtree, a splice's files live directly in the monorepo. Like a
submodule, the monorepo records an upstream commit. But a gitlink says
which revision to check out; a splice's commit is a sync point, the
upstream revision the folder last matched. Later commits can change
the folder and leave the sync point where it is
([sync model](../../test/concepts/sync-model/README.md)).

## Vocabulary

| Term | Meaning |
|---|---|
| **splice** | A folder of the monorepo that has its own upstream repository: "`vendor/a/` is spliced in from `github.com/x/a`", "the `vendor/a/` splice". Strictly, the noun means the joint, not the inserted piece ([why "splice"](name.md)). |
| **path** | Where the splice lives in the monorepo, e.g. `vendor/a/`. (`git subtree` calls it `--prefix`.) |
| **upstream** | The splice's own repository, named and given by URL in `.splice`, like a Git remote. |
| **state file** | `<path>/.splice`. Its presence in `HEAD` makes the folder a splice. |
| **synced commit**, **boundary**, **rebuild**, **upstream branch** | U(H), B, R and T of the [sync model](../../test/concepts/sync-model/README.md). |
| **last sync** | The newest first-parent commit in the monorepo that changed `<path>/.splice`: the last pull, usually. Its `.splice` records U(H). |
| **mount** | Where a splice's history starts: its first `.splice`, or a `git mv`. |
| **key** | An upstream's short name in one repository, e.g. `lib`, mapped to its URL in the repository's config. Names its refs. |
| **splice in** | Bring upstream content into the monorepo: `clone`, `merge`, `pull`. |
| **splice out** | Publish the monorepo's changes upstream: `push`. |
| **sync state** | How R and T relate: `up to date`, `push`, `pull`, `diverged` and so on. |
| **default branch** | A repository's main branch (`HEAD` on the remote). The monorepo's default branch corresponds to upstream's. |
| **nested splice** | A splice below another one's folder ([nesting](../../test/concepts/nesting/README.md)). |

"Default branch" belongs to a repository and is stored in `.splice` when
needed. It isn't called "fallback", which would describe only one of its
uses.

## Architecture

```
          monorepo                                  upstream (by URL)
 ┌────────────────────────────────┐
 │ HEAD                           │  fetch   ┌───────────────────────────┐
 │  └ vendor/a/                   │ <─────── │ refs/heads/*              │
 │      ├ .splice  (url, U(H))    │          └───────────────────────────┘
 │      └ …                       │                  ^
 │                                │                  │ push R
 │ refs/splices/<key>/heads/* (T) │                  │
 └────────────────────────────────┘                  │
        │ merge: cherry-pick of re-rooted trees      │
        │ push: rebuild of B..HEAD on top of U(B) ───┘
```

The state lives in two places, and both are plain Git data:

- **Committed:** `<path>/.splice`, with the upstream's URL and the synced
  commit U(H).
- **Local, rebuilt by `fetch`:** `refs/splices/<key>/heads/<branch>`, a copy of
  every upstream branch, under a key the repository's config maps the
  upstream's URL to.

Everything else, B, R and the sync state, is derived from those two and
the monorepo's history each time a command runs.
[Development](../development.md#code-map) maps this onto the code.

## The `.splice` file

[The `.splice` file](../../test/concepts/splice-file/README.md) shows
what it holds and which commands write it, and why it has no path and no
monorepo commit. The other choices:

- **Git's config format, read and written by Git.** There's no parser of
  our own, and the file is never sourced, since that would run whatever
  someone commits into it.
- **Its name** clashes with no known configuration file, so build or
  package globs that see it in the monorepo don't mistake it for theirs.
- **Its `id` is derived, not random,** from the path, `HEAD`, the
  upstream's URL and, for `clone`, the commit it splices in. So a command
  gives the same result each time it runs on the same commit, while two
  splices of different upstreams mounted at the same path on branches
  from the same commit still get different ids. The rebuild uses it to
  tell this splice from another one that had the same path before (see
  the push section).
- **`default-branch` is recorded once**, by `clone` and `init`, and only
  when it differs. That keeps it stable if the upstream later renames its
  default branch, and visible to anyone wondering why `main` syncs with
  `master`. It belongs to the upstream, like its URL: a company fork may
  name its default branch differently from the original. Where the
  splice above leaves it open, commands refuse rather than fall back to
  the monorepo's.
- **No merge driver** for the conflict two pulling branches get. One can
  follow if that turns out to be common.

## Refs instead of remotes

Upstream branches are fetched by URL into private refs:

```
git fetch --prune --no-tags <url> '+refs/heads/*:refs/splices/<key>/heads/*'
```

The key is the upstream's short name in this repository. The first
command that fetches an upstream records it in the repository's config,
which all its worktrees share, as they share the refs:

```
[splice "lib"]
	url = https://github.com/x/lib.git
```

It comes from the end of the URL, without `.git`, in lower case: `lib`
for `https://github.com/x/lib.git`. If that's taken, by another URL or by
refs left under it, more of the URL goes in front, `x-lib`, then
`github.com-x-lib`, and only then a number. Lower case only, so no two
keys' refs share files on a case-insensitive file system, and short, so
they fit any file system's name limit. Commands record keys one at a
time, under a lock, and refuse a config edited by hand into keys that
aren't valid, or into two URLs for a key or two keys for a URL, naming
the `git config` command that fixes it. A key has no `/`, so it ends
right before `heads/`, and branch names, which may have one, follow that. `git splice key <path>` prints a splice's key, and
`git splice key <path> <new-key>` renames it, refs included. Commands
that only read, like `status`, never record a key: an upstream without
one hasn't been fetched.

The URL is the one written in `.splice`, before `insteadOf`. Spellings
that look alike can name different repositories, e.g. `/srv/lib` and
`/srv/lib.git`, or `host:lib` (relative to the home folder) and
`ssh://host/lib`, so only equal URLs share a key. Keys are local, like the
refs: two clones may give one upstream different keys.

Keyed by URL, not by path, the refs describe the upstream rather than the
folder:

- `git mv` keeps the URL, so a moved splice still finds its refs.
- Splices at the same path with different upstreams, e.g. on two
  branches, don't overwrite each other's refs, and `init` on a path that
  had another upstream doesn't see that one's refs.
- Splices with equal URLs share refs, which is fine, since refs only
  describe the upstream. `fetch` fetches each upstream once.
- No Git remote exists, so nothing can push the monorepo there by mistake.
  [Why that matters](accidental-monorepo-push.md).
- `url.<base>.insteadOf` and `pushInsteadOf` still apply, since they work
  on URLs.
- `push` goes to the URL, and then updates `refs/splices/<key>/heads/<branch>`
  itself. If it can't, the push counts as failed.
- `--prune` drops branches deleted upstream, so no `prune` command is
  needed.
- Every Git command can read an upstream as `splices/<key>/heads/<branch>`,
  as of the last fetch, so no separate clone is needed
  ([looking at an upstream](../../test/walkthrough/fetch.md#looking-at-an-upstream)).

Two rules follow from the layout:

- **Both sides of a [nested splice](../../test/concepts/nesting/README.md)
  find the same state.** The `.splice` holds nothing specific to the
  monorepo, and fetched refs are keyed by URL, so the monorepo and the
  upstream above find the same synced commit under the same refs. An
  upstream with a `.splice` at its root is refused: it would replace the
  splice's own.
- **A splice's path must work in a ref name** (`git check-ref-format`),
  which applies to the whole path: no spaces, no component ending in
  `.lock`, and so on.

## How the commands work

Which splices a command acts on depends on what it does:

| Kind | Commands | Without a path |
|---|---|---|
| Starts a splice | `clone`, `init` | Take one URL and one path, no `--all`. `clone` defaults the path to the repository's name, as `git clone` does. |
| Splices in or out: changes the monorepo or an upstream | `merge`, `pull`, `push` | Refuses. Takes one or more paths, or `--all`. |
| Looks or prepares: changes neither | `status`, `diff`, `log`, `fetch` | Every splice; paths narrow it down. |

Splicing in writes a commit into the monorepo, and splicing out publishes
commits upstream. Both should name their target, as `git push <remote>`
does. An overview such as `status` is only useful if it's complete.

### Starting a splice: `clone` and `init`

| Situation | Command |
|---|---|
| Upstream exists, the folder doesn't | `git splice clone <url> [<path>]` |
| The folder exists, upstream is new or empty | `git splice init <path> <url>` |
| Both exist with the same content | `git splice clone <url> <path>`: only writes `.splice`, since nothing can be lost |
| Both exist and differ | `git splice clone --merge <url> <path>` |

- `clone` refuses a folder that exists and differs from upstream, like
  `git clone` refuses a non-empty directory. The message names `--merge`.
- `--merge` runs the same mechanism as `merge` (below), with an empty
  folder as the merge base. Every file that differs becomes an add/add
  conflict, and nothing is lost. Deleting the folder on a branch,
  re-cloning it there and merging `main` back **isn't** a substitute: the
  merge base still has the folder, so Git takes upstream's side wholesale
  and drops local-only files.
- To replace the folder with upstream's version instead, `git rm` it in one
  commit, then `clone` into the empty spot.
- `init` refuses an upstream that already has commits, and points to
  `clone --merge`. It writes `.splice` without a synced commit, and the
  first push creates the upstream branch starting at the init commit,
  followed by any commits after it, also on a feature branch where the
  folder didn't change. The folder's history before it isn't
  published: it was written
  for the monorepo, and may hold what was removed before anyone decided
  to publish the folder
  ([example](../../test/scenarios/02-starting-a-splice/04-init-new-upstream/01-removed-before-init/README.md)).
- The name `add` is avoided on purpose: it suggests `git add`.

### Splicing in: `merge`, and `pull` = `fetch` + `merge`

`merge` turns already fetched upstream changes into **one ordinary
commit** in the monorepo, and never touches the network. The problem it
solves: upstream's commits have the splice's content at their root, while
the monorepo has it at `<path>/`, and they share no history, so Git can't
merge them directly. `git subtree` solves that by putting upstream's
history into the monorepo's. `merge` instead supplies the merge base
explicitly:

1. Build two throwaway commits whose trees have the monorepo's layout
   (`reroot_tree`, using a temporary index):
   - **base:** `HEAD`'s tree, with `<path>/` replaced by the merge base's
     tree and HEAD's `.splice`.
   - **theirs:** `HEAD`'s tree, with `<path>/` replaced by the upstream branch's
     tree and a `.splice` that records its commit. Its parent is base.
2. Run `git cherry-pick theirs`. That's a three-way merge of `HEAD` (ours)
   and theirs, with base as the merge base. Only `<path>/` differs between
   base and theirs, so only the splice can conflict. Local edits are kept, and the
   `.splice` update comes along in the same commit. Git's ort merge does
   the work, including rename detection.

The merge base is `git merge-base R T`
([why](../../test/concepts/sync-model/README.md#three-ways-both-directions)).

**The same files, another history:** if the folder already has T's
files, there's nothing to merge. But if T isn't part of R's history,
`merge` still records T as U(H), in a commit that only changes `.splice`.
That happens when the upstream rewrote its history to the same files
([example](../../test/scenarios/06-rewritten-history/02-upstream-rewritten-equal-tree/README.md)),
squash-merged what was pushed, or got R edited before the push
([example](../../test/scenarios/06-rewritten-history/01-edited-before-push/README.md)).
Without the record, R would keep the monorepo's original commits, and
the next push would publish them. Right after an ordinary push, R is T,
and nothing is recorded. Once the folder changes again, it's too late:
the splice reads as diverged, or as unrelated history.

- **On a conflict:** resolve it, then run `git commit`, which finishes the
  cherry-pick and keeps the prepared message. Abort with
  `git cherry-pick --abort`. `git status` says "cherry-picking" although
  you ran `merge`, so `merge` names both commands when it stops.
- **base and theirs are never referenced** and get garbage-collected. Upstream
  commits stay in `refs/splices/` and never become ancestors of `HEAD`.
- **Nested splices:** a pull of a splice brings in the `.splice` files
  below it as its upstream has them, and becomes the last sync of those
  splices. If its upstream moved the synced commit of a splice below, the
  rebuild joins that splice's unpushed commits with the new one, as after
  a pull of a divergence. `pull` fetches the splices below too, so their
  new synced commit is there.
  - **Top-down:** `merge` and `pull` take a splice before the ones below
    it. Pulling the one below first, to a commit newer than the one the
    upstream above records, would make the pull above conflict. A pull
    that removed a `.splice` below ends that splice, and its pull is
    skipped. A failed fetch stops the pull of the splices above and below
    it, and a failed merge the merges below it.
  - **Bottom-up:** `push` takes a splice before the ones above it, whose
    push publishes its `.splice`, and a failed push stops them. Otherwise
    the upstream above would record content the upstream below doesn't
    have.

### Splicing out: `push` and the rebuild

A push sends the splice's history since the last sync, rebuilt as upstream
commits. `rebuild_splice` is a function of `HEAD` alone:

1. **Find the last sync.** *L* is
   `git log --first-parent -1 -- <path>/.splice`. Every `clone`, `init`
   and pull writes such a commit, and no rebase or squash merge can remove
   all of them. U(L) is the synced commit recorded at *L*.
2. **Start at U(L).** If *L*'s folder (without `.splice`) equals U(L)'s
   tree, *L* is B, and the rebuild continues from U(L). Otherwise a pull
   merged a divergence, or a squash merge mixed local edits into *L*, and
   *L* is rebuilt too, on the parents the
   [sync model](../../test/concepts/sync-model/README.md#pulls-in-between)
   picks, back to [B](../../test/concepts/sync-model/README.md#where-b-is)
   ([scenario](../../test/scenarios/01-everyday-sync/02-up-to-date/03-diverged-then-pulled/README.md)).
   Without U(L), e.g. after `init`, the rebuild starts at the mount, as a
   root commit.
3. **Copy each commit.** For each commit in
   `git rev-list --reverse --first-parent L..HEAD -- <path>` whose folder
   changed, `git commit-tree` with the folder's tree minus `.splice`.
   Author and committer are copied, **including their dates**, as
   `git subtree split`'s `copy_commit` does. The message is read with
   `--pretty=format:%B`, not `--format=`, which would add a newline.
   Commits are never signed: a signature would differ from run to run.

**First parent only:** a merge in the monorepo, e.g. `git merge main` on a
feature branch, becomes **one ordinary commit** upstream, with the merge's
message. Upstream doesn't know the monorepo's side branches, so a faithful
merge shape would add nothing, and leaving it out avoids the
parent-mapping problems `split` spent years fixing.

**Only this splice's history:** a splice's history starts at its
*mount*, the newest first-parent commit whose first parent had no
`.splice` at the path, or one with another `id`. Before the
mount, the folder was no splice, or another one, so nothing from there is
published, with or without a synced commit. That covers a folder's
history from before `init`
([example](../../test/scenarios/02-starting-a-splice/04-init-new-upstream/01-removed-before-init/README.md)),
two splices that swap paths
([example](../../test/scenarios/07-moved-folders/02-swapped-splices/README.md)), and a splice
removed and spliced in again
([example](../../test/scenarios/02-starting-a-splice/04-init-new-upstream/02-unspliced-then-cloned-again/README.md)).
A new upstream URL keeps the history: the `id` stays
([example](../../test/scenarios/04-upstreams/04-upstream-moved/README.md)).

**A nested splice's history up to the splice above's last sync** comes
from that splice's upstream, at its synced commit
([nesting](../../test/concepts/nesting/README.md),
[example](../../test/scenarios/05-nested-splices/01-nested-splices/spliced-elsewhere.md)).
Of the splices above, it takes the one with the newest last sync, and on
a tie the outermost: a push writes nothing to the monorepo, so the
`.splice` of the splice in between may name a commit from before the
change, while the outermost upstream has it
([three levels](../../test/scenarios/05-nested-splices/01-nested-splices/02-three-levels/README.md)).
Only if the upstream above has the same splice there, by its `id`
([replaced above](../../test/scenarios/05-nested-splices/01-nested-splices/replaced-above.md)).
And the monorepo's own commits before the last sync are joined in even if
the folder's files equal that rebuild, so a commit pushed straight to
the splice's upstream stays in its history
([pushed and made above](../../test/scenarios/05-nested-splices/01-nested-splices/pushed-and-made-above.md)).

**Costs** O(commits since B), not O(all history). The commit loop
reads all commit metadata with one `git log` and all folder trees with one
`git cat-file --batch-check`, so it spawns about one process per commit.

**Never writes to the monorepo**
([why](../../test/concepts/sync-model/README.md#why-a-push-isnt-recorded)).

**A new upstream branch** is created only if R has commits that
upstream's default branch lacks, which a PR from the new branch would
show. So starting a feature branch doesn't create empty branches on every
upstream, while commits the default branch lacks always count: the ones
the feature branch got from the branch it was cut from, and the first
push of a splice made by `init`, which has no upstream branch at all.
Whether the folder changed on this branch doesn't matter. A branch
stacked on one upstream has already gets its own branch upstream too,
with nothing new
([scenario](../../test/scenarios/03-branches-and-teamwork/01-feature-branch-unchanged/01-feature-branch-changed/01-stacked-branch/README.md)).

### `status`: the sync state

`classify_splice` works the state out each time, from R and T, as the
[sync model](../../test/concepts/sync-model/README.md#three-ways-both-directions)
describes. It compares the files first: when they're equal, nothing
needs rebuilding. Before that, it checks there's something to compare:
without `refs/splices/<key>/*`, and with U(H) recorded but not available
locally, as in a fresh clone of the monorepo, the splice was never
fetched.

### `diff` and `log`

- **`diff`** shows the file changes a push would send: `git diff T R`, or,
  for a missing upstream branch, from the merge base of R and upstream's
  default branch, as a PR from the new branch would show them.
- **`log`** shows commits in both directions:

  ```
  git log --left-right --cherry-mark R...refs/splices/<key>/heads/<branch>
  ```

  `<` is on the left (local) side only, so a push sends it; `>` is on the
  upstream side only, so a pull brings it; `=` is a commit upstream already
  applied by cherry-pick or rebase. Ours on the left, theirs on the right,
  as in Git's conflict markers. The format shows the author, because a
  push publishes it and it may be a private identity.

### Branches

- Each splice syncs with the upstream branch named like the monorepo's
  current branch, for every command. Switching branches switches every
  splice.
- The monorepo's default branch maps to upstream's default branch
  (the upstream's `default-branch` in `.splice` if the names differ). Every other branch
  keeps its name on both sides.
- The monorepo's default branch is `origin/HEAD`, else
  `init.defaultBranch`.
- If upstream has no branch named like the current one, every command
  compares with upstream's default branch instead, as a PR from that
  branch would, and `push` creates it only as described
  [above](#splicing-out-push-and-the-rebuild). Which branch it was cut
  from doesn't matter: Git doesn't record it, and commits from there
  that upstream lacks have to get there somehow, e.g. through a PR.

## Limits

These are known and accepted, each to keep the design simple:

- **A nested splice pulled on both sides:** if the monorepo and the
  upstream of the splice above each pull the splice below, the next pull
  of the splice above conflicts in the folder below, since each side
  brought in a different upstream commit. If the monorepo has no unpushed
  changes there, keep the upstream's side:
  `git checkout --theirs -- <above>/<below>`, then `git add` and
  `git commit`. Pushing the splice above right after pulling the one below
  avoids the conflict.
- **An upstream that keeps its submodules:** after
  `clone --from-submodule --recursive`, `pull` refuses every commit of
  theirs that moves one
  ([`clone`](../../test/walkthrough/clone.md#more),
  [#153](https://github.com/roschaefer/git-splice/issues/153)).
- **Paths that aren't valid in ref names**, e.g. with spaces, are refused.
- **Moving a splice with unpushed changes:** the `git mv` commit changes
  `.splice`, and the splice's history starts there, so the unpushed
  commits before it reach upstream folded into the move commit. Push before moving
  ([#4](https://github.com/roschaefer/git-splice/issues/4)).
- **Upstream URLs that differ only in letter case**, e.g.
  `ssh://host/Org/lib` and `ssh://host/org/lib`, share their fetched refs
  on case-insensitive file systems, like macOS's default one: fetching one
  overwrites the other's. And a URL component that is too long once
  escaped, e.g. many spaces, fails with "File name too long". Until
  [#51](https://github.com/roschaefer/git-splice/issues/51), avoid
  upstreams whose URLs differ only in case, and long path components.
- **A splice made by `init`** has no synced commit until its first pull, so
  until then every rebuild walks the folder's history since `init`.
- **Rare edge cases** each have an issue labelled
  [`edge case`](https://github.com/roschaefer/git-splice/issues?q=label%3A%22edge+case%22).
