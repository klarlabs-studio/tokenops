package cli

import (
	"encoding/json"
	"fmt"
	"sort"
	"strings"
	"time"

	"github.com/spf13/cobra"

	"go.klarlabs.de/tokenops/internal/contexts/coaching/prompts"
	"go.klarlabs.de/tokenops/internal/contexts/coaching/replies"
)

// newCoachCmd is the tree for prompt + workflow coaching. For now
// only the `prompts` subcommand is wired — workflow-trace coaching
// lives in `tokenops replay` (which the docs cross-reference).
func newCoachCmd() *cobra.Command {
	cmd := &cobra.Command{
		Use:   "coach",
		Short: "Analyze your prompting and workflow patterns for waste + anti-patterns",
	}
	cmd.AddCommand(newCoachPromptsCmd())
	cmd.AddCommand(newCoachRepliesCmd())
	return cmd
}

// newCoachRepliesCmd is the output-side sibling of newCoachPromptsCmd.
// It scans the same Claude Code / Codex JSONLs but extracts assistant
// replies instead of user prompts, then surfaces compression patterns
// — most notably whether a session ran with the caveman skill (or any
// equivalent output-compression skill) engaged.
func newCoachRepliesCmd() *cobra.Command {
	var (
		sinceFlag   string
		root        string
		replySource string
		session     string
		limit       int
		jsonOut     bool
	)
	cmd := &cobra.Command{
		Use:   "replies",
		Short: "Detect output-compression patterns (e.g. caveman skill) in assistant replies",
		Long: `replies walks ~/.claude/projects/**/*.jsonl, extracts every
assistant-emitted turn, and reports compression-style heuristics per
session:

  - article density   (a/an/the per word)
  - filler density    (just/really/basically/actually/sure/...)
  - avg word length   (caveman favours short synonyms)
  - code-block ratio  (preserved verbatim under caveman)
  - "caveman likely"  verdict per session
  - estimated token   savings vs. a verbose baseline (rough TEU input)

Reply text is read from the JSONLs at scan time — never persisted to
the TokenOps event store.`,
		RunE: func(cmd *cobra.Command, _ []string) error {
			opts := replies.ExtractOptions{
				Source:    replies.Source(replySource),
				Root:      root,
				SessionID: session,
				Limit:     limit,
			}
			if sinceFlag != "" {
				since, err := parseSince(sinceFlag)
				if err != nil {
					return fmt.Errorf("--since: %w", err)
				}
				opts.Since = since
			}
			extracted, err := replies.Extract(opts)
			if err != nil {
				return fmt.Errorf("extract: %w", err)
			}
			findings := replies.Analyze(extracted)
			if jsonOut {
				enc := json.NewEncoder(cmd.OutOrStdout())
				enc.SetIndent("", "  ")
				return enc.Encode(findings)
			}
			renderCoachReplies(cmd, findings, opts.Since)
			return nil
		},
	}
	cmd.Flags().StringVar(&sinceFlag, "since", "7d", "lower bound: RFC3339 timestamp or duration like 24h or 7d")
	cmd.Flags().StringVar(&root, "root", "", "scan root (defaults per source)")
	cmd.Flags().StringVar(&replySource, "source", "", "client: auto (default) | claude-code | codex | opencode")
	cmd.Flags().StringVar(&session, "session", "", "restrict to a single session id (filename stem)")
	cmd.Flags().IntVar(&limit, "limit", 0, "max replies to extract (0 = unbounded)")
	cmd.Flags().BoolVar(&jsonOut, "json", false, "emit JSON instead of text")
	return cmd
}

