# Fork sync — how xollama and `mann1x/ollama` stay in step

The contract between two repositories worked on by two sessions:

| | |
|---|---|
| **xollama** | `mann1x/xollama` — this repo. A soft fork of ollama; consumes patches. |
| **the fork** | `mann1x/ollama` — where patches are authored and staged as upstream PRs. |
| **upstream** | `ollama/ollama` — the eventual destination, which must be assumed never to merge. |

Agreed 2026-09-21 between the `xollama@solidpc` and `ollama@solidpc` sessions,
proposed by the latter. `docs/protocols/CARRIED-PATCHES.md` records *which*
patches this repo carries and at which merge; this file records *how* they get
here and stays the shared definition. Both repos reference it.

## Why it exists

Not theory. On 2026-09-21 `model/parsers/gemma4.go` was three different things
across two trees:

| | xollama `dev` | fork `think-budget` |
|---|---|---|
| `ToolCallTags()` | **absent** | present |
| stray channel-name strip | single `CutPrefix`, one orphan | loop over both orphans |
| thinking-state tool-call fix | present | present |

One patch at its current revision, one at an older revision, one missing
entirely. Nobody did anything wrong. There was simply **no statement anywhere of
what the patch set is and at which sha**, so each tree took whatever was visible
when someone last looked. Our own `CARRIED-PATCHES.md` even listed
`up-gemma4-stray-channel-name` as carried when it had never been merged.

Upstream merging is not the fix. Twelve fork PRs have sat on `ollama/ollama`
since August with no maintainer review, which is the reason the fork exists at
all. **The protocol assumes upstream never merges.**

## The rules

**R1 — One home per patch.** Every fix lives on exactly one branch in
`mann1x/ollama`, named `up-<slug>`, whose head *is* the head of its upstream PR.
A patch is never authored anywhere else.

> **A branch that is the head of an open cross-fork PR keeps the name it has.**
> Renaming it **closes the PR**. GitHub retargets open PRs on a rename *within*
> a repo; it does not do so when the head lives in a fork, and `gh pr reopen`
> then refuses, because the old ref survives only as a redirect and not as a
> real branch. Measured 2026-09-21 on upstream #18307: the rename to
> `up-gemma4-toolcall-in-thinking` closed it, and recovery cost recreating the
> branch, reopening the PR and deleting the duplicate — a close/reopen pair now
> sits in its timeline. Such a branch takes the `up-` prefix **only once its PR
> is closed or merged.**

