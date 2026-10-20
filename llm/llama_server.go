// llama_server.go wraps the llama-server binary as a subprocess
//
// Ollama uses two chat paths with llama-server. Models with explicit Ollama
// renderers/parsers, Harmony handling, MLX, or an enabled Go TEMPLATE layer
// still render prompts in Go and call /completion. Other GGUF chat models use
// llama-server's chat_template handling through /v1/chat/completions.
//
// For structured output, a JSON schema is passed to llama-server via its
// json_schema field and the "json" format as a builtin grammar via the grammar
// field. A format that applies after a response's thinking is sent as a
// grammar built around the GBNF llama-server itself derives from the schema.
//
// llama-server auto-detects GPU layers (-ngl), thread count (-t), and flash
// attention (--flash-attn).
package llm

import (
	"bufio"
	"bytes"
	"container/list"
	"context"
	crand "crypto/rand"
	"encoding/base64"
	"encoding/json"
	"errors"
	"fmt"
	"image/png"
	"io"
	"log/slog"
	"math/rand"
	"net"
	"net/http"
	"os"
	"os/exec"
	"path/filepath"
	"regexp"
	"runtime"
	"slices"
	"strconv"
	"strings"
	"sync"
	"sync/atomic"
	"time"

	"golang.org/x/image/webp"
	"golang.org/x/sync/semaphore"

	"github.com/ollama/ollama/api"
	"github.com/ollama/ollama/envconfig"
	"github.com/ollama/ollama/fs/gguf"
	"github.com/ollama/ollama/llm/engine"
	"github.com/ollama/ollama/ml"
	"github.com/ollama/ollama/types/xollama"
)

var grammarJSON = `
root   ::= object
value  ::= object | array | string | number | ("true" | "false" | "null") ws
object ::=
  "{" ws (
         string ":" ws value
    ("," ws string ":" ws value)*
  )? ws "}"
array  ::=
  "[" ws (
            value
    ("," ws value)*
  )? ws "]"
string ::=
  "\"" (
    [^"\\\x7F\x00-\x1F] |
    "\\" (["\\/bfnrt] | "u" [0-9a-fA-F] [0-9a-fA-F] [0-9a-fA-F] [0-9a-fA-F]) # escapes
  )* "\""
number ::= ("-"? ([0-9] | [1-9] [0-9]*)) ("." [0-9]+)? ([eE] [-+]? [0-9]+)?
# Optional space: by convention, applied in this grammar after literal chars when allowed
ws ::= ([ \t\n] ws)?
`

// DefaultEmbeddingNumBatch is the default NumBatch used for embedding models
// when neither the model nor the request specifies num_batch.
const (
	DefaultEmbeddingNumBatch             = 2048
	openEndedGenerationContextMultiplier = 10
)

const (
	llamaArgFitTargetEnv = "LLAMA_ARG_FIT_TARGET"
	bytesPerMiB          = 1 << 20

	// mmprojOffloadHeadroom leaves 1 GiB for backend buffers beyond projector weights.
	mmprojOffloadHeadroom = 1 << 30
)

// LlamaServerBatch resolves the batch size and extra memory allowance used
// when deciding whether to load a model alongside other models.
func LlamaServerBatch(f *gguf.Model, opts api.Options, completion bool) (int, uint64) {
	batch := opts.NumBatch
	// These decision heads read the whole prompt without a KV cache, so the
	// physical batch must hold the entire effective context.
	wholePrompt := f.KV().Uint("decision.block_count") > 0
	if wholePrompt {
		batch = opts.NumCtx
		if trainCtx := int(f.KV().ContextLength()); trainCtx > 0 {
			batch = min(batch, trainCtx)
		}
	}
	if !completion && !wholePrompt {
		return batch, 0
	}
	return batch, LlamaServerBatchMemory(batch)
}

// LlamaServerBatchMemory is the conservative extra memory allowance for a
// generation or whole-prompt decision batch above the default batch size.
func LlamaServerBatchMemory(batch int) uint64 {
	switch {
	case batch >= 2048:
		return 2 << 30
	case batch >= 1024:
		return 768 << 20
	default:
		return 0
	}
}

func boundedNumPredict(numPredict, numCtx int) int {
	if numCtx <= 0 {
		return numPredict
	}
	// Ollama's default num_predict=-1 means "generate until a stop condition".
	// llama-server still needs a finite request budget, so keep open-ended
	// generations bounded while allowing several full context windows.
	limit := openEndedGenerationContextMultiplier * numCtx
	if numPredict < 0 || numPredict > limit {
		return limit
	}
	return numPredict
}

// llamaServerRunner wraps an upstream llama-server process and implements the LlamaServer interface.
// It communicates with llama-server over HTTP.
type llamaServerRunner struct {
	// xollama-hook: council -- the engine's feature set, read once per process.
	polykvState
	// xollama-hook: engine-select -- set by stopProcess, so a stop xollama
	// asked for is not reported as the engine crashing.
	stopping atomic.Bool

	port               int
	cmd                *exec.Cmd
	done               chan struct{}
	doneErr            error
	client             *http.Client
	memoryMu           sync.RWMutex
	memTotal           uint64 // actual total buffer size parsed from llama-server logs (bytes)
	memGPU             uint64 // actual GPU buffer size parsed from llama-server logs (bytes)
	memModelFileBacked uint64 // model weight bytes whose buffers mirror the on-disk file (mmap views + direct device copies); excludes repacked copies like CPU_REPACK
	memCPUMappedModel  uint64 // model weight bytes in mmap-backed CPU buffers (e.g. CPU_Mapped), parsed from llama-server logs
	gpuLayers          uint64 // model layers loaded on GPU, parsed from llama-server logs
	gpuLayerOverflow   int    // number of GPU-selected layers partially overflowed to CPU
	status             *StatusWriter
	options            api.Options
	modelPath          string
	// mediaMarker must match the LLAMA_MEDIA_MARKER value passed to llama-server.
	// llama.cpp randomizes this by default; Ollama renders stable [img-N] markers
	// and rewrites them before forwarding the request.
	mediaMarker string

	// Per-device VRAM tracking, populated from llama-server log parsing.
	// Keys are device names from llama-server output (e.g., "CUDA0", "ROCm0", "MTL0").
	vramByDevice map[string]uint64

	// System-reported free VRAM per device at model load time, parsed from
	// "using device CUDA0 ... - 15221 MiB free" log lines. This reflects
	// real system state including external VRAM consumers (on platforms where
	// the GPU driver reports accurately). Keys match vramByDevice (e.g., "CUDA0").
	systemFreeAtLoad map[string]uint64

	// gpus is the list of GPU devices assigned to this runner at creation time,
	// used to map DeviceIDs to device names for VRAMByGPU lookups.
	gpus []ml.DeviceInfo

	metadata      *gguf.Model
	totalLayers   uint64 // maximum offloadable model layers
	loadStart     time.Time
	loadActivity  atomic.Int64
	loadTracking  atomic.Bool
	rawEmbeddings bool
	splitDirs     []string

	sem *semaphore.Weighted

	launch                  llamaServerLaunchConfig
	output                  *memoryParsingWriter
	mmprojOffloadOOMRetried bool
	// usedOpencoti records which engine served the current process, and
	// engineFallbackRetried keeps the stock retry to one attempt.
	usedOpencoti          bool
	engineFallbackRetried bool
	// pools remembers which shared prefix pool holds which prefix, for the life
	// of this process. See engine_pool.go.
	//
	// xollama-hook: engine-session
	pools *poolRegistry
}

type llamaServerLaunchConfig struct {
	modelPath string
	modelArch string
	// trainContext is the context the model was trained in, as its GGUF
	// declares it. It is carried because DCA has to know whether this load is
	// being asked for more than that. Zero means the file did not say.
	//
	// xollama-hook: launch-config
	trainContext int
	// recurrentState is set when the model keeps state that cannot be cut at an
	// arbitrary prefix, so no pool can ever help it. It is carried rather than
	// recomputed because it is read from the GGUF, which this struct is built
	// from and the launch path no longer has. See engine_pool_arch.go.
	//
	// xollama-hook: engine-session
	recurrentState       bool
	draftType            string
	projectors           []string
	mmprojMemory         uint64
	modelLayers          uint64
	adapters             []string
	opts                 api.Options
	numParallel          int
	kvCacheType          string
	embedding            bool
	decision             bool
	config               LlamaServerConfig
	gpus                 []ml.DeviceInfo
	gpuLibs              []string
	extraEnvs            map[string]string
	forceNoMMProjOffload bool
	// forceStockEngine skips the engine hook entirely. Set only by the
	// opt-in retry after an opencoti load failed; see XOLLAMA_ENGINE_FALLBACK.
	forceStockEngine bool
	// stockKV resolves the cache types for stock llama.cpp: set by the
	// relaunch when a server-wide XOLLAMA_K/V_CACHE_TYPE stock does not
	// accept met a load stock serves (resolveKVCacheTypesOn).
	stockKV bool
	// xollama-hook: kv-fa-retry — forceF16V relaunches with the V half at f16
	// after the engine refused a quantized V without flash attention.
	forceF16V bool
}

func newLlamaServerHTTPClient() *http.Client {
	return &http.Client{
		Transport: &http.Transport{
			DisableKeepAlives: true,
			Proxy:             nil,
		},
	}
}

var defaultLlamaServerHTTPClient = newLlamaServerHTTPClient()

func (s *llamaServerRunner) httpClient() *http.Client {
	if s.client != nil {
		return s.client
	}
	return defaultLlamaServerHTTPClient
}

func (s *llamaServerRunner) ModelPath() string {
	return s.modelPath
}

func (s *llamaServerRunner) Pid() int {
	if s.cmd != nil && s.cmd.Process != nil {
		return s.cmd.Process.Pid
	}
	return 0
}

func (s *llamaServerRunner) GetPort() int {
	return s.port
}

func (s *llamaServerRunner) HasExited() bool {
	return s.cmd != nil && s.cmd.ProcessState != nil && s.cmd.ProcessState.ExitCode() >= 0
}

func (s *llamaServerRunner) llamaServerMediaMarker() string {
	if s.mediaMarker != "" {
		return s.mediaMarker
	}
	return "<__media__>"
}

func newLlamaServerMediaMarker() string {
	var b [16]byte
	if _, err := crand.Read(b[:]); err == nil {
		return fmt.Sprintf("<__ollama_media_%x__>", b)
	}

	return fmt.Sprintf("<__ollama_media_%d_%d__>", time.Now().UnixNano(), rand.Int63())
}

func (s *llamaServerRunner) completionPrompt(prompt, leadingBOS string) string {
	if s.tokenizerAddsBOS() {
		if leadingBOS != "" && strings.HasPrefix(prompt, leadingBOS) {
			return strings.TrimPrefix(prompt, leadingBOS)
		}

		if strings.HasPrefix(prompt, "<bos>") {
			return strings.TrimPrefix(prompt, "<bos>")
		}
	}

	return prompt
}

func (s *llamaServerRunner) tokenizerAddsBOS() bool {
	if s.metadata == nil {
		return false
	}

	kv := s.metadata.KV()

	if kv.String("tokenizer.ggml.pre") == "lfm2" {
		return true
	}

	// llama.cpp forces add_bos on for Gemma4 at load time, even for GGUFs
	// whose tokenizer.ggml.add_bos_token metadata is explicitly false. Some
	// GGUFs omit tokenizer.ggml.pre and are still treated as Gemma4 from
	// tokenizer.ggml.model.
	if kv.String("tokenizer.ggml.pre") == "gemma4" || kv.String("tokenizer.ggml.model") == "gemma4" {
		return true
	}

	return kv.Bool("tokenizer.ggml.add_bos_token")
}

func (s *llamaServerRunner) completionPromptForRequest(ctx context.Context, req CompletionRequest) (any, error) {
	prompt := s.completionPrompt(req.Prompt, req.LeadingBOS)
	if !req.Truncate || len(req.Media) > 0 || s.options.NumCtx <= 1 || len(prompt) < s.options.NumCtx {
		return prompt, nil
	}

	tokens, err := s.tokenize(ctx, prompt, true)
	if err != nil {
		return nil, err
	}

	fullPromptLimit := s.options.NumCtx - 1
	if len(tokens) <= fullPromptLimit {
		return prompt, nil
	}

	if !s.launch.config.ContextShift {
		return nil, api.StatusError{StatusCode: http.StatusBadRequest, ErrorMessage: promptTooLongMessage}
	}

	nKeep := req.Options.NumKeep
	if nKeep < 0 {
		nKeep = len(tokens)
	}
	if s.tokenizerAddsBOS() {
		nKeep++
	}
	nKeep = min(nKeep, fullPromptLimit)

	limit := contextShiftPromptLimit(s.options.NumCtx, nKeep)
	discard := len(tokens) - limit
	truncated := make([]int, 0, limit)
	truncated = append(truncated, tokens[:nKeep]...)
	truncated = append(truncated, tokens[nKeep+discard:]...)

	slog.Warn("truncating input prompt", "limit", limit, "prompt", len(tokens), "keep", nKeep, "new", len(truncated))
	return truncated, nil
}

func contextShiftPromptLimit(numCtx, numKeep int) int {
	if numCtx <= 1 {
		return 0
	}

	numKeep = max(0, min(numKeep, numCtx-1))

	// Match the old runners' first context shift: preserve num_keep, then free
	// roughly half of the remaining context before generation needs the slot.
	return numCtx - max((numCtx-numKeep)/2, 1)
}

func (s *llamaServerRunner) ContextLength() int {
	return s.options.NumCtx
}

// FindLlamaServer locates the llama-server binary in lib/ollama/.
// There is a single binary that dynamically loads GPU backends at runtime.
func FindLlamaServer() (string, error) {
	path, candidates, err := findLlamaCppBinary("llama-server", defaultLlamaCppBinarySearch())
	if err != nil {
		return "", fmt.Errorf("llama-server binary not found (checked: %s). Run 'cmake -S llama/server --preset cpu && cmake --build --preset cpu' first", strings.Join(candidates, ", "))
	}
	return path, nil
}

// engineBackends is the distinct backend of every device this load will use,
// in the order ollama selected them, for the engine routing policy. An empty
// result means a CPU-only load.
func engineDevices(gpus []ml.DeviceInfo) []engine.Device {
	devices := make([]engine.Device, 0, len(gpus))
	for _, g := range gpus {
		// Compute capability rides along because routing needs it: it is the
		// axis that separates a V100 from a 4090 inside one "CUDA" backend.
		d := engine.Device{
			Backend:      engine.Backend(g.Library),
			ComputeMajor: g.ComputeMajor,
			ComputeMinor: g.ComputeMinor,
		}
		if !slices.Contains(devices, d) {
			devices = append(devices, d)
		}
	}
	return devices
}

