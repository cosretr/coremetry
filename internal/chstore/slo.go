package chstore

import (
	"context"
	"fmt"
	"time"
)

// SLI types — kept tiny on purpose. availability counts ok-vs-error spans
// against a service (and optional operation); latency counts spans whose
// duration is within the threshold as "good".
const (
	SLITypeAvailability = "availability"
	SLITypeLatency      = "latency"
)

type SLO struct {
	ID          string  `json:"id"`
	Name        string  `json:"name"`
	Service     string  `json:"service"`
	SLIType     string  `json:"sliType"`
	Target      float64 `json:"target"`      // 0..1, e.g. 0.99
	WindowDays  uint16  `json:"windowDays"`  // rolling window
	ThresholdMs float64 `json:"thresholdMs"` // latency only
	Operation   string  `json:"operation"`   // optional span-name filter
	CreatedAt   int64   `json:"createdAt"`   // unix ns
}

// SLOStatus is the computed runtime state of an SLO. Burn rate > 1 means
// the budget is being consumed faster than its replenishment rate.
type SLOStatus struct {
	Total           uint64  `json:"total"`           // events in window
	Good            uint64  `json:"good"`            // satisfying events
	Bad             uint64  `json:"bad"`             // total - good
	SLI             float64 `json:"sli"`             // good/total, 0..1
	BudgetRemaining float64 `json:"budgetRemaining"` // 0..1, share of error budget left
	BurnRate        float64 `json:"burnRate"`        // current_error_rate / (1 - target)
	Healthy         bool    `json:"healthy"`         // SLI >= target; NoData'da false
	// NoData (v0.10.801, denetim S2 — Honeycomb "No Events"): pencerede
	// hiç olay yok. Öncesi SLI 1.0 + Healthy=true "vacuously" yeşildi; yanlış
	// operasyon adı / servis adı değişimi kalıcı %100 gösteriyordu. Ne
	// sağlıklı ne ihlal: FE gri "Olay yok".
	NoData bool `json:"noData,omitempty"`
	// Hint (v0.10.801) — SLI tanım kontrolü ipucu: olay yok / hiç başarısız
	// olmuyor / her olay başarısız. Boş = ipucu yok.
	Hint string `json:"hint,omitempty"`
}

// sloNeverFailsMinTotal — "SLI hiç başarısız olmuyor" ipucu için taban:
// küçük pencerelerde %100 doğaldır; bu kadar olay görüp sıfır kötü, tanımı
// sorgulatır (Honeycomb: "%100 sonsuza dek = yanlış SLI").
const sloNeverFailsMinTotal = 1000

// sloStatusFrom — SAF (v0.10.801): sayımlardan durum. ComputeSLOStatus
// yalnız sayar, matematik ve ipuçları burada; tablo-testli.
func sloStatusFrom(total, good uint64, target float64) SLOStatus {
	st := SLOStatus{Total: total, Good: good}
	if total > 0 {
		st.Bad = total - good
		st.SLI = float64(good) / float64(total)
	} else {
		// Olay yok: SLI 1.0 bütçe matematiğini bozmasın diye kalır, ama
		// sağlıklı DEĞİL — pencere boşsa hedef "karşılanmış" sayılmaz.
		st.SLI = 1.0
		st.NoData = true
		st.Hint = "Olay yok: servis / operasyon adı ve pencereyi kontrol et (yanlış ad kalıcı yeşil görünürdü)"
	}
	st.Healthy = !st.NoData && st.SLI >= target
	if !st.NoData {
		switch {
		case st.Bad == 0 && st.Total >= sloNeverFailsMinTotal:
			st.Hint = "SLI hiç başarısız olmuyor: eşik / operasyon tanımını kontrol et"
		case st.Bad == st.Total:
			st.Hint = "Her olay başarısız: SLI mantığı ters olabilir"
		}
	}
	budget := 1.0 - target
	if budget > 0 {
		used := 1.0 - st.SLI
		st.BudgetRemaining = 1.0 - (used / budget)
		if st.BudgetRemaining < 0 {
			st.BudgetRemaining = 0
		}
		st.BurnRate = used / budget
	}
	return st
}