So two of the twelve carry no prefix on purpose:
`gemma4-toolcall-in-thinking` (#18307) and
`qwen3coder-tolerate-malformed-tool-calls` (#17914). The missing prefix is also
what hid them — #17914 never appeared in an `up-*` survey for exactly that
reason, the same way #18307 went astray. **Survey the manifest, never the
branch names.**

**R2 — `think-budget` is integration only.** Every commit on it is a
`cherry-pick -x` from an `up-*` branch, or CI/notes/manifest. Releases are cut
from it and nowhere else. No patch is authored directly on it.

**R3 — `PATCHES.json` is the contract.** At the root of `think-budget`,
fetchable raw:

```
https://raw.githubusercontent.com/mann1x/ollama/think-budget/PATCHES.json
```

```json
{
  "base": "v0.34.2",
  "updated": "2026-09-21",
  "integration": { "branch": "think-budget", "sha": "3af5f361",
                   "release": { "tag": "v0.34.2-1-thinkbudget", "sha": "645ec440" } },
  "patches": [
    { "slug": "gemma4-toolcall-in-thinking",
      "branch": "gemma4-toolcall-in-thinking",
      "sha": "16a78556",
      "upstream_pr": 18307,
      "rebased_onto": "v0.34.2",
      "files": ["model/parsers/gemma4.go", "model/parsers/gemma4_test.go"],
      "status": "open-upstream" }
  ],
  "known_conflicts": [ ... ],
  "verification": { "per_patch": "...", "apply_order": "..." }
}
```

`integration.sha` is the tree the patch set describes; the manifest commit is
its child. `known_conflicts` names the collisions that are **not** ordering
mistakes — two additive test blocks landing at the same point conflict in
either direction — and carries the resolution, so a merge conflict can be
checked against it instead of guessed at.

It is bumped in the same commit that changes what is applied. One `curl`
answers "what is the patch set, at which sha" with no guessing from PR
timestamps. **`patches[]` order is apply order** — xollama merges each as its
own `--no-ff` merge, and a wrong order is a silent conflict resolution rather
than an error.

**R4 — Consume by sha, never by hand-copy.** xollama merges `up-<slug>` at the
sha the manifest names. If a patch needs changing *for* xollama, the change goes
onto the `up-*` branch first and returns through a manifest bump. A fix authored
inside xollama, on a file both repos own, is exactly how the `gemma4.go` split
above happened.

**R5 — A mail on every manifest bump**, to `xollama@solidpc`, naming the base
tag and the shas that moved. Neither side polls.

**R6 — A sync delivers everything xollama consumes.** "Sync the fork to
upstream tag X" is one job, and it is done only when xollama can move to X
without asking the fork for anything. On every upstream tag we build against,
the fork delivers all of the following, in this order:

1. **The patch set.** Every `up-*` and PR-head branch rebased onto the tag, and
   the manifest republished with the new `base` and shas.
2. **The fork release for that tag**, `v<X>-thinkbudget`, cut from
   `think-budget` by `thinkbudget-release.yaml` (`--ref think-budget`). It
   carries `ollama-linux-amd64-runtime.tgz` and `ollama-linux-arm64-runtime.tgz`
   (since 2026-10-04, built in the same run from the same commit), the Linux
   CPU runtimes xollama pins in `llama/runtime-pin-linux.txt` and
   `llama/runtime-pin-linux-arm64.txt`. Without either,
   `scripts/docker-assemble.sh` refuses that architecture, and
   `xollama-release.yaml` refuses the release. The fork publishes binaries
   only; the container image, both architectures, is xollama's (owner,
   2026-10-04).
   - A release is required on **every** sync, even when `LLAMA_CPP_VERSION`,
     `llama/server` and `llama/compat` did not change. That keeps the pin's
     tag in step with the base and leaves nothing to decide per sync.
   - The release commit may add only release notes and manifest commits on top
     of `integration.sha`, so the llama inputs digest is unchanged.
3. **Upstream's MLX runtimes on that release**, for every platform, bytes
   unchanged (owner, 2026-10-05). xollama serves safetensors models through
   MLX and never compiles it, so the fork republishes what upstream built:
   - `ollama-linux-amd64-mlx.tar.zst` and `ollama-windows-amd64-mlx.zip`:
     upstream's assets as they are; their sha256 equals upstream's
     `sha256sum.txt`.
   - `ollama-windows-amd64-mlx-reldir.zip` (from v0.40.0): the fork's own
     build of the same MLX with `MLX_CUDA_BIN_DIR` and `MLX_CUDNN_BIN_DIR`
     set to `.`, built by the fork's workflow (`only=mlx-windows`,
     `asset_suffix=-reldir`). It is what `llama/runtime-pin-windows-mlx.txt`
     pins: upstream's `mlx.dll` needs cuDNN installed in
     `C:/Program Files/NVIDIA/CUDNN`. It never replaces an existing asset.
   - `ollama-darwin-mlx.tgz`: `mlx_metal_v3/` (universal, Intel and Apple
     silicon), `mlx_metal_v4/` (Apple silicon) and the MLX, MLX-C, xgrammar,
     dlpack, picojson and fmt licence texts, cut entry for entry from
     upstream's `ollama-darwin.tgz`. No `llama-server`, no `libllama`, no
     ggml. Every file's sha256 equals upstream's, and the archive is
     reproducible.
   - `mlx-runtime.txt`: the upstream tag and commit, `MLX_VERSION`,
     `MLX_C_VERSION`, each asset's sha256, the sha256 of the upstream archive
     the macOS one was cut from, and the sha256 of every file in it.

   One command, run from the `think-budget` worktree after the release exists:
   `scripts/thinkbudget-mlx-assets.sh v<X> <work dir on a real disk> --upload`.
   It refuses when a download disagrees with upstream's `sha256sum.txt` or
   when upstream stopped publishing one of the three. Without `--upload` it
   builds and checks and publishes nothing.
