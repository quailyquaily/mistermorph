package llmutil

import (
	"errors"
	"os"
	"path/filepath"
	"strings"
	"testing"
	"time"

	"github.com/quailyquaily/mistermorph/internal/llmconfig"
	"github.com/quailyquaily/mistermorph/internal/proaccount"
	codexProvider "github.com/quailyquaily/mistermorph/providers/codex"
	uniaiProvider "github.com/quailyquaily/mistermorph/providers/uniai"
	"github.com/spf13/viper"
)

type failingRuntimeConfigReader struct {
	err error
}

func (r failingRuntimeConfigReader) GetString(string) string {
	return ""
}

func (r failingRuntimeConfigReader) UnmarshalKey(string, any, ...viper.DecoderConfigOption) error {
	return r.err
}

func TestRuntimeValuesFromReaderReturnsDecodeError(t *testing.T) {
	wantErr := errors.New("decode failed")
	_, err := RuntimeValuesFromReader(failingRuntimeConfigReader{err: wantErr})
	if !errors.Is(err, wantErr) {
		t.Fatalf("RuntimeValuesFromReader() error = %v, want %v", err, wantErr)
	}
}

func TestRuntimeValuesFromReaderReturnsRouteParseError(t *testing.T) {
	v := viper.New()
	v.Set("llm.routes", map[string]any{
		"main_loop": 42,
	})
	_, err := RuntimeValuesFromReader(v)
	if err == nil {
		t.Fatal("RuntimeValuesFromReader() error = nil, want route parse error")
	}
	if !strings.Contains(err.Error(), "llm.routes") {
		t.Fatalf("RuntimeValuesFromReader() error = %v, want llm.routes path", err)
	}
}

func requireRuntimeValues(t *testing.T, reader ConfigReader) RuntimeValues {
	t.Helper()
	values, err := RuntimeValuesFromReader(reader)
	if err != nil {
		t.Fatalf("RuntimeValuesFromReader() error = %v", err)
	}
	return values
}

func TestEndpointForProviderWithValues_CloudflareDefaultEndpoint(t *testing.T) {
	values := RuntimeValues{Endpoint: "https://api.openai.com"}
	if got := EndpointForProviderWithValues("cloudflare", values); got != "" {
		t.Fatalf("EndpointForProviderWithValues() = %q, want empty", got)
	}
	values.Endpoint = "https://api.openai.com/v1"
	if got := EndpointForProviderWithValues("cloudflare", values); got != "" {
		t.Fatalf("EndpointForProviderWithValues() = %q, want empty", got)
	}
}

func TestEndpointForProviderWithValues_CloudflareCustomEndpoint(t *testing.T) {
	values := RuntimeValues{Endpoint: "https://gateway.ai.cloudflare.com/v1/acc/route"}
	if got := EndpointForProviderWithValues("cloudflare", values); got != values.Endpoint {
		t.Fatalf("EndpointForProviderWithValues() = %q, want %q", got, values.Endpoint)
	}
}

func TestAPIKeyForProviderWithValues_CloudflareFallback(t *testing.T) {
	values := RuntimeValues{
		APIKey:             "generic-key",
		CloudflareAPIToken: "cf-token",
	}
	if got := APIKeyForProviderWithValues("cloudflare", values); got != "cf-token" {
		t.Fatalf("APIKeyForProviderWithValues() = %q, want cf-token", got)
	}
	values.CloudflareAPIToken = ""
	if got := APIKeyForProviderWithValues("cloudflare", values); got != "generic-key" {
		t.Fatalf("APIKeyForProviderWithValues() = %q, want generic-key", got)
	}
}

func TestAPIKeyForProviderWithValues_MisterMorphProStore(t *testing.T) {
	stateDir := t.TempDir()
	if err := proaccount.WriteSession(stateDir, proaccount.StoredSession{
		SubscriptionAPIKey: "store-key",
	}); err != nil {
		t.Fatalf("WriteSession() error = %v", err)
	}

	values := RuntimeValues{
		InferenceProvider: InferenceProviderMisterMorphPro,
		FileStateDir:      stateDir,
	}
	if got := APIKeyForProviderWithValues("openai", values); got != "store-key" {
		t.Fatalf("APIKeyForProviderWithValues() = %q, want store-key", got)
	}

	values.APIKey = "explicit-key"
	if got := APIKeyForProviderWithValues("openai", values); got != "store-key" {
		t.Fatalf("APIKeyForProviderWithValues() = %q, want store-key", got)
	}

	values.FileStateDir = t.TempDir()
	if got := APIKeyForProviderWithValues("openai", values); got != "" {
		t.Fatalf("APIKeyForProviderWithValues() = %q, want empty without auth store", got)
	}
}

func TestRuntimeValuesFromReader_ReadsMisterMorphLLMAPIKeyFromEnv(t *testing.T) {
	t.Setenv("MISTER_MORPH_LLM_API_KEY", "env-llm-key")

	v := viper.New()
	v.SetEnvPrefix("MISTER_MORPH")
	v.SetEnvKeyReplacer(strings.NewReplacer("-", "_", ".", "_"))
	v.AutomaticEnv()

	values := requireRuntimeValues(t, v)
	if values.APIKey != "env-llm-key" {
		t.Fatalf("RuntimeValuesFromReader().APIKey = %q, want env-llm-key", values.APIKey)
	}

	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.ClientConfig.APIKey != "env-llm-key" {
		t.Fatalf("resolved api key = %q, want env-llm-key", resolved.ClientConfig.APIKey)
	}
}

func TestRuntimeValuesFromReader_UsesEnvWhenConfigOmitsLLMAPIKey(t *testing.T) {
	t.Setenv("MISTER_MORPH_LLM_API_KEY", "env-llm-key")

	v := viper.New()
	v.SetEnvPrefix("MISTER_MORPH")
	v.SetEnvKeyReplacer(strings.NewReplacer("-", "_", ".", "_"))
	v.AutomaticEnv()
	v.SetConfigType("yaml")
	if err := v.ReadConfig(strings.NewReader("llm:\n  provider: openai\n  model: gpt-5.2\n")); err != nil {
		t.Fatalf("ReadConfig() error = %v", err)
	}

	values := requireRuntimeValues(t, v)
	if values.APIKey != "env-llm-key" {
		t.Fatalf("RuntimeValuesFromReader().APIKey = %q, want env-llm-key", values.APIKey)
	}
}

func TestRuntimeValuesFromReader_ReadsLLMHeaders(t *testing.T) {
	v := viper.New()
	v.SetConfigType("yaml")
	if err := v.ReadConfig(strings.NewReader(`
llm:
  provider: openai_resp
  headers:
    "-X-ABC-TOKEN": "${ABC_TOKEN}"
    OpenAI-Organization: org_123
`)); err != nil {
		t.Fatalf("ReadConfig() error = %v", err)
	}

	values := requireRuntimeValues(t, v)
	if got := values.Headers["-x-abc-token"]; got != "${ABC_TOKEN}" {
		t.Fatalf("headers[-x-abc-token] = %q, want ${ABC_TOKEN}", got)
	}
	if got := values.Headers["openai-organization"]; got != "org_123" {
		t.Fatalf("headers[openai-organization] = %q, want org_123", got)
	}
}