// startLlamaServer spawns the upstream llama-server process with appropriate CLI flags.
func startLlamaServer(launch llamaServerLaunchConfig, out io.Writer) (cmd *exec.Cmd, port int, usedOpencoti bool, err error) {
	exe, err := FindLlamaServer()
	if err != nil {
		// xollama-hook: stockless — macOS ships no stock llama-server; opencoti
		// serves every load there (llm/engine/stockless.go).
		if engine.StockShipped(runtime.GOOS) {
			return nil, 0, false, err
		}
		exe = ""
	}

	// Allocate a port
	port = 0
	if a, err := net.ResolveTCPAddr("tcp", "localhost:0"); err == nil {
		var l *net.TCPListener
		if l, err = net.ListenTCP("tcp", a); err == nil {
			port = l.Addr().(*net.TCPAddr).Port
			l.Close()
		}
	}
	if port == 0 {
		slog.Debug("ResolveTCPAddr failed, using random port")
		port = rand.Intn(65535-49152) + 49152
	}

	// Build CLI flags — minimal set, let llama-server auto-detect the rest
	params := []string{
		"--model", launch.modelPath,
		"--port", strconv.Itoa(port),
		"--host", "127.0.0.1",
		"--no-webui",
		"--offline",
		"-c", strconv.Itoa(launch.opts.NumCtx * launch.numParallel),
	}
	// The questions of a decision request share their prompt only while they
	// run in parallel slots. Their prompts rarely repeat across requests, and
	// at trace verbosity llama-server logs its whole prompt cache after each one.
	if launch.decision {
		params = append(params, "-np", "16", "--kv-unified", "--cache-ram", "0")
	} else {
		params = append(params, "-np", strconv.Itoa(launch.numParallel))
	}
	params = appendLlamaServerLogArgs(params)
	params = appendJinjaArgs(params, launch.config)

	params = appendMMProjArgs(params, launch)
	params = appendDraftArgs(params, launch.draftType, launch.config.DraftModelPath, launch.opts)

	params = append(params, qwenVLServerArgs(launch.modelArch)...)

	for _, adapter := range launch.adapters {
		slog.Warn("LoRA adapters are deprecated and will be removed in a future release", "adapter", adapter)
		params = append(params, "--lora", adapter)
	}

	params = appendLoadModeArgs(params, launch.opts, launch.gpus)

	// KV cache type
	//
	// xollama-hook: launch-config — upstream writes one type into both halves.
	// The resolver keeps OLLAMA_KV_CACHE_TYPE as the default and lets the
	// XOLLAMA_* variables and the model's own config override either half.
	// See docs/xollama/kv-cache.mdx.
	kvTypes := launch.withF16V(resolveKVCacheTypesOn(launch.config, launch.kvCacheType, launch.stockKV)) // xollama-hook: kv-fa-retry
	params = appendKVCacheArgs(params, kvTypes)

	params = appendFlashAttentionArgs(params, launch.config, launch.gpus)

	params = appendBatchArgs(params, launch.opts, launch.embedding, launch.numParallel)

	// GPU layer offloading — only pass if user explicitly set it (non-default).
	// Default behavior: let llama-server auto-detect via -ngl auto.
	if launch.opts.NumGPU > 0 {
		params = append(params, "-ngl", strconv.Itoa(launch.opts.NumGPU))
	} else if launch.opts.NumGPU == 0 {
		// Explicit 0 means CPU only
		params = append(params, "-ngl", "0")
	}
	// NumGPU == -1 (default): don't pass -ngl, let llama-server auto-detect

	// Thread count — only pass if user explicitly set it.
	// Default behavior: let llama-server auto-detect.
	if launch.opts.NumThread > 0 {
		params = append(params, "-t", strconv.Itoa(launch.opts.NumThread))
	}

	params = appendMainGPUArgs(params, launch.opts)

	params = appendContextShiftArgs(params, launch.opts, launch.config.ContextShift)

	// xollama-hook: engine-select — see docs/features/engine-opencoti-llamafile.md
	// Resolves which engine serves this load. Returns (exe, params) unchanged
	// whenever the answer is llama.cpp, which is what keeps the off path
	// byte-identical to upstream. forceStockEngine is set only by the opt-in
	// retry after an opencoti load has already failed.
	// xollama-hook: model-config — a model may pin the engine it needs.
	// llamacpp pins skip the hook entirely, which is the same path
	// XOLLAMA_ENGINE=llamacpp takes, so the argv stays upstream's.
	enginePin := launch.config.enginePin()

	name, args, usedOpencoti := exe, params, false
	if !launch.forceStockEngine && enginePin != xollama.EngineLlamaCpp {
		name, args, usedOpencoti = engine.Launch(exe, params, engineDevices(launch.gpus), ml.LibOllamaPath)
	}

	// A model pinned to opencoti that did not get it must not quietly run on
	// llama.cpp: the pin exists precisely because the model does not work
	// there, and a silent downgrade would surface as a load crash with no
	// mention of the engine.
	// xollama-hook: stockless — no stock engine to run what opencoti did not take.
	if !usedOpencoti && !engine.StockShipped(runtime.GOOS) {
		return nil, 0, false, errors.New(engine.StocklessRefusal(runtime.GOOS))
	}
	if enginePin == xollama.EngineOpencoti && !usedOpencoti {
		return nil, 0, false, fmt.Errorf("model requires the opencoti engine (xollama.json pins engine=%q) but it was not selected; check %s and that an artifact is installed",
			enginePin, engine.EnvSelector)
	}

	// xollama-hook: launch-config — the scheduler lifts the ollama/ollama#4165
	// single-sequence rule when it predicts opencoti (WouldUseOpencoti). A
	// prediction is not the launch: with the artifact missing, or on the
	// opt-in retry after an opencoti failure, stock llama.cpp serves the load
	// and gets upstream's one sequence back. Fewer sequences than planned only
	// ever uses less memory than was reserved.
	if n := servedSequences(launch.config, launch.numParallel, usedOpencoti); n != launch.numParallel {
		slog.Warn("model architecture does not currently support parallel requests on stock llama-server; serving one sequence",
			"requested", launch.numParallel)
		launch.numParallel = n
		return startLlamaServer(launch, out)
	}

	// xollama-hook: launch-config — a cache type stock llama.cpp does not know,
	// or a sliding-window ring it has no flag for, must be refused here rather
	// than handed to an engine that will reject the argument itself. The
	// message names the setting, because "unknown argument" from a subprocess
	// does not tell anyone which of four places set it.
	if why := kvTypes.requiresEngineExtension(); why != "" && !usedOpencoti {
		// A server-wide opencoti type falls back to the legacy one here; only
		// what the model itself asks for is refused.
		if !launch.stockKV && resolveKVCacheTypesOn(launch.config, launch.kvCacheType, true).requiresEngineExtension() == "" {
			slog.Warn("stock llama-server serves this load; using the legacy KV cache type instead of XOLLAMA_K/V_CACHE_TYPE", "reason", why, "legacy", launch.kvCacheType)
			launch.stockKV = true
			return startLlamaServer(launch, out)
		}
		return nil, 0, false, fmt.Errorf("this KV cache configuration needs the opencoti engine: %s; set %s=opencoti, or choose a type stock llama.cpp accepts (%s)",
			why, engine.EnvSelector, strings.Join(stockCacheTypes, ", "))
	}
	// The ring exists in opencoti's development tree but not in the cut this
	// build ships, and that engine rejects the whole command line rather than
	// ignoring a flag it does not know. Refuse where the setting was made.
	if kvTypes.KSWA != "" || kvTypes.VSWA != "" {
		if why := engine.SlidingWindowRingUnavailable(); why != "" {
			return nil, 0, false, fmt.Errorf("kv.k_swa / kv.v_swa cannot be used: %s", why)
		}
		// Available is not the same as askable in this shape. An engine that
		// has the ring still refuses combinations of it, during startup, which
		// reaches the operator as a load that failed.
		if why := kvTypes.ringShapeError(); why != "" {
			return nil, 0, false, fmt.Errorf("this sliding-window ring configuration would be refused by the engine: %s", why)
		}
	}
	args = appendKVCacheRingArgs(args, kvTypes, usedOpencoti)
	args = appendKVResidencyArgs(args, kvTypes, usedOpencoti)
	// xollama-hook: system-settings — fit, rolling window, MTP policy.
	args = appendEnginePolicyArgs(args, launch.config.Xollama, usedOpencoti)

	// xollama-hook: launch-config — dynamic slots. See docs/xollama/slots.mdx.
	// xollama-hook: council -- a council starts with a slot per parallel member.
	live := councilLive(launch.config, launch.numParallel, usedOpencoti)
	args = councilSlotArgs(args, live, launch.numParallel)
	slots := resolveSlotPlan(launch.config, live, launch.config.singleSequence(usedOpencoti))
	// xollama-hook: council -- the council's pool seats ride on the same flag.
	args = appendSlotArgs(args, slots, enginePoolSeats(launch.config, len(launch.projectors) > 0), kvTypes.Unified, usedOpencoti)
	args = appendSWABudgetArgs(args, slots, usedOpencoti)

	// xollama-hook: launch-config — dual chunk attention. See docs/xollama/dca.mdx.
	//
	// Both checks refuse rather than start: a load configured to run past its
	// trained context, started without the thing that makes that safe, would
	// answer confidently and wrongly, and nothing downstream could tell.
	dca := resolveDCAPlan(launch.config)
	if why := dca.requiresEngineExtension(); why != "" && !usedOpencoti {
		return nil, 0, false, fmt.Errorf("%s; set %s=opencoti, or turn DCA off", why, engine.EnvSelector)
	}
	if dca.Enabled {
		warn, refuse := checkDCAArchitecture(launch.modelArch, launch.opts.NumCtx, launch.trainContext)
		if refuse != nil {
			return nil, 0, false, refuse
		}
		if warn != "" {
			slog.Warn(warn, "architecture", launch.modelArch, "supported", dcaArchitectures)
		}
	}
	args, err = appendDCAArgs(args, dca, launch.modelArch, launch.opts.NumCtx, launch.trainContext, launch.opts.NumBatch, usedOpencoti)
	if err != nil {
		return nil, 0, false, err
	}

	// xollama-hook: draft-assistant — see docs/features/gemma4-drafter.md
	if launch.draftType != "" {
		args = retargetSpecType(args, launch.draftType, usedOpencoti)
	}
	// xollama-hook: drafter — see docs/features/gemma4-drafter.md
	args = appendDraftOffArgs(args, launch.draftType, launch.config.DraftOff && launch.opts.DraftNumPredict <= 0, usedOpencoti)
	// xollama-hook: notices -- the model's notice templates (llm/engine_notice.go).
	args = appendNoticeTemplatesArgs(args, launch.config.NoticeTemplatesPath, usedOpencoti)

	// xollama-hook: engine-args — the operator's append-only escape hatch, for
	// engine flags with no LLAMA_ARG_* twin. LAST on purpose: llama-server
	// takes the final occurrence of a repeated flag, so appending here puts the
	// operator ahead of everything above without this code having to reorder or
	// remove anything. Operator-side only, never model-carried — see
	// llm/engine_args.go for why that boundary is where it is.
	args, err = appendEngineArgs(args, envconfig.EngineArgs())
	if err != nil {
		return nil, 0, false, err
	}

	// xollama-hook: engine-payload — a self-extracting engine unpacks its GPU
	// payload into $HOME/.llamafile/v/<compile-time version>/, which two builds
	// carrying one tag share. Give it a HOME of our own holding exactly the
	// payload of the artifact about to run, so the operator's own opencoti
	// builds and ours cannot reach each other. See llm/engine/payload.go.
	// Nothing happens on the stock path: a llama-server binary extracts
	// nothing and is launched with the environment it inherited.
	envs := launch.extraEnvsForStart()
	if usedOpencoti {
		envs = launch.opencotiEnvsForStart() // xollama-hook: engine-fit -- no vision pad on the fit target; see llm/engine_fit_target.go
		userHome, _ := os.UserHomeDir()
		if payloadHome := engine.PayloadHome(engine.ArtifactOf(name, args), ml.LibOllamaPath, userHome); payloadHome != "" {
			envs = cloneStringMap(envs)
			envs["HOME"] = payloadHome
		}
	}

	// Set up library paths for GPU backend discovery
	cmd = exec.Command(name, args...)

	if out != nil {
		// os/exec serializes Write calls when stdout and stderr share a writer.
		cmd.Stdout = out
		cmd.Stderr = out
	}
	cmd.SysProcAttr = LlamaServerSysProcAttr
	libExe := exe
	if libExe == "" { // xollama-hook: stockless — the engine's directory holds its libraries
		libExe = name
	}
	SetupLlamaServerCommandEnv(cmd, libExe, launch.gpuLibs, envs)

	slog.Info("starting llama-server", "cmd", cmd)
	slog.Debug("subprocess", "", filteredEnv(cmd.Env))

	if err = cmd.Start(); err != nil {
		return nil, 0, false, err
	}

	if err = AddRunnerToJob(cmd.Process.Pid); err != nil {
		_ = cmd.Process.Kill()
		_ = cmd.Wait()
		return nil, 0, false, fmt.Errorf("assign llama-server to runner job: %w", err)
	}
	return cmd, port, usedOpencoti, nil
}

// SetupLlamaServerCommandEnv configures the environment for a llama-server
// subprocess so discovery and real model runners use the same library search
// paths and GPU backend selection.
func SetupLlamaServerCommandEnv(cmd *exec.Cmd, exe string, gpuLibs []string, extraEnvs map[string]string) {
	cmd.Env = envconfig.Environ() // xollama-hook: system-settings — the tweak file's envs reach the engine

	envUpdates := make(map[string]string, len(extraEnvs)+2)
	for k, v := range extraEnvs {
		envUpdates[k] = v
	}

	libraryPaths := llamaServerLibraryPaths(exe, gpuLibs, envUpdates)
	pathEnv := llamaServerLibraryPathEnv()
	envUpdates[pathEnv] = strings.Join(libraryPaths, string(filepath.ListSeparator))

	applied := make(map[string]bool, len(envUpdates))
	for i := range cmd.Env {
		key, _, ok := strings.Cut(cmd.Env[i], "=")
		if !ok {
			continue
		}
		for updateKey, updateVal := range envUpdates {
			if strings.EqualFold(key, updateKey) {
				cmd.Env[i] = updateKey + "=" + updateVal
				applied[updateKey] = true
			}
		}
	}
	for key, val := range envUpdates {
		if !applied[key] {
			cmd.Env = append(cmd.Env, key+"="+val)
		}
	}
}

func llamaServerLibraryPathEnv() string {
	switch runtime.GOOS {
	case "windows":
		return "PATH"
	case "darwin":
		return "DYLD_LIBRARY_PATH"
	default:
		return "LD_LIBRARY_PATH"
	}
}

func llamaServerLibraryPaths(exe string, gpuLibs []string, envUpdates map[string]string) []string {
	llamaDir := filepath.Dir(exe)
	seen := map[string]bool{}
	var libraryPaths []string
	addPath := func(path string) {
		if path == "" || seen[path] {
			return
		}
		seen[path] = true
		libraryPaths = append(libraryPaths, path)
	}

	// Library path ordering:
	// 1. llama-server's own directory — ggml-base, ggml-cpu, libllama
	// 2. GPU variant directories — cublas, cudart, backend DLL/.so
	// 3. User/system library path
	addPath(llamaDir)
	for _, dir := range gpuLibs {
		if dir == ml.LibOllamaPath || dir == llamaDir {
			continue
		}
		if envUpdates["GGML_BACKEND_PATH"] == "" {
			if backend := findLlamaServerGPUBackend(dir); backend != "" {
				envUpdates["GGML_BACKEND_PATH"] = backend
			}
		}
		addPath(dir)
	}
	if libraryPath, ok := os.LookupEnv(llamaServerLibraryPathEnv()); ok {
		for _, dir := range filepath.SplitList(libraryPath) {
			addPath(dir)
		}
	}
	return adjustPlatformLibraryPaths(libraryPaths, gpuLibs)
}

func findLlamaServerGPUBackend(dir string) string {
	patterns := []string{
		"libggml-*.so*",
		"libggml-*.dylib",
		"libggml-*.dll",
		"ggml-*.dll",
	}
	var candidates []string
	for _, pattern := range patterns {
		matches, _ := filepath.Glob(filepath.Join(dir, pattern))
		candidates = append(candidates, matches...)
	}
	slices.Sort(candidates)

	for _, match := range candidates {
		if isLlamaServerGPUBackend(match) {
			return match
		}
	}
	return ""
}

func isLlamaServerGPUBackend(path string) bool {
	name := strings.ToLower(filepath.Base(path))
	for _, prefix := range []string{
		"libggml-base",
		"ggml-base",
		"libggml-cpu",
		"ggml-cpu",
	} {
		if strings.HasPrefix(name, prefix) {
			return false
		}
	}
	return true
}

func embeddingBatchSize(opts api.Options, numParallel int) int {
	batchSize := opts.NumBatch
	if batchSize <= 0 {
		return 0
	}
	if opts.NumCtx > 0 {
		batchSize = min(batchSize, opts.NumCtx*max(numParallel, 1))
	}
	return batchSize
}

func appendLlamaServerLogArgs(params []string) []string {
	// Keep startup memory/offload lines visible for scheduler accounting.
	return append(params,
		"--log-verbosity", "4",
		"--no-log-prefix",
		"--no-log-timestamps",
	)
}

func appendBatchArgs(params []string, opts api.Options, embedding bool, numParallel int) []string {
	if embedding {
		params = append(params, "--embedding")
		if batchSize := embeddingBatchSize(opts, numParallel); batchSize > 0 {
			params = append(params, "-b", strconv.Itoa(batchSize), "-ub", strconv.Itoa(batchSize))
		}
		return params
	}

	if opts.NumBatch > 0 {
		params = append(params, "-b", strconv.Itoa(opts.NumBatch), "-ub", strconv.Itoa(opts.NumBatch))
	}
	return params
}

// LlamaServerFlashAttention resolves the flash-attention mode passed to
// llama-server.
//
// xollama-hook: launch-config — cfg carries the model's own answer, which beats
// the server's OLLAMA_FLASH_ATTENTION. Whether flash attention helps or breaks
// a model is a property of the model and its cache, not of the machine, and
// upstream has only the server-wide switch. A model that says nothing takes
// exactly upstream's path below.
func LlamaServerFlashAttention(cfg LlamaServerConfig, gpus []ml.DeviceInfo) ml.FlashAttentionType {
	switch cfg.flashAttention() {
	case "on":
		return ml.FlashAttentionEnabled
	case "off":
		return ml.FlashAttentionDisabled
	case "auto":
		// An explicit "auto" still defers to what the devices can do, exactly
		// as an unset server does; it means "decide for me", not "force on".
		if !ml.FlashAttentionSupported(gpus) {
			return ml.FlashAttentionDisabled
		}
		return ml.FlashAttentionAuto
	}

	enabled := envconfig.FlashAttention(false)
	userSet := enabled == envconfig.FlashAttention(true)
	if userSet {
		if enabled {
			return ml.FlashAttentionEnabled
		}
		return ml.FlashAttentionDisabled
	}

	if !ml.FlashAttentionSupported(gpus) {
		return ml.FlashAttentionDisabled
	}
	return ml.FlashAttentionAuto
}

func appendFlashAttentionArgs(params []string, cfg LlamaServerConfig, gpus []ml.DeviceInfo) []string {
	switch LlamaServerFlashAttention(cfg, gpus) {
	case ml.FlashAttentionEnabled:
		return append(params, "--flash-attn", "on")
	case ml.FlashAttentionDisabled:
		return append(params, "--flash-attn", "off")
	default:
		return append(params, "--flash-attn", "auto")
	}
}

// appendLoadModeArgs selects llama-server's single model loading mode. Direct I/O
// skips the page cache on load for integrated CUDA/ROCm GPUs, which share system
// memory with the CPU and would otherwise double-buffer weights.
func appendLoadModeArgs(params []string, opts api.Options, gpus []ml.DeviceInfo) []string {
	for _, g := range gpus {
		if runtime.GOOS == "linux" && g.Integrated && (strings.EqualFold(g.Library, "CUDA") || strings.EqualFold(g.Library, "ROCm")) {
			return append(params, "--load-mode", "dio")
		}
	}

	if opts.UseMMap != nil && !*opts.UseMMap {
		return append(params, "--load-mode", "none")
	}

	return params
}

func appendMainGPUArgs(params []string, opts api.Options) []string {
	if opts.MainGPU == nil {
		return params
	}

	return append(params, "--split-mode", "none", "--main-gpu", strconv.Itoa(*opts.MainGPU))
}