4. **The release recorded in the manifest**: `integration.release` with the
   tag, the commit it was built at, the run, the asset's sha256 and the inputs
   digest in xollama's definition (below), and `integration.release.mlx` with
   the three MLX assets' sha256 and the upstream versions.
5. **One mail** naming the base tag, the shas that moved, the release tag, the
   build commit, the asset sha256, the inputs digest and the MLX pin rows.

   xollama pins the macOS archive in `llama/runtime-pin-darwin.txt` (tag,
   sha256, the two MLX versions) and `scripts/build_darwin.sh` unpacks it
   instead of compiling MLX; the release workflow's `plan` refuses a pin whose
   versions are not the tree's. It moves with the two Linux runtime pins.
   The Windows archive is pinned the same way in
   `llama/runtime-pin-windows-mlx.txt` and moves with them; the installer
   downloads it (it does not fit inside `xOllamaSetup.exe`), and `plan`
   refuses it on the same terms. The Linux one is a `gpu` row of
   `llama/runtime-pin-linux.txt`, unpacked into the image.

> **Why step 3 exists.** Upstream dropped safetensors-to-GGUF conversion in
> `98acec40a` (2026-09-14, in v0.35.x): `ollama create` from safetensors now
> imports an MLX model, so safetensors support is the MLX runtime, on every
> platform. Until 2026-10-05 the fork's release carried none: Linux was pinned
> to upstream's asset directly, Windows and macOS had nothing, and the macOS
> build compiled MLX itself.

The digest xollama checks is the sha256 of
`git ls-tree -r <commit> -- LLAMA_CPP_VERSION llama/server llama/compat llama/clef`
with the `llama/compat/README.md` line removed. `llama/clef` joined it at
v0.40.1 (mails 887–889): upstream's own directory, but `llama-server` compiles
`clef.cpp` in, and #18777 changed it while the old digest stayed put. The fork computes it at the release
commit and states it in the manifest and the mail. If the two sides disagree,
the mail says which side moved.

