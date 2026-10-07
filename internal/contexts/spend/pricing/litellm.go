package pricing

import (
	"encoding/json"
	"fmt"
	"math"
	"regexp"
	"sort"
	"strconv"
	"strings"
	"time"
)

// LiteLLMSourceName is the Source name, and Snapshot.Source, of the LiteLLM
// rate card (BerriAI/litellm's model_prices_and_context_window.json: vendor
// list prices, not proxy-marked-up). This is the ADR 0002 default source; the
// HTTP fetch lives in internal/infra/pricingsource.
const LiteLLMSourceName = "litellm"

// litellmEntry is the subset of a LiteLLM model record this adapter reads.
// Costs are per single token; convert to per-million with ×1e6.
type litellmEntry struct {
	Provider          string  `json:"litellm_provider"`
	InputCostPerToken float64 `json:"input_cost_per_token"`
	OutputCost        float64 `json:"output_cost_per_token"`
	CacheReadCost     float64 `json:"cache_read_input_token_cost"`
	CacheCreationCost float64 `json:"cache_creation_input_token_cost"`
	// CacheCreation1hCost is the one-hour cache-write price, where the
	// vendor charges one.
	CacheCreation1hCost float64 `json:"cache_creation_input_token_cost_above_1hr"`
}

// perMillion converts a per-token cost to per-million tokens.
const perMillion = 1_000_000.0

// perMillionCost converts a per-token cost to per-million and rounds to 6
// decimal places (micro-dollars per million). Rounding removes the float
// noise of ×1e6 — e.g. 0.0000008 × 1e6 = 0.7999999999999999 — so an unchanged
// rate compares equal to the YAML baseline and does not manufacture a spurious
// diff line.
func perMillionCost(perToken float64) float64 {
	return math.Round(perToken*perMillion*1e6) / 1e6
}

// litellmProviderMap maps a LiteLLM "litellm_provider" value to the tokenops
// provider string used in the catalog. Only providers the embedded catalog can
// price are listed; an entry whose litellm_provider is absent here is skipped,
// so the fetched snapshot's key-space stays aligned with the baseline and the
// diff remains meaningful. Multiplexers (fireworks, together, openrouter) are
// intentionally excluded — a static card cannot price their namespaced models.
var litellmProviderMap = map[string]string{
	"anthropic":                 "anthropic",
	"openai":                    "openai",
	"text-completion-openai":    "openai",
	"mistral":                   "mistral",
	"gemini":                    "gemini",
	"vertex_ai":                 "gemini",
	"vertex_ai-language-models": "gemini",
	"google":                    "gemini",
	"cohere":                    "cohere",
	"cohere_chat":               "cohere",
	"groq":                      "groq",
	"deepseek":                  "deepseek",
	"xai":                       "xai",
	"perplexity":                "perplexity",
	"cerebras":                  "cerebras",
}

// vendorPrefixes are the leading "<vendor>/" namespaces LiteLLM prepends to
// some model ids (e.g. "mistral/mistral-large-latest", "vertex_ai/gemini-…").
// Only these known tokens are stripped, so multi-segment ids from unmapped
// multiplexers are never mangled.
var vendorPrefixes = map[string]bool{
	"anthropic": true, "openai": true, "mistral": true, "gemini": true,
	"vertex_ai": true, "google": true, "cohere": true, "groq": true,
	"deepseek": true, "xai": true, "perplexity": true, "cerebras": true,
}