func renderCoachReplies(cmd *cobra.Command, f replies.Findings, since time.Time) {
	out := cmd.OutOrStdout()
	header := "Reply coach"
	if !since.IsZero() {
		header = fmt.Sprintf("Reply coach — since %s", since.Format(time.RFC3339))
	}
	fmt.Fprintln(out, header)
	fmt.Fprintf(out, "  total replies: %d\n", f.TotalReplies)
	if f.TotalReplies == 0 {
		fmt.Fprintln(out, "  (no assistant replies in the scan window)")
		return
	}
	fmt.Fprintln(out)
	fmt.Fprintln(out, "BASELINE (across all sessions)")
	fmt.Fprintf(out, "  avg words/reply:  %.1f\n", f.Baseline.AvgWords)
	fmt.Fprintf(out, "  avg word length:  %.2f\n", f.Baseline.AvgWordLen)
	fmt.Fprintf(out, "  article density:  %.2f%%   (typical English ~7%%)\n", f.Baseline.ArticleRatio*100)
	fmt.Fprintf(out, "  filler density:   %.2f%%   (typical ~1%%)\n", f.Baseline.FillerRatio*100)
	fmt.Fprintf(out, "  code-block ratio: %.1f%% of replies\n", f.Baseline.CodeBlockRatio*100)
	fmt.Fprintln(out)
	// Lead with the recommendation. Densities describe; only this tells
	// the operator what to change, which is the whole point of a coach.
	if rec, ok := replies.Recommend(f); ok {
		fmt.Fprintf(out, "\nBIGGEST WIN\n  %s\n", rec.Title)
		fmt.Fprintf(out, "  %s\n", rec.Evidence)
		fmt.Fprintf(out, "  Projected: ~%s output tokens across %d replies (%.0f → %.0f words each)\n",
			humanTokens(rec.EstimatedTokensSaved), f.TotalReplies,
			rec.CurrentAvgWords, rec.TargetAvgWords)
		fmt.Fprintf(out, "  Do: %s\n", rec.Action)
	}

	fmt.Fprintf(out, "\nCAVEMAN-LIKELY SESSIONS: %d / %d  ·  est. saved tokens: %d\n",
		f.CavemanLikelySessions, len(f.BySession), f.EstimatedTokenSavings)
	fmt.Fprintln(out)
	fmt.Fprintln(out, "PER SESSION")
	fmt.Fprintf(out, "  %-44s %5s %6s %7s %7s %6s\n", "session", "reply", "art%", "filler%", "wlen", "verdict")
	for _, s := range f.BySession {
		verdict := "—"
		if s.CavemanLikely {
			verdict = "caveman"
		}
		sid := s.SessionID
		if len(sid) > 44 {
			sid = sid[:42] + "…"
		}
		fmt.Fprintf(out, "  %-44s %5d %5.2f%% %6.2f%% %7.2f %6s\n",
			sid, s.Stats.Replies,
			s.Stats.ArticleRatio*100, s.Stats.FillerRatio*100,
			s.Stats.AvgWordLen, verdict)
	}
}

// newCoachPromptsCmd reads Claude Code session JSONLs (the same
// files the claudecodejsonl poller scans) and runs heuristic
// prompt-quality rules. Reads JSONLs directly so prompt text never
// lands in the event store — privacy-respecting and zero schema
// change.
func newCoachPromptsCmd() *cobra.Command {
	var (
		sourceFlag string
		sinceFlag  string
		root       string
		session    string
		limit      int
		jsonOut    bool
	)
	cmd := &cobra.Command{
		Use:   "prompts",
		Short: "Score your prompting against rule-based heuristics",
		Long: `prompts reads every client you run — Claude Code and Codex from
their JSONL transcripts, opencode from its SQLite store — extracts every
human-typed turn (tool results and the continuation prompts agents inject
for themselves are filtered out), and reports:

  - Length distribution (under-5-word / 5-15 / 15-50 / 50-200 / >200)
  - Vague-short prompts (<15 chars, ≤3 words)
  - Pure acknowledgements (yes/no/ok/continue)
  - Short questions (<60 chars with '?')
  - Repeated prompts (same text issued 3+ times)
  - Concrete recommendations

Prompt text is read at scan time — never persisted to the TokenOps event
store. --json emits machine-readable findings for
agents to consume.`,
		RunE: func(cmd *cobra.Command, _ []string) error {
			opts := prompts.ExtractOptions{
				Root:      root,
				Source:    prompts.Source(sourceFlag),
				SessionID: session,
				Limit:     limit,
			}
			if sinceFlag != "" {
				since, err := parseSince(sinceFlag)
				if err != nil {
					return fmt.Errorf("--since: %w", err)
				}
				opts.Since = since
			}
			extracted, err := prompts.Extract(opts)
			if err != nil {
				return fmt.Errorf("extract: %w", err)
			}
			findings := prompts.Analyze(extracted)
			stats, statsErr := prompts.ComputeTurnStats(opts)
			if statsErr != nil {
				// Stats are a render enrichment — log + continue.
				fmt.Fprintf(cmd.ErrOrStderr(), "warning: turn-stats unavailable: %v\n", statsErr)
			}
			if jsonOut {
				enc := json.NewEncoder(cmd.OutOrStdout())
				enc.SetIndent("", "  ")
				return enc.Encode(map[string]any{
					"findings":   findings,
					"turn_stats": stats,
				})
			}
			renderCoachPrompts(cmd, findings, stats, opts.Since)
			return nil
		},
	}
	cmd.Flags().StringVar(&sinceFlag, "since", "7d", "lower bound: RFC3339 timestamp or duration like 24h or 7d")
	cmd.Flags().StringVar(&root, "root", "", "scan root (defaults per source)")
	cmd.Flags().StringVar(&sourceFlag, "source", "", "client: auto (default) | claude-code | codex | opencode")
	cmd.Flags().StringVar(&session, "session", "", "restrict to a single session id (filename stem)")
	cmd.Flags().IntVar(&limit, "limit", 0, "max prompts to extract (0 = unbounded)")
	cmd.Flags().BoolVar(&jsonOut, "json", false, "emit JSON instead of text")
	return cmd
}

