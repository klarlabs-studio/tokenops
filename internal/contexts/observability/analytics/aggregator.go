// Package analytics rolls up the local SQLite event store into the
// time-bucketed aggregates the dashboard, CLI, and forecasting engines
// consume. The aggregator is read-only — it never mutates events — and
// is intentionally a thin layer over the (already-indexed) events table
// so the same queries can be ported to ClickHouse later.
package analytics

import (
	"context"
	"database/sql"
	"errors"
	"fmt"
	"strings"
	"time"

	"go.klarlabs.de/tokenops/internal/contexts/spend/spend"
	"go.klarlabs.de/tokenops/internal/storage/sqlite"
	"go.klarlabs.de/tokenops/pkg/eventschema"
)

// Bucket is the discretisation unit for time-bucketed aggregates.
type Bucket string

// Known buckets. Hour and Day cover the dashboards' live-view and
// forecasting windows; minute-resolution can be added later for SLOs.
const (
	BucketHour Bucket = "hour"
	BucketDay  Bucket = "day"
)

// seconds returns the bucket width in seconds.
func (b Bucket) seconds() int64 {
	switch b {
	case BucketDay:
		return 86_400
	default:
		return 3_600
	}
}

// Group identifies the dimension to group by.
type Group string

// Known group dimensions.
const (
	GroupNone     Group = ""
	GroupProvider Group = "provider"
	GroupModel    Group = "model"
	GroupWorkflow Group = "workflow"
	GroupAgent    Group = "agent"
)

// column resolves a Group to the events-table column it maps to.
func (g Group) column() string {
	switch g {
	case GroupProvider:
		return "provider"
	case GroupModel:
		return "model"
	case GroupWorkflow:
		return "workflow_id"
	case GroupAgent:
		return "agent_id"
	default:
		return ""
	}
}

// Filter narrows the events the aggregator considers. Empty fields are
// not constrained.
//
// ExcludeSources gates the synthetic / activity-proxy surfaces. nil
// means "apply DefaultExcludedSources". An empty non-nil slice means
// "include every source"; callers pass that when they explicitly want
// to see synthetic data alongside real traffic.
//
// IncludeSources re-admits named entries of DefaultExcludedSources
// without disturbing the rest, so an operator asking for demo seeds
// does not also get MCP activity pings folded in. It is ignored when
// ExcludeSources is non-nil, because an explicit exclude list already
// states exactly what to drop.
type Filter struct {
	EventType      eventschema.EventType
	Provider       string
	Model          string
	WorkflowID     string
	AgentID        string
	Since          time.Time
	Until          time.Time
	ExcludeSources []string
	IncludeSources []string
}

// DefaultExcludedSources is applied by every analytics query unless the
// caller passes a non-nil ExcludeSources slice. Neither entry is real
// LLM traffic: `demo` is seeded by `tokenops demo`, and `mcp-session`
// is the activity-proxy ping the MCP server records about itself, which
// would otherwise inflate the request count an operator reads as "calls
// I made". Opt either back in per-source via
// `--include-source=` / `include_sources: [...]`.
var DefaultExcludedSources = []string{"demo", "mcp-session"}

// resolveExcludeSources returns the operative exclude list for a
// Filter: caller-supplied slice when set (including empty for "show
// everything"), otherwise the package default minus anything the
// caller re-admitted via IncludeSources.
func resolveExcludeSources(f Filter) []string {
	if f.ExcludeSources != nil {
		return f.ExcludeSources
	}
	if len(f.IncludeSources) == 0 {
		return DefaultExcludedSources
	}
	readmit := make(map[string]bool, len(f.IncludeSources))
	for _, s := range f.IncludeSources {
		readmit[s] = true
	}
	out := make([]string, 0, len(DefaultExcludedSources))
	for _, s := range DefaultExcludedSources {
		if !readmit[s] {
			out = append(out, s)
		}
	}
	return out
}

// Row is one (bucket, group-key) cell of an aggregate.
type Row struct {
	BucketStart  time.Time
	GroupKey     string
	Requests     int64
	InputTokens  int64
	OutputTokens int64
	TotalTokens  int64
	CostUSD      float64
	// CostRecomputed reports the number of rows in this bucket whose
	// CostUSD was 0 in the store and was recomputed via spend.Engine.
	// Useful for dashboards to flag stale pricing tables.
	CostRecomputed int64
}