func appendMMProjArgs(params []string, launch llamaServerLaunchConfig) []string {
	if len(launch.projectors) == 0 {
		return params
	}

	params = append(params, "--mmproj", launch.projectors[0])
	if disable, reason := launch.mmprojOffloadDisabled(); disable {
		slog.Info("disabling multimodal projector offload", "reason", reason, "model", launch.modelPath, "projector", launch.projectors[0])
		params = append(params, "--no-mmproj-offload")
	}

	return params
}

func (launch llamaServerLaunchConfig) mmprojOffloadDisabled() (bool, string) {
	if launch.requiresMMProjGPUOffload() {
		return false, ""
	}
	if launch.forceNoMMProjOffload {
		return true, "startup-oom-retry"
	}
	return shouldDisableMMProjOffload(launch.opts, launch.gpus, launch.modelLayers, launch.mmprojMemory)
}

func (launch llamaServerLaunchConfig) requiresMMProjGPUOffload() bool {
	// Gemma3n's MobileNetV5 projector silently produces corrupted image
	// embeddings when it runs on the CPU backend, so keep it on the GPU
	// whenever one is in play.
	return launch.modelArch == "gemma3n" && launch.opts.NumGPU != 0 && len(launch.gpus) > 0
}

func shouldDisableMMProjOffload(opts api.Options, gpus []ml.DeviceInfo, modelLayers, mmprojMemory uint64) (bool, string) {
	if opts.NumGPU == 0 {
		return true, "cpu-only"
	}
	if opts.NumGPU > 0 && modelLayers > 0 && uint64(opts.NumGPU) < modelLayers {
		return true, "partial-text-offload"
	}

	requiredMemory := mmprojMemory + mmprojOffloadHeadroom

	for _, gpu := range gpus {
		memory := gpu.FreeMemory
		if memory == 0 || (gpu.TotalMemory > 0 && gpu.TotalMemory < memory) {
			memory = gpu.TotalMemory
		}
		if memory > 0 && memory < requiredMemory {
			return true, "limited-vram"
		}
	}

	return false, ""
}

func (launch llamaServerLaunchConfig) extraEnvsForStart() map[string]string {
	pad, ok := launch.mmprojFitTargetMiB()
	if !ok {
		return launch.extraEnvs
	}

	if existing, ok := launch.extraEnvs[llamaArgFitTargetEnv]; ok {
		existingTarget, err := strconv.ParseUint(existing, 10, 64)
		if err != nil {
			slog.Warn("invalid llama-server fit target", "env", llamaArgFitTargetEnv, "value", existing, "error", err)
			return launch.extraEnvs
		}

		envs := cloneStringMap(launch.extraEnvs)
		envs[llamaArgFitTargetEnv] = strconv.FormatUint(existingTarget+pad, 10)
		return envs
	}

	if _, ok := envconfig.LookupEnv(llamaArgFitTargetEnv); ok { // xollama-hook: system-settings
		// Preserve an inherited user override. SetupLlamaServerCommandEnv
		// will pass it through unless extraEnvs overrides it.
		return launch.extraEnvs
	}

	envs := cloneStringMap(launch.extraEnvs)
	envs[llamaArgFitTargetEnv] = strconv.FormatUint(pad, 10)
	return envs
}

func (launch llamaServerLaunchConfig) mmprojFitTargetMiB() (uint64, bool) {
	if len(launch.projectors) == 0 || launch.mmprojMemory == 0 {
		return 0, false
	}
	if disable, _ := launch.mmprojOffloadDisabled(); disable {
		return 0, false
	}

	requiredMemory := launch.mmprojMemory + mmprojOffloadHeadroom
	return (requiredMemory + bytesPerMiB - 1) / bytesPerMiB, true
}

// mmprojMemoryRequirement is a stopgap until fit accounts for mmproj memory directly.
func mmprojMemoryRequirement(modelPath string, f *gguf.Model, projectors []string) (uint64, error) {
	if len(projectors) == 0 {
		return 0, nil
	}

	if projectors[0] == modelPath {
		if f == nil {
			return 0, errors.New("read inline mmproj metadata: missing model metadata")
		}
		size := f.Tensors().Size("v.", "mm.", "a.")
		if size == 0 {
			return 0, errors.New("read inline mmproj metadata: no projector tensors found")
		}
		return size, nil
	}

	projector, err := LoadModel(projectors[0], 1024)
	if err != nil {
		return 0, fmt.Errorf("read mmproj metadata %q: %w", projectors[0], err)
	}
	size := projector.Tensors().Size()
	if size == 0 {
		return 0, fmt.Errorf("read mmproj metadata %q: no projector tensors found", projectors[0])
	}
	return size, nil
}

func appendJinjaArgs(params []string, config LlamaServerConfig) []string {
	if config.DisableJinja {
		// Go-rendered chat paths send already-rendered prompts through completion
		// endpoints. Override any GGUF chat template so llama-server startup
		// does not parse an unused model template. llama-server still requires a
		// template name, so chatml is a startup-only placeholder and must not be
		// used for request routing.
		return append(params, "--no-jinja", "--chat-template", "chatml")
	}

	return params
}

func appendContextShiftArgs(params []string, opts api.Options, enabled bool) []string {
	if !enabled {
		return params
	}

	params = append(params, "--context-shift")
	if opts.NumKeep > 0 {
		params = append(params, "--keep", strconv.Itoa(opts.NumKeep))
	}

	return params
}

const (
	draftTypeMTP    = "draft-mtp"
	draftTypeDFlash = "draft-dflash"
	// draftTypeAssistant marks a draft head that has no context of its own and
	// runs against the target's. The two engines name the same driver
	// differently: upstream llama.cpp reaches it through draft-mtp, which
	// detects the shared context, while opencoti exposes it as its own
	// --spec-type value. specTypeArg maps between them.
	draftTypeAssistant = "draft-assistant"
)

// xollama-hook: draft-assistant — see docs/features/gemma4-drafter.md
//
// specTypeArg maps a draft type onto the --spec-type value a given engine
// understands. Only the assistant drafter differs between the two.
func specTypeArg(draftType string, opencoti bool) string {
	if draftType == draftTypeAssistant && !opencoti {
		return draftTypeMTP
	}
	return draftType
}

// retargetSpecType rewrites the --spec-type value once the engine is known.
// Params are built before the engine hook runs, so they carry the upstream
// spelling and only an opencoti launch needs adjusting.
func retargetSpecType(args []string, draftType string, opencoti bool) []string {
	want := specTypeArg(draftType, opencoti)
	for i := 0; i+1 < len(args); i++ {
		if args[i] == "--spec-type" && args[i+1] != want {
			out := slices.Clone(args)
			out[i+1] = want
			return out
		}
	}
	return args
}

func appendDraftArgs(params []string, draftType, draftModelPath string, opts api.Options) []string {
	if draftType == "" {
		return params
	}
	if opts.DraftNumPredict <= 0 {
		return params
	}

	params = append(params, "--spec-type", specTypeArg(draftType, false))
	params = append(params, "--spec-draft-n-max", strconv.Itoa(opts.DraftNumPredict))
	if draftType == draftTypeMTP {
		params = append(params, "--spec-draft-backend-sampling")
	}
	if draftModelPath != "" {
		params = append(params, "--spec-draft-model", draftModelPath)
	}
	return params
}

// resolveDraftType settles the --spec-type for this load: what the model
// explicitly pins, falling back to what the drafter's own metadata implies.
//
// The guard is the inferred type and not the presence of an attached drafter
// file, which is the distinction this function exists to hold. A pin is
// equally meaningful on a built-in head -- nextn_predict_layers, or qwen35's
// mtp.* tensors -- and consulting it only on the external path was a silent
// no-op: `tweak model --spec-type=...` wrote the layer and `xollama show`
// printed it while the launch went on passing the inferred value. A model with
// no drafter at all still states nothing, because a --spec-type with no
// drafter behind it is not a preference, it is a broken command line.

func resolveDraftType(inferred, override string) string {
	if inferred == "" || override == "" {
		return inferred
	}
	return override
}

// externalDraftType picks the --spec-type for an attached draft model.
//
// A drafter that declares <arch>.requires_target_arch is a head rather than a
// standalone model: it carries no context and has to be built against the
// target's. Launching one as draft-mtp does not degrade, it fails the load, so
// the metadata has to decide this and not the caller.
func externalDraftType(path, targetArch string) (string, error) {
	f, err := LoadModel(path, 1)
	if err != nil {
		return "", fmt.Errorf("load draft model metadata: %w", err)
	}
	// xollama-hook: draft-assistant — see docs/features/gemma4-drafter.md
	//
	// The rule itself lives in DraftTypeFor so that `xollama show` reaches the
	// same answer as the launch without restating it.
	draftType, err := DraftTypeFor(f.KV().Architecture(), f.KV().String("requires_target_arch"), targetArch)
	if err != nil {
		return "", fmt.Errorf("draft model %s: %w", path, err)
	}
	return draftType, nil
}

func hasMTPDraft(f *gguf.Model) bool {
	// xollama-hook: model-config — BuiltInDrafter holds the rule so `show` can
	// ask the same question without a second reading of it.
	return BuiltInDrafter(f.KV().Architecture(), f.KV().Uint("nextn_predict_layers"), f.Tensors().Items("mtp."))
}

func hasLegacyQwenMTPDraft(arch string, tensors []gguf.TensorInfo) bool {
	switch arch {
	case "qwen35", "qwen35moe":
		return len(tensors) > 0
	default:
		return false
	}
}

// NewLlamaServerRunner creates a new llama-server runner that wraps the upstream llama-server binary.
func NewLlamaServerRunner(
	gpus []ml.DeviceInfo,
	modelPath string,
	f *gguf.Model,
	adapters, projectors []string,
	opts api.Options,
	numParallel int,
	kvCacheType string,
	config LlamaServerConfig,
) (LlamaServer, error) {
	// Check if this is an embedding model
	arch := f.KV().Architecture()
	isEmbedding := f.KV().Has("pooling_type")
	decisionType := f.KV().String("decision.type")

	// Older Ollama-format GGUFs store vision tensors (v.*, mm.*) inline in
	// the main model file rather than in a separate projector layer. When
	// the arch has a llama/compat clip handler, we can point --mmproj at
	// the same file and the in-process shim translates the two views.
	//
	// If we auto-enable --mmproj for an arch whose clip handler doesn't
	// exist yet, upstream's clip loader sees un-translated Ollama tensors
	// and aborts model load. So gate on an explicit allowlist that mirrors
	// the compat layer's clip-side coverage in llama/compat/.
	compatClipArches := map[string]bool{
		"gemma3":          true,
		"gemma4":          true,
		"qwen35":          true,
		"qwen35moe":       true,
		"qwen25vl":        true,
		"qwen3vl":         true,
		"qwen3vlmoe":      true,
		"mistral3":        true,
		"deepseekocr":     true,
		"glmocr":          true,
		"llama4":          true,
		"nemotron_h_omni": true,
		// Add entries as llama/compat grows clip handlers.
	}
	if len(projectors) == 0 &&
		len(f.Tensors().Items("v.")) > 0 &&
		compatClipArches[arch] {
		projectors = []string{modelPath}
	}
	mmprojMemory, err := mmprojMemoryRequirement(modelPath, f, projectors)
	if err != nil {
		return nil, err
	}
	if config.DraftModelPath == "" && hasMTPDraft(f) {
		config.EnableMTP = true
	}

	draftType := ""
	if config.EnableMTP {
		draftType = draftTypeMTP
	}
	if config.DraftModelPath != "" {
		draftType, err = externalDraftType(config.DraftModelPath, arch)
		if err != nil {
			return nil, err
		}
	}
	// xollama-hook: model-config — see docs/features/model-config.md
	draftType = resolveDraftType(draftType, config.draftSpecTypeOverride())
	splitModel, err := materializeSplitModels(f.Files(), projectors, config)
	if err != nil {
		return nil, err
	}
	config.DraftModelPath = splitModel.draftModelPath

	gpuLibs := ml.LibraryPaths(gpus)
	status := NewStatusWriter(os.Stderr)

	// memWriter wraps the status writer and parses buffer size lines from llama-server logs
	memWriter := &memoryParsingWriter{inner: status}

	mediaMarker := newLlamaServerMediaMarker()
	extraEnvs := ml.GetDevicesEnv(gpus)
	serverEnvs := make(map[string]string, len(extraEnvs)+1)
	for k, v := range extraEnvs {
		serverEnvs[k] = v
	}
	serverEnvs["LLAMA_MEDIA_MARKER"] = mediaMarker
	// xollama-hook: system-settings — the server's GPU policy for these GPUs.
	if DeviceEnvs != nil {
		for k, v := range DeviceEnvs(gpus) {
			serverEnvs[k] = v
		}
	}

	launch := llamaServerLaunchConfig{
		modelPath:      splitModel.modelPath,
		modelArch:      arch,
		trainContext:   int(f.KV().ContextLength()),
		recurrentState: modelKeepsRecurrentState(f),
		draftType:      draftType,
		projectors:     slices.Clone(splitModel.projectors),
		mmprojMemory:   mmprojMemory,
		modelLayers:    f.KV().BlockCount() + 1,
		adapters:       slices.Clone(adapters),
		opts:           opts,
		numParallel:    numParallel,
		kvCacheType:    kvCacheType,
		embedding:      isEmbedding,
		decision:       decisionType != "",
		config:         config,
		gpus:           slices.Clone(gpus),
		gpuLibs:        slices.Clone(gpuLibs),
		extraEnvs:      cloneStringMap(serverEnvs),
	}

	s := &llamaServerRunner{
		client:           newLlamaServerHTTPClient(),
		status:           status,
		options:          opts,
		modelPath:        modelPath,
		splitDirs:        splitModel.dirs,
		mediaMarker:      mediaMarker,
		vramByDevice:     make(map[string]uint64),
		systemFreeAtLoad: make(map[string]uint64),
		gpus:             gpus,
		metadata:         f,
		totalLayers:      f.KV().BlockCount() + 1,
		rawEmbeddings:    legacyEmbeddingsWereRaw(f.KV()),
		sem:              semaphore.NewWeighted(int64(numParallel)),
		launch:           launch,
		output:           memWriter,
	}
	// Point the memory parsing writer at this runner so values are updated as logs stream in
	memWriter.runner = s

	if err := s.startProcess(); err != nil {
		_ = s.removeSplitDirs()
		msg := s.lastErrMsg()
		return nil, fmt.Errorf("error starting llama-server: %v %s", err, msg)
	}

	return s, nil
}

func cloneStringMap(src map[string]string) map[string]string {
	dst := make(map[string]string, len(src))
	for k, v := range src {
		dst[k] = v
	}
	return dst
}

func legacyEmbeddingsWereRaw(kv *gguf.Metadata) bool {
	arch := kv.Architecture()
	if !kv.Has("pooling_type") {
		return false
	}

	// Legacy /api/embeddings returned runner output, so preserve only old raw embed paths.
	switch arch {
	case "bert":
		if kv.String("tokenizer.ggml.model", "bert") != "bert" {
			return true
		}
		return !kv.Bool("normalize_embeddings", true)
	case "nomic-bert", "nomic-bert-moe":
		return !kv.Bool("normalize_embeddings", false)
	case "gemma3", "gemma-embedding", "qwen3":
		return false
	default:
		return false
	}
}

func (s *llamaServerRunner) startProcess() error {
	cmd, port, usedOpencoti, err := startLlamaServer(s.launch, s.output)
	if err != nil {
		return err
	}

	// xollama-hook: launch-config — the half that makes dynamic slots visible.
	// ollama gates concurrency on this semaphore, sized to num_parallel, so an
	// engine that had grown to four live slots would still be fed one request
	// at a time. Resized here rather than at construction because it depends on
	// which engine answered, which is only known now.
	// xollama-hook: council -- the council's live slots, as in the launch.
	if plan := resolveSlotPlan(s.launch.config, councilLive(s.launch.config, s.launch.numParallel, usedOpencoti), s.launch.config.singleSequence(usedOpencoti)); usedOpencoti {
		if n := plan.concurrency(); n > s.launch.numParallel {
			slog.Info("dynamic slots: concurrency raised, engine admits slots as headroom allows",
				"live", plan.Live, "max", n)
			s.sem = semaphore.NewWeighted(int64(n))
		}
	}

	s.cmd = cmd
	s.port = port
	s.usedOpencoti = usedOpencoti
	// xollama-hook: engine-session — the pool registry is sized to the same
	// number the engine was given seats for, and is rebuilt per process: pool
	// ids belong to the engine that issued them.
	switch pools := effectivePoolCount(s.launch.config, len(s.launch.projectors) > 0); {
	case !usedOpencoti:
		s.pools = nil
	// Before the pools <= 0 case: effectivePoolCount returns 0 for exactly
	// this, so testing the count first would swallow the one explanation an
	// operator who asked for pooling actually needs.
	case len(s.launch.projectors) > 0 && resolvePoolCount(s.launch.config) > 0:
		slog.Info("shared prefix pools are off for this model: the engine does not support them on a multimodal load",
			"model", s.modelPath)
		s.pools = nil
	case pools <= 0:
		s.pools = nil
	default:
		// Said once, at load: on these models the engine takes a share only
		// when it covers the pool exactly, so pooling works from the Chat path,
		// where the template boundary can be measured, and is skipped on the
		// Completion path, where it cannot. An operator watching for pools on
		// a hybrid model is owed that. See engine_pool_arch.go.
		if s.launch.recurrentState {
			slog.Info("shared prefix pools on this model need an exact prefix: its recurrent state is shared only as a whole, so a pool is created only where the template boundary can be measured",
				"model", s.modelPath, "architecture", s.launch.modelArch)
		}
		s.pools = newPoolRegistry(pools)
	}
	s.done = make(chan struct{})
	s.doneErr = nil
	s.stopping.Store(false) // xollama-hook: engine-select
	s.loadStart = time.Now()
	s.startLoadTracking(s.loadStart)

	// Reap subprocess when it exits.
	go func(cmd *exec.Cmd, done chan struct{}) {
		err := cmd.Wait()
		if s.usedOpencoti {
			engine.AdoptPayloadHome(engine.HomeOf(cmd.Env)) // xollama-hook: engine-payload -- a root run hands the engine's files to the service account
		}
		s.doneErr = err
		if msg := s.lastErrMsg(); err != nil && msg != "" {
			// xollama-hook: engine-select -- at load, opencoti prints a benign
			// "Error: Jinja Exception: No messages provided." while probing the
			// chat template. That line is the runner's last "error", so every
			// unload was logged as a crash (bug-117).
			if s.usedOpencoti && s.stopping.Load() {
				slog.Debug("llama-server stopped as asked", "error", err)
			} else {
				slog.Error("llama-server terminated", "error", err, "exit", ExitStatusFromError(err))
			}
			s.doneErr = errors.New(msg)
		}
		close(done)
	}(s.cmd, s.done)

	return nil
}

