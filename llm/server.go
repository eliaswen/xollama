package llm

import (
	"context"
	"encoding/json"
	"errors"
	"log/slog"
	"slices"
	"strings"
	"time"

	"github.com/ollama/ollama/api"
	"github.com/ollama/ollama/envconfig"
	"github.com/ollama/ollama/format"
	"github.com/ollama/ollama/fs/gguf"
	"github.com/ollama/ollama/ml"
	"github.com/ollama/ollama/types/xollama"
)

var ErrLoadRequiredFull = errors.New("unable to load full model on GPU")

type filteredEnv []string

func (e filteredEnv) LogValue() slog.Value {
	var attrs []slog.Attr
	for _, env := range e {
		if key, value, ok := strings.Cut(env, "="); ok {
			if filteredEnvLogKey(key) {
				attrs = append(attrs, slog.String(key, filteredEnvLogValue(key, value)))
			}
		}
	}
	return slog.GroupValue(attrs...)
}

func filteredEnvLogKey(key string) bool {
	return strings.HasPrefix(key, "CUDA_") ||
		strings.HasPrefix(key, "ROCR_") ||
		strings.HasPrefix(key, "ROCM_") ||
		strings.HasPrefix(key, "HIP_") ||
		strings.HasPrefix(key, "HSA_") ||
		strings.HasPrefix(key, "GGML_") ||
		slices.Contains([]string{
			"PATH",
			"LD_LIBRARY_PATH",
			"DYLD_LIBRARY_PATH",
		}, key)
}

func filteredEnvLogValue(key, value string) string {
	for _, token := range []string{"API", "KEY", "TOKEN", "SECRET", "PASSWORD", "PASS", "CREDENTIAL", "AUTH"} {
		if strings.Contains(strings.ToUpper(key), token) {
			return "[redacted]"
		}
	}
	return value
}

type LlamaServer interface {
	ModelPath() string
	Load(ctx context.Context, systemInfo ml.SystemInfo, gpus []ml.DeviceInfo, requireFull bool) ([]ml.DeviceID, error)
	Ping(ctx context.Context) error
	WaitUntilRunning(ctx context.Context) error
	Completion(ctx context.Context, req CompletionRequest, fn func(CompletionResponse)) error
	Chat(ctx context.Context, req ChatRequest, fn func(ChatResponse)) error
	ApplyChatTemplate(ctx context.Context, req ChatRequest) (string, error)
	Embedding(ctx context.Context, input string, media [][]byte) ([]float32, int, error)
	Tokenize(ctx context.Context, content string) ([]int, error)
	Detokenize(ctx context.Context, tokens []int) (string, error)
	Close() error
	MemorySize() (total, vram uint64)
	VRAMByGPU(id ml.DeviceID) uint64
	Pid() int
	GetPort() int
	GetDeviceInfos(ctx context.Context) []ml.DeviceInfo
	HasExited() bool
	ContextLength() int
}

type LlamaServerConfig struct {
	DisableJinja         bool
	ContextShift         bool
	EnableMTP            bool
	ManifestDigest       string
	DraftModelPath       string
	DraftModelShardPaths []string
	// xollama-hook: model-config — the model's own xollama.json, nil for the
	// overwhelming majority of models. See docs/features/model-config.md.
	Xollama *xollama.Config

	// xollama-hook: drafter — the model itself says not to draft, which a
	// draft length of 0 alone cannot carry. See appendDraftOffArgs.
	DraftOff bool

	// xollama-hook: launch-config — this model must be served one sequence at
	// a time, because it is an embedding model or its architecture gives wrong
	// answers with several in flight (ollama/ollama#4165). Dynamic slots must
	// never grow past one here: that deny-list is a correctness decision, not
	// a capacity preference. See docs/xollama/slots.mdx.
	SingleSequenceOnly bool

	// xollama-hook: launch-config — the only reason for SingleSequenceOnly is
	// the ollama/ollama#4165 architecture deny-list. That list records what
	// stock llama.cpp gets wrong; opencoti serves those architectures with
	// several sequences in flight, so on opencoti the rule is lifted. An
	// embedding model never sets this. See singleSequence.
	SingleSequenceStockOnly bool

	// xollama-hook: council -- engine pool seats reserved for a council's pool
	// tree, over and above the automatic prefix pools. Zero for a model that
	// is not a council, or whose council does not use PolyKV.
	CouncilPools int
	// CouncilSlots is the live slots a council's widest parallel step needs
	// (llm/engine_council_slots.go); -c is not sized by it. Zero for a model
	// that is not a council.
	CouncilSlots int

	// xollama-hook: notices -- the --notice-templates file: the model's own
	// templates layer, else xollama's defaults. Empty starts the engine with
	// its built-in ladder.
	NoticeTemplatesPath string
}