func TestResolveRouteReadsContextWindowTokens(t *testing.T) {
	v := viper.New()
	v.SetConfigType("yaml")
	if err := v.ReadConfig(strings.NewReader(`
llm:
  provider: openai
  model: gpt-5.5
  context_window_tokens: 100000
  profiles:
    backup:
      model: gpt-5.4
      context_window_tokens: 200000
  routes:
    main_loop:
      profile: backup
`)); err != nil {
		t.Fatalf("ReadConfig() error = %v", err)
	}

	route, err := ResolveRoute(requireRuntimeValues(t, v), RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.ClientConfig.ContextWindowTokens != 200000 {
		t.Fatalf("context window = %d, want 200000", route.ClientConfig.ContextWindowTokens)
	}
}

func TestResolveRouteRejectsNegativeContextWindowTokens(t *testing.T) {
	values := RuntimeValues{
		Provider:         "openai",
		Model:            "gpt-5.5",
		ContextWindowRaw: "-1",
	}
	_, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err == nil {
		t.Fatalf("ResolveRoute() error = nil, want error")
	}
	if !strings.Contains(err.Error(), "llm.context_window_tokens") {
		t.Fatalf("ResolveRoute() error = %v, want field name", err)
	}
}

func TestRuntimeValuesFromReader_ReadsSharedImageConfig(t *testing.T) {
	v := viper.New()
	v.SetConfigType("yaml")
	if err := v.ReadConfig(strings.NewReader(`
llm:
  provider: openai
  api_key: chat-key
  image:
    request_timeout: 180s
    options:
      openai:
        quality: high
      gemini:
        aspect_ratio: "1:1"
`)); err != nil {
		t.Fatalf("ReadConfig() error = %v", err)
	}

	values := requireRuntimeValues(t, v)
	if values.ImageTimeoutRaw != "180s" {
		t.Fatalf("ImageTimeoutRaw = %q, want 180s", values.ImageTimeoutRaw)
	}
	if got := values.ImageOptions.OpenAI["quality"]; got != "high" {
		t.Fatalf("openai quality = %#v, want high", got)
	}
	if got := values.ImageOptions.Gemini["aspect_ratio"]; got != "1:1" {
		t.Fatalf("gemini aspect_ratio = %#v, want 1:1", got)
	}
}

func TestImageRouteValuesUsesTheRoutedProfile(t *testing.T) {
	v := viper.New()
	v.SetConfigType("yaml")
	if err := v.ReadConfig(strings.NewReader(`
llm:
  provider: openai
  api_key: chat-key
  model: gpt-5.5
  image:
    request_timeout: 45s
  profiles:
    painter:
      inference_provider: gemini
      api_key: gemini-key
      model: gemini-image
  routes:
    image: painter
`)); err != nil {
		t.Fatalf("ReadConfig() error = %v", err)
	}
	values := requireRuntimeValues(t, v)
	image, err := ImageRouteValues(values, values)
	if err != nil {
		t.Fatalf("ImageRouteValues() error = %v", err)
	}
	meta := ResolveImageClientMetadata(image)
	if meta.Provider != "gemini" || meta.Model != "gemini-image" {
		t.Fatalf("image metadata = %#v, want gemini/gemini-image", meta)
	}
	if image.APIKey != "gemini-key" {
		t.Fatalf("image api key = %q, want the profile's key", image.APIKey)
	}
	// Shared image settings stay available on the routed profile.
	if image.ImageTimeoutRaw != "45s" {
		t.Fatalf("ImageTimeoutRaw = %q, want 45s", image.ImageTimeoutRaw)
	}
}

func TestImageRouteValuesFollowsTheCurrentModelWithoutARoute(t *testing.T) {
	values := RuntimeValues{Provider: "openai", APIKey: "default-key", Model: "gpt-5.5"}
	current := RuntimeValues{Provider: "gemini", APIKey: "profile-key", Model: "gemini-2.5"}
	image, err := ImageRouteValues(values, current)
	if err != nil {
		t.Fatalf("ImageRouteValues() error = %v", err)
	}
	if image.Model != "gemini-2.5" || image.APIKey != "profile-key" {
		t.Fatalf("image values = %#v, want the current model", image)
	}
}

func TestImageRouteValuesRejectsCandidatesAndMissingProfiles(t *testing.T) {
	withCandidates := RuntimeValues{Routes: RoutesConfig{PurposeRoutes: PurposeRoutes{Image: RoutePolicyConfig{
		Candidates: []RouteCandidateConfig{{Profile: "a", Weight: 1}},
	}}}}
	if _, err := ImageRouteValues(withCandidates, withCandidates); err == nil || !strings.Contains(err.Error(), "llm.routes.image") {
		t.Fatalf("ImageRouteValues() error = %v, want an llm.routes.image error", err)
	}
	missing := RuntimeValues{Routes: RoutesConfig{PurposeRoutes: PurposeRoutes{Image: RoutePolicyConfig{Profile: "nope"}}}}
	var missingErr *MissingProfileError
	if _, err := ImageRouteValues(missing, missing); !errors.As(err, &missingErr) {
		t.Fatalf("ImageRouteValues() error = %v, want MissingProfileError", err)
	}
}

func TestRuntimeValuesWithClientConfigAppliesEffectiveLLMConfig(t *testing.T) {
	values := RuntimeValues{
		Provider:          "openai_codex",
		Endpoint:          "https://codex.example.test",
		APIKey:            "old-key",
		Model:             "gpt-5.5",
		RequestTimeoutRaw: "90s",
	}
	got := RuntimeValuesWithClientConfig(values, llmconfig.ClientConfig{
		Provider:       "openai",
		Endpoint:       "https://api.openai.com/v1",
		APIKey:         "image-key",
		Model:          "gpt-image-2",
		RequestTimeout: 2 * time.Minute,
	})
	if got.Provider != "openai" || got.APIKey != "image-key" || got.Model != "gpt-image-2" {
		t.Fatalf("effective values = %#v", got)
	}
	if got.RequestTimeoutRaw != "2m0s" {
		t.Fatalf("RequestTimeoutRaw = %q, want 2m0s", got.RequestTimeoutRaw)
	}
}

func TestNormalizeImageProviderForUniaiMapsChatOnlyOpenAIProviders(t *testing.T) {
	for _, provider := range []string{"openai_codex", "openai_resp"} {
		t.Run(provider, func(t *testing.T) {
			if got := normalizeImageProviderForUniai(provider); got != "openai" {
				t.Fatalf("normalizeImageProviderForUniai(%q) = %q, want openai", provider, got)
			}
		})
	}
	if got := normalizeImageProviderForUniai("gemini"); got != "gemini" {
		t.Fatalf("normalizeImageProviderForUniai(gemini) = %q, want gemini", got)
	}
}

func TestResolveRoute_ExplicitInferenceProviderDerivesProviderEndpoint(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderMisterMorphPro,
		Provider:          "anthropic",
		Endpoint:          "https://wrong.example.test",
		Model:             "carrot/gpt",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "openai" {
		t.Fatalf("provider = %q, want openai", route.Values.Provider)
	}
	if route.Values.Endpoint != DefaultMisterMorphProEndpoint {
		t.Fatalf("endpoint = %q, want %q", route.Values.Endpoint, DefaultMisterMorphProEndpoint)
	}
	if route.ClientConfig.Provider != "openai" || route.ClientConfig.Endpoint != DefaultMisterMorphProEndpoint {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestResolveRoute_OpenAIInferenceProviderUsesResponsesProtocol(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderOpenAI,
		Provider:          "openai",
		Endpoint:          "https://wrong.example.test",
		Model:             "gpt-5.4",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "openai_resp" {
		t.Fatalf("provider = %q, want openai_resp", route.Values.Provider)
	}
	if route.Values.Endpoint != DefaultOpenAIEndpoint {
		t.Fatalf("endpoint = %q, want %q", route.Values.Endpoint, DefaultOpenAIEndpoint)
	}
	if route.ClientConfig.Provider != "openai_resp" || route.ClientConfig.Endpoint != DefaultOpenAIEndpoint {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestResolveRoute_OpenAICodexDefaultModel(t *testing.T) {
	for _, tt := range []struct {
		name  string
		model string
		want  string
	}{
		{name: "empty", want: "gpt-5.6-luna"},
		{name: "whitespace", model: "  ", want: "gpt-5.6-luna"},
		{name: "explicit", model: "gpt-5.6-sol", want: "gpt-5.6-sol"},
	} {
		t.Run(tt.name, func(t *testing.T) {
			route, err := ResolveRoute(RuntimeValues{
				InferenceProvider: InferenceProviderOpenAICodex,
				Model:             tt.model,
			}, RoutePurposeMainLoop)
			if err != nil {
				t.Fatal(err)
			}
			if got := route.ClientConfig.Model; got != tt.want {
				t.Fatalf("model = %q, want %q", got, tt.want)
			}
		})
	}
}

func TestResolveRoute_OpenAICodexSupportsOptionalCustomEndpoint(t *testing.T) {
	tests := []struct {
		name         string
		endpoint     string
		apiKey       string
		wantEndpoint string
		wantAPIKey   string
	}{
		{
			name:         "default",
			apiKey:       "ignored-with-default-endpoint",
			wantEndpoint: "https://chatgpt.com/backend-api/codex",
			wantAPIKey:   "ignored-with-default-endpoint",
		},
		{
			name:         "custom",
			endpoint:     "https://codex.example.test/api",
			apiKey:       "provider-key",
			wantEndpoint: "https://codex.example.test/api",
			wantAPIKey:   "provider-key",
		},
	}
	for _, tt := range tests {
		t.Run(tt.name, func(t *testing.T) {
			route, err := ResolveRoute(RuntimeValues{
				InferenceProvider: InferenceProviderOpenAICodex,
				Endpoint:          tt.endpoint,
				APIKey:            tt.apiKey,
				Model:             "gpt-5.5",
			}, RoutePurposeMainLoop)
			if err != nil {
				t.Fatalf("ResolveRoute() error = %v", err)
			}
			if route.ClientConfig.Provider != "openai_codex" {
				t.Fatalf("provider = %q, want openai_codex", route.ClientConfig.Provider)
			}
			if route.ClientConfig.Endpoint != tt.wantEndpoint {
				t.Fatalf("endpoint = %q, want %q", route.ClientConfig.Endpoint, tt.wantEndpoint)
			}
			if route.ClientConfig.APIKey != tt.wantAPIKey {
				t.Fatalf("api key = %q, want %q", route.ClientConfig.APIKey, tt.wantAPIKey)
			}
		})
	}
}

func TestResolveRoute_OpenAICodexProfileDoesNotInheritEndpoint(t *testing.T) {
	tests := []struct {
		name             string
		base             RuntimeValues
		profile          ProfileConfig
		wantEndpoint     string
		wantRouteProfile string
	}{
		{
			name: "switching provider uses Codex default",
			base: RuntimeValues{
				InferenceProvider: InferenceProviderOpenAI,
				Endpoint:          DefaultOpenAIEndpoint,
				Model:             "gpt-5.4",
			},
			profile: ProfileConfig{
				InferenceProvider: InferenceProviderOpenAICodex,
				Model:             "gpt-5.5",
			},
			wantEndpoint:     "https://chatgpt.com/backend-api/codex",
			wantRouteProfile: "codex",
		},
		{
			name: "Codex profile ignores top-level Codex custom endpoint",
			base: RuntimeValues{
				InferenceProvider: InferenceProviderOpenAICodex,
				Endpoint:          "https://codex.example.test/api",
				Model:             "gpt-5.5",
			},
			profile: ProfileConfig{
				InferenceProvider: InferenceProviderOpenAICodex,
				Model:             "gpt-5.5-mini",
			},
			wantEndpoint:     "https://chatgpt.com/backend-api/codex",
			wantRouteProfile: "codex",
		},
	}
	for _, tt := range tests {
		t.Run(tt.name, func(t *testing.T) {
			values := tt.base
			values.Profiles = map[string]ProfileConfig{"codex": tt.profile}
			values.Routes = RoutesConfig{PurposeRoutes: PurposeRoutes{
				MainLoop: RoutePolicyConfig{Profile: "codex"},
			}}

			route, err := ResolveRoute(values, RoutePurposeMainLoop)
			if err != nil {
				t.Fatalf("ResolveRoute() error = %v", err)
			}
			if route.Profile != tt.wantRouteProfile {
				t.Fatalf("profile = %q, want %q", route.Profile, tt.wantRouteProfile)
			}
			if route.ClientConfig.Endpoint != tt.wantEndpoint {
				t.Fatalf("endpoint = %q, want %q", route.ClientConfig.Endpoint, tt.wantEndpoint)
			}
		})
	}
}

func TestResolveRoute_XAIOAuthClearsAPIKeyAndPinsEndpoint(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: "xai_oauth",
		Provider:          "xai",
		Endpoint:          "https://attacker.example.test/v1",
		APIKey:            "must-not-be-used",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "xai_oauth" {
		t.Fatalf("provider = %q, want xai_oauth", route.Values.Provider)
	}
	if route.ClientConfig.Provider != "xai_oauth" {
		t.Fatalf("client provider = %q, want xai_oauth", route.ClientConfig.Provider)
	}
	if route.ClientConfig.Endpoint != "https://api.x.ai/v1" {
		t.Fatalf("endpoint = %q, want fixed xAI endpoint", route.ClientConfig.Endpoint)
	}
	if route.ClientConfig.APIKey != "" {
		t.Fatalf("api key = %q, want empty", route.ClientConfig.APIKey)
	}
	if route.ClientConfig.Model != "grok-4.5" {
		t.Fatalf("model = %q, want grok-4.5", route.ClientConfig.Model)
	}
}

func TestResolveRoute_ProfileCanSelectXAIOAuth(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderOpenAI,
		Provider:          "openai_resp",
		Endpoint:          DefaultOpenAIEndpoint,
		Model:             "gpt-5.4",
		Profiles: map[string]ProfileConfig{
			"grok": {
				InferenceProvider: "xai_oauth",
				Model:             "grok-4.5",
			},
		},
		Routes: RoutesConfig{PurposeRoutes: PurposeRoutes{
			MainLoop: RoutePolicyConfig{Profile: "grok"},
		}},
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Profile != "grok" || route.ClientConfig.Provider != "xai_oauth" ||
		route.ClientConfig.Model != "grok-4.5" {
		t.Fatalf("route = %+v", route)
	}
}

func TestInferInferenceProvider_MisterMorphPro(t *testing.T) {
	if got := InferInferenceProvider("openai", DefaultMisterMorphProEndpoint); got != InferenceProviderMisterMorphPro {
		t.Fatalf("InferInferenceProvider(openai, router) = %q, want %q", got, InferenceProviderMisterMorphPro)
	}
}

func TestInferInferenceProvider_OpenAIResponsesDefaultEndpoint(t *testing.T) {
	if got := InferInferenceProvider("openai_resp", DefaultOpenAIEndpoint); got != InferenceProviderOpenAI {
		t.Fatalf("InferInferenceProvider(openai_resp, openai) = %q, want %q", got, InferenceProviderOpenAI)
	}
	if got := InferInferenceProvider("openai_resp", "https://api.example.test/v1"); got != InferenceProviderOpenAIResponseCompatible {
		t.Fatalf("InferInferenceProvider(openai_resp, custom) = %q, want %q", got, InferenceProviderOpenAIResponseCompatible)
	}
}

func TestResolveRoute_OpenRouterInferenceProvider(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderOpenRouter,
		Provider:          "openai",
		Endpoint:          "https://wrong.example.test",
		Model:             "openai/gpt-5.4",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "openai" {
		t.Fatalf("provider = %q, want openai", route.Values.Provider)
	}
	if route.Values.Endpoint != DefaultOpenRouterEndpoint {
		t.Fatalf("endpoint = %q, want %q", route.Values.Endpoint, DefaultOpenRouterEndpoint)
	}
	if route.ClientConfig.Provider != "openai" || route.ClientConfig.Endpoint != DefaultOpenRouterEndpoint {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestInferInferenceProvider_OpenRouterEndpoint(t *testing.T) {
	if got := InferInferenceProvider("openai", DefaultOpenRouterEndpoint); got != InferenceProviderOpenRouter {
		t.Fatalf("InferInferenceProvider(openai, openrouter) = %q, want %q", got, InferenceProviderOpenRouter)
	}
}

func TestResolveRoute_GroqInferenceProvider(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderGroq,
		Provider:          "openai",
		Endpoint:          "https://wrong.example.test",
		Model:             "llama-3.3-70b-versatile",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "openai" {
		t.Fatalf("provider = %q, want openai", route.Values.Provider)
	}
	if route.Values.Endpoint != DefaultGroqEndpoint {
		t.Fatalf("endpoint = %q, want %q", route.Values.Endpoint, DefaultGroqEndpoint)
	}
	if route.ClientConfig.Provider != "openai" || route.ClientConfig.Endpoint != DefaultGroqEndpoint {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestResolveRoute_MetaInferenceProvider(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: "meta",
		Provider:          "openai",
		Endpoint:          "https://wrong.example.test",
		Model:             "muse-spark-1.1",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "meta" {
		t.Fatalf("provider = %q, want meta", route.Values.Provider)
	}
	if route.Values.Endpoint != "https://api.ai.meta.com/v1" {
		t.Fatalf("endpoint = %q, want Meta Model API", route.Values.Endpoint)
	}
	if route.ClientConfig.Provider != "meta" || route.ClientConfig.Endpoint != "https://api.ai.meta.com/v1" {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestInferInferenceProvider_MetaEndpoint(t *testing.T) {
	if got := InferInferenceProvider("meta", ""); got != "meta" {
		t.Fatalf("InferInferenceProvider(meta, empty) = %q, want meta", got)
	}
	if got := InferInferenceProvider("openai", "https://api.ai.meta.com/v1"); got != "meta" {
		t.Fatalf("InferInferenceProvider(openai, Meta) = %q, want meta", got)
	}
}

func TestResolveRoute_SakanaInferenceProvider(t *testing.T) {
	values := RuntimeValues{
		InferenceProvider: InferenceProviderSakana,
		Provider:          "openai",
		Endpoint:          "https://wrong.example.test",
		Model:             "fugu-ultra",
	}
	route, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if route.Values.Provider != "sakana" {
		t.Fatalf("provider = %q, want sakana", route.Values.Provider)
	}
	if route.Values.Endpoint != DefaultSakanaEndpoint {
		t.Fatalf("endpoint = %q, want %q", route.Values.Endpoint, DefaultSakanaEndpoint)
	}
	if route.ClientConfig.Provider != "sakana" || route.ClientConfig.Endpoint != DefaultSakanaEndpoint {
		t.Fatalf("client config = %#v", route.ClientConfig)
	}
}

func TestInferInferenceProvider_SakanaEndpoint(t *testing.T) {
	if got := InferInferenceProvider("sakana", ""); got != InferenceProviderSakana {
		t.Fatalf("InferInferenceProvider(sakana, empty) = %q, want %q", got, InferenceProviderSakana)
	}
	for _, provider := range []string{"openai", "openai_resp"} {
		t.Run(provider, func(t *testing.T) {
			if got := InferInferenceProvider(provider, DefaultSakanaEndpoint); got != InferenceProviderSakana {
				t.Fatalf("InferInferenceProvider(%q, sakana) = %q, want %q", provider, got, InferenceProviderSakana)
			}
		})
	}
}

func TestInferInferenceProvider_GroqEndpoint(t *testing.T) {
	if got := InferInferenceProvider("groq", ""); got != InferenceProviderGroq {
		t.Fatalf("InferInferenceProvider(groq, empty) = %q, want %q", got, InferenceProviderGroq)
	}
	if got := InferInferenceProvider("openai", DefaultGroqEndpoint); got != InferenceProviderGroq {
		t.Fatalf("InferInferenceProvider(openai, groq) = %q, want %q", got, InferenceProviderGroq)
	}
}

func TestImageEndpointForValuesDoesNotInheritCodexEndpoint(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai_codex",
		Endpoint: "https://chatgpt.com/backend-api/codex",
	}
	if got := imageEndpointForValues(values.Provider, normalizeImageProviderForUniai(values.Provider), values); got != "" {
		t.Fatalf("image endpoint = %q, want empty", got)
	}
}

func TestModelForProviderWithValues_AzureDeploymentFirst(t *testing.T) {
	values := RuntimeValues{
		Model:           "gpt-5.2",
		AzureDeployment: "gpt5-deploy",
	}
	if got := ModelForProviderWithValues("azure", values); got != "gpt5-deploy" {
		t.Fatalf("ModelForProviderWithValues() = %q, want gpt5-deploy", got)
	}
	values.AzureDeployment = ""
	if got := ModelForProviderWithValues("azure", values); got != "gpt-5.2" {
		t.Fatalf("ModelForProviderWithValues() = %q, want gpt-5.2", got)
	}
}

func TestClientFromConfigWithValues_InvalidToolsMode(t *testing.T) {
	_, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider:       "openai",
		Endpoint:       "https://api.openai.com",
		APIKey:         "k",
		Model:          "gpt-5.2",
		RequestTimeout: 10 * time.Second,
	}, RuntimeValues{
		ToolsEmulationMode: "invalid",
	})
	if err == nil {
		t.Fatalf("expected error for invalid tools emulation mode")
	}
	if !strings.Contains(err.Error(), "llm.tools_emulation_mode") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestClientFromConfigWithValues_InvalidTemperature(t *testing.T) {
	_, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider: "openai",
	}, RuntimeValues{
		TemperatureRaw: "abc",
	})
	if err == nil {
		t.Fatalf("expected error for invalid temperature")
	}
	if !strings.Contains(err.Error(), "llm.temperature") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestClientFromConfigWithValues_CodexIgnoresUnsupportedRuntimeOptions(t *testing.T) {
	client, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider: "openai_codex",
		Model:    "gpt-5.5",
	}, RuntimeValues{
		FileStateDir:       t.TempDir(),
		TemperatureRaw:     "abc",
		ReasoningBudgetRaw: "8k",
	})
	if err != nil {
		t.Fatalf("ClientFromConfigWithValues() error = %v", err)
	}
	if _, ok := client.(*uniaiProvider.Client); !ok {
		t.Fatalf("client type = %T, want *uniai.Client", client)
	}
}

func TestClientFromConfigWithValuesKeepsCodexAPIKeyCompatibilityClient(t *testing.T) {
	for _, endpoint := range []string{"", "https://example.test/v1"} {
		client, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
			Provider: "openai_codex",
			Endpoint: endpoint,
			APIKey:   "provider-key",
			Model:    "gpt-5.5",
		}, RuntimeValues{})
		if err != nil {
			t.Fatalf("ClientFromConfigWithValues(%q) error = %v", endpoint, err)
		}
		if _, ok := client.(*codexProvider.Client); !ok {
			t.Fatalf("client type for endpoint %q = %T, want *codex.Client", endpoint, client)
		}
	}
}

func TestClientFromConfigWithValuesBuildsXAIOAuthWithoutPricing(t *testing.T) {
	client, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider: "xai_oauth",
		Endpoint: "https://attacker.example.test/v1",
		APIKey:   "must-not-be-used",
		Model:    "grok-4.5",
	}, RuntimeValues{
		FileStateDir:       t.TempDir(),
		PricingFile:        filepath.Join(t.TempDir(), "missing-pricing.yaml"),
		ReasoningBudgetRaw: "invalid-but-ignored",
		TemperatureRaw:     "0.2",
	})
	if err != nil {
		t.Fatalf("ClientFromConfigWithValues() error = %v", err)
	}
	if _, ok := client.(*uniaiProvider.Client); !ok {
		t.Fatalf("client type = %T, want *uniai.Client", client)
	}
}

func TestClientFromConfigWithValues_InvalidReasoningEffort(t *testing.T) {
	_, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider: "openai",
	}, RuntimeValues{
		ReasoningEffortRaw: "extreme",
	})
	if err == nil {
		t.Fatalf("expected error for invalid reasoning effort")
	}
	if !strings.Contains(err.Error(), "llm.reasoning_effort") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestClientFromConfigWithValues_InvalidReasoningBudget(t *testing.T) {
	_, err := ClientFromConfigWithValues(llmconfig.ClientConfig{
		Provider: "openai",
	}, RuntimeValues{
		ReasoningBudgetRaw: "8k",
	})
	if err == nil {
		t.Fatalf("expected error for invalid reasoning budget")
	}
	if !strings.Contains(err.Error(), "llm.reasoning_budget_tokens") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestPricingCatalogFromValues_ResolvesRelativeToConfigPath(t *testing.T) {
	dir := t.TempDir()
	configPath := filepath.Join(dir, "config.yaml")
	pricingPath := filepath.Join(dir, "pricing.yaml")
	if err := os.WriteFile(pricingPath, []byte("version: uniai.pricing.v1\nchat:\n  - inference_provider: openai\n    model: gpt-5.4\n    input_usd_per_million: 1\n    output_usd_per_million: 2\n"), 0o644); err != nil {
		t.Fatalf("WriteFile(pricing.yaml) error = %v", err)
	}

	pricing, digest, err := LoadPricingCatalog(RuntimeValues{
		ConfigPath:  configPath,
		PricingFile: "./pricing.yaml",
	})
	if err != nil {
		t.Fatalf("LoadPricingCatalog() error = %v", err)
	}
	if pricing == nil || len(pricing.Chat) != 1 {
		t.Fatalf("pricing catalog = %#v, want one chat rule", pricing)
	}
	if strings.TrimSpace(digest) == "" {
		t.Fatalf("expected non-empty pricing digest")
	}
	if pricing.Chat[0].InferenceProvider != "openai" || pricing.Chat[0].Model != "gpt-5.4" {
		t.Fatalf("pricing rule = %#v", pricing.Chat[0])
	}
}

func TestPricingCatalogFromValues_MissingFileFallsBackToDefault(t *testing.T) {
	dir := t.TempDir()

	pricing, digest, err := LoadPricingCatalog(RuntimeValues{
		ConfigPath:  filepath.Join(dir, "config.yaml"),
		PricingFile: "./pricing.yaml",
	})
	if err != nil {
		t.Fatalf("LoadPricingCatalog() error = %v", err)
	}
	if pricing == nil {
		t.Fatalf("expected default pricing catalog")
	}
	if len(pricing.Chat) == 0 {
		t.Fatalf("expected default pricing catalog to include chat rules")
	}
	if strings.TrimSpace(digest) == "" {
		t.Fatalf("expected non-empty pricing digest")
	}
}

func TestPricingCatalogFromValues_EmptyPathFallsBackToDefault(t *testing.T) {
	pricing, digest, err := LoadPricingCatalog(RuntimeValues{})
	if err != nil {
		t.Fatalf("LoadPricingCatalog() error = %v", err)
	}
	if pricing == nil {
		t.Fatalf("expected default pricing catalog")
	}
	if len(pricing.Chat) == 0 {
		t.Fatalf("expected default pricing catalog to include chat rules")
	}
	if strings.TrimSpace(digest) == "" {
		t.Fatalf("expected non-empty pricing digest")
	}
}

func TestPricingCatalogFromValues_InvalidYAML(t *testing.T) {
	dir := t.TempDir()
	configPath := filepath.Join(dir, "config.yaml")
	pricingPath := filepath.Join(dir, "pricing.yaml")
	if err := os.WriteFile(pricingPath, []byte("version: ["), 0o644); err != nil {
		t.Fatalf("WriteFile(pricing.yaml) error = %v", err)
	}

	_, _, err := LoadPricingCatalog(RuntimeValues{
		ConfigPath:  configPath,
		PricingFile: "./pricing.yaml",
	})
	if err == nil {
		t.Fatalf("expected parse error for invalid pricing yaml")
	}
	if !strings.Contains(err.Error(), "llm.pricing_file") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestResolveRoute_DefaultMainLoop(t *testing.T) {
	values := RuntimeValues{
		Provider:          "openai",
		Endpoint:          "https://api.openai.com",
		APIKey:            "base-key",
		Model:             "gpt-5.2",
		RequestTimeoutRaw: "90s",
	}
	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.Profile != RouteProfileDefault {
		t.Fatalf("profile = %q, want default", resolved.Profile)
	}
	if resolved.ClientConfig.Model != "gpt-5.2" {
		t.Fatalf("model = %q, want gpt-5.2", resolved.ClientConfig.Model)
	}
	if resolved.ClientConfig.RequestTimeout != 90*time.Second {
		t.Fatalf("request timeout = %v, want 90s", resolved.ClientConfig.RequestTimeout)
	}
}

func TestResolveRoute_GlobalPurposeOverride(t *testing.T) {
	values := RuntimeValues{
		Provider:          "openai",
		Endpoint:          "https://api.openai.com",
		APIKey:            "base-key",
		Model:             "gpt-5.2",
		RequestTimeoutRaw: "90s",
		Profiles: map[string]ProfileConfig{
			"cheap": {
				Model: "gpt-4.1-mini",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				MainLoop: RoutePolicyConfig{Profile: "cheap"},
			},
		},
	}
	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.Profile != "cheap" {
		t.Fatalf("profile = %q, want cheap", resolved.Profile)
	}
	if resolved.ClientConfig.Model != "gpt-4.1-mini" {
		t.Fatalf("model = %q, want gpt-4.1-mini", resolved.ClientConfig.Model)
	}
}

func TestResolveRoute_NamedProfileDoesNotInheritTopLevelLLMFields(t *testing.T) {
	supportsImageParts := true
	values := RuntimeValues{
		InferenceProvider:  InferenceProviderAnthropic,
		Provider:           "anthropic",
		Endpoint:           DefaultAnthropicEndpoint,
		APIKey:             "base-key",
		Model:              "claude-base",
		SupportsImageParts: &supportsImageParts,
		ContextWindowRaw:   "200000",
		Headers:            map[string]string{"X-App-Name": "mistermorph", "X-Trace": "base"},
		CacheTTL:           "short",
		CacheKeyPrefix:     "base-cache",
		RequestTimeoutRaw:  "90s",
		ToolsEmulationMode: "force",
		TemperatureRaw:     "0.8",
		ReasoningEffortRaw: "high",
		ReasoningBudgetRaw: "4096",
		PricingFile:        "./pricing.yaml",
		ConfigPath:         "/config/config.yaml",
		FileStateDir:       "/state",
		ImageTimeoutRaw:    "45s",
		Profiles: map[string]ProfileConfig{
			"cheap": {
				InferenceProvider: InferenceProviderOpenAI,
				Model:             "gpt-4.1-mini",
				Headers:           map[string]string{"X-Trace": "cheap", "-X-ABC-TOKEN": "p1"},
				TemperatureRaw:    "0.2",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				Addressing: RoutePolicyConfig{Profile: "cheap"},
			},
		},
	}
	values.AzureDeployment = "base-deployment"
	values.BedrockAWSKey = "base-aws-key"
	values.BedrockAWSSecret = "base-aws-secret"
	values.BedrockAWSSessionToken = "base-session-token"
	values.BedrockAWSProfile = "base-profile"
	values.BedrockAWSRegion = "us-east-1"
	values.BedrockModelARN = "base-model-arn"
	values.CloudflareAccountID = "base-account"
	values.CloudflareAPIToken = "base-token"

	resolved, err := ResolveRoute(values, RoutePurposeAddressing)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.Values.InferenceProvider != InferenceProviderOpenAI || resolved.ClientConfig.Provider != "openai_resp" {
		t.Fatalf("provider = %q/%q, want openai/openai_resp", resolved.Values.InferenceProvider, resolved.ClientConfig.Provider)
	}
	if resolved.ClientConfig.Endpoint != DefaultOpenAIEndpoint {
		t.Fatalf("endpoint = %q, want OpenAI default", resolved.ClientConfig.Endpoint)
	}
	if resolved.ClientConfig.APIKey != "" {
		t.Fatalf("api key = %q, want empty", resolved.ClientConfig.APIKey)
	}
	if resolved.Values.TemperatureRaw != "0.2" {
		t.Fatalf("temperature raw = %q, want 0.2", resolved.Values.TemperatureRaw)
	}
	if _, ok := resolved.ClientConfig.Headers["X-App-Name"]; ok {
		t.Fatalf("headers = %#v, must not contain top-level X-App-Name", resolved.ClientConfig.Headers)
	}
	if got := resolved.ClientConfig.Headers["X-Trace"]; got != "cheap" {
		t.Fatalf("headers[X-Trace] = %q, want cheap", got)
	}
	if got := resolved.ClientConfig.Headers["-X-ABC-TOKEN"]; got != "p1" {
		t.Fatalf("headers[-X-ABC-TOKEN] = %q, want p1", got)
	}
	if len(resolved.Fallbacks) != 0 {
		t.Fatalf("fallbacks = %d, want 0", len(resolved.Fallbacks))
	}
	for name, value := range map[string]string{
		"context_window_tokens":     resolved.Values.ContextWindowRaw,
		"cache_ttl":                 resolved.Values.CacheTTL,
		"cache_key_prefix":          resolved.Values.CacheKeyPrefix,
		"request_timeout":           resolved.Values.RequestTimeoutRaw,
		"tools_emulation_mode":      resolved.Values.ToolsEmulationMode,
		"reasoning_effort":          resolved.Values.ReasoningEffortRaw,
		"reasoning_budget_tokens":   resolved.Values.ReasoningBudgetRaw,
		"azure.deployment":          resolved.Values.AzureDeployment,
		"bedrock.aws_key":           resolved.Values.BedrockAWSKey,
		"bedrock.aws_secret":        resolved.Values.BedrockAWSSecret,
		"bedrock.aws_session_token": resolved.Values.BedrockAWSSessionToken,
		"bedrock.aws_profile":       resolved.Values.BedrockAWSProfile,
		"bedrock.region":            resolved.Values.BedrockAWSRegion,
		"bedrock.model_arn":         resolved.Values.BedrockModelARN,
		"cloudflare.account_id":     resolved.Values.CloudflareAccountID,
		"cloudflare.api_token":      resolved.Values.CloudflareAPIToken,
	} {
		if value != "" {
			t.Errorf("%s = %q, want empty", name, value)
		}
	}
	if resolved.Values.SupportsImageParts != nil {
		t.Errorf("supports_image_parts = %v, want nil", *resolved.Values.SupportsImageParts)
	}
	if resolved.ClientConfig.RequestTimeout != 0 {
		t.Errorf("request timeout = %v, want zero", resolved.ClientConfig.RequestTimeout)
	}
	if resolved.Values.PricingFile != values.PricingFile || resolved.Values.ConfigPath != values.ConfigPath || resolved.Values.FileStateDir != values.FileStateDir {
		t.Errorf("shared runtime paths = %#v, want pricing/config/state preserved", resolved.Values)
	}
	if resolved.Values.ImageTimeoutRaw != values.ImageTimeoutRaw {
		t.Errorf("image runtime config = %#v, want shared image config preserved", resolved.Values)
	}
}

func TestResolveRoute_RejectsRemovedMemoryDraftPurpose(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
	}
	if _, err := ResolveRoute(values, "memory_draft"); err == nil {
		t.Fatal("ResolveRoute(memory_draft) error = nil, want unsupported purpose")
	}
}

func TestResolveRoute_ThinkPurpose(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
		Profiles: map[string]ProfileConfig{
			"reasoning": {
				Model:              "gpt-5.5",
				ReasoningEffortRaw: "medium",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				Think: RoutePolicyConfig{Profile: "reasoning"},
			},
		},
	}
	resolved, err := ResolveRoute(values, RoutePurposeThink)
	if err != nil {
		t.Fatalf("ResolveRoute(think) error = %v", err)
	}
	if resolved.Profile != "reasoning" {
		t.Fatalf("profile = %q, want reasoning", resolved.Profile)
	}
	if resolved.ClientConfig.Model != "gpt-5.5" {
		t.Fatalf("model = %q, want gpt-5.5", resolved.ClientConfig.Model)
	}

	resolved = ResolvedRouteWithReasoningEffort(resolved, ReasoningEffortXHigh)
	if resolved.Values.ReasoningEffortRaw != ReasoningEffortXHigh {
		t.Fatalf("reasoning effort = %q, want xhigh", resolved.Values.ReasoningEffortRaw)
	}
}

func TestResolveRoute_ThinkPurposeDefaultsToDefaultProfile(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
	}
	resolved, err := ResolveRoute(values, RoutePurposeThink)
	if err != nil {
		t.Fatalf("ResolveRoute(think) error = %v", err)
	}
	if resolved.Profile != RouteProfileDefault {
		t.Fatalf("profile = %q, want default", resolved.Profile)
	}
	if resolved.ClientConfig.Model != "gpt-5.2" {
		t.Fatalf("model = %q, want gpt-5.2", resolved.ClientConfig.Model)
	}
}