func (s *Store) ListSLOs(ctx context.Context) ([]SLO, error) {
	rows, err := s.conn.Query(ctx, `
		SELECT id, name, service, sli_type, target, window_days, threshold_ms,
		       operation, toUnixTimestamp64Nano(created_at)
		FROM slos FINAL
		ORDER BY created_at DESC`)
	if err != nil {
		return nil, err
	}
	defer rows.Close()
	var out []SLO
	for rows.Next() {
		var o SLO
		if err := rows.Scan(&o.ID, &o.Name, &o.Service, &o.SLIType, &o.Target,
			&o.WindowDays, &o.ThresholdMs, &o.Operation, &o.CreatedAt); err != nil {
			return nil, err
		}
		out = append(out, o)
	}
	return out, rows.Err()
}

func (s *Store) GetSLO(ctx context.Context, id string) (*SLO, error) {
	row := s.conn.QueryRow(ctx, `
		SELECT id, name, service, sli_type, target, window_days, threshold_ms,
		       operation, toUnixTimestamp64Nano(created_at)
		FROM slos FINAL
		WHERE id = ? LIMIT 1`, id)
	var o SLO
	if err := row.Scan(&o.ID, &o.Name, &o.Service, &o.SLIType, &o.Target,
		&o.WindowDays, &o.ThresholdMs, &o.Operation, &o.CreatedAt); err != nil {
		if err.Error() == "sql: no rows in result set" {
			return nil, nil
		}
		return nil, err
	}
	return &o, nil
}

func (s *Store) UpsertSLO(ctx context.Context, o SLO) error {
	if o.WindowDays == 0 {
		o.WindowDays = 30
	}
	batch, err := s.conn.PrepareBatch(ctx,
		"INSERT INTO slos (id, name, service, sli_type, target, window_days, threshold_ms, operation)")
	if err != nil {
		return fmt.Errorf("prepare slos: %w", err)
	}
	if err := batch.Append(o.ID, o.Name, o.Service, o.SLIType,
		o.Target, o.WindowDays, o.ThresholdMs, o.Operation); err != nil {
		return fmt.Errorf("append slo: %w", err)
	}
	return batch.Send()
}

func (s *Store) DeleteSLO(ctx context.Context, id string) error {
	return s.conn.Exec(ctx, `ALTER TABLE slos DELETE WHERE id = ?`, id)
}

// sloLatencyEntryWhere scopes a latency SLI to the spans where the service
// ANSWERS something, mirroring lib/entrySpans.ts on the read side (v0.9.241).
//
// A latency SLI counts "spans under the threshold ÷ all spans". Over the full
// span population that denominator is dominated by the service's own outbound
// calls — DB clients at a fraction of a millisecond, hundreds of thousands of
// them — so the ratio measures the database, not the service. Measured in
// production on one service over an hour: 241,919 entry spans, all-span SLI
// 99.99%, entry-span SLI 99.85%. The gap is small HERE only because this
// service's real p99 (99ms) already sits under its 150ms threshold; on a
// service whose entry spans are slow, the all-span form hides the breach
// entirely behind the client-span majority.
//
// server + consumer, same as the UI: handling a request and processing a
// queue message are both the service's own work.
const sloLatencyEntryWhere = " AND kind IN ('server','consumer')"