// enginePin returns the engine this model says it needs, or "".
//
// xollama-hook: model-config
func (c LlamaServerConfig) enginePin() string {
	if c.Xollama == nil {
		return ""
	}
	return c.Xollama.Engine
}

// draftSpecTypeOverride returns the --spec-type the model pins, or "".
//
// xollama-hook: model-config
func (c LlamaServerConfig) draftSpecTypeOverride() string {
	if c.Xollama == nil || c.Xollama.Draft == nil {
		return ""
	}
	return c.Xollama.Draft.SpecType
}

// flashAttention returns the flash-attention mode this model pins, or "".
//
// xollama-hook: model-config
func (c LlamaServerConfig) flashAttention() string {
	if c.Xollama == nil {
		return ""
	}
	return c.Xollama.FlashAttention
}

// sessionAffinity reports whether this model asks for session affinity, and
// whether it said anything at all. A model that says nothing leaves the
// decision to XOLLAMA_SESSION_AFFINITY.
//
// xollama-hook: model-config
func (c LlamaServerConfig) sessionAffinity() (want, stated bool) {
	if c.Xollama == nil || c.Xollama.Session == nil || c.Xollama.Session.Affinity == nil {
		return false, false
	}
	return *c.Xollama.Session.Affinity, true
}

// sessionPool reports whether this model asks for a shared prefix pool, and
// whether it said anything at all.
//
// xollama-hook: model-config
func (c LlamaServerConfig) sessionPool() (want, stated bool) {
	if c.Xollama == nil || c.Xollama.Session == nil || c.Xollama.Session.Pool == nil {
		return false, false
	}
	return *c.Xollama.Session.Pool, true
}

// IsLlamaCPP reports whether the server is backed by the llama.cpp
// llama-server runner implementation.
func IsLlamaCPP(s LlamaServer) bool {
	_, ok := s.(*llamaServerRunner)
	return ok
}

// LoadModel loads GGUF model metadata from disk.
//
// It collects array values for arrays with a size less than or equal to
// maxArraySize. If maxArraySize is 0, the default value of 1024 is used. If
// the maxArraySize is negative, all arrays are collected.
func LoadModel(model string, maxArraySize int, shards ...string) (*gguf.Model, error) {
	return gguf.ReadModel(model, maxArraySize, shards...)
}

// NewLlamaServer creates a new llama-server runner for the given model.
// All GGUF models are served via the upstream llama-server subprocess.
func NewLlamaServer(systemInfo ml.SystemInfo, gpus []ml.DeviceInfo, modelPath string, f *gguf.Model, adapters, projectors []string, opts api.Options, numParallel int, config LlamaServerConfig) (LlamaServer, error) {
	slog.Info("using llama-server for model", "model", modelPath)

	// Verify the requested context size is <= the model training size
	//
	// xollama-hook: launch-config — unless dual chunk attention is on, which is
	// the one thing that makes a longer context safe. The clamp is otherwise
	// upstream's, warning and all. See docs/xollama/dca.mdx.
	trainCtx := f.KV().ContextLength()
	// xollama-hook: polykv-window — the whole-pool mark becomes the trained
	// context where the load runs PolyKV, upstream's minimum elsewhere.
	opts.NumCtx = ResolveWholePool(opts.NumCtx, int(trainCtx), WouldUseOpencoti(config, gpus) && enginePoolSeats(config, len(projectors) > 0) > 0)
	if opts.NumCtx > int(trainCtx) && trainCtx > 0 {
		if DCAUnlocksContext(config, gpus, f) {
			slog.Info("serving past the model's trained context with dual chunk attention",
				"num_ctx", opts.NumCtx, "n_ctx_train", trainCtx)
		} else {
			slog.Warn("requested context size too large for model", "num_ctx", opts.NumCtx, "n_ctx_train", trainCtx)
			opts.NumCtx = int(trainCtx)
		}
	}

	kvct := strings.ToLower(envconfig.KvCacheType())
	return NewLlamaServerRunner(gpus, modelPath, f, adapters, projectors, opts, numParallel, kvct, config)
}

// Server status types