// ParseLiteLLM normalizes a LiteLLM rate-card body into a Snapshot: every
// entry whose litellm_provider resolves to a catalog provider is keyed
// "<provider>/<model>". sourceURL and fetchedAt are the fetch's provenance.
// A body that is not a JSON object is wrapped in ErrFetch so the caller
// falls back to the baseline without writing a snapshot.
func ParseLiteLLM(body []byte, sourceURL string, fetchedAt time.Time) (Snapshot, error) {
	var raw map[string]json.RawMessage
	if err := json.Unmarshal(body, &raw); err != nil {
		return Snapshot{}, fmt.Errorf("%w: parse JSON: %v", ErrFetch, err)
	}

	snap := Snapshot{
		Source:    LiteLLMSourceName,
		SourceURL: sourceURL,
		FetchedAt: fetchedAt,
		Rates:     map[string]Rate{},
	}
	catalogKeys := catalogModelKeys()

	// Group candidate LiteLLM ids by the catalog key they map to. A broad
	// catalog key (e.g. "mistral-large") collapses every dated SKU LiteLLM
	// carries — mistral-large-2402, -2411, -latest, … — onto one key. Picking
	// the lexically-first id would adopt the *oldest* archived snapshot (usually
	// the priciest), manufacturing false "drift". Instead pick the id that best
	// represents the vendor's live price via preferID (see versionRank).
	type candidate struct {
		id   string
		rate Rate
	}
	groups := make(map[string][]candidate)
	for id, msg := range raw {
		if id == "sample_spec" { // LiteLLM's schema doc row, not a model
			continue
		}
		var e litellmEntry
		if json.Unmarshal(msg, &e) != nil {
			continue // non-model or unexpected shape → skip, don't fail
		}
		provider, ok := litellmProviderMap[strings.ToLower(e.Provider)]
		if !ok {
			continue // provider not in the catalog → skip so key-space matches
		}
		providerKeys, priced := catalogKeys[provider]
		if !priced {
			continue // catalog carries no rows for this provider
		}
		if e.InputCostPerToken == 0 && e.OutputCost == 0 {
			continue // no usable price
		}
		key := snapKey(provider, mapModelKey(id, providerKeys))
		groups[key] = append(groups[key], candidate{
			id: id,
			rate: Rate{
				InputPerMillion:        perMillionCost(e.InputCostPerToken),
				OutputPerMillion:       perMillionCost(e.OutputCost),
				CachedInputPerMillion:  perMillionCost(e.CacheReadCost),
				CacheWritePerMillion:   perMillionCost(e.CacheCreationCost),
				CacheWrite1hPerMillion: perMillionCost(e.CacheCreation1hCost),
			},
		})
	}
	for key, cands := range groups {
		best := cands[0]
		for _, c := range cands[1:] {
			if preferID(c.id, best.id) {
				best = c
			}
		}
		snap.Rates[key] = best.rate
	}
	return snap, nil
}

// versionDate matches a trailing numeric version/date suffix LiteLLM appends to
// dated model snapshots: 8-digit YYYYMMDD (Anthropic "claude-…-20241022"),
// 6-digit YYMMDD, or 4-digit YYMM (Mistral "mistral-large-2411"). Higher digits
// mean a newer release, so the captured number orders variants within a family.
var versionDate = regexp.MustCompile(`-(\d{4,8})$`)

// datedScore extracts a comparable release number from a trailing numeric
// suffix, and reports whether the suffix is a genuine date. 8-digit YYYYMMDD
// (Anthropic "claude-…-20241022") and 6-digit YYMMDD are always dates. A
// 4-digit suffix is a date ONLY when it is a plausible YYMM — year 20–29,
// month 01–12 (Mistral "mistral-large-2411") — so OpenAI's MMDD snapshots are
// NOT misread: "gpt-3.5-turbo-1106" (Nov) and "-0125" (Jan) would otherwise
// order as 1106 > 0125 and pick the OLDER November SKU. Rejecting them drops
// both to the bare tier, where the undated "gpt-3.5-turbo" alias (the current
// price) wins.
func datedScore(stem string) (int, bool) {
	m := versionDate.FindStringSubmatch(stem)
	if m == nil {
		return 0, false
	}
	n, _ := strconv.Atoi(m[1])
	if len(m[1]) == 4 {
		if yy, mm := n/100, n%100; yy < 20 || yy > 29 || mm < 1 || mm > 12 {
			return 0, false
		}
	}
	return n, true
}

// versionRank scores how well a LiteLLM model id represents the *current* price
// of its family. Higher wins: a precise dated snapshot outranks everything and
// the newest date among them wins; a "-latest" alias is the fallback used only
// when no dated SKU is listed; an undated/bare id ranks lowest. Dated snapshots
// are preferred over "-latest" because LiteLLM's "-latest" aliases are sometimes
// stale — e.g. "codestral-latest" still carries the old $1/$3 rate while the
// current "codestral-2508" is $0.30/$0.90 — so trusting the alias would
// manufacture false drift against a catalog that tracks the newest SKU.
func versionRank(id string) (tier, date int) {
	stem := stripVendorPrefix(id)
	if n, ok := datedScore(stem); ok {
		return 3, n // a precise dated snapshot — newest wins
	}
	if strings.HasSuffix(stem, "-latest") {
		return 2, 0 // vendor's moving pointer; used when no dated SKU is listed
	}
	return 1, 0 // undated / bare id
}