// ComputeSLOStatus derives total/good counts within the SLO's rolling window.
// Availability reads the summary MV (count + error per 5m bucket — no raw-spans
// scan); latency needs a per-span threshold compare so it reads `spans`, bounded
// by max_execution_time. Called once per SLO by the (cached) /api/slos list.
func (s *Store) ComputeSLOStatus(ctx context.Context, o SLO) (*SLOStatus, error) {
	if o.Service == "" {
		return nil, fmt.Errorf("slo service is required")
	}
	since := time.Now().Add(-time.Duration(o.WindowDays) * 24 * time.Hour)

	var total, good uint64
	switch o.SLIType {
	case SLITypeAvailability:
		// v0.8.200 (scale-audit) — availability = (count - errors)/count, which
		// the summary MVs already pre-aggregate per (service[, operation], 5m).
		// Reading the MV instead of raw `spans` turns what was a 30-day
		// billion-span scan — looped over EVERY SLO on each /api/slos load — into
		// a cheap state merge over a few thousand bucket rows.
		mv := "service_summary_5m"
		nameClause := ""
		args := []any{o.Service, since}
		if o.Operation != "" {
			mv = "operation_summary_5m"
			nameClause = " AND name = ?"
			args = append(args, o.Operation)
		}
		q := "SELECT countMerge(span_count_state) AS total, " +
			// v0.9.232 — the bare subtraction yields Int64 in ClickHouse, and the
			// driver refuses Int64 → *uint64. It failed at SCAN time, was logged
			// and swallowed, so every availability SLO had silently shown no
			// status since v0.8.200. greatest(...,0) keeps the cast total —
			// errors are a subset of spans, so it can only ever clamp a
			// merge-skew underflow.
			"toUInt64(greatest(countMerge(span_count_state) - countIfMerge(error_count_state), 0)) AS good " +
			"FROM " + mv + " WHERE service_name = ? AND time_bucket >= ?" + nameClause +
			" SETTINGS max_execution_time = 20"
		if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &good); err != nil {
			return nil, err
		}
	case SLITypeLatency:
		// v0.10.518 — spanmetrics_1m t-digest inverse CDF (slo_latency_mv.go)
		// when the MV covers the window; raw spans only as the cutover/TTL
		// fallback. Prod: 140-SLO fan-out timed out at 20 s on the raw scan.
		if sloLatencyMVEligible(since, s.spanmetricsCoverageStart(ctx)) {
			q := sloLatencyMVSQL(s.spanmetricsSourceFor("spanmetrics_1m"), o.Operation != "", false, 20)
			args := []any{o.Service, since}
			if o.Operation != "" {
				args = append(args, o.Operation)
			}
			var qs []float64
			if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &qs); err != nil {
				return nil, err
			}
			good = sloGoodCount(total, sloGoodFraction(sloLatencyLevels, qs, o.ThresholdMs*1e6))
			break
		}
		// "good" = duration under the threshold — a per-span compare the MVs
		// don't pre-compute, so raw spans, but BOUNDED (this was an uncapped
		// 30-day scan before v0.8.200). service_name + time prefix-prunes.
		q := "SELECT count() AS total, countIf(duration <= ?) AS good FROM spans " +
			"WHERE service_name = ? AND time >= ?" + sloLatencyEntryWhere
		args := []any{o.ThresholdMs * 1e6, o.Service, since}
		if o.Operation != "" {
			q += " AND name = ?"
			args = append(args, o.Operation)
		}
		q += " SETTINGS max_execution_time = 20"
		if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &good); err != nil {
			return nil, err
		}
	default:
		return nil, fmt.Errorf("unknown sli_type: %s", o.SLIType)
	}

	st := sloStatusFrom(total, good, o.Target) // v0.10.801 — saf matematik + NoData/ipucu
	return &st, nil
}

// BurnPoint is one bucket of the per-day burn-rate timeseries
// surfaced as a sparkline on the /slos overview (v0.5.150).
// Time is the bucket-start (UTC, day granularity for a 7d view).
// BurnRate is (1-SLI_bucket)/(1-target) — same definition as
// SLOStatus.BurnRate, just over the day instead of the SLO's
// rolling window.
type BurnPoint struct {
	Time     int64   `json:"time"` // unix ns, bucket start
	Total    uint64  `json:"total"`
	Good     uint64  `json:"good"`
	BurnRate float64 `json:"burnRate"` // >1 = eating budget faster than allowed
}