func qwenVLServerArgs(modelArch string) []string {
	switch modelArch {
	case "qwen2vl", "qwen25vl", "qwen3vl", "qwen3vlmoe":
		// Upstream mtmd warns that Qwen-VL needs at least 1024 image tokens for
		// correct grounding/counting behavior; the GGUF metadata default is too low.
		return []string{"--image-min-tokens", "1024"}
	default:
		return nil
	}
}

// Load waits for llama-server to finish loading the model. llama-server loads
// the model at startup and auto-detects GPU layers, so this just waits for
// health to report ready. The scheduler handles full-fit preflight for
// llama-server before this point.
func (s *llamaServerRunner) Load(ctx context.Context, systemInfo ml.SystemInfo, gpus []ml.DeviceInfo, _ bool) ([]ml.DeviceID, error) {
	slog.Info("loading model via llama-server", "model", s.modelPath)

	if err := s.WaitUntilRunning(ctx); err != nil {
		retried, retryErr := s.retryWithMMProjCPUOffload(err)
		if retryErr != nil {
			return nil, retryErr
		}
		if retried {
			if err := s.WaitUntilRunning(ctx); err != nil {
				return nil, fmt.Errorf("llama-server startup failed after projector CPU offload retry: %w", err)
			}
		} else if kvRetried, kvErr := s.retryWithF16V(err); kvErr != nil || kvRetried { // xollama-hook: kv-fa-retry
			if kvErr != nil {
				return nil, kvErr
			}
			if err := s.WaitUntilRunning(ctx); err != nil {
				return nil, fmt.Errorf("llama-server startup failed after retrying with an f16 V cache: %w", err)
			}
		} else {
			stockRetried, stockErr := s.retryOnStockEngine(err)
			if stockErr != nil {
				return nil, stockErr
			}
			if !stockRetried {
				// xollama-hook: engine-defects — a published engine build we
				// cannot patch still gets to fail with a readable message.
				return nil, s.annotateEngineDefect(err)
			}
			if err := s.WaitUntilRunning(ctx); err != nil {
				return nil, fmt.Errorf("llama-server startup failed after falling back to the stock engine: %w", err)
			}
		}
	}
	if err := s.removeSplitDirs(); err != nil {
		slog.Debug("split GGUF alias cleanup deferred until runner shutdown", "error", err)
	}

	// Verify that buffer size parsing captured GPU allocations.
	// If parsing failed (e.g., llama-server log format changed), warn so the
	// issue is visible in logs when users report problems.
	if len(s.gpus) > 0 && !s.hasParsedVRAM() {
		slog.Warn("llama-server VRAM tracking: no per-device buffer sizes were parsed from "+
			"llama-server logs. VRAM accounting will be inaccurate. This may indicate a "+
			"change in llama-server's log format — check for 'buffer size' lines in the output.",
			"model", s.modelPath, "gpus", len(s.gpus))
	}

	if s.options.MainGPU != nil && *s.options.MainGPU >= 0 && *s.options.MainGPU < len(gpus) {
		return []ml.DeviceID{gpus[*s.options.MainGPU].DeviceID}, nil
	}

	// Return device IDs for all GPUs when llama-server manages layer placement itself.
	deviceIDs := make([]ml.DeviceID, len(gpus))
	for i, g := range gpus {
		deviceIDs[i] = g.DeviceID
	}

	return deviceIDs, nil
}

// retryOnStockEngine restarts a failed opencoti load on stock llama-server.
//
// Off unless XOLLAMA_ENGINE_FALLBACK is set. The default is to fail, because a
// silent downgrade is the worse outcome: the load would succeed with none of
// the engine's behaviour and nothing in the response would say so, and every
// A/B against vanilla would quietly become an A/A.
func (s *llamaServerRunner) retryOnStockEngine(loadErr error) (bool, error) {
	if !s.usedOpencoti || s.engineFallbackRetried || !engine.FallbackOnLoadFailure() ||
		!engine.StockShipped(runtime.GOOS) { // xollama-hook: stockless
		return false, nil
	}

	slog.Warn("opencoti-llamafile failed to load this model; falling back to stock llama-server",
		"model", s.modelPath, "error", loadErr, "enabled_by", engine.EnvFallback)
	s.engineFallbackRetried = true
	s.launch.forceStockEngine = true

	if err := s.stopProcess(); err != nil {
		return false, fmt.Errorf("opencoti load failed: %w; error stopping failed process: %v", loadErr, err)
	}
	s.resetLoadAccounting()

	if err := s.startProcess(); err != nil {
		return false, fmt.Errorf("opencoti load failed: %w; error starting stock retry: %v", loadErr, err)
	}
	return true, nil
}

func (s *llamaServerRunner) retryWithMMProjCPUOffload(loadErr error) (bool, error) {
	if !s.shouldRetryMMProjCPUOffload(loadErr) {
		return false, nil
	}

	slog.Warn("llama-server startup failed with projector GPU offload; retrying with projector CPU offload", "model", s.modelPath, "error", loadErr)
	s.mmprojOffloadOOMRetried = true
	s.launch.forceNoMMProjOffload = true

	if err := s.stopProcess(); err != nil {
		return false, fmt.Errorf("llama-server startup failed before projector CPU offload retry: %w; error stopping failed process: %v", loadErr, err)
	}
	s.resetLoadAccounting()

	if err := s.startProcess(); err != nil {
		return false, fmt.Errorf("llama-server startup failed before projector CPU offload retry: %w; error starting retry: %v", loadErr, err)
	}
	return true, nil
}

func (s *llamaServerRunner) shouldRetryMMProjCPUOffload(err error) bool {
	if err == nil || s.mmprojOffloadOOMRetried || !IsOutOfMemory(err) || len(s.launch.projectors) == 0 {
		return false
	}
	if s.launch.requiresMMProjGPUOffload() {
		return false
	}
	// llama-server --fit can select a text-layer placement that fits before
	// mtmd/CLIP allocates the multimodal projector. Retry once with the
	// projector on CPU so the scheduler can keep the text model placement.
	disabled, _ := s.launch.mmprojOffloadDisabled()
	return !disabled
}

func (s *llamaServerRunner) resetLoadAccounting() {
	s.memoryMu.Lock()
	defer s.memoryMu.Unlock()

	s.memTotal = 0
	s.memGPU = 0
	s.memModelFileBacked = 0
	s.memCPUMappedModel = 0
	s.gpuLayers = 0
	s.gpuLayerOverflow = 0
	for k := range s.vramByDevice {
		delete(s.vramByDevice, k)
	}
	for k := range s.systemFreeAtLoad {
		delete(s.systemFreeAtLoad, k)
	}
	if s.status != nil {
		s.status.SetLastError("")
	}
}

func (s *llamaServerRunner) hasParsedVRAM() bool {
	s.memoryMu.RLock()
	defer s.memoryMu.RUnlock()

	return len(s.vramByDevice) > 0
}

func (s *llamaServerRunner) startLoadTracking(t time.Time) {
	if s == nil {
		return
	}
	s.loadTracking.Store(true)
	s.noteLoadActivity(t)
}

func (s *llamaServerRunner) stopLoadTracking() {
	if s == nil {
		return
	}
	s.loadTracking.Store(false)
}

func (s *llamaServerRunner) noteLoadActivity(t time.Time) {
	if s == nil || t.IsZero() {
		return
	}
	if !s.loadTracking.Load() {
		return
	}

	ns := t.UnixNano()
	for {
		prev := s.loadActivity.Load()
		if ns <= prev {
			return
		}
		if s.loadActivity.CompareAndSwap(prev, ns) {
			return
		}
	}
}

func (s *llamaServerRunner) lastLoadActivity() time.Time {
	if s == nil {
		return time.Time{}
	}
	if ns := s.loadActivity.Load(); ns > 0 {
		return time.Unix(0, ns)
	}
	return time.Time{}
}

// getServerStatus checks llama-server's /health endpoint.
// llama-server returns {"status":"ok"}, {"status":"loading model"}, or {"status":"error"}.
func (s *llamaServerRunner) getServerStatus(ctx context.Context) (ServerStatus, error) {
	if s.cmd.ProcessState != nil {
		msg := s.lastErrMsg()
		if s.cmd.ProcessState.ExitCode() == -1 {
			slog.Warn("llama-server process no longer running", "sys", s.cmd.ProcessState.Sys(), "string", s.cmd.ProcessState)
		}
		return ServerStatusError, fmt.Errorf("llama-server process no longer running: %s %s", ExitStatus(s.cmd.ProcessState.ExitCode()), msg)
	}

	req, err := http.NewRequestWithContext(ctx, http.MethodGet, fmt.Sprintf("http://127.0.0.1:%d/health", s.port), nil)
	if err != nil {
		return ServerStatusError, fmt.Errorf("error creating health request: %v", err)
	}

	resp, err := s.httpClient().Do(req)
	if err != nil {
		if errors.Is(err, context.DeadlineExceeded) {
			return ServerStatusNotResponding, errors.New("server not responding")
		}
		if strings.Contains(err.Error(), "connection refused") {
			return ServerStatusNotResponding, errors.New("connection refused")
		}
		return ServerStatusError, fmt.Errorf("health resp: %w", err)
	}
	defer resp.Body.Close()

	body, err := io.ReadAll(resp.Body)
	if err != nil {
		return ServerStatusError, fmt.Errorf("read health response: %w", err)
	}

	// llama-server returns {"status":"ok"}, {"status":"loading model"}, {"status":"error", ...}
	var result struct {
		Status string `json:"status"`
		Error  *struct {
			Message string `json:"message"`
		} `json:"error"`
	}
	if err := json.Unmarshal(body, &result); err != nil {
		return ServerStatusError, fmt.Errorf("health unmarshal: %w", err)
	}

	switch result.Status {
	case "ok":
		return ServerStatusReady, nil
	case "loading model":
		return ServerStatusLoadingModel, nil
	case "no slot available":
		return ServerStatusNoSlotsAvailable, nil
	default:
		if result.Error != nil {
			switch strings.ToLower(strings.TrimSpace(result.Error.Message)) {
			case "loading model":
				return ServerStatusLoadingModel, nil
			case "no slot available":
				return ServerStatusNoSlotsAvailable, nil
			}
		}
		return ServerStatusError, fmt.Errorf("llama-server error: %s", string(body))
	}
}

func (s *llamaServerRunner) getServerStatusRetry(ctx context.Context) (ServerStatus, error) {
	var retries int
	for {
		status, err := s.getServerStatus(ctx)
		if err != nil {
			// xollama-hook: engine-health-retry — a dial that failed against a
			// live opencoti is tried again (engine_health_retry.go).
			if status, err = s.retryHealth(ctx, status, err); err != nil {
				return status, err
			}
		}
		if status == ServerStatusNoSlotsAvailable {
			if retries >= 10 {
				return status, fmt.Errorf("no slots available after %d retries", retries)
			}
			time.Sleep(5 * time.Millisecond)
			retries++
			continue
		}
		return status, nil
	}
}

func (s *llamaServerRunner) Ping(ctx context.Context) error {
	_, err := s.getServerStatus(ctx)
	if err != nil {
		slog.Debug("llama-server unhealthy", "error", err)
	}
	return err
}

func (s *llamaServerRunner) WaitUntilRunning(ctx context.Context) error {
	s.startLoadTracking(time.Now())
	defer s.stopLoadTracking()

	stallTimeout := envconfig.LoadTimeout()
	lastActivity := s.lastLoadActivity()
	if lastActivity.IsZero() {
		lastActivity = s.loadStart
	}
	if lastActivity.IsZero() {
		lastActivity = time.Now()
	}
	loadDeadline := lastActivity.Add(stallTimeout)

	slog.Info("waiting for llama-server to start responding")
	var lastStatus ServerStatus = -1

	for {
		select {
		case <-ctx.Done():
			slog.Warn("client connection closed before llama-server finished loading, aborting load")
			return fmt.Errorf("timed out waiting for llama-server to start: %w", ctx.Err())
		case <-s.done:
			if msg := s.lastErrMsg(); msg != "" {
				if s.doneErr == nil {
					return fmt.Errorf("llama-server process has terminated: %s", msg)
				}
				if s.cmd != nil && s.cmd.ProcessState != nil && s.cmd.ProcessState.ExitCode() >= 0 {
					return fmt.Errorf("llama-server process has terminated: %s: %s", ExitStatus(s.cmd.ProcessState.ExitCode()), msg)
				}
				if exit := ExitStatusFromError(s.doneErr); exit.Known() {
					return fmt.Errorf("llama-server process has terminated: %s: %s", exit, msg)
				}
				return fmt.Errorf("llama-server process has terminated: %w: %s", s.doneErr, msg)
			}
			if s.doneErr == nil {
				if s.cmd != nil && s.cmd.ProcessState != nil {
					return fmt.Errorf("llama-server process has terminated: %s", ExitStatus(s.cmd.ProcessState.ExitCode()))
				}
				return errors.New("llama-server process has terminated")
			}
			if exit := ExitStatusFromError(s.doneErr); exit.Known() {
				return fmt.Errorf("llama-server process has terminated: %s", exit)
			}
			return fmt.Errorf("llama-server process has terminated: %w", s.doneErr)
		default:
		}

		if activity := s.lastLoadActivity(); activity.After(lastActivity) {
			lastActivity = activity
			loadDeadline = lastActivity.Add(stallTimeout)
		}

		if time.Now().After(loadDeadline) {
			msg := s.lastErrMsg()
			return fmt.Errorf("timed out waiting for llama-server to start - %s", msg)
		}

		if s.cmd.ProcessState != nil {
			msg := s.lastErrMsg()
			return fmt.Errorf("llama-server process no longer running: %s %s", ExitStatus(s.cmd.ProcessState.ExitCode()), msg)
		}

		pollCtx, cancel := context.WithTimeout(ctx, 200*time.Millisecond)
		status, statusErr := s.getServerStatus(pollCtx)
		cancel()

		statusChanged := lastStatus != status
		if statusChanged && status != ServerStatusReady {
			slog.Info("waiting for llama-server to become available", "status", status)
		}
		if statusChanged && status == ServerStatusLoadingModel {
			lastActivity = time.Now()
			loadDeadline = lastActivity.Add(stallTimeout)
		}

		switch status {
		case ServerStatusReady:
			if s.status != nil {
				s.status.SetLastError("")
			}
			slog.Info(fmt.Sprintf("llama-server started in %0.2f seconds", time.Since(s.loadStart).Seconds()))
			return nil
		case ServerStatusError:
			msg := s.lastErrMsg()
			if isRecoverableOutOfMemoryMessage(msg) || isRecoverableOutOfMemory(statusErr) {
				lastStatus = status
				time.Sleep(time.Millisecond * 250)
				continue
			}
			if IsOutOfMemoryMessage(msg) {
				return fmt.Errorf("llama-server reported out-of-memory during startup: %s", msg)
			}
			if IsOutOfMemory(statusErr) {
				return fmt.Errorf("llama-server reported out-of-memory during startup: %w", statusErr)
			}
			lastStatus = status
			time.Sleep(time.Millisecond * 250)
		default:
			lastStatus = status
			time.Sleep(time.Millisecond * 250)
		}
	}
}

func (s *llamaServerRunner) lastErrMsg() string {
	if s.status == nil {
		return ""
	}
	return s.status.LastError()
}