func TestResolveRoute_RouteLocalFallbackProfiles(t *testing.T) {
	values := RuntimeValues{
		Provider:          "openai",
		Endpoint:          "https://api.openai.com",
		APIKey:            "base-key",
		Model:             "gpt-5.2",
		RequestTimeoutRaw: "90s",
		Profiles: map[string]ProfileConfig{
			"cheap": {
				Model: "gpt-4.1-mini",
			},
			"reasoning": {
				Provider: "xai",
				Model:    "grok-4.1-fast-reasoning",
				APIKey:   "xai-key",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				MainLoop: RoutePolicyConfig{
					FallbackProfiles: []string{"cheap", "reasoning", "cheap"},
				},
			},
		},
	}
	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if got := len(resolved.Fallbacks); got != 2 {
		t.Fatalf("fallback count = %d, want 2", got)
	}
	if resolved.Fallbacks[0].Profile != "cheap" {
		t.Fatalf("fallback[0].profile = %q, want cheap", resolved.Fallbacks[0].Profile)
	}
	if resolved.Fallbacks[0].ClientConfig.Model != "gpt-4.1-mini" {
		t.Fatalf("fallback[0].model = %q, want gpt-4.1-mini", resolved.Fallbacks[0].ClientConfig.Model)
	}
	if resolved.Fallbacks[1].Profile != "reasoning" {
		t.Fatalf("fallback[1].profile = %q, want reasoning", resolved.Fallbacks[1].Profile)
	}
	if resolved.Fallbacks[1].ClientConfig.Provider != "xai" {
		t.Fatalf("fallback[1].provider = %q, want xai", resolved.Fallbacks[1].ClientConfig.Provider)
	}
}