// ComputeSLOBurnSeries returns a per-day burn-rate timeseries
// over the past `days` days. Used by the SLO list page to
// render a sparkline next to each row so the operator can spot
// "this SLO has been eroding for the last 3 days" without
// opening the detail view. Day granularity is enough for a 7-30
// day picture; tighter granularity would just add noise to the
// thumb-sized chart.
func (s *Store) ComputeSLOBurnSeries(ctx context.Context, o SLO, days int) ([]BurnPoint, error) {
	if o.Service == "" {
		return nil, fmt.Errorf("slo service is required")
	}
	if days <= 0 || days > 90 {
		days = 7
	}
	since := time.Now().Add(-time.Duration(days) * 24 * time.Hour)

	// v0.9.237 (scale-audit M3) — availability rides the summary MV, the
	// same routing ComputeSLOStatus (v0.8.200) and ComputeSLOBurnRate
	// (v0.9.231) already use. The MV's 5m buckets roll up to days with a
	// plain toStartOfDay on time_bucket, so the day series is identical
	// while the scan drops from N days of raw spans to a state merge.
	//
	// toUInt64(greatest(...)) is NOT cosmetic: the bare subtraction yields
	// Int64 and the driver refuses Int64 → *uint64 at SCAN time. That is
	// exactly the bug v0.9.232 found in the two sibling functions, where it
	// had silently blanked every availability SLO for a month.
	var q string
	args := []any{o.Service, since}
	if o.SLIType == SLITypeAvailability {
		mv := "service_summary_5m"
		nameClause := ""
		if o.Operation != "" {
			mv = "operation_summary_5m"
			nameClause = " AND name = ?"
		}
		q = `
		SELECT toStartOfDay(time_bucket) AS bucket,
		       countMerge(span_count_state) AS total,
		       toUInt64(greatest(countMerge(span_count_state) - countIfMerge(error_count_state), 0)) AS good
		FROM ` + mv + `
		WHERE service_name = ? AND time_bucket >= ?` + nameClause
		if o.Operation != "" {
			args = append(args, o.Operation)
		}
	} else if o.SLIType == SLITypeLatency {
		// v0.10.518 — per-day t-digest merge on spanmetrics_1m when covered
		// (slo_latency_mv.go); the raw per-span compare stays as the
		// cutover/TTL fallback.
		if sloLatencyMVEligible(since, s.spanmetricsCoverageStart(ctx)) {
			if o.Operation != "" {
				args = append(args, o.Operation)
			}
			return s.sloBurnSeriesFromMV(ctx, o, sloLatencyMVSQL(
				s.spanmetricsSourceFor("spanmetrics_1m"), o.Operation != "", true, 15), args)
		}
		q = `
		SELECT toStartOfDay(time)            AS bucket,
		       count()                       AS total,
		       ` + fmt.Sprintf("countIf(duration <= %f)", o.ThresholdMs*1e6) + ` AS good
		FROM spans
		WHERE service_name = ? AND time >= ?` + sloLatencyEntryWhere
		if o.Operation != "" {
			q += ` AND name = ?`
			args = append(args, o.Operation)
		}
	} else {
		return nil, fmt.Errorf("unknown sli_type: %s", o.SLIType)
	}
	q += `
		GROUP BY bucket
		ORDER BY bucket
		SETTINGS max_execution_time = 15`
	rows, err := s.conn.Query(ctx, q, args...)
	if err != nil {
		return nil, err
	}
	defer rows.Close()
	budget := 1.0 - o.Target
	out := []BurnPoint{}
	for rows.Next() {
		var bucket time.Time
		var total, good uint64
		if err := rows.Scan(&bucket, &total, &good); err != nil {
			return nil, err
		}
		bp := BurnPoint{
			Time:  bucket.UnixNano(),
			Total: total, Good: good,
		}
		if total > 0 && budget > 0 {
			sli := float64(good) / float64(total)
			used := 1.0 - sli
			bp.BurnRate = used / budget
		}
		out = append(out, bp)
	}
	return out, rows.Err()
}

// sloBurnSeriesFromMV — v0.10.518: per-day latency burn points from the
// spanmetrics_1m quantile curve (one row per day: bucket, total, qs).
func (s *Store) sloBurnSeriesFromMV(ctx context.Context, o SLO, q string, args []any) ([]BurnPoint, error) {
	rows, err := s.conn.Query(ctx, q, args...)
	if err != nil {
		return nil, err
	}
	defer rows.Close()
	budget := 1.0 - o.Target
	out := []BurnPoint{}
	for rows.Next() {
		var bucket time.Time
		var total uint64
		var qs []float64
		if err := rows.Scan(&bucket, &total, &qs); err != nil {
			return nil, err
		}
		good := sloGoodCount(total, sloGoodFraction(sloLatencyLevels, qs, o.ThresholdMs*1e6))
		bp := BurnPoint{Time: bucket.UnixNano(), Total: total, Good: good}
		if total > 0 && budget > 0 {
			bp.BurnRate = (1.0 - float64(good)/float64(total)) / budget
		}
		out = append(out, bp)
	}
	return out, rows.Err()
}