func renderCoachPrompts(cmd *cobra.Command, f prompts.Findings, stats prompts.TurnStats, since time.Time) {
	out := cmd.OutOrStdout()
	header := "Prompting coach"
	if !since.IsZero() {
		header = fmt.Sprintf("Prompting coach — since %s", since.Format(time.RFC3339))
	}
	fmt.Fprintln(out, header)
	fmt.Fprintf(out, "  total prompts: %d  |  avg %.0f chars / %.0f words  |  min %d, max %d chars\n",
		f.TotalPrompts, f.AvgChars, f.AvgWords, f.MinChars, f.MaxChars)
	if stats.TotalTurns > 0 {
		fmt.Fprintf(out, "  avg assistant turn: %.0f input tokens (%.0f cached) + %.0f output  |  $%.4f  |  %.0fs of your attention\n",
			stats.AvgInputTokens, stats.AvgCachedTokens, stats.AvgOutputTokens,
			stats.AvgCostUSD, stats.AvgSeconds)
	}
	if f.TotalPrompts == 0 {
		fmt.Fprintln(out, "  (no human prompts in the scan window)")
		return
	}
	fmt.Fprintln(out)
	fmt.Fprintln(out, "LENGTH DISTRIBUTION")
	keys := []string{"<5w", "5-15w", "15-50w", "50-200w", ">200w"}
	for _, k := range keys {
		n := f.LengthDistribution[k]
		pct := 100 * float64(n) / float64(f.TotalPrompts)
		bar := strings.Repeat("█", int(pct/2))
		fmt.Fprintf(out, "  %-8s %5d  (%5.1f%%) %s\n", k, n, pct, bar)
	}
	fmt.Fprintln(out)
	fmt.Fprintln(out, "FINDINGS")
	fmt.Fprintf(out, "  vague/short (<15 chars, ≤3 words):  %d (%.1f%%)\n",
		f.VagueShort, pctOf(f.VagueShort, f.TotalPrompts))
	for _, s := range f.VagueShortSamples {
		fmt.Fprintf(out, "      • %q\n", s)
	}
	fmt.Fprintf(out, "  pure acknowledgements:              %d (%.1f%%)\n",
		f.Acknowledgements, pctOf(f.Acknowledgements, f.TotalPrompts))
	fmt.Fprintf(out, "  short questions (<60 chars + '?'):  %d (%.1f%%)\n",
		f.ShortQuestions, pctOf(f.ShortQuestions, f.TotalPrompts))
	fmt.Fprintf(out, "  single-sentence no-context:         %d (%.1f%%)\n",
		f.NoContextSingles, pctOf(f.NoContextSingles, f.TotalPrompts))
	if len(f.RepeatedPrompts) > 0 {
		fmt.Fprintln(out)
		fmt.Fprintln(out, "REPEATED PROMPTS (≥3x)")
		sort.Slice(f.RepeatedPrompts, func(i, j int) bool {
			return f.RepeatedPrompts[i].Count > f.RepeatedPrompts[j].Count
		})
		for _, r := range f.RepeatedPrompts {
			t := r.Text
			if len(t) > 60 {
				t = t[:60] + "…"
			}
			fmt.Fprintf(out, "  %3dx  %q\n", r.Count, t)
		}
	}
	fmt.Fprintln(out)
	renderRecommendations(out, f.Recommendations, stats)
}

