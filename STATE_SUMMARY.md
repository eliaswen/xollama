# xollama — State Summary

Newest entry first. Each entry is dated and says what changed (commit shas,
release tags, measurements) and what is left. The fixed sections below the
entries are rewritten in place so they always describe *now*. Plans are
indexed in [`plans/MASTER_PLAN.md`](plans/MASTER_PLAN.md).

> **2026-10-10 — Upstream v0.40.2 synced (fork manifest `5a7be425`, llama.cpp still b11351, no runtime rebuilt, engine c11 r2 unchanged).**
> - Owner: "promote it, then move to v0.40.2". `sync/upstream-v0.40.2`, in its own worktree (no branch in two worktrees).
>   - `9402f3a5` merged the tag (6 commits, 5 files). One conflict: `README.md` keeps ours.
>   - Upstream: `xollama launch claude` sets `CLAUDE_CODE_MAX_CONTEXT_TOKENS` for a cloud model and keeps a user's `CLAUDE_CODE_AUTO_COMPACT_WINDOW`; `/api/tags` lists a manifest list's selected child only and hides the downgrade guard tag. With `opencoti-first` the selected child is the GGUF one, as before.
>   - No change in `model/parsers`, `model/renderers`, `thinking`, `template`, `harmony`, `llm` or any digested path.
> - The fork's 24 patches followed as `--no-ff` merges at the manifest's shas (table in CARRIED-PATCHES). Same `git patch-id` set as the v0.40.1 copies for every one, compared before the loop; each merge leaves the tree as its first parent. Parsers, `thinking`, `llama/compat`, `llama/server`, `llama/clef`, `LLAMA_CPP_VERSION`, `MLX_VERSION`, `MLX_C_VERSION` byte-identical to the fork. All 12 upstream PRs still open.
> - Pins (`080cfbe3`): both inputs digests unchanged (`d0cc3cdd…`, `e7259fe5…`), so the Windows CPU runtime pin does not move and the fork's `v0.40.2-thinkbudget` carries the v0.40.1 runtimes byte for byte: the Linux amd64 and arm64 rows change their tag only. New bytes: upstream v0.40.2's GPU tarballs (amd64 `726bee78…`, mlx `74d4583c…`; arm64 `92b3ef3d…`, jetpack5 `fb12be57…`, jetpack6 `69c89b78…`) and the macOS MLX archive (`171d8c13…`). The Windows MLX reldir zip is the v0.40.1 file under the new tag (`31c743bd…`, already checked on eleven2go).
> - Checks on the branch: gofmt silent, `go vet ./...` clean, `go test ./...` 71 ok / 0 failed, lint 0, 43 hooks registered, compat-origin 0 foreign. `scripts/docker-assemble.sh` on the new pins passed sha256, inputs and provenance. Live on solidPC (`/srv/ml/xc11/sync402/boot.log`, the assembled payload as `ollama` on 22498, scratch store, 512 tokens, two runs): opencoti c11 gemma4:e2b 137 to 139, qwen3.5:2b 126 to 143, gemma3:4b-it-qat 102 tok/s; stock llama.cpp 129 to 134, 128 to 129, 100 to 101; 0 crash lines, 0 foreign files.
> - Merged into `dev` as `1f421b875`. Security check on it: Dependabot 99 open (was 99), govulncheck 0 reachable, no alert on a line the fork changed against v0.40.2.
> - Gates of an upstream sync on `dev` (`4c0dfdd33`). solidPC (`scripts/gates/linux-all.sh`, `/srv/ml/xc11/sync402/linux-all.log`): G3 compat 8/8, llama3 77.2 to 77.9 tok/s, four slots 308.3, Gemma 4 right, 70B overflow 3.05; G4 decision 0 stock loads, chat paths all pass, 0 refusals; G6 speech 8/8, video 33/33 twice; G5 council PolyKV 4/4 (5 pools, 0 refusals), no-PolyKV and idle pass (35 kv refusals, waited out). The `:dev` image (run 38070351517): G10 amd64 opencoti 85.7 to 85.9, llama.cpp 86.0 to 86.2, speech 4/4, `PAYLOAD` names v0.40.2-thinkbudget and upstream v0.40.2's archives; G10 arm64 on the Pi 9.9 to 10.0 against 10.9 to 11.0, speech 3/3, the owner's containers up; G7 38.8 to 39.0 tok/s on the integrated GPU with the host quiet (load 3.8), which settles the 27.6 to 37.5 of the afternoon as host load.
> - Left: `v0.40.2-rc.1.xollama` (PR opened next): G2 on its PR, then G9, G11 and G12 on the published candidate. The new bytes it carries are upstream's Windows GPU backends and the macOS MLX archive.

> **2026-10-10 — `v0.40.1-xollama.1` is promoted (owner, 18:39: "promote it, then move to v0.40.2").**
> - Before it, the step still owed: the macOS in-app update (`scripts/gates/mac-update.sh`, new in the repository, `T=0.40.1-xollama.1`). The installed `0.40.0-rc.1.xollama` app found the pre-release, "update checksum verified", "bundle passed verification", a hidden start applied it: server and bundle `0.40.1-xollama.1`, codesign ok, notarized Developer ID, staple valid, 129.6 to 130.0 tok/s. The script's wait counted log lines from before the app rotated its log and ran out its 10 minutes; it now reads lines by timestamp.
> - `gh release edit v0.40.1-xollama.1 --prerelease=false --latest` at 18:51. Discord announced (run of 16:51Z, success). The image workflow was run on the tag again (run 38069341248) so `:latest` moves.
> - `:latest` moved: `mannixita/xollama:latest` = `0.40.1-xollama.1` (`1cb73481…`), `ghcr.io/mann1x/xollama:latest` likewise (`29f5ccd9…`), run 38069341248.
> - The drafter-dropped field for `show`/`ps` comes with opencoti c12 (stage 32.2, owner and opencoti's receipt on #958); nothing to do here until its shape is mailed.
> - Next: the sync to upstream v0.40.2 on the fork's manifest `5a7be425` (mail #926), then `v0.40.2-rc.1.xollama`.

> **2026-10-10 — `v0.40.1-xollama.1` is built and published as a pre-release (not promoted): opencoti c11 r2, the Spark and Thor library, Mesa's Vulkan drivers in the image.**
> - PR #20, merge `9c8a7b392`, run 38063943913 green; hosted test legs all pass after `a7f749831` (the macOS leg had failed on the host-architecture reading, bug-261). The name is the owner's choice: a candidate is refused once `v0.40.1-xollama` is published.
> - G12: 8 files match `sha256sum.txt`; payload id `f5836840…` (changed, so the full installer). Image `0.40.1-xollama.1` = `:dev` (`8b497ce6…`, amd64 + arm64), `:latest` unmoved (`4acba360…`).
> - eleven2go, full check: `xOllamaSetup.exe` over `0.40.1-xollama` exit 0 in 31 s, version and payload id right, 11434 untouched. Installed server: 3090 CUDA 124.7 to 125.0 tok/s; 9070 XT Vulkan 100.4 cold, 102.9 to 103.0; integrated 4.9 to 5.0; 37/37 layers each; all three display devices OK. The side binary and engine directory of the pin gates are removed.
> - Mac mini, the workflow's app (`mac-ci.sh`): notarized Developer ID, staple valid on app and DMG, `qwen2.5:1.5b` 124.2 to 129.0, `llama3` 31.8 to 32.0, speech 7/7 answered, 0 crash lines.
> - The tagged image: G10 amd64 opencoti 85.7 to 85.8, llama.cpp 85.8 to 85.9, speech 4/4; arm64 on the Pi 10.0 against 10.9 to 11.0, speech 3/3, the owner's containers up. G7 (iGPU through the image): 27.6 to 37.5 tok/s over two runs with solidPC loaded by other tenants (load average 11 to 19; the iGPU shares the CPU's memory), 38.8 to 39.0 on the same engine two hours earlier; 29/29 layers, polls 200, 0 crash lines.
> - **Promotion is the owner's.** Left after it: the sync to upstream v0.40.2 (fork mail #926), then `v0.40.2-rc.1.xollama`; surfacing the engine's "drafter DROPPED" in `show`/`ps`.