// Summary is the global rollup over a query: total requests / tokens /
// cost across the entire filter window. It is what the CLI prints as
// "this week's spend" and the dashboard surfaces as headline numbers.
type Summary struct {
	Requests     int64
	InputTokens  int64
	OutputTokens int64
	TotalTokens  int64
	CostUSD      float64
	// APIEquivalentUSD is what the window would have billed at API list
	// prices: CostUSD plus a list-price recompute of plan-included and
	// trial traffic (which is $0 real). For metered-only deployments it
	// equals CostUSD; for flat-plan deployments it is the shadow value
	// the subscription absorbed.
	APIEquivalentUSD float64
	// Unpriced lists (provider, model) pairs in the window whose events
	// carry no stored cost and have no rate in the pricing table, so
	// their cost is silently absent from CostUSD. Surfaces (e.g. a newly
	// released model) should render this as a warning.
	Unpriced []UnpricedModel `json:",omitempty"`
}

// UnpricedModel identifies a model whose usage could not be costed.
type UnpricedModel struct {
	Provider string
	Model    string
	Requests int64
}

// Aggregator answers rollup queries against a sqlite.Store. spend.Engine
// is consulted when a row's CostUSD is zero (e.g. older events written
// before the spend engine was wired in).
type Aggregator struct {
	store *sqlite.Store
	spend *spend.Engine
}

// New constructs an Aggregator. spendEng may be nil — rows with zero cost
// then stay zero rather than being recomputed.
func New(store *sqlite.Store, spendEng *spend.Engine) *Aggregator {
	return &Aggregator{store: store, spend: spendEng}
}

// AggregateBy returns time-bucketed aggregates. Setting group to GroupNone
// produces one row per bucket (across all events in the bucket).
func (a *Aggregator) AggregateBy(ctx context.Context, f Filter, bucket Bucket, group Group) ([]Row, error) {
	if a == nil || a.store == nil {
		return nil, errors.New("analytics: aggregator not initialised")
	}
	width := bucket.seconds()
	if width <= 0 {
		return nil, fmt.Errorf("analytics: invalid bucket %q", bucket)
	}

	conds, args := buildConditions(f)

	// SQLite has no native time bucketing, but timestamp_ns is already a
	// monotonic int. Floor-divide by the bucket width to get a stable key.
	// Convert ns -> seconds first to keep numbers small (and in int64 range).
	bucketExpr := fmt.Sprintf("(timestamp_ns / 1000000000 / %d) * %d", width, width)
	groupCol := group.column()

	selectCols := []string{
		bucketExpr + " AS bucket_start_sec",
	}
	if groupCol != "" {
		selectCols = append(selectCols, fmt.Sprintf("COALESCE(%s, '') AS group_key", groupCol))
	} else {
		selectCols = append(selectCols, "'' AS group_key")
	}
	selectCols = append(selectCols,
		"COUNT(*) AS requests",
		"COALESCE(SUM(input_tokens), 0)  AS input_tokens",
		"COALESCE(SUM(output_tokens), 0) AS output_tokens",
		"COALESCE(SUM(total_tokens), 0)  AS total_tokens",
		"COALESCE(SUM(cost_usd), 0)      AS cost_usd",
	)

	q := "SELECT " + strings.Join(selectCols, ", ") +
		" FROM events"
	if len(conds) > 0 {
		q += " WHERE " + strings.Join(conds, " AND ")
	}
	q += " GROUP BY bucket_start_sec"
	if groupCol != "" {
		q += ", group_key"
	}
	q += " ORDER BY bucket_start_sec ASC"
	if groupCol != "" {
		q += ", group_key ASC"
	}

	rows, err := a.store.DB().QueryContext(ctx, q, args...)
	if err != nil {
		return nil, fmt.Errorf("analytics: query: %w", err)
	}
	defer func() { _ = rows.Close() }()

	var out []Row
	for rows.Next() {
		var (
			bucketStartSec int64
			groupKey       string
			r              Row
		)
		if err := rows.Scan(&bucketStartSec, &groupKey, &r.Requests, &r.InputTokens, &r.OutputTokens, &r.TotalTokens, &r.CostUSD); err != nil {
			return nil, fmt.Errorf("analytics: scan: %w", err)
		}
		r.BucketStart = time.Unix(bucketStartSec, 0).UTC()
		r.GroupKey = groupKey
		out = append(out, r)
	}
	if err := rows.Err(); err != nil {
		return nil, fmt.Errorf("analytics: iterate: %w", err)
	}

	if a.spend != nil {
		if err := a.recomputeMissingCosts(ctx, f, out); err != nil {
			return nil, err
		}
	}
	return out, nil
}