type ServerStatus int

const (
	ServerStatusReady ServerStatus = iota
	ServerStatusNoSlotsAvailable
	ServerStatusLaunched
	ServerStatusLoadingModel
	ServerStatusNotResponding
	ServerStatusError
)

func (s ServerStatus) String() string {
	switch s {
	case ServerStatusReady:
		return "llm server ready"
	case ServerStatusNoSlotsAvailable:
		return "llm busy - no slots available"
	case ServerStatusLaunched:
		return "llm server launched"
	case ServerStatusLoadingModel:
		return "llm server loading model"
	case ServerStatusNotResponding:
		return "llm server not responding"
	default:
		return "llm server error"
	}
}

type ServerStatusResponse struct {
	Status   ServerStatus `json:"status"`
	Progress float32      `json:"progress"`
}

// Request/Response types

const (
	llamaServerStreamInitialBufferSize = 64 * 1024
	// llamaServerStreamMaxBufferSize bounds a single runner response stream line.
	llamaServerStreamMaxBufferSize = 8 * format.MegaByte
)

type MediaKind string

const (
	MediaKindUnknown MediaKind = ""
	MediaKindImage   MediaKind = "image"
	MediaKindAudio   MediaKind = "audio"
)

type MediaData struct {
	Data []byte `json:"data"`
	ID   int    `json:"id"`
	Kind MediaKind
}

type Message struct {
	Role       string
	Content    string
	Thinking   string
	Media      []MediaData
	ToolCalls  []api.ToolCall
	ToolName   string
	ToolCallID string
}

func MessageFromAPI(msg api.Message) Message {
	media := make([]MediaData, len(msg.Images))
	for i, data := range msg.Images {
		media[i] = NewMediaData(i, data)
	}

	return Message{
		Role:       msg.Role,
		Content:    msg.Content,
		Thinking:   msg.Thinking,
		Media:      media,
		ToolCalls:  msg.ToolCalls,
		ToolName:   msg.ToolName,
		ToolCallID: msg.ToolCallID,
	}
}

type CompletionRequest struct {
	Prompt  string
	Format  json.RawMessage
	Media   []MediaData
	Options *api.Options

	Shift           bool
	Truncate        bool
	PreservedTokens []string // parser tokens to render as text; ignored by non-llama-server runners
	ToolCallTag     string   // raw generic tool parser tag, if any
	LeadingBOS      string   // textual BOS emitted by Go rendering, if any
	// ThinkingClose holds the strings any of which ends the thinking the
	// response begins with, which Format leaves free; none when the response
	// starts in content.
	ThinkingClose []string

	// ThinkBudget caps the number of tokens the model may spend inside a
	// thinking block. Zero leaves thinking unrestricted. Enforcing it requires
	// the thinking delimiters below; runners without a reasoning-budget sampler
	// ignore all three.
	ThinkBudget        int
	ThinkBudgetMessage string
	ThinkingStartTag   string
	ThinkingEndTag     string

	// ThinkBudgetResetTag is the tag a tool call opens with, when the model has
	// a parser that names one. The budget is spent across the whole response
	// rather than per thinking block -- a model that closes each block just
	// short of its window and opens another is otherwise never cut -- and this
	// tag is what separates a model circling from a model making progress: the
	// thinking that produced a tool call is forgiven, and what follows starts
	// from a full budget again. Empty leaves the budget cumulative with nothing
	// to forgive it.
	ThinkBudgetResetTag string

	// Logprobs specifies whether to include log probabilities in the response
	Logprobs bool

	// TopLogprobs specifies the number of most likely alternative tokens to return (0-20)
	TopLogprobs int

	// xollama-hook: engine-session — see docs/xollama/sessions.mdx.
	//
	// SessionID names the conversation, so an engine with session affinity
	// returns it to the slot already holding its KV. PoolID attaches it to a
	// shared prefix pool the engine owns. Both are emitted only when the load
	// actually ran on an engine that has them; on stock llama.cpp nothing is
	// sent and the request body is upstream's, byte for byte.
	SessionID string
	PoolID    *int
	// PoolProbes are this request's prefix rendered against
	// llm.PoolProbeContents by whichever template produced Prompt. The pool has
	// to stop exactly where the shared template stops, and only the renderer
	// that made the prompt can say where that is; on this path that renderer is
	// ollama's and lives in the server package. Empty means no pool boundary
	// can be measured for this request.
	PoolProbes []string

	// PoolKey identifies the prefix this request would share with others --
	// the system prompt and tool names, not the conversation. When pooling is
	// on and a pool already holds this prefix, the request attaches to it; when
	// none does, the first such request creates one for the rest. An explicit
	// PoolID from the caller always wins.
	PoolKey string

	// xollama-hook: council -- a council member's place on the engine: the
	// pool the council built for it and, for the owner, the window it books.
	// Applied only where sessions exist (llm/engine_council.go); nil for every
	// request that is not a council's.
	Placement *Placement

	// xollama-hook: notices -- the client's `notices` object, sent only to an
	// engine that declares generation_notice_v1 (llm/engine_notice.go).
	Notices json.RawMessage
}

