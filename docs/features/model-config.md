# Model config carrier — `xollama.json`

## The problem

xollama needs some settings to travel *with a model*: which engine it requires,
which speculative driver to use. Upstream has no field for them, and the obvious
place is the wrong one.

`api.FormatParams` resolves every Modelfile `PARAMETER` name against the json
tags of `api.Options` and returns `unknown parameter '%s'` for anything else. So
a fork setting added there would make a model published from xollama **fail to
create on stock ollama**. That is the opposite of what a soft fork should do —
the model should still work, just without the fork's behaviour.

Hijacking the `LICENSE` layer was the fallback idea. It is not used: a license
layer that is not a license is the kind of thing a fork gets criticised for, and
it only carries one unstructured string.

## The carrier

A layer of media type `application/vnd.ollama.image.json`, named `xollama.json`.

Four properties make this work, and all four are upstream's own behaviour:

| | Why it holds |
|---|---|
| **Stock ollama ignores it** | The layer switch in `server/images.go` has no case for this media type at all, so it is read past in silence. |
| **It cannot collide** | Upstream's own json layers are named `config.json` and `<prefix>/config.json`. The NAME is what separates them, which is why the remove-on-override matches on name as well as media type — dropping by media type alone would delete a safetensors model's real config. |
| **Push and pull carry it** | Neither filters by media type; both iterate `mf.Layers` whole. |
| **The reader already exists** | `manifest.ConfigLayer` / `ReadConfig` / `ReadConfigJSON` are generic over the layer name. |

## Schema

`types/xollama` is an additive package — the schema, and nothing about how the
fork uses it.

```json
{
  "version": 1,
  "engine": "opencoti",
  "draft": { "spec_type": "draft-assistant" }
}
```