func TestResolveRoute_ProfileAPIKeyOverride(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		APIKey:   "base-key",
		Model:    "gpt-5.2",
		Profiles: map[string]ProfileConfig{
			"reasoning": {
				Provider: "xai",
				Model:    "grok-4.1-fast-reasoning",
				APIKey:   "xai-key",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				PlanCreate: RoutePolicyConfig{Profile: "reasoning"},
			},
		},
	}
	resolved, err := ResolveRoute(values, RoutePurposePlanCreate)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.ClientConfig.Provider != "xai" {
		t.Fatalf("provider = %q, want xai", resolved.ClientConfig.Provider)
	}
	if resolved.ClientConfig.APIKey != "xai-key" {
		t.Fatalf("api key = %q, want xai-key", resolved.ClientConfig.APIKey)
	}
}

func TestResolveRoute_CloudflareAPIToken(t *testing.T) {
	values := RuntimeValues{
		Provider:            "cloudflare",
		Model:               "@cf/meta/llama-4",
		CloudflareAccountID: "acc-id",
		CloudflareAPIToken:  "cf-token",
	}
	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if resolved.ClientConfig.Provider != "cloudflare" {
		t.Fatalf("provider = %q, want cloudflare", resolved.ClientConfig.Provider)
	}
	if resolved.ClientConfig.APIKey != "cf-token" {
		t.Fatalf("api key = %q, want cf-token", resolved.ClientConfig.APIKey)
	}
}