// recomputeMissingCosts scans for rows where CostUSD == 0 (within their
// bucket+group) and computes the cost from per-event token totals via
// spend.Engine, attributing the recompute to row.CostRecomputed. This
// keeps existing event CostUSD authoritative while filling in zeros.
func (a *Aggregator) recomputeMissingCosts(ctx context.Context, f Filter, rows []Row) error {
	for i := range rows {
		if rows[i].CostUSD > 0 {
			continue
		}
		// Pull the underlying events for this bucket+group and recompute.
		conds, args := buildConditions(f)
		conds = append(conds,
			"timestamp_ns >= ?",
			"timestamp_ns < ?",
			costSourceMetered,
		)
		args = append(args,
			rows[i].BucketStart.UnixNano(),
			rows[i].BucketStart.Add(time.Second*time.Duration(BucketHour.seconds())).UnixNano(),
		)
		// override second arg if BucketDay
		// (kept simple; correct because the test column uses bucket_start_sec)
		var (
			cost  float64
			fixed int64
		)
		q := `SELECT provider, model, input_tokens, output_tokens,
				CAST(COALESCE(json_extract(payload, '$.cached_input_tokens'), json_extract(attributes, '$.cache_read_input')) AS INTEGER)
			FROM events`
		if len(conds) > 0 {
			q += " WHERE " + strings.Join(conds, " AND ")
		}
		eventRows, err := a.store.DB().QueryContext(ctx, q, args...)
		if err != nil {
			return fmt.Errorf("analytics: recompute query: %w", err)
		}
		err = func() error {
			defer func() { _ = eventRows.Close() }()
			for eventRows.Next() {
				var (
					provider, model        sql.NullString
					inTok, outTok, cacheIn sql.NullInt64
				)
				if err := eventRows.Scan(&provider, &model, &inTok, &outTok, &cacheIn); err != nil {
					return err
				}
				p := &eventschema.PromptEvent{
					Provider:          eventschema.Provider(provider.String),
					RequestModel:      model.String,
					InputTokens:       inTok.Int64,
					CachedInputTokens: cacheIn.Int64,
					OutputTokens:      outTok.Int64,
				}
				// Price at the rate card in effect for this bucket (ADR 0002
				// Phase 2). Rate changes are dated to a day, so the bucket
				// start is the correct effective instant; for a baseline-only
				// engine this is identical to Compute.
				if c, err := a.spend.ComputeAt(p, rows[i].BucketStart); err == nil {
					cost += c
					fixed++
				}
			}
			return eventRows.Err()
		}()
		if err != nil {
			return fmt.Errorf("analytics: recompute scan: %w", err)
		}
		rows[i].CostUSD = cost
		rows[i].CostRecomputed = fixed
	}
	return nil
}

