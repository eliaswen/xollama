package mediahub

import (
	"slices"

	"github.com/ollama/ollama/types/xollama"
)

// Entry is one media template the catalog offers: what it is, and the
// xollama.json media block it becomes, with hf.co references where the
// digests will go.
//
// The models and their settings are the ones SurfSense's desktop app ships
// and reviewed (surfsense_local/backend/scripts/local_manifest/entries.py at
// 666bbb07), plus the OuteTTS pair opencoti's b97 engine was tested with.
type Entry struct {
	ID          string
	Name        string
	Kind        string // image, stt, tts, video, or mix
	Family      string
	License     string
	Description string
	// Needs says what the engine must have for it, when b97 does not.
	Needs string
	// Template is the name the entry is published under on ollama.com, and
	// Published says it is there: xollama pull Template gets the same model
	// media create builds. The names are mannix/<family>:<size> (owner,
	// 2026-10-02); stock ollama pulls them but cannot run a media-only one.
	Template  string
	Published bool
	Media     xollama.Media
}

// Refs lists the entry's component references, in component order.
func (e Entry) Refs() []string {
	var out []string
	for _, c := range e.Media.Components() {
		if !slices.Contains(out, c.Digest) {
			out = append(out, c.Digest)
		}
	}
	return out
}

func f(v float64) *float64 { return &v }

const (
	qwen3_4B    = "hf.co/unsloth/Qwen3-4B-GGUF/Qwen3-4B-Q4_0.gguf"
	umt5        = "hf.co/city96/umt5-xxl-encoder-gguf/umt5-xxl-encoder-Q4_K_M.gguf"
	audioCppHub = "hf.co/audio-cpp/audio.cpp-gguf/"
	needsM7     = "opencoti M7"
)

// openAIVoices maps OpenAI's six voice names to each voice model's own.
var (
	kokoroVoices     = map[string]string{"alloy": "af_alloy", "echo": "am_echo", "fable": "bm_fable", "onyx": "am_onyx", "nova": "af_nova", "shimmer": "af_heart"}
	supertonicVoices = map[string]string{"alloy": "F1", "echo": "M1", "fable": "M2", "onyx": "M3", "nova": "F2", "shimmer": "F3"}
	kittenVoices     = map[string]string{"alloy": "Bella", "echo": "Jasper", "fable": "Hugo", "onyx": "Bruno", "nova": "Luna", "shimmer": "Rosie"}
)

func klein() *xollama.ImageMedia {
	return &xollama.ImageMedia{
		Model: "hf.co/leejet/FLUX.2-klein-4B-GGUF/flux-2-klein-4b-Q8_0.gguf",
		VAE:   "hf.co/Comfy-Org/vae-text-encorder-for-flux-klein-4b/split_files/vae/flux2-vae.safetensors",
		LLM:   qwen3_4B,
		// No edit mode: the engine decides by family. M7's auto edits FLUX.2
		// from reference images, and b97, which has no switch, edits as
		// img2img; stating one would keep the template off b97.
		Defaults: &xollama.ImageDefaults{
			Width: 1024, Height: 1024, Steps: 4, CFG: f(1), Sampler: "euler", OutputFormat: "png",
		},
	}
}

func whisper() *xollama.STTMedia {
	return &xollama.STTMedia{
		Model:    "hf.co/ggerganov/whisper.cpp/ggml-large-v3-turbo-q8_0.bin",
		Defaults: &xollama.STTDefaults{ResponseFormat: "json"},
	}
}

// whistle is Cactus Compute's 17 MB streaming transcriber. It needs an engine
// with the `whistle` architecture (opencoti c12); vad adds the Silero
// detector the engine was gated with.
func whistle(vad bool) *xollama.STTMedia {
	m := &xollama.STTMedia{
		Model:    "hf.co/ManniX-ITA/whistle-GGUF/whistle.gguf",
		Defaults: &xollama.STTDefaults{ResponseFormat: "json"},
	}
	if vad {
		m.VAD = "hf.co/ManniX-ITA/whistle-GGUF/ggml-silero-v6.2.0.bin"
	}
	return m
}