type ChatRequest struct {
	Messages []api.Message
	Tools    api.Tools
	Format   json.RawMessage
	Options  *api.Options
	Think    *api.ThinkValue
	Shift    bool

	Logprobs    bool
	TopLogprobs int

	// xollama-hook: engine-session — see docs/xollama/sessions.mdx.
	//
	// SessionID names the conversation, so an engine with session affinity
	// returns it to the slot already holding its KV. PoolID attaches it to a
	// shared prefix pool the engine owns. Both are emitted only when the load
	// actually ran on an engine that has them; on stock llama.cpp nothing is
	// sent and the request body is upstream's, byte for byte.
	SessionID string
	PoolID    *int
	// PoolKey identifies the prefix this request would share with others --
	// the system prompt and tool names, not the conversation. When pooling is
	// on and a pool already holds this prefix, the request attaches to it; when
	// none does, the first such request creates one for the rest. An explicit
	// PoolID from the caller always wins.
	PoolKey string

	// xollama-hook: council -- a council member's place on the engine: the
	// pool the council built for it and, for the owner, the window it books.
	// Applied only where sessions exist (llm/engine_council.go); nil for every
	// request that is not a council's.
	Placement *Placement

	// xollama-hook: notices -- as CompletionRequest.Notices.
	Notices json.RawMessage
}

type ChatResponse struct {
	Message               api.Message   `json:"message"`
	DoneReason            DoneReason    `json:"done_reason"`
	Done                  bool          `json:"done"`
	PromptEvalCount       int           `json:"prompt_eval_count"`
	PromptEvalCachedCount *int          `json:"prompt_eval_cached_count,omitempty"`
	PromptEvalDuration    time.Duration `json:"prompt_eval_duration"`
	EvalCount             int           `json:"eval_count"`
	EvalDuration          time.Duration `json:"eval_duration"`
	Logprobs              []Logprob     `json:"logprobs,omitempty"`
	// xollama-hook: notices -- the engine's timings.notices_planted.
	NoticesPlanted int `json:"notices_planted,omitempty"`
}

// DoneReason represents the reason why a completion response is done
type DoneReason int

const (
	DoneReasonStop DoneReason = iota
	DoneReasonLength
	DoneReasonConnectionClosed
	// DoneReasonRepeat is reported when a generation was stopped because it
	// had degenerated into repeating the same short sequence.
	DoneReasonRepeat
)

func (d DoneReason) String() string {
	switch d {
	case DoneReasonLength:
		return "length"
	case DoneReasonStop:
		return "stop"
	case DoneReasonRepeat:
		return "repeat"
	default:
		return ""
	}
}

// TokenLogprob represents log probability information for a single token alternative.
type TokenLogprob struct {
	Token   string  `json:"token"`
	Logprob float64 `json:"logprob"`
}

// Logprob contains log probability information for a generated token.
type Logprob struct {
	TokenLogprob
	TopLogprobs []TokenLogprob `json:"top_logprobs,omitempty"`
}

type CompletionResponse struct {
	Content               string        `json:"content"`
	DoneReason            DoneReason    `json:"done_reason"`
	Done                  bool          `json:"done"`
	PromptEvalCount       int           `json:"prompt_eval_count"`
	PromptEvalCachedCount *int          `json:"prompt_eval_cached_count,omitempty"`
	PromptEvalDuration    time.Duration `json:"prompt_eval_duration"`
	EvalCount             int           `json:"eval_count"`
	EvalDuration          time.Duration `json:"eval_duration"`

	// Logprobs contains log probability information if requested
	Logprobs []Logprob `json:"logprobs,omitempty"`

	// xollama-hook: notices -- the engine's timings.notices_planted.
	NoticesPlanted int `json:"notices_planted,omitempty"`
}