// Summarize returns a single global rollup over the filter window. It is
// equivalent to AggregateBy with an unbounded bucket; using a dedicated
// query keeps the SQL plan simpler.
func (a *Aggregator) Summarize(ctx context.Context, f Filter) (Summary, error) {
	if a == nil || a.store == nil {
		return Summary{}, errors.New("analytics: aggregator not initialised")
	}
	conds, args := buildConditions(f)
	q := `SELECT COUNT(*),
		COALESCE(SUM(input_tokens), 0),
		COALESCE(SUM(output_tokens), 0),
		COALESCE(SUM(total_tokens), 0),
		COALESCE(SUM(cost_usd), 0)
		FROM events`
	if len(conds) > 0 {
		q += " WHERE " + strings.Join(conds, " AND ")
	}
	var s Summary
	if err := a.store.DB().QueryRowContext(ctx, q, args...).Scan(
		&s.Requests, &s.InputTokens, &s.OutputTokens, &s.TotalTokens, &s.CostUSD,
	); err != nil {
		return Summary{}, fmt.Errorf("analytics: summarize: %w", err)
	}
	if a.spend != nil {
		recomputed, unpriced, err := a.summarizeMissingCost(ctx, f)
		if err != nil {
			return Summary{}, err
		}
		s.CostUSD += recomputed
		s.Unpriced = unpriced
		planValue, planUnpriced, err := a.summarizePlanCoveredValue(ctx, f)
		if err != nil {
			return Summary{}, err
		}
		s.Unpriced = mergeUnpriced(s.Unpriced, planUnpriced)
		s.APIEquivalentUSD = s.CostUSD + planValue
	} else {
		s.APIEquivalentUSD = s.CostUSD
	}
	return s, nil
}

// summarizePlanCoveredValue recomputes plan-included / trial traffic at
// list prices — the shadow value a flat-rate subscription absorbed.
// Mirrors summarizeMissingCost with the cost-source filter inverted;
// unknown models are skipped silently here (they already surface via
// Unpriced when metered, and pseudo-models like mcp-session would only
// add noise).
// summarizePlanCoveredValue returns the list-price value the subscription
// absorbed, plus any (provider, model) pairs it could not price. The
// second return matters on a flat plan: an unpriced model contributes
// nothing to the shadow value, and because its real cost is legitimately
// zero it would otherwise leave no trace at all.
func (a *Aggregator) summarizePlanCoveredValue(ctx context.Context, f Filter) (float64, []UnpricedModel, error) {
	conds, args := buildConditions(f)
	conds = append(conds,
		`COALESCE(json_extract(payload, '$.cost_source'), '') IN ('plan_included', 'trial')`,
	)
	q := `SELECT provider, model,
			COALESCE(SUM(input_tokens), 0),
			COALESCE(SUM(output_tokens), 0),
			COALESCE(SUM(CAST(COALESCE(json_extract(payload, '$.cached_input_tokens'), json_extract(attributes, '$.cache_read_input')) AS INTEGER)), 0),
			COUNT(*)
		FROM events WHERE ` + strings.Join(conds, " AND ") +
		` GROUP BY provider, model`
	rows, err := a.store.DB().QueryContext(ctx, q, args...)
	if err != nil {
		return 0, nil, fmt.Errorf("analytics: plan-covered value query: %w", err)
	}
	defer func() { _ = rows.Close() }()
	var (
		total    float64
		unpriced []UnpricedModel
	)
	for rows.Next() {
		var (
			provider, model        sql.NullString
			inTok, outTok, cacheIn sql.NullInt64
			requests               sql.NullInt64
		)
		if err := rows.Scan(&provider, &model, &inTok, &outTok, &cacheIn, &requests); err != nil {
			return 0, nil, fmt.Errorf("analytics: plan-covered value scan: %w", err)
		}
		p := &eventschema.PromptEvent{
			Provider:          eventschema.Provider(provider.String),
			RequestModel:      model.String,
			InputTokens:       inTok.Int64,
			CachedInputTokens: cacheIn.Int64,
			OutputTokens:      outTok.Int64,
		}
		c, err := a.spend.Compute(p)
		if err != nil {
			// tokenops' own telemetry (MCP session pings and friends)
			// carries a pseudo-model that will never have a rate card.
			// It is not a model call, so it is not a pricing gap.
			if isSelfTelemetryModel(model.String) {
				continue
			}
			// No rate card for a model the operator actually ran.
			// Record it rather than discarding the error — silently
			// dropping the row is how a subscription's dominant model can
			// be missing from the api-equivalent figure with nothing to
			// show for it.
			unpriced = append(unpriced, UnpricedModel{
				Provider: provider.String,
				Model:    model.String,
				Requests: requests.Int64,
			})
			continue
		}
		total += c
	}
	if err := rows.Err(); err != nil {
		return 0, nil, fmt.Errorf("analytics: plan-covered value iterate: %w", err)
	}
	return total, unpriced, nil
}