// llamaServerCompletionRequest is the request format for llama-server's POST /completion endpoint.
type llamaServerCompletionRequest struct {
	Prompt          any             `json:"prompt"`
	Stream          bool            `json:"stream"`
	CachePrompt     bool            `json:"cache_prompt"`
	NPredict        int             `json:"n_predict,omitempty"`
	NKeep           int             `json:"n_keep,omitempty"`
	Temperature     float32         `json:"temperature"`
	TopK            int             `json:"top_k"`
	TopP            float32         `json:"top_p"`
	MinP            float32         `json:"min_p"`
	Stop            []string        `json:"stop,omitempty"`
	RepeatPenalty   float32         `json:"repeat_penalty"`
	RepeatLastN     int             `json:"repeat_last_n"`
	FreqPenalty     float32         `json:"frequency_penalty"`
	PresPenalty     float32         `json:"presence_penalty"`
	TypicalP        float32         `json:"typical_p,omitempty"`
	Seed            int             `json:"seed"`
	Grammar         string          `json:"grammar,omitempty"`
	JsonSchema      json.RawMessage `json:"json_schema,omitempty"`
	NProbs          int             `json:"n_probs,omitempty"`
	PreservedTokens []string        `json:"preserved_tokens,omitempty"`
	TimingsPerToken bool            `json:"timings_per_token,omitempty"`

	// Reasoning budget sampler. llama-server activates it once it sees
	// ReasoningBudgetStartTag generated (or present in GenerationPrompt), then
	// forces ReasoningBudgetEndTag after ReasoningBudgetTokens tokens.
	ReasoningBudgetTokens   int    `json:"reasoning_budget_tokens,omitempty"`
	ReasoningBudgetStartTag string `json:"reasoning_budget_start_tag,omitempty"`
	ReasoningBudgetEndTag   string `json:"reasoning_budget_end_tag,omitempty"`
	// ReasoningBudgetMessage must be sent even when empty: llama-server builds
	// the sequence it forces from message+end_tag, and only does so when this
	// field is present. A pointer keeps the empty string on the wire.
	ReasoningBudgetMessage *string `json:"reasoning_budget_message,omitempty"`
	// ReasoningBudgetScope spends the budget across the whole response
	// ("response") rather than re-arming it for every thinking block
	// ("block", llama-server's default). ReasoningBudgetResetTag forgives what
	// has been spent when it appears -- a tool call means progress, not a loop.
	ReasoningBudgetScope    string `json:"reasoning_budget_scope,omitempty"`
	ReasoningBudgetResetTag string `json:"reasoning_budget_reset_tag,omitempty"`
	GenerationPrompt        string `json:"generation_prompt,omitempty"`

	// xollama-hook: engine-session — opencoti-llamafile only. SessionID binds
	// this request to the slot already holding that conversation's KV; PoolID
	// attaches it to a shared prefix pool, whose overlap the engine computes
	// itself token-exactly. Omitted entirely on every other engine.
	SessionID string `json:"session_id,omitempty"`
	PoolID    *int   `json:"pool_id,omitempty"`
	// xollama-hook: council -- the window a council owner books. Never set
	// outside a council's placement, so every other body is unchanged.
	NumCtx     int   `json:"num_ctx,omitempty"`
	NumCtxMin  int   `json:"num_ctx_min,omitempty"`
	NumCtxHold *bool `json:"num_ctx_hold,omitempty"`
	// xollama-hook: notices -- opencoti's generation notices, only on an
	// engine that declares them (llm/engine_notice.go).
	Notices json.RawMessage `json:"notices,omitempty"`
}

// schemaGrammars caches the grammars llama-server derives from JSON schemas,
// most recently used first. The conversion depends only on the llama-server
// build, which is fixed for the process, so entries are shared by every
// runner and never expire.
var schemaGrammars = struct {
	sync.Mutex
	entries map[string]*list.Element
	order   list.List
}{entries: map[string]*list.Element{}}

const schemaGrammarsSize = 64

type schemaGrammar struct {
	schema, grammar string
}

// schemaGrammar converts a JSON schema to GBNF with llama-server's own
// converter. An empty completion evaluates and generates nothing, but its
// final response still reports the grammar the schema was converted to.
func (s *llamaServerRunner) schemaGrammar(ctx context.Context, schema json.RawMessage) (string, error) {
	key := string(schema)
	schemaGrammars.Lock()
	if e, ok := schemaGrammars.entries[key]; ok {
		schemaGrammars.order.MoveToFront(e)
		schemaGrammars.Unlock()
		return e.Value.(*schemaGrammar).grammar, nil
	}
	schemaGrammars.Unlock()

	body, err := json.Marshal(struct {
		Prompt         [][]int         `json:"prompt"`
		NPredict       int             `json:"n_predict"`
		JsonSchema     json.RawMessage `json:"json_schema"`
		ResponseFields []string        `json:"response_fields"`
		// xollama-hook: council -- on opencoti the conversion states a small
		// window of its own (engine_grammar.go); absent on stock llama.cpp.
		NumCtx int `json:"num_ctx,omitempty"`
	}{Prompt: [][]int{{}}, JsonSchema: schema, ResponseFields: []string{"generation_settings/grammar"}, NumCtx: grammarWindow(s.usedOpencoti)})
	if err != nil {
		return "", fmt.Errorf("failed to marshal grammar request: %v", err)
	}
	endpoint := fmt.Sprintf("http://127.0.0.1:%d/completion", s.port)
	serverReq, err := http.NewRequestWithContext(ctx, http.MethodPost, endpoint, bytes.NewReader(body))
	if err != nil {
		return "", fmt.Errorf("error creating grammar request: %v", err)
	}
	serverReq.Header.Set("Content-Type", "application/json")
	res, err := s.httpClient().Do(serverReq)
	if err != nil {
		return "", fmt.Errorf("llama-server grammar request failed: %v", err)
	}
	defer res.Body.Close()
	resBody, err := io.ReadAll(res.Body)
	if err != nil {
		return "", fmt.Errorf("failed reading llama-server grammar response: %w", err)
	}
	if res.StatusCode >= 400 {
		return "", api.StatusError{StatusCode: res.StatusCode, ErrorMessage: s.statusErrorMessage(resBody)}
	}
	var lsRes struct {
		Grammar string `json:"generation_settings/grammar"`
	}
	if err := json.Unmarshal(resBody, &lsRes); err != nil {
		return "", fmt.Errorf("error unmarshalling llama-server grammar response: %v", err)
	}
	if lsRes.Grammar == "" {
		return "", errors.New("llama-server returned no grammar for the schema")
	}

	schemaGrammars.Lock()
	defer schemaGrammars.Unlock()
	if _, ok := schemaGrammars.entries[key]; !ok {
		if schemaGrammars.order.Len() == schemaGrammarsSize {
			oldest := schemaGrammars.order.Back()
			delete(schemaGrammars.entries, oldest.Value.(*schemaGrammar).schema)
			schemaGrammars.order.Remove(oldest)
		}
		schemaGrammars.entries[key] = schemaGrammars.order.PushFront(&schemaGrammar{schema: key, grammar: lsRes.Grammar})
	}
	return lsRes.Grammar, nil
}

func llamaServerPreservedTokens(parserTokens []string, toolCallTag string) []string {
	tokens := append([]string{}, parserTokens...)
	tokens = append(tokens, llamaServerPreservedTokensForToolTag(toolCallTag)...)
	return tokens
}

// llama-server only preserves strings that tokenize to one special token. Some
// Go templates use a parser tag like "[TOOL_CALLS][", where the first segment
// is the special token and the trailing "[" is regular JSON punctuation.
func llamaServerPreservedTokensForToolTag(tag string) []string {
	if tag == "" || tag == "{" || tag == "[" {
		return nil
	}

	if token := leadingSpecialTokenCandidate(tag); token != "" {
		return []string{token}
	}

	return []string{tag}
}

func leadingSpecialTokenCandidate(tag string) string {
	if len(tag) == 0 {
		return ""
	}

	var close byte
	switch tag[0] {
	case '[':
		close = ']'
	case '<':
		close = '>'
	default:
		return ""
	}

	end := strings.IndexByte(tag, close)
	if end <= 0 {
		return ""
	}

	return tag[:end+1]
}

// maxThinkingGenerationPrompt bounds how much of the prompt is replayed into
// the budget sampler. Every renderer that primes thinking does so with the
// opening tag and at most a channel name, so a longer run means the tag came
// from message content rather than the template: replaying that would activate
// the budget against text the model never generated.
const maxThinkingGenerationPrompt = 64

// thinkingGenerationPrompt returns the part of the prompt that already sits
// inside an unclosed thinking block, for llama-server to replay into the
// reasoning-budget sampler before decoding.
//
// The sampler leaves its idle state only when the opening tag passes through
// it, so a template that primes thinking — by ending the prompt with the tag,
// or with the tag plus a channel name, as gemma4 does after a tool response —
// otherwise leaves the budget silently inert for the whole turn. Matching the
// unclosed opening rather than the exact suffix keeps that from depending on
// how much a renderer writes after the tag.
func thinkingGenerationPrompt(prompt, startTag, endTag string) string {
	if startTag == "" || endTag == "" {
		return ""
	}

	start := strings.LastIndex(prompt, startTag)
	if start == -1 {
		return ""
	}

	tail := prompt[start:]
	if strings.Contains(tail[len(startTag):], endTag) || len(tail) > maxThinkingGenerationPrompt {
		return ""
	}

	return tail
}

// llamaServerMultimodalPrompt is used when images are present.
// llama-server's /completion endpoint accepts this as the "prompt" field.
type llamaServerMultimodalPrompt struct {
	PromptString   string   `json:"prompt_string"`
	MultimodalData []string `json:"multimodal_data"`
}

// llamaServerCompletionResponse is the response format from llama-server's /completion endpoint.
type llamaServerCompletionResponse struct {
	Content                 string                 `json:"content"`
	Stop                    bool                   `json:"stop"`
	StopType                string                 `json:"stop_type"`
	Timings                 llamaServerTimings     `json:"timings"`
	CompletionProbabilities []llamaServerTokenProb `json:"completion_probabilities"`
	// xollama-hook: notices -- opencoti contract v3, on the first token's chunk.
	Notice *api.Notice `json:"notice"`
}

type llamaServerChatChoice struct {
	Delta struct {
		Content          string `json:"content"`
		ReasoningContent string `json:"reasoning_content"`
		ToolCalls        []struct {
			Index    int    `json:"index"`
			ID       string `json:"id"`
			Type     string `json:"type"`
			Function struct {
				Name      string `json:"name"`
				Arguments string `json:"arguments"`
			} `json:"function"`
		} `json:"tool_calls"`
	} `json:"delta"`
	FinishReason *string `json:"finish_reason"`
	Logprobs     struct {
		Content []llamaServerTokenProb `json:"content"`
	} `json:"logprobs"`
}

type llamaServerChatResponse struct {
	Choices []llamaServerChatChoice `json:"choices"`
	Timings llamaServerTimings      `json:"timings"`
	Error   any                     `json:"error"`
	// xollama-hook: notices -- opencoti contract v3, on the first token's chunk.
	Notice *api.Notice `json:"notice"`
}

type llamaServerTimings struct {
	CacheN    *int    `json:"cache_n"`
	PromptN   int     `json:"prompt_n"`
	PromptMS  float64 `json:"prompt_ms"`
	PredictN  int     `json:"predicted_n"`
	PredictMS float64 `json:"predicted_ms"`
	// xollama-hook: notices -- opencoti contract v2; Notices is v3's list.
	NoticesPlanted int          `json:"notices_planted"`
	Notices        []api.Notice `json:"notices"`
}

func (t llamaServerTimings) promptEvalCount() int {
	if t.CacheN == nil {
		return t.PromptN
	}
	return *t.CacheN + t.PromptN
}

type llamaServerApplyTemplateResponse struct {
	Prompt string `json:"prompt"`
	Error  any    `json:"error"`
}

type llamaServerTokenProb struct {
	Token       string                 `json:"token"`
	Logprob     float64                `json:"logprob"`
	Prob        float64                `json:"prob"`
	TopLogprobs []llamaServerTokenProb `json:"top_logprobs"`
	TopProbs    []llamaServerTokenProb `json:"top_probs"`
}

func (s *llamaServerRunner) Completion(ctx context.Context, req CompletionRequest, fn func(CompletionResponse)) (err error) {
	slog.Debug("llama-server completion request", "media", len(req.Media), "prompt_len", len(req.Prompt))

	// xollama-hook: engine-session — a request that succeeded is evidence about
	// what conversations with this system prompt have in common, which is what
	// a pool is built from. ollama rendered this prompt, so it is handed over
	// as it stands. It happens after the response, in the background, and can
	// only fail quietly. See engine_pool.go.
	pooled := poolSource{prompt: req.Prompt, probes: req.PoolProbes}
	defer func() {
		if err == nil {
			s.capturePool(req.PoolKey, pooled)
		}
	}()

	if req.Options == nil {
		opts := api.DefaultOptions()
		req.Options = &opts
	}

	if err := s.sem.Acquire(ctx, 1); err != nil {
		if errors.Is(err, context.Canceled) {
			slog.Info("aborting completion request due to client closing the connection")
		}
		return err
	}
	defer s.sem.Release(1)

	req.Options.NumPredict = boundedNumPredict(req.Options.NumPredict, s.options.NumCtx)

	status, err := s.getServerStatusRetry(ctx)
	if err != nil {
		return err
	} else if status != ServerStatusReady {
		return fmt.Errorf("unexpected server status: %s", status)
	}

	prompt, err := s.completionPromptForRequest(ctx, req)
	if err != nil {
		return err
	}

	// Build the llama-server request
	lsReq := llamaServerCompletionRequest{
		Prompt:          prompt,
		Stream:          true,
		CachePrompt:     true,
		NPredict:        req.Options.NumPredict,
		NKeep:           req.Options.NumKeep,
		Temperature:     req.Options.Temperature,
		TopK:            req.Options.TopK,
		TopP:            req.Options.TopP,
		MinP:            req.Options.MinP,
		Stop:            req.Options.Stop,
		RepeatPenalty:   req.Options.RepeatPenalty,
		RepeatLastN:     stockRepeatLastN(req.Options.RepeatLastN, s.options.NumCtx, s.usedOpencoti), // xollama-hook: repeat-last-n
		FreqPenalty:     req.Options.FrequencyPenalty,
		PresPenalty:     req.Options.PresencePenalty,
		TypicalP:        req.Options.TypicalP,
		Seed:            req.Options.Seed,
		PreservedTokens: llamaServerPreservedTokens(req.PreservedTokens, req.ToolCallTag),
	}

	if req.Logprobs {
		lsReq.NProbs = max(req.TopLogprobs, 1)
	}

	// Cap thinking. llama-server's reasoning budget sampler needs both
	// delimiters: it starts counting at the opening tag and forces the closing
	// tag once the budget runs out.
	if req.ThinkBudget > 0 && req.ThinkingStartTag != "" && req.ThinkingEndTag != "" {
		lsReq.ReasoningBudgetTokens = req.ThinkBudget
		lsReq.ReasoningBudgetStartTag = req.ThinkingStartTag
		lsReq.ReasoningBudgetEndTag = req.ThinkingEndTag
		// Sent even when empty. llama-server builds the sequence it forces
		// from message+end_tag, and on the pinned runtime it builds it in this
		// field's handler, so an absent field is a handler that never runs:
		// the budget expires with nothing to force, the sampler logs its usual
		// states, and the thinking block is left open.
		lsReq.ReasoningBudgetMessage = &req.ThinkBudgetMessage

		// Bound the response, not the block. Measured live on gemma4: six
		// consecutive thinking blocks, each closed by the model just short of
		// its 8,000-token window and each re-armed in full, consumed a 32,000
		// token output cap without the budget ever expiring -- so the message
		// that tells the model to wrap up was never injected and the turn
		// ended with neither an answer nor a tool call.
		lsReq.ReasoningBudgetScope = "response"
		lsReq.ReasoningBudgetResetTag = req.ThinkBudgetResetTag

		// The sampler only sees tokens the model generates, so a template that
		// primes thinking by ending the prompt inside a thinking block would
		// never activate it. Hand that opening over as the generation prompt
		// instead: llama-server replays it into the sampler before decoding.
		lsReq.GenerationPrompt = thinkingGenerationPrompt(req.Prompt, req.ThinkingStartTag, req.ThinkingEndTag)
	}

	// xollama-hook: engine-session — see docs/xollama/sessions.mdx.
	poolID := req.PoolID
	if poolID == nil {
		poolID = s.poolFor(req.PoolKey)
	}
	applySession(&lsReq, s.usedOpencoti, s.launch.config, req.SessionID, poolID)
	// xollama-hook: notices
	if n := s.noticesFor(ctx, req.Notices); n != nil {
		lsReq.Notices = n
		defer s.trackNotice(n)()
	}
	// xollama-hook: council -- a placed call takes the council's pool and
	// window, and teaches the automatic pools nothing.
	if pool, n, nmin := placementFields(s.usedOpencoti, s.launch.config, req.Placement); pool != nil || n > 0 {
		if pool != nil {
			lsReq.PoolID = pool
		}
		lsReq.NumCtx, lsReq.NumCtxMin = n, nmin
		lsReq.NumCtxHold = s.ctxHoldFor(ctx, req.Placement, n)
		pooled = poolSource{}
	}
	if poolID != nil {
		// Already attached to a pool, so this request has nothing left to teach
		// us about the prefix: it is the prefix, shared.
		pooled = poolSource{}
	}

	// Handle format: pass JSON schema directly to llama-server, or use grammar
	if len(req.Format) > 0 {
		switch string(req.Format) {
		case `null`, `""`:
			// not set
		case `"json"`:
			lsReq.Grammar = grammarJSON
		default:
			if req.Format[0] == '{' {
				lsReq.JsonSchema = req.Format
			} else {
				return fmt.Errorf("invalid format: %q; expected \"json\" or a valid JSON Schema object", req.Format)
			}
		}
	}

	// A format on a thinking response applies after the closing string, which
	// only a grammar of our own can express, so a schema is converted first.
	if len(req.ThinkingClose) > 0 && (lsReq.Grammar != "" || lsReq.JsonSchema != nil) {
		if lsReq.Grammar == "" {
			grammar, err := s.schemaGrammar(ctx, lsReq.JsonSchema)
			if err != nil {
				return err
			}
			lsReq.Grammar, lsReq.JsonSchema = grammar, nil
		}
		lsReq.Grammar = thinkingGrammar(req.ThinkingClose, lsReq.Grammar)
	}

	// Convert media: replace Ollama's stable [img-N] markers with the per-process
	// llama-server media marker and package the matching payloads as base64.
	if len(req.Media) > 0 {
		promptStr := lsReq.Prompt.(string)
		var mediaData []string
		for _, media := range req.Media {
			marker := fmt.Sprintf("[img-%d]", media.ID)
			promptStr = strings.Replace(promptStr, marker, s.llamaServerMediaMarker(), 1)
			data, err := llamaServerMediaBytes(media.Data)
			if err != nil {
				return err
			}
			mediaData = append(mediaData, base64.StdEncoding.EncodeToString(data))
		}
		lsReq.Prompt = llamaServerMultimodalPrompt{
			PromptString:   promptStr,
			MultimodalData: mediaData,
		}
	}

	buffer := &bytes.Buffer{}
	enc := json.NewEncoder(buffer)
	enc.SetEscapeHTML(false)
	if err := enc.Encode(lsReq); err != nil {
		return fmt.Errorf("failed to marshal completion request: %v", err)
	}

	endpoint := fmt.Sprintf("http://127.0.0.1:%d/completion", s.port)
	// xollama-hook: launch-config — an engine with dynamic slots refuses a
	// request it cannot seat, with 429 and a Retry-After, rather than queueing
	// it. ollama's contract is that a busy server queues, so the wait happens
	// here. See docs/xollama/slots.mdx.
	res, err := s.postWaitingForAdmission(ctx, endpoint, buffer.Bytes())
	if err != nil {
		if errors.Is(err, context.Canceled) || errors.Is(err, context.DeadlineExceeded) {
			return err
		}
		if errors.Is(err, errNoAdmission) {
			return api.StatusError{StatusCode: http.StatusServiceUnavailable, ErrorMessage: err.Error()}
		}
		if refused := (*WindowRefusedError)(nil); errors.As(err, &refused) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusTooManyRequests, ErrorMessage: refused.Message}
		}
		if errors.Is(err, ErrNeverFits) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusBadRequest, ErrorMessage: err.Error()}
		}
		if errors.Is(err, ErrOwnerFull) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusInsufficientStorage, ErrorMessage: err.Error()}
		}
		slog.Error("llama-server completion error", "error", err)
		if msg := s.lastErrMsg(); msg != "" {
			return fmt.Errorf("model runner has unexpectedly stopped, this may be due to resource limitations or an internal error, check xollama server logs for details: %s", msg)
		}
		return errors.New("model runner has unexpectedly stopped, this may be due to resource limitations or an internal error, check xollama server logs for details")
	}
	defer res.Body.Close()

	if res.StatusCode >= 400 {
		bodyBytes, err := io.ReadAll(res.Body)
		if err != nil {
			return fmt.Errorf("failed reading llama-server error response: %w", err)
		}

		return api.StatusError{StatusCode: res.StatusCode, ErrorMessage: s.statusErrorMessage(bodyBytes)}
	}

	// Parse SSE stream from llama-server. Delay the final Done callback until
	// after the response body is closed because routes may tokenize from that
	// callback to build the final Generate context.
	scanner := bufio.NewScanner(res.Body)
	buf := make([]byte, 0, llamaServerStreamInitialBufferSize)
	scanner.Buffer(buf, llamaServerStreamMaxBufferSize)

	var repeat repeatGuard
	var evalCount int
	var finalResp CompletionResponse
	var hasFinalResp bool

	for scanner.Scan() {
		select {
		case <-ctx.Done():
			return ctx.Err()
		default:
			line := scanner.Bytes()
			if len(line) == 0 {
				continue
			}
			if bytes.HasPrefix(line, []byte(":")) {
				continue
			}

			evt, ok := bytes.CutPrefix(line, []byte("data: "))
			if !ok {
				evt = line
			}

			var lsResp llamaServerCompletionResponse
			if err := json.Unmarshal(evt, &lsResp); err != nil {
				return fmt.Errorf("error unmarshalling llama-server response: %v", err)
			}
			// xollama-hook: engine-stream-error — opencoti's error event ends
			// the completion as an error (llm/engine_stream_error.go).
			if err := s.streamFailed(evt); err != nil {
				return err
			}

			if lsResp.Content != "" {
				evalCount++
			}

			// A generation that has come apart repeats one short unit until
			// something stops it. Cut it off, and say so: the response is
			// already partly streamed, so it ends as a normal completion with
			// a reason the caller can act on.
			if repeat.observe(lsResp.Content) {
				slog.Warn("stopping generation, output repeated the same sequence past the limit",
					"period", repeat.period(), "bytes", repeatGuardBudgetBytes)
				if err := res.Body.Close(); err != nil {
					return fmt.Errorf("error closing llama-server response: %v", err)
				}
				fn(CompletionResponse{
					Done:       true,
					DoneReason: DoneReasonRepeat,
					EvalCount:  evalCount,
				})
				return nil
			}

			if (lsResp.Content != "" || lsResp.Notice != nil) && !lsResp.Stop { // xollama-hook: notices
				fn(CompletionResponse{
					Content:  lsResp.Content,
					Logprobs: convertLogprobs(lsResp.CompletionProbabilities, req.TopLogprobs > 0),
					Notice:   lsResp.Notice, // xollama-hook: notices
				})
			}

			if lsResp.Stop {
				doneReason := DoneReasonStop
				if lsResp.StopType == "limit" {
					doneReason = DoneReasonLength
				}

				finalResp = CompletionResponse{
					Content:               lsResp.Content,
					Done:                  true,
					DoneReason:            doneReason,
					PromptEvalCount:       lsResp.Timings.promptEvalCount(),
					PromptEvalCachedCount: lsResp.Timings.CacheN,
					PromptEvalDuration:    time.Duration(lsResp.Timings.PromptMS * float64(time.Millisecond)),
					EvalCount:             lsResp.Timings.PredictN,
					EvalDuration:          time.Duration(lsResp.Timings.PredictMS * float64(time.Millisecond)),
					NoticesPlanted:        lsResp.Timings.NoticesPlanted, // xollama-hook: notices
					Notice:                lsResp.Notice,                 // xollama-hook: notices
					Notices:               lsResp.Timings.Notices,        // xollama-hook: notices
				}
				hasFinalResp = true
			}
		}

		if hasFinalResp {
			break
		}
	}

	if hasFinalResp {
		for scanner.Scan() {
		}

		if err := scanner.Err(); err != nil {
			if err := llamaServerStreamLimitError("response", err); err != nil {
				return err
			}
			return fmt.Errorf("error reading llama-server response: %v", err)
		}

		if err := res.Body.Close(); err != nil {
			return fmt.Errorf("error closing llama-server response: %v", err)
		}

		fn(finalResp)
		return nil
	}

	if err := scanner.Err(); err != nil {
		if err := llamaServerStreamLimitError("response", err); err != nil {
			return err
		}
		if strings.Contains(err.Error(), "unexpected EOF") || strings.Contains(err.Error(), "forcibly closed") {
			s.Close()
			msg := s.lastErrMsg()
			if msg == "" {
				msg = err.Error()
			}
			return fmt.Errorf("an error was encountered while running the model: %s", msg)
		}
		return fmt.Errorf("error reading llama-server response: %v", err)
	}

	// xollama-hook: engine-stream-error — on opencoti a stream that ended
	// without its final event is an error; nil on stock llama.cpp.
	return s.streamUnfinished()
}