> **2026-10-10 — The engine pin moves to opencoti c11 r2 (`2610101328001`), and the arm64 CUDA library for DGX Spark and Jetson Thor is taken, built blind. For `v0.40.1-rc.3.xollama`.**
> - Pin: index `322fae03…`, pins rev `b14e609d…`; engine `2610101328001`, cuda `2610100758001`, cuda12 `…002`, sbsa `…003`, vulkan `2610100032004`, macos `…005`, media `2610071902001` unchanged, ABI ggml `ea73e6b2…`. r2 is the first c11 cut plus patch 0613: the first cut aborted loading Qwen3.5 0.8B/2B/4B when the fit streamed a host tail (bug-3999, `GGML_ASSERT(ggml_is_padded_1d(a))`), found by our G3 (compat 7/8). The libraries are byte-identical to the first cut.
> - **`sbsa` (owner: "we build it blindly, untested").** `ggml-cuda-sbsa-aarch64.so`, 347 MB, staged beside the engine on linux/arm64, so in the arm64 image. `Pin.SBSASASS` (110 121) and `Pin.HostCUDASASS`: on aarch64 `CoversCUDA` reads the sbsa list and its 121 matches compute 12.1 exactly (`sm_121a`); 11.x is served, Orin 8.7 and everything else stay on stock llama.cpp. Guard `TestTheSBSAComponentServesAarch64WithItsOwnSASS`. Neither opencoti nor we have run it; the docs and the notes say so and name `XOLLAMA_ENGINE=llamacpp`. Upstream ships its own CUDA 13 build for these machines (that is what stock serves here) and has open Spark reports (#15318, #17596).
> - **bug-260 on c11** (`/srv/ml/xc11/r2/fit16-r2.out`, 3090 held to 14984 MiB free, 45k-token prompt): the engine measures the head after load and drops the drafter when that makes the window resident. Two boots, both `assistant drafter DROPPED`, 54.2 to 54.9 tok/s (no drafter 51.4 to 54.1; c10 r3 with the drafter 3.1 to 3.4). Open: the decision sits on about 150 MiB of boot-to-boot variation (opencoti c12), and `show`/`ps` still list the drafter as attached.
> - Gates on r2, tree `792521c52` plus this change. G1: gofmt, lint 0, 43 hooks, compat-origin 0, `go test` of llm, discover, server, cmd, envconfig, types ok. **solidPC** (`scripts/gates/linux-all.sh`, `/srv/ml/xc11/r2/linux-all.log`): G3 compat 8/8 (`qwen3.5:2b` loads), llama3 76.7 to 77.6 tok/s, four slots 302.8, Gemma 4 tool call and thinking right, 70B overflow 3.73; G4 decision same scores as c10, 2 opencoti loads and 0 stock, chat paths all pass, 0 refusals; G6 speech 8/8, video 33/33 frames twice; G5 council PolyKV 4/4 (5 pools, 0 refusals, 0 crashes), no-PolyKV pass, idle pass (45 kv refusals, waited out). **eleven2go** (side binary, engine staged from the pin): 3090 CUDA 123.0 cold, 124.7 to 124.9; 9070 XT Vulkan 100.2 cold, 102.8, 103.6 after 120 s idle, polls 200, card OK, no dump; kill test on the 3090, engine gone in 831 ms; integrated 5.2, 37/37; speech 4/4; 11434 untouched. **Pi 5** (`pi-image.sh`, the engine replaced in `ghcr.io/mann1x/xollama:dev`): opencoti 10.0, llama.cpp 10.9 to 11.1, speech 5/5, 0 crash lines, the sbsa library beside the engine does nothing there, the owner's containers up. **Mac mini** (`mac-engine.sh`, a server built from this tree, the engine through `ape` on Metal, ABI matches): `qwen2.5:1.5b` 123.4 to 127.2, `llama3` 30.8 to 31.8, 29/29 and 33/33 layers, speech 7/7 answered (the OuteTTS narrator as "shoot", as in the baseline), 0 crash lines.
> - **Found by the release PR's macOS test leg (#20), fixed before the build:** the sbsa change read the architecture of the running binary, so a question about linux/amd64 got the host's answer on a Mac (3 tests failed) and on an arm64 builder (6, under qemu). The platform is now carried: `cudaArch(p)`, `Pin.CoversCUDAOn` / `CoversCUDA12On` / `CUDASASSOn`, and `coveredByCUDA13`, `needsCUDA12`, `cudaPayload` take the `Platform`. Routing on the gated hosts is unchanged (x86_64 and aarch64 answer as measured); tests pass on amd64, on the Mac mini and as linux/arm64 under qemu.
> - Gate scripts: `pi-image.sh` takes `TAG=` and `BASE=` (it named build b140); `mac-engine.sh` is new (G11 before an app exists); `engine-ab.sh` makes its output directory for the `ollama` user.
> - On the `:dev` image of `5cd88a68f` (run 38058625153, `ghcr.io/mann1x/xollama:dev`): G7, the Renoir iGPU through the image's Mesa drivers, 38.8 to 39.0 tok/s, 29/29 layers, polls 200, 39.0 after them, 0 crash lines. G10 amd64: opencoti 85.4 to 85.8, llama.cpp 85.7 to 86.2, speech 4/4. G10 arm64 on the Pi: 10.0 to 10.1 against 11.0, speech 3/3, `PAYLOAD` names the sbsa library, the owner's containers up.
> - The two-GPU KV fix (bug-3957) on r2, eleven2go, `qwen2.5:32b` Q6_K over the 3090 and the 9070 XT on Vulkan at `-c 65536`: 23.4 to 23.5 tok/s at 8k, 19.5 at 32k (c10: about 5); "KV on 2 devices: the window is sized on each against its own memory"; card OK.
> - **The next build is `v0.40.1-xollama.1` (owner, 2026-10-10 16:40).** `v0.40.1-xollama` is published (a pre-release, not promoted), so the workflow refuses `v0.40.1-rc.3.xollama`: a candidate sorts below it. Asked; the owner chose the protocol's re-release: cut from `dev`, published as a pre-release, full check, promoted as the same bytes only on the owner's word. Security check before the PR: Dependabot 99 open (was 99), govulncheck 0 reachable, no alert on a line the fork changed.

> **2026-10-10 — The image carries Mesa's Vulkan drivers, so an AMD or Intel GPU works in a container on a host whose own drivers the engine refuses; the Linux gates run from the repository on the tree's pin.**
> - Owner: "a lot of people have my same issue, they are forced to use their igpu or gpu thru a docker container". `Dockerfile.xollama` installs `mesa-vulkan-drivers` (Ubuntu 24.04, Mesa 25.2.8); the host passes `--device /dev/dri/renderD12x` and needs only its kernel driver. The image had the Vulkan loader and no driver, as upstream's has.
> - Measured on solidPC's Renoir iGPU (host RADV 20.3.5 and amdgpu-pro 20.40, refused by the engine since c10), a test image = the local `:dev` plus the package: listed as Vulkan on opencoti, `qwen2.5:1.5b` 38.3 to 38.9 tok/s, 29/29 layers, `props` and `kv` 200, 0 crash lines. With no device passed nothing is listed (llvmpipe is never a GPU); with `--gpus all` as well, the 3090 (CUDA) and the iGPU (Vulkan) are both listed. Image size 5.89 to 6.17 GB. Not yet run on a published image or on arm64.
> - G7 now runs through the image (`scripts/gates/vulkan-linux.sh`, `IMAGE=`): on the host it could only show the refusal.
> - Gate scripts: the Linux ones named an engine build, a run directory and a shared store of the day they were recorded; runs were made from copies, and a copy printed FAIL for `clef-flash` listing `decision` and `vision` (correct since upstream v0.40.0, already fixed in the repository). They now stage the engine from `llm/engine/pin` (`serve-side.sh`, `side.sh`), take scratch stores from the environment, and `linux-all.sh` runs G3 to G6. `decision.sh` and `chat-paths.sh` were run from the repository on the c11 engine: all pass.
> - On the published image (`ghcr.io/mann1x/xollama:dev` of `cb6b910b0`, run 38049316908): G7 37.8 to 38.9 tok/s, 29/29 layers, polls 200, 38.9 after them, 0 crash lines. On the Pi (G10, arm64, same image): opencoti 10.0 to 10.1 tok/s, llama.cpp 11.0, speech 3/3 transcribed back, 0 crash lines, the owner's containers still up: the package changes nothing there.

> **2026-10-10 — `v0.40.1-xollama` is built and published as a pre-release (not promoted). A drafter on a card the model nearly fills is much slower at depth: engine, opencoti mailed.**
> - `v0.40.1-rc.2.xollama` (PR #18, run 37996838303): 8 files match `sha256sum.txt`; image `0.40.1-rc.2.xollama` = `:dev` (`892787d1…`, amd64 + arm64), `:latest` unmoved. eleven2go: `xOllamaUpdate.exe` over rc.1 exit 0 (payload id `10ffa638…` unchanged), 3090 CUDA 123.7 to 123.9 tok/s, 9070 XT Vulkan 103.1, integrated 5.4, 37/37 layers, 11434 untouched.
> - `v0.40.1-xollama`: empty commit `3e4ddda7a`, PR #19, "tree matches v0.40.1-rc.2.xollama", merge `fc4dcccf2`, run 38000052216 green. Short check: 8 files match, `xOllamaUpdate.exe` over rc.2 on eleven2go exit 0, version and payload id right, 3090 122.4 and 123.6 tok/s at 512 tokens. **Promotion waits for the owner** (the finding below; opencoti c11 is being cut tonight).
> - **bug-260, the owner on pandorum (RTX 5080, 16 GB):** `v9-agentic_std12_tb:q4km-64k-mtp` at 12 to 19 tok/s at any context. The engine's KVarN sizer holds `fit target + 824 (assistant head) + 1000 (SWA ring at F16)`: 2491 MiB with the head against about 2170 free, so the record budget is 0, 1 of 500 groups is resident and the rest are read from host memory. Without the head the hold is 1667 and the cache is fully resident (85 to 122 tok/s). Short prompts stay fast (203 to 206), which is why the 3090 measurements missed it.
> - Reproduced on solidPC with the 3090 held to 14984 MiB free (`/srv/ml/xc10/drafter/fit16.sh`, 45k-token prompt): 54 tok/s without the drafter, 3.1 to 3.4 with it. A stated `LLAMA_ARG_FIT_TARGET` (741, 512, 256) does not help: the 824 is added on top. No operator setting lowers the hold; the fix is opencoti's (mails #939, #940). The head takes 485 MiB and the ring 736, so 603 MiB are held and not used.
> - Stated as a known issue in the release notes. The drafter attached to the base tag on pandorum during the candidate check was detached again.
> - Session admission (owner's ruling: lose the idle lead's cache at once, not after 5 minutes): Cerebriline told to close its idle lead through `/api/engine` and to send side calls with a `placement` (mail #936); opencoti takes "the refusal says the holder is idle and when it is released" as c12 row 31.1, feature `kv_reservation_idle_v1` (#937, #938).
> - **Owner, 2026-10-10 07:31: not promoted; wait for opencoti c11 and make `v0.40.1-rc.3.xollama` on it.** opencoti fixes bug-260 in c11 before its cut (patch 0610 `fit-head-exact`, engine `2610100625001`, mail #942: the SWA ring is built first, the head is measured after it loads and the KV is rebuilt against the real numbers, the sizer warns on a collapsed budget); no safe setting exists on c10 r3. The pin moves on our own run of `fit16.sh` and the engine gates.
> - Cerebriline (cline `44d942ece`, mail #941) closes its idle lead only for the capped-thinking note and the retrospective; told to read `X-Context-Largest-Admissible` on the 429 and not the refusal text (#944).
> - Left: the sync to upstream v0.40.2 and the c11 pin, on a measurement; a load-time warning in xOllama when the engine reports a record budget of 0 is worth considering once opencoti answers.

> **2026-10-09 — `xollama tweak model` attaches the right drafter and sets its length; a manifest that cannot be read stops blob pruning. After a model was lost on pandorum.**
> - The report: on pandorum (`v0.40.0-xollama.1`), `tweak model v9-agentic_std12_tb:q4km-64k --spec-type=draft-assistant` wrote a driver pin on a model with no drafter, said every setting was one the model could act on, attached nothing, and the model's 16 GB of weights were gone.
> - The loss: upstream v0.40.0 stores named manifests as symbolic links, and that machine refused to follow them ("untrusted mount point"). The rewritten manifest could not be read back, so the prune of the old manifest's layers counted the weights as unused and deleted them. Upstream v0.40.1 stores copies on Windows; rc.1 installed over it repaired 167 manifests and the model was recreated from its GGUF. `v0.40.0-xollama.1`, the promoted release, still carries the path.
> - `prune-guard` (new hook): a named manifest that fails to open stops the prune, nothing is removed. A missing or damaged one is skipped as upstream does.
> - `drafter` (new hook), schema v8:
>   - `--drafter=auto|PATH|hf.co/…|sha256|none` (`draft.head`). `auto` fetches the head published for the model from `ManniX-ITA/gemma-4-<size>-it-assistant-GGUF` and attaches it. The size is read from the embedding width, so a fine-tune is recognised (the v9-agentic merge is 2816 wide, the 26B-A4B head). A head for another size is refused when attached.
>   - `--draft-tokens` (`draft.tokens`): the length; 0 is off and, on opencoti, starts the engine with `--spec-type none` so a built-in head is not loaded.
>   - The driver menu marks this model's driver; a drafter setting on a model without a drafter is dropped with the reason; a run that changes nothing writes nothing.
>   - `xollama show` names the published drafter for a model without one, and the draft length a load will use.
> - Measured on solidPC, RTX 3090, c10 r3, 256 tokens (`/srv/ml/xc10/drafter`): the v9-agentic A4B on coding prompts at temperature 0 is 94 tok/s without and 136–141 at length 2 (acceptance 0.79), 128–136 at 3, 122–140 at 4; on an essay at 0.7 it is 111 at 2, 102 at 3, 95 at 4. So `auto` sets 2. The first table published here used only the essay, and the owner called it low; opencoti's record (mail #929, v7-coder 76.6 → 137.0 at acceptance 0.91) is on in-domain code. Qwen3.6-27B built-in head: 31 to 32 left to the engine, 24 with length 0 (722 MiB less), 24 with policy `off` (head still loaded).
> - Live as `ollama` on the scratch store: fetch from the hub, attach, replace, detach, six rewrites with the weights intact, 0 foreign files.
> - Owner, 22:59: "once done, make a new release with the latest c10 republish". The latest c10 on the hub is r3, already pinned and measured, so the pin does not move. The tree changed after rc.1, so the release is cut as `v0.40.1-rc.2.xollama` (PR #18) and then `v0.40.1-xollama` from its tree. The base stays upstream v0.40.1; the fork's v0.40.2 sync (mail #926) and c11 are the next cycle.
> - Gates before the candidate (VALIDATION.md): G1 clean, security no delta, G3 compat 8/8 on both engines with tok/s at the morning's level on a quiet host, G4 all pass. G8 not run: eleven2go is held by opencoti's c11 gates.

> **2026-10-09 — `v0.40.1-rc.1.xollama` published (pre-release) and checked on every gate: upstream v0.40.1, opencoti c10 r3.**
> - PR #17, G2: 20 pass and 4 skip. The 4 native legs that have no runner were cancelled, with no step failed. Merged as `49677a133`; release run 37884166795 succeeded in every job. Payload id `10ffa638…`; over `.1` an update takes the full installer.
> - G12: every `sha256sum.txt` line OK; the amd64 binary on solidPC and the arm64 binary on the Pi name the tag; the image is amd64 and arm64 on both registries (run 37885287777).
> - G9 on eleven2go, over `v0.40.0-xollama.1`:
>   - The full installer exits 0 in 98 s, with the version, `PAYLOAD_ID` and `/api/xollama` right. The new Windows MLX runtime is fetched (`MLX_ID` `31c743bd…`).
>   - Five 512-token runs of `qwen3:8b` on the installed server: RTX 3090 CUDA 123.4–123.9, RX 9070 XT Vulkan 102.6–103.2, iGPU 5.2. Every layer is on the GPU and the displays are `OK`.
>   - The small installer over it exits 0 in 4 s, starting a new server with the same version.
>   - 11434 is untouched.
> - G10:
>   - solidPC: opencoti 85.4–85.9 tok/s, llama.cpp 85.8–86.0, speech 4/4. `PAYLOAD` names engine `2610090401001`. 0 foreign files in the scratch stores.
>   - Pi 5: opencoti 9.9–10.3 against llama.cpp 11.0, speech 3/3. The owner's containers stayed up, and the test container is removed.
> - G11, the workflow's Mac app: notarized and stapled; `qwen2.5:1.5b` 127.8–128.4 and `llama3` 32.1–32.3 tok/s on opencoti through Metal; speech 7/7; 0 crash lines.
> - Candidates are never promoted. The release `v0.40.1-xollama` would be cut from this tree (empty commit, short check), on the owner's go.

> **2026-10-09 — Engine pin on opencoti c10 r3 (`2610090401001`), measured; `x/net` 0.60.0 for four reachable advisories; the council's continue route no longer repeats its last answer. `v0.40.1-rc.1.xollama` next.**
> - Owner: "rc.1 on c10 r2, opencoti is not doing a good job and extermely late". c11, which carries bug-3957 (0589), waits for a CUDA round that has not started (opencoti #914). So the candidate goes out on the published c10 line, and c11 moves the pin later.
> - The pin is c10 **r3**, published within the hour after r2 (#917; index `0ad2dde5`, pins `b31394f6`). It is r2 (0594: an embedded library unpacks beside the exe) plus 0595 (an unset Windows `HOME` falls back to `%USERPROFILE%`). Neither reaches xollama, because we ship the bare engine with its libraries and set `HOME` ourselves (`engine.PayloadHome`). Every library pin differs from r1 only in its `rev` line, and the ABI digests and features are c10's.
> - Measured (`/srv/ml/xc10/r3`, as `ollama`; numbers in VALIDATION.md and the pin's comment):
>   - G3/G4: the same as r1 within noise, and decision scores identical to the digit.
>   - G6: speech 8/8, video 33/33.
>   - G7: the Renoir iGPU is refused and the load runs on the CPU.
>   - G8 on eleven2go: 3090 123.4–124.1, 9070 XT 102.3–103.2, iGPU 5.0, speech 4/4. The kill test ran with the model on the 3090, never on the 9070 XT.
> - Security check before the candidate: govulncheck found 4 reachable `golang.org/x/net` advisories (GO-2026-6603, -6611, -6612, -6617). `x/net` moved to 0.60.0, taking `x/crypto` 0.57, `x/mod` 0.41, `x/sync` 0.23, `x/sys` 0.48, `x/term` 0.46 and `x/text` 0.42 (every line keeps its `security-deps` hook). After the move, 0 are reachable. Dependabot is at 99 (was 99), with none on a line the fork changed (bug-254).
> - Found by G5 and fixed (bug-255):
>   - The council's `continue` route answered "And if the leak were 20 litres a minute?" with the first turn's 26 min 40 s, in 2 of 6 runs (PolyKV and idle tags). The reply was in the synthesizer's prompt, but the note never named it and the whole record said 26:40.
>   - `continuedNote` now quotes the reply and says the record answered the earlier message.
>   - A replay of the logged failing prompt over 6 seeds: old note 1/6 right, new note 5/6.
>   - G5 rerun: 6/6 PASS, with `continue` taken 4 times and right each time. Guard: `TestTheContinueNoteQuotesTheReply`.
> - `go test ./...` on solidPC (bug-256): the MLX packages fail on this host's environment only. The local `build/` MLX is reached without `LD_LIBRARY_PATH`; upstream's wired-limit test needs a Metal key. The sync's 71 ok came from a worktree with no `build/`, where those tests skip.
> - Left for the candidate: G2 on the PR, then G9, G10, G11 (the workflow's signed app) and G12 on the pre-release. The known issue in the notes is the two-GPU Vulkan KV window (bug-3957, c11).

> **2026-10-08 — Upstream v0.40.1 synced (fork manifest `9acdc12a`, llama.cpp still b11351, `llama/clef` changed, MLX `a59cc231`).**
> - Owner's go. `sync/upstream-v0.40.1`, in its own worktree.
>   - `69a86b8e` merged the tag (7 commits, 21 files). Two conflicts: `README.md` keeps ours, and `cmd/welcome_test.go` drops `TestWelcomeCloudStatus` as upstream did (#18826).
>   - Upstream copies manifests instead of linking them on Windows (#18852). Its `copyManifestFile` already writes through `fsowner`.
>   - New upstream routes `/api/balance` and `/api/usage` proxy the signed-in cloud account.
>   - No change in `model/parsers`, `model/renderers`, `thinking`, `template` or `harmony`.
> - The fork's 24 patches followed as `--no-ff` merges at the manifest's shas (`6b41b4fc` … `f29adbaf`, table in CARRIED-PATCHES).
>   - Each has the same `git patch-id` set as the v0.40.0 copy dev carries, and leaves the tree as its first parent.
>   - From `up-think-budget` on, each conflicted with its own earlier copy and was resolved `-X ours`.
>   - The loop stops on a patch-id difference or a tree change; neither happened.
>   - Parsers, `thinking`, `llama/compat`, `llama/server`, `llama/clef` and `LLAMA_CPP_VERSION` are byte-identical to the fork's `fdfa954d`.
>   - All 12 upstream PRs are still open at the manifest's shas.
> - The inputs digest now takes `llama/clef` (`90516222`, mails 887–889 with the fork). `llama-server` compiles `clef.cpp` in, and upstream changed it (#18777) while the old digest stayed `9defcc44…`. The four sites: `xollama-runtime.yaml`, `xollama-release.yaml` (Windows and Linux) and `docker-assemble.sh`. The new values:
>   - Linux (README excluded): `d0cc3cdd…`, equal at the fork's `d0508358`.
>   - Windows (README kept): `e7259fe5…`.
> - Pins:
>   - Linux amd64 and arm64 runtimes and the macOS MLX archive moved to the fork's `v0.40.1-thinkbudget`, with upstream v0.40.1's GPU tarballs (`90516222`).
>   - Windows runtime `runtime-windows-amd64-b11351-e7259fe5e807`, built by run 37741379732 from `90516222`, sha256 checked on a download (`48e8aeda`).
>   - `scripts/docker-assemble.sh` on the new pins passed its sha256, inputs and provenance checks.
> - Checks on the branch:
>   - gofmt silent, `go vet ./...` clean, `go test ./...` 71 ok / 0 failed, `golangci-lint` 0 issues.
>   - 41 hooks, all registered; `check-compat-origin` 0 foreign.
>   - Live on solidPC: the assembled payload as `ollama` on 22498, on the scratch v0.40 store (never the shared stores), 512 tokens, two runs.
>     - opencoti c10: gemma4:e2b 131 to 133, qwen3.5:2b 130 to 145, gemma3:4b-it-qat 101 tok/s.
>     - Stock llama.cpp: 134 (warm), 127, 101 tok/s.
>     - 0 crash lines; 0 foreign files in the store.
> - Windows MLX pin (later the same morning): the fork's reldir zip for v0.40.1 (`31c743bd…`, fork run 37737304380 from `d0508358`, MLX `a59cc231`; mail #897).
>   - Checked on eleven2go (no cuDNN installed) with a v0.40.1 side server: `qwen3.5:0.8b` on MLX 300 tokens (68 tok/s warm), `embeddinggemma-2` embeds (cos 0.771 near vs 0.524 far), create from Qwen3-0.6B safetensors (316 layers, generates 104.6 tok/s); no panic.
>   - The pin moves to it; every pin is now on v0.40.1, so nothing stands between this tree and a release candidate.

> **2026-10-08 — xo-20 done: one GPU through two backends (a 3090 on Vulkan, alone or split with the RX 9070 XT); a refresh its caller cut no longer starts a cooldown.**
> - Owner's go. `backend-copies` hook (Registry row): while opencoti may serve, discovery keeps the Vulkan copy of a CUDA/ROCm GPU with the same PCI ID; `discover.GPUDevices` still returns one entry per GPU (startup sizing, runner counts unchanged); a load gets the copies only when its pin or the `gpu` policy names a backend, and `applyGPUPolicy` keeps one entry per GPU. The engine's listing now carries PCI IDs (`OPENCOTI_LIST_DEVICE_IDS=1`): the RX 9070 XT and the iGPU on Windows have one for the first time. Measured on eleven2go: CUDA 123.3 unchanged; 3090 on Vulkan by pin or by policy 106.2; spread over 9070 XT + 3090 on Vulkan 92.7 tok/s. Name pin re-read after today's reboot: on the 9070 XT, now Vulkan2. Guards fail on removal.
> - Found and fixed (bug-250): the VRAM-recovery wait after an unload calls the refresh under its own deadline; cut 0.3 s into a listing, the refresh warned and put both backends in a 15-minute cooldown. A cut with less time left than a listing needs is now the caller's: Debug, no cooldown.
> - opencoti and the fork: the inputs digest gains `llama/clef` from v0.40.1 (the fork names the README-excluded value, `d0cc3cdd…`, in PATCHES.json); our four digest sites change in the sync PR.

> **2026-10-08 — `v0.40.0-xollama.1` released and promoted: macOS opencoti only, Windows MLX without cuDNN installed, the free-memory refresh fixed.**
> - PR #16 (merge `4d695c111`, run 37731569137). Full check passed, numbers in `docs/protocols/VALIDATION.md`: the small updater over `v0.40.0-xollama` fetched the new MLX runtime (`MLX_ID` `b715921b…`), RTX 3090 123.1–123.5, RX 9070 XT 102.7–103.0, iGPU 5.7 tok/s, MLX on the installed server 66.7–67.8 tok/s, no refresh Warn in 17 refreshes; the release's signed Mac app has no stock binaries, 127.3–129.6 / 32.3–32.5 tok/s, speech 7/7, `llamacpp` refused. Promoted, Discord announced, `:latest` re-run on the tag.
> - opencoti re-cut its plans (#886): c11 is Ternary Bonsai 2 27B only (new weight types PQ2_0 = 142, PTQ1_0 = 143, a weight rotation at load); the structured refused-device signal is c12 row 27.1 (op-71). The `REFUSED` line stays the interface until then.

> **2026-10-08 — `v0.40.0-xollama.1` opened (owner's go; eleven2go rebooted, the two wedged MLX runners gone with it).**
> - Content: macOS without stock `llama-server` and the Windows MLX reldir runtime; xo-20 stays out. G1 on `e25837bcf`: gofmt, build, tests, lint 0, 40 hooks, compat-origin clean. Security check: Dependabot 99 open (was 99), no alert on a line the fork changed; govulncheck 0 reachable. Snapshot committed.
> - Full check after the pre-release: G9 (the update installer must fetch the new MLX, its `MLX_ID` differs), G11 on the release's own signed app, G12; then promote.
> - Found and fixed for `.1` (bug-249): the intermittent "opencoti free-memory refresh found nothing" Warn (G9, G10, mailed to opencoti as possibly theirs) is ours. The refresh listed CUDA, then Vulkan, under upstream's one 3 s budget; on eleven2go each listing exits 0 in 1.1 to 1.9 s (measured from the logged-in session), so the second was often killed at the deadline ("exit status 1" on Windows) and free memory stayed stale for 15 minutes. `forkRefresh` now lists the backends side by side, and a listing cut by the budget says so. Guards fail on the old code.

> **2026-10-08 — Windows MLX pinned to the fork's build that loads cuDNN beside itself; macOS without stock `llama-server` on dev. Both for `v0.40.0-xollama.1`.**
> - The fork published `ollama-windows-amd64-mlx-reldir.zip` (`b715921b…`, run 37687432548 from `2630dba7`, mail #883): upstream's MLX with `MLX_CUDA_BIN_DIR`/`MLX_CUDNN_BIN_DIR` = `.`. Measured on eleven2go, no cuDNN installed, side server on 22498: upstream's zip panics on `qwen3.5:0.8b` on MLX (`directory_iterator … "C:/Program Files/NVIDIA/CUDNN/bin/x64"`) and the request hangs; the reldir zip generates it (300 tokens, 45.8 cold / 68.3 tok/s warm), `embeddinggemma-2` embeds (768 dims, cos 0.771 near / 0.524 far), and a create from Qwen3-0.6B safetensors imports in 3 s (316 layers, bf16) and generates at 92.6 tok/s. `llama/runtime-pin-windows-mlx.txt` moved to it; installs update to it through the small installer (`MLX_ID` differs).
> - Left on eleven2go by the control run: two MLX runner processes of the side copy (`xo-mlxrel`, PIDs 14096 and 24784) that panicked and cannot be terminated (one thread each, about 2.4 GB on the RTX 3090; `taskkill /F` from the logged-in session: "no running instance"). The installed xOllama and the owner's ollama are unaffected. They go with the next reboot, which is the owner's call. This is upstream's MLX bug that the reldir build removes.
> - `macos/opencoti-only` merged into dev (`d22be5bf1`).

> **2026-10-08 — `v0.40.0-xollama` released and promoted (upstream v0.40.0, opencoti c10); rc.2 checked on every gate first.**
> - Owner: publish the release on c10 overnight. `v0.40.0-rc.2.xollama` (PR #14, run 37698039727, payload id `d413785f…`): G9 on eleven2go full and update installers exit 0, MLX kept by its pinned `MLX_ID` (the download ran in the release job, 1,338 MB), RTX 3090 123.0 to 123.5, RX 9070 XT 102.9 to 103.0 warm, integrated 5.0; G12 every checksum OK, versions on amd64 and the Pi, image amd64+arm64 on both registries, `:dev` moved. Numbers in `docs/protocols/VALIDATION.md`.
> - `v0.40.0-xollama` from rc.2's tree (empty commit, PR #15, `tree matches`, merge `4e4534103`, run 37701523918): same payload id; short check over rc.2 with the small installer, 123.1 / 123.6 tok/s; promoted, Discord announced; the image re-run on the tag moves `:latest`.
> - macOS without stock `llama-server` (owner's go) is done on `macos/opencoti-only` (`f1e438e3f`, `c2efadafd`), not on dev until now: `stockless` and `macos-stockless` hooks, the bundle carries no `llama-server`/`llama-quantize`, a load that misses opencoti (or `XOLLAMA_ENGINE=llamacpp`) is refused with the reason. Measured on the Mac mini from the built bundle: Metal discovered, qwen2.5:1.5b 122.3 and llama3 31.5 tok/s over 300 tokens, no fallback; full `go test ./...` passes there. It goes into `v0.40.0-xollama.1`.
> - Seen again (G9 and G10): a Vulkan "free-memory refresh found nothing" Warn before a load, the load placed right. Looked into next.

> **2026-10-07 — Engine pin on opencoti c10 (release `2610072136001`), measured; a refused GPU is no longer placed on; arm64 runtime repinned.**
> - Owner: when c10 is published, a quick Clef 27B check on macOS, then publish c10, then release. c10-dev snapshot 2 validated first and mailed PASS (#869): G3, Clef/nimble, speech 8/8 with a root-owned `/tmp/audiocpp-gguf` (bug-3955 fixed), Mac Clef 27B, and bug-3954 at the engine on eleven2go: a fresh engine and one that served a request first are identical with the 3090 and the 9070 XT on Vulkan (`-ts 1,1`), where the c10-dev 1 engine differs from token 196 (`scripts/gates/windows-twogpu-engine.ps1`). opencoti published c10 (index `d6078962`): the engine is snapshot 2 plus the version tag, every library the snapshot's file.
> - `llm/engine/pin/` moved to c10 on the release bytes; numbers in the index header and `docs/protocols/VALIDATION.md` ("On opencoti c10"): G3 8/8, 77.26 tok/s, 4 slots 299.7; G4 pass; G5 the PolyKV tag 4 of 4, the other two tags pass; G6 speech 8/8, video 33/33; G8 3090 123.3–123.8, 9070 XT 102.9–103.0 warm, engine gone 1047 ms after a kill; G11 129.3 / 32.4 tok/s, speech 7/7, Clef 27B on Metal. The pin declares `clef_score_v1`: Clef models now run on opencoti (stock loads 0).
> - Found and fixed (bug-246): c10 refuses old AMD drivers (`… is REFUSED:`, RADV ≤ Mesa 20, amdgpu-pro ≤ 2.0.154). On solidPC its listing lists no Vulkan device and exits 1, and xollama took that for a failed listing, kept llama.cpp's view and placed every Vulkan load on the refused iGPU ("Vulkan is not usable on this system"). `discover/opencoti_refused.go`: a listing that refused every device is the engine's answer; the devices are dropped at Warn (driver and `OPENCOTI_VK_ALLOW_OLD_DRIVER` named) and the load runs elsewhere (verified: CPU, 35 tok/s). Line format agreed with opencoti (#878). G7 on solidPC is therefore a refusal check now; Vulkan throughput is G8's 9070 XT.
> - Found (bug-247): the fork's Windows MLX dispatch also rebuilt and re-uploaded `ollama-linux-arm64-runtime.tgz`, replacing the pinned bytes (`f6fcc0c8…`, gone). Rebuilt from the same commit `2630dba7` as `ollama-linux-arm64-runtime-2630dba7.tgz` (`7ad250e8…`) and repinned (inputs unchanged); the fork's uploads no longer replace an existing asset.
> - Gate scripts (`795431af3`): Windows gates run in the logged-in session (`windows-gate-run.ps1`), the Windows speech script finds the pin-format-2 engine.
> - Open: G10 on the `:dev` image of this tree (new arm64 runtime and c10); the fork's Windows MLX build with a relative cuDNN directory (`ollama-windows-amd64-mlx-reldir.zip`, mailed when published; rc.2 ships upstream's zip); the Windows Vulkan device ids need `OPENCOTI_LIST_DEVICE_IDS=1` (xo-20); the owner's macOS `llama-server` removal, unblocked now that c10 carries the Clef head.

> **2026-10-07 — opencoti first on every platform (`opencoti-first` hook); Windows MLX to be downloaded by the installer.**
> - Found on the published `v0.40.0-rc.1.xollama` (Mac mini): `pull qwen3.5:0.8b` took the MLX variant and ran it on MLX, because upstream v0.40.0's `runnerPreferences` puts MLX first on Apple silicon. The registry now publishes qwen3.8/3.6/3.5, gemma4 and the decision models (nimble, tev1, clef, clef-flash) with a GGUF and an MLX variant each; embeddinggemma-2, laya and the `-mlx`/nvfp4 tags are MLX only; safetensors create needs MLX on every OS (upstream dropped GGUF conversion 2026-09-14). Elsewhere upstream already prefers GGUF.
> - Owner: "this must NEVER happen, always opencoti first on all platforms". Fixed by the `opencoti-first` hook (Registry row): GGUF children before MLX on every OS while opencoti is the engine; `XOLLAMA_ENGINE=llamacpp` keeps upstream's order. Verified on the Mac mini: the guard fails without the hook (`[mlx llamacpp ggml]`); a side server from this tree pulled `qwen3.5:0.8b` as `llamacpp gguf` and served it on opencoti `2610050707001`. rc.1 stays as published (a candidate); the next candidate carries the fix. A model already pulled as MLX stays MLX until pulled again.
> - Owner: Windows gets MLX downloaded at install (xo-21), not bundled: installer plus MLX zip would exceed GitHub's 2 GiB asset cap; upstream's own installer has no MLX (the user unpacks the zip by hand).
> - Built (xo-21): `app/xollama-mlx.iss` (`windows-mlx` hook) downloads the archive pinned in `llama/runtime-pin-windows-mlx.txt` (the fork's `ollama-windows-amd64-mlx.zip`, sha256 `c0ea38f2…`, 2.06 GB unpacked) after install, NVIDIA only by default, sha256-checked, kept across installs by `MLX_ID`; the release job's install check forces it. NOT YET COMPILED: the next step is ISCC on eleven2go once opencoti is off it, then the install there with an MLX model run on the 3090.

> **2026-10-07 — Security check in every release; speech gates run the pinned engine; an audio.cpp temp-directory bug found.**
> - Owner: save the Dependabot alerts, keep the last check's results and investigate the delta every release. `scripts/security-check.sh` writes `docs/protocols/security/dependabot.tsv` and `govulncheck.txt` and prints new/gone alerts and any alert on a manifest line the fork changed; `RELEASE.md` step 1 makes it part of every release. First snapshot: 99 open, 98 in `app/ui/app/package-lock.json` (byte-identical to upstream v0.40.0; 10 new since the 88 of 2026-09-25, all in that file), one in `go.mod` (`github.com/buger/jsonparser` v1.1.1, upstream's indirect version, not called). govulncheck on go1.26.8: 0 reachable; four `golang.org/x/crypto` findings in v0.52.0 (the fork's `security-deps` version) fixed in v0.56.0, not called.
> - Owner: the speech check always uses the engine being integrated. `scripts/gates/stage-engine.sh` stages what `llm/engine/pin` names (the build's own fetch); `windows-speech.ps1` takes that directory and refuses any other engine or bytes; `serve-side.sh`/`speech-linux.sh` start on it and need a writable scratch store. Linux run on c9: the engine named itself `build 2610050707001`; OuteTTS 3 of 3; Kokoro, Supertonic, KittenTTS refused, see next. Windows run waits for opencoti to leave eleven2go.
> - Found (mail #857 to opencoti, not worked around here): audio.cpp unpacks into `<temp>/audiocpp-gguf`, one directory for all accounts; a root run left `/tmp/audiocpp-gguf` root-owned on 2026-10-03 and the `ollama` service now fails every Kokoro/KittenTTS/Supertonic load ("cannot create directories: Permission denied"). With `TMPDIR` on a directory `ollama` owns the same request is 200. Same shape as xo-17; on a Linux install the service shares `/tmp` with root. The stale directory stays as evidence.
> - Owner: MLX ships on Windows, Linux and macOS from the c10 release. Linux: the image already takes the fork's `ollama-linux-amd64-mlx.tar.zst` (a `gpu` row of `llama/runtime-pin-linux.txt`). macOS: as today. Windows: upstream's installer excludes `mlx_*` too, and installer plus MLX zip would be about 2.5 GiB against GitHub's 2 GiB asset cap; how to deliver it is open (owner's call).

> **2026-10-07 — `v0.40.0-rc.1.xollama` published as a pre-release (upstream v0.40.0, opencoti c9); every gate passed.**
> - Owner: no new engine snapshot when the sync is done, so deliver a pre-release on c9. opencoti's c10 is still unpublished (a dev snapshot is announced for today).
> - PR #13, dry run 37608537655, merged as `e311046b5`; release run 37621365711 (plan, windows, macos, linux amd64 and arm64, publish all success), image run 37623955010. A candidate, never promoted: `:latest` stays `.4` on Docker Hub and GHCR, `:dev` is this tag.
> - Gates, numbers in `docs/protocols/VALIDATION.md` ("On upstream v0.40.0"): G2 26 pass, 12 skipped; G3 both engines 8/8 and within noise of the baseline; G5 the PolyKV tag 4 of 4, the other two tags pass; G9 full and update installers exit 0, RTX 3090 120.9 to 122.3 tok/s, RX 9070 XT 102.4 to 102.5, integrated 5.0, 16 alternating Vulkan loads 0 failed; G10 amd64 85.6 to 86.0 on both engines, arm64 9.9 to 11.0, speech on both; G11 on the workflow's app 128.4 / 32.1 tok/s and the MLX model 77.0 on the pinned MLX libraries; G12 every checksum OK, payload id `fa784c12…` as tested, versions right on amd64, arm64 and the Mac. The installed `.4` app on the Mac mini updated itself to the pre-release (download kept, so its checksum matched; bundle verified; 129.5 tok/s after).
> - Found: since upstream v0.40.0 a store the server cannot write lists no models (`mkdir …/manifests-v2`), stock v0.40.0 alike. Said in the release notes; `scripts/gates/image-x86.sh` mounted the shared stores read-only and now takes writable scratch stores (`LLM=`, `MEDIA=`).
> - Not run: the Windows speech script, which still names the c8 engine and a side server; G9's steps do not include it.
> - Left: the c10 pin move on a measurement when opencoti publishes it, then the release `v0.40.0-xollama` (Clef on opencoti and macOS, macOS `llama-server` removal, the forced link by `pci=` on Windows, the fork's MLX runtimes); owner's call whether the Windows MLX zip goes into the installer.

> **2026-10-07 — Upstream v0.40.0 synced (fork manifest `d8ec2163`, llama.cpp b11351, MLX `264c14fe`); the engine stays opencoti c9.**
> - Owner: c10 is still cooking (rolling KV window and KVarN bugs), so sync to upstream now and, if no new engine snapshot is out when it is done, deliver a pre-release on c9.
> - `sync/upstream-v0.40.0`, in its own worktree. `c243389b` merged the tag (26 commits, 206 files). Seven conflicts: upstream's manifest-list store against the `store-ownership` hook (`manifest/manifest.go`, `manifest/paths.go`, `server/images.go`), `go.mod`, `scheduleRunner`'s new signature beside the `polykv-window` hook, and two test files (both blocks kept). The council and tokenize callers that hold a model now call `scheduleRunnerForModel`. Three new upstream CLI tests set `OLLAMA_HOST` and were reaching the live server on this host: `XOLLAMA_HOST`.
> - The fork's 24 patches followed as `--no-ff` merges at the manifest's shas (`935b2c3e` … `63a55e8d`, table in CARRIED-PATCHES). All are the v0.35.1 commits rebased (patch id, or range-diff with context only); every merge leaves the tree as its first parent. Parsers, `thinking` and `llama/compat` are byte-identical to the fork's `b47cefb7`; both inputs digests equal the fork's.
> - Pins, each sha256 from a download made here: Linux amd64 and arm64 runtimes and the macOS MLX archive from the fork's `v0.40.0-thinkbudget` (`71814778`); Windows runtime `runtime-windows-amd64-b11351-c5dafb5ce36b` built by `xollama-runtime.yaml` (run 37603747610, `ceae6a04`). The Windows installer still carries no MLX, as before.
> - What upstream changed that matters here. (1) Named manifests live in `manifests-v2/` as symbolic links to a manifest blob; a tag can be a list with one child per runner (`ggml`, `llamacpp`, `mlx`). (2) The first load of an older Ollama-format GGUF (gemma3, gemma4, qwen3.5, mistral3, …) starts a background conversion that writes a second, llama.cpp-format copy of the model into the store and prefers it from then on: measured 13 GB more for gemma4:e2b, qwen3.5:2b and gemma3:4b together, 7 to 14 s each. `list` then shows the tag twice and a `llamacpp:<digest>` row per converted model; the stock v0.40.0 binary prints the same list on the same store, so this is upstream's, not ours. A server stopped mid-conversion leaves a `compat-migrate-*.gguf` in `blobs/` (14.6 GB for mistral-small3.1) until a start more than an hour later prunes it. (3) `clef-flash` now reports `decision` and `vision`.
> - Ours, because of (1): `fsowner.Symlink` hands over the link itself (`lchown`; `TestSymlinkHandsOverTheLinkItself`, checked by removal), and the conversion's temp blob goes through `fsowner.CreateTemp`. A root-run server pulling and copying into an `ollama`-owned store leaves 0 foreign entries. `check-compat-origin` now passes a merge upstream made itself (`1c345795a`); the known offenders in history are still flagged. `.gitleaks.toml` allowlists two GGUF key names in `compatmigrate/` by value.
> - Checks on the branch: gofmt silent, `go build` and `go vet ./...` clean, `go test ./...` no failures (the three `OLLAMA_HOST` tests above were the only ones), `-race` clean on llm, server, parsers, thinking, parser, middleware, council, manifest and compatmigrate, `golangci-lint` 0 issues, 36 hooks all registered, `check-compat-origin` 0. On the Mac mini (unsigned build with the pinned MLX, 1 min 42 s): 76 packages ok, the two `app` packages need the UI built first.
> - Live on solidPC, the assembled image payload (`scripts/docker-assemble.sh` on the new pins) as `ollama`, scratch stores of hard links (never the shared stores, which the conversion would grow): on opencoti c9 and on stock llama.cpp b11351, gemma4:e2b, qwen3.5:2b, llama3 and gemma3:4b answer before and after the conversion at the same speed (145 to 148, 121 to 153, 85 to 86, 100 to 102 tok/s on opencoti; 300 tokens, two runs), and all three vision models name the picture after it. `tweak model` on a converted model writes one manifest on the converted GGUF and the setting reaches the launch. G4: six turns, the OpenAI stream, the tool call and its result pass, 0 refusals; `nimble` on opencoti and `clef-flash` on stock answer `/v1/systemone`, the image question included.
> - Disk: the owner asked for stale test files gone from `/srv/ml`; 85 GB of superseded build stages, caches and image contexts removed (`/srv/ml/xc9/sync40/cleanup-stale.sh`), council tests and their logs kept.
> - Left: G3 and G5 on this payload (running), then the candidate `v0.40.0-rc.1.xollama` with G2, G9, G10, G11 and G12 on what the workflow builds.

> **2026-10-06 — opencoti's findings on the three media failures of the c9 matrix, and what c10 will carry (nothing published yet, nothing changed in this tree).**
> - Correction to the matrix below: the OuteTTS file made on the Renoir integrated GPU was never noise. It transcribes word for word on a CPU Whisper; the listener in my run was Whisper on the same broken driver. A media check on a doubtful GPU needs its listener on another device.
> - Renoir on solidPC (bug-3936): the host's two Vulkan drivers are from 2020 (Mesa 20.3.5 RADV, amdgpu-pro 20.40) and cause all three symptoms. From c10 the engine does not offer them as devices (`OPENCOTI_VK_ALLOW_OLD_DRIVER=1` keeps them). The same GPU works in the container `opencoti-vulkan-radv:24.04` (Mesa 25.2.8, `/srv/dev-disk-by-label-opt/dev/tools/vulkan-radv/vulkan-igpu.sh`): opencoti ran z-image (109 s), Whisper and OuteTTS there. The Linux Vulkan phase of the media gate runs in that container from now on; the Wan clip, flux2-klein and an LLM are not yet run in it.
> - RX 9070 XT video crash (bug-3937, patch 0572, Windows only): a C++ throw inside the Vulkan library (a buffer over the card's 2 GiB limit) ended the process before the library's own catch. Proven by opencoti on eleven2go with a control: the clip completes in 70 s. On c9 there is no workaround for video on an AMD card; `--fa` does not avoid it.
> - c10 also turns flash attention on by default for the image and video engines (a picture at a given seed will differ from c9's), declares images, edit, video and image-to-video for `macos-aarch64` (opencoti ran image-to-video on the Mac mini: 611 s), and carries the Clef decision head (patch 0573, `clef_score_v1`, stock's wire; answers equal stock's on 30 of 30 fields on CUDA, Vulkan, CPU and Metal, 29 of 30 on the 9070 XT where the one field is a near tie; logits are not bitwise equal between any two builds, stock's included). Give `-c` to a decision model. Only Clef Flash was run, not the 27B Clef.
> - Left for this tree at the c10 pin move: `clefEngine` (`server/decision_engine.go`) stops sending Clef to stock once the pin declares `clef_score_v1`, the macOS `llama-server` removal, and the confirmation of Clef on macOS through xollama's own path, which needs a published engine.

> **2026-10-05 — quantized KV (`q4_0`, `q8_0`) is broken on the legacy CUDA 12 library in c8 and c9; the fix comes with c10.**
> - Report: the published `.4` container on a Tesla V100 (sm_70, driver 580.173.02) aborted with "illegal memory access" (`ggml-cuda.cu:3292`) on a 27B model, `q4_0` KV, context 262144, about 62k prompt tokens.
> - Reproduced on the same card from the debug box with the image's own files. 27B, opencoti c9, CUDA 12 library: `q4_0` faults at 5k, 8k, 20k, 40k and 62k tokens and at contexts 32768, 131072 and 262144; `q8_0` faults at 8k; the drafter off changes nothing; below about 4k tokens there is no fault but the text is garbage. `f16` (8k, 62k), `kvarn3` (8k, 62k at 262144) and stock llama.cpp with `q4_0` (8k, 20k) are clean.
> - Cause, opencoti's (bug-3932): since their patch 0483 the CUDA flash-attention allocation skips the f16 conversion space for a quantized KV when the direct quantized read applies, but the tile kernel used on sm_70 and older always converts. That is the whole legacy library (sm_52, sm_61, sm_70); the CUDA 13 library is not affected.
> - Fix, opencoti patch 0565, run here on the V100 beside the reporter's load with `qwen3:8b` at 16384 (the card had 7 of 32 GiB free, so not the 27B): c9 aborts while loading with `q4_0` (2 of 2) and `q8_0`; the fixed library answers sensibly with `q4_0` (8k twice, 230 tokens) and `q8_0`; `f16` is clean on both. `qwen2.5:1.5b` does not show the fault and is no check for it.
> - Speeds on the V100, 27B, 512 tokens, warm, drafter on: `f16` 35.4 to 36.2 tok/s and `kvarn3` 33.5 to 36.5 at 32768 with a short prompt; with 62k tokens in the window `f16` 24.3 to 26.5 at 131072, `kvarn3` 14.3 to 15.0 at 131072 and 13.9 to 14.9 at 262144. KVarN is about 43 % slower than `f16` at depth on this card; reported to opencoti, not examined yet.
> - The reporter's own case, run when the card came free (21:58 to 22:23, engine started with xollama's launch line for the 27B: projector, MTP drafter, unified KV; 61,860 prompt tokens, then 512 tokens four times): c9 with `q4_0` at 262144 aborts after the prefill with the illegal memory access; the fixed library answers every time with no CUDA error: `q4_0` at 262144 34.4 to 40.5 tok/s (25.9 GiB), `q8_0` at 262144 32.3 to 35.6 (30.0 GiB), `q4_0` at 131072 34.7 to 40.5, against `f16` at 131072 36.2 to 40.0 in the same session. So a quantized KV shows no depth penalty on this card, unlike KVarN (opencoti: a chip without tensor cores has no in-kernel KVarN decode for this head size and expands every key per token; a kernel for it is new work). These speeds are with the drafter on and another request text than the earlier ones, and are not comparable with them.
> - Owner, 2026-10-05: the fix ships with c10, not as a c9 library update. Until then a card served by the legacy library (Pascal, Volta, Maxwell) uses `f16` or KVarN, never `q4_0` or `q8_0`. Nothing changed in this tree; the pin moves to c10 on a measurement of the published files, which repeats this case.

> **2026-10-05 — the release workflow builds, signs and notarizes the macOS app (`macos` job); MLX comes from a pin, not a compile.**
> - The owner put the six signing secrets in the repository (`MACOS_SIGNING_KEY`, `MACOS_SIGNING_KEY_PASSWORD`, `APPLE_IDENTITY`, `APPLE_NOTARY_KEY`, `APPLE_NOTARY_KEY_ID`, `APPLE_NOTARY_ISSUER`) with `~/dev/xollama/set-ci-secrets.sh` on the Mac mini, at its Terminal (`gh` over ssh cannot read its token there). First set failed on the runner: the `.p12` was made by Homebrew's OpenSSL 3, which `security import` refuses as "MAC verification failed"; the script now uses `/usr/bin/openssl` and test-imports into a keychain of its own.
> - `xollama-release.yaml`, job `macos` on hosted `macos-26` (macOS 26.6.2, Xcode 26.6, Metal toolchain present; Go installed from go.dev by digest since the image has none on its PATH): a keychain of the run's own, `scripts/build_darwin.sh build sign app`, then Gatekeeper and stapler on the app, the DMG and the app inside the zip, version, Go toolchain, updater feed, the loader's entitlement; `publish` waits for it and checksums both files.
> - Dry run 1 on draft PR #12 (`release: v0.35.1-xollama.5`, run 37313354505): all jobs green, macOS in 42 minutes, three notarizations accepted. Of those, 31.5 minutes were compiling: MLX twice (Metal 3, Metal 4) and llama.cpp. The CI-built app on the Mac mini (`ci-gate.sh`): "Notarized Developer ID" on macOS 27, same file list as the Mac-built `.4`, engine through `ape` on Metal, `qwen2.5:1.5b` 128.7 to 128.9 tok/s, `llama3` 31.8 to 32.0, speech 7 of 7, no crash line.
> - Owner: why compile what upstream and opencoti already publish? MLX no longer is: `llama/runtime-pin-darwin.txt` names the fork's `ollama-darwin-mlx.tgz` (upstream v0.35.1's bytes, `79bd8b87…`) and `build_darwin.sh` unpacks it (`macos-mlx-pin` hook; `XOLLAMA_MLX=compile` is the old path); `plan` refuses a pin whose MLX versions are not the tree's. On the Mac mini the whole signed build went from 7 to 3 minutes; `mlx.metallib` in the bundle is upstream's byte for byte (`178186a2…`), re-signed with our team; an MLX model (`qwen3.5:2b-nvfp4`) loads through `mlx_metal_v4` and gives 77.0 to 77.5 tok/s; G11 as before (128.4 to 128.7, 31.2 to 31.6, speech 7 of 7).
> - Dry run 2 with the pin (run 37320717361, `a1c4f7c60`): all jobs green; the macOS job 20 minutes instead of 42 (llama.cpp for Metal 9 minutes on the 3-core runner, three notarizations about 7, the rest UI, app and DMG); Windows takes 17. That app on the Mac mini (`scripts/gates/mac-ci.sh`): Gatekeeper and stapler accept both files, `mlx.metallib` is upstream's (`178186a2…`), `qwen2.5:1.5b` 128.1 to 128.5 tok/s, `llama3` 31.7 to 31.9, the MLX model 77.3 to 77.5, speech 7 of 7, no crash line.
> - Owner, 2026-10-05: no `.5` is cut, the Mac mini is not made a runner, and the llama.cpp compile waits for c10 (it goes with the macOS `llama-server` removal). Draft PR #12 closed unmerged and its draft release deleted (no tag ever existed). What is on `dev` after `.4` (the three media fixes, the macOS job, the MLX pin) ships with the release on opencoti c10; the fork is not asked for a macOS llama.cpp runtime.

> **2026-10-05 — a media model's device pin is applied, and every media kind was run on each backend with c9.**
> - Defect: `mediaTwin` (`server/media.go`) dropped the model's `devices`, so `tweak model --device-backend/--devices` did nothing for a media model and its engine always took the GPU with the most free memory. The twin now carries the pin and the scheduler's `selectModelDevices` applies it. Guard `TestAMediaModelsDevicePinReachesTheScheduler`. In the tree after `.4`; not in a release yet.
> - Proven on eleven2go with a side build of the tree beside the installed `.4` runtime, server in the logged-in session, every media model pinned by `tweak model`: pinned to CUDA the engines ran on `CUDA0`; pinned to `name:AMD Radeon RX 9070 XT` on that card; with CUDA hidden and pinned to `name:NVIDIA GeForce RTX 3090` on the 3090 through Vulkan. Kokoro pinned to a GPU stayed on the CPU (`--gpu disable`), as intended.
> - Media matrix, opencoti c9, one 512x512 picture each from flux2-klein:4b and z-image:turbo, one edit, Kokoro and OuteTTS speech transcribed back by Whisper large-v3-turbo, one Wan 2.1 1.3B clip (640x352, 33 frames):
>
> | backend | host | images | edit | speech | Whisper | video |
> |---|---|---|---|---|---|---|
> | CUDA, RTX 3090 | solidPC (Linux) | 7 s, 8 s | 5 s | pass | on `CUDA0` | 234 s |
> | CUDA, RTX 3090 | eleven2go (Windows) | 8 s, 8 s | 4 s | pass | on `CUDA0` | 384 s wall, cold weights |
> | Vulkan, RTX 3090 | eleven2go | 30 s, 27 s (cold) | 4 s | pass | on Vulkan | 384 s wall, 139.6 s generating |
> | Vulkan, RX 9070 XT | eleven2go | 10 s, 19 s | 13 to 16 s | pass | on Vulkan | **engine SIGSEGV at `generate_video`, 2 of 2** |
> | Metal, M4 | Mac mini, installed `.4` | 18 s, 25 s | 26 s | pass | on `MTL0` | 1284 s |
> | Vulkan, Renoir integrated (RADV) | solidPC | flux2 78 s; **z-image `vk::DeviceLostError`** | 106 s | Kokoro pass; OuteTTS judged noise by the Whisper on this same GPU (wrong: the file is right, see 2026-10-06) | on Vulkan, **first of two answered 502 (engine gone)** | **`vk::DeviceLostError` at `generate_video`** (a later lone run was still generating after 180 s: not deterministic) |
>
> - Second defect, found because the crashed clips left their clients polling: a video job whose engine exited was dropped, so the status route answered 502 and then 404, never `failed` (my Linux script polled 2400 s). `videoJob.lose` keeps the job for the keep as `failed` / `engine_exited`, content 409. Guard `TestAVideoWhoseEngineExitedIsAFailedJobNotAMissingOne` (fails with 404 without the fix); live on solidPC, engine killed by PID mid-clip: `failed` within 3 s (`/srv/ml/xc9/media/lost-check.sh`). The dead engine also stayed in `/api/ps` until its keep-alive ended: `mediaEngineGone` (`server/media_gone.go`, one `media` hook line in `processCompleted`) unloads an exited media engine as its last request finishes, media keys only so stock llama.cpp is untouched; guard `TestAMediaEngineThatExitedIsUnloadedAtOnce`, live: `/api/ps` empty right after the kill (owner asked, 2026-10-05).
> - Whisper is on the GPU on every backend (its own log line names the device). audio.cpp speech is CPU by design.
> - macOS serves image generation, edit and video on Metal although the pin's `images_*` / `videos_*` rows name only `x86_64 win-x86_64`; opencoti asked to declare them for `macos-aarch64` (owner: the pin should list them). The pin is theirs; nothing was edited here.
> - Left, all engine side and reported to opencoti: the 9070 XT video crash; the Renoir failures (an integrated GPU, never chosen for an unpinned model). Scripts: `/srv/ml/xc9/media/` (`media-all.sh`, `run-linux.sh`, `win-media.ps1`).

> **2026-10-05 — `v0.35.1-xollama.4` is the release: published, checked on every platform and both images, promoted to latest.**
> - PR #11, merge `37ba94ec3` (tree of `f433d0bc4`), payload id `3ac8a57c…` as `.3`, opencoti c9. `.2` + the c9 pin, the Clef routing, the macOS cache folder and the macOS log folder. Dry run first (the first dispatch on the final commit was cancelled by my own edit of the PR text while it was queued; do not touch an open release PR while a dry run waits).
> - Draft, then the published files, eleven2go: small installer over `.3` applied (same payload), full installer, small over full, all exit 0; RTX 3090 123.5 to 123.8 tok/s, RX 9070 XT 102.9 to 103.2, integrated GPU 5.0 to 5.1; speech 4 of 4; installed server 0 failed of 34 Vulkan loads, twice more. Images, `:dev` of the tree and then the tag: amd64 85.6 to 86.0 tok/s on opencoti, speech 4 of 4, both decision models, no crash line; Pi 9.8 to 10.0 tok/s, speech 3 of 3. opencoti kept off eleven2go meanwhile (#810) and was told when it was free (#811).
> - macOS: dmg `0b5b10a3…` and zip `bc61fc45…` attached, both in `sha256sum.txt`. Before the merge the built app was run from `/Applications` on the Mac mini with planted leftovers: our zip, backup and marker removed, a fake stock download kept, logs in `~/Library/Logs/xOllama`. After publication the installed `.3` app updated itself to `.4`. The old shared folder was empty afterwards, fake stock download included: that was `.3`'s own last `cleanupOldDownloads`, the bug; planted again under the published `.4`, a stock download, backup and marker all survived a restart.
> - Promoted with `gh release edit v0.35.1-xollama.4 --prerelease=false --latest`; the Discord announcement ran; `docker-release.yaml` rerun on the tag for `:latest`. `.0`, `.1` and `.3` stay pre-releases (deleting them is the owner's call).
> - Left: the fork's MLX runtimes and the macOS `llama-server` removal come with the release on opencoti c10 (owner, 2026-10-05), with the Clef head; CI macOS job once the six signing secrets exist; the engine fetch still has no retry.

> **2026-10-05 — `v0.35.1-xollama.3` published as a pre-release, checked everywhere, and held: the macOS updater shared its staging folder with a stock Ollama. Fixed for `v0.35.1-xollama.4`.**
> - `.3`: PR #10, merge `f881f06f8`, payload id `3ac8a57c…`, opencoti c9. Dry run first. eleven2go, draft and then the published files: the small installer over `.2` refused (exit 7, the payload differs), full installer and small one over it exit 0; RTX 3090 123.2 to 123.5 tok/s, RX 9070 XT 102.9 to 103.1, integrated GPU 5.0 to 5.2, speech 4 of 4; **installed server, 14 stale signal files in place, 0 failed of 34 alternating Vulkan loads, twice** (`.2` on c8: 5 of about 33). Sent to opencoti as #809; their op-62 is closed on it. `:dev` image of the tree: x86 85.5 tok/s on opencoti, 86 on llama.cpp, speech 4 of 4, `nimble` on opencoti and `clef-flash` on stock inside the image; Pi 10 tok/s. One line matching the crash pattern in the first x86 speech run, its text lost with the container, none in four reruns; `scripts/gates/image-x86.sh` now prints such lines.
> - macOS, the owner's question ("why can't you attach by hand the xOllama-darwin.zip with checksum"): nothing prevented it. `xOllama.dmg` and `xOllama-darwin.zip` built on the Mac mini from `a911136ff` (same tree as the merge), signed, notarized, stapled, attached, both added to the release's `sha256sum.txt`. **The app's own update ran for the first time against a release:** the published `.2` app with `XOLLAMA_UPDATE_PRERELEASE=1` found `.3`, downloaded the zip, `update checksum verified`, `bundle passed verification`; a normal start only offers "Restart to update", a start with `--args hidden` applied it; the app then reports `0.35.1-xollama.3`, passes `spctl` and `stapler`, 128 tok/s on opencoti c9. `docs/protocols/RELEASE.md` has the steps.
> - **Not promoted.** Reading that updater: its stage directory, the backup of the replaced app and the upgrade marker are in `~/Library/Caches/ollama`, upstream's folder. `cleanupOldDownloads` removes everything in the stage directory, so xOllama and a stock Ollama on one account delete each other's staged update, and they share one backup directory and one marker. I reported it and went on; the owner: "this is not harmless, we must use our own cache folder and purge the old installers". Fixed: `~/Library/Caches/xOllama` (`app/updater/fork_stage.go`), and `purgeLegacyStage` removes from the old folder only our own zip and our own backup, then records the upgrade the older build performed. `.3` is the first release with a zip for the updater, so it would have been the first to do this in the field: it stays a pre-release and `.4` carries the fix.
> - Same class, found next and fixed in the same release: on macOS `app.log`, `server.log` and `upgrade.log` were `~/.ollama/logs/`, the files a stock Ollama app writes and rotates at every start. They are now in `~/Library/Logs/xOllama`. The old files are left where they are: they may be the other app's. The source guard (`internal/onboarding/xollama_app_state_test.go`) now fails on both stock names.
> - Left: `.4` (PR #11, dry run, Mac build, merge, checks, the `.3` app updating to `.4` on the Mac mini with the old folder inspected after), promote, `:latest`.

> **2026-10-05 — engine pin moved to opencoti c9 (the Windows Vulkan start fix), and Clef decision models served again: both for `v0.35.1-xollama.3`.**
> - Pin: index `49fa8727`, pins `fe760b73`, engine `2610050707001` = c8 + patch `0560-win-sigfile-exit`; every library is c8's file. Measured, not read from the changelog: eleven2go with the server in the logged-in user's session and 14 stale files in `C:\ProgramData\cosmo\sig`, 34 alternating Vulkan loads per engine, **c8 3 failed, c9 0 failed**. solidPC as `ollama`: compat 8/8, llama3 76.8 to 76.9 tok/s (c8 77.2 to 77.8), four slots 302.1 tok/s (c8 303.8), speech 8/8, video, Vulkan 34.2 to 34.4 tok/s, chat paths, 0 refusals; council passes, one no-PolyKV second turn of four repeated the first turn's answer (three reruns pass: sampling). Pi image with c9: speech all 200. Sent to opencoti as #807.
> - **Bug shipped in `.2`, found on the owner's question about decision models:** a Clef model (`clef`, `clef-flash`; `decision.type = clef`) does not load on opencoti, "wrong number of tensors; expected 549, got 427", so `/v1/systemone` returned 500 for it wherever opencoti serves. `nimble` (scored from token probabilities) was never affected: on c9 "bug" 0.9793 against stock's 0.9778. Fix: `clefEngine` (`server/decision_engine.go`) serves a Clef model on stock `llama-server` while the pin declares no `clef_score_v1` (`engine.HasClefHead`); nothing is refused, and the code stops acting on the pin that carries the feature (opencoti took the head for c10, op-64). Live on solidPC: `clef-flash` text and image answers equal the stock control's. Gate added to G4: `scripts/gates/decision.sh`.
> - Decision models in lists (owner asked): the server reports them with the single capability `decision` in `/api/tags` and `/api/show` (upstream `3b1999d1d`, unchanged here, checked live). **No client filters on it**, in upstream `main`, upstream `v0.40.0-rc3` or here: the desktop picker, the launcher inventory and `/v1/models` list `nimble` like a chat model. A filter in the fork's pickers is the owner's call, asked 2026-10-05, not made.
> - Left for `.3`: Mac dmg from the release commit and its gate; PR, dry run, merge; full check on every platform and both images, with the installed-server Vulkan starts on eleven2go (opencoti's op-62 closes on that); promote; `:latest`.

> **2026-10-05 — `v0.35.1-xollama.2` is the first release: published, checked on every platform and both images, promoted to latest. One known bug shipped by the owner's decision.**
> - PR #9, merge `fbf40c889`, payload id `9702e4d6…`, opencoti c8. Dry run first (a draft from the open PR; its first Windows job died on a Hugging Face download, "Stream error in the HTTP/2 framing layer", and passed on a rerun): the new CI step ran `xOllamaSetup.exe` and then `xOllamaUpdate.exe` on the runner, both exit 0, and the draft's small installer took eleven2go from `.1` to `.2` in 4 s.
> - Checks on the published `.2`: artifact (six checksums, version, amd64 and arm64 on Docker Hub and GHCR); eleven2go: small installer over `.1`, full installer, small installer over it, all exit 0; RTX 3090 123.2 to 123.5 tok/s, RX 9070 XT 102.9 to 103.2, integrated GPU 5.2, speech 4 of 4; amd64 image 85.3 to 85.7 tok/s on opencoti and 85.8 to 86.2 on llama.cpp, speech 4 of 4; Pi 5 image 9.9 to 10.0 and 10.9 to 11.0, speech 3 of 3; Mac mini signed build 128.6 to 128.9 and 31.9 to 32.0, speech 7 of 7 answered.
> - Promoted with `gh release edit v0.35.1-xollama.2 --prerelease=false --latest`; the Discord announcement ran; `docker-release.yaml` rerun on the tag to move `:latest`.
> - **Known bug** (owner, 2026-10-05: "we promote anyway and record it as known bug"; "the fix for vulkan probe will go in c9"): on the installed Windows server a Vulkan engine start fails now and then, "Vulkan is not usable on this system", 5 of about 33 starts on eleven2go; a retry works. Never on a side server over ssh (0 of 32 on c8, 0 of 32 on the previous engine). In the release notes, in `docs/protocols/VALIDATION.md` (G9) and under Known gaps. opencoti's patch 0560 retries the probe and prints the reason; it ships in c9.
> - macOS: the release went out without a macOS download and the owner was told only when they asked, after promotion; "don't skip any platform" had been read as "test every platform". `xOllama.dmg` (Apple silicon, signed, notarized, stapled, built on the Mac mini at `1c9ae505e`, the release's tree `02ce7689`, sha256 `82bf2205…`) was attached to `v0.35.1-xollama.2` by hand and the notes rewritten; the published file's checksum was read back. The updater ignores it: it matches `xOllama-darwin.zip` by exact name. `docs/protocols/RELEASE.md` now makes the disk image part of a release until CI has the signing secrets.
> - Left: pin c9 when it is published and rerun G9's Vulkan starts on the installed server; send opencoti one `--verbose` capture of a failure on c8 (asked in #798); the engine fetch in `cmake/opencoti-fetch.cmake` has no retry, so one failed download fails a release job; `v0.35.1-xollama` and `.1` are still listed as pre-releases (the owner's call whether to delete them).
>
> **2026-10-05 — `v0.35.1-xollama.1` published and NOT promoted either: its update installer refuses every install. A second bug behind the first; fixed, and CI now runs both installers.**
> - `v0.35.1-xollama.1` (PR #8, merge `3d0978f4c`, all 13 hosted checks green, payload id `9702e4d6…` unchanged): artifact OK, both image architectures on Docker Hub and GHCR. The Mac mini build of this tree, signed and notarized: `qwen2.5:1.5b` 128.5 to 129.0 tok/s, `llama3` 31.7 to 31.9, speech 7 of 7 answered, no crash line. On eleven2go the full installer passed (exit 0 in 30 s, version, `PAYLOAD_ID`, 22434, devices).
> - Its `xOllamaUpdate.exe` exits 7, "This update was built against a different inference engine than the one installed", over an install whose `PAYLOAD_ID` equals the release's `payload-id.txt`. Cause: `payloadId` in `scripts/build_windows.ps1` ends with `Write-Output "Engine payload id …"` and `return $id`; a PowerShell function returns both, `$env:PKG_PAYLOAD_ID` became the two joined by a space, and the update installer was compiled against that string. `payload-id.txt` and the installed marker were always right, because the function writes the file itself. Shown on eleven2go with a four-line script (`count=2`). Present since the update installer was added; the `{app}` runtime error had kept anyone from reaching it.
> - Fixed: `Write-Host` for the progress line; `requirePayloadId` stops the build of either installer when the id is not a bare sha256.
> - The net that was missing in CI: the release workflow's Windows job now runs `xOllamaSetup.exe`, checks the installed `PAYLOAD_ID` and version, then runs `xOllamaUpdate.exe` over it, before anything is attached. Two releases went out with a file nothing had ever started.
> - Left: `release: v0.35.1-xollama.2`, dry run first (a draft built from the open PR, its installers tried on eleven2go), then merge, the full check everywhere and promotion. `v0.35.1-xollama` and `.1` stay pre-releases; an install on the pre-release channel that is offered either downloads a small installer that fails or refuses and stays as it was.
>
> **2026-10-05 — `v0.35.1-rc.2.xollama` and `v0.35.1-xollama` published on c8; the release is NOT promoted: its small update installer fails on every machine. Fixed here, to ship as `v0.35.1-xollama.1`.**
> - Candidate 2 (merge `358ec5bf7`, tree `f8e9639e`, payload id `9702e4d6…`) passed every gate on every platform and both images. The release (merge `de3b4851a`, the same tree and payload id, the workflow printed "tree matches") was cut from an empty commit on `dev`, now a written step in `docs/protocols/RELEASE.md`.
> - The release's checks: artifact OK (checksums, the version in the amd64 and arm64 binaries, both image architectures on Docker Hub and GHCR, provenance names c8); the amd64 image on solidPC, `llama3`: opencoti 85.0 to 85.4 tok/s, llama.cpp 85.0 to 85.3, speech 4 of 4; the Mac mini, a signed and notarized build stamped with the release: `qwen2.5:1.5b` 127.2 to 128.8 tok/s, `llama3` 31.4 to 31.9, speech 7 of 7 answered (the known "shoot" for "shot" on the OuteTTS narrator); the arm64 image on the Pi 5, cooled: opencoti 9.6 to 10.0 tok/s, llama.cpp 10.4 to 10.9, speech 3 of 3, the owner's containers up. The Pi throttles: the same image read 5.3 to 9.2 tok/s while it went from 59 to 80 °C, so `scripts/gates/image-pi.sh` now prints temperature and throttle state before and after.
> - **Windows failed.** The short check installs the release over the candidate with `xOllamaUpdate.exe`. It exits 1 after 4 s: "Runtime error (at 1:107): Internal error: An attempt was made to expand the "app" constant before it was initialized." The update-only installer's payload check stood in `InitializeSetup` and expanded `{app}`, which Inno Setup creates later. Every run of that file fails; no release gate had ever run it, the candidates were installed with `xOllamaSetup.exe`. An install on the pre-release channel that is offered `v0.35.1-xollama` downloads the small installer (the payload id matches), it fails, and the install stays where it was: nothing is damaged, nothing updates.
> - The fix: the check is `PayloadRefusal` in `app/xollama.iss`, asked first thing in `PrepareToInstall`, before anything is stopped. Guard `app/updater/installer_script_test.go` (both tests fail against the released script). Measured on eleven2go with Inno Setup 6.7.3 installed there and three installers compiled from the scripts: the released script reproduces the error; the fixed one with a wrong payload id exits 7, the message names `xOllamaSetup.exe`, the server keeps its pid; the fixed one exits 0 in 4 s, `xollama --version` goes from `0.35.1-rc.2.xollama` to `0.35.1-xollama` and a new server listens on 22434.
> - The gate that was missing is written down: G9 and `RELEASE.md` step 7 now run the release's own `xOllamaUpdate.exe` over the full install (`scripts/gates/windows-update.ps1`), so a candidate proves the file.
> - Left: cut `release: v0.35.1-xollama.1` from `dev`, full check on every platform and both images, promote it, move `:latest`. `v0.35.1-xollama` stays a pre-release; whether to delete it is the owner's call. eleven2go currently holds a test install (the release's `xollama.exe` beside rc.2's app), replaced by the re-release's installer.
>
> **2026-10-05 — Engine pin moved to opencoti's c8 release (engine `2610042347001`, mail #795, index `7d7e774b`, pins `8855c5c2`, payload `1523ea1e`); the last known-defect row retired; a council fault found and fixed on the way.**
> - Owner, 2026-10-04 23:26: "proceed to the first release with c8. don't skip any platform or docker image." The pin is now `channel release`, repo `ManniX-ITA/opencoti-llamafile`, tag `c8`. The engine is new bytes: rc.1's source plus patch 0558 (a planned KV rolling window on hybrid models cost speed before any cell left VRAM) and 0559 (the boot line). Its file is named in the release form (`opencoti-llamafile-0.10.5-c8-bare.llamafile`); `TestCommittedPinParses` asked a tag to end in the build id and now asks that of a dev build only. The libraries are the same files as before.
> - Measured on the c8 bytes on every platform (`/srv/ml/xc8`): solidPC compat 8/8, llama3 77.3 tok/s, 4 slots 304, speech 8/8, video 33/33 on both models, Vulkan iGPU 34.7 with `/props` and `/kv` 200, chat paths all pass; eleven2go RTX 3090 123.3 to 123.5, RX 9070 XT 103.2 warm and clean after a 120 s idle, the engine gone 830 ms after its server was killed, iGPU 5.4 to 5.5, speech 4/4; Pi 5 10.0 to 10.2 against llama.cpp 11.1, speech 5/5; Mac mini, signed and notarized, 125.0 to 127.9 and 31.5 to 31.7 tok/s, speech 7/7 answered.
> - `llm/engine_defects.go` is empty. Its one row named opencoti c7 r2 (a model too large for VRAM aborting under the POSITION_WINDOW tactic); on c8 the recipe (70B q3_K_S on the 24 GiB card, 32k, `POSITION_WINDOW mode ON (--kv-residency-mode auto)` in the log) loads, 62/81 layers. The `LLAMA_ARG_KV_RESIDENCY_MODE=head` advice left `docs/xollama/slots.mdx`; the result is appended to `docs/evaluations/phase2-engine-ab.md`.
> - The council fault, ours and also in rc.1: `gate/council-kv3-384k` failed its convened turn with a 429 ("largest admissible 185 < this request's minimum window 258"), 3 runs of 4 on c8 and 1 of 3 on the previous engine. A thinking member with a format has its schema converted by an empty completion (`schemaGrammar`); it named no window, opencoti asked a default one (262144) and the council's owners held the pool. It only happens when the builder gives the planner a think level and only on the first such call of a server process, which is why one passing run had hidden it. Fix: the conversion states `llm.GrammarWindow` (512) on opencoti (`llm/engine_grammar.go`) and the council asks the owner for that room first (`grammarRoom`, `server/council_room.go`). After it: 4 runs of 4, 0 refusals, the owner shrunk by 512 in the three runs that needed it.
> - Not a fault: convened and second turns of 55 to 294 s against 33 s on 2026-10-04. The previous engine with the same binary gave 171 and 294 s; the gate now prints calls, tokens and rate, and the long turns are 10,000 to 14,500 generated tokens at 40 tok/s. The council decides how much to do.
> - The gate docs say so now: `VALIDATION.md` G5 and `RELEASE.md` ask for the PolyKV tag four times on fresh servers; `scripts/gates/council.sh` keeps a log per run (the first failure's log was overwritten by its rerun).
> - Left: `release: v0.35.1-rc.2.xollama` from this tree, its gates on every platform and both images, then `release: v0.35.1-xollama` from the same tree. The candidate's and the release's results are committed after the release, because the release must ship the candidate's tree.

> **2026-10-04 — `v0.35.1-rc.1.xollama` is published (PR #5 merged, `3284571c5`) and passed every gate of `docs/protocols/VALIDATION.md`.**
> - Merged on the owner's word (21:22: merge if all green) with 23 checks passing and 12 skipped on `f27add71a`. The release run and the image run succeeded; the candidate is a pre-release with seven assets and images for amd64 and arm64 on Docker Hub and GHCR.
> - G12, the artifact: every checksum OK, both Linux binaries name the version on their own architecture, provenance names engine `2610041714001`.
> - G9, the installer on eleven2go: exit 0 in 29 s, version and payload id match, `qwen3:8b` at 512 tokens: RTX 3090 123.4 to 123.6 tok/s, RX 9070 XT (pinned by name) 102.9 to 103.0, integrated GPU 5.1, all layers on the GPU, all display devices OK, the owner's ollama untouched.
> - G10, the images: amd64 on solidPC opencoti 85.6 to 85.9 tok/s and llama.cpp 85.6 to 86.1 (`llama3`), speech 4 of 4; arm64 on the Pi 5 opencoti 10.1 and llama.cpp 11.0 to 11.1, speech 3 of 3. The Mac mini has no Docker; the Mac is covered by the signed app (G11).
> - Seen, open: on eleven2go the free-memory refresh before the integrated GPU's load warned "context deadline exceeded" after 504 µs and the load used the old values; the load and the run were fine.
> - Left: opencoti promotes opencoti-llamafile to c8 (asked by mail); then the engine pin moves to the c8 release and `release: v0.35.1-xollama` is cut from the candidate's tree with the short check.

> **2026-10-04 — The gates of a release are written down (`docs/protocols/VALIDATION.md`), and the first release's baseline is recorded.**
> - Owner, 21:22: the first release validates everything; every later release passes only the delta of the previous validation, plus what regressed. `VALIDATION.md` lists gates G1 to G12, each with host, steps, expected result and the last measured baseline, a table from "what the change touches" to the gates it needs, and what is not gated. The scripts as run are in `scripts/gates/`.
> - Added to the baseline on tree `4db0bcedb`: hosted CI 23 pass, 12 skipping; stock llama.cpp control on solidPC compat 8/8, llama3 78.5 tok/s (opencoti 77.4), 4 slots 591 tok/s (opencoti 301; known gap, llama.cpp was 620 on 2026-09-21), overflow 2.9 (3.1); macOS, the bundle signed and notarized from this tree on the Mac mini: `qwen2.5:1.5b` 125.9 to 127.4 tok/s, `llama3` 31.3 to 31.7, Metal library "abi ggml 41ba479c24d7 matches this engine", speech 7 of 7 answered (one OuteTTS voice transcribed back with one wrong word).
> - The Mac mini has no Docker, so the image is not run on macOS; G11 (the app) covers the Mac.
> - Left: G9, G10 and G12 are recorded from the candidate (`v0.35.1-rc.1.xollama`), which the owner allowed to be merged once everything is green; then opencoti's c8 promotion and the first release.

> **2026-10-04 — Engine pin moved to `2610041714001` (opencoti mail #782, index `ad2b7db1`, pins `08990a5c`, payload `771ce08f`); a council no longer asks the engine for its whole window, and the release has a written council gate.**
> - The pin: engine patches 0555 to 0557 (loopback `POST /shutdown`, a parent watch, `OPENCOTI_SHUTDOWN_GPU`, stable device ids with `OPENCOTI_LIST_DEVICE_IDS=1`, and bug-3921: `/props` and `/kv` killed the engine with Vulkan on a glibc older than 2.34). Vulkan `2610041656001` is rebuilt and states its abi. cuda, cuda12, macos and media keep their versions.
> - Measured (`/srv/ml/xb140`, results `pin-b140`): solidPC compat 8/8, llama3 77.4 tok/s, 4 slots 301, overflow 3.1, speech 8/8, video 33/33, Vulkan iGPU 33.5 with `/props` and `/kv` 200 (502 on the old engine), chat paths (six turns, an OpenAI stream, a tool call and its result) with 0 refusals. eleven2go on AMD Software 26.9.2: RTX 3090 123.4 to 123.8 tok/s, RX 9070 XT 100.8 cold and 103.1 to 103.3 warm with a clean idle, a killed server's engine gone in 848 ms, ten shutdown and reopen cycles clean, iGPU 5.3 tok/s 37/37, speech 4/4. Pi 5: engine 9.8 to 9.9 against llama.cpp 10.8 to 10.9, speech 5/5.
> - The council failure was ours, not the engine's. `omni-council-idle` (16k context, default council) answered 503 after two minutes on both `2610040950001` and `2610041714001`: the owner session's first booking asked `num_ctx_min` = the whole window, and the root pool already holds cells of that same context ("largest admissible 16371 < num_ctx_min 16384"). The benchmark tags never showed it because their pool is two windows. Now `firstFloor` (`server/council_polykv.go`): a stated `council.context.floor` is kept as it is; an unstated one asks for the roles' reserve, at most half the window and at least 4096. And a council whose roles may write more than the model's context (`councilOutgrowsContext`) runs that turn without PolyKV unless `council.polykv` is `on`, with a Warn naming both numbers. Guards: `server/council_floor_test.go`.
> - The gate is in `docs/protocols/RELEASE.md` ("The council gate"): the three tags, how to rebuild them, `scripts/council-gate.py` and what to expect. Run on this tree and engine: `gate/council-kv3-384k` three PASS (8 / 33 / 32 s, 5 pools, 0 refusals); `gate/council-kv3-nopolykv` three PASS (9 / 43 / 40 s, 0 pools); `omni-council-idle` three PASS through the unpooled turn (7 / 357 / 7 s, 19 refusals waited out).
> - ROCm against Vulkan on the RX 9070 XT, through the owner's ollama on eleven2go (27B dense): IQ2_M, all in VRAM, 34.6 against 31.7 tok/s generating (+9%) and 922 against 774 prompt (+19%); Q4_K_M, over-committed, 23.9 against 9.3 generating, prompt equal at about 405. Not 50% when the model fits. Mailed to opencoti with the request to put ROCm libraries in the c9 plan.
> - Not measured: macOS on this engine. Not used yet: xollama still ends an engine with `Process.Kill` and does not read the `uuid:` device ids.
> - Left: the candidate build from PR #5 and its checks (installer on eleven2go, `:dev` image on the Pi, the Mac mini); the name pin re-read after a reboot of eleven2go. No merge without the owner's word.

> **2026-10-04 — A GPU is pinned by name where it has no PCI ID (xo-20); the RX 9070 XT drop-off was AMD's driver, fixed by AMD Software 26.9.2.**
> - The driver fault, closed (owner: "we call it fixed"). On eleven2go the RX 9070 XT timed out (live dump 0x141, `amdkmdag.sys+0x1D0FB0`) with display driver 32.0.31041.1004 (AMD Software 26.8.1) whenever several GiB of device-local host-visible Vulkan memory stayed mapped and the queue went idle. Reproduced with a standalone program and no llama.cpp code (`/srv/ml/e2g-9070-dumps/vkidle/`); the same 7 GiB not host-visible was clean, and so was llama.cpp with `GGML_VK_DISABLE_HOST_VISIBLE_VIDMEM=1` (4 idle periods of 4, about 6% slower) against 6 of 6 bad at its default. Updating the iGPU driver alone changed nothing. On 32.0.32015.2008 (26.9.2): the standalone case, stock llama.cpp at its default (103.8 to 104.0 tok/s warm), opencoti `2610040950001` through xollama (103.7 to 103.8) and ten POST `/shutdown` + reopen cycles of `2610041105001` were all clean, one boot. So the orphan, the kill and the clean shutdown were never the cause; the `engine-lifetime` hook stays because an engine should not outlive its server. Not re-run on the new driver: the orphan case, idles beyond two minutes, a second boot. `README.md` names the minimum driver; opencoti has every result (mails #775 to #778) and is asked to state it in its usage doc. Notes and dumps: `/srv/ml/e2g-9070-dumps/AMD-REPORT.md`.
> - xo-20, the pin. Vulkan on Windows gives no PCI ID, and the index moved: the 9070 XT was `Vulkan1`, `Vulkan2`, `Vulkan1` across three boots of one day, and two engines number it differently on one boot. New selector `name:<name>[#n]` (`types/xollama/device_name.go`): case and runs of spaces ignored, within the pinned backend, the bare name selects every device of that name and `#n` the n-th in the backend's order. Accepted in `devices.ids` and as a key of the server's GPU policy (`GPUSettings.Lookup`, `policyFor`); both tweak menus write the PCI ID when there is one and the name otherwise, never the index (`selectorFor`); `tweak server gpu` now lists and sets a GPU without a PCI ID (it could not before), and refuses a forced link on one, since the engine reads links by PCI ID. An index pin still loads and every such load says at Warn that it is positional. No new hook: every file touched is the fork's own.
> - Measured on eleven2go with a build of this tree as a side server (22498): the test tag pinned `name:AMD Radeon RX 9070 XT` loaded on the 9070 XT at `Vulkan1` (98.4 cold, 103.4 tok/s warm, 256 tokens) while the installed server listed the same card at `Vulkan2`; pinned `2` it loaded on what is at 2 there, the iGPU, with the Warn line; `tweak show server` lists `name:AMD Radeon RX 9070 XT` and `name:AMD Radeon(TM) Graphics` beside the 3090's PCI ID. Tests verified by removal (name matching off and the warning off fail three tests).
> - Limits: two identical cards with no PCI ID are told apart only by their order, which can change; the engine's `uuid:` ids (`list_device_ids_v1`, engine `2610041105001`) would fix that and are not in the pinned engine. `priorityOrder` compares two GPUs without their list, so two such twins are both read as the first. A pin by name is refused by a server built before this change, the installed rc.1 included.
> - Also seen: the engine still installed on eleven2go from rc.1 (`2610031615001`) dies opening the iGPU (exit 0xc0000028) with today's iGPU driver 32.0.21045.11001; the pinned `2610040950001` runs it (5.7 tok/s, 37/37 layers). `TestTheCLIFallsBackToTheStockPortOnlyForAnXollama` failed once on solidPC on a port another service holds (8191) and passed three reruns.
> - Left: the pin re-read after a reboot of eleven2go (the acceptance line "measured across a reboot"); `uuid:` ids when the pin carries them; the release candidate still waits on opencoti.

> **2026-10-04 — Engine pin moved to `2610040950001` (opencoti mail #757, index `00e93a0f`, pins `1668127e`, payload `b5dc5d72`).**
> - What is new: the engine (patch 0554) states the interface it was built against and checks a library that states one; a mismatch is refused. Its pin now carries `cache_type_swa_v1` and `log_memory_plan_v1`, so our `llm/engine/pin/xollama.txt` and the consumer-file mechanism are gone. Media `2610040945001` is twelve new sidecars with the statement; macOS `2610041000001` has a new Metal library. CUDA, CUDA 12 and Vulkan keep their versions and bytes with new pin text and do **not** state an interface yet ("abi not stated ... NOT checked"): opencoti rebuilds them for the release candidate, which is what the candidate waits on. The classic dev pin is retired on their side (#758).
> - Parsers: every component now publishes `BUILD_INFO.<component>.md`, so the rename in `Asset.StagedName` and in `cmake/opencoti-fetch.cmake` is gone, and both refuse two components that stage one file name.
> - Measured: solidPC compat 8/8, llama3 76.9 tok/s, 4 slots 299, overflow 3.5, speech 8/8, Wan 33/33, Vulkan iGPU 33.2 to 34.3; Pi 5 engine 10.0 to 10.1 against llama.cpp 11.0, speech 5/5 with the new aarch64 sidecars; eleven2go RTX 3090 123.8 to 124.2 tok/s, RX 9070 XT Vulkan 101.0 to 101.1 warm, Radeon iGPU 5.4 to 5.6, speech 4/4 with all three media DLLs "abi ... matches this engine". The header of `llm/engine/pin/index.txt` has the detail.
> - Not measured: macOS with the new Metal library; the eSpeak path limit on Windows; CUDA 12 (legacy). The `:dev` image has not been rebuilt on this pin.
> - Left: the release candidate waits for opencoti's rebuilt GPU libraries (and now patch 0555, see the entry above); then the install check on eleven2go, the image check on the Pi and the Mac.

> **2026-10-04 — An opencoti engine no longer outlives its server on Windows (`engine-lifetime` hook).**
> - What happened on eleven2go (RTX 3090 + RX 9070 XT + Radeon iGPU): a test server was force-stopped with qwen3:8b loaded on the 9070 XT through Vulkan. Windows does not end a child with its parent, so the engine stayed, orphaned and idle. At 08:28 (engine `2610040710001`, stop 08:28:06) Windows wrote a display watchdog dump `0x141` at 08:28:28, the driver `amduw23g` failed to unload and the card sat in PnP code 31 until a reboot. A kill loop the owner allowed (engine `2610040950001`) reproduced it on its first iteration: stop 10:49:22, `0x141` at 10:49:36 with nothing having touched the engine, the engine then unkillable, the machine frozen and reset by hand.
> - The control: seven loads on the same card each ended by xollama's own unload (the engine terminated at once, server alive): card fine every time. So the trigger is the idle orphan, not the kill. Why the orphan hangs the driver is open with opencoti (mails #759 to #761); the same signature is in the host's logs for 2026-09-28 (stock llama.cpp Vulkan) and three times on 2026-10-01 (opencoti's own runs, also hard stops).
> - The fix on our side: `engine.BindLifetime` (`llm/engine/lifetime_windows.go`) puts every opencoti engine, LLM and media, in one job object with kill-on-close, called from `bindEngineLifetime` (`llm/engine_lifetime.go`) right after the start; a failed binding is a Warn. Stock llama.cpp is untouched. Guards run on eleven2go from a cross-compiled test binary, three times each: `TestAnEngineEndsWithAKilledServer` passes and its control `TestAnUnboundChildOutlivesAKilledServer` shows the orphan without the binding.
> - Not done: the kill loop's forced-stop mode has not been run against a Windows build carrying this hook (no such build yet; the next release candidate's installer is the first). opencoti is building patch 0555 (loopback `POST /shutdown`, Vulkan devices idled and destroyed before exit, a 10 s deadline, the Vulkan `deviceUUID` as a stable device id); xollama will call that route before `Process.Kill()` once a pinned engine advertises `graceful_shutdown_v1`, and the loop is run again then.
> - Also seen: Vulkan device order on that host changed across a reboot (9070 XT was `Vulkan1`, then `Vulkan2`); a model pinned by index was refused by name, as designed, and had to be re-pinned.

> **2026-10-04 — Pin format 2: the engine pin is now `llm/engine/pin/` (our index plus opencoti's component pins, vendored), and the engine moved to `2610040837001`.**
> - opencoti mail #754: the delivery the owner was waiting for, published in pin format 2 only (index `64551cef`, pins `03702be6`, payload `21462d10`). The engine is new (`a936348b` + patch 0553, the load diagnostics opencoti had deferred: an eSpeak data path over the limit refused by name, the real `dlopen` reason printed, a sidecar that is present and cannot be loaded saying so); every library is the same bytes measured with `2610040710001`.
> - The cutover, one commit: `llm/engine/pin.txt` is gone. `llm/engine/pin/index.txt` is ours (`sbsa absent`), `engine.txt`, `cuda.txt`, `cuda12.txt`, `vulkan.txt`, `macos.txt`, `media.txt` are opencoti's byte for byte, `xollama.txt` holds our two measured `feature` rows. `LoadPin` (`llm/engine/pin.go`) and `cmake/opencoti-fetch.cmake` both refuse a vendored pin that is not the one the index names, a component whose `abi` the engine does not provide, and one built for a newer engine. `TestCMakeStagesWhatGoReads` runs the real script per platform against a pin both read.
> - Published names only: `ggml-cuda-x86_64.so`, `ggml-cuda-cu12-x86_64.so`, `ggml-vulkan-x86_64.so` and the Windows DLLs are staged as published, no rename; the engine's Windows row carries the `.exe` name. Every component publishes a `BUILD_INFO.md`, so they are staged as `BUILD_INFO.<component>.md` (told to opencoti). The fetch removes what the classic pin left (`ggml-cuda.so`, `engines/cuda_v12`); it writes a manifest that `scripts/docker-assemble.sh` and the release workflow check the payload against.
> - **CUDA 12 sits beside the same engine.** The second engine copy in `lib/ollama/engines/cuda_v12` is gone: a load on cards only CUDA 12 serves starts the engine with `OPENCOTI_CUDA_LEGACY=1` (`engine.LegacyCUDA`, `opencotiEnvsForStart`, the media runner), and discovery lists CUDA a second time with it. The image is 134 MB smaller. CUDA 12 is legacy and never waits for a card (owner, 2026-10-04).
> - Measured (`/srv/ml/xb137`, results `pin-b137`, as `ollama`): compat 8/8, llama3 76.9 tok/s (77.4 before), 4 slots 301 tok/s (302), overflow 3.8 tok/s; speech 8/8 transcribed back; Wan2.1 and Wan2.2 33/33 frames; Vulkan on the Renoir iGPU 34.0–34.1 tok/s, 29/29 layers; from the restaged build tree with no `XOLLAMA_ENGINE_PATH` 85.5 tok/s over four 512-token runs. The engine loads both libraries by their published names and the CUDA 12 one with the switch ("CUDA 12 legacy library loaded", on the RTX 3090). A codec file that is not an ELF: "it was FOUND but could not be loaded … invalid ELF header". dietpi5, the aarch64 rows in the `:dev` image: engine 9.9–10.1 tok/s, llama.cpp 10.9–11.1 interleaved, speech 5/5.
> - `0bce07ea6`, pushed; PR #5: 24 checks pass, 12 skipped, Windows and macOS test legs included (`llm/engine/pin/.gitattributes` keeps a Windows checkout from converting the vendored pins). The image assembled locally from that commit by `scripts/docker-assemble.sh` (amd64, exit 0, `PAYLOAD` lists every engine file by component): in the container with `--gpus all` llama3 85.5–85.9 tok/s over four 512-token runs on `ggml-cuda-x86_64.so`, Kokoro, KittenTTS and Supertonic return mp3, and there is no `engines/cuda_v12`. opencoti told (#756): parser landed, the `BUILD_INFO.md` name collision, the two feature rows we keep ourselves.
> - Not measured: Windows (the published DLL names, the eSpeak limit of 259) and macOS, which are the candidate's install check and the Mac re-measure; CUDA 12 on a card older than 7.5.
> - Left: a new candidate (rc.2) from this tree, then the install check on eleven2go (owner's word needed), the image check on the Pi and the Mac re-measured; no merge of PR #5 before that. xollama's own error for an unloadable sidecar still says "update the engine" while the engine's log has the real reason. `go test ./...` on solidPC fails in `mlx`, `mlxrunner` and `mlxrunner/sample` on a missing `libnvrtc-builtins.so.13.0`, a host condition.

> **2026-10-04 — Engine pin moved to `2610040710001` (rev `a936348b`): the Windows integrated-GPU crash and the CUDA use-after-free are fixed; measured on solidPC, eleven2go and the Raspberry Pi 5.**
> - opencoti mail #750: patch 0551 (the Vulkan DLL registers the real stack, bug-3913, our #740), 0550 (CUDA use-after-free under multi-slot serving, bug-3777, every CUDA library), 0552 (a library beside the engine wins the lookup), `oc-espeak` with a 4096-byte data path (bug-3912, our #739), `oc-audiocpp-linux-aarch64.so` without `libatomic` (our #744). Changed bytes: the engine, four CUDA libraries, two Vulkan libraries, four `oc-espeak`, one arm64 audio library.
> - solidPC (as `ollama`, `/srv/ml/xb133`, results `pin-b133`): compat 8/8, llama3 77.4 tok/s (76.5 on 70cee052), 4 slots 302 tok/s (299), overflow 3.6 tok/s; speech 8/8 transcribed back; Wan2.1 and Wan2.2 33/33 frames; Vulkan on the Renoir iGPU 34.2–34.6 tok/s, 29/29 layers.
> - eleven2go (owner: "rerun the tests on eleven2go"; the new files in the fresh side directory `xollama-b133\engines`, served by the installed candidate on 22498): **the iGPU runs**, 37/37 layers, 5.0 tok/s over five 512-token runs, while the installed `2610031615001` still exits `0xc0000028` in the same minute; RX 9070 XT 104.2–104.3 tok/s warm; RTX 3090 123.5–123.9; Kokoro, KittenTTS, Supertonic, OuteTTS transcribed back. Test tags removed, the installed server and the ollama on 11434 untouched.
> - dietpi5: the aarch64 rows in an image with `libatomic` purged: engine 9.9–10.0 tok/s, llama.cpp 9.9–11.0 interleaved, speech 5/5. `libatomic1` is out of `Dockerfile.xollama` again.
> - Not measured on these bytes: macOS (engine and `oc-espeak` changed), CUDA 12, the long eSpeak path (my deep-directory run did not push the data path past 160 characters; opencoti's gate did), bug-3777's own trigger.
> - Told opencoti what is still not delivered (#751, owner's instruction) and got its answers (#752): the per-component pin format and the engine's refusal of a mismatched library are not built and not dated (the first v2 snapshot will be these bytes); the misleading dlopen-helper message is open; the arm64 dot-product path is their c9; eSpeak past Windows' ~260 characters still fails without naming the limit; `BUILD_INFO.md` joins `SHA256SUMS` from the next publish; CUDA 12 waits for chris-v100; a prebuilt dlopen helper has been inside the engine since 2026-09-27 (0431), unverified by us on a bare arm64 host.
> - Owner: the release starts the image automatically ("keep the image start automatic").
> - CI: the macOS test leg had been red since `7d5769833` (five `discover` tests about CUDA and Vulkan, which `existsOn` leaves unlisted on a Mac); the tests now name their platform (`opencotiHost`, `onLinux`). Noticed only now: the draft of `rc.1` was built from a commit with that leg red.
> - Left: a new candidate (`rc.2`) from this tree, with its draft and install check; PR #5's notes follow the tree, its title is still `rc.1`.
>
> **2026-10-04 — `:dev` published for amd64 and arm64; the release now carries Linux arm64 and starts the image; protocols updated (owner's instruction).**
> - Published: `docker-release` from `dev` at `e90f26fa4`, run 37178934906, all four jobs green, the first real run of `manifest`. `mannixita/xollama:dev` and `ghcr.io/mann1x/xollama:dev` (and `:0.35.1-dev.e90f26fa`) are manifest lists over `linux/amd64` and `linux/arm64`; `-amd64` and `-arm64` tags beside them. `:latest` not touched.
> - The published image pulled and run on dietpi5: `arm64/linux`, `/api/xollama` names `0.35.1-dev.e90f26fa`, `PAYLOAD` names the fork's runtime `096e5e43…`. `qwen2.5:1.5b`, 512 tokens, the two engines interleaved over four rounds: llama.cpp 10.9 / 10.9 / 10.9 / 11.0 tok/s, the engine 9.9 / 10.0 / 9.8 / 9.9. The engine is about 10 % behind on a Cortex-A76 (its CPU build has no dot-product or FP16 path); the Pi reports past thermal throttling (`0xe0000`), which is the spread between earlier sessions. Kokoro answered mp3, transcribed back. The owner's containers untouched.
> - `xollama-release.yaml`: `plan` refuses a release whose two Linux runtime pins would not assemble (a pin without a runtime, other llama inputs, an unpublished asset, another upstream, or the two on different fork releases); `publish` starts `docker-release.yaml` on the tag it created (`actions: write`; a failure is a warning with the command to run by hand) and the notes gain a Linux row and a container image row. The guard was run locally against this tree. Not run on hosted runners yet: the release workflow's arm64 `linux` job, the guard and the dispatch; the next candidate's dry run is their first.
> - Protocols: `docs/protocols/RELEASE.md` (the image is part of the cycle; assets, sources and checks for Linux and the image; dietpi5 as the arm64 test host with its check list; `:latest` needs one image run after promotion; known gaps rewritten), `docs/protocols/FORK-SYNC.md` (the fork delivers both runtimes, both pins move in one commit, the image is xollama's). User pages: `docs/xollama/docker.mdx`, `docs/dockerhub/README.md`, `README.md`, `docs/features/docker-release.md`.
>
> **2026-10-04 — The fork's arm64 runtime is pinned; the arm64 image is built from pins alone and measured on the Raspberry Pi 5.**
> - The fork published `ollama-linux-arm64-runtime.tgz` on `v0.35.1-thinkbudget` (mail #746: sha256 `096e5e43…570b`, built at `1040f03d`, the amd64 runtime's inputs `57004c3c…`; a native arm64 runner, AlmaLinux 8, CPU variants armv8.0–9.2 chosen at load). Pinned in `llama/runtime-pin-linux-arm64.txt` (`4a17d2114`); the assembly passes for arm64 with no test switch. The owner ruled the fork ships binaries only: the arm64 image is xollama's.
> - Image built on dietpi5 from that context, `qwen2.5:1.5b`, 512 tokens, four runs: llama.cpp (the fork's runtime) 10.1 / 9.8 / 9.7 / 9.7 tok/s, the engine 9.8 / 9.8 / 9.9 / 9.9. Kokoro, Supertonic and KittenTTS each transcribed back by Whisper, 3/3. (That run showed no gap between the two; the interleaved run in the entry above does.)
> - Hosted run 37177604018 (`docker-release`, push off): amd64 green; arm64 failed in the Go build, `mlx/include/mlx/c/half.h: arm_bf16.h: No such file` with AlmaLinux 8's gcc 8. Fixed as upstream builds it: clang on arm64, in `scripts/docker-assemble.sh` and the `linux` job of `xollama-release.yaml`; the same container build run natively on the Pi gives a binary that needs glibc 2.28.
>
> **2026-10-04 — Linux arm64: wired into the release and the image, measured on a Raspberry Pi 5; eleven2go runs the shipped engine; PR #5 is not merged.**
> - Owner: no merge of PR #5; another bug is being fixed too (opencoti bug-3777, a CUDA use-after-free under multi-slot serving, fixed in the unpublished engine build 2610040459001, mail #743), then a new candidate. The Windows iGPU crash (#740) is the other one.
> - eleven2go: `XOLLAMA_ENGINE_PATH` removed from the user environment on the owner's word, the app restarted in the desktop session; the installed server now runs its own engine (build 2610031615001, the 790 MB CUDA library, 37/37 layers, `qwen3:8b` 123.7 / 124.2 / 123.8 tok/s over 512 tokens). `XOLLAMA_ENGINE_ARGS` is still set. The host is opencoti's next, for the traces of #740 (owner).
> - Asked the fork for `ollama-linux-arm64-runtime.tgz` (mail #741): it supplies llama.cpp, and its release has no arm64 runtime while upstream ships `ollama-linux-arm64.tar.zst` and a multi-arch image.
> - Measured on dietpi5 (Raspberry Pi 5, 8 GB, Debian 13, glibc 2.41, 16K pages) with upstream's v0.35.1 arm64 CPU runtime standing in for the fork's, the engine's `aarch64` rows staged by the pin, `xollama` cross-built at `38623cbc`. `qwen2.5:1.5b`, 512 tokens, four runs: bare metal 9.2 / 9.2 / 8.9 / 8.9 tok/s on the engine and 10.0–10.1 on llama.cpp; in the image 9.5–9.6 and 10.7–10.8. Speech: Kokoro (two voices), Supertonic (mp3, wav), KittenTTS, each transcribed back by Whisper, 5/5 bare and in the image.
> - Found on arm64, reported to opencoti (#744): the audio library needs the system's `libatomic.so.1`, absent from `ubuntu:24.04` (every speech load failed in the image; `libatomic1` added to `Dockerfile.xollama`, a bare minimal system is still exposed); the engine's message beside it blames the dlopen helper; the engine's CPU build lacks the dot-product and FP16 paths upstream's runtime picks on a Cortex-A76, about 10 % slower.
> - Code: `scripts/docker-assemble.sh` takes `ARCH` (pin, engine rows, Go container by architecture; `ALLOW_UPSTREAM_RUNTIME=1` for a local test without the fork's runtime, refused in CI); `llama/runtime-pin-linux-arm64.txt` (upstream's arm64 GPU rows, runtime rows awaited); `docker-release.yaml` builds per architecture on native runners and joins `:<version>` and the moving tag in a `manifest` job, arm64 switched on by the pin; `xollama-release.yaml` builds `xollama-linux-arm64` beside amd64 and expects it in the asset set. The amd64 assembly gives the same file set as before.
> - Not run: the two workflows on hosted runners (the arm64 runner, the manifest job), the Go build inside the arm64 container, the JetPack and CUDA payloads on arm64 hardware.
> - Left on dietpi5: `/root/xollama-arm64` (stage, store 2.6 GB, context) and the image `xollama:arm64-test`; the test container is removed; the owner's containers were not touched.
>
> **2026-10-04 — The draft of `v0.35.1-rc.1.xollama` installed and measured on eleven2go (owner's instruction).**
> - Install (RELEASE.md steps 6–7): `xOllamaSetup.exe` (sha256 `3037c046…9e54`) through a one-time interactive scheduled task, exit 0 in 30 s. `xollama.exe --version` is `0.35.1-rc.1.xollama`, `lib\ollama\PAYLOAD_ID` equals `payload-id.txt` (`af8547b7…aa7f`), 22434 listens and `/api/xollama` answers, `/api/xollama/devices` lists the RTX 3090 (CUDA) and the RX 9070 XT and the Radeon iGPU (Vulkan), all on the engine; the think-budget ollama still answers on 11434 (same process).
> - **The host overrides the engine.** Its user environment sets `XOLLAMA_ENGINE_PATH` to `opencoti-b208\opencoti-0.10.5-c7-2609281805001.exe` (and `XOLLAMA_ENGINE_ARGS`), so the installed server runs that engine and its 311 MB CUDA DLL, not the draft's; a Vulkan load there fails loudly ("Vulkan is not usable": that directory has no Vulkan library). Left as the owner set it. The draft's own engine was measured from a second server on 22498, started from the installed files without the two variables, then stopped.
> - Measured, `qwen3:8b` Q4_K_M, 512 tokens, one cold and four warm runs: RTX 3090 through the six-architecture `ggml-cuda.dll` 123.4–123.6 tok/s, 37/37 layers (the older DLL: 121.6–123.4); RX 9070 XT through `ggml-vulkan.dll` 101.3–104.3 tok/s warm, 37/37 layers.
> - **Found: the engine crashes on the Radeon iGPU through Vulkan on Windows** (`0xc0000028`, in the fit step, and at tensor load with `-fit off`). Stock llama.cpp loads the same model on the same iGPU in the same session (5.0 tok/s). An unpinned model is kept off an integrated GPU when a discrete one exists, so this host is not affected by default; a Windows machine with only an AMD iGPU would be. Reported to opencoti, noted in PR #5, not worked around.
> - Also seen: the engine numbers the Vulkan devices differently from the listing the b208 override produces (RX 9070 XT is `Vulkan1` on the pinned engine, `Vulkan2` there), so a device pin by index does not survive an engine override.
> - Left: the owner's call on merging PR #5 with the iGPU defect open; Linux arm64 is not packaged (see Known gaps).
>
> **2026-10-04 — Draft build of `v0.35.1-rc.1.xollama` from `7d5769833` (release PR #5, not merged).**
> - `gh workflow run xollama-release.yaml --ref dev -f pr=5` (run 37170880018): plan, linux, windows and publish green; a **draft** release, no tag, invisible to the updater. Assets: `xOllamaSetup.exe` 1.30 GB (797 MB in v0.34.4-xollama.2: the six-architecture CUDA DLL is 790 MB), `xOllamaUpdate.exe` 14.8 MB, both binaries, `payload-id.txt` `af8547b7…aa7f`.
> - Verified from the downloaded draft (`backup_models/release-check/v0.35.1-rc.1.xollama`): every `sha256sum.txt` line OK; `xollama-linux-amd64 --version` names `0.35.1-rc.1.xollama`. The Windows payload carries, in `lib\ollama\engines`, the engine, `ggml-cuda.dll` (790,682,112 bytes), `ggml-vulkan.dll`, the three media DLLs, the four licence texts and `BUILD_INFO.md`.
> - Container: `scripts/docker-assemble.sh` run locally from the same pin, exit 0: the CUDA and Vulkan libraries beside the engine, the CUDA 12 library in `engines/cuda_v12` with a second engine copy. No image published.
> - Left before the candidate is released: the install check of the draft on eleven2go (it is also the only Windows measurement of the six-architecture and Vulkan DLLs), then the merge of PR #5. Both need the owner's word.

> **2026-10-04 — Engine pin moved to rev `70cee052` (the full library set of `2610031615001`); a per-component pin format agreed with opencoti.**
> - Owner: "agree a new pinning schema that allows partial and staggered release, then make a full pre-release build from hf dev" and "we publish cuda 12 without testing it, legacy".
> - The pin: same engine, sidecars and macOS files; new are the six-architecture CUDA libraries for Linux and Windows (`cuda-sass 75 80 86 89 90 120`), the Vulkan libraries for both, and the CUDA 12 legacy library (`cuda12-sass 52 61 70`, Linux, pinned without a run on such a card). No row for the Linux arm64 library: nothing we ship is built for it.
> - solidPC, host under load (load average 20–40): compat 8/8, llama3 76.5 tok/s (77.4), four slots 299 tok/s (302), speech 8/8, Wan2.1 and Wan2.2 33/33 frames. 70B overflow 1.0–3.0 tok/s against 4.0 the day before; the previous library as control in the same hour gave 2.2 and 3.0, so it is host load. Vulkan on the Renoir iGPU through the engine's own library: 29/29 layers, 35.7 tok/s over 512 tokens. Not measured through xollama: both Windows libraries, CUDA 12, any 7.5 / 8.0 / 9.0 card.
> - Found: eSpeak-ng holds its data path in 160 bytes. A stage directory one character longer made the path exactly 160 and Kokoro and KittenTTS failed at load. Reported to opencoti; a user with a long home path would hit it.
> - Fixed: with `XOLLAMA_ENGINE=opencoti`, Linux asked the engine for Metal devices on every start and warned (`existsOn`, `discover/opencoti.go`), a side effect of the macOS commit.
> - Pin format v2 (opencoti `docs/protocols/PIN_FORMAT.md`, mails #730–#737): one pin file per component (engine, cuda, cuda12, sbsa, vulkan, macos, media) with its own version and rev; an index composes them; xollama keeps its own index and vendors the pin files, so a release can take one component without the others; named ABIs (`ggml`, `media`, `loader`) decide compatibility and the engine will refuse a mismatched library at load; files keep their published names. One cutover: opencoti publishes the first v2 snapshot from these bytes, then we land the parser. Not started on our side.

> **2026-10-03 — The macOS app is Apple silicon only (owner's choice); built, notarized and installed in one script run.**
> - Why: the owner saw macOS 27's popup that xOllama "includes a component that will not open in macOS 28". The universal bundle carried 22 x86_64-only llama.cpp libraries (the Intel runtime is shared libraries, the arm64 one is static). `scripts/build_darwin.sh` now takes its architecture list for the merge, the payload copy and the app binary, and defaults to `arm64` (`7870ebef3`); `-a "arm64 amd64"` builds the universal app.
> - The build of `7870ebef` ran `build sign app` in one pass with notarization on: app and DMG accepted and stapled, 17 Mach-O files, all arm64. `xOllama.dmg` 219 MB, sha256 `2e0e4e90…7b1bf`, in `~/dev/xollama/dist` on the Mac mini; not published.
> - Installed on the Mac mini and run through the app's own server on 22434: qwen2.5:1.5b 129.5 tok/s, gemma3:4b-it-qat 43.9 tok/s (512 tokens, warm), speech 7/7, signature valid after the runs, no authorization dialog on this start.

> **2026-10-03 — `2610031615001` measured on Windows; the Mac app's names confirmed at the screen.**
> - eleven2go (Windows 11, RTX 3090), on the owner's word, side directory `xollama-b130` on port 22498, installed servers untouched: qwen2.5:1.5b three 512-token runs at 327.5 / 326.7 / 325.2 tok/s, 100 % GPU (322 on the previous pin); Kokoro (two voices), Supertonic, KittenTTS and OuteTTS mp3, each transcribed back; two custom voices listed and spoken; Wan2.1 in 149 s, 21.8 GiB peak; the four licence texts beside the DLLs. The pin is now measured on Linux, Windows and macOS.
> - Mac mini, after the owner answered the authorization dialog: the app started its server, the CLI link is `/usr/local/bin/xollama` (the old `/usr/local/bin/ollama` removed by the owner), the login item registered under `com.mann1x.xollama`, state is in `~/Library/Application Support/xOllama`. Phase 4 of `plans/macos-build.md` closed.
> - The hosted `test` workflow failed on the macOS runner after the macOS commit (two tests asserting llama.cpp or upstream names, one gofumpt line); fixed in `bdcaa7e30`, green.

> **2026-10-03 — macOS: the app and its DMG are notarized.**
> - Apple accepted the signed universal `xOllama.app` (submission `e793062d`) and the DMG (`c95ba8de`); both are stapled and Gatekeeper reports "Notarized Developer ID". The notarized app is installed on the Mac mini. `xOllama.dmg` sha256 `26a668e0…4560c` (272 MB), in `~/dev/xollama/dist` there; not published anywhere.
> - The app is the build of commit `7997b42a9`'s tree made before that commit, so it names itself `0.35.1-dev.fb0ec3f5`. The DMG was made without the Finder styling (no desktop session over ssh).
> - Left for macOS: a run of the app at the Mac's screen (the CLI-link dialog, the login item), a release path for the macOS assets, image, video, vision and MTP on Metal.

> **2026-10-03 — macOS: opencoti on Metal inside a Developer ID signed universal xOllama.app; engine pin moved to `2610031615001` (rev `cee83ff6`), on the owner's word.**
> - The pin: `2610031615001` fixes the Metal abort on a prompt longer than one ubatch (0549), ships the signed macOS loader `ape-macos-aarch64`, and carries the ffmpeg, lame and openh264 licence texts, now on rows of their own for every platform. New bytes: the engine (`abd906ca`) and the Linux CUDA payload (`154dc672`); the Windows DLL and every Linux and Windows library are unchanged.
> - solidPC as `ollama`, one run (`pin-b130`; `2610031319001` in brackets): compat 8/8 (8/8), llama3 77.4 tok/s (77.1), four slots 302 tok/s (302), gemma4 identical, 70B overflow 4.0 tok/s (4.1). Speech 8/8 mp3, each transcribed back. Wan2.1 33/33 frames (221 s), Wan2.2 Q4_K_M 33/33 (112 s). **Windows was not measured on this build**: eleven2go is paused and this test was not among the owner's exceptions.
> - macOS code (hook `macos-engine`, plan `plans/macos-build.md`): package `macos-aarch64` (`PackageArch`), `darwin/arm64` Metal and CPU in the tested matrix, the launch, device listing and link probe through the loader (`run`), `--gpu apple`, Metal in discovery, the engine's HOME never inside the app bundle (`payloadRoots`), the loader staged executable by `cmake/opencoti-fetch.cmake`. `scripts/build_darwin.sh` stages the engine into `Contents/Resources/engines`, signs the loader with `app/darwin/engine-loader.entitlements`, and notarizes by API key (`XOLLAMA_NOTARIZE=off` signs only). An Intel Mac has no opencoti files and stays on llama.cpp.
> - Mac mini (M6, 24 GB, macOS 27.0.1), engine inside the signed app, 512 tokens, one cold and three warm runs, stock llama.cpp on Metal in brackets: qwen2.5:1.5b 124.5 tok/s (130.3), llama3 31.3 (31.4), gemma3:4b-it-qat 42.2 (42.4). Speech 7/7 (Kokoro, Supertonic mp3 and wav, KittenTTS, OuteTTS, a custom voice), transcribed back by Whisper there. Signature valid after the runs. Intel half under Rosetta: opencoti refused by name, llama.cpp serves. The Mac's store holds 27 tags (129 GB) copied from solidPC.
> - The app on macOS (`app-brand`, `app-state`): it registered a login item under upstream's plist name (failed), wrote its CLI link to `/usr/local/bin/ollama`, kept state in `~/Library/Application Support/Ollama`, relaunched itself as `Contents/MacOS/Ollama`, and treated a running stock Ollama app as another instance of itself. All five fixed; the fixes are built and signed but not yet run at the Mac's screen.
> - Left: notarization (Apple has accepted nothing from this account yet), staple and DMG; the Windows measurement of this pin; image, video, vision and MTP on Metal; a macOS release path. Found by running the tests on the Mac: two launch tests read the runner's real `~/.ollama/engines` (given a private HOME).

> **2026-10-03 — Engine pin moved to opencoti `2610031319001` (rev `26cd5645`), on the owner's word; measured on solidPC and on Windows.**
> - What it adds over `2610031112001` (opencoti #714, #715): a request cancelled while queued no longer keeps its KV reservation for 600 s and a queued stream gets its keepalive (0546); `--dca on` no longer aborts on a CPU-only run (0542). Only the engine (`1e6e30cb`) and `BUILD_INFO.md` changed among what xollama ships; CUDA payloads and all libraries are the same bytes. The snapshot's new macOS files have no pin rows.
> - solidPC as `ollama`, one run (`pin-b128`; `2610031112001` in brackets): compat 8/8 (8/8), llama3 77.1 tok/s (76.4), four slots 302 tok/s (302), gemma4 identical, 70B overflow 4.1 tok/s (3.8). Speech: all five models and two custom voices mp3, Whisper returns the sentence. Wan2.1 33/33 frames (223 s), Wan2.2 Q4_K_M 33/33 (114 s).
> - eleven2go (Windows 11, RTX 3090), side directory on port 22498, installed servers untouched: qwen2.5:1.5b three 512-token runs at 322 tok/s, 100 % GPU; Kokoro, Supertonic, KittenTTS, OuteTTS mp3 and transcribed back; two custom voices; Wan2.1 33/33 frames in 149 s; licence text and `BUILD_INFO.md` beside the DLLs.
> - CPU-only gap: opencoti decodes about 12 % under stock on CPU (36.9 vs 41.8 tok/s). opencoti: structural (only the matmul kernels are built per ISA), their c9 stage 17. No tuning on our side.
> - Left: the queueing faults 0546 fixes were not exercised here; Wan2.2 and the installer on Windows; the Docker assembly and the hosted workflows on this pin.
>
> **2026-10-03 — Linux runtime pin moved to the fork's `v0.35.1-thinkbudget` (b11232); the Docker assembly runs unmodified again.**
> - `llama/runtime-pin-linux.txt`: runtime `2334fe35…` built at fork `1040f03d` (inputs `57004c3c…`, this tree's), upstream `v0.35.1` GPU archives `9fcd79ac…` and `15ee9a52…` (upstream's own `sha256sum.txt`). The runtime's sha256 was checked on a download of my own, not taken from the fork's mail (#708).
> - `scripts/docker-assemble.sh`, as CI runs it, exit 0: both llama checks pass; the image carries the runtime, the engine, the three libraries and both licence files. In a container (no compiler, no eSpeak-ng, CPU only): Kokoro, KittenTTS, Supertonic mp3; qwen2.5:1.5b answers on stock `llama-server` and on opencoti. Measured afterwards at 256 tokens, six warm runs, host load 12-14: stock 41.8 tok/s, opencoti 36.9, a consistent ~12 % CPU-only gap (opencoti mail #712); the 47 / 38 first quoted here came from a 10-token smoke and is withdrawn.
> - Left: a GPU run of the image (solidPC's Docker has no NVIDIA runtime), the hosted `docker-release` run.
>
> **2026-10-03 — A root-run server no longer costs the service its GPU (xo-17); licence text ships with the libraries (xo-18); the Docker assembly is blocked on the fork's Linux runtime.**
> - xo-17. The engine writes `.cosmo/` (dlopen helper), `.nv/` and `.cache/` into the HOME xollama gives it, as whoever it runs as. After one `sudo xollama serve`, the `ollama` service failed every GPU load with "dlopen() isn't supported on this platform". Fix: `engine.AdoptPayloadHome` hands the tree to the store's owner when the engine exits and when the HOME is prepared (root only, only a directory with the payload marker); an unprivileged server that finds unusable foreign files warns once and takes the next root; launch, device listing and link probe all get their HOME from `engine.PayloadHome`.
> - Measured on solidPC with one install run as root, then as `ollama` (`/srv/ml/xo17/run.sh`, qwen2.5:1.5b): unfixed binary, root ok then `ollama` fails with the dlopen error; fixed binary, both fully on the GPU and every file `ollama`-owned; fixed binary as `ollama` in the directory the unfixed root run spoiled, one Warn naming the path and the fix, fallback to `~/.ollama/engines/payload`, GPU ok.
> - xo-18. `COPYING.espeak-ng` and the engine's `BUILD_INFO.md` are `#! sidecar` rows (kinds `espeak-licence`, `build-info`, three arches), staged beside the libraries; `TestEveryLicensedSidecarShipsItsText` refuses a pin without them. They first landed in `9f01c170c`, the fork session's docs commit, which swept up the staged files by accident (its mail #706); on the owner's word they were taken back out (`af2c9ee5b`) and committed as themselves (`0d16aebe7`), the tree byte for byte the same. The LGPL texts of ffmpeg and lame and openh264's licence are not in the snapshot: asked of opencoti.
> - Docker. `scripts/docker-assemble.sh` refuses this tree: `llama/runtime-pin-linux.txt` still names the fork's `v0.34.4-thinkbudget` runtime (b11081) and the tree is at b11232. The fork is cutting `v0.35.1-thinkbudget` (its run 37116267125); the pin moves on its mail. With those two checks skipped in a test copy, the assembly staged the engine, three libraries and both licence files, the image built, and in a container with no compiler and no eSpeak-ng Kokoro, KittenTTS and Supertonic answered mp3 (the eSpeak data is written under the engine's HOME, `/usr/lib/ollama/engines/payload`, writable there). No NVIDIA runtime in solidPC's Docker, so no GPU-in-container run.
> - Also removed: `voicesTar`, an unused test helper left by the voices change, which failed lint.
> - Left: move the Linux runtime pin and rerun the real assembly; the LGPL licence texts; a GPU run of the image.
>
> **2026-10-03 — Engine pin moved to opencoti `2610031112001` (rev `50f953bd`): b119 with the Windows audio.cpp fix. Measured on solidPC and, for the first time, on Windows (eleven2go).**
> - Why: opencoti #701, bug-3899. b119's `oc-audiocpp-win-x86_64.dll` killed the engine at the first audio.cpp model load on Windows. The fix is half in the DLL, half in the engine (0541), so the engine (`9f7b8637`) and the three `oc-audiocpp` files move together; CUDA payloads, `oc-codec` and `oc-espeak` are b119's bytes.
> - solidPC, as `ollama`, one run (`/srv/ml/xollama-phase2/as-ollama/pin-b120`; b119 in brackets): compat 8/8 (8/8), llama3 76.4 tok/s (77.3), four slots 302 tok/s (300), gemma4 identical, 70B overflow 3.8 tok/s (3.0). Through xollama: Kokoro, Supertonic f16/q8_0, KittenTTS, OuteTTS (default + two voice files) all mp3, Whisper returns the sentence; Wan2.1 33/33 frames (270 s, 18.1 GiB), Wan2.2 Q4_K_M 33/33 (116 s, 21.6 GiB).
> - eleven2go (Windows 11, RTX 3090), dev `xollama.exe` in `%USERPROFILE%\xollama-b120` on port 22498 with its own store, beside the installed xOllama (22434) and Ollama (11434), both left running; `lib\ollama\engines` staged by `cmake/opencoti-fetch.cmake` from this pin, hashes checked on the host; no eSpeak-ng on the host. qwen2.5:1.5b 100 % GPU at 322 tok/s; Kokoro (default, nova), Supertonic, KittenTTS, OuteTTS answer mp3 with `oc-codec`, `oc-audiocpp` and `oc-espeak` mapped in the engine process, Whisper returns the sentence from each; `--tts-voices=` with two files, both listed and spoken by name; Wan2.1 640x352 33/33 decoded frames, 149 s, 20.3 GiB peak. Logs: `/srv/ml/xollama-b120/win-test.log`, `win-test2.log`.
> - Doc bug found by the Windows run: `tweak model` flags take `--flag=value` (cobra `NoOptDefVal`); `docs/xollama/media.mdx` and the posted OuteTTS card had `--tts-voices value`, which fails with "accepts 1 arg(s), received 2". Both corrected.
> - Left: the Windows installer and updater path (this was a side directory, not an install), Wan2.2 on Windows, the aarch64 sidecars, macOS sidecars (opencoti c9), no CUDA 12 payload (Volta on llama.cpp), the Docker assemble run and its writable-home check, xo-17, xo-14.
>
> **2026-10-03 — Engine pin moved to opencoti b119 (`2610031022001`, rev `a542184f`), measured; eSpeak-ng ships with the engine; three engine workarounds removed.**
> - Pin (`f9eabcd22`): engine `7bd91cb6`, Linux CUDA `7d129e82`, Windows CUDA DLL `32de1a88`, and nine `#! sidecar` rows (codec, audiocpp, espeak for x86_64, win-x86_64, aarch64). No CUDA 12 payload: Volta goes to llama.cpp until opencoti publishes one (owner accepted the gap). The Windows DLL and the Windows / aarch64 sidecars have not run on their platforms.
> - Measured on solidPC, paired with b208 on the same xollama (`/srv/ml/xollama-phase2/as-ollama/pin-b119`, `pin-b119-baseline-b208`), one run each: compat 8/8 (8/8), llama3 77.3 tok/s (77.6), four slots 300 tok/s aggregate (144), gemma4 identical, 70B overflow 3.0 tok/s (3.2); a two-turn `/api/chat` held (93 tok/s).
> - Media through xollama on a host with NO system eSpeak-ng, all from blob paths: Kokoro 7.9 s, Supertonic f16 6.9 s, q8_0 6.8 s, KittenTTS 5.0 s cold, mp3, Whisper word for word; OuteTTS with two `--tts-voice` files (`tweak --tts-voices narrator=…,host=…`) speaks as each and lists both. Wan2.1 33/33 decoded frames at 16 fps (221 s, 17.2 GiB), Wan2.2 Q4_K_M 33/33 at 24 fps (113 s, 20.6 GiB) on the 3090.
> - eSpeak-ng (owner): a third sidecar, `oc-espeak`, one file with its data inside, GPL-3, loaded at runtime (opencoti #696–#698). The rebuilt `oc-audiocpp` is required with it.
> - Merged with the pin, each checked on b119's bytes against b208: no f16-V relaunch on opencoti (`-fa auto` with `-ctv q8_0` on CPU: b208 refuses, b119 boots), no `--override-kv` for DCA (`--dca on -c 49152` on a 32768 model boots and generates), the opencoti status-line filter deleted (`llm/status.go` is upstream's again).
> - Found on the way: a root run leaves root-owned `.cosmo`/`.nv` in the engine's payload HOME and the service then loses the GPU with "dlopen() isn't supported" (task xo-17, open). `--dca on` on the CPU aborts in ggml on both builds (reported to opencoti).
> - NOT merged: `098712c9b` (no `-<arch>` renames when staging; needs a Windows run) and `1172994dd` (one engine for CUDA 12; needs a CUDA 12 payload and a Volta run).
> - Left: eleven2go run of the Windows payloads, xo-17, cards re-posted, PR #5 notes.

> **2026-10-03 — opencoti b117 measured through xollama on solidPC; the engine's media sidecars are read from the pin and staged; eSpeak-ng found to be a host dependency.**
> - b117 `2610030921001` (HF dev rev `a6cc834c`, same bytes as `5d1aad39` plus six sidecars) fetched by sha to `/srv/ml/xollama-b117`, sidecars beside the engine under their published names; test server on 22498, CPU only.
> - `mannix/supertonic:3` and `:3-q8_0` answer mp3 44.1 kHz from the blob path, no hard link (6.4 s / 6.8 s cold); `/health` features `audio_speech_v1, audio_speech_content_format_v1, audio_speech_audiocpp_v1, media_codec_v1`. `mannix/kokoro:82m` and `mannix/kittentts:mini-0.8` are refused at load: they phonemise with eSpeak-ng, which nobody ships and solidPC lacks (bs2 has it, which hid it). Owner: eSpeak-ng ships as a third sidecar loaded at runtime, no system dependency, on Linux, Windows and macOS (opencoti #696).
> - Release blocker found and fixed on our side (task xo-16): the sidecars (`oc-audiocpp`, `oc-codec`) were on bs2 only, with no pin rows and nothing in xollama staging them. Now `#! sidecar <arch> <kind> <path> <sha256>` rows (any kind) are read by `ParsePin` (`Pin.Sidecars`) and staged beside the engine by `cmake/opencoti-fetch.cmake`, `scripts/docker-assemble.sh` and the Windows release workflow, sha256 enforced (`5362dab31`). Load-time gate: an `audiocpp` model needs `audio_speech_audiocpp_v1`; a template default that needs the codec (not wav/pcm, avi/webm) needs `media_codec_v1`.
> - Two xollama bugs from the run, fixed in `cdce0b274`: an audio.cpp speech model was placed on a GPU (VRAM booked for nothing, `--gpu vulkan` refused by the engine) and now counts as CPU; a failed media load reported the engine's last line only (its advice) and now its last four.
> - `3bbd7100e`: the engine payload directory is locked (mutex + lock file) and keyed by content, through `fsowner`.
> - NOT merged, waiting on a measured pin move: `841f9a688` (pin b117 with sidecar rows; no Windows CUDA DLL and no CUDA 12 row in this snapshot yet), the c8-tree glue removals (`worktree-agent-aa0b54d446e18540e`: f16-V relaunch, DCA override-kv, status filter, arch renames) and one engine for CUDA 12 (`1172994dd`).
> - Left: Windows DLL re-issue, eSpeak sidecar, OuteTTS with `--tts-voice` through xollama, mp4 frame counts on the 3090, the pin measurement, cards re-posted (kokoro, supertonic, kittentts, outetts, wan2.1, wan2.2).

> **2026-10-03 — Extra voices are one layer each, `--tts-voice NAME=<blob>`; the voices tar is gone, before the template format freezes at c8.**
> - Owner: one layer per voice, and the engine flag now, because the model template format cannot change after c8 without breaking published models. `tts.voices` is `{NAME: digest}`, each voice a `media/tts.voices.<NAME>` layer; names `[A-Za-z0-9_.-]{1,64}`. The launch passes `--tts-voice NAME=<blob>` per voice (sorted); a model with voices needs `/health` feature `audio_speech_voice_files_v1`. `xollama tweak model`'s "Extra voices" row takes `name=file` pairs (local path, hf.co or digest). No published model carried a voices tar.
> - opencoti #677: stop the tar reader (B), ship `--tts-voice` + the feature flag in c8; asked whether audio.cpp can take a standalone voice file.

> **2026-10-03 — No engine workarounds in xollama: the audio.cpp hard link is gone, the engine is fixed instead; audit of the rest sent to opencoti.**
> - Owner ruling: xollama never papers over a limitation of an engine we control. `server/media_named.go` (hard-linking an audio.cpp GGUF as `<digest>.gguf`) was filesystem-dependent, fell back silently and cleaned up only on a later load. Deleted, with the voices-tar unpack (`mediaVoicesDir`).
> - Now every media component goes to the engine as its blob path. An audio.cpp speech model needs `/health` feature `audio_speech_content_format_v1` (`MediaFeatures`); an older engine is refused at load naming the feature. A missing component blob is refused by name before launch; an unreadable `/health` body fails at once instead of reading as "no features".
> - opencoti: #672 (bug-3880 contract: format by contents at package.cpp:60, tensor_source.cpp:1566, vocos_vocoder.cpp:61, espeak_phonemizer.cpp:136; voices from a tar file) and #674 (owner: both in c8 today, with the two feature flags). Audit of 14 further engine/packaging workarounds in xollama sent as #673, ranked (payload HOME, dlopen helper, text-parsed 429, /health retry, voices dir, staging renames, CUDA 12 APE copy, …); task xo-14 retires each with the build that fixes it. xollama's own silent fallbacks: task xo-15.
> - Published models are unchanged and need no republish: the same blobs load on a c8 engine. Cards in `dev/posts/ollama` now name c8 as the minimum. Their b112 measurements were taken through the hard link and are re-run on c8.
> - Left: c8 build + gate lines from opencoti, pin move, TTS re-measure on c8.

> **2026-10-03 — Media templates published from bs2: Kokoro, Supertonic, KittenTTS, Wan2.2 5B and a Wan2.1 fp16 tag; audio.cpp needs a `.gguf` name.**
> - Owner: publish the M7 templates from bs2, with the most relevant quants rather than a full ladder. On bs2 GPU0 (opencoti's slot, #667/#668), using opencoti b112 `2610030147001` with its CUDA payload `023a2930` and its codec and audio.cpp sidecars, all checked by sha256. GPU1/8244 was left alone.
> - **bs2 house rule:** models come from HF only. A copy from solidPC was stopped and removed. `xollama media fetch` fetched from HF by sha256, and bs2's own files were hard-linked.
> - **Published:** `mannix/kokoro:82m`, `mannix/supertonic:3` (f16) and `:3-q8_0`, `mannix/kittentts:mini-0.8`, `mannix/wan2.2:ti2v-5b` (Q4_K_M) and `:ti2v-5b-q8_0`, `mannix/wan2.1:t2v-1.3b-fp16`.
>   - New catalog entries, sharing builders (`supertonic`, `wan21`, `wan22`) with the defaults.
>   - The `--dry-run` configs of the five existing entries are byte-identical before and after.
> - **Fix, `server/media_named.go`:** audio.cpp judges a model file by its name.
>   - It read the blob path as a safetensors package and failed on all four TTS templates (missing `config.json` or `voice_styles/M2.json`).
>   - A symlink is not enough: it is resolved and then refused.
>   - So an audio.cpp GGUF speech model is now hard-linked as `<models>/media/named/<digest>.gguf`, and names whose blob is gone are dropped.
>   - Three tests; four plus three mutations, all killed. Reported to opencoti (#670).
> - **TTS:** every template answers mp3 (Kokoro 54 voices at 24 kHz, Supertonic 10 at 44.1 kHz, KittenTTS 8 at 24 kHz). Whisper large-v3 turbo transcribed the default voice and `nova` word for word on all four. audio.cpp runs on the CPU.
> - **Wan2.2 TI2V 5B, first run anywhere:**
>   - 832x480x33: 29.3 GiB (Q4_K_M) and 31.2 GiB (Q8_0) peak, 74 s;
>   - 640x352x33: 20.3 and 22.2 GiB, 35 s.
>   - The template is now 640x352x33 at 24 fps with a 13,312 MiB reserve, so the Q4_K_M tag fits a 24 GB card; a larger request is a 400.
> - **Wan2.1 fp16:** 640x352x33 in 76 s at 20.4 GiB, but the mp4 has 32 frames for 33 asked (asked opencoti).
> - **Model cards** for all nine media repos on ollama.com: `/srv/dev-disk-by-label-opt/dev/posts/ollama/`.
> - Left: `mannix/media-kit`, and Wan2.2 image-to-video (not measured).

> **2026-10-03 — Upstream v0.35.1 synced (fork manifest `f430d02f`, llama.cpp b11232).**
> - `sync/upstream-v0.35.1`, in its own worktree (the new one-branch-one-worktree rule, `9ccbf89b`):
>   - `d3c2f4ea` merged the tag. Four conflicts, each kept both sides: upstream's `CAPABILITY` directive beside the `model-config` hook's `XOLLAMA` (`parser/parser.go`, `cmd/create_safetensors.go`), `/v1/systemone` beside the tokenize routes (`docs/docs.json`), and `XOLLAMA_HOST` in upstream's reworked `TestWebSearchLoopMaxLimit`.
>   - The 24 patches followed as `--no-ff` merges at the manifest's shas, in order (`acb29d3c` … `38c76e8a`; the table is in CARRIED-PATCHES).
> - 23 patches are the v0.35.0 commits rebased (`git range-diff` all `=`). Each of those merges leaves the tree exactly as its first parent; the ones that conflicted with their own earlier copy were resolved to this side. The one change is `up-modelfile-roundtrip`'s `95ece51a` (`CAPABILITY` is a directive a quote can swallow), and that merge adds exactly its diff.
> - `LLAMA_CPP_VERSION` b11081 → b11232 plus upstream's `002-clef.patch`. `LLAMA_CPP_VERSION`, `llama/compat` and `llama/server` are byte-identical to the fork's `think-budget` (digest `f9c1055da0f6`). The runtime pin moved to `runtime-windows-amd64-b11232-f9c1055da0f6` (run 37093679156: compat markers present, asset sha256 `6c2bdf2c…` and inputs digest checked here).
> - Checks: gofmt silent, `go build`/`go vet ./...` clean, `go test ./...` no failures, `-race` clean on llm, server, model/parsers, thinking, parser, middleware and internal/council, `golangci-lint` 0 issues, `check-hooks` 33 hooks all registered, `check-compat-origin` 0 commits not from the fork or upstream.
> - Also committed: five agent rule files that `CLAUDE.md` already pointed at but were never added (`app-brand`, `engine-fit`, `modelfile-roundtrip`, `system-settings`, `system-settings-gpu`).
> - Left: a `TEMPLATE` quote swallowing an `XOLLAMA` line is still not caught (the pattern is the fork's and `XOLLAMA` is ours). `main` stays v0.34.4 until the next release PR.

> **2026-10-03 — Row B on opencoti b109 (head fixed); video slowdown is the shape; b208 commit control on eleven2go.**
> - b109 `2610022238001`, auto: 22,662-token arm 0.27 / 159.7 t/s (two fit passes, 62/81). Short-arm decode 2.79 t/s (b105: 2.10).
> - b109, head: no fit passes (bug-3874 fixed), 47/81 layers, 10 s boot, long arm 0.20 / 134.2. Its short-arm decode came in at 1.49 t/s (b105: 1.97), asked opencoti whether to repeat. Pin can move to a published build with 0527 + 3874 + 0531 (#656).
> - Video, reverse order (#655): 832x480x17 takes 570 s even first in a fresh process, and 640x352x33 takes 216 s second. So it is the shape, not eviction.
> - eleven2go (owner's go for the b111 rerun of bug-3876): b208 control commit is 17.7 GB after load, 23.3 GB after the first drafting request (+5.6 GB, untouched), 28.4 GB after 4 x 16k. b111 is staged and waits for its Windows CUDA DLL.

> **2026-10-02 — Cerebriline ran all five media tools live on 22499 (b105, #650); an edit keeps its source's size.**
> - Results: Klein generate 7.6 s; edit 41.2 s (a true reference edit, so b105's `auto` picks reference for FLUX.2); speech mp3 by default; transcription exact; Wan2.1 clip 228.8 s; a cancelled clip freed the card within 5 s. Cerebriline main `daa8ce078` reads `default_for`.
> - An edit without a size now comes back at its first image's size, capped at the template's pixel count, in multiples of 16 (`server/media_edit_size.go`, 5 mutations, all killed). Before, it came back at the template's 1024x1024.
> - 22499 also names a video default (`video=mannix/wan2.1:t2v-1.3b`).

> **2026-10-02 — bug-3755 repro on eleven2go for opencoti (#642 → #646; owner's go for this run only).**
> - b208 `2609281805001` on a separate xollama on 22436, under a commit hog (about 1 GB of commit left free), with procdump attached.
> - Run 1, one sequence: 60 prompts, 15 clean 503s, no crash.
> - Run 2, `--max-parallel 4`: the engine aborted on `ggml_aligned_malloc` (3,042 MB) → `GGML_ASSERT(ctx->mem_buffer != NULL)` (exit 6), not a SIGSEGV; xollama expired the model.
> - The September SIGSEGV did not reproduce. Host restored afterwards (hog and server stopped, WER key removed). eleven2go stays paused otherwise.

> **2026-10-02 — Row B on opencoti b105 2610022033001: bug-3859 fixed (#639 → #641).**
> - auto: the 22,662-token arm completes at 0.23 / 158.7 t/s (b97 and b103 crashed). The fit makes room in two passes (+432 then +80 MiB), and the sizer reports no shortfall. 62/81 layers on the GPU.
> - head: 0.20 / 131.7 at long context (was 0.14). Two fit passes of +224 MiB each, 46/81 layers, 25 s boot. Asked opencoti whether head needs that room.
> - Short arm: auto 2.10, head 1.97 t/s decode. The pin can move to a published build with patch 0527 on this measurement.

> **2026-10-02 — Media: a default model per kind (`XOLLAMA_MEDIA_DEFAULTS`).**
> - Cerebriline's `--media-provider` offered no image tool on 22499, because there are two image models and it never guesses.
> - The operator now names one per kind: `/v1/models` marks it with `default_for`, and a request without a model gets it.
> - Video: `/v1/videos` (create, poll, content, delete, list) with xollama job ids. The engine is held per job, and the template's clip is the cap. Live on the 3090 with b105: Wan2.1 1.3B 640x352x33 peaks at 17.0 GiB in 216 s; 832x480x17 tiles its VAE decode (~19 GB wanted) and takes 563 s. Both came back as h264 mp4.
> - The Wan2.1 template is set to 640x352x33 with a 12 GiB reserve (owner) and published as `mannix/wan2.1:t2v-1.3b`.

> **2026-10-02 — Row B on opencoti b103 2610021841001: bug-3859 not fixed (#632 → #635).**
> - auto: boot 71 s, short arm 2.22 / 197.4 t/s; the 22,662-token arm still dies, now as `failed to allocate CUDA0 buffer of size 363071744` at 17,920 tokens.
> - Patch 0524 flags the 359 MiB shortfall, but no `fit target … weights placed again` follows, and the fit keeps 64/81 layers on the GPU, as b97 did.
> - head: 15 s boot, 1.82 / 147.8 t/s, and the long arm passes at 0.14 / 133.7 t/s.
> - Logs: `/srv/ml/xollama-phase2/as-ollama/residency-ab-b103/`. The engine pin does not move.

> **2026-10-02 — Media: capabilities on `/v1/models` and a voice list, for Cerebriline (#628).**
> - Media models' `/v1/models` entries carry `capabilities` (`5c5d65d02`).
> - `/api/xollama/media/voices` (GET `?model=` or POST) and `xollama media voices MODEL` list the engine's voices with the template's OpenAI names as aliases, the default, formats and sample rate.
> - A test server for Cerebriline runs at `127.0.0.1:22499` (b97, the four published models).

> **2026-10-02 — Media endpoints, Phase 4: templates published on ollama.com.**
> - **Registry test passed.** ollama.com accepts the `application/vnd.xollama.media` layer, and a clean store pulled it back intact.
> - **Stock ollama (v0.35.0, built from `upstream`):** it pulls media templates but cannot show or run a media-only one (owner: fine). A chat model with media attached still chats; stock skips the layer.
> - **Published** as `mannix/<family>:<size>` (owner's choice): `whisper:large-v3-turbo`, `outetts:0.3`, `z-image:turbo` and `flux2-klein:4b`.
>   - Z-Image was GPU-tested before the push (1024² in 36 s), and a clean store pulled Whisper and OuteTTS and used them.
>   - Klein and Z-Image state no edit mode, so one Klein template edits as img2img on b97 and from reference images on M7.
> - **Catalog:** `Template` names and a PULL column in `xollama media list`.
> - **Next:** the M7 templates (Kokoro, Supertonic, KittenTTS, Wan, media-kit) once M7 is tested. The owner deletes `mannix/xollama-registry-test` and adds "needs xOllama" descriptions on the pages.

> **2026-10-02 — opencoti b97: row B re-check (#626 → #627).**
> - **Setup:** llama3.1:70b q3_K_S on the 3090, b97 `2610021340001` with its `ggml-cuda.so` beside it (`/srv/ml/xollama-phase2/engines/b97-2610021340001`), the same recipe as b177.
> - **Boot (bug-3515) is fixed.** `--kv-residency-mode auto` boots in 38 s on POSITION_WINDOW (window 256, host tail 32512) and answers.
> - **New defect: `auto` crashes on the long arm.** It dies with a CUDA OOM in `fattn.cu` (ring / `g_slotK` cudaMalloc) at about 18-19k tokens of a 22.6k prompt, reproduced 2/2; b177 completed that arm.
> - **`head` is clean:** 1.74 / 0.17 t/s on the short / long arm; `auto` gets 2.25 t/s on the short arm.
> - Row B stays open on opencoti's side. No pin moves.

> **2026-10-02 — Media endpoints, Phase 3: the OpenAI media routes, and a local model mirror.**
> - **Routes** (`server/media_routes.go`): `/v1/images/generations`, `/v1/images/edits`, `/v1/audio/speech`, `/v1/audio/translations`, and `/v1/audio/transcriptions` for a model with STT (any other model still goes to upstream's shim). `/v1/models` adds modalities and an `?output_modalities=` filter.
> - **Template control:** every field a client leaves out comes from the template's `defaults`, and `fixed` fields always do. `voice_map` maps OpenAI voice names.
> - **Queue:** one FIFO per engine (16 deep, 10 min), then 503 with `Retry-After`.
> - **Mirror** (owner: "we can't re-download them every time"): `xollama media fetch --dir` and `media create --dir` (`internal/mediahub/mirror.go`). The whole catalog is in `/shared/dev/opencoti/.opencoti/models/media`; `/srv/ml/media` is now a symlink to it.
> - **Live on solidPC, on CPU (dev c7 `2610020719001`):** a Klein image (template steps, cfg and sampler confirmed in the PNG), OuteTTS speech, Whisper transcription (exact) and translation, the modality filter, and two queued speech requests served in turn. 13 mutations, all killed.
> - **Live on the 3090 with b97 `2610021340001`** (handoff #626, staged with its `ggml-cuda.so`):
>   - Klein 1024² in 16 s, as a `data:` URL;
>   - Klein edit 200, but barely changed: img2img until M7's ref switch;
>   - OuteTTS speech in 4 s, Whisper transcription in 1 s, exact.
>   - The STT and TTS memory estimates are short by up to 0.3 GiB; Phase 0 and M7 settle the reserves.
> - **Open:** Cerebriline's own image tool against xollama. b97 has no `--diffusion-edit`, which M7 adds.

> **2026-10-02 — Media endpoints, Phase 2: the media runner, `hf.co` sourcing and `xollama media`.**
> - **Runner:** a model's media runs in its own media-only opencoti process (`llm/engine_media.go`), scheduled under `media:<manifest digest>` through one hook in `Scheduler.load` (`server/media.go`).
>   - Reserves go to the GPU with the most free memory.
>   - An engine missing a configured feature is refused at start.
> - **Capabilities:** `image_generation`, `image_edit`, `speech`, `transcription` and `video` show in `/api/show`.
> - **Media-only templates:** `create` and `show` now handle a model with no GGUF.
> - **Sourcing:** `hf.co/<repo>@<rev>:<path>` resolves by HEAD (`internal/mediahub`), and the server fetches it with upstream's `downloadBlob` (`/api/xollama/media/pull`).
> - **Discovery:** a catalog (Klein, Z-Image, Whisper, OuteTTS, Kokoro, Supertonic, KittenTTS, Wan 2.1/2.2, `media-kit`) and `xollama media list|search|files|create`.
> - **Live on solidPC (dev engine c7):** OuteTTS speech → Whisper transcription round-tripped; `media create` fetched Whisper (874 MB in 37 s) and attached OuteTTS to Qwen3-4B. 12 mutations, all killed.
> - **opencoti:**
>   - #623: mp3 encoding, Klein `ref` edit, combined-boot gate and `/v1/videos` are in M7;
>   - #624: audio.cpp TTS and mp4/h264 are in M7, and the provisional `--video-*` flag names were sent.
>   - xollama never encodes audio.
> - Next: Phase 3, the OpenAI routes, with image generation first for Cerebriline. Phase 0 waits on b97 and the M7 build.

> **2026-10-02 — Media endpoints, Phase 1: schema v7 `media`.**
> - **Schema:** `xollama.json` gains `media.image`, `media.stt`, `media.tts` and `media.video` (`types/xollama/media.go`).
>   - Components are named by digest. `create` writes each one as an `application/vnd.xollama.media` layer named `media/<kind>.<role>` (`create/xollama_media.go`, inside the `model-config` hook).
>   - Each kind's `defaults` are the template's engine settings; `fixed` lists the ones a request may not override.
> - **CLI:** `xollama tweak model` gains a row per setting (`cmd/tweak/media.go`). A component given as a path is hashed, then uploaded on write only when the server lacks it.
> - **Tests:** unit and mutation tests (11 mutations, all killed).
> - **Live on solidPC (scratch store):** Kokoro and Whisper were attached to a Qwen3-4B model, shown, re-run without re-upload, and garbage-collected on `rm`.
> - **opencoti #622:**
>   - no mp3 encoder in the engine (the owner decides between encoding in xollama and WAV);
>   - Klein edits are img2img until a switch;
>   - combined boot is ungated, so Phase 2 runs media in its own process;
>   - video is queued as M7.
> - Next: Phase 2 (launch and scheduler). Phase 0 waits on the b97 handoff.

> **2026-10-02 — Media endpoints: plan written (`plans/media-integration.md`).**
> - opencoti closed row M (#619, b97 `2610021340001`): image generation and edit, STT and TTS behind the OpenAI routes.
> - The plan attaches them to a model, or to a media-only template, through a `media` section in `xollama.json` (schema v7). Components are `application/vnd.xollama.media` layers named by role.
> - Routes: `/v1/images/*`, `/v1/audio/speech`, and `/v1/audio/transcriptions` when the model has STT (otherwise upstream's shim). `/v1/models` gains modalities.
> - SurfSense was read from source (666bbb07). Chat and embeddings already work; images, TTS and STT go through `openai_compatible` and LiteLLM's routes.
> - Engine gaps were mailed to opencoti: the Klein reference edit, audio.cpp for Kokoro, Supertonic and KittenTTS (GGUF in `audio-cpp/audio.cpp-gguf`), mp3, and video.
> - Owner decisions:
>   - push a registry test under `mannix` (the owner deletes it);
>   - SurfSense gets docs first;
>   - mp3 is asked of opencoti;
>   - the model template owns the media engine's settings: launch defaults plus a per-request fill-in, with a client value winning unless the field is `fixed`.
> - Video and SurfSense's other engine needs were sent to opencoti (#621).
> - Phase 0 test models are downloading to `/srv/ml/media`.
> - Next: Phase 1 (schema v7). The Phase 0 engine runs wait on the b97 handoff.

> **2026-10-02 — A forced link speed is now per GPU.**
> - opencoti #611 shipped patch 0512 (dev build 2610020826001), which accepts `OPENCOTI_LINK_GBPS=<pci>=<GB/s>,...`.
> - `tweak server gpu` now sends one entry per GPU of the load that has a forced link; a GPU without one is probed. The engine still plans each KV cache with the slowest of its GPUs.
> - Not gated on the engine build. Owner: there has been no first release, and every build is a dev build.
> - Also from #611: the link profile no longer reads a GPU's idle gen1 state, and `--link-probe` lists integrated GPUs.

> **2026-10-02 — Server settings, Phase 5: the engine's auto policies (schema v6).**
> - New settings, on `tweak model` and as `tweak server` defaults:
>   - `kv.rolling_window` (`--kv-rolling-window`: on, off or MiB);
>   - `draft.auto_mtp_policy` (`--auto-mtp-policy`);
>   - `fit.enabled` (`--fit`);
>   - `fit.vram_target_mib` (`--vram-target`).
> - `kv.residency_mode`'s help now carries opencoti #609's semantics.
> - A rolling window under `head` residency is refused, because head disables the window.
> - All but `--fit` are opencoti only.
> - These configs are stamped v6, so an older build refuses them rather than dropping them.
> - Not yet run against a live opencoti: eleven2go is paused for the rolling-window validation.
> - Phase 6: feature doc `docs/features/system-settings.md`. Open: the desktop app restarting its server for a restart-needed setting.

> **2026-10-02 — Server settings, Phase 4: the link probe in `tweak server gpu`.**
> - The GPU menu now has the engine measure each GPU's host link (`/api/xollama/link-probe`, which runs `opencoti --link-probe`, b62 or later).
>   - It shows the detected PCIe generation and lanes and the measured rate, and the link wizard starts from them.
>   - A backend with a model generating on it is not probed.
> - Measured on solidPC (dev build 2610020719001): the RTX 3090 runs at PCIe 3.0 x8 in a 4.0 x16 slot, 6.7 GB/s host to device.
> - The owner approved opencoti's per-device link force (`PCI=GBPS,...`). opencoti builds it alongside the rolling-window validation; until then a load uses the slowest forced figure among its GPUs.

> **2026-10-02 — Server settings, Phase 3: `tweak server gpu`; opencoti answered #608.**
> - `xollama tweak server gpu` sets the GPU policy:
>   - which GPUs models may use;
>   - priority (fill order, ahead of free memory);
>   - the backend for a GPU reachable through several;
>   - a forced link speed (GB/s, `4x16`, or a generation-and-lanes wizard);
>   - split auto/spread/single;
>   - split mode: layer, or row (CUDA only, unvalidated).
> - A model's own device pin still wins.
> - The engine takes one forced link figure per process, so a load spread over several GPUs gets the slowest forced figure among them; opencoti confirms that's right.
> - opencoti #609: per-device link force is queued at opencoti and needs the owner's go-ahead. It also gave the complete auto-policy list, the residency × rolling-window matrix (FINAL), the split modes (tensor unsupported), and confirmed the link probe is safe on an idle GPU. All of it is recorded in the plan.
> - Verified: mutation on the three placement hooks, race tests, lint, and a live smoke test.

> **2026-10-02 — Server settings, Phase 2: defaults for every model's settings.**
> - `xollama tweak server` now sets server-wide defaults for every `tweak model` setting a server may default: engine, flash attention, KV types, unified KV, residency, slots, session pooling and the speculative type.
>   - It uses the same flags, walk and consistency pass as `tweak model`.
>   - A bare run asks whether to change the defaults or the API key.
> - The defaults are merged under the model's own settings at launch (`WithDefaults`).
>   - The model wins, and a cache pair stays a pair.
>   - A default the model cannot act on is left out and logged.
>   - DCA, devices and council are a model's own settings and are not offered as defaults.
> - `tweak show model NAME` marks each setting `model` or `server`.
> - Verified: mutation, race tests, lint, and a live smoke test.
> - Next: Phase 3, `tweak server gpu`. Still waiting on opencoti #608: the auto policies, and residency mode vs the rolling window.

> **2026-10-02 — Server settings, Phase 1: `tweak envs` and `tweak show`.**
> - The server's `~/.ollama/xollama-settings.json` now overrides the environment.
>   - `envconfig.Var` and `XollamaOnly` read its `envs` section first.
>   - Engines get it through `envconfig.Environ()`.
>   - It is written only through `/api/xollama/settings`: from the server's own machine, never through a proxy, and with the key while one is set.
> - New commands:
>   - `xollama tweak envs NAME=VALUE`, `--unset NAME`, or no arguments to be asked;
>   - `xollama tweak show envs` (`--all` too), `show server` and `show model NAME`.
> - What each change does:
>   - Load-time variables apply at once; the command offers to unload the running models.
>   - Variables read when the server starts say a restart is needed.
>   - The API key and unknown names are refused.
> - With no settings file nothing changes. The Registry has a new `system-settings` row.
> - Verified: mutation (removing the `Var` hook fails two tests), the race detector, lint, and a live smoke test on a scratch server.
> - Next: Phase 2, server defaults for the `tweak model` settings.

> **2026-10-02 — Plan: server settings without environment variables.**
> - Owner: `tweak server` sets only the API key, but every server-wide setting should be real configuration. Asked for: `tweak server` (defaults for every pertinent `tweak model` setting), `tweak server gpu` (which GPUs, their priority, the backend, the PCIe link, split), `tweak envs` (environment overrides) and `tweak show server|envs|model NAME`.
> - Decided with the owner:
>   - The tweak file beats the process environment.
>   - Changes apply immediately where possible.
>   - A forced link is per GPU, set through a generation-then-lanes wizard.
>   - Priority is fill order.
>   - Split is auto, spread or single, plus the split mode.
>   - "Auto" means the engine's fit; residency mode and engine selection are offered as well.
> - Plan: `plans/system-settings.md`.
> - Engine questions to opencoti (#608): a per-device link force, every auto policy, residency mode vs `--kv-rolling-window`, split modes, and probing a busy GPU.
> - No code yet.

> **2026-10-01 — Fixes for 0427/0428's lost time: check tools read, folds stick, housekeeping is plain.**
> - `check_file`, and any tool whose name says check, lint, validate, verify or diagnose, now counts as read-only (5f29e671b). Researchers and critics get it, and the synthesizer's calls no longer count as changes. A write word still wins.
> - **Every fold now sticks.** Two causes, both found while testing the refused-root fold:
>   - `sentTokens` (194c9cab6, this morning) measured the client's raw messages through `apply`. `apply` drops a record that doesn't match, and the raw messages never match the members' view, so every fold was dropped the moment it was made. All 8 server folds of series 4 were dropped; series 3 had none. Now it measures the raw messages directly and the record is never touched.
>   - The refused-root fold and the idle fold folded the client's raw messages (`full`). They now fold the members' view (`hist`), as every apply does.
>   - Guards: `TestARefusedRootsFoldIsOfTheMembersView` (each site fails it alone) and `TestTheSentConversationIsMeasuredWhole` (fails with `apply` back in).
> - **A generic client's housekeeping is answered plainly.** A request without tools and without `council_chat_state`, whose messages already hold tool calls, skips the council: no members, no server fold. In 0427 each of Cerebriline's compaction requests took 13.5 minutes through the council. Edge case, documented in `council-integration.mdx`: a desktop chat that used web search and then turns it off is answered by the model alone after that. Guard: `TestAToolTasksHousekeepingIsAnsweredPlainly`, verified by removal.
> - Not yet run on eleven2go: testing there is paused for opencoti's gates.

> **2026-10-01 — Why council runs 0427 and 0428 lost time (analysis; no code change yet).**
> - Neither run ever got the game to parse. Every oracle run in both was a SyntaxError: the original one-bracket error on a long minified line (`dDec`) became "Unexpected token '{'" on the next method and stayed that way. 0427 ended as a TIMEOUT at 7,204 s. 0428 was stopped at 12:38 by the owner, with about 10 minutes of its cap left.
> - **The members could not locate the error.** Read-only tools are inferred from their names, and `check_file` has neither a read word nor a run word. So researchers and critics never get it, and for the synthesizer it counts as a change. 0428 called `check_file` 0 times (0427: 1), against 47 reads and 11 edits. The synthesizer edited a different long line almost every time, twice resending one unchanged. Plain 0425 called it 6 times, with 16 reads and 21 edits.
> - **Researchers and critics took most of the time.** 0428: 30 round trips with researchers or critics took 4,419 s (79% of the time in requests), against 31 synthesizer steps (1,079 s), over 5 synthesizer cycles. 0427: 3,070 s against 1,973 s.
> - **Server-side compaction is thrown away.** The refused-root fold in `councilChat` folds `full`, the client's raw conversation, while every other fold and apply uses `hist` (after `council.History`, which rewrites tool-call messages). The record's hash never matches, so each fold (about 6 minutes) is dropped by the next apply, the root is refused again, and another fold follows. 0428's last 20 minutes were three folds, each dropped.
> - **A client compaction runs through the whole council.** Each of Cerebriline's compaction requests in 0427 (route=direct, no tools) took 13.5 minutes: a server fold of the same conversation (6 min 16 s), a refused fold (5 min 39 s), then the summary the client asked for. Two of them, plus a 426 s round at 161k, account for most of 0427's last 2,000 s.
> - Analysis files: `/srv/ml/xollama-phase2/as-ollama/e2g-s4/` (`server-1.log`, `losttime-*.txt`).

> **2026-10-01 — A Q4_K_M council fits the 3090 at the same window, on kvarn2.**
> - Owner: IQ2_M costs about 3.6x the steps of Q4_K_M (v6 arms), and every council role pays it. New tags on eleven2go: `omni-council-q4km-kv2` (omnimerge-v4 Q4_K_M MTP, `kv: kvarn2`, `num_ctx` 196,608, 2 live slots, the council settings of `omni-council-think`) and its plain twin `omni-plain-q4km-kv2` (same, council off). A plain arm uses its council's KV type even where it would not need it (owner).
> - Measured on b208, 393,216 cells (196,608 x 2), all fully resident on the GPU:
>
>   | | IQ2_M + kvarn3 | Q4_K_M + kvarn2 |
>   |---|---|---|
>   | weights | 9,238 MiB | 15,339 MiB |
>   | KV cache | 5,672 MiB | 4,136 MiB |
>   | GPU in use | 19,202 MiB | 23,760 MiB (of 24,576) |
>   | one council turn | 282 s, 17,770 tokens, 50.7 tok/s | 221 s, 10,519 tokens, 47.4 tok/s |
>
>   The turn is one sample, not a measurement. About 800 MiB is left free, so 196,608 per slot is the ceiling for Q4_K_M on this card.
> - Also: `omni-plain-v4-iq2m-128k` (IQ2_M, 128k, default KV): `omnimerge-v4-mtp_tb:27b-iq2m-128k` with its `think_budget_message` fixed (it was a lone `"`).
> - Why plain omni went from ~300 s (0129) to ~2,000 s (0425): the oracle. Re-scored with v3, none of eight old fast fixes passes (0129: 16/23). The work grew about 4x (16 to 59 requests, 15.6k to 62k output tokens, 87-94% of it thinking), generation slowed from 60 to 46 tok/s (Q4_K_M MTP on stock to IQ2_M kvarn3 on opencoti), and prefill grew from 32 s to 613 s (contexts 28k to 98k). The 0129 setup reruns on Q4_K_M with the v3 oracle and medium thinking after series 4.
> - Council run 0427 (da40325d, first on the session fix): TIMEOUT in 7,204 s, the page does not parse. No engine abort; its conversation reached 161k.

> **2026-10-01 — A task sent again starts clean.**
> - A request with no assistant turn, on a session the server derived, drops what was kept for that session: the kept deliberation, the review desk, the held resume point and the compaction record. The derived id comes from the conversation's opening, so every run of the harness's task landed on the last run's session (0422, 0424 and 0426 all ran on `xo-efd33195b0dfad24`). The test showed this was worse than a stale note: without the reset, a re-sent task resumed the past run's council mid-turn from its held point, with no planner. A session the client names is never reset.
> - Guards: `TestATaskSentAgainStartsClean` (verified by removal) and `TestOnlyAConversationWithNoAnswerYetIsANewTask`.
> - opencoti fixed the overnight abort (#593 → #594): b32 `2610010811001`, patch 0489. The refusal is now an HTTP 400 `exceed_context_size_error`. It is a dev snapshot; eleven2go stays on b208 until the owner says otherwise.

> **2026-10-01 — Series 3 on eleven2go (2fa24de0): council 0 of 3 fixed, plain omni 1 of 2. A council's reported size is now the request's whole.**
> - Runs (cline 1bd850f60, generic wire, `PROVIDER=ollama`, `THINKING=medium`, 7,200 s cap):
>
>   | Run | Arm | Result | Time |
>   |---|---|---|---|
>   | 0422 | council | TIMEOUT, does not load | 7,203 s |
>   | 0423 | plain omni | broken, does not load | 2,874 s |
>   | 0424 | council | TIMEOUT, 18/23 (friction, run, jump, wall, left_edge) | 7,204 s |
>   | 0425 | plain omni | FIXED 23/23 | 2,012 s |
>   | 0426 | council | TIMEOUT, 22/23 (hud) | 7,203 s |
>
> - The check now runs through the turn: 0426 ran the program at 55, 587, 1,092, 1,469 and 1,861 s (0418: 51 s, then nothing until 1,989 s).
> - Where the council's time went:
>   - **The reported size was still a sum on resumed research rounds** (143k-393k on 0426; the window is 196,608). The compactor measured only the history before the turn's tool traffic. A generic harness's task is one message, so that history was too short to measure, and a turn with no front or planner call fell back to the members' sum. Cerebriline then compacted its conversation (0426: two compactions, about 1,500 s with the crash below). Fixed: the done chunk now reports the whole request the client sent, tool round trips included, rendered with its tools and tokenized (`sentTokens`). Guards: `TestTheSentConversationIsMeasuredWhole` and `TestTheDoneChunkReportsTheConversationsPrompt`, the latter verified by removal.
>   - **The engine aborted five times** (opencoti b208, `server-context.cpp:6852: GGML_ASSERT(n_ctx > 0 && n_prompt_tokens > 0)`, exit 6). Each abort came beside a "session allocation full … compact the session" refusal, while a compaction writer and the front ran together. Each cost about 10 minutes: a retry that waited 5 minutes on a closed pipe, then a 5-minute GPU discovery watchdog before the reload. Reported to opencoti.
>   - Every council run used the same xollama session (`xo-efd33195b0dfad24`), because the session id comes from the conversation's first message and the harness sends the same task each time. What a session keeps (the held resume point, the compaction record, the review desk, the kept deliberation, the root pool) may therefore cross runs. Not yet measured.

> **2026-10-01 — The done chunk reports the conversation's size; a turn's first run is its check.**
> - 0418's done chunks once reported a 229k prompt: the synthesizer's, which holds the plan and the findings on top of the conversation. Cerebriline sizes its context from that number and compacts at about 159k, so the council's own deliberation could fold the client's conversation.
> - The compactor now records what it measured on every pass (folded or not), and the done chunk reports that. Without a measurement it falls back to the front's or the planner's prompt; the synthesizer's is never taken as the conversation's.
> - Guards: `TestTheReportedPromptIsTheConversations`, `TestCompactMeasuresTheConversation`, both verified by removal.
> - A turn's check can now be inferred from one run. 0418 ran the program once at 51 s, before any change, and nothing ran it again until 1,989 s, because the check was inferred only from a call repeated across a change. Now, with no repeat, the turn's first non-reading call is the check when its tool runs something (run, exec, command, shell, bash, test). An edit tool's call is never taken, and a member's own inference still waits for a repeat. Guard: `TestATurnsFirstRunIsItsCheck`, verified by removal.

> **2026-09-30 — Council members get Cerebriline's output budget.**
> - Each member's reply cap is the least of three quarters of the council's window, the ceiling (`council.max_tokens`, default 16,384, settable 1,024-96,000) and the model's `num_predict`. It is the VS Code plugin's rule (#578), with a lower ceiling.
> - The thinking now sits inside the cap instead of on top of it. A level is a share of the cap, and `on` means medium. Each member is told its cap and its thinking share (Cerebriline's Output Budget section).
> - The reserve books the caps alone.
> - The Cerebriline harness now works for both plain arms:
>   - plain omni, 0411: FIXED 23/23 in 1,125 s;
>   - plain glm, 0412: FIXED 23/23 in 2,532 s.
>   Both ran on the CLI's old budget (49,152 / 12,288: the gateway fallback, not the plugin's 96,000 / 24,000), and 0412 overlapped a rebuild of Cerebriline's core (#580). They will be rerun once the CLI matches the plugin.
> - Runner-issued check: a directive's `check_call` (`council_check_call_v1`) is the turn's check, even through a shell tool. A synthesizer that changed something and ends without running it has the council make it. Needed because Cerebriline's `./run_game` goes through `run_commands`, which the council counted as a change (#581).
> - `council_read_many` dropped: `read_files` already takes several files, and one step already carries several calls.
> - **A generic harness now gets the council** (owner: the test is a council tag driven by a harness that does not know it is one).
>   - 0411 showed why this was needed: tools without `council_chat_state` had been a plain chat. Now they are the council's, and the server keeps the resume point itself.
>   - Read-only tools are inferred from their names.
>   - The check is inferred as the call repeated unchanged across a change.
>   - Resent thinking is not read by members.
>   - From this build on, a council tag is no plain arm: plain runs need a plain tag.
> - Plain arms on the parity build (96,000 / 24,000):
>   - plain omni, 0413: FIXED 23/23 in 2,197 s;
>   - plain glm, 0414: FIXED 23/23 in 1,189 s.
> - First council arm, 0415 (`omni-council-think`, bb7434ce): the council engaged on the plain request (front turn, 4,096 think budget), then ABORTED at 692 s. A researcher's forced report carried `maxLength` 2,000, which the engine cannot turn into a grammar. The fix drops the bound from the schema and asks a refused format again once without it.
> - A request whose `num_predict` is below 64 is a probe and is answered plainly. Cerebriline's fixed template probe sends two such requests (`num_predict` 1), and without this each would start a council.
> - Council arm 0416 (`omni-council-think`, 55d4baf7, generic wire, PROVIDER=ollama) ended **broken**: the game loads, but only 18/23 checks pass (friction, run, wall, left_edge and hud fail), after 4,815 s. The plain arms fixed it in 1,189-2,197 s.
> - The lane is paused (owner) while Cerebriline lands its `/chat` template-probe fix (#586/#587); eleven2go is on 19fd62cc. Runs after that fix are a new series, since past thinking may then be replayed.
> - **Why 0416 lost** (log in `/srv/ml/xollama-phase2/as-ollama/e2g-0416/`):
>   1. **Compaction, 1,987 s (41% of the run).** The done chunk's `prompt_eval_count` was the sum over all members, 161,214. The harness took that for its context size and ran its 5-step compaction on a ~50k conversation, each step a council turn. Fixed: the done chunk now reports the prompt of the last call on the conversation.
>   2. **Stopped at 18/23.** The synthesizer called the failures "minor" and said DONE. A reviewer refuted that. The synthesizer then re-sent the same unchanged result, and the second reviewer, fed only a file read, confirmed it. Fixed:
>      - a refutation stands until a change answers it, and DONE is refused meanwhile;
>      - a review with no change since judges the last check;
>      - the verdict wording counts any failure anywhere in the output.
>   3. **Slow to 18/23: 2,588 s, where plain took 309 s.** Six cycles, each fixing the one runtime error the last check named. Each cycle spent 3-5 min on planner, researchers and critics before the synthesizer's minute, and ended at the step bound with a RETEST. Fixed (owner approved):
>      - the synthesizer's step bound counts from its check's last change of output (`cycleSteps`), so it keeps its cycle while each fix moves the check;
>      - a cycle is capped at 4× its steps;
>      - a new research round starts only when the check stops moving, or when the synthesizer asks for one.
> - **Council arm 0417** (9d3a2d2f, Cerebriline d3c58e1a9, new series): TIMEOUT at 7,203 s, the game never loading.
>   - The synthesizer spent nine cycles on edits built on a wrong theory ("trailing semicolons" on class methods), and restored the original file twice.
>   - It ran the check twice in two hours. Every cycle ended at its step bound, never on a check result.
>   - The council-issued check never fired. The check had not been inferred, because the front and each synthesizer cycle start their own turns, so no one member's turns held two runs of it. And a cycle ended by its steps skipped the end-of-turn issue.
>   - Fixed: the check is inferred from the whole turn's tool traffic (`InferCheck`, server side), and a cycle whose steps are spent with changes unchecked has the check made before it ends.
> - **Council arm 0418** (6c03a9cf): **FIXED 23/23 in 3,333 s.** The first council fix driven by a generic harness.
>   - First edit at 788 s. The checks went 20, then 21, then 23 passed between 2,493 s and 2,956 s. No harness compaction ran.
>   - Left: the check was not run from 51 s to 1,989 s. The only earlier run was the front's, and inference needs two runs; a single run of a run-type tool could seed it.
>   - One reported prompt still reached 229k. A member's prompt can exceed the client's conversation.
> - Plain control for the council tag: `omni-plain-kv3-384k` on eleven2go, a copy of `omni-council-kv3-384k` with `council.enabled` off. Plain arms of the new series, one run each:
>   - plain omni, 0419 (`omni-plain-kv3-384k`): FIXED 23/23 in 2,672 s;
>   - plain glm, 0420: FIXED 23/23 in 419 s.
>   - The council, 0418, took 3,333 s: 1.25x plain omni on the same weights.

> **2026-09-30 — 11.29 started: step limits, a spot-checking critic, empty-reply retries.**
> - Plain omni through Cerebriline's harness (`native.sh`, eleven2go lane): FIXED 23/23 in 1,125 s. The engine budget was 12,288; asked Cerebriline why (#577).
> - Researchers take 4 tool steps and critics 3. A step is any turn that called a client tool. Past the limit the call is not made, and the member reports.
> - The critic checks only the claims the answer depends on.
> - An empty plan or report is asked again once without thinking. No two researchers share a fallback brief.
> - The scope of 11.29, with the owner's choices (16k default ceiling; all four structural changes), is in the plan.
> - Every member call is asked again when it fails or stalls (5 min with nothing sent, 20 min in all): up to twice, never for a refusal or a full owner.
> - Members end with typed results the council answers itself, rendered into the flow's existing form:
>   - researchers call `council_report`: proposals with their exact old text, claims, reads by ref;
>   - critics call `council_verdict`;
>   - a checking synthesizer calls `council_done` or `council_retest`.
>   At the step limit the member's call carries its result's schema as the format.
> - Each member step now replays the reasoning of the member's last step. Reasoning that hit its budget is replaced by a short note in the member's own voice (Cerebriline's condensation).
> - A compaction fold is now one call, the writer's. The critics' review and the retrospective are opt-in (`council.context.review`, `.retrospective`).

> **2026-09-30 — glm council fixed hard at 13x the plain cost. The council will be rebuilt on Cerebriline's budgets.**
> - **All-glm council** (every role on glm-5.3-flash:cloud, max_tokens 131072):
>   - Fixed hard, 23/23 traps.
>   - It took 10,866 s, 60 trips, 3.44M tokens in and 875k out. Plain glm took 300-814 s and 29k-70k out.
>   - The first edit came only after 62 min.
>   - One critic made 50 `find_text` calls in a row. The critics used 1.94M input tokens, about 44k per call.
>   - Researchers wrote a median of 10.6k tokens per call.
>   - The synthesizer broke the file 3 times before the fix.
>   - The owner stopped the rest of the batch (glm on one role at a time).
> - **Plain omni, thinking on** (`think_budget "medium"`, num_predict 131072):
>   - Failed, with the original SyntaxError, after 1,815 s and 21 trips.
>   - "medium" is a quarter of the reply room, so the engine budget was 32,768 (`common_reaso: activated, budget=32768`). The engine also forgives spent tokens on a reset sequence (up to 13,435 in this run).
>   - One turn ran 1,062 s with no tool call.
> - **Owner's direction:**
>   - Thinking stays on.
>   - The manic harness here is not reliable enough to decide anything; measure plain and council through Cerebriline's harness (eleven2go lane, oracle v3).
>   - Port Cerebriline's approach into the council: the automatic output budget; a customisable ceiling, low by default; mapping thinking levels and tokens onto the output; reasoning replay; reasoning condensation; and one-step agentic replay compaction instead of the 5-member fold.
>   - Asked Cerebriline for source pointers and the harness commands (mail #573).

> **2026-09-30 — solidPC's service (11434) moved to `0.35.0-dev.562eea98`.**
> - The owner asked for it. The payload was assembled with `scripts/docker-assemble.sh` from the pins: runtime b11081 (the inputs digest matches), upstream GPU backends, and opencoti b208. No native code was rebuilt.
> - It was swapped by `/srv/ml/xollama-phase2/solidpc-swap-0.35.0.sh`. The old binary and `lib/ollama` are kept as `.bak-20260930-103348`. The unit's drop-ins (11434, debug, parallel 1) are unchanged.
> - Checks: `/api/xollama` lists 11 features (council included); CUDA0 is on opencoti and the Vulkan iGPU on llamacpp; `qwen3.5:2b` ran on the opencoti engine at 130 tok/s.
> - The service now serves council models, which the 05c16dfa build refused.

> **2026-09-30 — Harness v3 (the logic oracle), the glm plain baseline, and 11.27 (a role's cap and window are its own model's).**
> - **Harness v3** (`/srv/ml/xollama-phase2`, `manic/README.md`). `manic/bin/run_game` is a compiled, obfuscated build of `manic/work/run_game.logic.js` (root 0600). It prints the old verdict plus `game_logic`: 23 behavioural traps on the game's own rules. A run is fixed only when the page loads and the traps pass. The model sees which traps fail but cannot read them.
> - **Re-score of every earlier run.** 12 of 28 old "fixed" runs keep the game's rules: omni council 2/12, omni plain 8/13, glm 2/3. Both of a0968aea's hard council fixes fail (empty `pop()`; falling through the floor). Table: `manic/work/logic-rescore-all-20260930.tsv`.
> - **Fixed in the oracle:** a countdown-trap false positive, which jumped the clock without frames, found live. Rebuilt; sha f13e481f. Sent to the ollama session for Cerebriline (#569-#571).
> - **Plain glm-5.3-flash:cloud, hard, thinking on, `num_predict` 131,072:**
>
>   | Run | Result | Trips | Wall | In | Out |
>   |---|---|---|---|---|---|
>   | 1 | fixed, 23/23 | 6 | 814 s | 80,463 | 69,755 |
>   | 2 | fixed, 23/23 | 13 | 572 s | 367,051 | 57,588 |
>   | 3 | fixed, 23/23 | 10 | 300 s | 144,875 | 28,985 |
>
>   Mean 562 s, 197k in, 52k out. The longest replies were 59k, 48k and 24k tokens, mostly thinking. The old 16,384 cap would have cut every run.
> - **11.27.** The council's built-in caps (1024-3072 plus 2048) would have cut every glm role. Now a role's stated `max_tokens` holds on its own model. Unstated, a cloud or other-model role inherits its template, and a lead role takes the council model's `num_predict`, else the built-in cap. Only lead roles are booked in the owner (`councilReserve`). There is a new `council.<role>.num_ctx` (schema v5), and members on another model shed the client's `num_predict` and `num_ctx`.
> - **11.28.**
>   - The owner's reserve now books each lead member's think budget beside its reply cap: a stated `think`, else the builder's ceiling of 4096. It had counted only the cap, although a member is sent cap + budget.
>   - A token budget is sent with the model template's `think_budget_message`, to local members and xollama endpoints alike.
>   - Measured in the omni councils: 22-29% of thinking calls exhausted the 2048 budget.
> - **Also fixed:** the route decision, the direct answer and the front turn ran on the lead whatever their role's model, as the first all-glm smoke run showed. They now run on the planner's and the synthesizer's model.
> - **Next.** Set glm roles to `max_tokens` 131,072 in the four glm councils; run all-glm, then critic, researcher and planner one at a time, with glm as the builder.

> **2026-09-30 — Hard on eleven2go with a0968aea, stopped at 4 pairs (the owner's call): council 2/4, plain 3/4.**
> | Pair | Council | Plain |
> |---|---|---|
> | 1 | fixed, 81 trips, 4,695 s | fixed, 59 trips, 1,353 s |
> | 2 | fixed, 46 trips, 2,278 s | fixed, 56 trips, 499 s |
> | 3 | lost at trip 41: a health dial failed (fixed on dev, `engine-health-retry`) | not fixed, 120 trips, 1,298 s |
> | 4 | lost at trip 118: owner full, waited out (fixed on dev, 11.26) | fixed, 64 trips, 590 s |
>
> The council's first fixes of hard. Neither council loss was a reasoning
> failure; both are fixed on dev and not yet measured live. Council run 5 was
> stopped at about 10 minutes, with its run directory marked `-STOPPED`. Next,
> the owner's direction: test with the cloud model.

> **2026-09-30 — 11.26: a full owner compacts and the turn resumes.**
> Council run 4 of hard (a0968aea, eleven2go) failed at trip 118. A 120k
> root plus a 39k stage filled the 196608-cell owner, and the next worker's
> 39662 cells did not fit. The engine said "compact the session"; xollama
> waited two minutes and failed. The owner's choice: compact on the refusal
> and retry the member. Built: owner-bound members are refused at once
> (`llm.ErrOwnerFull`, 507). They wait only while a sibling may give cells
> back. Otherwise the turn lets its pools go, folds the conversation, rebuilds
> the root, and resumes from the last checkpoint.
> `server/council_owner_full.go`, the `context-window` hook row extended.
> Four tests, each piece mutation-checked; server, llm and council pass under
> `-race`, lint clean. bug-186. Deploy after the batch.

> **2026-09-30 — Hard on eleven2go with a0968aea: 5 of 6 fixed so far; a failed health dial lost council run 3.**
> - Council: run 1 fixed in 81 trips (4,695 s), run 2 in 46 trips (2,278 s).
>   Before this build the council had never fixed hard. Run 3 ended at trip 41:
>   a health check to the live engine failed on loopback (`connectex: A
>   connection attempt failed…`), and the engine answered three seconds later.
> - Plain: run 1 fixed in 59 trips (1,353 s), run 2 in 56 trips (499 s).
> - Council run 1 kept its layers on 76 of 81 requests, and 30 builds prefilled
>   261k tokens. The layer log shows no per-researcher split.
> - Fix on dev, not deployed until the batch ends: `engine-health-retry`
>   (`llm/engine_health_retry.go`, one hook line). On opencoti only, while the
>   engine runs, a dial that failed is tried up to four more times with
>   backoff; stock llama.cpp keeps upstream's single failure. Three tests
>   (mutation-checked), `-race`, lint, 31 hooks registered. bug-185.
> - The batch continues on a0968aea (pairs 3–5), so all ten runs share a build.

> **2026-09-30 — 11.25: with broadcast on, researchers never shared their stage.**
> The pools of the same length on solidPC's hard run (13 and 14, 6724) were
> round 2's two researchers, one layer each. The member log shows their
> messages equal up to each one's own instruction, then the mates' notes. The
> layer was cut before the last user message (the notes), so it held the
> instruction. Now `council.OwnPart` cuts at the member's first instruction
> after the last plan. That also covers the synthesizer's appended system
> prompt and the nudges in a tool loop, which had put a member's own turns into
> its layer. Pool texts and where siblings diverge are logged
> (`council_layer_log.go`). Tests (mutation-checked); server and council under
> `-race`, lint clean. bug-184.

> **2026-09-29 — 11.24: a turn's stage layers are kept across its tool round trips.**
> On hard, 265,334 of the 582,509 tokens the pool builds prefilled were
> layers the previous request had just released. Each round trip is a new
> request, and only the conversation's root survived one. Now a request
> ending with the members' calls stashes the layers it used, and the next
> request of the same turn adopts them, on the same runner and kept root.
> Anything else releases them, as does 10 minutes without a round trip.
> `server/council_layers_kept.go`. Six tests (mutation-checked); server and
> council suites pass under `-race`, lint clean. Live on solidPC's 3090
> (569747788, `omni-council-ab5`, hard, 40 trips): 37 of 40 requests stashed
> their layers and the next adopted them. Resumes built no pool. Pool builds
> prefilled 275,292 tokens in 34 builds (6.9k a trip), against eleven2go's
> 582,509 in 68 (12.1k a trip, a different host and model, so indicative).
> Nothing failed to release. Not fixed in 40 trips (3,012 s). Open: two pools
> of the same length (6,724) built 7 s apart on one parent; the texts were not
> logged, so a duplicate build is not ruled out.

> **2026-09-29 — 11.23: the 12800-token windows were a reviewer sized by a character estimate.**
> The small windows on hard were the members sized to their own request (a
> background reviewer, the builder), not the council's working members (116
> requests in 196608-token pool windows). `ownWindow` counted characters/3 as
> tokens; a critic's 13196-token review was sized 12800 and refused, and that
> review was lost. Now the request is rendered and tokenized as sent (the
> tree's counter, handed to the background reviewer's member set); half the
> characters only if counting fails. Tests (mutation-checked), server and
> council suites under `-race`. Open: a reviewer shares no prefix with the
> tree and prefills its whole request each time.

> **2026-09-29 — 11.22: a stuck re-plan has to change the task list.**
> From the hard analysis: the planner said it would replace the failing part
> whole and kept every task open. Now, while the stuck note is in force, a
> re-plan whose list update refutes no task or adds none is asked again once
> with `keptNote` (which says what it left undone, and that a whole
> replacement is a task a researcher writes out and the synthesizer applies in
> one write); the second answer stands. `approachKept`/`keptNote`
> (`stuck.go`), `ReplanAgain` (`steps.go`), `run.go`. Tests on the real
> round-2 list and a run-level one (mutation-checked); council and server
> suites pass under `-race`. Not measured live yet (eleven2go lent to
> opencoti). Next, in the owner's order: the 12800-token member windows (the
> owner: not low priority), the engine memory note to opencoti, the hard
> rerun when eleven2go is free.

> **2026-09-29 — Why the hard pair ended as it did: the host ran out of virtual memory, and the council's change of approach never became a task.**
> Engine deaths (eleven2go server log, Windows event 2004): both followed a
> low-virtual-memory condition. 15:34:55: our b208 engine 33.2 GB + opencoti's
> own test engine on the 9070 (2609291336001) 21.8 GB; 15:36:37 SIGSEGV in the
> CUDA graph path. 16:00:30: 37.3 + 18.6 GB; 16:00:40 `cudaGraphInstantiate`
> out of memory, abort 0xc0000409; Edge crashed OOM the same second. Commit
> limit 63 GB on 31 GB RAM. Our engine's host footprint is large for a 10 GB
> model: 10 sequences, up to 32 context checkpoints each at 85-250 MiB (8.3 GiB
> live at the second death) plus the prompt cache. Contention, not a new defect.
> Plain did not localize the fault either: 20 trips on the same template-literal
> theory with the check unchanged, then `write_file` of the whole file at trip
> 22, which passes `run_gamefull.js` exactly as `reference.html` does. The
> council never used `write_file` (16 local edits). The stuck note fired (58
> times, "or replace the failing part whole"), and planner round 2 wrote "instead
> of piecemeal fixes, I'll replace the entire JavaScript section", but its
> briefs kept the refuted theory (task #4, template literals), left every task
> `open`, and assigned the rewrite to nobody; the synthesizer applies what
> members propose, so it made local edits again. Round 5 narrowed to "the Level
> class methods for unclosed braces" (the actual fault, `Level.dDec`) two
> minutes before the engine died, at trip 48 of 120. Also: four member requests
> got a 12800-token engine window; one critic's 13196-token request was refused.

> **2026-09-29 — A quantized V the engine refuses without flash attention is retried at f16 (`kv-fa-retry`); hard: plain fixed, council not, both runs ended in an engine death.**
> llama.cpp resolves `--flash-attn auto` from the actual placement
> (`llm_fused_op_flash_attn_probe`) and then refuses a quantized V. Upstream
> v0.35.0 sends the same flags and has no retry, which corrects my earlier
> claim that upstream falls back to f16 (only its old Go runner did). The
> owner chose a single retry: on exactly that refusal, relaunch once with V at
> f16 and warn, only for a V xollama asked for (the model's `kv.v` or
> `XOLLAMA_V_CACHE_TYPE`). `OLLAMA_KV_CACHE_TYPE` alone keeps upstream's
> failure. `llm/engine_kv_fa.go` plus three marked lines in
> `llm/llama_server.go`; four tests, the upstream gate mutation-checked.
> Verified live on solidPC's xollama-dev (`council-c365.sh`, now the
> `xollama-kvfa-wip` build, b208 at the pin): `omni-council-64k` (`kv.v`
> q8_0) CPU-only was refused, retried with `v=f16` (KV 98 → 128 MiB) and
> answered; the failed start cost 11 s. solidPC's 3090 was busy with
> opencoti's gemma-4-31B run, hence the CPU-only probe.
> Hard on eleven2go (5ce5f7e7, 120 trips, `MANIC_NUM_PREDICT=16384`):
> **plain fixed** in 24 trips, 232 s (oracle PLAYING), and then its next
> request died with the engine (`wsarecv: forcibly closed`); **council not
> fixed**, 48 trips, 1440 s, ended by a critic request over its 12800-token
> slot and then `CUDA error: out of memory` in `cudaGraphInstantiate` on the
> 3090. The first plain start ran without the reply cap and was aborted after
> one reply ran more than 20 minutes (kept as `*-ABORTED-uncapped`). Next:
> the eleven2go server log for both engine deaths.

> **2026-09-29 — Every load names its model in the server log (`load-log`).**
> The engines log a load only by its blob path. `server/load_log.go`, from one
> hook line before `newServerFn` in `server/sched.go`, now writes three Info
> lines first: `loading model` (name:tag, blob, shards, drafter, projectors,
> adapters), `model file` (family, quant, parameters, size, layers, embedding,
> heads, experts used/total, sliding window, trained context) and
> `model placement` (devices, num_ctx, parallel, batch, predicted memory). All
> from the GGUF metadata the estimator already parsed and the placement
> already made: no read, no computation. Logged on every engine, llamacpp
> included, by the owner's decision (a Go log line, not behaviour). Tests
> `TestALoadIsLoggedByTheModelsName` (mutation-checked) and
> `TestALoadWithoutAFileStillNamesTheModel`; Registry row `load-log`. Not yet
> deployed: eleven2go is running the hard pair.

> **2026-09-29 — Versions follow upstream's, with release candidates; PR #5 is `release: v0.35.0-rc.1.xollama`.**
> Owner's rule: a version always follows the upstream release dev is based on.
> Three forms: `v<upstream>-rc.<k>.xollama` (a candidate, the dev builds, never
> promoted), `v<upstream>-xollama` (the release, which must ship the tree of
> the last published candidate and so takes a short install check), and
> `v<upstream>-xollama.<n>` (a re-release, no candidates, full check). The
> owner first proposed `xollama.rc<k>`. Measured against both sorters in the
> release path, that sorts after `xollama.3` under semver (the updater) and
> between `xollama` and `xollama.1` under `sort -V` (the workflow), so the
> updater would have offered a candidate to an install already on the release.
> With the candidate before the fork's name, both sorters agree and no
> comparator of our own is needed. `xollama-release.yaml`: the title pattern,
> a `kind` output, the tag filters, and the tree rule for a release.
> `discord-announce.yaml` never announces a candidate. `app/updater`: the order
> is documented, and `TestReleaseNamesOrderAsTheyShip` plus
> `TestACandidateMovesToItsRelease` hold it (compiled for Windows here; they run
> on CI's windows and macos legs). RELEASE.md's "Versions and tags" and step 7
> (the short check) are rewritten; CLAUDE.md and the docker docs follow. PR #5
> (head 339ef4b6, notes as before: v0.35.0 base, b208, council 11.17–11.21)
> is retitled from the never-cut v0.34.4-xollama.3. Budgeted localization is
> dropped (owner); the escalate measurement is later.
> Hard runs started on eleven2go's 3090 (5ce5f7e7, plain then council, 120
> trips each, up from 60, since both arms ran out at 60 on 2026-09-28; plain
> at 120 stays at about 320k of the 384k window). The owner lifted the hold on
> eleven2go for the 3090; the 9070 XT stays opencoti's (mail #556 sent).

> **2026-09-29 — Medium council twice on 2da8f3fd (11.21): fixed twice; the stuck path fires live.**
> - Run 1: FIXED, 27 trips, 939 s, 1.21 M prompt tokens, 6 edits (0 missed).
> - Run 2: FIXED, 45 trips, 2,312 s, 2.99 M prompt tokens, 10 edits (1 missed).
> - The server log now carries `same` 78, `moved` 55 and the stuck note 41 times; on 4770e33b it was `same` 0, `moved` 149, stuck 0.
>   - In run 2 the planner saw "same" at re-plans 2 and 3, with the stuck note. Then the checks moved (4 and 5), and it fixed the task.
> - Medium council across today's builds: 26 fixed / 60 not / 31 fixed / 60 not / 27 fixed / 45 fixed. Plain: 11–15 trips, 125–132 s.
> - Deployed `5ce5f7e7` (the line-number hint) to eleven2go.

> **2026-09-29 — The consultants' answer to csl-2026-09-29-1156-aa48, and why they read old code.**
> - Their code review of `quote.go` was mostly wrong: no replay, a guard that disables itself, a per-turn budget. The main checkout they read (their `cwd`) was on `sync/upstream-v0.35.0` at `ce7f5147`, two fixes behind. Everything since was committed from a separate worktree on `dev`. My mistake, not the skill's.
>   - Fixed: the main checkout is back on `dev`, and the worktree is removed.
> - Kept from the review: a quote that copies the read's line numbers is now answered in place (`numberedQuote`, `TestAQuoteWithLineNumbersIsAnswered`, which fails with the branch off).
> - Held by the owner: their #1, budgeted localization (a narrowing brief when the check names no place), and the escalate measurement ("first we stabilize"). Their refined hidden-progress rule is recorded, not built.

> **2026-09-29 — Why the council missed the brace: every check read as progress (11.21).**
> - 4770e33b run 2 had 7 identical `SyntaxError`s, yet the planner was told "changed ... progress" every cycle: 149 `moved` notes in the log, 0 `same`. So the stuck note never fired, and the first theory (template literals) was never refuted.
> - The cause is `lastCheck` again. "The first read after the last change" took the synthesizer's read of the file it had just edited, after it had run the check and edited again. The e75c7c3e logs show the same: 140 `moved`, 0 `same`.
> - Fix: the check is the read-only call the member calls most after its first change. One repeating the previous check is taken first. Replayed over run 2, the stuck note fires from cycle 3.
> - Guard `TestTheCheckIsTheCallTheMemberChecksWith`, which fails on the old rule exactly as live.

> **2026-09-29 — Medium council twice on 4770e33b (replay): fixed once, unfixed once.**
> - Run 1: FIXED, 31 trips, 784 s, 1.51 M prompt tokens, 8 edits (1 missed). That is the council's fastest medium fix so far.
> - Run 2: UNFIXED at the 60-trip cap, 1,644 s, 4.10 M prompt tokens, 11 edits (2 missed).
>   - It failed in a different way: all 7 checks returned the same first error (the stray `}` ending `dGrid`), and the council never located it.
>   - It made 36 `find_text` searches, 14 of them by researcher 2, and edited elsewhere.
> - Misses at the client fell from 13 of 32 edits (`cf223635`) to 1 of 8 and 2 of 11.
> - Sent to the consultants as follow-up `csl-2026-09-29-1156-aa48` (7 of 11 in the chain), with a review request for `quote.go` and `directive.go`, the re-plan cost, and the escalate measurement.
>   - Per the owner, n = 5 per cell with the seed fixed is planned for later.

> **2026-09-29 — 11.20: the read follows the member's own changes.**
> - The member's own changes to a target since its last read, when they went through, are now replayed onto that read. A whole write is taken as the text itself.
> - So a misquote right after an edit is answered in place too. On `cf223635` those were nearly all of the 13 misses.
> - Guard `TestTheReadFollowsTheMembersOwnChanges`, which fails with the replay off.
> - Next: deploy, and run medium twice.

> **2026-09-29 — Medium council after 11.20: fixed once, unfixed once; 78e49747 deployed on eleven2go.**
> - Run 1 on `96ff1f5d`: FIXED, 26 trips, 1,078 s, 3.20 M prompt tokens, 6 edits (1 missed at the client). This is the council's best result on medium so far (earlier: 34 / 54 trips).
> - Run 2 on `cf223635`: UNFIXED at the 60-trip cap, 3,786 s, 5.67 M prompt tokens, 32 edits (13 missed at the client).
>   - This build adds the cue line in the front's prompt. At n = 1 each, run-to-run variance can't be told apart from the change.
> - Why the guard let run 2's misses through: almost all of them follow a successful edit to the same file (trips 34→35, 39→40, 45→46). The guard then treats the member's last read as stale, by design, and forwards the edit. One followed only a partial `find_text` read, which it also skips.
>   - Next step for 11.20: replay the member's own successful edits onto its last read, so the read stays current after a change.
> - Deployed `78e49747` (v0.35.0 + everything above) to eleven2go: `0.35.0-dev.78e49747`, `council_directive_v1` advertised, `/v1/systemone` answering.

> **2026-09-29 — Upstream v0.35.0 synced (fork manifest `b723d1ce`).**
> - `sync/upstream-v0.35.0`:
>   - `1ab773d7` merged the tag. One conflict, `server/routes.go`: the carried tokenize routes stay beside upstream's new `/v1/systemone`.
>   - The 24 patches followed as `--no-ff` merges at the manifest's shas, in order (`9d7b8793` … `7d479188`; the table is in CARRIED-PATCHES).
>   - Then `dev` was merged in.
> - Every rebased patch has the same diff as at v0.34.4 (`git patch-id`). Conflicts were resolved `-X ours`, owner-authorized; every merge was checked to add nothing over its first parent.
> - Fixed: six new upstream tests in `cmd/bench/bench_test.go` set `OLLAMA_HOST`, which the fork ignores by design, so they reached a live server (404). They now set `XOLLAMA_HOST`, as the file's other tests do.
> - Checks: `go test ./...`, `-race` on the main packages, `golangci-lint` 0 issues, `check-hooks` and `check-compat-origin` all pass.
> - llama.cpp stays b11081, and the runtime pin does not move. `main` stays v0.34.4 until the next release PR.

> **2026-09-29 — The council for harnesses: instructions, the directive and the user's cues (plan Phases 1–3).**
> - `ChatRequest.Council` (`council_directive_v1`) states the turn's `mode`, `instructions`, `build`, `evidence` and `check`.
>   - `answer` is the synthesizer alone; `escalate` and `deliberate` start the council with no front turn or route decision.
>   - A stated build replaces the builder, and its `max_tests`/`max_steps` stand within the builder's bounds.
>   - The evidence is verbatim, and the agent's last check is the council's first comparison point.
>   - A named check tool replaces the `lastCheck` guess. An unknown mode or slot is a 400.
> - Instructions by slot, from the model (`council.instructions`, `council.<role>.instructions`) and the request. The council-wide ones sit in the charter's shared prefix.
> - The route decision and the front read the user's cues about care. A stated mode skips them.
> - Also: the medium council on `96ff1f5d` (11.20) is running on eleven2go. The upstream v0.35.0 sync is on `sync/upstream-v0.35.0`, paused at `up-think-budget`'s conflicts. All 24 rebased patches have the same diff as before (`git patch-id`), so HEAD's side is right; resolving them needs the owner's go-ahead.

> **2026-09-29 — The consultants answered; a misquoted change is now answered in place (11.20).**
> - `csl-2026-09-29-0846-320d` (34 min). Ranked: (1) a hidden-progress signal, (2) repairing edit quotes, (3) the harness directive, (4) batching by a runtime prompt, (5) runtime escalation, (6) Stream-and-Sift. Measure n = 5 per cell with seeds fixed and jitter 0 before the cloud tests.
> - Built (2): `internal/council/quote.go`. When a writer's own last read of the same target shows a long start of the change's quote but not the rest, the call is answered in place with the read's own text where the match stops. No trip. At most 4 per member. Four tests, three of which fail with the guard off.
> - Not built (1), as proposed. Its signal ("same check output, but a write was accepted, so continue") is exactly 96edc4ae's failure: accepted syntax conversions and the same error six times. It would undo 11.19. The correction also stands: on e75c7c3e the rewrites of `dIt`/`dPw` were no progress, and the real faults surfaced one per check, as in plain.
> - Not built (4). It is a prompt at the step budget, and plain also edits once per trip. The cost is the re-plan cycles (≈1,300 of 1,954 s), not the synthesizer's trips.
> - The harness review is recorded in `plans/council-harness.md` (Review): verbatim evidence, `answer` skips the route, instructions in the charter, the mode holds for the turn, and an optional check tool named by the harness.

> **2026-09-29 — Plain medium on e75c7c3e: fixed in 15 trips / 125 s. A correction: `dIt`/`dPw` were never faults.**
> - Plain: 15 trips, 125 s, 549 k prompt tokens, 3 edits, all applied. It changed exactly three places: the extra `}` ending `dGrid`, a missing `sX`, a missing `initClouds`.
> - Correction to earlier entries and to the consultants' brief: `} })};` at the end of `dIt` and `dPw` is valid JavaScript (a class body allows a stray `;`; checked with node).
>   - The council's seven failed edits on `dIt`'s ending were attempts to fix text that was never broken. Those rewrites were no progress, not hidden progress.
>   - What diagnosing a non-fault costs is now part of the consultation (injected into `csl-2026-09-29-0846-320d`).
> - Plain run 2 confirms it: fixed in 11 trips / 132 s, 305 k prompt tokens, 3 edits, all applied. It fixed `dGrid`'s brace, added `sX`, and added the missing top-level functions in one block. Again it never touched `dIt` or `dPw`.
> - Council vs plain on this build: 34 / 54 trips vs 15 / 11, and 1,954 / 3,054 s vs 125 / 132.

> **2026-09-29 — Medium council run 2 on e75c7c3e: fixed again, 54 trips / 3,054 s.**
> - Two of two runs fixed on this build (34 trips / 1,954 s, then 54 / 3,054). Plain: 12 / 114.
> - Run 2 cleared the syntax errors by trip 35, then followed each runtime error one per check (`initClouds`, `setupLevel`, `sX`, `gameLoop`). 6 of its 21 edits missed their text.
>   - Re-plan cycles cost 140–290 s per trip; the synthesizer's own trips cost 15–30 s.
> - Usage (calls / prompt tokens): synthesizer 62 / 2.08 M, researcher 50 / 1.44 M, critic 19 / 0.51 M, planner 7, reviewer 6, front 5, builder 1. Total 4.21 M.
> - Both runs and today's fixes went to the consultants as a follow-up of `csl-2026-09-28-1844-26be`. The harness plan went with them for review.

> **2026-09-29 — Plan: the council for harnesses, and an integration guide.**
> - The owner wants the council adaptive in a chat, and usable by agents and as an escalation path, with Cerebriline first. A harness should drive the builder and the council, and say how the council is built, to save trips and avoid mode switches.
> - New plan `plans/council-harness.md` (PROPOSED):
>   - Phase 1: instructions for the council and the builder, at model and request level.
>   - Phase 2: the harness directive `council_directive_v1` (`mode` answer/escalate/deliberate/auto, a stated `build` that replaces the builder call, `evidence` as prior failed checks).
>   - Phase 3: adaptive chat from the user's cues.
>   - Phase 4: Cerebriline, built by the ollama session, with quality feedback.
> - Phase 0 built: `docs/xollama/council-integration.mdx`, the integration guide for harness authors. It covers today's contract, the three use cases, and the planned parts marked as planned.
> - Phases 1–4 wait for the consultants' answer to the follow-up, which is sent after medium run 2.
> - Owner's decisions: the field is `council`; `answer` mode offers no hand-off; a harness `build` may override the model's `max_tests` / `max_steps` up or down (a user setting in the harness), within the builder's bound.

> **2026-09-29 — Fork patch 24 merged: `up-modelfile-roundtrip` @ `c8e22c11` (manifest `23a43c77`, fork-only).**
> - `show --modelfile` writes `TEMPLATE` only for a model that carries one. `create` refuses an unterminated `TEMPLATE`/`SYSTEM` quote that would have swallowed the directives after it.
> - One conflict, in `server/images.go`: xollama's own `modelfile-roundtrip` hook carried the same condition. Resolved to the patch's side. The hook and its registry row are retired, since the fork now supplies the fix.
> - `go test ./parser ./server ./cmd` passes, and `check-hooks` reports 28 hooks.

> **2026-09-29 — Medium council on e75c7c3e (eleven2go 3090): fixed.**
> - **Fixed** in 34 trips and 1,954 s, and declared DONE. The first council fix of medium since d17af426 on b203 (19 trips / 778 s).
>   - Nine checks: five identical SyntaxErrors, then a changed error (`missing ) after argument list`), then back to the first error, then passing.
>   - Twelve edits, three of which missed their text.
> - Plain on the same build and host: 12 trips / 114 s, so the council is 17× slower.
> - Usage (calls / prompt / output tokens):
>   - synthesizer 35 / 1.20 M / 18 k;
>   - researcher 28 / 0.87 M / 35 k;
>   - critic 8 / 0.20 M / 9 k;
>   - planner 4, front 5, reviewer 4, builder 1.
> - The first attempt on this build died at engine startup: an engine orphaned by the test deploy script held its pinned memory. The script now unloads models before stopping xollama.

> **2026-09-29 — Why the council kept a refuted explanation: its "moved" signal was wrong.**
> - In the 96edc4ae transcripts, the planner converted one kind of syntax, then more of it, then another kind, while every check returned the same SyntaxError.
> - The runtime told it each check had moved. It took the cycle's last read-only call as the check, and that was a search after `run_game`. The stuck note never fired.
> - Fixed (plan 11.19): the check is the first read after the cycle's last change. The stuck note now also says the explanation behind the unmoved changes is refuted.
> - `TestTheCheckIsTheReadAfterTheLastChange` fails on the old code exactly as live.

> **2026-09-29 — Medium council on 96edc4ae (eleven2go 3090, 384k context back): unfixed, no stalls.**
> - 60 trips (the harness limit), 1,695 s (was 4,137 s on 837a1fce). No cut replies and no admission refusals: the cap and placement fixes held.
> - 23 edits "succeeded". Every check still returned `SyntaxError: Unexpected token '{'`, with no line number.
>   - The members rewrote syntax they suspected: arrow functions to `function` (which breaks `this` in `gen`) and template literals to concatenation.
>   - The extra `}` ending `dGrid` was never touched.
> - Plain fixed the same task in 12 trips / 114 s by reading the file and rewriting the broken class whole. The council's failure is now diagnosis, not capacity.
> - Usage: synthesizer 59 calls / 1.81 M prompt tokens; researcher 40 / 1.11 M; critic 13 / 0.34 M; planner 6; front 5; reviewer 3; builder 1.
> - 688d1f53 (owner makes room) deployed afterwards.

> **2026-09-29 — The owner makes room for the builder and the reviewers.**
> - A member booked on its own session beside the conversation's owner could wait out its whole admission budget when the owner held the whole window. That was the builder's 2-minute refusal on 62c7d5ec.
> - `roomFor` (plan 11.18, `server/council_room.go`) reads `/kv`'s `largest_admissible`. When it is short of the member's window, the owner shrinks by the difference, never below its used cells plus the turn's reserve. The shrink is applied at once, or deferred if the engine refuses. The next turn grows the owner back.
> - Two tests; the call was checked by removal.
> - Not yet deployed: the medium council run on 96edc4ae is still going on eleven2go.

> **2026-09-29 — Medium council rerun on 62c7d5ec: stopped by the placement fix, now fixed again.**
> - The first rerun without the CUDA pin ended after 5 trips. The engine refused the builder for 2 minutes ("no room"). Nothing to do with the cap fix:
>   - `opencotiPlacement` (b22e5649) filtered the GPUs only where the model is placed;
>   - `liveSlots` and the deny-list still saw the 3090 and the 9070 XT together, answered "not opencoti", and dropped `slots.live 2` to one slot;
>   - the engine launched with `-c 196608`, not 393216, and the conversation's owner booked the whole window.
> - Fix: the filter runs in `processPending`, right after the device pin, so the whole load sees it. The new `TestAModelOnlyOpencotiServesLoadsWithItsOwnSlots` fails with the old position ("launched with 1 slots, want slots.live's 2").
> - Also seen: an unpooled member (the builder) waits for its full timeout when the owner holds the whole window. Not changed here.

> **2026-09-29 — Why the medium council failed, and the fix: a writer has room for its edit.**
> - Plain medium on 837a1fce + b208 (eleven2go 3090): **fixed** in 12 trips, 114 s, 208 k prompt tokens, 5.2 k output. It read the file and rewrote the whole broken class in one `edit_file`.
> - The council's front and synthesizer set out to make the same rewrite. The front's last three calls each stopped at exactly 3,072 output tokens, the cap, inside the tool call, so only the prose survived. The class is about 3.3 k tokens, and an edit carries old and new (about 6.6 k).
> - Built (plan 11.17, `internal/council/cut.go`):
>   - a writer's cap on a tool turn is at least 16,384;
>   - `done_reason "length"` reaches the council as `Reply.Cut`, and a cut writer is asked again once for smaller steps.
>   - Four tests, each checked by removal.
> - Next: deploy to eleven2go with b22e5649, drop the `--device-backend=cuda` workaround, rerun the medium council. Cloud tests wait until the council works.

> **2026-09-28 — Medium council on 837a1fce + b208 (eleven2go 3090): unfixed.**
> - 57 trips, 4,137 s. Every one of the 10 checks returned the same `SyntaxError: Unexpected token '{'`, which carries no line number.
>   - The fault is in `dDec`, which no member ever read, the same miss as simple run 7.
>   - The members edited template literals, braces elsewhere and `sX`, and 5 edits missed their text.
>   - The run ended with 4 trips of narrated intent and no tool call (3 nudges), which the harness scored as DONE.
> - For reference, d17af426 on b203 fixed medium in 19 trips / 778 s.
> - Usage (prompt share / output share):
>   - synthesizer 44 % / 31 %;
>   - researcher 36 % / 45 %;
>   - critic 10 % / 13 %;
>   - front 9 % / 7 %;
>   - planner 1.3 % / 3.5 %.
> - Totals: 5.39 M prompt tokens (2.5 M cached), 145 k output.

> **2026-09-28 — A model only opencoti can serve stays on opencoti's GPUs.**
> - eleven2go has an RX 9070 XT (Vulkan) beside its RTX 3090. The medium council model (kvarn3, 384k) fits no single GPU, and upstream's placement picked the Vulkan backend by free memory. The launch refused it: kvarn3 needs opencoti.
> - `opencotiPlacement` (registry row `opencoti-placement`) now keeps such a model on the GPU groups opencoti serves; nothing changes for other models or with `XOLLAMA_ENGINE=llamacpp`.
> - Workaround for the current run: `omni-council-kv3-384k` pinned to `--device-backend=cuda`.
> - Also measured on eleven2go (2k prompt, 512 gen), xOllama on the 3090:
>   - omnimerge-v4 IQ2_M: 48 tok/s gen, 1,150 prefill;
>   - qwen3.6 35b-a3b: 189 / 3,040;
>   - v9-agentic: 124 / 4,600.
> - On the 9070 XT, xOllama (Vulkan) matches stock Ollama within noise. b208 has no Windows Vulkan payload, so there is no rolling-KV on AMD yet.

> **2026-09-28 — xOllama's own icon, and an installer that stops only xOllama.**
> - The icons are the llama with a red X painted on its chest, from `scripts/xollama-icon.py`; the owner picked red over violet (preview artifact).
> - The installer and uninstaller no longer run `taskkill /im llama-server.exe`, which stopped a stock Ollama's runners and missed the opencoti engine.
>   - `app/xollama-stop.ps1` stops what runs from the install directory, the engines and runners those started, and orphaned opencoti engines, then waits for them to exit.
>   - It runs from `PrepareToInstall`, before any file is copied, and from `[UninstallRun]`. It replaces the 5 s timeout hack.
> - Not yet run on Windows: eleven2go is rebooting for updates.

> **2026-09-28 — The desktop app says xOllama.**
> - Found on eleven2go: two identical trays, both called Ollama.
> - Tray tooltip, menu (Open/Quit xOllama), notifications and window title now come from `wintray.AppName`.
> - The UI's ~170 "Ollama" strings are rewritten at build time by `app/ui/app/xollama-brand.ts` (a Vite plugin), not edited, so UI merges stay clean. "Ollama account" and "Ollama.com" stay, since they name ollama.com.
> - Registry row `app-brand`. The new icon followed (entry above).

> **2026-09-28 — The xOllama tray no longer exits when a stock Ollama tray started first.**
> - Found on eleven2go after the 9070 XT reboot. At logon the xOllama app logged "existing instance found, exiting": its single-instance check is `FindWindowW` on the tray window class, and the class was still upstream's `OllamaClass`, which Ollama's own tray had already registered.
> - It also sent Ollama's app a focus request. The class is now `xOllamaClass` (the `app-state` hook). The source guard in `internal/onboarding` flags `"OllamaClass"` and fails without the fix.

> **2026-09-28 — Engine pin moved to b208 for v0.34.4-xollama.3 (owner's ruling).**
> - opencoti `2609281805001` (b208, rev `f8fc1116`, mail #540): the V100 fixes (KVarN collapse 0447, the engine picking the CUDA 12 payload below cc 7.5), the #530 scatter assert (0448), the drafter-KV fixes (0449/0450) and the wider TinyBLAS GEMM (0451).
> - Measured on these bytes (`as-ollama/b208-ab`), against b177: compat 8/8; llama3 76.8 tok/s (75.5); multislot 144 (142); gemma4 identical.
>   - Overflow read 3.32 against b177's 3.85. Paired, alternating reruns read b177 at 3.28 and 3.34, b208 at 3.36 and 3.29: noise.
>   - Two-turn `/api/chat` held on two models, with 0 REFUSED. The argv probe (`probe208.sh`) matches b177 on every row. All four shas were checked on HF at the rev.
> - No defect row is retired. Docs name b208.
> - Next: release PR `release: v0.34.4-xollama.3`, a pre-release (not promoted).

> **2026-09-28 — council 11.16: the builder gets its own model.**
> - `council.builder` (`model`, `host`, `think`, `max_tokens`; no `prompt`, no `count`); unstated, it runs on the planner's, as before.
> - For the owner's cloud tests: the builder on `glm-5.3-turbo:cloud` while the critic, researcher or planner moves there, one at a time.

> **2026-09-28 — council 11.15: loop guards from Cerebriline, the front's handoff, no idle researchers.**
> - The consultants' #3–#6, as the owner took them (#2 waits for the flow-modes follow-up):
>   - a no-op change is refused in place;
>   - a changing call resent with the same result gets Cerebriline's steering ladder, and at 4 strikes the member reports;
>   - a refused change is redone from the text as it is now;
>   - the front stops at 3 steps, and its current reads reach every member as research, not as a failed attempt;
>   - the planner keeps every researcher working.
> - Next: deploy, then measure.

> **2026-09-28 — b203 holds on eleven2go; the council missed simple on it.**
> - opencoti #530 rerun: b203 host (2609281335001) with the b201 Win DLL, the `head` relief removed (`auto` residency, POSITION_WINDOW on), 4 live slots, unified KV.
>   - The simple council ran 60 trips in 2028 s, 5 cycles, with no assert; log sent (#538).
>   - eleven2go now runs b203 through `XOLLAMA_ENGINE_PATH`. Revert: clear it, and set `XOLLAMA_ENGINE_ARGS=--kv-residency-mode head`. The pin is unchanged.
> - The council did not fix simple on d17af426: the same "missing )" for all 13 checks.
>   - The planner moved off template literals to "unbalanced parentheses or brackets", but only ever counted `()`/`[]`, as the error names. `dDec`, which holds the stray `}`, was never edited.
>   - This is one run against run 6's fix (34924cbe), with the engine and the prompt both changed and sampling varying, so it needs repeats before it says anything.
> - Usage: the synthesizer took 66 % of the prompt (59 calls, 2.6M tokens), the researchers 22 %, the critic 10 %, the planner 0.7 %.
> - opencoti #535: #528's 20 % loss was a bug (quantized drafter KV read in the wrong basis). It is fixed in b206, where an inheriting q8_0 drafter costs nothing; the pin is the owner's call.

> **2026-09-28 — council 11.14 measured: medium 778 s (was 1101 s); first real per-role usage.**
> - Medium on d17af426 (eleven2go): council **fixed**, 19 trips, 778 s (was 27 trips, 1101 s; plain: 11, 91 s). One batch of edits fixed the stray brace and every missing function at once.
> - Per-role usage (`council_usage_v1`, tokens), as prompt share / output share:
>   - synthesizer: 52 % / 22 %
>   - researchers: 28 % / 54 %; they also spent the most decode time (310 s)
>   - critic: 10 % / 13 %
>   - front: 7 % / 5 %
>   - planner: 2 % / 5 %
>   - reviewer and builder: 2 % / 2 %
> - About 45 % of the prompt came from cache.

> **2026-09-28 — council 11.14: the synthesizer applies the proposals together.**
> - The consultants council (csl-2026-09-28-1441-4bbf) traced medium's slowness to our own synthesizer prompt: "one at a time … after each change, run its check".
> - Now the synthesizer makes every non-conflicting proposed edit in one reply and checks once. It fixes a next failure its check already shows, and hands back only what needs investigating. Researchers report every fault in their part.
> - Hard on 032db6c2: **a cliff for both arms**.
>   - Council: unfixed at the 60-trip cap, 4129 s; last error `Unexpected token ')'`.
>   - Plain: unfixed at the cap, 538 s; last error `Unexpected token '{'`.
>   - Both got past the first "missing )" and stalled on the misplaced braces further down.
>   - Plain's usage (the first run recorded): 60 calls, 4.2M prompt tokens sent (2.06M cached), 21k written.
> - Next: deploy, medium against plain's 91 s; then the role-upgrade matrix (follow-up csl-2026-09-28-1521-242f).

> **2026-09-28 — council: medium fixed, 12× slower than plain; usage per role reported.**
> - Medium on 032db6c2 (eleven2go): council **fixed**, 27 trips, 1101 s. Plain **fixed**, 11 trips, 91 s. It read the file once, fixed seven faults in four edits and checked once; the council paid a whole check cycle per fault.
> - The consultants council has been asked for optimizations (brief: `/srv/ml/xollama-phase2/consult-council/BRIEF.md`).
> - Built: `council_usage_v1`. Each council done chunk reports what each role spent (calls, prompt sent and cached, written, durations), and the manic harness records it per trip and per role (plan 11.13).
>   - First reading, medium: the researchers take 45 % of the prompt and the synthesizer 43 %; the critic 7 % and the planner 2 %.
>   - Prompts are about 68× the output.
> - Hard is running (council, then plain).

> **2026-09-28 — council: simple fixed for the first time; task ids keep the list's numbering.**
> - Sixth simple run (34924cbe, eleven2go, `head` relief): **fixed**, 40 trips, 1401 s (plain: 27 trips).
>   - Cycles 1–2 chased template literals (seven harmless edits) against the same check output.
>   - The stuck note fired, and cycle 3 replaced the `dDec` method whole. The error moved to `sX`, then to `collide`, and the council followed each one to the fix: 11.10–11.12 working as designed.
>   - The planner's re-plans numbered the task list from 0 again, so its updates landed on the wrong tasks.
> - Fixed: plans are kept with the list's ids, tasks are matched by their words before their id, and the rule says never to renumber (`TestARenumberedListUpdatesTheTasksItNames`, checked by removal).
> - Next: medium on 032db6c2 (running), plain medium for a baseline, hard once, then the b203 rerun for opencoti #533.

> **2026-09-28 — council 11.10–11.12: a task list for the planner, stuck checks, reviews with verdicts.**
> - Fifth simple run (b336b144): unfixed, 60 trips, 1619 s. Six reviews fired and were mostly right to refute, but only one carried its `REVIEW:` line. Every check returned the same "missing ) after argument list". The plain arm fixed the task in 27 trips, with a whole-file rewrite at trip 20, then followed the new errors.
> - Built:
>   - the planner keeps a task list in its plan (`tasks.go`, with rules the runtime enforces, carried across turns and dropped on a rebuild), and the builder writes its instruction as a coordinator's;
>   - two checks in a row with the same output tell the council to change approach (`stuck.go`, topic-agnostic), a changed output counts as progress, and a whole-part replacement is allowed;
>   - a review without its verdict is sent back once with the structure, then marked unclear.
> - Tests were checked by removal; the full sweep, race, lint and hooks are clean.
> - Next: deploy to eleven2go, rerun simple; if it passes, medium and hard once each.

> **2026-09-28 — council: the builder reads only the user; unsent checks are sent; reviews stream.**
> - Fourth simple run (5b331d1b) peeked mid-run: `n_slots = 4 (live = 4)`. The builder no longer names a place or a cause. The synthesizer never called `council_review`.
> - Built: the builder reads the system prompt and the user's messages only, on its own session (`5b331d1b`). A check the synthesizer moves on from (its next call changes something) is sent for it, and the DONE's check reuses that id. Reviews stream as `Reviewer N` thinking at delivery (`b336b144`).

> **2026-09-28 — council 11.9: the critics review the synthesizer's checks while it works.**
> - Third simple run on eleven2go (311010f9, `--kv-residency-mode head` relief): unfixed, 60 trips, 3466 s, no engine fault. The synthesizer made 27 edits against 11 checks with no second reader.
> - Built, as the owner designed it: `council_review` queues a check (the change plus what the calls returned). A per-conversation desk runs one reviewer per critic in the background, and each finished review reaches the synthesizer before its next step. Only DONE waits for the reviews still out, and sends its last check itself when it was never sent.
> - Next: deploy, rerun simple on eleven2go.

> **2026-09-28 — council 11.8: all the engine's parallel slots; cloud members counted apart.**
> - The council ran with 2 live slots of eleven2go's 4, because xollama sized them to its widest step. It now starts with the engine's parallel ceiling (4 by default, `slots.max`), with its local width as the floor.
> - Members on a cloud model take no engine slot: they run `council.cloud_parallel` at a time (default 3, `--council-cloud-parallel`), one count per council model.
> - Next: 11.9, the critics reviewing the synthesizer's checks asynchronously (owner's design: queued, each finished review returned as it lands).

> **2026-09-28 — council 11.7: every message names its writer; earlier turns attributed.**
> - eleven2go simple rerun on b96e3c96: unfixed, 667 s / 24 trips. The engine asserted in cycle 3 (opencoti #530: position-window scatter, two sequences prefilling, kv-unified, `auto` residency). Cycle 2 had edited the right line and found both missing functions. The bounds held (front 3 steps, synthesizer 6 per cycle).
> - The owner's points: the history should show the member; wrong claims must not stay in view; council messages must name their role and the user's stay plain; no anchoring. Built: `council.History` (calls split per member and headed, working notes dropped, repeats pointed at), source headers on every council message plus `sourcesNote`, and the front's report cut to its calls and results.
> - Relief on eleven2go: `XOLLAMA_ENGINE_ARGS=--kv-residency-mode head` (user env) until #530 is fixed.
> - Next: redeploy, simple on eleven2go, then medium and hard once each.

> **2026-09-28 — council 11.6: ab-5 read, and the fixes it asked for.**
> - ab-5 simple: plain fixed it on both hosts (solidPC 339 s / 30 trips capped, eleven2go 162 s / 20). The council did not (solidPC 3405 s / 60, unfixed; eleven2go 659 s / 24, declared done unfixed).
> - Members are served exactly as a plain turn: same ChatHandler, template and options; 2 of 140 replies hit a cap. The delta is context. The client history carries every member's calls as one assistant, five copies of the file and the front's wrong claims. Findings arrived as user messages and were obeyed. The builder anchored every role on the front's theory. The synthesizer investigated for 16 trips instead of testing.
> - Built (A–J): the builder never names a cause; failed checks are carried across turns (`Progress.Prior`, state field 10); the verdict is nudged once and never re-streamed; a synthesizer step budget (`MaxSteps` 6, builder `max_steps`, Build field 5); a test note that forbids investigating on its own; the front's attempts reach the council; localize-first coding example; critics told they cannot test; findings framed as claims; the front forwards before investigating (4 steps, then forced). Guards are in `internal/council/checks_test.go`, each checked by removal.
> - #468 (opencoti) on the 3090, 70B q3_K_S, 32k: `--kv-residency-mode auto` beats `head`. Decode 2.45 vs 2.10 tok/s at 1k and 0.24 vs 0.16 at 24k: auto keeps 59 layers on the GPU against head's 48. Mailed as #529.
> - Next: redeploy to eleven2go, rerun simple, then medium and hard once each.

> **2026-09-28 — council Phase 11 opened: caps raised, a repeated call pointed out.**
> - ab-4 simple on eleven2go (kvarn3, `-c 393216`, two live slots): the council was unfixed at 1463 s against plain's 233 s. The researchers could not test, were capped at 384 tokens, and read once each. The diagnosis went untested. The synthesizer repeated one failing edit 15 times, and each of its resumes re-prefilled about 18k tokens.
> - 11.1: reply caps 2048/2048/1024/2048 (planner/researcher/critic/synthesizer) with terse prompts, evidence carried whole to 4000 characters and capped at 16000, notes 600 characters.
> - 11.2: a result that repeats an earlier identical call's result gets a generic note (`TestARepeatedCallWithTheSameResultIsPointedOut`, checked by removal).
> - 11.4 test loop: researchers propose, the synthesizer checks, and a failed check (`VERDICT: RETEST`, with its evidence) goes back to every member of the next cycle, up to 6 cycles, carried in the state (Progress field 7). Loop and prefix checked by removal.
> - Owner's answers applied: the planner re-plans each cycle from the failed checks (`Replan`, state field 8). The user gets the synthesizer's brief status in the same response while the report after the verdict is held back for the council (`holdBack`).
> - 11.5 builder built. On a request's first trip to the council it reads the system prompt, the requests and the tools, then writes per-role instructions, think budgets for the roles the user left unset, and the check bound (0..12), plus a target. The user's council stands. The build is kept across turns (state field 9), and the route decision can `rebuild`.
> - 11.5 front: on a tool turn the synthesizer takes the request first, on the conversation's session. It answers, or calls `council_forward` (the builder runs first when there is no build) or `council_rebuild` (it is told the new setup, then forwards). Only it may route. Turns without tools keep the planner's route decision, with `rebuild`. Checked by removal.
> - Preemption: a broadcast verdict (`kind` confirmed/refuted) interrupts the mates generating, who keep their partial text and read it before going on (at most twice). Ordinary notes still wait for the next call.
> - 11.3: member sessions are no longer closed after a call. The council lives until its client leaves (the owner's ruling), and each member resumes from its own cache (opencoti #526, traced in code). They are closed only when the client drops mid-turn.
> - ab-5 (simple, plain vs council) is running on the solidPC dev server (127.0.0.1:22440, b177, kvarn3, 131072 per slot). It was started before 11.3, so it measures 11.1–11.5 only. 11.5 (the builder) is designed in the plan. No live run yet.

> **2026-09-28 — v0.34.4-xollama.2 published (pre-release) and installed on eleven2go; a council says --kv-unified once.**
> - PR #4 merged as `ac1af15c` (23 checks green); release run 36356726357 published the pre-release, not promoted. Installed on eleven2go with `/SILENT` through the scheduled task: 22 s, exit 0, the think-budget Ollama untouched (same process, files, models and uninstall entry); `xollama.exe` byte-identical to the release, PAYLOAD_ID equal. Docker image dispatched on the tag.
> - ab-4 simple on eleven2go: the council launched `-np 2` (live 2), both researchers in the engine at once (slots 0 and 1 interleaved, no "defer task"). The run was stopped at round 6: the model's `num_ctx 16384` gave the whole council one 16k pool; it is re-run with kvarn3 at the largest context that fits.
> - The council launch carried `--kv-unified` twice (`councilSlotArgs` and `appendSlotArgs`); `appendSlotArgs` now writes it only when the argv lacks it. Guard `TestACouncilWithPoolsSaysKVUnifiedOnce`, checked by removing the fix.

> **2026-09-28 — Engine pin moved to b177 for v0.34.4-xollama.2 (owner's ruling).**
> - `llm/engine/pin.txt` → `opencoti-0.10.5-c7-2609272353001`, rev `7fc93cc8` (#515): fit growth-free (MTP reserve as it runs, no RS for idle slots), the KV-window sizer fix, the bundled dlopen helper, q6_0 mixed pairs served. sha256 of bin, DSO and CUDA 12 payload checked on download.
> - Re-probed: every cache type and ring shape as on b171, except a KVarN key over a plain value with a ring, now accepted by the engine (promoted); xollama keeps refusing it. A/B vs b171: compat 8/8 (was 7/8), llama3 75.5 tok/s, multislot 142, gemma4 identical, 70B overflow 3.85 tok/s (was 3.05).
> - Docs name b177; the q6_0 warning says the pairs now run, slower. Left: the `:dev` image on this pin, verified on the 3090; then merge PR #4.

> **2026-09-27 — xollama was passing opencoti a fit target for every vision model; stopped.**
> - Chris's V100 (32 GB, 18 GB model) ran at 2.9 tok/s with 4 GB of KV on the host and 4.9 GB of VRAM free. The engine's "runtime margin 1909" was ours: upstream's mmproj stopgap (ollama#16996) sets `LLAMA_ARG_FIT_TARGET` = projector + 1 GiB (885 + 1024), and an explicit target switches opencoti's automatic 256 MiB margin off. The `engine-fit` hook (`llm/engine_fit_target.go`) drops the pad on opencoti; stock keeps it (bug-167).
> - Left with opencoti (#510/#511): the MTP booking (2360 MiB held, 1348 used) and RS growth held for slots that are not live (1122 MiB for 3 slots at live 1).

> **2026-09-27 — A silent install tried to uninstall Ollama; fixed before v0.34.4-xollama.2.**
> - Installing v0.34.4-xollama.1 on eleven2go with `/SILENT` (RELEASE.md step 6) ran the think-budget Ollama's uninstaller: the Ollama-found page was built in silent mode and its default is "uninstall". Ollama survived (it was running; files, 210 GB of models, registry entry and app data all intact, app data also backed up). The in-app updater runs the full installer `/SILENT`, so every update on a host with Ollama was exposed. `app/xollama-setup-pages.iss` now never builds or acts on that page silently (bug-166).
> - v0.34.4-xollama.1 had this installer; withdrawn to draft on the owner's word (23:40), so the updater no longer offers it (the tag stays, on `dd739034`). Left: install .2 on eleven2go once it is published.

> **2026-09-27 — Council 10.6: a broadcast channel between parallel members, off by default.**
> - `council.broadcast` (tweak `council-broadcast`): members with a same-role mate get a server-answered `council_post` tool, 200 chars and 4 notes per member per turn, delivered before the mate's next model call and never waited on; the board travels in the sealed state. Tests: `TestANoteReachesTheMateBesideIt` (40/40 under race), `TestTheNotesBoardTravelsInTheState`.
> - Left: A/B it on and off in ab-4 (10.7) on eleven2go; drop it if it costs more turns than it saves.

> **2026-09-27 — Council 10.5: one council across turns; v0.34.4-xollama.2 cut (not promoted).**
> - A follow-up message is feedback to the same council: the planner routes `direct` (done/trivial), `continue` (the synthesizer carries on from the kept plan, findings and critiques) or `council` (fresh). Kept per session in memory and in `council_chat_state` fields 6-8, bound to the conversation it answered. ab-3's nudges restarted the whole council twice; they now continue it.
> - Release PR #4 `release: v0.34.4-xollama.2` (the Docker GPU fix, V100 discovery, council 10.1-10.6, Docker and KV docs). Owner: not promoted.

> **2026-09-27 — KV cache values and combinations documented, from opencoti's matrix (#507).**
> - `docs/xollama/kv-cache.mdx` "Values and the combinations that work": presets (quality / balanced / max context, dense vs sliding-window), every accepted type with its flash-attention and backend limits, the mixing rules (plain+plain and KVarN+KVarN may differ; KVarN+plain is silently promoted, so not offered), the ring rules, and the CUDA `q6_0` mixed-pair crash (opencoti bug-3705, fix not pinned). The stale "ring not in this build" Warning is gone: the pin carries `feature swa-cache-types`.
> - `docs/xollama/docker.mdx` and the Docker Hub page carry the presets and link the section; the Hub page is published.
> - Left: `CacheShapeError` does not yet refuse KVarN+plain or the three crashing `q6_0` pairs; opencoti 0431 (a bundled dlopen helper) lands with the next snapshot, after which the image's own helper is redundant but harmless.

> **2026-09-27 — The Docker image could not use any NVIDIA GPU; fixed. A V100 is kept through discovery.**
> - Chris (V100) got `support for --gpu nvidia was explicitly requested, but it wasn't available`. Reproduced on solidPC's 3090 with `:dev`: the engine (a Cosmopolitan APE) found `ggml-cuda.so` but `dlopen() isn't supported on this platform` -- it builds a libc helper with the system `cc` into `$HOME/.cosmo`, and the image has no compiler. `Dockerfile.xollama` now builds the helper in a gcc stage and ships it in both engine homes; a derived test image loaded qwen3:0.6b 100% on GPU at 195 tok/s. Bare-metal Linux hosts without `cc` are affected too: reported to opencoti.
> - Docker docs: README `## Docker` (ollama-style one-liners, GPU passthrough), `docs/xollama/docker.mdx` (tags, volumes, every operator env var, slots/KV, NVIDIA toolkit setup), `docs/dockerhub/README.md` for the Hub page; `engines.mdx` coverage corrected for the V100 payload.
> - Discovery listed CUDA devices through the main (CUDA 13) engine only, so a V100 on a 570 driver would have been dropped; it now also asks the `engines/cuda_v12` engine and keeps the longer list (`discover/opencoti_cuda12.go`).

> **2026-09-27 — v0.34.4-xollama.1 pre-release published; council Phase 10 started from the ab-3 analysis.**
> - PR #3 merged (`dd739034`); release run 36345410380 published the pre-release (setup 797 MB, update 14 MB, both binaries, sha256sum, payload-id). Docker image for the tag: run 36346010621 (`:dev`, a pre-release). Promotion waits on the eleven2go install check.
> - Upstream's `test-llamacpp-update.yaml` guarded to `ollama/ollama` (`docker-release` hook): it fired on the release PR because `LLAMA_CPP_VERSION` moved, and targets runners the fork lacks.
> - ab-3 finding: the council's members were serialized by the engine (`-np 1`, no slot for the second worker, opencoti #501) and the council restarted on each nudge. Built: a slot per parallel member (`-c` unchanged), one critic by default, shared reads, `VERDICT: CONFIRMED`. Next: the council kept across turns, broadcast, ab-4 on eleven2go. See plans/agentic-council-chat.md Phase 10.

> **2026-09-27 — Engine pin b171 with a CUDA 12 (V100) payload; runtime pins on v0.34.4 (owner: assemble the pre-release and the Docker image).**
> - `llm/engine/pin.txt`: rev `7b836910` (b171 plus `ggml-cuda-cu12-x86_64.so`, sm_70, driver ≥ 570, opencoti #498).
>   - It is read from `#! dso-cuda12` / `#! cuda12-sass`.
>   - `cudaPayload` sends a 7.0 card to `engines/cuda_v12`, where `docker-assemble.sh` stages the payload beside a copy of the engine; a load spanning both payloads goes to llama.cpp.
>   - Guard: `llm/engine/pin_cuda12_test.go`.
>   - Pinned on the owner's say-so despite the b171 gate: its 70B first-load failure is bug-3702, which b145 also has; the fix is in opencoti's next build.
> - Linux runtime pin: `v0.34.4-thinkbudget` (tgz `9769cb4b`, inputs `17ab8578` = ours) with upstream v0.34.4's GPU tarballs.
> - Windows runtime pin: `runtime-windows-amd64-b11081-3023ebe12b5e` (zip `2b5fbffa`, run 36342602471).
> - Docs: device-selection, docker-release, and the engine-pin rule.

> **2026-09-27 — Manifest e314b235 consumed: lint fixed, compat README by sha, inputs digest now equals the fork's.**
> - Merged `up-think-budget`@b463e532 → `9b2b56a6`, the new `up-compat-readme`@ddde8473 → `20ad1fd4` (README conflict taken from its side, as the fork predicted), and the rebuilt `up-response-scope-think-budget`@87d417bf → `4fd3de2c`.
> - Now: `golangci-lint` 0 issues; digest `3023ebe12b5e` (= the fork's); build, vet and test pass.
> - Left: check-compat-origin flags the superseded `15ebdeca`, since the fork's rebuild left it on no ref (asked for an archive ref in the reply); the Linux runtime release waits on the owner (fork item 3).

> **2026-09-27 — b171 (2609271900001) measured and NOT pinned; gemma4-toolcall-in-thinking is fork-only.**
> - b171 carries opencoti's fit rework: an automatic margin, lazy vision, and the rolling-KV window inside the fit. It went through phase2-engine-ab.py as `ollama`; results are in `/srv/ml/xollama-phase2/as-ollama/b171-ab`.
> - Throughput 74.9 tok/s and gemma4 are fine. Two axes regress against b145:
>   - the 70B q3_K_S first load fails allocating its 5.6 GiB KV buffer, because the fit leaves 256 MiB and does not count it;
>   - multislot serializes (142 vs 590 tok/s): `kv-reservation: REFUSED … need 32768`.
> - Sent to opencoti in #491. The pin stays on b145.
> - A Docker image with CUDA 12 (V100) plus CUDA 13 for a tester: upstream's `cuda_v12` is already in the image. The engine's own v12 payload is still compiling at opencoti; asked for its pin shape in #490.
> - CARRIED-PATCHES follows manifest bump `78333d54`: `gemma4-toolcall-in-thinking` is fork-only (#18307 was closed upstream and stays closed).

> **2026-09-27 — Synced to upstream v0.34.4 and the fork's v0.34.4 manifest (branch `sync/upstream-v0.34.4`).**
> - `c43d0a68` merges the v0.34.4 tag. xollama's hooks (council, engine-session fields, api-key, context-window) are kept, upstream's `thinkingparser` / `ThinkingClose` is adopted, and the structured-outputs double request is dropped as upstream did.
> - The fork's 22 patches (manifest `3edc2006`, integration `e74b1daa`) are merged at their shas in order, `a9b28ffe`..`7f560400`. The table is in `docs/protocols/CARRIED-PATCHES.md`.
> - Verified:
>   - no file differs from the fork's tree beyond xollama's own set;
>   - `go build`, `go vet` and `go test ./...` pass;
>   - `check-hooks` passes (26 hooks);
>   - `check-compat-origin` passes after the README fix below.
> - `LLAMA_CPP_VERSION` is b11081. Three new upstream tests set `OLLAMA_HOST` and now set `XOLLAMA_HOST` (default-port rule).
> - Left:
>   - the fork's combined `llama/compat/README.md` (`3f1fcb62`) reaches no patch branch, so ours is the line-boundary copy until the fork puts it on one;
>   - two lint findings in fork code (`server/think_budget_resolution_test.go` bodyclose, `server/routes_generate_test.go` trailing blank line) were sent to the fork;
>   - the Windows runtime pin must be rebuilt (`xollama-runtime.yaml`) and the Linux pin waits for a fork v0.34.4 runtime release, both before a release PR.

> **2026-09-27 — Documented how the context pool is shared; the default stays num_ctx × 1.**
> - Owner's decision: the pool stays `num_ctx × XOLLAMA_PARALLEL` (32k × 1 by default on a 24 GB card). A request that states no window gets the whole pool, so by default requests take turns, as on Ollama.
> - A request that asks for a window (`placement.num_ctx`) gets that window, and up to `XOLLAMA_MAX_PARALLEL` of them share the pool: a 256k pool serves 1 × 256k, 2 × 128k or 4 × 64k from one load.
> - Measured on b171: `-c 131072` allocates the whole pool at load (qwen2.5:1.5b KV 896 → 3584 MiB). opencoti's grow-on-demand pool is planned for c9, stage 8 (mail #497). A prototype that sized the pool for the ceiling was discarded.
> - `docs/xollama/slots.mdx` gains "How the context is shared", and its claim that several conversations run side by side by default is corrected. `docs/xollama/sessions.mdx` links to it.

> **2026-09-27 — Promoted releases are announced on Discord.**
> - New `.github/workflows/discord-announce.yaml`, copied from mann1x/osync's "Announce on Discord" step.
> - It runs on `release: released`, so on the RELEASE.md step-8 promotion and never for a pre-release. It posts the notes as an embed via the `TECH_CORNER_DISCOWH` secret, which the repo already has. `workflow_dispatch -f tag=` re-announces a tag.
> - Validated with actionlint and a local payload dry run on the v0.34.2-xollama.1 notes. Nothing was posted.
> - It takes effect once it reaches `main` with the next release PR.

> **2026-09-27 — Installer setup pages; XOLLAMA_PARALLEL replaces OLLAMA_NUM_PARALLEL on opencoti; server-wide KV types fall back on stock.**
> Owner's requests, for moving pandorum (RTX 5080, an `Ollama think-budget` install) to xOllama.
> - **Installer** (`app/xollama-setup-pages.iss`, included from `app/xollama.iss`, full installer only): the pages are Ollama found (uninstall `/SILENT` after backing up `%LOCALAPPDATA%\Ollama`, or keep it), port (22434 / 11434 greyed out while an Ollama stays / custom), API key (generate / copy / skip) and KV cache (opencoti K and V + legacy type). Silent installs change nothing. Compiled clean with Inno Setup 6.7.1 (CI's version) on pandorum against a stub payload; the real installer comes from the dry-run release build.
> - **`XOLLAMA_PARALLEL`**: on opencoti `liveSlots` takes `slots.live`, else `XOLLAMA_PARALLEL`, else 1, and never reads `OLLAMA_NUM_PARALLEL` (shared with any stock ollama). Stock llama.cpp keeps `OLLAMA_NUM_PARALLEL`. `XOLLAMA_MAX_PARALLEL` unchanged. Guards: `TestXollamaParallelReplacesNumParallelOnOpencoti`, the updated `TestLiveSlotsBindOnlyOnOpencoti` and `TestTheSingleSequenceRuleBindsOnlyStockLlamaCpp`; a mutant restoring the old count fails both slot tests.
> - **KV fallback**: a server-wide `XOLLAMA_K/V_CACHE_TYPE` stock llama.cpp cannot parse no longer fails a load stock serves. `resolveKVCacheTypesOn(..., stock)` keeps the legacy type (`XOLLAMA_KV_CACHE_TYPE` / `OLLAMA_KV_CACHE_TYPE`), and `startLlamaServer` relaunches with `stockKV`. A model's own `kv` is still refused. Guard `TestServerWideOpencotiTypesFallBackOnStock` (mutant killed).
> - pandorum backup before any change: `J:\xollama-migration-backup\20260927` (Ollama app data, `~\.ollama`, machine `OLLAMA_*`, uninstall key).
> - Left: the dry-run installer for the owner to test on pandorum; b160 still unpublished on HF (asked opencoti, #475); the Gemma-4 swallowed-key parser check must come from the fork (#476).

> **2026-09-27 — The opencoti engine logs at ollama's level with --log-memory-plan, not at 5.**
> - xollama forced `--log-verbosity 5` so the memory scrapers would see the buffer-size lines. opencoti shipped `--log-memory-plan` for exactly this (0302, requested 2026-09-18), but xollama never adopted it.
> - Now `logArgs` in `llm/engine/opencoti.go` passes `--log-verbosity 4 --log-memory-plan` when the pin declares `feature log-memory-plan` (the committed pin does), and keeps 5 otherwise.
> - Measured on 2609271108001:
>   - solidPC llama3 8B: every non-zero buffer line, "MiB free" and "offloaded N/M layers" still print; ~3,630 → 32 log lines per request; speed unchanged (~81 tok/s).
>   - eleven2go, Windows build: the same flags, no memory-parsing warning, identical reported VRAM; qwen3:8b 4,265 / 123.0 tok/s, the same as at 5.
> - Also measured: xollama vs ollama on eleven2go. Dense models are within 1% between xollama's defaults and an ollama-like setup (`xollama tweak --slots=off --kv-unified=off`); the gap to ollama is the engine (qwen3:8b −15% prefill, −4% gen). qwen3.6:35b-a3b loses ~18% gen under the defaults (elastic recurrent state on the CPU is the lead); a 7-model re-run is in progress, and opencoti gets the full report.

> **2026-09-27 — v0.34.2-xollama.2 published as a pre-release (PR #2, merge 69f1a658) and verified on eleven2go.**
> - Release run 36319352313: plan, windows, linux, publish all green. Six assets; `sha256sum -c` all OK; payload-id `fcdf0b73…`.
> - eleven2go install (RELEASE.md step 6, scheduled task): `--version` names the tag, PAYLOAD_ID matches, `*:22434`, `/api/xollama` lists 9 features, the tray app names the fork's feed, and ollama on 11434 is untouched.
> - Devices: the RTX 3090 goes to opencoti (CUDA); the Radeon iGPU (Vulkan) goes to llama.cpp.
> - Measured: 700 tokens at 123.0 tok/s on the engine from `lib\ollama\engines`. The omni-council-idle tools turn passes (9 rounds, 87 s).
> - The council models were copied to eleven2go losslessly by recreating them. osync 1.3.1 is lossy against a Windows target: see `/shared/dev/handover/2026-09-27-osync-xollama-copy-issues.md`.
> - Left: promote to latest (step 8) when the owner says so.

> **2026-09-27 — Engine pin moves to opencoti 2609271108001, the first with a Windows CUDA engine; tested live on eleven2go.**
> - Pin: HF rev `ed6430b9`, bin `32287454` (one APE for x86_64, aarch64 and Windows), dso `868ed520` (Linux CUDA) and `ee622711` (Windows CUDA DLL), mail #439. It carries the b145 line: council/PolyKV surface plus opencoti's media runtime and STT.
> - Windows packaging now accepts a dev snapshot's shape (`bin win-x86_64` + `dso win-x86_64`):
>   - `Pin.ArchFor` falls back to it when no `win-x86_64-gpu` bin exists; `cmake/opencoti-engine.cmake` and `xollama-release.yaml` make the same choice.
>   - The engine is staged as `<name>.exe` with `ggml-cuda.dll` in `lib\ollama\engines`, not beside `llama-server.exe`: ggml's loader falls back to `ggml-cuda.dll` in the exe's directory.
> - New pin directive `cuda-sass 86 120`: the payloads carry SASS for sm_86 and sm_120f only, so `Pin.CoversCUDA` routes 7.5/8.0/9.0/10.x to llama.cpp, naming why, instead of letting them run on the CPU.
> - Measured on eleven2go (RTX 3090), with a cross-built xollama installed over the manual install:
>   - qwen3:8b ran on the engine on CUDA0 at 123.7 tok/s.
>   - omnimerge-v4 MTP IQ2_M at 128k made a correct tool call, at 60.7 tok/s with a 131072 window.
>   - `XOLLAMA_ENGINE=llamacpp` stays on stock llama-server on the GPU (109.5 tok/s, no header).
> - Linux A/B on solidPC (`phase2-engine-ab.py` as ollama) against b111:
>   - compat 8/8; llama3 75.4 vs 75.6 tok/s.
>   - multislot 590 vs 461 tok/s; 70B overflow 3.69 vs 1.21 tok/s (single run).
>   - gemma4 tool call and thinking split correct.
>   - No defect row accuses a dev build, so none is retired.
> - CI red on PR #2 since the API key commit, fixed: `app/ui/apikey.go` lacked the `windows || darwin` tag its only caller has (lint `unused` on Linux); `TestLiveAppUpdate` now skips when GitHub rate-limits the unauthenticated feed (403) instead of failing. Release dry run `36317134651` passed (plan, windows, linux, publish).
> - Left: merge PR #2 and the CI pre-release.

> **2026-09-27 — A client's pooled worker is refused fast too; a never-fitting request is a 400, not a "runner stopped".**
> - Cerebriline's first live run of both paths (mail #430) worked on dev 58cd5bf1, b137, omnimerge-v4-mtp:IQ2_M:
>   - The lead pooled (n_pool_shared 941–960) with `X-Context-Window: 31827`.
>   - The swarm owner got 98304, and its workers pooled.
>   - Negotiating asks got fast 429s.
> - Their ask 2 is done: a plain `/api/chat` with `placement.pool_id >= 0` now negotiates as `placement.num_ctx` does. The engine's 429 comes through at once, including the "session allocation full" of a full owner, on which their worker grows its owner. `X-Context-Largest-Admissible` is sent only when the engine names one; `Retry-After` is always sent.
> - Bug found on the way (bug-157): `ErrNeverFits` was never mapped in `Completion` or `Chat`. So the fail-fast of a01f3043 reached clients as "model runner has unexpectedly stopped". It is now a 400 naming the numbers, for requests that do not negotiate.
> - Their ask 1: omnimerge-v4-mtp:IQ2_M went to `session.client_pools: 3`, and the re-test (#433) attached all 3 swarm layers. A lead with a window beside the swarm then exhausted the reservoir (lead 2 + swarm 3 = 5 > 4), so the model is now at 5. `model-settings.mdx` says to count the client pools alive at once: 2 per windowed lead, 3 per swarm tree.
> - The re-test also passed ask 2: a full owner's 429 arrived in 0.4 s with the engine's reason, and their resize-and-grow path works through `/api/engine`.
> - Mutants: 5 more, all killed.

> **2026-09-27 — The engine's granted window reaches the client (`X-Context-Window`), and a window a client negotiates is refused fast.**
> - Cerebriline asked for this in #418. opencoti sets `X-Context-Window: <granted>` on every admitted response when it books windows; before this, xollama dropped it.
>   - The header is now on `/api/chat` and `/api/generate`, streamed or not, and on the OpenAI and Anthropic routes.
>   - A council turn reports its owner's grant.
>   - No header still means no guaranteed window: stock llama.cpp is unchanged.
>   - The value reaches the handler through a collector on the request context. A writer wrapper sets it before the first byte, on the handler's goroutine, so nothing races.
> - A client that states `placement.num_ctx` is negotiating. When the engine cannot book even `num_ctx_min`, the client gets the engine's 429 at once, with `X-Context-Largest-Admissible`, `Retry-After` and the engine's reason, instead of waiting 2 minutes for a 503. Requests that state no window still queue.
> - Feature `context_window_v1`. Registry row `context-window`. Docs in `docs/xollama/sessions.mdx` ("The session's window").
> - Tests in `server/context_window_test.go` and `llm/engine_slots_test.go`. 21 compiling mutants, all killed.
> - Live on solidPC: a throwaway server on :22500, CPU-only, engine b137, tinyllama, run as `ollama`.
>   - The header appeared on every route.
>   - Placement 1536/512 was granted 1536; the continuation held 1536.
>   - Asking 2048/1024 with 512 free gave 429 in 0.0 s, with largest 512 and Retry-After 2.
>   - 2048/256 was granted 512.
> - Limits:
>   - The OpenAI and Anthropic shims do not carry `session_id` or `placement`, so negotiation is `/api/chat` only.
>   - `options.num_ctx` still reloads the model; `placement.num_ctx` is the way to ask for a window.
> - API key tests extended with positive twins and edges: every route with the key, the ollama.com-signed request plus `x-api-key`, Bearer precedence, case sensitivity, throttle forgiveness and expiry, key rotation without a restart, `::1`, remote callers refused even with the key, a client with no key, and the desktop proxy (`app/ui/apikey_test.go`, runs on Windows/macOS CI). 7 more mutants killed; 2 equivalent ones noted.

> **2026-09-27 — A local API key for incoming connections (`xollama tweak server --api-key`).**
> - Upstream accepts `api_key="ollama"` and ignores it. xollama can now require
>   a real key on every route, as `Authorization: Bearer` or `x-api-key`
>   (`401` + `WWW-Authenticate: Bearer realm="xollama"` otherwise). It is a local
>   key only: registry and cloud keep ollama.com signing, and `OLLAMA_API_KEY` is
>   never read for it. Set with `xollama tweak server --api-key=generate|set|remove|status`
>   (the key is never on the command line) or `XOLLAMA_API_KEY` on the server,
>   which wins. The server stores only the SHA-256 (`~/.ollama/xollama-server.json`,
>   0600). The client sends `XOLLAMA_API_KEY` or `~/.ollama/xollama-api-key`.
> - Hardening:
>   - constant-time digest compare;
>   - 10 wrong keys per peer per minute → 429, keyed on the TCP peer (not
>     `X-Forwarded-For`), and a missing key does not count;
>   - the key is stripped before handlers, so the cloud passthrough cannot
>     forward it;
>   - the management route is loopback-only and refuses proxied requests;
>   - `ClientFromEnvironment` alone carries the key, and never follows a
>     cross-host redirect with it;
>   - the host probe never sends it and recognises a keyed xollama by its
>     challenge;
>   - the CLI warns before sending it over plain HTTP to another host;
>   - the server's self-calls use a per-process token;
>   - the desktop proxy injects the user's key;
>   - feature `api_key_v1`.
> - Docs: `docs/xollama/api-key.mdx`, with a Warning that the key is clear text
>   over HTTP and the connection must be TLS-encapsulated; Caddy, nginx and SSH
>   tunnel recipes. Registry row `api-key`.
> - Tests in five files, and 20 compiling mutants, all killed. Live on solidPC
>   with a throwaway server on :22500 as `ollama`: open → generate → 401 without
>   the key / 200 with it (Bearer, x-api-key, LAN) → CLI error naming
>   `XOLLAMA_API_KEY` → plain-HTTP warning → remote and proxied admin 403 →
>   429 after 10 wrong keys from the LAN while loopback kept 200 → remove →
>   open. The key never appeared in the server log.
> - Also today: eleven2go's xollama (0.34.2-xollama.1) is exposed on
>   `192.168.178.161:22434`. It uses `XOLLAMA_HOST=0.0.0.0:22434` as a user
>   variable, because that build predates the Expose fix, plus a firewall rule
>   "xOllama 22434" (Private). The solidPC dev server is on `*:22434`. Both are
>   reached from pandorum.
> - Left: remote council members (`council.<role>.host`) send no key yet; the
>   engine subprocess port is loopback-only and not keyed; mail Cerebriline the
>   header contract.

> **2026-09-27 — Plain models can host a client's own PolyKV pools (`session.client_pools`).**
> - Cerebriline asked (mail #411) to drive PolyKV itself on non-council models.
>   The engine had no seats for that: `--polykv-max-pools` defaults to 0, and
>   xollama passed it only for its own automatic pooling or a council.
>   `session.client_pools` / `XOLLAMA_POLYKV_CLIENT_POOLS` now adds seats for
>   the client, counted in the memory estimate, never in xollama's registry.
> - A native chat placed on a client's pool no longer feeds automatic capture
>   (it already did not on the completion path).
> - Contract answered per question in mail #414.

> **2026-09-27 — A council member's own results fit its window; never-fitting requests fail at once; Expose binds.**
> - A member's own tool results fold to refs past three quarters of the window
>   (characters): older turns first, then its last turn's largest, searched
>   with `council_evidence`. A refusal needing more than the whole window is an
>   immediate error, not 2 minutes of retries.
> - The desktop app's Expose set only `OLLAMA_HOST`, which xollama ignores, so
>   an exposed install stayed on 127.0.0.1 (eleven2go). It now sets
>   `XOLLAMA_HOST=0.0.0.0:<port>`.

> **2026-09-27 — Council tools: narrated calls stopped; long results travel by ref (`council_evidence`).**
> - A researcher's first reply that names a tool without calling it is dropped
>   and asked again once. With the stronger note it never fired: live 10+10,
>   council 10/10, plain 8/10.
> - Results over 1,500 characters travel in findings as a ref plus ten lines;
>   members read ranges or patterns back with the council's own
>   `council_evidence` tool, answered in the server. A member's own older
>   results fold to refs past 12,000 characters.
> - Live, 20 KB log + 8 KB config: every completed run right and byte-exact on
>   both sides (council 9/9, plain 12/12). Three council runs never completed:
>   a member whose own results outgrew the owner's window, waited out for 2
>   minutes, then 503. Open, with the owner.

> **2026-09-27 — A council worker with no pool layer runs inside the owner's window.**
> - Booked on its own session it could wait out admission beside an owner
>   holding the whole cache. It now runs on the owner, inside its window, one
>   at a time, as compaction calls do. The test fails without the branch.

> **2026-09-27 — 9.5 fixed: the council is as reliable with tools as the plain model.**
> - The owner rejected "less reliable" as a finding. A per-member debug trace
>   found three faults of ours, with compaction and thinking both ruled out:
>   - tool results stayed private to the member that called for them, so
>     the synthesizer (the only writer) never saw the file it edited, and
>     critics re-read everything. Findings now carry their evidence;
>   - the charter contradicted the tools ("only their own knowledge");
>   - a resumed member's PolyKV layer was cut after its own tool results.
>     That meant a private pool per round trip, or none: it booked cells
>     beside a full owner, and waited out admission.
> - Live A/B after the fixes, interleaved: council 6/6, 27–38 s; plain 6/6,
>   5–7 s. No critic tool calls, no unpooled members.
> - A procedure fault on the way (bug-144): the dev server was found by
>   name, so a build named `xollama-trace` survived a restart and served one
>   batch on the old binary. That batch was discarded. Find it by its port.

> **2026-09-26 — Phase 9.5: the council uses the client's tools (`council_tools_v1`).**
> - A council turn with tools and `council_chat_state` uses the tools.
>   Researchers and critics call only the tools marked `x_read_only` (or MCP
>   `readOnlyHint`); the synthesizer and a direct answer call any. A member's
>   call ends the response like a model's, under an id naming the member
>   (`r2:call_x`); the results plus the state resume it. Without the state,
>   tools stay a plain chat. Every member carries the tools, and so does the
>   PolyKV root.
> - Live on b137, a client loop over a fake repository: parallel members'
>   calls travel together, each round trip resumes only who waits, and only
>   the synthesizer writes. The first prompts made researchers invent tool
>   results, because the charter still said "their own knowledge". With a
>   tools paragraph and role notes, 4/6 runs were fully right. The plain model
>   got 6/6 in about a sixth of the time.
> - bug-143 (a race on the suspended members) caught by `-race` and fixed.
> - Open for the owner: whether easy tool turns should go to the council at
>   all.

> **2026-09-26 — Hugging Face pulls work again; upstream's Dockerfile listens where it says.**
> - Hugging Face now redirects downloads across its own hosts (hf.co →
>   huggingface.co → its CDN), and the v0.34.2 base followed same-host
>   redirects only, so every `hf.co/…` pull failed with "blocked redirect to a
>   different host". Upstream fixed it in v0.34.4 (6383a0fa, #18533:
>   redirects allowed among hf.co, huggingface.co, ollama.com, ollama.ai and
>   their subdomains); cherry-picked with `-x`, so the next sync meets the
>   same hunks. Live: `hf.co/bartowski/SmolLM2-135M-Instruct-GGUF:Q4_K_M`
>   pulls on the dev server. Reported by a user's test suite, which skips that
>   scenario on xollama until this ships.
> - Upstream's `Dockerfile` set `OLLAMA_HOST=0.0.0.0:11434`, which xollama
>   ignores: an image built from it bound the container's loopback at 22434
>   and was unreachable. It now sets `XOLLAMA_HOST=0.0.0.0:22434` and
>   `EXPOSE 22434` like `Dockerfile.xollama` (`docker-release` hook). The
>   published image was already right; it is built from `Dockerfile.xollama`.

> **2026-09-26 — Phase 9.4: a council turn resumes from the client's state (`council_chat_state_v1`).**
> - A client that sends `"council_chat_state": ""` gets a sealed state blob
>   after the route, the plan and each member, and on the done chunk.
>   Sending the newest back resumes the turn: finished members are not
>   asked again. The done blob carries the compaction record, which a
>   restarted server takes back. Protobuf (`protowire`), AES-256-GCM, key at
>   `<models>/council-state.key`, bound to hashes of the history and the last
>   user turn.
> - Live on b137: a turn broken off after 4 states (26.8 s), resent with the
>   newest: only the 2 critics and the synthesizer ran, 28.3 s, first token
>   12.9 s.
> - bug-142 fixed on the way: a client leaving mid-turn left the turn waiting
>   forever. The scheduler drops a cancelled request unanswered, so a member
>   being scheduled never returned, the root was never promoted, and the next
>   turn on that conversation waited on it. The member's read now ends with
>   the context.
> - Next: mail the Cerebriline session; then 9.5, tools on council turns.

> **2026-09-26 — The compaction writer fits its window: compact instruction, measured on b137.**
> - The writer's instruction went from 2.5–3k tokens to about 500: a compact
>   replay prompt (565 → 247), marker (156 → 63), and no requests block (the
>   summary still quotes them). The trigger is capped so the writer fits.
> - A/B on opencoti b137 (0412 in): both arms 6/6 turns and 6/6 recall, the
>   same wall time; mean first token 19.2 s against 24.1 s. At 16k the
>   writer now fits (pooled folds), with no text path and no refused-root fold.
> - opencoti b137's pool-owner-evict fired in the council's pattern: no
>   500s, bug-139 closed.

> **2026-09-26 — Phase 9.3: the council shares one prefix.**
> - Every member sends an empty system message, then the conversation. The
>   charter opens the planner's route and plan requests. The client's system
>   prompt goes only to the synthesizer and a direct answer.
> - A/B on b133, today's layout against 9.3: same routing (6/6 once the route
>   request carries the charter; 4/6 without it) and the same format adherence
>   (9/9). A council turn takes 38.6 s instead of 26.4 s, because researchers
>   and critics are no longer held to the client's answer format and write to
>   their caps.
> - A live check of 9.3: a Cerebriline-style P0 (`[{system:""},{user:…}]`,
>   8 tokens, owned by the session) is now what a council's root forks from.
>   No fallback; 5,249 of 6,033 prompt tokens were cached.
> - bug-141 fixed: roots the engine made unowned (their session had ended) are
>   no longer kept, which leaked pinned pool seats.
> - Left: tools on council turns (9.5) and the sealed state (9.4); the
>   compact-writer A/B waits for opencoti 0412.

> **2026-09-26 — Phase 9.2: client placement (`client_placement_v1`).**
> - `placement {pool_id, num_ctx, num_ctx_min}` on `/api/chat`. A plain turn
>   hands all three to the engine. A council turn forks its conversation root
>   from the named pool when its prompt starts with it, else builds its own.
>   It never releases the client's pool.
> - Live on b133: a plain turn served 285 of 316 prompt tokens from a client
>   pool. A council turn with a pool it does not start with fell back cleanly
>   (engine 400), and the pool was left alone. Findings for clients: the model
>   needs pools on (`XOLLAMA_SESSION_POOL`), the pool must be rendered from the
>   exact text sent, and on a council model it must belong to the conversation's
>   session.
> - `chat_render_v1`: `_debug_render_only` on `/api/chat` is the renderer a
>   client cuts P0 from (Cerebriline, mail #390); on a council model it now
>   renders what the members send instead of convening the council.
> - Left: sharing on council turns needs 9.3's layout (Cerebriline's P0 =
>   render([{system:""},{user:SENTINEL}] + tools) cut at the sentinel, #390);
>   the compact-writer A/B waits for opencoti 0412.

> **2026-09-26 — Phase 9.1: `/api/xollama` lists features; council thinking is tagged per member.**
> - `features: ["council", "council_compaction_v1", "council_tags_v1"]` on
>   `/api/xollama`. Cerebriline gates each piece on these names.
> - Every thinking chunk of a council turn carries `council: {role, index,
>   round}` and holds one member only. Content (the answer) and the done chunk
>   are untagged; the text headings stay for clients that do not read tags.
> - Cerebriline decisions recorded in the plan (mails #379–#384): the state is
>   `council_chat_state`, a sealed protobuf blob for resume only, emitted at
>   every checkpoint; Cerebriline sends `placement.pool_id` on council turns.
> - Left: the compact-writer A/B on b133 (running; compaction changes held
>   back until it is measured), the opencoti 500 on pool create (#385, fix in
>   a new build), then 9.2 client placement.

> **2026-09-26 — Council compaction live on b133: five faults fixed, six turns clean of stalls.**
> - Live runs (six turns, 16k council, ~9.5k tokens of history) found and
>   fixed bug-134…138: the writer is asked only when it fits, the text path
>   goes in pieces on the owner (serially), the kept root is released before
>   a fold from text, a resize's new window is `window_new` (misread since
>   Phase 6), and a review with no room to fork is skipped.
> - Fifth run: every turn 45–77 s, first token 10–34 s; idle folds 2–3 min;
>   no admission waits. Turn 2 went from 153.9 s (first token 100.4 s) to
>   57.7 s (11.2 s).
> - Open: the writer rarely fits at the trigger on a 16k window (every fold
>   came from text), and bug-139 (text calls leave private cells on the
>   owner, so the next root is refused once); asked opencoti (#376).

> **2026-09-26 — Council compaction: fits its window; dev server on b133.**
> - The first live run (b128) failed on turn 2's idle fold: the owner held a
>   6,656 grant under a 9.5k conversation, so the writer was refused three
>   times, and the one-piece text request waited out admission while holding
>   the next turn (bug-134).
> - Fixed: the writer runs only when conversation, instruction and reply fit;
>   the text path goes in pieces that fit; the budget floor scales to
>   window/8 below 32k. New test and 6 mutants.
> - The dev server (22434) runs opencoti b133 `2609261655001` (b128 + 0410
>   ckpt-periodic + 0411 adm-running-priority), copied from bs2 and
>   hash-checked, as the owner asked; `council-b133.sh`.
> - Cerebriline provider design (mails #366/#367): the owner's decisions are
>   recorded — sealed council state in-band, PolyKV driven by the client,
>   tools on council turns with read-only members and a writing synthesizer,
>   the council compacting, and one prompt layout (empty system, tools,
>   conversation; role prompts as user messages; the client's system prompt
>   after the synthesizer's). Answered in #370–#372.

> **2026-09-26 — Council compaction: Phase 8 built, Cerebriline's ported.**
> - `server/council_compaction.go` and `council_compaction_prompts.go`
>   replace Phase 6's compaction: a record per conversation applied every
>   turn, the writer as the owner's next turn on the root, two critics on
>   the replay's halves and a synthesizer on a fork of it, a retrospective,
>   incremental folds, and Cerebriline's fallbacks. It runs on every engine.
> - Settings: `council.context.compaction` (`agentic`/`basic`), `review`,
>   `retrospective` (schema v4, unreleased).
> - Faults found while building it: an unowned tree's per-request grant was
>   taken as the window, and hung the idle fold; the refused-root retry
>   compared message counts; a fold could grow the conversation.
> - Tests under `-race`; 28 compiling mutants, all caught but one
>   equivalent. Live run on b128 pending.

> **2026-09-26 — Council compaction: Phase 8 proposed, a port of Cerebriline's.**
> - The owner asked whether the council's compaction followed Cerebriline's
>   agentic council compaction. It did not: only the 0.85 pressure trigger
>   came from the guide. Reading the code also showed faults:
>   - it forgets a compaction, so it likely flips between compacted and full
>     turns;
>   - it re-summarises all the old turns;
>   - its budget is wrong;
>   - it edits the system message, which breaks the cached prefix.
> - The plan's Phase 8 now ports Cerebriline's flow, read from
>   `/shared/dev/cline`:
>   - trigger min(0.9 × usable, room) and target 0.25 of the message budget;
>   - the kept tail by recency bounds;
>   - one user-role summary message at the front: the user's requests
>     verbatim, a retrospective and the replay;
>   - a writer, two critics on the replay's halves, and a synthesizer;
>   - carried forward and incremental, with Cerebriline's fallbacks.
> - Approved 2026-09-26, sized on the granted window as Cerebriline does;
>   being built.

> **2026-09-26 — The council holds the conversation once; idle compaction tested live.**
> - Scripting the idle test found a design flaw: the planner's session and P1
>   were two copies of the conversation, both charged to the owner. The tree
>   was full at ~45 % of the window, so compaction never fired, and refused
>   pools ended the turn with a 503 after 2 min.
> - Fixed as the owner chose (guide §6.2 arm C, `server/council_polykv.go`):
>   - P1 is built first and the planner attached to it.
>   - The first turn's P1 is unowned (`pool_unowned_v1`), and the idle council
>     promotes it to an owned one. The next turn waits for that and forks it.
>   - The summary is asked as a turn of the conversation.
>   - A root refused with "compact the session" (`llm.ErrSessionFull`)
>     compacts and retries.
>   - Seats: `councilPoolSeats` + 2 for the root chain.
> - Live on b128, `omni-council-idle` at 16k, ~7,000 tokens of history. With
>   the idle summary the next message's first token came at 2.5 s (turn 47 s);
>   without it, 18.3 s (turn 64.5 s). The owner's pressure after turn N was
>   0.867.
> - Phases 6 and 7 closed. Left: the pin moves to a published build with
>   `pool_unowned_v1`, on a measurement.

> **2026-09-26 — opencoti fixed #349 (b128); `num_ctx 0` and `slots.live` tested live on it.**
> - opencoti b128 `2609261427001` (dev, local only) builds the recurrent
>   state before the attention window and reserves the MTP draft context.
>   Their gate: b125 fails our `-c 524288 -np 4` launch, and b128 loads it.
> - Our councils on b128 (a copy in `/srv/ml/xollama-phase2/engines/`, dev
>   launcher `council-b128.sh`):
>   - `num_ctx 0` → `-c 262144`, the trained context, 22.9 GB. The pools
>     were created `owner ''` (unowned), and the turn took 74 s.
>   - `slots.live: 4` at 131k → `-c 524288 -np 4`, 23.0 GB, turn 86 s.
> - The pin stays on b111 until opencoti publishes to the HF dev repo and it
>   is measured. Left: idle compaction on a long conversation.

> **2026-09-26 — Council roles on eleven2go tested live; three bugs fixed.**
> - Researchers ran on eleven2go's ollama (the think-budget fork, `:11434`,
>   treated as stock: `think=true`, 56 s), on its xollama through an SSH
>   tunnel (`think=2048`, 66 s), and on a cloud model through that xollama
>   (`think=true`, 53 s). A tunnel killed mid-reply fell back (58 s).
> - Fixed:
>   - A cloud reference's `/api/show` carries no `remote_host`. A cloud
>     reference is now cloud by name on every server.
>   - A dropped connection ended the stream silently, and the council went on
>     with no research. A remote reply now needs its `done` line.
>   - A role on another model had `think` cleared to nil, which upstream reads
>     as true, so `qwen3:8b` reasoned away its whole cap and answered nothing.
>     `think: false` is now kept, and an empty reply from elsewhere falls back.
> - opencoti #356: #349's cause is found (rs built after the attention
>   window; draft context not reserved). b126 boots the main context, and
>   the draft-aware sizer is in progress. We stay on 131k.

> **2026-09-26 — Cloud roles tested live; think budgets only where understood.**
> - `gemma4:31b-cloud` as researchers, critics, planner and synthesizer,
>   and in all four roles: every turn answered, 17–54 s. The all-cloud
>   council took 17 s. A researcher on a missing model fell back to the
>   council's model and said so (59 s, 9 members).
> - The owner's "hang" on `omni-council-think` was the pre-2048 build.
>   `on` was `medium`, 32,768 tokens per member, and each researcher ran to
>   the cap at about 40 tok/s (13.5 and 14 min). The same question on the
>   current build takes 2 min 11 s.
> - Found live: ollama.com refuses a numeric `think`. `councilTakesBudget`
>   now sends a token budget only to this server's own models and to a model
>   another xollama serves itself. Cloud is decided by manifest or
>   `remote_host`, as cerebriline does, never by name. Everything else gets
>   `think: true`. Retest: 47 s, no error.
> - The dev home's unregistered key is linked to the service's signed-in key
>   (the old one kept as `id_ed25519.dev-unregistered`), at the owner's
>   request.
> - opencoti #353: 0408 does not fix #349. b125 fails the 4 × 131k launch
>   the same way, and they are investigating.

> **2026-09-26 — Council Phase 7 built: roles on cloud models and other servers.**
> - The owner decided the open points. A researcher or critic that fails on
>   another model or host is answered by the council's own model, and the
>   turn goes on; a planner or synthesizer failure fails the turn. A literal
>   host URL is fine. `host` joins schema v4, which no release has shipped.
> - A cloud role already worked: `council.<role>.model: …:cloud` goes
>   through `ChatHandler`'s cloud proxy.
> - New `council.<role>.host` (needs `model`; tweak
>   `--council-<role>-host`). It is served by `server/council_remote.go`
>   over `api.Client`, with no session and no pool.
> - Hosts are gated by the operator's `XOLLAMA_COUNCIL_HOSTS` (default
>   none): a pulled council model could otherwise send every conversation to
>   the host it names.
> - Unit tests with a stub ollama over HTTP; every guard fails under a
>   mutation. The live test is pending.

> **2026-09-26 — Council Phase 6 built: think 2048, pressure and idle compaction, `num_ctx 0` as unowned pools, `slots.live`; Phase 7 proposed.**
> - The owner approved Phase 6. A role's `think: on` is now a 2048-token
>   budget (`DefaultCouncilThinkBudget`), and mode and budget stay per role.
> - Compaction follows the owner's raw `/kv` pressure: at `compact_at`
>   (0.85) before a turn, and at the new `council.context.idle_compact_at`
>   (0.75, tweak `--council-idle-compact-at`) in the background after the
>   answer, so the next message finds the summary ready. Without a pressure
>   reading, the token budget still decides.
> - `num_ctx 0` under PolyKV only (hook `polykv-window`,
>   `llm/engine_window.go`): the launch takes the trained context as the
>   pool, and with `pool_unowned_v1` the council's pools are unowned and the
>   planner sends no `num_ctx`. Stock llama.cpp and opencoti without pools
>   keep upstream's clamp to 4.
> - `slots.live` (hook `slots-live`): the slots a model loads with, in place
>   of `OLLAMA_NUM_PARALLEL`, on opencoti only.
> - Unit tests at every layer, each mutation-checked. No live run: the owner
>   tests it on the next promoted build. Not built: warming the owner session
>   with the compacted prefix after an idle summary.
> - opencoti #350 on #349: the fit bug is the main context's two-pass window
>   re-size ignoring its recurrent-state cells, not the MTP context. Fix
>   0408 comes in the next dev build.
> - Phase 7 proposed: a role on another model **or another ollama instance**
>   (a cloud model, or another machine), via `council.<role>.host`.

> **2026-09-26 — Council members can think; the MTP IQ2_M runs councils at 131k; Phase 6 proposed.**
> - `council.<role>.think` (`off` | `on` = medium | level | token count), with
>   `tweak --council-<role>-think`. The council resolves the level against the
>   member's window and sends an explicit token budget. It raises
>   `num_predict` to the reply cap plus the budget. It never shows the
>   reasoning, and the model's `think_budget_message` closes it at the cap.
>   The routing call never reasons. Tests at the schema, runner and server
>   level; each fails under a mutation.
> - Live, the defaults proved unusable. `medium` at a 131,072 window is
>   32,768 tokens per member, and a researcher looped ("Wait, I should
>   check…") past 29k tokens. The run was stopped after 11 min. The default
>   budget for members is an open decision.
> - Stores: `mannix/omnimerge-v4-mtp:IQ2_M` (MTP, 65 blocks) replaces the
>   non-MTP IQ2_M in both. The service store's
>   `omnimerge-v4-mtp_tb:27b-iq2m-128k` is recreated on it. The old tag's
>   CRLF Modelfile had swallowed its RENDERER, PARSER and think_budget into
>   the TEMPLATE, so the new tag takes them from `…:27b-q4km-128k`. The
>   council store holds `omni-council` and `omni-council-think` (qwen3.5
>   renderer, `num_ctx 131072`, `kv {k: f16, v: q8_0}`).
> - 131k with MTP: it failed only because the test script set
>   `XOLLAMA_NUM_PARALLEL=4`, which makes `-c = 4 × 131072`. Without it: `-c
>   131072 -np 1 --max-parallel 4`, 10.4 GB, and a full council turn in 52 s.
>   The engine's fit omits the MTP context's recurrent-state cells
>   (opencoti #349).
> - Phase 6 is proposed in the plan: PolyKV-only sizing, `num_ctx 0`,
>   compaction on the owner's pressure (0.85, and 0.75 while idle), per-model
>   `slots.live`. Stock llama.cpp and opencoti without PolyKV stay as they are.

> **2026-09-26 — `continue_pool` planned, waiting for an HF dev publish.**
> - New plan [`plans/council-continue-pool.md`](plans/council-continue-pool.md)
>   (WAITING). It starts when an opencoti build carrying patch 0406
>   (`continue_pool`, unowned pools; b124 is local only) is published to
>   the HF dev repo, as the owner decided. Phase 0 measures turn-over-turn
>   prefill, dense and hybrid, at 16k and 131k.
> - The Docker image plan's row is brought up to date: the first `:dev`
>   image is published and GHCR is public; user testing remains.
> - The installed service (`/usr/local/bin/xollama`, `05c16dfa`, 11434)
>   predates the council and refuses a council model. Councils are tested
>   with the `dev` build on 22434 against the isolated store.

> **2026-09-26 — Desktop app shows councils (option C); GHCR confirmed public.**
> - A council model gets a *council* badge in the model picker, and a
>   **Deliberation** toggle in place of the Think button. The toggle is on
>   by default and remembered per browser. The app's backend dropped every
>   `think:false`, so nothing could hide the deliberation before. It now
>   forwards `false` for a council only (`app/ui/council.go`, `council`
>   hook). The UI builds, vitest passes 201 of 201, and the Go test runs on
>   Linux and compiles for Windows. Not yet tried in the running desktop app.
> - `ghcr.io/mann1x/xollama` was created public by its first push. An
>   anonymous token lists `dev` and `0.34.2-dev.1f14838e`;
>   `docs/features/docker-release.md` says so.
> - opencoti b124 (dev build, not published) adds `continue_pool` and unowned
>   pools (#343). They are request fields on routes `/api/engine` already
>   proxies, so it needs no change. The pin stays on b111.

> **2026-09-26 — Council Chat Phase 5 closed: docs, the one-shot CLI turn,
> councils at 131k on a hybrid model; bug-117 fixed.**
> - Docs: `docs/xollama/council.mdx` (users, in the navigation and the index)
>   and `docs/features/council.md` (maintainers). `compact_at` wording
>   corrected in the schema, `tweak` and the validation error.
> - CLI walked live as `ollama` on b111. One-shot `xollama run <council> "…"`
>   went to `/api/generate` and silently skipped the council; it is now sent
>   as a chat turn (`cmd/council_run.go`, `council` hook in `cmd/cmd.go`).
> - bug-118, at the model's own 131k (`-c 524288`, `-np 4`). The engine's
>   elastic recurrent-state cache stayed at 4 committed cells and refused a
>   critic with 429. Three things went wrong in turn, each fixed. The chat path did not wait out a 429,
>   as the completion path does, and now it does (503 after 2 min). ggml's
>   routine `failed to allocate graph, reserving` line read as a runtime OOM
>   and expired every model; on opencoti it is no longer an error. And the
>   tree's four pinned layers held every cell, so the synthesizer could never
>   be seated. On a recurrent engine the tree now releases each finished
>   stage's layer. Live: 3 of 3 full council turns (115, 66, 54 s), 0
>   refusals, 0 errors, no expiry.
> - bug-117: a runner swap no longer waits on stock-llama-server discovery
>   for devices opencoti serves (`discover/refresh_opencoti.go`; timed-out
>   dirs cool down 15 min). The reaper no longer logs a stop it asked for as
>   an ERROR. Refresh-to-load went from 9.3 s to about 1 s, and a swap's
>   round trip from 15.8–20.2 s to 10.1–11.8 s.
> - Desktop toggle not built. The app already serves a council tag, with
>   the deliberation shown as thinking; the options are under Open
>   decisions.
> - Sent to opencoti: the elastic `rs` cache grew 4 → 8 at 16k but not at
>   `-c 524288`.

> **2026-09-26 — b65 vs b111 re-measured, paired and interleaved (opencoti
> #329): the pin stays on b111.**
> - Five repeats per cell, order alternating, never more than one compute
>   app on the 3090 in any cell (sampled every second).
> - Multislot aggregate: b65 median 541.9, b111 500.8 tok/s (−7.6 %). Each
>   build's range is about 18 %; b111 was lower in 3 of 5 pairs. At most a
>   small effect.
> - 70B overflow: b65 median 1.39, b111 1.87 gen tok/s; b111 faster in 4 of
>   5. The earlier deficit does not reproduce. Both builds follow load time
>   (host page cache), not the build.
> - Sent to opencoti (#336). Raw data:
>   `/srv/ml/xollama-phase2/as-ollama/regress-paired/`.

> **2026-09-26 — Council Chat Phase 4: members share the conversation's KV
> through PolyKV; `/api/engine` reaches every opencoti route.**
> - `llm/engine_council.go` is the PolyKV client: a per-request `Placement`,
>   plus pools, fork, release, session close, `/kv` and resize.
>   `server/council_polykv.go` is the per-turn tree. The owner books the
>   window; P1, P2r, P2f and P3s are each built once; workers attach and are
>   closed; pools are released newest first. The owner's window shrinks,
>   deferred, under `/kv` pressure and grows back when the pressure clears,
>   and the conversation is compacted past `compact_at`. A PolyKV council
>   launches with `2 + 2 × rounds` pool seats. Hunks: `council` Registry row.
> - A/B on b111 (omnimerge v4 IQ2_M, 16k, `-np 4`, ABAB, 4 council turns per
>   arm): computed prefill 3,139 → 525 tokens per turn (−83 %), cache hit
>   48–52 % → 89–94 %, peak KV cells about −40 %, 4 of 4 pool seats used, no
>   refusals, no pools left after a turn. Wall time at parity (60.2 s vs
>   57.6 s): the turn is decode-bound. Plan Phase 4 has the table.
> - `/api/engine` now serves GET, POST and DELETE over opencoti's whole
>   management surface (`kv`, `elastic`, pools and their capacity, `tps` SSE,
>   sessions close and resize, locks, `apply-template`…), from a route table
>   mirrored from the engine's registration. Inference, `/cors-proxy` and
>   `/tools` stay out. `?live=1` and other queries are forwarded.
> - Fixed: the members saw the model's `MESSAGE` turns twice (bug-116). Open:
>   every runner swap waits about 2.3 s for a discovery subprocess and logs an
>   ERROR killing it (bug-117).
> - Docker `:dev` run 36221348282 (the b111 image) succeeded.
> - Left: Phase 5 (surfaces, `docs/xollama/council.mdx`).

> **2026-09-26 — Council Chat Phase 3: a council model answers through
> every chat API.**
> - `internal/council/` (the errgroup runner) and `server/council.go`
>   (members as in-process chat turns, each on its own engine session), plus
>   one `council` hook line in `ChatHandler`. Tools, a `format` and every
>   member's own turn bypass it.
> - Live on b111 (omnimerge v4 IQ2_M council tag): "Hello!" answered
>   directly in 1.4 s warm; a council turn in 54–102 s with 7 members; the
>   second turn, OpenAI (`reasoning` + content) and Anthropic all correct.
> - Corrected: a council tag does not share its base tag's runner (upstream's
>   `ManifestDigest` is in the launch config); the docs said it did.
>
> Next: Phase 4, the PolyKV path (owner session, pools, pressure and resize).

> **2026-09-26 — Engine pin moved to b111 (2609252051001).**
> - `llm/engine/pin.txt`: rev `1d0f1dcd`, bin `a66e9e27`, CUDA dso
>   `f32ebf54`. b111 brings `kv_pressure_v1`, `kv_resize_v1` and
>   `kv_resize_deferred_v1`, the surface Council Chat Phase 4 builds on.
> - Cost: **no Linux Vulkan payload** in these bytes, so the Vulkan dso and
>   accel rows are retired and Vulkan loads route to llama.cpp again.
> - Measured as `ollama` beside b65: compat 8/8, throughput and gemma4 parsing
>   equal; argv surface unchanged. Medians lower on b111 for multislot
>   (485 vs 595 tok/s) and the 70B overflow (2.17 vs 3.18 tok/s), spreads
>   overlapping, reported to opencoti. No engine-defect row changes.
>
> Next: Council Phase 3 live on b111; the `:dev` image picks this pin up.

> **2026-09-26 — ollama#4165's single-sequence rule binds only stock
> llama.cpp.**
> - Qwen3.5, Qwen3-Next, Qwen3-VL, LFM2, Nemotron-H and mllama now take
>   `OLLAMA_NUM_PARALLEL` and dynamic slots when opencoti serves them. The
>   scheduler asks `llm.WouldUseOpencoti` before capping; with
>   `XOLLAMA_ENGINE=llamacpp` the cap is upstream's, unchanged.
> - A load predicted for opencoti that lands on stock anyway (artifact
>   missing, or the opt-in retry) relaunches at one sequence
>   (`servedSequences`). Embedding models stay at one on every engine.
> - Measured on b111 as `ollama`: qwen3.5:2b launched `-np 4`, 4 streams at
>   ~107 tok/s each. `probe/parallel_correctness.py` (4 checkable tasks,
>   serial then concurrent, greedy, 3 rounds): omnimerge v4 IQ2_M 12/12
>   correct, 12/12 identical to serial; qwen3.5:2b the same 9/12 correct
>   serial and parallel (the misses are the model's), 0 cross-task bleed.
>
> Next: the b111 pin (a multislot/overflow gap against b65 is being
> re-measured) and Council Phase 3 live.

> **2026-09-26 — Docker image: assembled on hosted runners from pinned
> artifacts.**
> - `docker-release.yaml` no longer compiles anything, and no longer needs
>   the bs2 runner, which was never registered. On `ubuntu-latest` it runs
>   `scripts/docker-assemble.sh`, which stages:
>   - the fork's CPU runtime tgz (`33ac42c1…`);
>   - upstream v0.34.2's GPU and MLX tarballs, pinned by sha256;
>   - the engine from `llm/engine/pin.txt`;
>   - a Go-only `xollama` (go1.26.8, AlmaLinux 8).
>
>   `Dockerfile.xollama` then builds, smoke-tests and pushes the image.
> - The pins are in `llama/runtime-pin-linux.txt`. Its inputs digest leaves
>   out `llama/compat/README.md`; the fork at `d6e24119` and `dev` both come
>   to `eff6800e…`.
> - Validated locally:
>   - the assembly, and a 5.43 GB image;
>   - the container answers `/api/xollama` on `0.0.0.0:22434`;
>   - actionlint and shellcheck are clean.
> - The channel is now the GitHub pre-release flag, not the hyphen, and
>   `:latest` never moves from a branch.
> - Found: upstream's `Dockerfile` sets `OLLAMA_HOST`, so an image built from
>   it would be unreachable. The new image sets `XOLLAMA_HOST`.
>
> Next: push `dev`, then
> `gh workflow run docker-release.yaml --ref dev -f push=true -f channel=dev`
> for the first `:dev` image, then user testing.

> **2026-09-26 — Council Chat Phase 2: a council is a model setting.**
> - `council` in `xollama.json` (schema v4, `types/xollama/council.go`),
>   with 23 `xollama tweak model` rows (`--council`, `--council-charter`,
>   prompts from `@file`), `show` rows and the Modelfile round-trip, all
>   tested.
> - Fixed before it could ship: a council tag would have had its own runner,
>   a second copy of the weights. The launch config now leaves the council
>   out (`LaunchConfig`, inside the `model-config` hook).
> - Found for Phase 3: qwen35 (omnimerge) is on upstream's single-sequence
>   list, so through xollama its council members would run one at a time.
> - The eval harness no longer holds the library implementations (their
>   notes are kept), so no `go.mod` in the repo links eino, langgraphgo or
>   trpc-agent-go.
> - The plan gains "Context, pressure and compaction": every member states
>   its context, and compaction follows the owner's PolyKV pressure.
>
> Next: Phase 3, the runner on the llama.cpp path.

> **2026-09-25 — Council Chat Phase 1: the in-house `errgroup` runner wins
> the library bake-off.** The same council was built in eino, langgraphgo,
> trpc-agent-go and on `errgroup`, all over one shared core and one suite, in
> `plans/council-eval/` (its own module). All four pass 11 tests under
> `-race`, but every library needed sibling cancellation and error ordering
> added by hand. Per request the baseline costs 56 µs per council and 3.2 µs
> per direct turn; langgraphgo costs 69/17 µs, eino 130–180/60 µs, and
> trpc-agent-go 0.9 ms/278 µs, rising to 22.5 ms and 33 MB at 1 MB of state.
> The libraries would bump sonic, protobuf, go-sqlite3 and testify in
> xollama's go.mod. Against b65 with omnimerge v4 IQ2_M, all four run a
> council in 65–70 s, which is noise. Also found:
> - On the hybrid qwen35 model the pools share on exact matches: 33–77
>   tokens prefilled per member, and 54 s pooled against 65–69 s unpooled.
> - Members must state `num_ctx`. Without it the second parallel member is
>   refused with a 429.
> - The planner's calls must share a session: the direct path takes 3.3 s
>   that way, against 6.1 s.
> - The IQ2_M omnimerge tag has no MTP head.
> - One unexplained session leak in 18 runs; the TTL reclaimed it.
>
> Next: Phase 2, the `Council` config in `types/xollama` and `tweak`.

> **2026-09-25 — Council Chat Phase 0 measured on b65.** On b65 with
> llama3.1:8b, the council's pool tree shares as designed. Researchers,
> critics and the synthesizer each prefilled 29–73 tokens of 2.5k–3.4k-token
> prompts, and the owner held 3,343 cells for the whole tree against ~16k
> unpooled. The council's wall time was 13–17 s. Close released everything.
> Confirmed: a request with a `session_id` and no `num_ctx` books the full
> 65,536-cell `session_ctx_max` per request. Routing is the weak link, so the
> planner's decision becomes route-only: 86/100 trivial messages direct,
> 60/60 hard messages to the council, +0.13 s to the first token. Probes are
> in `plans/council-eval/probe/`. Next: the same probes on b111 when it is on
> HF, and Phase 1 over a stub model.

> **2026-09-25 — Project record started; Agentic Council Chat planned.**
> `STATE_SUMMARY.md` and `plans/` created, with a standing rule in `CLAUDE.md`
> to keep them current. New plan
> [`plans/agentic-council-chat.md`](plans/agentic-council-chat.md), now at
> Phase 0. The target is opencoti **b111**; development and smoke tests run on
> the pinned b65 until b111 is on the HF dev repo. The library research
> shortlisted cloudwego/eino, smallnest/langgraphgo and trpc-agent-go, plus an
> in-house `errgroup` baseline, for the Phase 1 bake-off. The Docker image
> design is written down as [`plans/docker-image.md`](plans/docker-image.md)
> (PARKED).

> **2026-09-25 — Toolchain and dependency security (`ad5842ce`).** Releases
> build on upstream's `go` line (go.mod `go 1.26.0`) at its newest patch,
> derived from go.dev in the `plan` job. Today that is go1.26.8, and every
> binary is checked for it. `golang.org/x/{crypto,image,net,sync,sys,mod,term,text}`
> are bumped under the `security-deps` hook. govulncheck went from 25
> reachable vulnerabilities to 0. The 88 UI lockfile Dependabot alerts are
> inherited from upstream (50 are dev-only) and were left as they are.

> **2026-09-25 — llama.cpp comes from the fork, enforced (`10a88f1b`).**
> `scripts/check-compat-origin.sh` and `.github/workflows/compat-origin.yaml`
> refuse any change to `LLAMA_CPP_VERSION`, `llama/server` or `llama/compat`
> that is not reachable from a mann1x/ollama or ollama/ollama ref. For a merge,
> every file must match one of its parents. The fork's 005 was merged by sha
> (`89ae39d3`). The inputs digest is now `73387c282b7f` on both sides.
> `llama/compat/README.md` is agreed to become static, with each patch
> documenting itself; the fork commits that change first.

> **2026-09-25 — First release: `v0.34.2-xollama.1` (PR #1, `990e35e2`).**
> Built on hosted CI and promoted to latest after the eleven2go install check:
> 126.4 tok/s, and the installed exe's sha256 matched the release. The Windows
> legs are pinned to `windows-2022`: the `windows-latest` and `windows-2025`
> images both ship VS2026, which breaks CUDA 13.0 and ROCm 7.1. Payload-id is
> `54e16442…`. First-time-contributor auto-approval was removed on
> mann1x/xollama and mann1x/ollama.

## Where we are

`v0.40.0-xollama.1` is the latest release (2026-10-08): upstream v0.40.0, the
fork's carried patches, opencoti c10 (`2610072136001`), Clef on opencoti,
opencoti first on every platform and the only engine on macOS, the Windows
MLX runtime downloaded by the installer and needing no cuDNN install. `dev`
is upstream v0.40.1 with every runtime pin moved, xo-20 (one GPU through two
backends), the engine on opencoti c10 r3 (`2610090401001`), `x/net` 0.60.0
and the council continue fix; `v0.40.1-rc.1.xollama` is cut from it. Next:
opencoti c11 (bug-3957, the two-GPU KV window; Ternary Bonsai 2 27B) when it
is published. The Agentic Council Chat is in Phase 11.

## What exists today

- Soft fork of ollama v0.34.4 with full upstream history. The engine seam is
  opencoti-llamafile, pinned in `llm/engine/pin/` (pin format 2; engine `2610040837001`).
- Release protocol and hosted CI: `docs/protocols/RELEASE.md` and
  `.github/workflows/xollama-release.yaml`. The Windows CPU runtime is pinned
  in `llama/runtime-pin.txt`, and delta updates are keyed on `payload-id.txt`.
- Model config and `xollama tweak model`, device selection, store ownership,
  the 22434 port with the `XOLLAMA_HOST` namespace, the rebrand, and the
  Windows installer. See the `docs/features/` list in `CLAUDE.md`.
- Guards: `scripts/check-hooks.sh`, the compat-origin check, and gitleaks.

## In flight / waiting on others

- **opencoti:** the pin is on b208 (2026-09-28). Older, from b111: the paired re-run (#336) did not
  reproduce the overflow deficit, and multislot is at most −7.6 % median,
  inside the spread; no bisect, agreed with opencoti (#339). Also waiting
  on: an HF dev publish
  of patch 0406 (`continue_pool`, #343), and of the #349 fix (b128,
  verified locally). The Linux Vulkan `.so`
  comes in their next dev publish. Also waiting on the spent-response port
  and the E2B/E4B gate, which needs an HF repo@rev.
- **mann1x/ollama (fork):** the static `llama/compat/README.md` commit. When
  it lands, xollama takes it by sha.

## Known gaps

- **c10 refuses old AMD drivers** (RADV from Mesa 20 or older, amdgpu-pro
  2.0.154 or older): such a GPU is not used, and models load elsewhere (CPU
  when it is the only one). `OPENCOTI_VK_ALLOW_OLD_DRIVER=1` uses it anyway.
- **Releases before `v0.35.1-xollama.4` have known bugs:** `.2` fails Clef
  models and, on Windows, a Vulkan load now and then; `.3` (pre-release) is
  the first macOS build that updates itself and stages in the folder a stock
  Ollama uses, deleting its staged update. Update to `.4`.
- **Linux arm64** is in `:dev` (2026-10-04) and in the next release as
  `xollama-linux-arm64`. `:latest` is still an amd64-only image of the last
  release. The arm64 image's CUDA and JetPack payloads have never run on such
  hardware; the release workflow's arm64 job, its Linux pin guard and its
  start of the image workflow have not run on hosted runners yet. No Linux
  archive with a runtime exists for either architecture.
- **The last published candidate draft (`rc.1`, pin `2610031615001`) crashes on
  an AMD integrated GPU through Vulkan on Windows.** Fixed by the pin move to
  `2610040710001` (measured on eleven2go, 2026-10-04); it reaches users with
  the next candidate.
- The Docker image is published to `:dev` (run 36221348282). It is amd64
  only, and b111 carries no Vulkan payload, so Vulkan loads go to llama.cpp.
- Upstream's `Dockerfile` still sets `OLLAMA_HOST`/`EXPOSE 11434`, which
  xollama ignores; only `Dockerfile.xollama` makes a reachable image.
- `/api/engine` control routes are unauthenticated, like the rest of the
  Ollama API. On a server bound beyond localhost, anyone who can reach the
  port can close sessions or release pools (stated in
  `docs/xollama/introspection.mdx`).
- On a hybrid model at a large context (b111, `-c 524288`) the engine keeps
  4 recurrent-state cells and refuses a fifth sequence. This is intended
  (opencoti #348): the cache grows only into free VRAM beyond a 1 GiB margin
  (`OPENCOTI_RS_VRAM_MARGIN_MIB`), and the base KV reservation leaves none.
  A council copes by releasing finished layers, and other parallel work
  queues.
- Open fork-sync items: `docs/protocols/FORK-SYNC.md` § "Open items".
- Carried upstream PRs: `docs/protocols/CARRIED-PATCHES.md`.
- UI lockfile Dependabot alerts are inherited from upstream and not addressed.

## Immediate next steps (in order)

1. The v0.40.1 sync when the fork's pins arrive (inputs digest gains
   `llama/clef`, README-excluded for the fork's runtimes; MLX moves, the
   reldir Windows zip later and re-checked without cuDNN); xo-20 ships with it.
2. opencoti c11 (Ternary Bonsai 2 27B, two new weight types): the catalog and
   the pin move on a measurement once opencoti publishes it.
3. Run the Phase 8 compaction live over four and more turns
   (`council-idle.py`), then assess the council's use of the shared prefix on
   PolyKV (the owner's request).
4. Move the engine pin only on a measurement.

## Open decisions

- None open on the council; the next choices come from the live tests.

## Maintenance protocol

Every session that changes code, releases, pins or plans adds a dated entry
at the top of this file, in the same commit as the change. That session also
rewrites any fixed section the change makes stale. When a plan changes status
or phase, update its row in `plans/MASTER_PLAN.md` and the plan itself in the
same commit. Keep entries factual: shas, tags, numbers, and what is left.
