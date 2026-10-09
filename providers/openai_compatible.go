package providers

import (
	"context"
	"net/http"
	"net/url"
	"slices"
	"strings"
	"time"

	translate "github.com/kayiik/llm-translate"
	core "github.com/kayiik/llmgw-core"
)

// The gateway's default OpenAI-compatible timeout, and its bound on a
// catalog request.
const (
	openAICompatibleTimeout        = 300 * time.Second
	openAICompatibleCatalogTimeout = 10 * time.Second
)

// OpenAICompatibleConfig configures OpenAICompatible. BaseURL is required.
type OpenAICompatibleConfig struct {
	// BaseURL is the API base the operation paths follow, such as
	// https://api.openai.com/v1: /chat/completions, /responses and /models.
	BaseURL string
	// RegistryID is the registry entry the instance serves, as a Registry
	// names it. It selects the wire facts the gateway keys on an entry:
	// "openai" serves Responses for every model, and kilo_code, llm7,
	// ovh_ai_endpoints and pollinations list, without a key, only the
	// models anonymous access admits. Pollinations also takes Chat at
	// /v1/chat/completions and lists its catalog as a bare array. An alias
	// names its entry, and an id or alias Registry does not hold is kept as
	// given.
	RegistryID string
	// Registry resolves RegistryID, so that it may be an alias, or an entry
	// a product's overlay adds. Nil uses DefaultRegistry.
	Registry *Registry
	// Models returns the row a product's catalog holds for a model, as
	// ListModels returned it. A model whose row lists a Responses endpoint
	// serves Responses natively, and adaptation reads the row too. A model
	// the catalog lacks, or a nil Models, serves Chat Completions only,
	// unless RegistryID is "openai".
	Models func(model string) (core.ModelInfo, bool)
	// Headers are sent with every request, before a credential's own
	// headers. Neither replaces a header the transport sets, Authorization
	// included when the request has a key. A name that is not an HTTP
	// token, or a value with a control character, is refused, since Go's
	// transport would refuse to send it.
	Headers map[string]string
	// ForwardAllFields sends every Chat field a request sets to the Chat
	// endpoint. By default only the fields the gateway's transport forwards
	// are sent, and each other field is dropped and reported as an advisory
	// loss. Chat served over Responses carries only the fields the
	// gateway's Chat facade forwards, either way.
	ForwardAllFields bool
	// ForceAPISupport turns the gateway's API adaptation on for every Chat
	// request, as its provider-level force_api_support does: a model whose
	// row lists Responses but not Chat Completions is served over
	// Responses, and a model whose row lists reasoning efforts takes
	// max_tokens as max_completion_tokens. A request's boolean
	// force_api_support turns it on or off for that request.
	ForceAPISupport bool
	// Client performs inference. Nil uses a client that times out after
	// 300 seconds, the gateway's default.
	Client *http.Client
	// CatalogClient lists models. Nil uses a client that times out after
	// 10 seconds, the gateway's bound on catalog requests.
	CatalogClient *http.Client
	// Now stamps catalog discovery and reads Retry-After dates. Nil uses
	// time.Now.
	Now func() time.Time
}

// OpenAICompatible implements core.Provider for an upstream that speaks the
// OpenAI wire: the gateway's openai_compatible, openai and litellm
// instances, the anonymous catalogs the registry curates, and, through
// NewBedrock, Amazon Bedrock. It is the gateway's OpenAI transport without
// its OpenCode Zen and GitHub Copilot branches, which Zen and Copilot own.
//
// Chat Completions is native for every model, and Responses for a model
// whose catalog row lists it or that the openai registry entry serves. A
// translation.Adapter in front serves Messages over Chat, and Responses
// over Chat for the other models. The OpenAI audio surfaces are native for
// every model too, except on Bedrock: audio_transcriptions forwards the
// multipart upload unchanged to /audio/transcriptions, and audio_speech
// the speech JSON, with the request's model, to /audio/speech. Their
// answers are returned as sent, with the upstream's content type, and
// neither streams.
//
// A credential's API key, or else its token, is the bearer, without any
// "Bearer " prefix. No key, "free" or "none" sends no Authorization, and
// to an anonymous registry entry it is anonymous access, as "public" is.
// A credential's headers are sent too.
//
// Errors are *core.ProviderError. A refusal is classified by the gateway's
// status set with the upstream's Retry-After, and its message never quotes
// the upstream; a catalog failure's *CatalogError has a CatalogCode* code.
type OpenAICompatible struct {
	baseURL, registryID, label string
	models                     func(string) (core.ModelInfo, bool)
	headers                    extraHeaders
	forwardAll, adapt, audio   bool
	client, catalogClient      *http.Client
	now                        func() time.Time
}