func llamaServerStreamLimitError(label string, err error) error {
	if !strings.Contains(err.Error(), "token too long") {
		return nil
	}

	return fmt.Errorf("llama-server %s stream event exceeded %d MB limit", label, llamaServerStreamMaxBufferSize/(1000*1000))
}

func (s *llamaServerRunner) statusErrorMessage(body []byte) string {
	errMsg := extractLlamaServerErrorMessage(body)
	if errMsg == "" {
		errMsg = strings.TrimSpace(string(body))
	}
	statusMsg := s.lastErrMsg()
	if statusMsg == "" {
		return errMsg
	}

	if IsOutOfMemoryMessage(statusMsg) && !strings.Contains(strings.ToLower(errMsg), strings.ToLower(statusMsg)) {
		return strings.TrimSpace(errMsg + "\n" + statusMsg)
	}

	return errMsg
}

// convertLogprobs converts llama-server's completion_probabilities to Ollama's Logprob format.
// includeTop controls whether top alternatives are included in the output.
func convertLogprobs(probs []llamaServerTokenProb, includeTop bool) []Logprob {
	if len(probs) == 0 {
		return nil
	}
	result := make([]Logprob, len(probs))
	for i, p := range probs {
		// llama-server uses "logprob" for log-probs mode, "prob" for sampling-probs mode
		logprob := p.Logprob
		if logprob == 0 && p.Prob != 0 {
			logprob = p.Prob // Use whichever is set
		}
		result[i] = Logprob{
			TokenLogprob: TokenLogprob{
				Token:   p.Token,
				Logprob: logprob,
			},
		}

		if !includeTop {
			continue
		}

		// Convert top logprobs (could be top_logprobs or top_probs depending on mode)
		topProbs := p.TopLogprobs
		if len(topProbs) == 0 {
			topProbs = p.TopProbs
		}
		for _, tp := range topProbs {
			tl := tp.Logprob
			if tl == 0 && tp.Prob != 0 {
				tl = tp.Prob
			}
			result[i].TopLogprobs = append(result[i].TopLogprobs, TokenLogprob{
				Token:   tp.Token,
				Logprob: tl,
			})
		}
	}
	return result
}

func (s *llamaServerRunner) ApplyChatTemplate(ctx context.Context, req ChatRequest) (string, error) {
	data, err := s.llamaServerChatRequest(req, false)
	if err != nil {
		return "", err
	}

	body, err := json.Marshal(data)
	if err != nil {
		return "", fmt.Errorf("failed to marshal chat template request: %v", err)
	}

	endpoint := fmt.Sprintf("http://127.0.0.1:%d/apply-template", s.port)
	serverReq, err := http.NewRequestWithContext(ctx, http.MethodPost, endpoint, bytes.NewReader(body))
	if err != nil {
		return "", fmt.Errorf("error creating chat template request: %v", err)
	}
	serverReq.Header.Set("Content-Type", "application/json")

	res, err := s.httpClient().Do(serverReq)
	if err != nil {
		if errors.Is(err, context.Canceled) {
			return "", err
		}
		return "", fmt.Errorf("llama-server apply-template error: %w", err)
	}
	defer res.Body.Close()

	bodyBytes, err := io.ReadAll(res.Body)
	if err != nil {
		return "", fmt.Errorf("failed reading llama-server template response: %w", err)
	}
	if res.StatusCode >= 400 {
		return "", api.StatusError{StatusCode: res.StatusCode, ErrorMessage: s.statusErrorMessage(bodyBytes)}
	}

	var lsResp llamaServerApplyTemplateResponse
	if err := json.Unmarshal(bodyBytes, &lsResp); err != nil {
		return "", fmt.Errorf("error unmarshalling llama-server template response: %v", err)
	}
	if lsResp.Error != nil {
		return "", fmt.Errorf("llama-server template error: %v", lsResp.Error)
	}

	return lsResp.Prompt, nil
}

func (s *llamaServerRunner) Chat(ctx context.Context, req ChatRequest, fn func(ChatResponse)) (err error) {
	slog.Debug("llama-server chat request", "messages", len(req.Messages), "tools", len(req.Tools))

	// xollama-hook: engine-session — see the note on Completion. On this path
	// the ENGINE renders the template, so the request itself is handed over and
	// the rendering is asked of the engine rather than reconstructed here.
	// Only a request that did NOT attach to a pool is worth learning from: one
	// that attached already has its prefix shared.
	var pooled poolSource
	// xollama-hook: council -- as on Completion, a placed call teaches the
	// automatic pools nothing: its prefix is the client's pool, not ours.
	placed := req.Placement != nil && (req.Placement.PoolID != nil || req.Placement.NumCtx > 0)
	if req.PoolID == nil && s.poolFor(req.PoolKey) == nil && !placed {
		chat := req
		pooled = poolSource{chat: &chat}
	}
	defer func() {
		if err == nil {
			s.capturePool(req.PoolKey, pooled)
		}
	}()

	if req.Options == nil {
		opts := api.DefaultOptions()
		req.Options = &opts
	}

	if err := s.sem.Acquire(ctx, 1); err != nil {
		if errors.Is(err, context.Canceled) {
			slog.Info("aborting chat request due to client closing the connection")
		}
		return err
	}
	defer s.sem.Release(1)

	req.Options.NumPredict = boundedNumPredict(req.Options.NumPredict, s.options.NumCtx)

	status, err := s.getServerStatusRetry(ctx)
	if err != nil {
		return err
	} else if status != ServerStatusReady {
		return fmt.Errorf("unexpected server status: %s", status)
	}

	lsReq, err := s.llamaServerChatRequest(req, true)
	if err != nil {
		return err
	}
	// xollama-hook: notices -- the chat path's copy.
	if n := s.noticesFor(ctx, req.Notices); n != nil {
		lsReq["notices"] = n
		defer s.trackNotice(n)()
	}
	// xollama-hook: context-window-unbooked -- beside the placed window.
	if n, ok := lsReq["num_ctx"].(int); ok {
		if hold := s.ctxHoldFor(ctx, req.Placement, n); hold != nil {
			lsReq["num_ctx_hold"] = *hold
		}
	}

	buffer := &bytes.Buffer{}
	enc := json.NewEncoder(buffer)
	enc.SetEscapeHTML(false)
	if err := enc.Encode(lsReq); err != nil {
		return fmt.Errorf("failed to marshal chat request: %v", err)
	}

	endpoint := fmt.Sprintf("http://127.0.0.1:%d/v1/chat/completions", s.port)
	// xollama-hook: launch-config — as on the completion path: an engine with
	// an admission gate refuses with 429 and Retry-After instead of queueing,
	// and a busy server queues. Council members and every native-template
	// chat come this way (bug-118).
	res, err := s.postWaitingForAdmission(ctx, endpoint, buffer.Bytes())
	if err != nil {
		if errors.Is(err, context.Canceled) {
			return err
		}
		if errors.Is(err, errNoAdmission) {
			return api.StatusError{StatusCode: http.StatusServiceUnavailable, ErrorMessage: err.Error()}
		}
		if refused := (*WindowRefusedError)(nil); errors.As(err, &refused) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusTooManyRequests, ErrorMessage: refused.Message}
		}
		if errors.Is(err, ErrNeverFits) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusBadRequest, ErrorMessage: err.Error()}
		}
		if errors.Is(err, ErrOwnerFull) { // xollama-hook: context-window
			return api.StatusError{StatusCode: http.StatusInsufficientStorage, ErrorMessage: err.Error()}
		}
		slog.Error("llama-server chat error", "error", err)
		if msg := s.lastErrMsg(); msg != "" {
			return fmt.Errorf("model runner has unexpectedly stopped, this may be due to resource limitations or an internal error, check xollama server logs for details: %s", msg)
		}
		return errors.New("model runner has unexpectedly stopped, this may be due to resource limitations or an internal error, check xollama server logs for details")
	}
	defer res.Body.Close()

	if res.StatusCode >= 400 {
		bodyBytes, err := io.ReadAll(res.Body)
		if err != nil {
			return fmt.Errorf("failed reading llama-server error response: %w", err)
		}

		return api.StatusError{StatusCode: res.StatusCode, ErrorMessage: s.statusErrorMessage(bodyBytes)}
	}

	scanner := bufio.NewScanner(res.Body)
	buf := make([]byte, 0, llamaServerStreamInitialBufferSize)
	scanner.Buffer(buf, llamaServerStreamMaxBufferSize)

	toolCalls := map[int]*llamaServerToolCallAccumulator{}
	var finalResp ChatResponse
	var hasFinalResp bool

	for scanner.Scan() {
		select {
		case <-ctx.Done():
			return ctx.Err()
		default:
			line := scanner.Bytes()
			if len(line) == 0 {
				continue
			}
			if bytes.HasPrefix(line, []byte(":")) {
				continue
			}

			evt, ok := bytes.CutPrefix(line, []byte("data: "))
			if !ok {
				evt = line
			}
			if bytes.Equal(evt, []byte("[DONE]")) {
				continue
			}

			var lsResp llamaServerChatResponse
			if err := json.Unmarshal(evt, &lsResp); err != nil {
				return fmt.Errorf("error unmarshalling llama-server chat response: %v", err)
			}
			if lsResp.Error != nil {
				return fmt.Errorf("llama-server chat error: %v", lsResp.Error)
			}
			if len(lsResp.Choices) == 0 {
				if lsResp.Notice != nil { // xollama-hook: notices
					fn(ChatResponse{Message: api.Message{Role: "assistant"}, Notice: lsResp.Notice})
				}
				continue
			}

			choice := lsResp.Choices[0]
			resp := ChatResponse{
				Message: api.Message{
					Role:     "assistant",
					Content:  choice.Delta.Content,
					Thinking: choice.Delta.ReasoningContent,
				},
				Logprobs: convertLogprobs(choice.Logprobs.Content, req.TopLogprobs > 0),
				Notice:   lsResp.Notice, // xollama-hook: notices
			}

			for _, tc := range choice.Delta.ToolCalls {
				acc := toolCalls[tc.Index]
				if acc == nil {
					acc = &llamaServerToolCallAccumulator{index: tc.Index}
					toolCalls[tc.Index] = acc
				}
				acc.id += tc.ID
				if tc.Function.Name != "" {
					acc.name += tc.Function.Name
				}
				acc.arguments += tc.Function.Arguments
			}

			if choice.FinishReason != nil {
				doneReason := DoneReasonStop
				if *choice.FinishReason == "length" {
					doneReason = DoneReasonLength
				}

				resp.Done = true
				resp.DoneReason = doneReason
				resp.PromptEvalCount = lsResp.Timings.promptEvalCount()
				resp.PromptEvalCachedCount = lsResp.Timings.CacheN
				resp.PromptEvalDuration = time.Duration(lsResp.Timings.PromptMS * float64(time.Millisecond))
				resp.EvalCount = lsResp.Timings.PredictN
				resp.EvalDuration = time.Duration(lsResp.Timings.PredictMS * float64(time.Millisecond))
				resp.NoticesPlanted = lsResp.Timings.NoticesPlanted // xollama-hook: notices
				resp.Notices = lsResp.Timings.Notices               // xollama-hook: notices
				toolCalls, err := accumulatedToolCalls(toolCalls)
				if err != nil {
					return err
				}
				resp.Message.ToolCalls = toolCalls
				finalResp = resp
				hasFinalResp = true
				break
			}

			if resp.Message.Content != "" || resp.Message.Thinking != "" || len(resp.Logprobs) > 0 || resp.Notice != nil { // xollama-hook: notices
				fn(resp)
			}
		}

		if hasFinalResp {
			break
		}
	}

	if hasFinalResp {
		for scanner.Scan() {
		}

		if err := scanner.Err(); err != nil {
			if err := llamaServerStreamLimitError("chat response", err); err != nil {
				return err
			}
			return fmt.Errorf("error reading llama-server chat response: %v", err)
		}

		if err := res.Body.Close(); err != nil {
			return fmt.Errorf("error closing llama-server chat response: %v", err)
		}

		fn(finalResp)
		return nil
	}

	if err := scanner.Err(); err != nil {
		if err := llamaServerStreamLimitError("chat response", err); err != nil {
			return err
		}
		if strings.Contains(err.Error(), "unexpected EOF") || strings.Contains(err.Error(), "forcibly closed") {
			s.Close()
			msg := s.lastErrMsg()
			if msg == "" {
				msg = err.Error()
			}
			return fmt.Errorf("an error was encountered while running the model: %s", msg)
		}
		return fmt.Errorf("error reading llama-server chat response: %v", err)
	}

	return nil
}