// CacheStatsResult is the per-window cache split. Token counts are
// summed across the filter range; CacheRatio is the share of input
// tokens that came from cache reads (0..1).
type CacheStatsResult struct {
	TotalInputTokens    int64   `json:"total_input_tokens"`
	CachedInputTokens   int64   `json:"cached_input_tokens"`
	UncachedInputTokens int64   `json:"uncached_input_tokens"`
	OutputTokens        int64   `json:"output_tokens"`
	CacheRatio          float64 `json:"cache_ratio"`
}

// CacheStats sums cached vs uncached input over the filter window.
// JSONL events carry the cache split in payload.cached_input_tokens
// (post-v0.14.2 poller) or attributes.cache_read_input (legacy).
// COALESCE-over-both so old events still pay the cache discount
// without a re-ingest.
func (a *Aggregator) CacheStats(ctx context.Context, f Filter) (CacheStatsResult, error) {
	if a == nil || a.store == nil {
		return CacheStatsResult{}, errors.New("analytics: aggregator not initialised")
	}
	conds, args := buildConditions(f)
	q := `SELECT
		COALESCE(SUM(input_tokens), 0),
		COALESCE(SUM(CAST(COALESCE(json_extract(payload, '$.cached_input_tokens'), json_extract(attributes, '$.cache_read_input')) AS INTEGER)), 0),
		COALESCE(SUM(output_tokens), 0)
		FROM events`
	if len(conds) > 0 {
		q += " WHERE " + strings.Join(conds, " AND ")
	}
	var s CacheStatsResult
	if err := a.store.DB().QueryRowContext(ctx, q, args...).Scan(
		&s.TotalInputTokens, &s.CachedInputTokens, &s.OutputTokens,
	); err != nil {
		return CacheStatsResult{}, fmt.Errorf("analytics: cache_stats: %w", err)
	}
	s.UncachedInputTokens = s.TotalInputTokens - s.CachedInputTokens
	if s.UncachedInputTokens < 0 {
		s.UncachedInputTokens = 0
	}
	if s.TotalInputTokens > 0 {
		s.CacheRatio = float64(s.CachedInputTokens) / float64(s.TotalInputTokens)
	}
	return s, nil
}

// summarizeMissingCost computes the spend.Engine cost for events whose
// stored cost_usd is zero — the case for vendor-usage-jsonl sources that
// ship token counts but not prices. Groups by (provider, model) so one
// engine.Compute call covers the entire bucket per model, which is
// linear-in-tokens and matches the per-event sum exactly. Cached input
// tokens are summed from payload JSON (the schema column carries only
// the bundled input_tokens) so cache-heavy workloads get the lower
// cache rate instead of being billed at the new-input rate.
//
// Models the pricing table doesn't know are returned as UnpricedModel
// entries instead of being silently dropped — their cost stays absent
// from the total, and callers surface that gap as a warning.
func (a *Aggregator) summarizeMissingCost(ctx context.Context, f Filter) (float64, []UnpricedModel, error) {
	conds, args := buildConditions(f)
	conds = append(conds, "(cost_usd IS NULL OR cost_usd = 0)", costSourceMetered)
	q := `SELECT provider, model, COUNT(*),
			COALESCE(SUM(input_tokens), 0),
			COALESCE(SUM(output_tokens), 0),
			COALESCE(SUM(CAST(COALESCE(json_extract(payload, '$.cached_input_tokens'), json_extract(attributes, '$.cache_read_input')) AS INTEGER)), 0)
		FROM events WHERE ` + strings.Join(conds, " AND ") +
		` GROUP BY provider, model ORDER BY provider, model`
	rows, err := a.store.DB().QueryContext(ctx, q, args...)
	if err != nil {
		return 0, nil, fmt.Errorf("analytics: summarize recompute query: %w", err)
	}
	defer func() { _ = rows.Close() }()
	var (
		total    float64
		unpriced []UnpricedModel
	)
	for rows.Next() {
		var (
			provider, model                  sql.NullString
			requests, inTok, outTok, cacheIn sql.NullInt64
		)
		if err := rows.Scan(&provider, &model, &requests, &inTok, &outTok, &cacheIn); err != nil {
			return 0, nil, fmt.Errorf("analytics: summarize recompute scan: %w", err)
		}
		p := &eventschema.PromptEvent{
			Provider:          eventschema.Provider(provider.String),
			RequestModel:      model.String,
			InputTokens:       inTok.Int64,
			CachedInputTokens: cacheIn.Int64,
			OutputTokens:      outTok.Int64,
		}
		c, err := a.spend.Compute(p)
		switch {
		case err == nil:
			total += c
		case errors.Is(err, spend.ErrUnknownModel):
			unpriced = append(unpriced, UnpricedModel{
				Provider: provider.String,
				Model:    model.String,
				Requests: requests.Int64,
			})
		}
	}
	if err := rows.Err(); err != nil {
		return 0, nil, fmt.Errorf("analytics: summarize recompute iterate: %w", err)
	}
	return total, unpriced, nil
}