var (
	_ core.Provider      = (*OpenAICompatible)(nil)
	_ core.WirePreserver = (*OpenAICompatible)(nil)
)

// NewOpenAICompatible returns an OpenAICompatible provider.
func NewOpenAICompatible(config OpenAICompatibleConfig) (*OpenAICompatible, error) {
	base := strings.TrimSpace(config.BaseURL)
	parsed, err := url.Parse(base)
	if err != nil || parsed.Scheme == "" || parsed.Host == "" {
		return nil, core.NewConfigurationError("the OpenAI-compatible base URL must be an absolute URL", err)
	}
	headers, err := newExtraHeaders("OpenAI-compatible", config.Headers)
	if err != nil {
		return nil, err
	}
	registry := config.Registry
	if registry == nil {
		registry = DefaultRegistry()
	}
	p := &OpenAICompatible{
		baseURL: strings.TrimRight(base, "/"), registryID: registry.CanonicalID(config.RegistryID),
		label: "OpenAI-compatible", models: config.Models, headers: headers,
		forwardAll: config.ForwardAllFields, adapt: config.ForceAPISupport, audio: true,
		client: config.Client, catalogClient: config.CatalogClient, now: config.Now,
	}
	if p.client == nil {
		p.client = &http.Client{Timeout: openAICompatibleTimeout}
	}
	if p.catalogClient == nil {
		p.catalogClient = &http.Client{Timeout: openAICompatibleCatalogTimeout}
	}
	if p.now == nil {
		p.now = time.Now
	}
	return p, nil
}

// NativeSurfaces reports Chat Completions for every model, Responses for a
// model the openai registry entry serves or whose row lists it, and the
// OpenAI audio surfaces, audio_transcriptions and audio_speech, for every
// model but Bedrock's. Whether the upstream serves a model on the audio
// endpoints is the upstream's to say, as it is for Chat. An OVHcloud AI
// Endpoints NVR voice serves audio_speech alone; see invokeNVR.
func (p *OpenAICompatible) NativeSurfaces(model string) []core.ModelSurface {
	if p.ovhNVR(model) {
		return []core.ModelSurface{core.ModelSurfaceAudioSpeech}
	}
	surfaces := []core.ModelSurface{core.ModelSurfaceChatCompletions}
	if p.responsesNative(model) {
		surfaces = append(surfaces, core.ModelSurfaceResponses)
	}
	if p.audio {
		surfaces = append(surfaces, core.ModelSurfaceAudioTranscriptions, core.ModelSurfaceAudioSpeech)
	}
	return surfaces
}

// PreservesWire implements core.WirePreserver. Responses is forwarded as
// sent, and so is Chat on the Chat endpoint: the model and stream flag are
// set, and fields the transport does not forward are dropped, but nothing
// is converted. Chat that the configured adaptation serves over Responses
// is converted, so it is not preserved; neither is a request whose own
// force_api_support turns adaptation on, which this declaration cannot see.
// The audio surfaces are forwarded as sent too, speech with the request's
// model, and their answers returned as sent. An NVR voice's speech is
// converted, so it is not preserved.
func (p *OpenAICompatible) PreservesWire(model string, surface core.ModelSurface) bool {
	if p.ovhNVR(model) {
		return false
	}
	switch surface {
	case core.ModelSurfaceResponses:
		return p.responsesNative(model)
	case core.ModelSurfaceChatCompletions:
		return !p.adaptsToResponses(model, p.adapt)
	case core.ModelSurfaceAudioTranscriptions, core.ModelSurfaceAudioSpeech:
		return p.audio
	}
	return false
}