// SLOForecast — v0.6.30. Given an SLO + its current short-window
// burn rate + the remaining error budget, projects when the
// budget will be fully consumed at the current pace. Operator-
// facing answer to "is this going to breach before the weekend?"
//
// At BurnRate ≤ 1 the budget grows back faster than it's
// consumed; HoursToExhaust = +Inf (we represent it as 0 with
// SafeBurn=true so the UI can render an "OK" pill).
//
// At BurnRate > 1 the math is:
//
//	hoursToExhaust = budgetRemaining × (windowDays × 24) / burnRate
//
// rounded down. When that value ≤ 24h, WillBreachWithin24h is
// flagged so the /slos page can promote the row to the operator's
// attention without an actual alert wired up yet.
type SLOForecast struct {
	BurnRate            float64 `json:"burnRate"`            // short-window burn rate
	BurnWindowSec       int     `json:"burnWindowSec"`       // window the rate was measured over
	BudgetRemaining     float64 `json:"budgetRemaining"`     // 0..1 — copied from status
	HoursToExhaust      float64 `json:"hoursToExhaust"`      // projected; 0 when SafeBurn
	WillBreachWithin24h bool    `json:"willBreachWithin24h"` // operator-attention flag
	SafeBurn            bool    `json:"safeBurn"`            // burnRate ≤ 1, no forecast needed
}

// projectBurnHours is the pure-math half of ComputeSLOForecast,
// extracted for testability. budgetRemaining is 0..1,
// windowHours is the SLO's full window in hours (e.g. 30 days =
// 720), rate is the current short-window burn rate. Returns
// hours-to-exhaust + the SafeBurn flag + the 24h-breach flag.
func projectBurnHours(budgetRemaining, windowHours, rate float64) (hours float64, safe bool, within24h bool) {
	if rate <= 1.0 {
		return 0, true, false
	}
	if budgetRemaining <= 0 {
		return 0, false, true
	}
	hours = budgetRemaining * windowHours / rate
	if hours <= 24.0 {
		within24h = true
	}
	return hours, false, within24h
}

// ComputeSLOForecast runs ComputeSLOStatus + ComputeSLOBurnRate
// (over `burnWindow`) and combines them into a forecast. Two
// CH reads — both bounded by service+time WHEREs so total cost
// is tiny.
func (s *Store) ComputeSLOForecast(ctx context.Context, o SLO, burnWindow time.Duration) (*SLOForecast, error) {
	if burnWindow <= 0 {
		burnWindow = time.Hour
	}
	status, err := s.ComputeSLOStatus(ctx, o)
	if err != nil {
		return nil, fmt.Errorf("slo status: %w", err)
	}
	rate, _, err := s.ComputeSLOBurnRate(ctx, o, burnWindow)
	if err != nil {
		return nil, fmt.Errorf("slo burn rate: %w", err)
	}
	out := &SLOForecast{
		BurnRate:        rate,
		BurnWindowSec:   int(burnWindow.Seconds()),
		BudgetRemaining: status.BudgetRemaining,
	}
	hours, safe, within24h := projectBurnHours(
		status.BudgetRemaining, float64(o.WindowDays)*24.0, rate)
	out.HoursToExhaust = hours
	out.SafeBurn = safe
	out.WillBreachWithin24h = within24h
	return out, nil
}