> **Why this is spelled out.** On 2026-10-03 the v0.35.1 sync stopped after
> step 1: branches rebased, manifest `f430d02f` published, mail sent, no
> release. xollama merged all 24 patches and then could not assemble rc.1's
> Docker image, because its Linux pin still named `v0.34.4-thinkbudget`
> (llama.cpp b11081, inputs `17ab8578…`) against a tree at b11232 (inputs
> `57004c3c…`). It had to ask (mail #703), and the release was cut hours later
> as `v0.35.1-thinkbudget` at `1040f03d`. The old wording of this rule,
> "rebased, the manifest is republished, and the mail goes out", described
> exactly the half that was done.

**R7 — `mann1x/ollama@main` mirrors upstream, plus the release workflow.** It
was six weeks stale, which is what made every fork PR a 451-file diff burying
the two files that mattered. Mirrored, it is never a development target and
never a base anyone reasons about.

> **`.github/workflows/thinkbudget-release.yaml` must stay on `main`.** GitHub
> discovers a `workflow_dispatch` workflow **only on the default branch**, so
> mirroring it away put the workflow into state `deleted` and the fork could not
> cut a release at all — silently, until the next release. `main`'s copy is
> `think-budget`'s, byte for byte, which also closes the opposite trap: `main`
> once held a four-job version against the branch's seven, so a dispatch that
> forgot `--ref` produced a *green* run missing two release assets. Keep the two
> copies in step; dispatch stays `--ref think-budget`.

> **Done 2026-09-21.** `main` moved from `eef55508` (2026-08-10) to upstream
> `6383a0fa` plus that one file, at `a4aed68b` — verified here against the
> GitHub API: one changed file, parent `6383a0fa`, workflow state `active`. The
> pre-mirror `main` is kept as `main-pre-mirror-20260921` at `eef55508`. The
> payoff is measured: fork PR #1 (`think-budget` → `main`) went from a 451-file
> diff to 66 files, `+6179/-311`.
>
> Fifteen commits were on the old `main` and not upstream; two had no `up-*`
> home, and both were checked before the overwrite rather than after —
> `b002feda` is obsolete (its file does not exist at v0.34.2) and `f05a6f76`
> already lives on `think-budget`. An untracked patch that still applied would
> have been given an `up-*` branch first. That is R1 doing its job.

> **xollama fetches nothing from `mann1x/ollama@main`.** Verified 2026-09-21:
> no build file, cmake module, pin, workflow or Go source references
> `mann1x/ollama` at all. We touch the `fork` remote only to fetch `up-*`
> branches for merges. Mirroring `main` cost this repo nothing — which is *why*
> the mirror was safe to do, so this verification is load-bearing in both
> directions.

## One branch, one worktree

**A branch the sync moves is checked out in at most one worktree.** That covers
`think-budget`, `main`, every `up-*` and PR-head branch, and `thinkbudget-*`.

When a branch is checked out in two worktrees, moving it from one of them by
commit, cherry-pick, reset or merge moves the shared ref. It does **not** touch
the other worktree's index or files. From then on, `git status` there compares
the new `HEAD` with the old tree and shows every change since as **staged**,
reversing it. Two things follow:

- **It looks like someone's work in progress, and it is not.** Nothing was
  edited. The "changes" are the branch's own recent commits, shown backwards.
- **A commit there reverts patches silently.** Any `git commit` in that
  worktree, including `-a` or after an unrelated `git add`, records the old tree
  and undoes every commit since, with no conflict and no warning.

> **Measured 2026-10-03, during the v0.35.1 sync.** `ollama-pr` and
> `ollama-wt-tb` both had `think-budget` checked out. On 2026-09-29 the branch
> advanced from `ollama-wt-tb` by `64f1ae1c` + `23a43c77` (adding
> `up-modelfile-roundtrip`). `ollama-pr` then showed five staged files
> (`PATCHES.json`, `parser/parser.go`, `parser/swallowed_directive_test.go`
> deleted, `server/images.go`, `server/images_test.go`) that removed that patch.
> The sync reported them as someone's staged work. `git write-tree` in
> `ollama-pr` was exactly the tree of `ec8b675d`, the commit before the patch
> landed.

`git worktree add` refuses a branch that is already checked out, so a duplicate
was made with `--force`. Don't use it for these branches.

**Before every sync**, in both repos:

```sh
git worktree list --porcelain | awk '/^branch /{print $2}' | sort | uniq -d
```

It must print nothing. If it prints a branch, detach every extra checkout before
moving that branch (`git -C <worktree> switch --detach`), or remove the
worktree. Do sync work in a worktree created for the sync and remove it
afterwards.

**When a worktree shows staged changes you did not make**, find out what they
are before reporting or acting on them:

```sh
idx=$(git write-tree)
for c in $(git rev-list -n 50 <branch>); do
  [ "$(git rev-parse "$c^{tree}")" = "$idx" ] && git log -1 --oneline "$c"
done
git diff --stat        # unstaged
git status --porcelain # untracked shows as ??
```

If the index matches a commit and there are no unstaged changes, the worktree is
stale, not modified. `git reset --hard HEAD` brings it up to date and loses
nothing, because the old tree is that commit. If nothing matches, the changes
are real and belong to whoever made them: report them and leave them alone.

## llama.cpp comes from the fork — enforced

Ruled 2026-09-25 by the repository owner: the fork **supplies** llama.cpp.
`LLAMA_CPP_VERSION`, `llama/server` and `llama/compat` here must be identical to
the fork's, and a change to any of them lands in the fork first and arrives by
sha, like every other carried patch. That includes `llama/compat/README.md`: a
README-only difference still moves the inputs digest the release workflow
compares, and it happened (`faabb1ca`, alongside `a836824b`, which wrote 005
here; both were measured as the whole gap between the fork's runtime at
`597db4f78d5b` and ours at `73387c282b7f`).

`.github/workflows/compat-origin.yaml` runs `scripts/check-compat-origin.sh` on
every PR and every push to `dev` and `main`. A commit that changes those paths
must be reachable from a `mann1x/ollama` branch or `ollama/ollama` `main`; a
merge passes only when every file it leaves under them is byte-identical to
that file in one of its parents, so resolving a conflict to either side is
fine and resolving it into new text is not. Run it locally after `git fetch
fork` and `git fetch upstream`:

```sh
scripts/check-compat-origin.sh origin/main..HEAD
```

Measured against history: it flags exactly `a836824b` and `faabb1ca` and passes
every fork merge, including `84bcccc5`, which combines the fork's 004 with this
tree's 005.

## The rebase base is the upstream TAG

`up-*` branches are rebased onto **the upstream release tag xollama builds**,
currently `v0.40.3` — never upstream `main`.

This repo's `dev` is upstream release v0.40.3 plus fork changes (`main` follows
at the next release), carrying the
full upstream history so every `git merge upstream/main` has a real merge-base.
A patch rebased onto upstream `main` drags unreleased upstream into that
merge-base and costs the ~33% per-sync conflict rate the fork was restructured
to avoid (measured: 155 of the 474 files upstream touched between v0.34.0 and
v0.34.2). When xollama moves to a new upstream tag, the fork is told **before**
the rebase, not after.