// Invoke performs one Chat Completions, Responses or audio request and
// returns the upstream's answer as sent, or, for Chat that adaptation
// serves over Responses, the answer converted to Chat.
func (p *OpenAICompatible) Invoke(ctx context.Context, request core.Request) (core.Response, error) {
	if p.ovhNVR(request.Model) && request.Surface != core.ModelSurfaceAudioSpeech {
		return core.Response{}, &core.SurfaceError{Surface: request.Surface, Model: request.Model}
	}
	if p.servesAudio(request.Surface) {
		return p.invokeAudio(ctx, request)
	}
	call, err := p.prepare(request)
	if err != nil {
		return core.Response{}, err
	}
	if request.Surface == core.ModelSurfaceResponses {
		return p.invokeResponses(ctx, call)
	}
	return p.invokeChat(ctx, call)
}

// Stream performs one streaming Chat Completions or Responses request. Its
// frames are the upstream's SSE records as sent, [DONE] included; Chat that
// adaptation serves over Responses streams the complete answer as Chat
// chunks ending in [DONE], as the gateway does. The stream reports the
// request's losses through core.LossReporter. An audio surface does not
// stream: see audioStreamUnsupported.
func (p *OpenAICompatible) Stream(ctx context.Context, request core.Request) (core.StreamIter, error) {
	if p.ovhNVR(request.Model) && request.Surface != core.ModelSurfaceAudioSpeech {
		return nil, &core.SurfaceError{Surface: request.Surface, Model: request.Model}
	}
	if p.servesAudio(request.Surface) {
		return nil, p.audioStreamUnsupported(request.Surface)
	}
	call, err := p.prepare(request)
	if err != nil {
		return nil, err
	}
	if request.Surface == core.ModelSurfaceResponses {
		return p.streamResponses(ctx, call)
	}
	return p.streamChat(ctx, call)
}

// openAICompatibleCall is one operation checked and about to be shaped.
type openAICompatibleCall struct {
	model   string
	payload map[string]any
	access  openAIAccess
}

// prepare refuses what the provider cannot serve before anything is sent.
func (p *OpenAICompatible) prepare(request core.Request) (openAICompatibleCall, error) {
	if request.Surface != core.ModelSurfaceChatCompletions && (request.Surface != core.ModelSurfaceResponses || !p.responsesNative(request.Model)) {
		return openAICompatibleCall{}, &core.SurfaceError{Surface: request.Surface, Model: request.Model}
	}
	if strings.TrimSpace(request.Model) == "" {
		return openAICompatibleCall{}, openAIInvalid("an OpenAI-compatible request needs a model", nil)
	}
	access, err := p.access(request.Credential)
	if err != nil {
		return openAICompatibleCall{}, err
	}
	payload, err := openAIPayload(request)
	if err != nil {
		return openAICompatibleCall{}, err
	}
	return openAICompatibleCall{model: request.Model, payload: payload, access: access}, nil
}

func (p *OpenAICompatible) row(model string) (core.ModelInfo, bool) {
	if p.models == nil {
		return core.ModelInfo{}, false
	}
	return p.models(model)
}

// responsesNative reports Responses served natively, as the gateway
// decides: for every model of the openai registry entry, and for a model
// whose row lists a Responses endpoint, its websocket form included.
func (p *OpenAICompatible) responsesNative(model string) bool {
	if p.registryID == "openai" {
		return true
	}
	row, ok := p.row(model)
	return ok && slices.ContainsFunc(row.SupportedAPIs, openAIResponsesEndpoint)
}

// adaptedRow returns the row adaptation reads for model, and nothing when
// adaptation is off, so that no catalog lookup is made for it.
func (p *OpenAICompatible) adaptedRow(model string, adapt bool) (core.ModelInfo, bool) {
	if !adapt {
		return core.ModelInfo{}, false
	}
	return p.row(model)
}

// adaptsToResponses reports Chat that adaptation serves over Responses: a
// model whose row lists Responses but not Chat Completions, as
// translate.PreferredEndpoint reads the row.
func (p *OpenAICompatible) adaptsToResponses(model string, adapt bool) bool {
	row, ok := p.adaptedRow(model, adapt)
	return ok && translate.PreferredEndpoint(row.SupportedAPIs) == "responses"
}

func openAIResponsesEndpoint(endpoint string) bool {
	switch strings.ToLower(strings.TrimSpace(endpoint)) {
	case "/responses", "/v1/responses", "ws:/responses":
		return true
	}
	return false
}