func kokoro() *xollama.TTSMedia {
	return &xollama.TTSMedia{
		Engine: "audiocpp", Model: audioCppHub + "Kokoro-82M-GGUF/kokoro-82m-q8_0.gguf",
		VoiceMap: kokoroVoices,
		Defaults: &xollama.TTSDefaults{Voice: "af_heart", ResponseFormat: "mp3"},
	}
}

func supertonic(file string) *xollama.TTSMedia {
	return &xollama.TTSMedia{
		Engine: "audiocpp", Model: audioCppHub + "Supertonic-3-GGUF/" + file,
		VoiceMap: supertonicVoices,
		Defaults: &xollama.TTSDefaults{Voice: "F1", ResponseFormat: "mp3"},
	}
}

// wan21 is Wan2.1 T2V 1.3B with the given weights and text encoder.
func wan21(model, encoder string) *xollama.VideoMedia {
	return &xollama.VideoMedia{
		Model:       model,
		VAE:         "hf.co/Comfy-Org/Wan_2.1_ComfyUI_repackaged/split_files/vae/wan_2.1_vae.safetensors",
		TextEncoder: encoder, Defaults: wanDefaults(640, 352, 16),
		MediaEngine: xollama.MediaEngine{ReserveMiB: wan21Reserve},
	}
}

// wan22 is Wan2.2 TI2V 5B with the given weights. It takes Wan2.2's own VAE,
// never 2.1's.
func wan22(model string) *xollama.VideoMedia {
	return &xollama.VideoMedia{
		Model:       model,
		VAE:         "hf.co/Comfy-Org/Wan_2.2_ComfyUI_Repackaged/split_files/vae/wan2.2_vae.safetensors",
		TextEncoder: umt5, Defaults: wanDefaults(640, 352, 24),
		MediaEngine: xollama.MediaEngine{ReserveMiB: wan22Reserve},
	}
}

func wanDefaults(width, height, fps int) *xollama.VideoDefaults {
	return &xollama.VideoDefaults{
		Width: width, Height: height, Frames: 33, FPS: fps, CFG: f(6), Sampler: "euler", FlowShift: f(3), OutputFormat: "mp4",
	}
}

// wan21Reserve is Wan2.1 1.3B's working memory at its template clip,
// 640x352x33: measured on an RTX 3090 with opencoti b105 (2026-10-02), the
// peak 17,044 MiB less 5.7 GiB after boot, about 11.3 GiB, rounded up. At
// 832x480 the VAE decode alone wants ~19 GB, more than a 24 GB card has
// beside the weights, so the template's clip is the smaller one.
const wan21Reserve = 12288

// wan22Reserve is Wan2.2 TI2V 5B's working memory at its template clip,
// 640x352x33: measured on an RTX PRO 6000 with opencoti b112 (2026-10-03),
// the peak less the components (Q4_K_M 20,773 - 8,104 MiB; Q8_0 22,687 -
// 10,013 MiB), about 12.4 GiB either way, rounded up. At 832x480x33 the peak
// is 29.3 GiB (Q4_K_M) and 31.2 GiB (Q8_0), more than a 24 GB card, so the
// template's clip is the smaller one, as for Wan2.1.
const wan22Reserve = 13312