type llamaServerToolCallAccumulator struct {
	index     int
	id        string
	name      string
	arguments string
}

type llamaServerChatToolCall struct {
	ID       string `json:"id,omitempty"`
	Index    int    `json:"index"`
	Type     string `json:"type"`
	Function struct {
		Name      string `json:"name"`
		Arguments string `json:"arguments"`
	} `json:"function"`
}

func accumulatedToolCalls(accs map[int]*llamaServerToolCallAccumulator) ([]api.ToolCall, error) {
	if len(accs) == 0 {
		return nil, nil
	}

	maxIndex := 0
	for index := range accs {
		maxIndex = max(maxIndex, index)
	}

	toolCalls := make([]api.ToolCall, 0, len(accs))
	for index := 0; index <= maxIndex; index++ {
		acc := accs[index]
		if acc == nil {
			continue
		}

		var args api.ToolCallFunctionArguments
		if strings.TrimSpace(acc.arguments) != "" {
			if err := json.Unmarshal([]byte(acc.arguments), &args); err != nil {
				return nil, fmt.Errorf("llama-server returned invalid tool call arguments for %q: %w", acc.name, err)
			}
		}

		toolCalls = append(toolCalls, api.ToolCall{
			ID: acc.id,
			Function: api.ToolCallFunction{
				Index:     acc.index,
				Name:      acc.name,
				Arguments: args,
			},
		})
	}

	return toolCalls, nil
}

func (s *llamaServerRunner) llamaServerChatRequest(req ChatRequest, stream bool) (map[string]any, error) {
	if req.Options == nil {
		opts := api.DefaultOptions()
		req.Options = &opts
	}

	messages := make([]map[string]any, 0, len(req.Messages))
	for _, msg := range req.Messages {
		converted, err := llamaServerChatMessage(MessageFromAPI(msg))
		if err != nil {
			return nil, err
		}
		messages = append(messages, converted)
	}

	body := map[string]any{
		"messages":          messages,
		"stream":            stream,
		"cache_prompt":      true,
		"n_predict":         req.Options.NumPredict,
		"n_keep":            req.Options.NumKeep,
		"temperature":       req.Options.Temperature,
		"top_k":             req.Options.TopK,
		"top_p":             req.Options.TopP,
		"min_p":             req.Options.MinP,
		"stop":              req.Options.Stop,
		"repeat_penalty":    req.Options.RepeatPenalty,
		"repeat_last_n":     stockRepeatLastN(req.Options.RepeatLastN, s.options.NumCtx, s.usedOpencoti), // xollama-hook: repeat-last-n
		"frequency_penalty": req.Options.FrequencyPenalty,
		"presence_penalty":  req.Options.PresencePenalty,
		"typical_p":         req.Options.TypicalP,
		"seed":              req.Options.Seed,
	}

	// xollama-hook: engine-session — see docs/xollama/sessions.mdx. The chat
	// path owns its own body, so the fields have to be added here too; on any
	// engine without session affinity neither key appears.
	chatPool := req.PoolID
	if chatPool == nil {
		chatPool = s.poolFor(req.PoolKey)
	}
	if id, pool := sessionFieldsFor(s.usedOpencoti, s.launch.config, req.SessionID, chatPool); id != "" || pool != nil {
		if id != "" {
			body["session_id"] = id
		}
		if pool != nil {
			body["pool_id"] = *pool
		}
	}

	// xollama-hook: council -- the chat path's copy of the placement.
	if pool, n, nmin := placementFields(s.usedOpencoti, s.launch.config, req.Placement); pool != nil || n > 0 {
		if pool != nil {
			body["pool_id"] = *pool
		}
		if n > 0 {
			body["num_ctx"], body["num_ctx_min"] = n, nmin
		}
	}

	if len(req.Tools) > 0 {
		body["tools"] = req.Tools
	}
	if req.Logprobs {
		body["logprobs"] = true
		body["top_logprobs"] = max(req.TopLogprobs, 1)
	}
	if kwargs := llamaServerChatTemplateKwargs(req.Think); kwargs != nil {
		body["chat_template_kwargs"] = kwargs
	}
	// llama-server owns the chat template on this path, so it already knows the
	// thinking delimiters and only needs the budget.
	window := api.ThinkBudgetWindow(s.ContextLength(), req.Options.NumPredict)
	// Only think_budget bounds thinking. A level in think is the model's
	// control and went into the template kwargs above.
	budget := 0
	if req.Think == nil || req.Think.Bool() {
		budget = req.Options.ThinkBudget.Tokens(window)
	}
	if budget > 0 {
		body["thinking_budget_tokens"] = budget
		// llama-server reads this from the chat body too, and needs it present
		// to build the sequence it forces
		body["reasoning_budget_message"] = req.Options.ThinkBudgetMessage
	}
	if format, err := llamaServerChatResponseFormat(req.Format); err != nil {
		return nil, err
	} else if format != nil {
		body["response_format"] = format
	}

	return body, nil
}

func llamaServerChatTemplateKwargs(think *api.ThinkValue) map[string]any {
	if think == nil {
		return nil
	}

	kwargs := map[string]any{
		"enable_thinking": think.Bool(),
	}
	if think.IsString() {
		if effort := think.String(); effort != "" {
			kwargs["reasoning_effort"] = effort
		}
	}
	return kwargs
}

func llamaServerChatMessage(msg Message) (map[string]any, error) {
	converted := map[string]any{
		"role": msg.Role,
	}
	// Thinking has to reach the chat template, not just the client. A template
	// that replays an assistant think block reads `reasoning_content`, and the
	// Qwen-family templates gate that replay on the message being newer than
	// the last real user query -- which, in an agentic tool loop, is every
	// assistant turn since the task was set. Dropping the field here leaves
	// those blocks empty, so a model re-derives each turn what it already
	// worked out, and describes its own earlier turns as someone else's.
	if msg.Thinking != "" {
		converted["reasoning_content"] = msg.Thinking
	}
	if msg.ToolCallID != "" {
		converted["tool_call_id"] = msg.ToolCallID
	}
	if msg.ToolName != "" {
		converted["name"] = msg.ToolName
	}
	if len(msg.ToolCalls) > 0 {
		toolCalls, err := llamaServerChatToolCalls(msg.ToolCalls)
		if err != nil {
			return nil, err
		}
		converted["tool_calls"] = toolCalls
	}

	if len(msg.Media) == 0 {
		converted["content"] = msg.Content
		return converted, nil
	}

	parts := make([]map[string]any, 0, len(msg.Media)+1)
	if msg.Content != "" {
		parts = append(parts, map[string]any{
			"type": "text",
			"text": msg.Content,
		})
	}
	for _, media := range msg.Media {
		part, err := llamaServerChatMediaPart(media)
		if err != nil {
			return nil, err
		}
		parts = append(parts, part)
	}
	converted["content"] = parts
	return converted, nil
}

func llamaServerChatMediaPart(media MediaData) (map[string]any, error) {
	if format, ok := AudioFormat(media.Data); ok {
		return map[string]any{
			"type": "input_audio",
			"input_audio": map[string]any{
				"data":   base64.StdEncoding.EncodeToString(media.Data),
				"format": format,
			},
		}, nil
	}

	data, err := llamaServerMediaBytes(media.Data)
	if err != nil {
		return nil, err
	}
	mime := http.DetectContentType(data)
	if !strings.HasPrefix(mime, "image/") {
		mime = "image/jpeg"
	}
	return map[string]any{
		"type": "image_url",
		"image_url": map[string]any{
			"url": "data:" + mime + ";base64," + base64.StdEncoding.EncodeToString(data),
		},
	}, nil
}

func llamaServerMediaBytes(data []byte) ([]byte, error) {
	if http.DetectContentType(data) != "image/webp" {
		return data, nil
	}

	img, err := webp.Decode(bytes.NewReader(data))
	if err != nil {
		return nil, fmt.Errorf("decode WebP image: %w", err)
	}

	var buf bytes.Buffer
	if err := png.Encode(&buf, img); err != nil {
		return nil, fmt.Errorf("encode WebP image as PNG: %w", err)
	}
	return buf.Bytes(), nil
}

func llamaServerChatToolCalls(tcs []api.ToolCall) ([]llamaServerChatToolCall, error) {
	toolCalls := make([]llamaServerChatToolCall, len(tcs))
	for i, tc := range tcs {
		toolCalls[i].ID = tc.ID
		toolCalls[i].Index = tc.Function.Index
		toolCalls[i].Type = "function"
		toolCalls[i].Function.Name = tc.Function.Name

		args, err := json.Marshal(tc.Function.Arguments)
		if err != nil {
			return nil, fmt.Errorf("failed to marshal tool call arguments for %q: %w", tc.Function.Name, err)
		}
		toolCalls[i].Function.Arguments = string(args)
	}

	return toolCalls, nil
}

func llamaServerChatResponseFormat(format json.RawMessage) (map[string]any, error) {
	if len(format) == 0 {
		return nil, nil
	}

	switch string(format) {
	case `null`, `""`:
		return nil, nil
	case `"json"`:
		return map[string]any{"type": "json_object"}, nil
	default:
		if format[0] != '{' {
			return nil, fmt.Errorf("invalid format: %q; expected \"json\" or a valid JSON Schema object", format)
		}

		var schema map[string]any
		if err := json.Unmarshal(format, &schema); err != nil {
			return nil, fmt.Errorf("invalid format: %q; expected \"json\" or a valid JSON Schema object", format)
		}

		return map[string]any{
			"type": "json_schema",
			"json_schema": map[string]any{
				"name":   "schema",
				"schema": schema,
			},
		}, nil
	}
}

func (s *llamaServerRunner) Embedding(ctx context.Context, input string, media [][]byte) ([]float32, int, error) {
	if err := s.sem.Acquire(ctx, 1); err != nil {
		return nil, 0, err
	}
	defer s.sem.Release(1)

	var prompt any = input
	if len(media) > 0 {
		if len(s.launch.projectors) == 0 {
			return nil, 0, api.StatusError{StatusCode: http.StatusNotImplemented, ErrorMessage: "model does not support media embeddings"}
		}
		multimodal := llamaServerMultimodalPrompt{PromptString: input + strings.Repeat(s.llamaServerMediaMarker(), len(media))}
		for _, m := range media {
			data, err := llamaServerMediaBytes(m)
			if err != nil {
				return nil, 0, api.StatusError{StatusCode: http.StatusBadRequest, ErrorMessage: err.Error()}
			}
			multimodal.MultimodalData = append(multimodal.MultimodalData, base64.StdEncoding.EncodeToString(data))
		}
		prompt = multimodal
	}

	status, err := s.getServerStatusRetry(ctx)
	if err != nil {
		return nil, 0, err
	} else if status != ServerStatusReady {
		return nil, 0, fmt.Errorf("unexpected server status: %s", status)
	}

	// Use "input" field (not "content") to get the OAI-compatible response format
	// which includes tokens_evaluated for prompt token counting
	req := map[string]any{"input": prompt}
	if s.rawEmbeddings {
		req["embd_normalize"] = -1
	}
	data, err := json.Marshal(req)
	if err != nil {
		return nil, 0, fmt.Errorf("error marshaling embed data: %w", err)
	}

	// Use /v1/embeddings (OAI-compatible) to get tokens_evaluated in the response
	r, err := http.NewRequestWithContext(ctx, http.MethodPost, fmt.Sprintf("http://127.0.0.1:%d/v1/embeddings", s.port), bytes.NewBuffer(data))
	if err != nil {
		return nil, 0, fmt.Errorf("error creating embed request: %w", err)
	}
	r.Header.Set("Content-Type", "application/json")

	resp, err := s.httpClient().Do(r)
	if err != nil {
		return nil, 0, fmt.Errorf("do embedding request: %w", err)
	}
	defer resp.Body.Close()

	body, err := io.ReadAll(resp.Body)
	if err != nil {
		return nil, 0, fmt.Errorf("error reading embed response: %w", err)
	}

	if resp.StatusCode >= 400 {
		statusCode, errMsg := normalizeEmbeddingError(resp.StatusCode, body)
		return nil, 0, api.StatusError{StatusCode: statusCode, ErrorMessage: errMsg}
	}

	// With "input" field, llama-server returns OAI-compatible format:
	//   {"data": [{"embedding": [0.1, ...], "tokens_evaluated": N}], "usage": {"prompt_tokens": N}}
	// With "content" field, it returns:
	//   [{"embedding": [[0.1, ...]], "index": 0}]
	var oaiResp struct {
		Data []struct {
			Embedding       json.RawMessage `json:"embedding"`
			TokensEvaluated int             `json:"tokens_evaluated"`
		} `json:"data"`
		Usage struct {
			PromptTokens int `json:"prompt_tokens"`
		} `json:"usage"`
	}
	if err := json.Unmarshal(body, &oaiResp); err == nil && len(oaiResp.Data) > 0 {
		var embedding []float32
		if err := json.Unmarshal(oaiResp.Data[0].Embedding, &embedding); err != nil {
			return nil, 0, fmt.Errorf("unmarshal embedding values: %w", err)
		}
		promptTokens := oaiResp.Usage.PromptTokens
		if promptTokens == 0 {
			promptTokens = oaiResp.Data[0].TokensEvaluated
		}
		return embedding, promptTokens, nil
	}

	// Fallback: non-OAI array format [{"embedding": [[0.1, ...]], "index": 0}]
	var results []struct {
		Embedding json.RawMessage `json:"embedding"`
	}
	if err := json.Unmarshal(body, &results); err != nil {
		return nil, 0, fmt.Errorf("unmarshal embedding response: %w", err)
	}
	if len(results) == 0 {
		return nil, 0, fmt.Errorf("empty embedding response")
	}

	var embedding []float32
	if err := json.Unmarshal(results[0].Embedding, &embedding); err != nil {
		var nested [][]float32
		if err2 := json.Unmarshal(results[0].Embedding, &nested); err2 != nil {
			return nil, 0, fmt.Errorf("unmarshal embedding values: %w (also tried nested: %w)", err, err2)
		}
		if len(nested) > 0 {
			embedding = nested[0]
		}
	}

	return embedding, 0, nil
}

func normalizeEmbeddingError(statusCode int, body []byte) (int, string) {
	raw := strings.TrimSpace(string(body))
	errMsg := extractLlamaServerErrorMessage(body)
	if errMsg == "" {
		errMsg = raw
	}

	if isEmbeddingInputLimitError(errMsg) || isEmbeddingInputLimitError(raw) {
		// 413 (Request Entity Too Large) distinguishes "input too long" from
		// other 400s so the server's truncate-and-retry path can tell a real
		// length problem apart from unrelated validation.
		return http.StatusRequestEntityTooLarge, "the input length exceeds the context length"
	}

	return statusCode, errMsg
}

func extractLlamaServerErrorMessage(body []byte) string {
	var resp struct {
		Error json.RawMessage `json:"error"`
	}
	if err := json.Unmarshal(body, &resp); err != nil || len(resp.Error) == 0 {
		return ""
	}

	var msg string
	if err := json.Unmarshal(resp.Error, &msg); err == nil {
		return strings.TrimSpace(msg)
	}

	var nested struct {
		Message string `json:"message"`
	}
	if err := json.Unmarshal(resp.Error, &nested); err == nil {
		return strings.TrimSpace(nested.Message)
	}

	return ""
}

const promptTooLongMessage = "the prompt is longer than the context length currently available to the model; shorten the prompt, adjust the context length in settings, or use a model with a longer context length"

func isEmbeddingInputLimitError(errMsg string) bool {
	msg := strings.ToLower(errMsg)
	return strings.Contains(msg, "too large") ||
		strings.Contains(msg, "context size") ||
		strings.Contains(msg, "context length") ||
		strings.Contains(msg, "physical batch size") ||
		strings.Contains(msg, "exceeds the available context")
}

func (s *llamaServerRunner) tokenize(ctx context.Context, content any, addSpecial bool) ([]int, error) {
	req := struct {
		Content    any  `json:"content"`
		AddSpecial bool `json:"add_special,omitempty"`
	}{
		Content:    content,
		AddSpecial: addSpecial,
	}

	data, err := json.Marshal(req)
	if err != nil {
		return nil, err
	}

	r, err := http.NewRequestWithContext(ctx, http.MethodPost, fmt.Sprintf("http://127.0.0.1:%d/tokenize", s.port), bytes.NewBuffer(data))
	if err != nil {
		return nil, err
	}
	r.Header.Set("Content-Type", "application/json")

	resp, err := s.httpClient().Do(r)
	if err != nil {
		return nil, err
	}
	defer resp.Body.Close()

	body, err := io.ReadAll(resp.Body)
	if err != nil {
		return nil, err
	}

	if resp.StatusCode >= 400 {
		return nil, fmt.Errorf("tokenize error: %s", body)
	}

	var result struct {
		Tokens []int `json:"tokens"`
	}
	if err := json.Unmarshal(body, &result); err != nil {
		return nil, err
	}

	return result.Tokens, nil
}