func TestResolveRoute_MissingProfile(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				PlanCreate: RoutePolicyConfig{Profile: "reasoning"},
			},
		},
	}
	_, err := ResolveRoute(values, RoutePurposePlanCreate)
	if err == nil {
		t.Fatalf("expected missing profile error")
	}
	if !strings.Contains(err.Error(), "missing profile") {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestResolveRoute_InvalidRouteFallbackProfile(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				MainLoop: RoutePolicyConfig{
					FallbackProfiles: []string{"missing"},
				},
			},
		},
	}
	_, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err == nil {
		t.Fatalf("expected invalid fallback profile error")
	}
	if !strings.Contains(err.Error(), `missing profile "missing"`) {
		t.Fatalf("unexpected error: %v", err)
	}
}

func TestResolveRoute_FallbackDedupesPrimaryAndCandidates(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
		Profiles: map[string]ProfileConfig{
			"cheap": {
				Model: "gpt-4.1-mini",
			},
			"reasoning": {
				Model: "grok-4.1-fast-reasoning",
			},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				MainLoop: RoutePolicyConfig{
					Candidates: []RouteCandidateConfig{
						{Profile: "default", Weight: 1},
						{Profile: "cheap", Weight: 1},
					},
					FallbackProfiles: []string{"default", "cheap", "reasoning"},
				},
			},
		},
	}
	resolved, err := ResolveRoute(values, RoutePurposeMainLoop)
	if err != nil {
		t.Fatalf("ResolveRoute() error = %v", err)
	}
	if got := len(resolved.Fallbacks); got != 1 {
		t.Fatalf("fallback count = %d, want 1", got)
	}
	if resolved.Fallbacks[0].Profile != "reasoning" {
		t.Fatalf("fallback[0].profile = %q, want reasoning", resolved.Fallbacks[0].Profile)
	}
}