| Field | Meaning |
|---|---|
| `version` | Required, and **computed rather than declared** — see below. A version newer than the build is an error, not a warning: these fields change how the model is served, so reading a v2 config as a v1 would serve it differently from how its publisher meant, silently. |
| `engine` | `opencoti` or `llamacpp`. Empty means the model does not care and `XOLLAMA_ENGINE` decides, which is the normal case. Note `auto` is **not** valid: a model saying "auto" is a model saying nothing. |
| `draft.spec_type` | Overrides the `--spec-type` otherwise inferred from the drafter's metadata. |
| `devices.backend` / `devices.ids` | Pins the backend (`CUDA`, `Vulkan`, `ROCm`, `CPU`) and optionally the devices a model runs on, by PCI ID, device index, `integrated` or `discrete`. A missing device refuses the load. See [device-selection.md](device-selection.md). |
| `kv.rolling_window` | opencoti's KV rolling window (`--kv-rolling-window`): `on` (the engine sizes it), `off`, or a size in MiB. It acts only when the cache overflows VRAM. `kv.residency_mode` `head` disables the window, so the pair is refused (v6). |
| `draft.auto_mtp_policy` | When a built-in MTP head drafts (`--auto-mtp-policy`): `measured` (the engine's default), `allocator`, `taper`, `always` or `off` (v6). |
| `fit.enabled` / `fit.vram_target_mib` | The engine's automatic fit (`--fit on\|off`, which stock llama.cpp also has) and opencoti's `--vram-target` cap on weights, KV and compute together (v6). |
| `draft` | `draft.head`: the drafter attached beside the weights, by sha256 digest, or `none` to detach it; `create` turns it into the model's one `DRAFT` layer and unset leaves the layers alone. `draft.tokens`: the draft length, 0 for off (v8). `draft.spec_type` pins the driver, `draft.auto_mtp_policy` is opencoti's policy for a built-in head. See [gemma4-drafter.md](gemma4-drafter.md). |
| `media` | opencoti's media engines attached to the model: `media.image` (generation and edit), `media.stt`, `media.tts`, `media.video` (reserved until the engine has video). Components are named by sha256 digest and stored as `application/vnd.xollama.media` layers named `media/<kind>.<role>`, which `create` writes from the config, so push, pull and blob GC carry them. Each kind's `defaults` are the template's engine settings: they boot the engine and fill every field a request leaves out; a client value wins unless the field is in `fixed`. Stock llama.cpp has no media engine, so `engine: llamacpp` with media is refused (v7). See [plans/media-integration.md](../../plans/media-integration.md). Since schema 9 `media.stt.vad` is an optional speech detector beside the transcriber (Silero in ggml form, `--stt-vad-model`, needs `audio_vad_v1`: opencoti c12); only a config that names one states version 9. |
| `council` | Makes the model a council: a planner, researchers and critics in parallel, and a synthesizer answer every chat turn (v4; a role's own `num_ctx`, v5). `council.enabled` is the switch; everything else has a measured default. Settings stated without the switch are refused. A council changes how a turn is answered, never how the model loads, so it is left out of the launch config (`LaunchConfig`). Like any two tags over one blob, a council tag and the model it is built `FROM` do not share a runner: switching between them reloads. See [plans/agentic-council-chat.md](../../plans/agentic-council-chat.md). |

### The version written is the lowest that is true

`Marshal` recomputes `version` from the fields the config actually uses, and
never from what the build knows. `SchemaVersion` is 8; `SchemaVersionBase` is 1;
only `kv.unified` and `kv.residency_mode` force the 2, and a `devices` pin forces
the 3 — an older build would read the pin as an unknown key and serve the model
on whatever hardware it chose, which is exactly what the pin exists to prevent.
A `council` forces the 4 for the same reason: an older build would serve the
council model as a plain chat, one model call where its publisher meant a council.
A role's own `num_ctx` (`council.<role>.num_ctx`) forces the 5: an older build
would drop it and run that role in its model template's window.
The engine policies (`kv.rolling_window`, `draft.auto_mtp_policy`, `fit`) force
the 6: an older build would drop them and run the engine's own policies instead.
`media` forces the 7: an older build would serve the model with no media engine,
and its image and speech routes would answer 404.
`draft.tokens` forces the 8: an older build would drop it and draft, at the
default length, a model whose publisher turned drafting off or set another
length. `draft.head` forces nothing: the drafter it names is an upstream `DRAFT`
layer, which every build loads.

Stamping the newest version unconditionally would have made every model this
build touched unreadable to an older xollama, including models using nothing
newer than v1 — because `Validate` treats a future version as an error, which is
the right call for the reason in the table above. So a config states the oldest
version that is true of it, and only a model actually using a v2 field pays the
v2 floor. It is recomputed rather than defaulted, so a config that was v2 and
has had its v2 fields cleared becomes readable by an older build again.

`TestTheVersionWrittenIsTheLowestThatIsTrue` and
`TestTheStoredVersionFollowsTheFieldsUsed` hold the two ends of that.

Unknown **keys** are accepted, so a model mentioning a setting a newer build
added is still servable. `draft_num_predict` is deliberately absent: it is
already an `api.Options` field and already travels in the params layer. Only
settings upstream has no home for belong here.

## Writing one

```dockerfile
FROM ./gemma-4-e4b.gguf
DRAFT ./gemma-4-E4B-it-assistant-Q8_0.gguf

XOLLAMA {"version": 1, "engine": "opencoti"}
```

The directive takes inline JSON or a path to a `.json` file beside the
Modelfile. It is validated while the Modelfile is parsed, not at create time, so
a typo is reported against the line that caused it. `ollama show --modelfile`
round-trips it.

A model creating `FROM` a parent that already carries a config **replaces** it
rather than inheriting — otherwise a child could never shed a stale engine pin.

`create.ApplyModelfileLayers` reads the request's `Xollama` **pointer**, not
`IsZero`, and the difference carries meaning. `nil` is "this request says
nothing about the fork config", and the parent's layer is inherited untouched —
that is every ordinary create. A non-nil config carrying no settings is "this
request says the fork config is nothing", and removes the layer. `tweak model
--clear` has no other way to say it, and neither does a Modelfile meaning to
strip a parent's engine pin rather than add to it.

### Or without a Modelfile

```sh
xollama tweak model qwen3.6:latest
xollama tweak model qwen3.6:latest --dca=on
xollama tweak model qwen3.6:latest --dca
```

`cmd/tweak` is additive, and everything it knows comes from one table
(`cmd/tweak/fields.go`): the wizard, the flags, the review, the consistency pass
and `--help` all derive from it, so a setting is added by adding a row and the
five cannot disagree about what exists. It writes through the ordinary create
path with `From` set to the model itself, so nothing but this layer changes.

It reads the current config from `/api/show` — which is why `api.ShowResponse`
gained an `Xollama` field — rather than from the manifest, so it works against a
remote server.

Two rules, kept apart deliberately:

- A setting the config **cannot act on** is dropped and named: an opencoti-only
  setting under `engine: "llamacpp"`, a `dca.chunk_size` under
  `dca.enabled: false`. There is nothing to decide.
- A combination where **only the operator knows which half they meant** is
  refused: `kv.unified: false` beside `slots.dynamic: true` is a choice between
  two features. Interactively the refusal re-asks exactly the settings it names
  (`fieldsNamedIn`, which matches a setting by reference rather than by word —
  "engine" appears in half these messages as prose). From a script it is an
  error and a non-zero exit.

The measured cache preconditions in `llm/engine_launch.go` (`ringShapeError`)
are applied here too, through `llm.CacheShapeError`, so a ring without a KVarN
base is refused at configuration time rather than at startup, where it reaches
the operator as a model that will not load. `llm.CacheNeedsFlashAttention` adds
the other one: a KVarN cache with `flash_attention: "off"` is refused, because
the engine refuses the pair at init.

`llm.KnownCacheTypes` is likewise a measurement, taken by asking the pinned
artifact's own parser (`--cache-type-k BOGUS` prints its allowed values). It has
**no kvarn7** — the run kvarn2, 3, 4, 5, 6, 8 invites the assumption and the
engine answers "Unsupported cache type". The vendor confirms that is structural
(`llama_kvarn_valid_bits()` admits those six bit widths and the type table is
built from them), not a parser omission, so the hole is not going to fill in.

[docs/xollama/tweak.mdx](../xollama/tweak.mdx) is the operator-facing page.

## What the fields do

**`engine: "llamacpp"`** skips the engine hook entirely, which is the same path
`XOLLAMA_ENGINE=llamacpp` takes, so the argv stays upstream's.

**`engine: "opencoti"`** fails the load if opencoti was not selected, rather than
running on llama.cpp anyway. The pin exists precisely because the model does not
work there, and the failure would otherwise surface as a load crash with no
mention of the engine. The worked example is a gemma-4 E2B/E4B assistant
drafter: it carries `masked_embd_*` tensors that upstream's loader rejects with a
`vector::_M_range_check` — see [gemma4-drafter.md](gemma4-drafter.md).

**`draft.spec_type`** beats inference, and still goes through
`retargetSpecType`, so pinning `draft-assistant` on llama.cpp resolves to
`draft-mtp` — that engine's spelling for the same driver — rather than a value it
would reject.

It is consulted wherever the drafter came from. `resolveDraftType` takes the
inferred type and the pin, and the guard is the inferred type, not whether a
drafter file was attached: a head that ships *inside* the target — Qwen's
`nextn_predict_layers`, or qwen35's `mtp.*` tensors — is just as much a drafter
to pin. Reading the pin only on the attached-file path was a silent no-op
(measured 2026-09-23 on `omnimerge-v4-mtp_tb:27b-q4km-128k`: the layer said
`draft-simple`, `xollama show` printed `draft-simple`, and the engine was handed
`--spec-type draft-mtp`). A model with no drafter at all still states nothing,
because a `--spec-type` with no drafter behind it is a broken command line, not
a preference.

Attaching a drafter is a `DRAFT` line in the Modelfile and is not part of this
layer — the layer says which *driver* to use, never which file. The two together
on the worked gemma-4 vehicle:

```
FROM  gemma-4-A4B-98e-v9-agentic-it-Q4_K_M.gguf
DRAFT gemma-4-26B-A4B-it-assistant-Q8_0.gguf
PARAMETER draft_num_predict 3
```

The drafter declares `requires_target_arch = gemma4`, so `externalDraftType`
resolves `draft-assistant` with no pin at all, and the launch carries
`--spec-type draft-assistant --spec-draft-n-max 3 --spec-draft-model <blob>`.
Pinning `draft-mtp` over that is accepted and reaches the engine, which then
refuses the load with `Gemma4Assistant requires ctx_other to be set` — the pin
is an override, so it is able to be wrong.

**`kv.unified`** (v2) says whether the cells are one pool shared across
sequences or a fixed per-slot split. Until v2 this was *derived*: the server
passed `--kv-unified` exactly when it had parked slots or a shared prefix pool
to admit into, and a model could not say otherwise. The derivation answers a
different question from the one an operator sometimes has — a shared pool lets
ONE long conversation use every cell, a fixed split guarantees each slot its
share, and the total cell count is the same either way. `nil` keeps the
derivation. Stating `false` while dynamic slots or session pooling are on is
refused: both are shares of the same cells.

**`kv.residency_mode`** (v2) is the rolling-KV tactic for a cache that does not
fit in VRAM: `auto`, `head` or `window`. The set is the engine's own, read from
its argument parser (`--kv-residency-mode must be auto|head|window`) rather than
from documentation. It is an opencoti extension, so a config that pins
`llamacpp` and also names a mode is refused rather than served without it.

## Off means off

A model with no `xollama.json` produces no layer, leaves `Model.Xollama` nil, and
takes every upstream path unchanged. The accessors on `LlamaServerConfig` are
nil-tolerant because almost every model will have no config at all.

## `REQUIRES` can name an xOllama release (`requires` hook)

`REQUIRES` is upstream's field (`ConfigV2.Requires`), checked at pull by
`checkPullRequires`, which drops the running version's suffix first. The fork's
whole version is that suffix, so a requirement could not tell `-xollama.2` from
`-xollama.3`. `server/xollama_requires.go`: a requirement whose prerelease
names `xollama` is compared against the whole running version with plain
semver, at pull and at load (`loadRequires`, chat and media). Upstream-form
requirements are untouched. A catalog entry's `Requires`
(`internal/mediahub/catalog.go`) is stamped by `xollama media create`; the
Whistle entries state `requiresC12`.