// Tokenize calls llama-server's /tokenize endpoint.
func (s *llamaServerRunner) Tokenize(ctx context.Context, content string) ([]int, error) {
	return s.tokenize(ctx, content, false)
}

// Detokenize calls llama-server's /detokenize endpoint.
func (s *llamaServerRunner) Detokenize(ctx context.Context, tokens []int) (string, error) {
	data, err := json.Marshal(map[string][]int{"tokens": tokens})
	if err != nil {
		return "", err
	}

	r, err := http.NewRequestWithContext(ctx, http.MethodPost, fmt.Sprintf("http://127.0.0.1:%d/detokenize", s.port), bytes.NewBuffer(data))
	if err != nil {
		return "", err
	}
	r.Header.Set("Content-Type", "application/json")

	resp, err := s.httpClient().Do(r)
	if err != nil {
		return "", err
	}
	defer resp.Body.Close()

	body, err := io.ReadAll(resp.Body)
	if err != nil {
		return "", err
	}

	if resp.StatusCode >= 400 {
		return "", fmt.Errorf("detokenize error: %s", body)
	}

	var result struct {
		Content string `json:"content"`
	}
	if err := json.Unmarshal(body, &result); err != nil {
		return "", err
	}

	return result.Content, nil
}

func (s *llamaServerRunner) Close() error {
	// xollama-hook: engine-session — pools are pinned so the engine's idle
	// sweep cannot drop one while xollama still holds its id, which makes
	// releasing them ours to do. Before stopProcess, while the engine is still
	// listening.
	s.releasePools()
	return errors.Join(s.stopProcess(), s.removeSplitDirs())
}

func (s *llamaServerRunner) stopProcess() error {
	if s.cmd != nil && s.cmd.Process != nil {
		if s.cmd.ProcessState != nil {
			return nil
		}
		slog.Debug("stopping llama-server", "pid", s.Pid())
		s.stopping.Store(true) // xollama-hook: engine-select
		if err := s.cmd.Process.Kill(); err != nil && !errors.Is(err, os.ErrProcessDone) {
			return err
		}
		if s.done != nil {
			slog.Debug("waiting for llama-server to exit", "pid", s.Pid())
			<-s.done
		}
		slog.Debug("llama-server stopped", "pid", s.Pid())
	}
	return nil
}

// GetDeviceInfos returns device info for GPUs used by this runner, with FreeMemory
// updated to reflect actual usage. Uses the minimum of:
//   - Our accounting: TotalMemory minus tracked VRAM allocations
//   - System-reported: free VRAM from llama-server at load time minus our allocations
//
// The min-of-two approach handles both our own usage (accurate) and external
// consumers (system-reported, may be optimistic on some platforms).
func (s *llamaServerRunner) GetDeviceInfos(ctx context.Context) []ml.DeviceInfo {
	if len(s.gpus) == 0 {
		return nil
	}
	s.memoryMu.RLock()
	defer s.memoryMu.RUnlock()

	infos := make([]ml.DeviceInfo, len(s.gpus))
	for i, gpu := range s.gpus {
		infos[i] = gpu
		used := s.vramByDevice[gpu.Name]

		// Our accounting: total minus what we allocated
		var accountedFree uint64
		if used < gpu.TotalMemory {
			accountedFree = gpu.TotalMemory - used
		}

		// System-reported: what the GPU said was free at load time, minus what
		// we've allocated since. This captures external consumers on platforms
		// where the driver reports accurately.
		systemFree := accountedFree // default to our accounting
		if sysFree, ok := s.systemFreeAtLoad[gpu.Name]; ok {
			if used < sysFree {
				systemFree = sysFree - used
			} else {
				systemFree = 0
			}
		}

		// Take the minimum — never optimistic
		infos[i].FreeMemory = min(accountedFree, systemFree)
	}
	return infos
}

// MemorySize returns total and GPU memory usage parsed from llama-server's
// post-load log output. Full model-layer offload is reported as 100% GPU.
func (s *llamaServerRunner) MemorySize() (total, vram uint64) {
	s.memoryMu.RLock()
	memTotal := s.memTotal
	memGPU := s.memGPU
	memModelFileBacked := s.memModelFileBacked
	memCPUMappedModel := s.memCPUMappedModel
	totalLayers := s.totalLayers
	gpuLayers := s.gpuLayers
	gpuLayerOverflow := s.gpuLayerOverflow
	s.memoryMu.RUnlock()

	if memTotal > 0 {
		total, vram = memTotal, memGPU
		// With mmap, llama-server reports each CPU_Mapped model buffer as the
		// file-offset span of its CPU-resident tensors. During partial offload
		// that span covers nearly the whole file (the first and last tensors
		// stay on CPU), re-counting weights already held in device buffers.
		// Only buffers that mirror the on-disk file can overlap this way;
		// repacked copies such as CPU_REPACK are separate real allocations and
		// must be left intact. Weights cannot exceed the model file on disk, so
		// trim that overlap from the mmap-backed (reclaimable page cache) portion.
		if memCPUMappedModel > 0 {
			if modelSize := modelFileSize(s.modelPath, s.metadata); modelSize > 0 && memModelFileBacked > modelSize {
				total -= min(memCPUMappedModel, memModelFileBacked-modelSize)
			}
		}
		if totalLayers > 0 && gpuLayers >= totalLayers && gpuLayerOverflow == 0 {
			total = vram
		}
		return total, vram
	}
	// Fallback: use model file size as a rough proxy
	slog.Debug("llama-server buffer sizes not available, falling back to file size estimate", "model", s.modelPath)
	if modelSize := modelFileSize(s.modelPath, s.metadata); modelSize > 0 {
		total = modelSize
		vram = total
	}
	return total, vram
}

// PredictServerVRAM estimates VRAM usage for a model without spawning llama-server.
// Uses model file size as a proxy for weights plus a rough KV cache estimate.
// This is intentionally conservative — it overestimates to avoid VRAM contention.
func PredictServerVRAM(modelPath string, f *gguf.Model, numCtx int) uint64 {
	weights := modelFileSize(modelPath, f)

	// KV cache: 2 (K+V) * layers * kv_heads * head_dim * context * 2 bytes (f16)
	layers := f.KV().BlockCount()
	kvHeads := f.KV().HeadCountKVMin()
	if kvHeads == 0 {
		kvHeads = 1
	}
	headDim := uint64(0)
	if f.KV().HeadCountMax() > 0 {
		headDim = f.KV().EmbeddingLength() / f.KV().HeadCountMax()
	}
	kvCache := 2 * layers * kvHeads * headDim * uint64(numCtx) * 2

	return weights + kvCache
}

// memoryParsingWriter wraps an io.Writer and parses llama-server log output
// for buffer size lines. It updates the runner's per-device VRAM tracking.
//
// Parsed line formats (all backends):
//
//	CUDA0 model buffer size =   852.89 MiB
//	CUDA0 KV buffer size =  1920.00 MiB
//	CUDA0 compute buffer size =   378.04 MiB
//	CPU_Mapped model buffer size =   308.23 MiB
//	CUDA_Host compute buffer size =   268.05 MiB
//	MTL0_Mapped model buffer size =  1918.35 MiB
//	ROCm0 model buffer size =  1918.35 MiB
type memoryParsingWriter struct {
	inner   io.Writer
	runner  *llamaServerRunner
	buffers map[memoryBufferKey]memoryBuffer

	// lastComponent is the component of the most recent buffer-size line.
	// A component that starts logging again after another one has reported is
	// re-stating its whole allocation, so its previous entries are dropped
	// first — see the comment in Write.
	lastComponent string

	// model is the file the engine last named in a model-loader line. A
	// drafter is a second model in the same process, and its load_tensors,
	// KV and compute lines carry the same component names as the target's.
	// Keyed by component alone they replaced the target's: on opencoti a
	// 13 GiB Gemma 4 with its assistant head was reported as 2.0 GB, the
	// head's own buffers (solidPC, c13 r2, 2026-10-15). Each model's lines
	// now count apart.
	model string
}

type memoryBufferKey struct {
	// model is the file the buffer belongs to (memoryParsingWriter.model).
	model     string
	component string
	backend   string
	kind      string
	// stream is "" for an unstreamed buffer. Each stream of one device is a
	// separate allocation, so it belongs in the key -- without it the streams
	// collide and only the last one is counted.
	stream string
}

type memoryBuffer struct {
	bytes uint64
}

// deviceFreeRegex matches per-device free VRAM reported at model load time:
//
//	using device CUDA0 (NVIDIA GeForce RTX 4060 Ti) (0000:01:00.0) - 15221 MiB free
//	using device MTL0 (Apple M5 Max) (unknown id) - 110100 MiB free
//	using device ROCm0 (AMD Radeon RX 6800) (0000:06:00.0) - 16196 MiB free
var deviceFreeRegex = regexp.MustCompile(`using device (\S+)\s+\(.*\)\s+-\s+(\d+)\s+MiB free`)

// bufferSizeRegex matches llama-server buffer size lines and captures the
// component so repeated fit/probe values can be replaced by the final load.
// xollama-hook: memory-scrape — see docs/features/engine-opencoti-llamafile.md
//
// A multi-slot server without --kv-unified prints its KV lines per stream:
//
//	llama_kv_cache:      CUDA0 KV buffer (stream 0) size =  3584.00 MiB
//
// and KVarN caches say "KVarN buffer" rather than "KV buffer". Both were
// invisible here, so a -np > 1 load silently under-counted its KV: no warning
// fired, because the model and compute lines still matched.
//
// Both shapes still have to be read. Dynamic slots do pass --kv-unified, under
// which the cells are one pool and the stream suffix goes away -- but that flag
// reaches only opencoti loads that raised their ceiling, so every other load
// still prints per stream. The stream group stays optional for that reason.
//
// KVarN precedes KV in the alternation: Go's regexp is leftmost-first, so "KV"
// would match the prefix of "KVarN" and then fail on the following " buffer".
// modelLoaderRegex is llama.cpp's line opening each model file it loads, the
// target's and then a drafter's.
var modelLoaderRegex = regexp.MustCompile(`llama_model_loader: loaded meta data with \d+ key-value pairs and \d+ tensors from (\S+)`)

var bufferSizeRegex = regexp.MustCompile(`(?m)(?:^|\n)[^\n:]*?([A-Za-z_][A-Za-z0-9_]*):\s+(\S+)\s+(model|KVarN|KV|compute|output|RS)\s+buffer(?:\s+\(stream\s+(\d+)\))?\s+size\s*=\s*([\d.]+)\s*MiB`)

var (
	offloadedLayersRegex      = regexp.MustCompile(`offloaded\s+(\d+)/(\d+)\s+layers to GPU`)
	fitOverflowingLayersRegex = regexp.MustCompile(`common_params_fit_impl:\s+-\s+.+:\s+\d+\s+layers\s+\(\s*(\d+)\s+overflowing\)`)
)

// isGPUBuffer returns true if the backend buffer name represents GPU memory.
// CPU, BLAS, and host-pinned buffers (*_Host) are not GPU memory.
// Device-mapped buffers (e.g., MTL0_Mapped) ARE GPU memory — they're model
// weights in device-accessible memory. Only CPU_Mapped is CPU memory.
func isGPUBuffer(name string) bool {
	if name == "CPU" || name == "BLAS" || strings.HasPrefix(name, "CPU_") {
		return false
	}
	if strings.HasSuffix(name, "_Host") {
		return false
	}
	return true
}

// deviceName returns the base device name for per-device VRAM tracking.
// Strips suffixes like _Mapped, _REPACK so that e.g. "MTL0_Mapped" is
// tracked under "MTL0" alongside "MTL0 KV buffer" and "MTL0 compute buffer".
func deviceName(backendName string) string {
	for _, suffix := range []string{"_Mapped", "_REPACK", "_Private"} {
		if strings.HasSuffix(backendName, suffix) {
			return strings.TrimSuffix(backendName, suffix)
		}
	}
	return backendName
}

func (w *memoryParsingWriter) Write(b []byte) (int, error) {
	if w.runner != nil {
		if len(b) > 0 && w.runner.loadTracking.Load() {
			w.runner.noteLoadActivity(time.Now())
		}

		func() {
			w.runner.memoryMu.Lock()
			defer w.runner.memoryMu.Unlock()

			if match := deviceFreeRegex.FindSubmatch(b); match != nil {
				devName := string(match[1])
				if mib, err := strconv.ParseUint(string(match[2]), 10, 64); err == nil {
					w.runner.systemFreeAtLoad[devName] = mib * 1024 * 1024
				}
			}
			for _, match := range offloadedLayersRegex.FindAllSubmatch(b, -1) {
				loaded, loadedErr := strconv.ParseUint(string(match[1]), 10, 64)
				total, totalErr := strconv.ParseUint(string(match[2]), 10, 64)
				if loadedErr == nil && totalErr == nil {
					w.runner.gpuLayers = loaded
					w.runner.totalLayers = total
				}
			}
			for _, match := range fitOverflowingLayersRegex.FindAllSubmatch(b, -1) {
				overflowing, err := strconv.ParseUint(string(match[1]), 10, 64)
				if err == nil && overflowing > 0 {
					w.runner.gpuLayerOverflow += int(overflowing)
				}
			}
			for _, line := range bytes.SplitAfter(b, []byte("\n")) {
				w.parseBufferLineLocked(line)
			}
		}()
	}
	return w.inner.Write(b)
}

// parseBufferLineLocked reads one line for the model it opens or a buffer it
// sizes. Line by line, so a loader line and the buffers after it in one write
// are taken in order.
func (w *memoryParsingWriter) parseBufferLineLocked(line []byte) {
	if match := modelLoaderRegex.FindSubmatch(line); match != nil {
		if model := string(match[1]); model != w.model {
			w.model = model
			w.lastComponent = ""
		}
		return
	}
	for _, match := range bufferSizeRegex.FindAllSubmatch(line, -1) {
		component := string(match[1])
		backendName := string(match[2])
		// KVarN is a KV cache under another name; count it as one.
		kind := string(match[3])
		if kind == "KVarN" {
			kind = "KV"
		}
		stream := string(match[4])
		if mib, err := strconv.ParseFloat(string(match[5]), 64); err == nil {
			if w.buffers == nil {
				w.buffers = make(map[memoryBufferKey]memoryBuffer)
			}
			// Per-key overwrite alone is not enough when a component
			// re-logs a *smaller* set of buffers than it did before.
			// An engine that revises an allocation plan — opencoti's
			// rolling-KV sizing converges over two passes, and the
			// first pass splits the KV cache across CUDA0 and
			// CUDA_Host while later passes keep it all on CUDA0 —
			// only restates the devices it still uses. The dropped
			// device's line is never superseded, so its bytes linger
			// and memTotal is overstated by the size of an allocation
			// that no longer exists.
			//
			// A component beginning a new run of lines is restating
			// its whole allocation, not adding to it, so drop what it
			// said last time first. Lines from one block are
			// contiguous, so this never discards a half-read block.
			if component != w.lastComponent {
				for key := range w.buffers {
					if key.component == component && key.model == w.model {
						delete(w.buffers, key)
					}
				}
				w.lastComponent = component
			}
			w.buffers[memoryBufferKey{
				model:     w.model,
				component: component,
				backend:   backendName,
				kind:      kind,
				stream:    stream,
			}] = memoryBuffer{bytes: uint64(mib * 1024 * 1024)}
			w.updateRunnerMemoryLocked()
		}
	}
}

func (w *memoryParsingWriter) updateRunnerMemoryLocked() {
	var total, gpu, modelFileBacked, cpuMappedModel uint64
	byDevice := make(map[string]uint64)

	for key, buffer := range w.buffers {
		total += buffer.bytes
		if key.kind == "model" {
			onGPU := isGPUBuffer(key.backend)
			mmapBacked := strings.HasSuffix(key.backend, "_Mapped")
			// Device copies and mmap views mirror the on-disk weights, so their
			// spans can overlap and double-count on partial offload. Repacked or
			// host-pinned CPU copies (e.g. CPU_REPACK) are separate real
			// allocations that never overlap the file, so keep them out of the base.
			if onGPU || mmapBacked {
				modelFileBacked += buffer.bytes
			}
			if !onGPU && mmapBacked {
				cpuMappedModel += buffer.bytes
			}
		}
		if isGPUBuffer(key.backend) {
			gpu += buffer.bytes
			byDevice[deviceName(key.backend)] += buffer.bytes
		}
	}

	w.runner.memTotal = total
	w.runner.memGPU = gpu
	w.runner.memModelFileBacked = modelFileBacked
	w.runner.memCPUMappedModel = cpuMappedModel
	w.runner.vramByDevice = byDevice
}

// VRAMByGPU returns the VRAM used by this runner on the specified device.
// The values are parsed from llama-server's buffer size log output during model load
// (model tensors + KV cache + compute buffers).
func (s *llamaServerRunner) VRAMByGPU(id ml.DeviceID) uint64 {
	s.memoryMu.RLock()
	defer s.memoryMu.RUnlock()

	// Map DeviceID to the log device name used by llama-server.
	// Discovery stores the device name (e.g., "CUDA0", "ROCm0", "MTL0") from
	// --list-devices stdout, which matches the buffer log prefix.
	for _, gpu := range s.gpus {
		if gpu.DeviceID == id {
			return s.vramByDevice[gpu.Name]
		}
	}
	return 0
}