func TestSelectRouteCandidateReturnsStableConcreteRoute(t *testing.T) {
	route := ResolvedRoute{
		Purpose:  RoutePurposeMainLoop,
		Identity: "weighted-test",
		Candidates: []ResolvedCandidate{
			{Profile: "text", Weight: 1, ClientConfig: llmconfig.ClientConfig{Model: "text-model"}},
			{Profile: "vision", Weight: 1, ClientConfig: llmconfig.ClientConfig{Model: "vision-model"}},
		},
		Fallbacks: []ResolvedFallback{{Profile: "backup", ClientConfig: llmconfig.ClientConfig{Model: "backup-model"}}},
	}

	first := SelectRouteCandidate(route, "run-stable")
	second := SelectRouteCandidate(route, "run-stable")
	if first.Profile != second.Profile || first.ClientConfig.Model != second.ClientConfig.Model {
		t.Fatalf("same key selected different routes: first=%#v second=%#v", first, second)
	}
	if len(first.Candidates) != 0 {
		t.Fatalf("selected route candidates = %d, want 0", len(first.Candidates))
	}
	if len(first.Fallbacks) != 2 {
		t.Fatalf("selected route fallbacks = %d, want alternate candidate plus configured fallback", len(first.Fallbacks))
	}
	if first.Fallbacks[1].Profile != "backup" {
		t.Fatalf("final fallback = %q, want backup", first.Fallbacks[1].Profile)
	}
}