## Dependent patches — the one amendment to "based on the upstream tag"

Decided 2026-09-21, on the first patch that could not satisfy the rule.

`up-*` branches rebase onto the upstream tag, and twelve of fourteen do. The
exception is a patch whose changes **cannot exist** on that tag. The case that
forced it: the reader half of the response-scope thinking budget edits
`llama/compat/004-reasoning-budget-line-boundary.patch`, a file that does not
exist at `v0.34.2` because `up-reasoning-budget-line-boundary` (#18212) creates
it, and it needs `up-think-budget`'s (#17566) Go plumbing besides. Its only
honest base is a tree carrying both.

**The amendment.** Such a patch gets a stacked `up-*` branch and declares its
dependencies:

- the manifest row carries `depends_on` naming them, and a `base` that is the
  dependency set rather than the tag;
- the branch is built on the merge of exactly those dependencies, **at their
  manifest shas**;
- it comes **after** all of them in `patches[]`, which apply order already
  guarantees once it is placed there;
- it is `fork-only`. Not by preference — a patch that only applies on top of two
  unmerged PRs cannot be a standalone upstream PR.

**What this changes on xollama's side.** The invariant checked before merging
was "every branch's merge-base is the upstream tag". It becomes: the merge-base
is the tag, **or** every entry in `depends_on` is earlier in `patches[]` and the
branch's merge-base lies within their merge. A branch that satisfies neither is
not merged and the fork is asked, as before.

**Why not the alternatives**, since both were offered and one looked cheaper:

- *Fold it into `up-think-budget` and reorder so #18212 precedes it.* This does
  not actually avoid the amendment. The branch would still have to edit a file
  that does not exist at its base, so either it stops being tag-based anyway, or
  it absorbs #18212's commit — which puts one open upstream PR's changes inside
  another's. #17566 is the headline PR and the one most likely to be read; the
  whole point of mirroring `main` was to stop fork PRs being unreadable.
- *Leave it fork-only on `think-budget` with a note.* That is precisely the
  state that produced the `ToolCallTags()` finding: code on the integration
  branch with no home, which R2 forbids and which nobody notices until someone
  greps for it. Choosing it knowingly is worse than having arrived there by
  accident.

## What xollama does on receipt of a manifest bump

A bump that moves `base` arrives with the fork release for that tag (R6). If the
mail names no release, the sync is not finished: say so in the reply instead
of working around it.

1. `git fetch fork` and merge each named `up-<slug>` **at the manifest's sha**,
   in `patches[]` order, each as its own `--no-ff` merge — so retiring one stays
   a single revert of an identifiable range.
2. Update `docs/protocols/CARRIED-PATCHES.md` in the same commit: the upstream
   PR number, the branch, and **our** merge sha.
3. Reply with those merge shas, so the fork's manifest and this registry can be
   reconciled from either end.
4. Move `llama/runtime-pin-linux.txt` and `llama/runtime-pin-linux-arm64.txt`
   to the release the mail names, in one commit, checking each asset's sha256
   and that each pin's inputs digest equals this tree's. The release workflow
   refuses two pins on different fork releases.
5. Never hand-copy a hunk from `think-budget`. If something is needed before the
   manifest exists, ask for the branch and sha.

## Identifiers

The **upstream PR number** is the single identifier for a patch, on both sides.
`CARRIED-PATCHES.md` already keys off it and `PATCHES.json` carries it as
`upstream_pr`. The fork-internal PRs on `mann1x/ollama` that duplicated the
upstream ones — #3, #4, #5, #6, #7 — are **closed** as of 2026-09-21. #1 stays
open: it is where the repository owner reviews `think-budget` itself, and it is
not a review surface for this repo either.

`#16820` (`/api/tokenize`) is carried here but is **not in the manifest** and
never will be: it is somebody else's upstream PR, merged from `pull/16820/head`,
so no branch in `mann1x/ollama` is its home. It is tracked only by
`CARRIED-PATCHES.md`.

## The drift on `004-reasoning-budget-line-boundary.patch`

Measured here on 2026-09-22, not taken on report, because the claim that
`up-reasoning-budget-line-boundary` (#18212) was a superset turned out to be
true only of the residue:

| | #18212 | `think-budget` | this tree |
|---|---|---|---|
| lines in the patch | 825 | 945 | 825 |
| touches `common/arg.cpp` | yes | **no** | yes |
| `reasoning-budget-scope`, `THINK_BUDGET_SCOPE` | 2, 1 | 0, 0 | 2, 1 |
| `forced` | 33 | **62** | 33 |
| `end_offset`, `_apply`, `reset_tokens` | 0, 0, 0 | **2, 3, 10** | 0, 0, 0 |

So the two have drifted in **both** directions, and this tree has #18212's side
of it exactly. What we do not have is `b4c58eee` — the fix for a spent response
repeating its wrap-up message, measured by the fork at 32 identical 240-character
copies in one turn. Its identifiers (`forced_end_pos`,
`common_reasoning_budget_end_offset`, `common_reasoning_budget_apply`) appear
nowhere on #18212 under any spelling, so it is genuinely absent rather than
renamed.

**Ruling: the llama.cpp half belongs on `up-response-scope-think-budget`, not
on #18212 and not left on `think-budget`.** That branch is already the fork-only
home of this feature's Go half, already stacked on #4+#8+#14, and already last in
apply order. Putting the C++ there closes the drift without rewriting an open
upstream PR's head, and leaves #18212 as what it should be: the upstream-facing
patch, with the `--reasoning-budget-scope` CLI flag that ollama does not use
because it sets the scope per request over the wire.

Two things follow:

- `ca2e2cdb` ("port to llama.cpp b10242") is almost certainly obsolete, the way
  `b002feda` was. This tree pins **b10969** (`LLAMA_CPP_VERSION`), and #18212's
  patch is the one that applies to it. Check it against the pin before carrying
  it; do not port backwards.
- Once the C++ moves, `think-budget`'s copy of the file must equal the replay of
  #18212 plus that branch's delta. That is checkable with a diff, and it is the
  test that says the drift is actually closed rather than moved.

**This cannot be verified by the Go gates.** A `.patch` is applied by
`cmake/apply-git-patches.cmake` through `FetchContent`'s `PATCH_COMMAND`; every
Go check passes on a tree whose patch is mangled. Worse, the applier is
idempotent: it skips anything `git apply --reverse --check` accepts, so on a
tree that already carries the old version of a patch the new one is skipped
rather than rejected. Only a **clean fetch** verifies it.

**Done, 2026-09-22.** Clean fetch of revision `391fac164` (b10969) applied
`001`, `models/003`, `004` and `005`; the union was checked by identifier, not
by line count. The end-to-end repro then ran on the 3090 in two arms differing
only in `llama-server`, `libllama-common.so*` and `libllama-server-impl.so`:
**thirteen before-arm runs across two models, seven budgets and two prompts
written to coax a reopen, and every one produced exactly one wrap-up copy.** The
32-copies behaviour does not reproduce here. That is not a refutation of
`b4c58eee` — no model reopened its thinking block, so the repro never reached
the path the fix guards — but it is what the fork asked to be told. Numbers,
arm provenance and the lane in `CARRIED-PATCHES.md`.

## Open items

- **Manifest at 18 patches**, all merged here; shas in `CARRIED-PATCHES.md`.
  The first stacked patch (`up-response-scope-think-budget`) exercised the
  amendment and the widened invariant held.
- **Three orphans found by looking at one feature**, all on `think-budget` with
  no `up-*` home: `677f91ce`, `b4c58eee`, `ca2e2cdb`. The fork has offered to
  sweep `think-budget` for every commit touching a file no branch carries —
  **accepted**. R2 stops new orphans; it does not find the ones already there.
- **Orphans point both ways.** `060144ab` was authored in xollama on an upstream
  file and never sent to the fork. The sweep should have a counterpart here: any
  xollama commit touching a file that exists at `v0.34.2` and is not part of a
  marked hook is a candidate for the same treatment.
- **The 004 end-to-end verification is closed** (2026-09-22) on the gate that
  matters, and open only on a model-level repro that has never fired here.
  `test-reasoning-budget` built and run against **our own** clean b10969 fetch
  carrying the merged 982-line patch: **14/14**, including
  `spent response scope closes quietly` and
  `spent response scope bars reopening`. The model-level side is a null result
  over two rounds — 19 before-arm runs across three models and both reset
  routes, one wrap-up copy every time, never a second block.
- **One remaining question, and it is the base.** Two hypotheses I raised are
  dead, both answered by the fork with evidence:
  - *harness-shaped* — **wrong, do not repeat it.** Their observation was a
    single `/api/chat` with no tools and no round trip, so it was the model
    reopening on its own.
  - *the guard defends a path b10969 no longer takes* — **wrong.** Reverting the
    two behaviours fails `tests/test-reasoning-budget.cpp:367` on b10969, so the
    sampler still re-enters `FORCING` on a second start tag. What a base change
    could alter is whether a model *emits* that tag, not whether the path exists.

  That leaves **b10434 → b10969**. Their two observations are different
  symptoms either side of an intermediate fix, not one defect at two sites:
  **08-17** is the 32-copy loop (pre-`b4c58eee`), **08-18** is the residual —
  loop gone, one copy in `thinking`, one *further* copy leaking into `response`
  and cutting the answer mid-word with a trailing `</think>`. Our before arm is
  pre-both by grep, i.e. the 08-17 configuration, and 32 copies did not happen
  on b10969.
- **#15–#17 do not go upstream.** Settled 2026-09-22 by the repository owner,
  who told the fork directly. `fork-only` with `upstream_pr: null` is their
  final state, not a placeholder, so the manifest invariant
  `fork-only ⇔ upstream_pr: null` holds for them permanently and the `note`
  asking for the status to be revisited can go. This also settles the general
  question raised with them: **xollama does not file upstream PRs, and does not
  ask the fork to file them on its behalf** — that decision belongs to the
  repository owner in every case.