// ComputeSLOBurnRate calculates the burn rate over a SHORT
// look-back window — used by the 2-window burn-rate alarm
// pattern (Google SRE Workbook). The status method above runs
// over the SLO's full rolling window (e.g. 30 days), which
// smooths out short bursts; for alerting we want to detect
// "currently burning fast" within the last 1h or 6h.
//
// Returned rate units: same as BurnRate on SLOStatus —
// (1 − SLI_window) / (1 − target). > 1 means the budget would
// be exhausted before the SLO window completes.
func (s *Store) ComputeSLOBurnRate(ctx context.Context, o SLO, window time.Duration) (float64, uint64, error) {
	if o.Service == "" {
		return 0, 0, fmt.Errorf("slo service is required")
	}
	since := time.Now().Add(-window)
	var total, good uint64

	// v0.9.231 (scale-audit) — the availability branch read raw `spans`
	// while its sibling ComputeSLOStatus has ridden the summary MVs since
	// v0.8.200. That mattered more here, not less: the burn evaluator calls
	// this FOUR times per SLO per tick (two policies × long/short window,
	// internal/evaluator/slo_burn.go), serially across every SLO, over
	// windows up to 24h. countMerge/countIfMerge over 5m buckets give the
	// identical ratio.
	//
	// Sub-5m windows can't be reconstructed from 5m buckets, so those still
	// go raw — the same boundary UseSummaryMV draws for the evaluator.
	// v0.10.518 — latency rides spanmetrics_1m too (same 5m-aligned window
	// start as availability; the evaluator calls this four times per SLO
	// per tick). Sub-5m and pre-coverage windows stay raw below.
	if o.SLIType == SLITypeLatency && UseSummaryMV(window) &&
		sloLatencyMVEligible(MVWindowStart(time.Now(), window), s.spanmetricsCoverageStart(ctx)) {
		q := sloLatencyMVSQL(s.spanmetricsSourceFor("spanmetrics_1m"), o.Operation != "", false, 10)
		args := []any{o.Service, MVWindowStart(time.Now(), window)}
		if o.Operation != "" {
			args = append(args, o.Operation)
		}
		var qs []float64
		if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &qs); err != nil {
			return 0, 0, err
		}
		good = sloGoodCount(total, sloGoodFraction(sloLatencyLevels, qs, o.ThresholdMs*1e6))
	} else if o.SLIType == SLITypeAvailability && UseSummaryMV(window) {
		mv := "service_summary_5m"
		nameClause := ""
		args := []any{o.Service, MVWindowStart(time.Now(), window)}
		if o.Operation != "" {
			mv = "operation_summary_5m"
			nameClause = " AND name = ?"
			args = append(args, o.Operation)
		}
		q := "SELECT countMerge(span_count_state) AS total, " +
			// v0.9.232 — the bare subtraction yields Int64 in ClickHouse, and the
			// driver refuses Int64 → *uint64. It failed at SCAN time, was logged
			// and swallowed, so every availability SLO had silently shown no
			// status since v0.8.200. greatest(...,0) keeps the cast total —
			// errors are a subset of spans, so it can only ever clamp a
			// merge-skew underflow.
			"toUInt64(greatest(countMerge(span_count_state) - countIfMerge(error_count_state), 0)) AS good " +
			"FROM " + mv + " WHERE service_name = ? AND time_bucket >= ?" + nameClause +
			" SETTINGS max_execution_time = 10"
		if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &good); err != nil {
			return 0, 0, err
		}
	} else {
		var goodExpr string
		switch o.SLIType {
		case SLITypeAvailability:
			goodExpr = "countIf(status_code != 'error')"
		case SLITypeLatency:
			// Per-span threshold compare — no MV pre-computes it.
			goodExpr = fmt.Sprintf("countIf(duration <= %f)", o.ThresholdMs*1e6)
		default:
			return 0, 0, fmt.Errorf("unknown sli_type: %s", o.SLIType)
		}
		// v0.9.231 — was inheriting the 60s connection default, twice the
		// ceiling every sibling read sets.
		q := `SELECT count() AS total, ` + goodExpr + ` AS good
	      FROM spans
	      WHERE service_name = ? AND time >= ?`
		// v0.9.241 — entry scope on LATENCY only. Availability's raw branch is
		// the sub-5m fallback for the MV path above, and the MV carries no kind
		// dimension; filtering here would make the two windows of the same SLO
		// disagree, which is worse than the distortion.
		if o.SLIType == SLITypeLatency {
			q += sloLatencyEntryWhere
		}
		args := []any{o.Service, since}
		if o.Operation != "" {
			q += ` AND name = ?`
			args = append(args, o.Operation)
		}
		q += ` SETTINGS max_execution_time = 10`
		if err := s.conn.QueryRow(ctx, q, args...).Scan(&total, &good); err != nil {
			return 0, 0, err
		}
	}
	if total == 0 {
		return 0, 0, nil
	}
	sli := float64(good) / float64(total)
	budget := 1.0 - o.Target
	if budget <= 0 {
		return 0, total, nil
	}
	used := 1.0 - sli
	return used / budget, total, nil
}