var catalog = []Entry{
	{
		ID: "flux2-klein-4b", Template: "mannix/flux2-klein:4b", Published: true, Name: "FLUX.2 klein 4B", Kind: "image", Family: "FLUX.2", License: "apache-2.0",
		Description: "Generates and edits (reference images) in four steps, in the least memory.",
		Media:       xollama.Media{Image: klein()},
	},
	{
		ID: "z-image-turbo", Template: "mannix/z-image:turbo", Published: true, Name: "Z-Image Turbo", Kind: "image", Family: "Z-Image", License: "apache-2.0",
		Description: "Photographic detail in eight steps; shares klein's text encoder.",
		Media: xollama.Media{Image: &xollama.ImageMedia{
			Model:    "hf.co/leejet/Z-Image-Turbo-GGUF/z_image_turbo-Q4_0.gguf",
			VAE:      "hf.co/Comfy-Org/z_image_turbo/split_files/vae/ae.safetensors",
			LLM:      qwen3_4B, // edit by the engine's choice, img2img for Z-Image
			Defaults: &xollama.ImageDefaults{Width: 1024, Height: 1024, Steps: 8, CFG: f(1), OutputFormat: "png"},
		}},
	},
	{
		ID: "whisper-large-v3-turbo", Template: "mannix/whisper:large-v3-turbo", Published: true, Name: "Whisper large-v3 turbo", Kind: "stt", Family: "Whisper", License: "mit",
		Description: "Transcription in 99 languages, and translation to English.",
		Media:       xollama.Media{STT: whisper()},
	},
	{
		ID: "whistle", Template: "mannix/whistle:latest", Published: true, Name: "Whistle", Kind: "stt", Family: "Whistle", License: "apache-2.0",
		Description: "A 17 MB transcriber for English, German, French, Spanish, Italian, Dutch and Polish, with word times.",
		Needs:       "opencoti c12",
		Media:       xollama.Media{STT: whistle(false)},
	},
	{
		ID: "whistle-vad", Template: "mannix/whistle:vad", Published: true, Name: "Whistle with the Silero detector", Kind: "stt", Family: "Whistle", License: "apache-2.0, mit",
		Description: "Whistle behind Silero VAD v6.2.0: silence and noise give no text, and long audio is cut at pauses.",
		Needs:       "opencoti c12",
		Media:       xollama.Media{STT: whistle(true)},
	},
	{
		ID: "outetts-0.3-500m", Template: "mannix/outetts:0.3", Published: true, Name: "OuteTTS 0.3 500M", Kind: "tts", Family: "OuteTTS", License: "cc-by-sa-4.0",
		Description: "Speech with the WavTokenizer vocoder; the pair opencoti b97 was tested with.",
		Media: xollama.Media{TTS: &xollama.TTSMedia{
			Model: "hf.co/OuteAI/OuteTTS-0.3-500M-GGUF/OuteTTS-0.3-500M-Q8_0.gguf",
			// No response_format: b97 answers wav only, and M7 makes mp3 the
			// engine's own default, so the engine's default is right on both.
			Vocoder: "hf.co/ggml-org/WavTokenizer/WavTokenizer-Large-75-F16.gguf",
		}},
	},
	{
		ID: "kokoro-82m", Template: "mannix/kokoro:82m", Published: true, Name: "Kokoro 82M", Kind: "tts", Family: "Kokoro", License: "apache-2.0",
		Description: "46 natural voices in eight languages; SurfSense's default voice.",
		Needs:       needsM7, Media: xollama.Media{TTS: kokoro()},
	},
	{
		ID: "supertonic-3", Template: "mannix/supertonic:3", Published: true, Name: "Supertonic 3", Kind: "tts", Family: "Supertonic", License: "openrail",
		Description: "Ten voices, each in 31 languages, in the least memory.",
		Needs:       needsM7,
		Media:       xollama.Media{TTS: supertonic("supertonic-3-f16.gguf")},
	},
	{
		ID: "supertonic-3-q8_0", Template: "mannix/supertonic:3-q8_0", Published: true, Name: "Supertonic 3 (Q8_0)", Kind: "tts", Family: "Supertonic", License: "openrail",
		Description: "Supertonic 3 from its Q8_0 file, the one opencoti's M7 gate ran.",
		Needs:       needsM7,
		Media:       xollama.Media{TTS: supertonic("supertonic-3-q8_0.gguf")},
	},
	{
		ID: "kitten-tts-mini-0.8", Template: "mannix/kittentts:mini-0.8", Published: true, Name: "KittenTTS Mini 0.8", Kind: "tts", Family: "KittenTTS", License: "apache-2.0",
		Description: "Eight English voices.",
		Needs:       needsM7,
		Media: xollama.Media{TTS: &xollama.TTSMedia{
			Engine: "audiocpp", Model: audioCppHub + "KittenTTS-GGUF/kitten-tts-mini-0.8-orig.gguf",
			VoiceMap: kittenVoices,
			Defaults: &xollama.TTSDefaults{Voice: "Bella", ResponseFormat: "mp3"},
		}},
	},
	{
		ID: "wan2.1-t2v-1.3b", Template: "mannix/wan2.1:t2v-1.3b", Published: true, Name: "Wan2.1 T2V 1.3B", Kind: "video", Family: "Wan", License: "apache-2.0",
		Description: "Short clips from text, in the least memory.",
		Needs:       needsM7,
		Media:       xollama.Media{Video: wan21("hf.co/samuelchristlie/Wan2.1-T2V-1.3B-GGUF/Wan2.1-T2V-1.3B-Q8_0.gguf", umt5)},
	},
	{
		ID: "wan2.1-t2v-1.3b-fp16", Template: "mannix/wan2.1:t2v-1.3b-fp16", Published: true, Name: "Wan2.1 T2V 1.3B (fp16)", Kind: "video", Family: "Wan", License: "apache-2.0",
		Description: "Wan2.1 at full precision with the Q8_0 text encoder, the set opencoti's M7 gate ran.",
		Needs:       needsM7,
		Media: xollama.Media{Video: wan21(
			"hf.co/Comfy-Org/Wan_2.1_ComfyUI_repackaged/split_files/diffusion_models/wan2.1_t2v_1.3B_fp16.safetensors",
			"hf.co/city96/umt5-xxl-encoder-gguf/umt5-xxl-encoder-Q8_0.gguf")},
	},
	{
		ID: "wan2.2-ti2v-5b", Template: "mannix/wan2.2:ti2v-5b", Published: true, Name: "Wan2.2 TI2V 5B", Kind: "video", Family: "Wan", License: "apache-2.0",
		Description: "Clips from text or an image, at 24 frames a second.",
		Needs:       needsM7,
		Media:       xollama.Media{Video: wan22("hf.co/QuantStack/Wan2.2-TI2V-5B-GGUF/Wan2.2-TI2V-5B-Q4_K_M.gguf")},
	},
	{
		ID: "wan2.2-ti2v-5b-q8_0", Template: "mannix/wan2.2:ti2v-5b-q8_0", Published: true, Name: "Wan2.2 TI2V 5B (Q8_0)", Kind: "video", Family: "Wan", License: "apache-2.0",
		Description: "Wan2.2 TI2V 5B at Q8_0, for the most quality in 5.4 GB of weights.",
		Needs:       needsM7,
		Media:       xollama.Media{Video: wan22("hf.co/QuantStack/Wan2.2-TI2V-5B-GGUF/Wan2.2-TI2V-5B-Q8_0.gguf")},
	},
	{
		ID: "media-kit", Template: "mannix/media-kit:latest", Name: "Media kit", Kind: "mix", Family: "mix", License: "see components",
		Description: "FLUX.2 klein, Whisper turbo and Kokoro in one template: images, transcription and speech.",
		Needs:       needsM7,
		Media:       xollama.Media{Image: klein(), STT: whisper(), TTS: kokoro()},
	},
}

// Catalog returns every entry, each a copy the caller may change.
func Catalog() []Entry {
	out := make([]Entry, len(catalog))
	for i, e := range catalog {
		e.Media = *e.Media.Clone()
		out[i] = e
	}
	return out
}

// Find returns the entry with that id.
func Find(id string) (Entry, bool) {
	for _, e := range Catalog() {
		if e.ID == id {
			return e, true
		}
	}
	return Entry{}, false
}