// preferID reports whether LiteLLM id a is a better current-price representative
// than b for a colliding catalog key (see versionRank). Ties break to the
// lexically-smaller id so a refresh is deterministic across runs.
func preferID(a, b string) bool {
	at, ad := versionRank(a)
	bt, bd := versionRank(b)
	switch {
	case at != bt:
		return at > bt
	case ad != bd:
		return ad > bd
	default:
		return a < b
	}
}

// catalogModelKeys returns the tokenops catalog model keys (from the embedded
// baseline) grouped by provider, each group sorted longest-first so mapModelKey
// can longest-prefix match within the right provider.
func catalogModelKeys() map[string][]string {
	base := BaselineSnapshot()
	out := make(map[string][]string)
	for key := range base.Rates {
		provider, model := splitSnapKey(key)
		out[provider] = append(out[provider], model)
	}
	for _, keys := range out {
		sort.Slice(keys, func(i, j int) bool { return len(keys[i]) > len(keys[j]) })
	}
	return out
}

// dateSuffix matches a trailing "-YYYYMMDD" or "-YYMMDD" date variant that
// LiteLLM appends to dated model snapshots (e.g. "-20241022").
var dateSuffix = regexp.MustCompile(`-\d{6,8}$`)

// skuQualifiers are tokens that mark a DISTINCT, separately-priced product
// tier rather than a dated/aliased version of the base model. A broad catalog
// key must not swallow an id whose remainder begins with one — e.g. "grok-3"
// must not absorb "grok-3-fast" ($5/$25) or "grok-3-mini" ($0.30/$0.50), and
// "gemini-2.5-flash" must not absorb "gemini-2.5-flash-lite" — or the fetched
// rate for the base model would be a different SKU's price. Such ids fall
// through to a shorter catalog key or surface under their own normalized key.
var skuQualifiers = map[string]bool{
	"fast": true, "mini": true, "nano": true, "lite": true, "pro": true,
	"turbo": true, "vision": true, "thinking": true, "reasoning": true,
	"audio": true, "embed": true, "embedding": true, "tts": true,
	"image": true, "coder": true, "ocr": true, "guard": true,
	"search": true, "rerank": true, "moderation": true,
}

// mapModelKey maps a LiteLLM model id to a tokenops model key within its
// provider. It strips any leading "<vendor>/" namespace, then takes the longest
// catalog key that is a prefix of the result (so "mistral/mistral-large-latest"
// → "mistral-large" and "claude-3-5-sonnet-20241022" → "claude-3-5-sonnet").
// A prefix match is only accepted at a token boundary whose next token is not a
// distinct SKU tier (see skuQualifiers), so "grok-3-fast" is not folded into
// "grok-3". When nothing matches it falls back to a normalized form of the id
// (vendor prefix + date/`-latest` marker stripped) so genuinely new models
// still surface in the diff under a readable key.
func mapModelKey(id string, catalogKeys []string) string {
	stem := stripVendorPrefix(id)
	for _, k := range catalogKeys {
		if k == "" || !strings.HasPrefix(stem, k) {
			continue
		}
		rest := stem[len(k):]
		if rest == "" {
			return k // exact match
		}
		if rest[0] != '-' {
			continue // not a token boundary (e.g. "grok-30" vs key "grok-3")
		}
		tok := rest[1:]
		if i := strings.IndexByte(tok, '-'); i >= 0 {
			tok = tok[:i]
		}
		if skuQualifiers[tok] {
			continue // distinct SKU tier — do not fold into the base key
		}
		return k
	}
	return normalizeModelID(id)
}

// stripVendorPrefix removes a single leading "<vendor>/" namespace when the
// vendor is a known token, leaving multi-segment ids from unmapped
// multiplexers untouched.
func stripVendorPrefix(id string) string {
	if i := strings.Index(id, "/"); i > 0 && vendorPrefixes[strings.ToLower(id[:i])] {
		return id[i+1:]
	}
	return id
}

// normalizeModelID strips a leading "<vendor>/" namespace and a trailing dated
// or "-latest" version marker, yielding a stable key for models absent from
// the catalog.
func normalizeModelID(id string) string {
	id = stripVendorPrefix(id)
	id = strings.TrimSuffix(id, "-latest")
	id = dateSuffix.ReplaceAllString(id, "")
	return strings.TrimSpace(id)
}