// selfTelemetryModels are pseudo-models tokenops emits about itself.
// They describe daemon activity, not an LLM call, so they will never
// have a rate card and must not be reported as pricing gaps.
var selfTelemetryModels = map[string]bool{"mcp-session": true}

func isSelfTelemetryModel(model string) bool { return selfTelemetryModels[model] }

// costSourceMetered keeps cost RECOMPUTE away from flat-rate traffic:
// plan-included and trial events are zero-cost BY DESIGN (the request is
// covered by a subscription or vendor credit), so repricing them at list
// rates would invent spend. Note this governs repricing only — pricing
// GAPS in plan-covered traffic are reported separately by
// summarizePlanCoveredValue, because on a subscription that traffic is
// the majority and an unpriced model there would otherwise leave no
// trace at all. The schema column carries only the bundled counters, so
// the source is read from payload JSON.
const costSourceMetered = `COALESCE(json_extract(payload, '$.cost_source'), '') NOT IN ('plan_included', 'trial')`

func buildConditions(f Filter) ([]string, []any) {
	var (
		conds []string
		args  []any
	)
	if f.EventType != "" {
		conds = append(conds, "type = ?")
		args = append(args, string(f.EventType))
	} else {
		// Default to prompts only — workflow/optimization events do not
		// carry per-request token counts in the indexed columns.
		conds = append(conds, "type = ?")
		args = append(args, string(eventschema.EventTypePrompt))
	}
	if f.Provider != "" {
		conds = append(conds, "provider = ?")
		args = append(args, f.Provider)
	}
	if f.Model != "" {
		conds = append(conds, "model = ?")
		args = append(args, f.Model)
	}
	if f.WorkflowID != "" {
		conds = append(conds, "workflow_id = ?")
		args = append(args, f.WorkflowID)
	}
	if f.AgentID != "" {
		conds = append(conds, "agent_id = ?")
		args = append(args, f.AgentID)
	}
	if !f.Since.IsZero() {
		conds = append(conds, "timestamp_ns >= ?")
		args = append(args, f.Since.UTC().UnixNano())
	}
	if !f.Until.IsZero() {
		conds = append(conds, "timestamp_ns < ?")
		args = append(args, f.Until.UTC().UnixNano())
	}
	if excludes := resolveExcludeSources(f); len(excludes) > 0 {
		placeholders := make([]string, len(excludes))
		for i, s := range excludes {
			placeholders[i] = "?"
			args = append(args, s)
		}
		conds = append(conds, "(source IS NULL OR source NOT IN ("+strings.Join(placeholders, ", ")+"))")
	}
	return conds, args
}

// mergeUnpriced folds two unpriced lists into one, summing requests for
// pairs that appear in both (a model can be partly metered and partly
// plan-covered inside one window).
func mergeUnpriced(a, b []UnpricedModel) []UnpricedModel {
	if len(b) == 0 {
		return a
	}
	idx := make(map[string]int, len(a)+len(b))
	out := make([]UnpricedModel, 0, len(a)+len(b))
	add := func(u UnpricedModel) {
		k := u.Provider + "/" + u.Model
		if i, ok := idx[k]; ok {
			out[i].Requests += u.Requests
			return
		}
		idx[k] = len(out)
		out = append(out, u)
	}
	for _, u := range a {
		add(u)
	}
	for _, u := range b {
		add(u)
	}
	return out
}