func TestRuntimeValuesFromReader_LoadProfilesAndRoutes(t *testing.T) {
	v := viper.New()
	v.Set("llm.provider", "openai")
	v.Set("llm.endpoint", "https://api.openai.com")
	v.Set("llm.api_key", "base-key")
	v.Set("llm.model", "gpt-5.2")
	v.Set("llm.cache_ttl", "short")
	v.Set("llm.cache_key_prefix", "base-cache")
	v.Set("llm.request_timeout", "90s")
	v.Set("llm.profiles", map[string]any{
		"cheap": map[string]any{
			"model":                "gpt-4.1-mini",
			"supports_image_parts": true,
			"temperature":          "0.2",
			"cache_ttl":            "long",
			"cache_key_prefix":     "cheap-cache",
		},
		"reasoning": map[string]any{
			"provider":         "xai",
			"model":            "grok-4.1-fast-reasoning",
			"api_key":          "xai-key",
			"reasoning_effort": "high",
		},
	})
	v.Set("llm.routes", map[string]any{
		"main_loop": map[string]any{
			"candidates": []map[string]any{
				{"profile": "default", "weight": 1},
				{"profile": "cheap", "weight": 1},
			},
			"fallback_profiles": []string{"reasoning"},
		},
		"addressing":  "cheap",
		"awareness":   "reasoning",
		"think":       "reasoning",
		"plan_create": "reasoning",
	})

	values := requireRuntimeValues(t, v)
	if values.Profiles["cheap"].Model != "gpt-4.1-mini" {
		t.Fatalf("cheap model = %q, want gpt-4.1-mini", values.Profiles["cheap"].Model)
	}
	if values.Profiles["cheap"].SupportsImageParts == nil || !*values.Profiles["cheap"].SupportsImageParts {
		t.Fatal("cheap supports_image_parts = false, want true")
	}
	cheapProfile, err := ResolveProfile(values, "cheap")
	if err != nil {
		t.Fatalf("ResolveProfile(cheap) error = %v", err)
	}
	if cheapProfile.Values.SupportsImageParts == nil || !*cheapProfile.Values.SupportsImageParts {
		t.Fatal("resolved cheap supports_image_parts = false, want true")
	}
	if values.CacheTTL != "short" {
		t.Fatalf("cache_ttl = %q, want short", values.CacheTTL)
	}
	if values.CacheKeyPrefix != "base-cache" {
		t.Fatalf("cache_key_prefix = %q, want base-cache", values.CacheKeyPrefix)
	}
	if values.Profiles["cheap"].CacheTTL != "long" {
		t.Fatalf("cheap cache_ttl = %q, want long", values.Profiles["cheap"].CacheTTL)
	}
	if values.Profiles["cheap"].CacheKeyPrefix != "cheap-cache" {
		t.Fatalf("cheap cache_key_prefix = %q, want cheap-cache", values.Profiles["cheap"].CacheKeyPrefix)
	}
	if values.Profiles["reasoning"].ReasoningEffortRaw != "high" {
		t.Fatalf("reasoning effort = %q, want high", values.Profiles["reasoning"].ReasoningEffortRaw)
	}
	if values.Profiles["reasoning"].APIKey != "xai-key" {
		t.Fatalf("reasoning api key = %q, want xai-key", values.Profiles["reasoning"].APIKey)
	}
	if values.Routes.Addressing.Profile != "cheap" {
		t.Fatalf("addressing route profile = %q, want cheap", values.Routes.Addressing.Profile)
	}
	if values.Routes.Awareness.Profile != "reasoning" {
		t.Fatalf("awareness route profile = %q, want reasoning", values.Routes.Awareness.Profile)
	}
	if values.Routes.Think.Profile != "reasoning" {
		t.Fatalf("think route profile = %q, want reasoning", values.Routes.Think.Profile)
	}
	if len(values.Routes.MainLoop.Candidates) != 2 {
		t.Fatalf("main loop candidate count = %d, want 2", len(values.Routes.MainLoop.Candidates))
	}
	if values.Routes.MainLoop.FallbackProfiles[0] != "reasoning" {
		t.Fatalf("main loop fallback = %#v, want [reasoning]", values.Routes.MainLoop.FallbackProfiles)
	}
}