// renderRecommendations leads with a BIGGEST WIN panel for the top
// rec (sorted by ImpactScore in the analyzer) and renders the rest
// as a numbered list with evidence + before/after templates +
// tangible savings (tokens / dollars / hours) derived from the
// operator's own turn averages.
func renderRecommendations(out fmtWriter, recs []prompts.Recommendation, stats prompts.TurnStats) {
	if len(recs) == 0 {
		return
	}
	first := recs[0]
	if first.ID == "no_data" || first.ID == "healthy" {
		fmt.Fprintln(out, "RECOMMENDATIONS")
		fmt.Fprintf(out, "  • %s\n", first.Title)
		return
	}
	fmt.Fprintln(out, "BIGGEST WIN")
	fmt.Fprintf(out, "  %s\n", first.Title)
	if first.Why != "" {
		fmt.Fprintf(out, "  %s\n", first.Why)
	}
	if first.Frequency > 0 {
		fmt.Fprintf(out, "  Seen %dx; estimated %d turns/month saved if fixed%s\n",
			first.Frequency, first.EstimatedMonthlyTurnsSaved, savingsSuffix(first, stats))
	}
	if first.Before != "" && first.After != "" {
		fmt.Fprintf(out, "  Before: %q\n", first.Before)
		fmt.Fprintf(out, "  After:  %q\n", first.After)
	}
	if len(first.Evidence) > 0 {
		fmt.Fprintln(out, "  Examples from your data:")
		for _, e := range first.Evidence {
			fmt.Fprintf(out, "      • %q\n", truncateForRec(e, 60))
		}
	}
	if len(recs) > 1 {
		fmt.Fprintln(out)
		fmt.Fprintln(out, "ALSO WORTH FIXING")
		for i, r := range recs[1:] {
			fmt.Fprintf(out, "  %d. %s\n", i+1, r.Title)
			if r.Frequency > 0 {
				fmt.Fprintf(out, "     %dx, ~%d turns/month%s\n",
					r.Frequency, r.EstimatedMonthlyTurnsSaved, savingsSuffix(r, stats))
			}
			if r.Before != "" && r.After != "" {
				fmt.Fprintf(out, "     %q  →  %q\n", r.Before, r.After)
			}
		}
	}
}

// savingsSuffix projects per-month turn savings into tangible
// units (tokens / dollars / hours) using the operator's own
// per-turn averages from TurnStats. Returns the empty string when
// stats are unavailable so the renderer doesn't append " (0 tokens
// / $0 / 0h)" garbage.
func savingsSuffix(r prompts.Recommendation, stats prompts.TurnStats) string {
	if stats.TotalTurns == 0 || r.EstimatedMonthlyTurnsSaved == 0 {
		return "."
	}
	s := prompts.ProjectSavings(r, stats)
	return fmt.Sprintf(" — ≈ %s tokens, $%.2f, %.1fh of your time.",
		compactInt(s.Tokens), s.CostUSD, s.HoursSaved)
}

func compactInt(n int64) string {
	switch {
	case n >= 1_000_000_000:
		return fmt.Sprintf("%.2fB", float64(n)/1e9)
	case n >= 1_000_000:
		return fmt.Sprintf("%.2fM", float64(n)/1e6)
	case n >= 1_000:
		return fmt.Sprintf("%.1fk", float64(n)/1e3)
	}
	return fmt.Sprintf("%d", n)
}

func truncateForRec(s string, n int) string {
	if len(s) <= n {
		return s
	}
	return s[:n] + "…"
}

func pctOf(n, total int) float64 {
	if total == 0 {
		return 0
	}
	return 100 * float64(n) / float64(total)
}