func TestResolveRoute_AwarenessFallsBackToHeartbeatRoute(t *testing.T) {
	values := RuntimeValues{
		Provider: "openai",
		Model:    "gpt-5.2",
		Profiles: map[string]ProfileConfig{
			"cheap": {Model: "gpt-4.1-mini"},
		},
		Routes: RoutesConfig{
			PurposeRoutes: PurposeRoutes{
				Heartbeat: RoutePolicyConfig{Profile: "cheap"},
			},
		},
	}

	resolved, err := ResolveRoute(values, RoutePurposeAwareness)
	if err != nil {
		t.Fatalf("ResolveRoute(awareness) error = %v", err)
	}
	if resolved.Purpose != RoutePurposeAwareness {
		t.Fatalf("purpose = %q, want awareness", resolved.Purpose)
	}
	if resolved.Profile != "cheap" {
		t.Fatalf("profile = %q, want cheap", resolved.Profile)
	}
	if resolved.ClientConfig.Model != "gpt-4.1-mini" {
		t.Fatalf("model = %q, want gpt-4.1-mini", resolved.ClientConfig.Model)
	}
}

func TestResolveProfile_AppliesCacheTTLOverrides(t *testing.T) {
	values := RuntimeValues{
		Provider:       "openai_resp",
		Model:          "gpt-5.2",
		CacheTTL:       "short",
		CacheKeyPrefix: "base-cache",
		Profiles: map[string]ProfileConfig{
			"cheap": {
				Model:          "gpt-4.1-mini",
				CacheTTL:       "long",
				CacheKeyPrefix: "cheap-cache",
			},
		},
	}

	resolved, err := ResolveProfile(values, "cheap")
	if err != nil {
		t.Fatalf("ResolveProfile() error = %v", err)
	}
	if resolved.Values.CacheTTL != "long" {
		t.Fatalf("resolved cache_ttl = %q, want long", resolved.Values.CacheTTL)
	}
	if resolved.Values.CacheKeyPrefix != "cheap-cache" {
		t.Fatalf("resolved cache_key_prefix = %q, want cheap-cache", resolved.Values.CacheKeyPrefix)
	}
	if resolved.ClientConfig.Model != "gpt-4.1-mini" {
		t.Fatalf("resolved model = %q, want gpt-4.1-mini", resolved.ClientConfig.Model)
	}
}

func TestSystemPromptCacheControl(t *testing.T) {
	ctrl, err := SystemPromptCacheControl("short")
	if err != nil {
		t.Fatalf("SystemPromptCacheControl() error = %v", err)
	}
	if ctrl == nil || ctrl.TTL != "short" {
		t.Fatalf("cache control = %#v, want TTL short", ctrl)
	}
}

func TestSystemPromptCacheControlEmpty(t *testing.T) {
	ctrl, err := SystemPromptCacheControl("")
	if err != nil {
		t.Fatalf("SystemPromptCacheControl() error = %v", err)
	}
	if ctrl != nil {
		t.Fatalf("cache control = %#v, want nil", ctrl)
	}
}

func TestSystemPromptCacheControlOff(t *testing.T) {
	ctrl, err := SystemPromptCacheControl("off")
	if err != nil {
		t.Fatalf("SystemPromptCacheControl() error = %v", err)
	}
	if ctrl != nil {
		t.Fatalf("cache control = %#v, want nil", ctrl)
	}
}

func TestSystemPromptCacheControlRejectsInvalidTTL(t *testing.T) {
	ctrl, err := SystemPromptCacheControl("not-a-ttl")
	if err == nil {
		t.Fatal("expected error for invalid cache ttl")
	}
	if ctrl != nil {
		t.Fatalf("cache control = %#v, want nil", ctrl)
	}
	if !strings.Contains(err.Error(), "expected off|short|long|Go duration") {
		t.Fatalf("error = %v, want cache ttl validation message", err)
	}
}
