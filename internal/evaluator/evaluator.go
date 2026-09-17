// Package evaluator runs alert rules on a fixed interval, opens problems
// when their condition is breached, and resolves problems whose breach is
// no longer present. Built-in rules cover the typical APM signals
// (error rate, P99 latency, request-rate drops).
package evaluator

import (
	"context"
	"crypto/rand"
	"encoding/hex"
	"fmt"
	"log"
	"strconv"
	"strings"
	"sync"
	"sync/atomic"
	"time"

	"github.com/cilcenk/coremetry/internal/cache"
	"github.com/cilcenk/coremetry/internal/chstore"
	"github.com/cilcenk/coremetry/internal/logstore"
	"github.com/cilcenk/coremetry/internal/notify"
	"github.com/cilcenk/coremetry/internal/vmetrics"
)

const lockKey = "coremetry:lock:evaluator"

type Evaluator struct {
	store *chstore.Store
	logs  logstore.Store // v0.5.242 — drives the saved-search log alert path
	// vmetrics — v0.9.1213: JVM GC alarmlarının VM dönüşü. nil = VM
	// kurulmamış, GC değerlendirmesi emekli kalır (runtime_vm.go).
	vmetrics *vmetrics.Service
	// pollerSourceLive — v0.10.605 (SetPollerSourceLive); nil = tüm poller Problem'leri muaf.
	pollerSourceLive func(subject string) bool
	interval         time.Duration
	lock             cache.Lock
	leader           *cache.LeaderHolder // v0.5.429
	notifier         *notify.Notifier

	// escCfg memoises the age-escalation settings (v0.9.248). The
	// per-service reconcile paths (db_capacity, runtime_pods) clamp
	// to the escalation floor on EVERY sample, and GetSetting is an
	// uncached CH query with FINAL — without a memo one tick would
	// fan out into a system_settings read per service. escMu guards
	// it the same way breachMu guards breachSince.
	escMu  sync.Mutex
	escCfg chstore.ProblemEscalationConfig
	escAt  time.Time

	// breachSince tracks when a (rule, service) tuple first
	// breached its threshold. Used by the v0.5.127 sustained-
	// breach gate (AlertRule.ForSec): a problem only opens once
	// the breach has persisted ForSec seconds. Reset to zero
	// time the moment the breach clears. Map mutex'd via
	// breachMu — the evaluator runs single-leader per tick but
	// the seed call + tests can touch it concurrently.
	breachSince map[breachKey]time.Time
	// lastResolved stamps when a problem on (rule, service) last
	// auto-resolved. Used by the v0.5.129 cooldown gate
	// (AlertRule.CooldownSec): re-opens within the cooldown
	// window are suppressed to absorb threshold-jitter flap.
	lastResolved map[breachKey]time.Time
	breachMu     sync.Mutex
	// stamps mirrors breachSince/lastResolved writes to Redis and
	// lazily hydrates in-memory misses, so the sustain/cooldown
	// clocks survive leader failover + rolling deploys (v0.8.354 —
	// HA audit 🟡#2; see stamps.go). nil or Noop = in-memory only.
	stamps cache.Cache

	// watcherLastRun paces imported ES watcher rules (v0.9.x) on
	// their own schedule interval: a 5m-interval watch runs when
	// due, not on every 1m tick. In-memory only by design — a
	// leader change resets the clocks and the worst case is one
	// early re-run (accepted trade-off; the monitor runner's
	// interval_sec pacing has the same shape). Guarded by watcherMu.
	watcherLastRun map[string]time.Time
	// diskSeries — self-disk-eta'nın (v0.9.1279, selfhealth.go) disk
	// başına doluluk örnekleri. BELLEKTE ve YALNIZ liderde: disk
	// geçmişini kalıcılaştırmak yeni bir tablo + yeni bir yazma yolu
	// demekti, oysa soru "önümüzdeki günlerde dolar mı" ve altı saatlik
	// bir pencere onu cevaplıyor. Lider değişimi seriyi sıfırlar →
	// yarım saat tahmin üretilmez (watcherLastRun ile aynı ömür
	// sözleşmesi: kabul edilmiş, sessiz-değil tarafta hata yapan bir
	// takas). diskMu, breachMu ile aynı gerekçeyle var.
	diskMu     sync.Mutex
	diskSeries map[string][]diskSample

	// volCache / volAt — self-volume-spike'ın (v0.9.1294,
	// selfhealth_volume.go) SON ÖLÇÜMÜ. Ölçüm saatlik, yaşam döngüsü
	// tik başına: iki tarama arasında bu önbellek yeniden sunulur, yoksa
	// sweepStaleProblems tazelenmeyen satırı üç dakikada bir kapatır ve
	// kural her saat yeniden açılıp bildirim yollardı. diskSeries ile
	// aynı ömür sözleşmesi — bellekte, yalnız liderde; lider değişimi
	// önbelleği sıfırlar ve bir sonraki tik gerçek bir ölçüm yapar
	// (kaybı bir MV sorgusu, kazancı sıfır kalıcılık borcu).
	volMu    sync.Mutex
	volCache []selfProblem
	volAt    time.Time

	// watcherFails — ardışık ölçüm hatası sayacı (v0.9.447): bozuk
	// kaynaklı (silinmiş index, ES yetkisi) watch'ların açık problemi
	// keep-alive'la ölümsüzleşiyordu. Guarded by watcherMu; girdiler
	// watcherLastRun ile aynı ömür sözleşmesini paylaşır.
	watcherFails map[string]int
	watcherMu    sync.Mutex

	// v0.9.550 — kalp atışı alanları (heartbeat.go).
	//
	// opened/resolved tik başına sıfırlanan sayaçlardır. Atomik
	// olmalarının sebebi eşzamanlılık değil (tik tek liderde
	// seridir), reconcile yollarının derinden çağırıyor olması ve
	// testlerin eşzamanlı dokunabilmesi — mutex'siz doğruluk
	// burada daha ucuz.
	opened   atomic.Int64
	resolved atomic.Int64
	// v0.9.588 — süreklilik izleri (tick_continuity.go). Yalnız lider
	// tikinden (seri, tek goroutine) yazılır ve okunur; kilit yok.
	//
	// lastTickAt — bu süreçteki bir önceki tikin başlangıcı.
	// contSince  — KESİNTİSİZ değerlendirmenin başladığı an. Sessiz-
	//              kaynak süpürmesi, bayatlığın kaynağının problem mi
	//              yoksa kendi kesintimiz mi olduğunu buradan ayırır.
	lastTickAt time.Time
	contSince  time.Time
	// version — kalp atışını yazan binary'nin kimliği. main'den
	// SetVersion ile geçer (evaluator main'i import edemez).
	// Bir dağıtım sonrası eski pod'un bayat kalp atışını taze
	// sanmamak için gerekli.
	version string
}

type breachKey struct {
	RuleID  string
	Service string
}

// New takes a cache.Lock so multiple Coremetry replicas only run the
// evaluation loop once per tick, and a notifier so PROBLEM OPENED
// transitions fan out to email/slack/etc.
func New(store *chstore.Store, interval time.Duration, lock cache.Lock, notifier *notify.Notifier) *Evaluator {
	if interval == 0 {
		interval = time.Minute
	}
	return &Evaluator{
		store:          store,
		interval:       interval,
		lock:           lock,
		leader:         cache.NewLeaderHolder(lock, lockKey, cache.LeaderTTL(interval)),
		notifier:       notifier,
		breachSince:    make(map[breachKey]time.Time),
		lastResolved:   make(map[breachKey]time.Time),
		watcherLastRun: make(map[string]time.Time),
		watcherFails:   make(map[string]int),
	}
}

// SetLogs wires the log backend so the saved-search alert path
// (rules with LogQuery != "") can count matches via logstore.
// Called from main() once buildLogStore has resolved the
// backend — keeps the New() constructor lean + avoids
// reordering boot-time wiring around the evaluator.
func (e *Evaluator) SetLogs(logs logstore.Store) { e.logs = logs }

// SetVMetrics — v0.9.1213 (JVM GC alarmlarının VM dönüşü). SetLogs
// emsali: boot sıralamasını bozmadan geç bağlanır. nil kalabilir
// (vmetrics kurulmadıysa) — runtime GC değerlendirmesi o durumda
// v0.9.1075 emekliliğinde kalır.
func (e *Evaluator) SetVMetrics(vm *vmetrics.Service) { e.vmetrics = vm }

// SetPollerSourceLive — v0.10.605: "bu poller kaynağı (özne ext:<ad>) hâlâ
// etkin mi?" sorusu. Bayat süpürme muafiyeti (592) yalnız YAŞAYAN kaynak
// için: silinen/kapatılan kaynağın ext-down/ext-cap Problem'leri artık
// süpürülür — yoksa hiçbir poller onları resolve etmez ve sonsuza dek açık
// kalırlardı. nil = 592 davranışı (hepsi muaf).
func (e *Evaluator) SetPollerSourceLive(fn func(subject string) bool) { e.pollerSourceLive = fn }

// Start runs the evaluation loop until ctx is cancelled. Built-in rules
// are seeded by every replica — that's safe (UpsertAlertRule is idempotent
// on id). Only the actual evaluation pass is leader-gated.
func (e *Evaluator) Start(ctx context.Context) {
	if err := e.seedBuiltinRules(ctx); err != nil {
		log.Printf("[evaluator] seed built-in rules: %v", err)
	}

	e.leader.Start(ctx)
	t := time.NewTicker(e.interval)
	defer t.Stop()

	e.runIfLeader(ctx) // run once immediately

	for {
		select {
		case <-ctx.Done():
			return
		case <-t.C:
			e.runIfLeader(ctx)
		}
	}
}

// runIfLeader skips the tick when another replica holds leadership.
// v0.5.429 — long-lived LeaderHolder; one pod owns the worker for
// its lifetime + refreshes the lease in the background.
// v0.9.550 — lider olmayan pod kalp atışı YAZMAZ. Yazsaydı iki pod
// aynı anahtarı çiğneyip birbirinin kaydını silerdi ve operatör
// "tik atıldı" görürken aslında hiçbir değerlendirme yapılmamış
// olabilirdi. Kalp atışı yalnız gerçekten değerlendirme yapanın
// kaydıdır — anahtarın bayatlaması "lider yok" halini de doğru
// şekilde gösterir.
func (e *Evaluator) runIfLeader(ctx context.Context) {
	if !e.leader.IsLeader() {
		return
	}

	// Tik başına deadline: asılı bir bağımlılık alarm üretimini
	// süresiz durduramasın (bkz. tickDeadline).
	tickCtx, cancel := context.WithTimeout(ctx, tickDeadline(e.interval))
	defer cancel()

	started := time.Now()
	e.opened.Store(0)
	e.resolved.Store(0)

	// v0.9.588 — süreklilik ÖNCE işlenir: sessiz-kaynak süpürmesi bu
	// tikin içinde koşuyor ve "bayatlığı ben mi ürettim" sorusunun
	// cevabına ihtiyacı var.
	e.noteTickContinuity(started)

	rules := e.evaluateAll(tickCtx)

	hb := Heartbeat{
		StartedAt:       started.UnixNano(),
		FinishedAt:      time.Now().UnixNano(),
		DurationMS:      time.Since(started).Milliseconds(),
		Rules:           rules,
		Opened:          int(e.opened.Load()),
		Resolved:        int(e.resolved.Load()),
		Leader:          true,
		ContinuousSince: e.contSince.UnixNano(),
	}
	// Deadline'a takılan tik BAŞARISIZDIR ve öyle kaydedilir.
	// Sessizce "bitti" yazmak, düzeltmeye çalıştığımız yanılgının
	// ta kendisi olurdu: operatör taze bir kalp atışı görüp
	// evaluator'ı sağlıklı sanardı.
	if err := tickCtx.Err(); err != nil {
		hb.Err = "tik süre sınırını aştı (" + tickDeadline(e.interval).String() + "): " + err.Error()
		log.Printf("[evaluator] %s", hb.Err)
	}
	e.writeHeartbeat(hb)
}

// ── Built-in rules ───────────────────────────────────────────────────────────
//
// Curated for banking-realistic baseline workloads — Coremetry's primary
// target. Pre-v0.4.87 we shipped 15 rules with sub-second thresholds
// (DB P99 >500ms, HTTP P99 >1s, etc.) which fired constantly on a real
// banking stack where Oracle calls + multi-hop transaction services
// routinely run 800ms-2s in steady state. That alarm fatigue erodes
// trust in every other alert.
//
// Two-tier default set (v0.8.262 — operator request: "built-in alert
// rule'larında hardening yap, gerçek alertler oluşsun, default
// gelsin"):
//
//	CRITICAL floor (5-min windows) — "really wrong", pages someone:
//	  error rate >15% · HTTP P99 >5s · DB P99 >5s · MQ consume P99 >2m
//	WARNING tier (10-min sustained) — real degradation forming, catch
//	  it before the floor trips:
//	  error rate >5% · HTTP P99 >3s · DB P99 >2.5s · MQ consume P99 >30s
//
// Every rule now carries the full anti-noise kit the engine already
// had but the defaults never used: MinSamples (v0.5.128 — no verdicts
// from a 3-span window), ForSec (v0.5.126 — breach must SUSTAIN, one
// spiky bucket doesn't open a problem), CooldownSec (v0.5.129 — no
// flap-reopen at the threshold boundary).
//
// Threshold history: pre-v0.4.87 shipped 15 sub-second rules that
// fired constantly on banking steady state (Oracle + multi-hop chains
// run 800ms–2s P99 normally) — alarm fatigue erased trust. v0.5.67
// slimmed near-duplicate transport error-rate rules into the service-
// wide error_rate. The warning tier deliberately sits ABOVE those
// documented steady-state ceilings (3s HTTP / 2.5s DB) with longer
// windows + sustain gates, so it flags true degradation, not morning
// warm-up.
var builtins = []chstore.AlertRule{
	// ── Critical floor ──────────────────────────────────────────
	// Service-wide error rate. 15% is the "something is clearly
	// failing" floor — normal failed-card-transactions noise
	// stays well below. Subsumes HTTP-5xx, DB-error, and
	// RPC-error sub-rates (all flow into this metric).
	{ID: "builtin-error-rate-15pct", Name: "Critical error rate (>15% over 5 min)",
		Metric: "error_rate", Comparator: ">", Threshold: 15, WindowSec: 5 * 60,
		Severity: "critical", Enabled: true, BuiltIn: true,
		MinSamples: 50, ForSec: 120, CooldownSec: 300},

	// v0.10.207 (operatör isteği): başarısızlık BAŞARIYI aşarsa — servis
	// genelinde hata payı > %50 ⇔ error_count > success_count. 15%'lik
	// kural genel bozulmayı yakalar; bu kural "çoğunluk artık hata"
	// çizgisinin kendisini adlandırır ve düşük hacimde de anlamlı olduğu
	// için tabanı daha alçak (20 örnek). Aynı ölçü ailesi (service_summary_5m,
	// TÜM span'ler) — giriş-span/trace kapsamı farkı için bkz. commit gövdesi.
	{ID: "builtin-error-majority-50pct", Name: "Failures exceed successes (>50% over 5 min)",
		Metric: "error_rate", Comparator: ">", Threshold: 50, WindowSec: 5 * 60,
		Severity: "critical", Enabled: true, BuiltIn: true,
		MinSamples: 20, ForSec: 120, CooldownSec: 300},

	// HTTP latency. P99 >5s in a banking call chain is SLO-
	// violating territory regardless of which service.
	{ID: "builtin-http-p99-5s", Name: "HTTP P99 latency >5s (5 min)",
		Metric: "http_p99_ms", Comparator: ">", Threshold: 5000, WindowSec: 5 * 60,
		Severity: "critical", Enabled: true, BuiltIn: true,
		MinSamples: 50, ForSec: 120, CooldownSec: 300},

	// Database latency. 5s is when the DB is actually broken
	// (lock storm, undersized, network blip) — not warm-up.
	{ID: "builtin-db-p99-5s", Name: "DB P99 latency >5s (5 min)",
		Metric: "db_p99_ms", Comparator: ">", Threshold: 5000, WindowSec: 5 * 60,
		Severity: "critical", Enabled: true, BuiltIn: true,
		MinSamples: 30, ForSec: 120, CooldownSec: 300},

	// Message-queue consumer lag. 2 minutes processing P99 on a
	// Kafka / IBM MQ consumer is real back-pressure. Producer
	// errors fold into error_rate so we don't double-page.
	{ID: "builtin-mq-consume-p99-2m", Name: "MQ consume P99 >2 min — consumer lag (5 min)",
		Metric: "mq_consume_p99_ms", Comparator: ">", Threshold: 120000, WindowSec: 5 * 60,
		Severity: "critical", Enabled: true, BuiltIn: true,
		MinSamples: 20, ForSec: 120, CooldownSec: 300},

	// ── Warning tier (sustained degradation) ────────────────────
	// 5% sustained error rate for 10+ minutes is genuinely
	// abnormal against a 1-2% banking steady state; 3-min
	// sustain + 100-sample floor keep single bad buckets and
	// low-traffic services quiet.
	{ID: "builtin-warn-error-rate-5pct", Name: "Elevated error rate (>5% sustained 10 min)",
		Metric: "error_rate", Comparator: ">", Threshold: 5, WindowSec: 10 * 60,
		Severity: "warning", Enabled: true, BuiltIn: true,
		MinSamples: 100, ForSec: 180, CooldownSec: 600},

	// 3s HTTP P99 sits above the documented 800ms–2s multi-hop
	// steady-state ceiling — sustained 10 min means real
	// degradation, with headroom before the 5s critical floor.
	{ID: "builtin-warn-http-p99-3s", Name: "HTTP P99 latency >3s (sustained 10 min)",
		Metric: "http_p99_ms", Comparator: ">", Threshold: 3000, WindowSec: 10 * 60,
		Severity: "warning", Enabled: true, BuiltIn: true,
		MinSamples: 100, ForSec: 180, CooldownSec: 600},

	// 2.5s DB P99 sustained — above the 500ms–1s warm steady
	// state banking datastores run, below the 5s "actually
	// broken" floor. Catches lock contention building up.
	{ID: "builtin-warn-db-p99-2500ms", Name: "DB P99 latency >2.5s (sustained 10 min)",
		Metric: "db_p99_ms", Comparator: ">", Threshold: 2500, WindowSec: 10 * 60,
		Severity: "warning", Enabled: true, BuiltIn: true,
		MinSamples: 60, ForSec: 180, CooldownSec: 600},

	// 30s consume P99 sustained = back-pressure forming well
	// before the 2-minute critical lag floor.
	{ID: "builtin-warn-mq-consume-p99-30s", Name: "MQ consume P99 >30s — back-pressure (sustained 10 min)",
		Metric: "mq_consume_p99_ms", Comparator: ">", Threshold: 30000, WindowSec: 10 * 60,
		Severity: "warning", Enabled: true, BuiltIn: true,
		MinSamples: 20, ForSec: 180, CooldownSec: 600},
}

// deprecatedBuiltinIDs lists IDs that USED TO be in the
// builtins slice. On boot we silently auto-disable any of
// them still enabled in the operator's alert_rules table so
// they stop generating noise on upgrade. Operator can
// re-enable from the UI if they actually want the rule;
// nothing is deleted (preserves any custom edits like
// runbookURL on the rule itself).
var deprecatedBuiltinIDs = []string{
	"builtin-http-5xx-5pct",   // subsumed by error_rate
	"builtin-db-error-5pct",   // subsumed by error_rate
	"builtin-rpc-error-10pct", // subsumed by error_rate
}

func (e *Evaluator) seedBuiltinRules(ctx context.Context) error {
	existing, err := e.store.ListAlertRules(ctx)
	if err != nil {
		return err
	}
	have := make(map[string]bool)
	byID := make(map[string]chstore.AlertRule, len(existing))
	for _, r := range existing {
		have[r.ID] = true
		byID[r.ID] = r
	}
	// Seed any new builtins that aren't in the table yet.
	for _, r := range builtins {
		if have[r.ID] {
			continue
		}
		r.CreatedAt = time.Now().UnixNano()
		if err := e.store.UpsertAlertRule(ctx, r); err != nil {
			log.Printf("[evaluator] seed %s: %v", r.ID, err)
		}
	}
	// Backfill the anti-noise kit onto builtin rows seeded by older
	// releases (v0.8.262): pre-hardening builtins carried
	// MinSamples/ForSec/CooldownSec = 0. Only zero fields are
	// filled — an operator's explicit non-zero setting is never
	// touched, and thresholds/windows/names are left alone entirely
	// (they may be customised).
	for _, def := range builtins {
		cur, ok := byID[def.ID]
		if !ok || !cur.BuiltIn {
			continue
		}
		next := cur
		if next.MinSamples == 0 {
			next.MinSamples = def.MinSamples
		}
		if next.ForSec == 0 {
			next.ForSec = def.ForSec
		}
		if next.CooldownSec == 0 {
			next.CooldownSec = def.CooldownSec
		}
		if next == cur {
			continue
		}
		if err := e.store.UpsertAlertRule(ctx, next); err != nil {
			log.Printf("[evaluator] harden builtin %s: %v", def.ID, err)
			continue
		}
		log.Printf("[evaluator] hardened builtin %s (minSamples=%d forSec=%d cooldownSec=%d)",
			def.ID, next.MinSamples, next.ForSec, next.CooldownSec)
	}
	// Auto-disable rules that USED TO be builtins but were
	// removed in a later release. Skips rules the operator
	// already disabled (idempotent) and never deletes, so any
	// runbookURL / threshold customisation survives the upgrade.
	for _, id := range deprecatedBuiltinIDs {
		r, ok := byID[id]
		if !ok || !r.Enabled {
			continue
		}
		if err := e.store.SetAlertRuleEnabled(ctx, id, false); err != nil {
			log.Printf("[evaluator] deprecate %s: %v", id, err)
			continue
		}
		log.Printf("[evaluator] disabled deprecated builtin %s (subsumed by error_rate)", id)
	}
	return nil
}

// ── Evaluation loop ──────────────────────────────────────────────────────────

// evaluateAll bir turu koşar ve DEĞERLENDİRİLEN kural sayısını döner
// (v0.9.550 — kalp atışı için; devre dışı kurallar sayılmaz). Dönüş
// değeri yalnız gözlemlenebilirlik içindir, akış kararı vermez.
func (e *Evaluator) evaluateAll(ctx context.Context) int {
	rules, err := e.store.ListAlertRules(ctx)
	if err != nil {
		log.Printf("[evaluator] list rules: %v", err)
		return 0
	}

	// Cache the recent service set so wildcard rules know what to
	// evaluate. v0.8.506: yalnız isim gerekiyor — GetServices(24h)
	// ham spans'te tam-gün agregasyon yapıyordu (MV-first ihlali);
	// isim listesi artık MV'den.
	serviceNames, err := e.store.ListActiveServiceNames(ctx, 24*time.Hour)
	if err != nil {
		log.Printf("[evaluator] services: %v", err)
		return 0
	}
	// v0.9.449 — request_rate< kuralları için taze hedef kümesi (L4).
	// Hata = nil = kapı devre dışı (fail-open).
	var freshSet map[string]bool
	if freshNames, ferr := e.store.ListActiveServiceNames(ctx, evalFreshWindow); ferr == nil {
		freshSet = make(map[string]bool, len(freshNames))
		for _, n := range freshNames {
			freshSet[n] = true
		}
	} else {
		log.Printf("[evaluator] fresh services (gate disabled this tick): %v", ferr)
	}

	// v0.8.352 (perf P2-A) — batched prefetch: ONE GROUP BY query per
	// DISTINCT (metric, window) pair (+ one per MinSamples count window)
	// instead of one measure + one count query per (rule, service). The
	// measured ~70k evaluator queries/hour collapse to ~tens; evaluateOne
	// consumes the maps below. See prefetch.go.
	pre := prefetchMeasures(ctx, e.store, rules, time.Now())

	// v0.8.520 (perf raporu #9) — açık problem seti tick başında TEK
	// FINAL taramayla çekilir; evaluateOne map'ten okur. Snapshot
	// hatasında nil geçer, evaluateOne nokta sorgusuna düşer.
	openSnap, snapErr := e.store.OpenProblemsSnapshot(ctx)
	if snapErr != nil {
		log.Printf("[evaluator] open-problems snapshot: %v (nokta sorgusuna düşülüyor)", snapErr)
		openSnap = nil
	}

	evaluated := 0
	for _, r := range rules {
		if !r.Enabled {
			continue
		}
		evaluated++
		// v0.8.342 (HA audit H9) — log-query rules evaluate ONCE per rule:
		// the KQL carries its own filters and evaluateLogQuery ignores the
		// service param, yet the wildcard expansion below used to fan the
		// SAME rule into one identical ES search per service — 1000
		// services = 1000 searches per tick, and during an ES brownout
		// each burned its timeout SEQUENTIALLY, stalling ALL alerting.
		if r.LogQuery != "" {
			e.evaluateLogQuery(ctx, r)
			continue
		}
		// Imported ES watcher rules (v0.9.x) evaluate ONCE per rule for
		// the same reason: the watch body carries its own filters and
		// the resulting Problem has no service dimension. Paced on the
		// watch's schedule interval inside evaluateWatcher.
		if r.WatcherJSON != "" {
			e.evaluateWatcher(ctx, r)
			continue
		}
		// v0.10.331 — hedefli kural (DB ifadesi): tek özne, servis döngüsü yok.
		if r.Target != nil {
			e.evaluateTargetRule(ctx, r, openSnap)
			continue
		}
		targets := ruleEvalTargets(r, serviceNames)
		if ruleNeedsFreshTargets(r) {
			targets = filterFreshTargets(targets, freshSet)
		}
		for _, svc := range targets {
			e.evaluateOne(ctx, r, svc, pre, openSnap)
		}
	}

	// SLO burn-rate alarms — independent of the user-defined
	// alert rules above. Each configured SLO gets two passes
	// (warning + critical) using the 2-window burn-rate
	// pattern from the Google SRE Workbook. Fires Problems on
	// the same pipeline as everything else, so the existing
	// notify / incident-attach / SSE wiring all picks up
	// burn-rate breaches without additional plumbing.
	e.evaluateSLOs(ctx)

	// DB capacity / saturation alarms (feature #5) — page off the
	// DB-receiver gauges (Oracle tablespace / sessions / processes,
	// defensively Postgres / MySQL connections + Redis evictions) that
	// the /databases dashboards only coloured cosmetically. Opens /
	// resolves Problems deduped per (instance, check) on this same
	// leader-locked tick, riding the existing notify / incident-attach
	// pipeline like every other Problem.
	e.evaluateDBCapacity(ctx)
	e.evaluateDBSlowStatements(ctx) // v0.10.325 — yavaş SQL → Problem (Kind=db → sahibi + SRE maili)

	// Runtime pod detector (v0.9.90) — JVM heap saturation + GC pause per
	// pod. Overview's Runtime panel only SHOWS these; this pass makes them
	// PAGEABLE. MetricExists-gated so a non-JVM install (local included)
	// never sees spurious Problems; same leader-lock / notify / dedup path.
	e.evaluateRuntimePods(ctx)

	// v0.9.572 — paylaşılan bağımlılık patlaması. Operatör raporu:
	// on beşten fazla servis aynı saniyede aynı ORA-18730 hatasını aldı
	// ve Coremetry on beş AYRI exception grubu gösterdi. Bu dedektör
	// ortak paydayı kuruyor: aynı tip + dar pencere + çok servis =
	// TEK bir problem. openSnap zaten elimizde (yukarıda tik başına bir
	// kez okundu), ek sorgu yok.
	e.evaluateSharedExceptionBursts(ctx, openSnap)

	// v0.9.609 (operatör isteği) — altyapı-ölümcül exception'lar.
	// UnknownHostException gibi "yeniden deneme düzeltmez, kendiliğinden
	// geçmez" sınıfı: tek oluşum bile anında P1. Aynı openSnap, ek okuma
	// yok.
	e.evaluateFatalExceptions(ctx, openSnap)

	// v0.9.1279 — SELF-HEALTH ailesi (Dynatrace-parite #8). "İzleme
	// sistemi kendisi öldü ve kimse bilmedi" sınıfı: ingest durması,
	// Distributed spool birikmesi, disk dolma projeksiyonu, ölü bildirim
	// kanalı. Tüm meta-görünürlük bugüne dek PASİF paneldi (sysstats.go,
	// cardinality.go) ve 2026-08-20 prod olayında 3.5 saatlik ölü ingest
	// tüm ekranlarda yeşil göründü. Aynı openSnap, ek problem sorgusu yok.
	e.evaluateSelfHealth(ctx, openSnap)

	// Escalation sweep — bump severity on problems that have
	// been open past the configured threshold without
	// acknowledgement. Refires SendProblemAlert with the new
	// severity so the next-tier channels (typically
	// "critical-only" oncall pages) light up. Run after the
	// main evaluate pass so a problem freshly opened this
	// tick doesn't get checked twice.
	e.escalateStaleProblems(ctx)

	// v0.5.352 — silent-source sweep. Operator-reported:
	// problems for services that have stopped emitting stay
	// open forever because the eval path's measure() returns
	// no data and the resolve branch never runs. Sweep here:
	// any open/acknowledged problem whose updated_at is older
	// than 3× the evaluator interval (no recent refresh →
	// source went silent) gets auto-resolved with a marker
	// reason. 3× is the same trade-off the evaluator's
	// escalation sweep uses: tolerant of a single missed tick
	// (network glitch, leader transition), strict enough that
	// a truly decommissioned service closes within ~minutes.
	e.sweepStaleProblems(ctx)

	// v0.7.33 — cascade incident resolution. Operator-reported: Problems
	// auto-resolve but Incidents stayed open forever (CH ground truth: 214
	// problems resolved / 0 open, yet 57 incidents open / 0 resolved). An
	// incident is a container for its attached problems; once they've ALL
	// cleared the incident is over, so auto-resolve it with resolved_at = the
	// last problem's clear time (the started→resolved interval then reflects the
	// real impact window). Operators still resolve manually for a postmortem
	// note; this just stops the inbox filling with stale containers.
	e.cascadeResolveIncidents(ctx)

	// Anomaly auto-promotion — convert strong, sustained
	// anomaly events into first-class Problems so the
	// existing alert pipeline picks them up. Threshold-driven
	// so noise stays in /anomalies; only the patterns the
	// detector keeps re-firing with a real ratio become
	// pageable.
	e.promoteStrongAnomalies(ctx)

	return evaluated
}

// incidentCascadeDecision decides whether an OPEN incident should auto-resolve
// because every problem attached to it has cleared, and at what end time. It
// resolves only when the incident has at least one attached problem and NONE
// remain unresolved. endedAt is the latest problem-clear time so the resolved
// incident's started→ended interval reflects the real impact window; it falls
// back to `now` when no clear timestamp is recorded. Pure for unit testing.
// incidentOrphanGrace — how long an incident with NO attached problem is left
// alone before the cascade closes it.
//
// The window exists for one reason: AttachProblemToIncident creates the
// incident and then binds the problem to it in a second statement. Between
// those two a rollup sees zero attached problems, and resolving there would
// close incidents the instant they open. An hour is far longer than that gap
// and far shorter than the days these were surviving.
const incidentOrphanGrace = time.Hour

func incidentCascadeDecision(problemCount, unresolved int, maxResolvedAt, now int64) (resolve bool, endedAt int64) {
	return incidentCascadeDecisionAt(problemCount, unresolved, maxResolvedAt, now, now)
}

// incidentCascadeDecisionAt decides whether an OPEN incident should
// auto-resolve because everything driving it has cleared, and at what end
// time. Pure for unit testing.
//
// v0.9.332 — problemCount == 0 used to mean "never resolve". Combined with
// the rollup's INNER JOINs (which did not even EMIT such incidents) that made
// an unattached incident immortal: measured locally, 26 of 32 open incidents
// had no attached problem, the oldest four days old. They accumulate, they
// dominate the triage queue, and nothing can ever close them — the operator's
// "çok fazla incident var, yanıltıcı oluyor".
//
// Now: nothing unresolved is attached → resolve, provided either something WAS
// attached (the original case) or the incident has outlived the grace window
// that protects the create→bind gap.
func incidentCascadeDecisionAt(problemCount, unresolved int, maxResolvedAt, startedAt, now int64) (resolve bool, endedAt int64) {
	if unresolved > 0 {
		return false, 0
	}
	if problemCount == 0 {
		// Never attached to anything. Only close it once we are past the
		// window where "not attached yet" is the honest explanation.
		if startedAt == 0 || now-startedAt < int64(incidentOrphanGrace) {
			return false, 0
		}
		// No problem-clear timestamp exists for an incident that never had
		// a problem, so `now` is the only honest end time.
		return true, now
	}
	if maxResolvedAt > 0 {
		return true, maxResolvedAt
	}
	return true, now
}

// cascadeResolveIncidents auto-resolves every open incident whose attached
// problems have ALL cleared (the operator-reported gap — see the evaluateAll
// call site). One bounded rollup query, then a per-settled-incident upsert +
// timeline event.
func (e *Evaluator) cascadeResolveIncidents(ctx context.Context) {
	rollups, err := e.store.OpenIncidentRollups(ctx)
	if err != nil {
		log.Printf("[evaluator] incident cascade rollup: %v", err)
		return
	}
	now := time.Now().UnixNano()
	for _, ro := range rollups {
		resolve, endedAt := incidentCascadeDecisionAt(ro.ProblemCount, ro.Unresolved, ro.MaxResolvedAt, ro.StartedAt, now)
		if !resolve {
			continue
		}
		inc, err := e.store.GetIncident(ctx, ro.ID)
		if err != nil || inc == nil || inc.Status == "resolved" {
			continue
		}
		reason := "auto-resolved: all attached problems cleared"
		if ro.ProblemCount == 0 {
			reason = "auto-resolved: no problem ever attached (orphaned past the grace window)"
		}
		inc.Status = "resolved"
		inc.ResolvedAt = &endedAt
		if err := e.store.UpsertIncident(ctx, inc); err != nil {
			log.Printf("[evaluator] incident cascade upsert %s: %v", ro.ID, err)
			continue
		}
		// v0.10.748 — yaşam döngüsü kancası (incident çözüm bildirimi).
		_ = e.store.AppendIncidentLifecycle(ctx, *inc, chstore.IncidentEvent{
			IncidentID: inc.ID,
			Time:       endedAt,
			Kind:       "resolved",
			Actor:      "system",
			Body:       reason,
		})
		// The log says WHICH rule closed it: "0 problems, all cleared" read as
		// a contradiction in the one case that matters most.
		if ro.ProblemCount == 0 {
			log.Printf("[evaluator] INCIDENT AUTO-RESOLVED: %s (orphaned — no problem ever attached)", inc.ID)
		} else {
			log.Printf("[evaluator] INCIDENT AUTO-RESOLVED: %s (%d problems, all cleared)", inc.ID, ro.ProblemCount)
		}
	}
}

// ruleEvalTargets expands a rule to its evaluation targets: the pinned
// service, or every recent service for a wildcard (service="") rule.
// Log-query rules NEVER reach this — they are hoisted to a single
// evaluateLogQuery call in evaluateAll (v0.8.342, HA audit H9). Pure so
// the fan-out multiplicity is table-tested.
func ruleEvalTargets(r chstore.AlertRule, serviceNames []string) []string {
	if r.Service != "" {
		return []string{r.Service}
	}
	return serviceNames
}

// evalFreshWindow (v0.9.449, hacim denetimi L4) — request_rate DÜŞÜŞ
// kuralları için hedef tazeliği: 24 saatlik wildcard listesi, 20 saat
// önce susmuş (emekliye ayrılmış) servisi hâlâ değerlendiriyor ve
// absentMeasure'ın 0'ı `request_rate <` eşiğini gün boyu ihlal
// ediyordu. 2 saatlik tazelik: susma alarmı ilk 2 saat NORMAL çalışır
// (asıl amaç), sonra değerlendirme durur → satır ~3×interval içinde
// stale sweep'le "source silent" gerekçesiyle kapanır.
const evalFreshWindow = 2 * time.Hour

// ruleNeedsFreshTargets — saf kapı: yalnız susmayla ihlale DÖNEN şekil
// (request_rate + küçüktür karşılaştırması). Diğer metrikler susan
// serviste ya değerlendirilmez (error_rate/avg_ms evaluate=false) ya
// da NaN ile resolve dalına düşer — onlara kapı gerekmez.
func ruleNeedsFreshTargets(r chstore.AlertRule) bool {
	return r.Metric == "request_rate" && (r.Comparator == "<" || r.Comparator == "<=")
}

// filterFreshTargets — hedef listesini taze kümeye indirger. fresh nil
// ise (okuma hatası) kapı DEVRE DIŞI: eski davranışa düş (fail-open,
// kör susturma olmasın).
func filterFreshTargets(targets []string, fresh map[string]bool) []string {
	if fresh == nil {
		return targets
	}
	kept := make([]string, 0, len(targets))
	for _, t := range targets {
		if fresh[t] {
			kept = append(kept, t)
		}
	}
	return kept
}

func (e *Evaluator) evaluateOne(ctx context.Context, r chstore.AlertRule, service string, pre *tickMeasures, openSnap *chstore.OpenProblems) {
	// Saved-search log alerts (v0.5.242) bypass the per-service
	// span-metric path entirely. The KQL itself carries any
	// service / pod / level filter the operator wants; the
	// evaluator just counts matches in the window and compares
	// to the threshold. We special-case BEFORE the service
	// guard because log_query rules use service="".
	if r.LogQuery != "" {
		e.evaluateLogQuery(ctx, r)
		return
	}
	// Same defensive hoist for imported watcher rules (v0.9.x) —
	// evaluateAll never routes them here, but a direct caller must
	// not fall through to the span-metric path with metric="watcher".
	if r.WatcherJSON != "" {
		e.evaluateWatcher(ctx, r)
		return
	}
	if service == "" {
		return
	}
	window := time.Duration(r.WindowSec) * time.Second
	// v0.8.352 (perf P2-A) — windows the 5m MV serves consume the per-tick
	// batched prefetch (see prefetch.go). Sub-5m custom windows keep the
	// per-service raw path below: they're rare (builtins are 5m/10m) and
	// the 5m MV grid can't reconstruct them (useSummaryMV).
	batched := pre != nil && useSummaryMV(window)

	// Sample floor (v0.5.128). For sample-dependent metrics
	// (error_rate / percentiles / avg_ms) a single bad request
	// in a low-traffic window pushes the value to scary levels
	// without any real signal — skip the eval entirely below
	// MinSamples. request_rate / error_count are absolute and
	// inherently sample-aware, so the gate doesn't apply.
	if r.MinSamples > 0 && metricNeedsSampleFloor(r.Metric) {
		var count uint64
		counted := false
		if batched {
			counts, failed, ok := pre.countFor(int(r.WindowSec))
			if failed {
				// Batched count read errored this tick (logged at
				// prefetch) — skip, same as a per-service error.
				return
			}
			if ok {
				count = counts[service] // absent = no MV buckets = 0 spans
				counted = true
			}
		}
		if !counted {
			// Sub-5m window, or a defensive fallback when the pair was
			// never prefetched (a collectMeasureKeys mismatch — bug).
			var err error
			count, err = e.measureCount(ctx, service, window)
			if err != nil {
				log.Printf("[evaluator] measure-count %s/%s: %v", r.ID, service, err)
				return
			}
		}
		if count < uint64(r.MinSamples) {
			// Also clear any stamped breach so a sustain gate
			// doesn't carry over once the service warms up.
			e.clearBreach(ctx, breachKey{RuleID: r.ID, Service: service})
			return
		}
	}

	var value float64
	measured := false
	if batched {
		vals, failed, ok := pre.measureFor(r.Metric, int(r.WindowSec))
		if failed {
			// Batched read errored this tick (logged at prefetch) —
			// skip every service on this rule, same blast radius as
			// the old per-service measure() error.
			return
		}
		if ok {
			v, present := vals[service]
			if !present {
				// Zero traffic in the window. absentMeasure reproduces
				// what the per-service query returned for an empty
				// result (0 / NaN / skip) — see prefetch.go.
				av, evaluate := absentMeasure(r.Metric)
				if !evaluate {
					return
				}
				v = av
			}
			value = v
			measured = true
		}
	}
	if !measured {
		var err error
		value, err = e.measure(ctx, service, r.Metric, window)
		if err != nil {
			log.Printf("[evaluator] measure %s/%s: %v", r.ID, service, err)
			return
		}
	}

	breached := compare(value, r.Comparator, r.Threshold)

	// Sustained-breach gate (v0.5.127): when r.ForSec > 0 we
	// stamp the first-breach time and only open a problem after
	// the breach has persisted that long. Clearing the breach
	// resets the stamp so a re-breach restarts the clock — same
	// semantics as Prometheus' `for:` directive. Open problems
	// don't pass through here; the breach has already been
	// promoted, refresh continues via the existing path.
	// v0.8.354 — the stamp is Redis-mirrored (stamps.go) so a
	// leader failover mid-sustain doesn't restart the clock.
	key := breachKey{RuleID: r.ID, Service: service}
	now := time.Now()
	if breached && r.ForSec > 0 {
		first, existing := e.breachStart(ctx, key, now, r.ForSec)
		if !existing {
			return // first sighting — wait for sustain
		}
		if now.Sub(first) < time.Duration(r.ForSec)*time.Second {
			return // still inside the sustain window
		}
		// Past the sustain — fall through to open.
	}
	if !breached {
		e.clearBreach(ctx, key)
	}

	// v0.8.520 — snapshot varsa map lookup; yoksa (snapshot hatası)
	// eski nokta sorgusu. Anahtar semantiği FindOpenProblem'la birebir
	// (reduceLatestProblem, chstore tablo-testli).
	var open *chstore.Problem
	var err error
	if openSnap != nil {
		open = openSnap.ByKey(r.ID, service)
	} else {
		open, err = e.store.FindOpenProblem(ctx, r.ID, service)
	}
	hasOpen := err == nil && open != nil && open.ID != ""

	switch {
	case breached && !hasOpen:
		// Cooldown gate (v0.5.129): if this (rule, service)
		// just auto-resolved, hold off re-opening until the
		// cooldown window passes. Threshold-jitter near the
		// boundary stops producing OPEN/RESOLVED churn.
		// v0.8.354 — resolvedAt hydrates the Redis mirror on an
		// in-memory miss so a failover can't punch the cooldown.
		if r.CooldownSec > 0 {
			if rt, seen := e.resolvedAt(ctx, key); seen && now.Sub(rt) < time.Duration(r.CooldownSec)*time.Second {
				return
			}
		}
		// Open a new problem
		p := chstore.Problem{
			ID:       newID(),
			RuleID:   r.ID,
			RuleName: r.Name,
			Severity: r.Severity,
			Service:  service,
			Metric:   r.Metric,
			Value:    value,
			// v0.9.976 — ihlalin YÖNÜ satıra iniyor. chstore.computePriority
			// ters-çevirme kolu buna bakıyor: alan yokken eşiğin ALTINDA
			// kalan her ">" kuralı (error_rate 3.9 / eşik 15) ters çevrilip
			// "3.8x büyük ihlal" sayılıyor ve SAHTE P1 üretiyordu.
			Comparator:  r.Comparator,
			Threshold:   r.Threshold,
			Status:      "open",
			Description: describeProblem(r, service, value),
			Assignee:    e.defaultAssignee(ctx, service),
			StartedAt:   time.Now().UnixNano(),
		}
		if err := e.store.UpsertProblem(ctx, p); err != nil {
			log.Printf("[evaluator] open problem: %v", err)
		} else {
			e.countOpened() // v0.9.550 — kalp atışı sayacı
			log.Printf("[evaluator] PROBLEM OPENED: %s · %s = %.2f (threshold %.2f)",
				service, r.Metric, value, r.Threshold)
			// Auto-group into an Incident — same-service same-severity
			// problems within 30min get folded under one declared
			// incident so the oncall has a single place to drive
			// response from. Best-effort; failure here doesn't block
			// alerting.
			if _, err := e.store.AttachProblemToIncident(ctx, p); err != nil {
				log.Printf("[evaluator] incident attach: %v", err)
			}
			// Fan out to user channels (email/slack/etc). Fire-and-forget
			// so a flaky SMTP doesn't block the eval loop. When a
			// maintenance window is active for this (service,
			// severity) at firing time, skip the notification —
			// the Problem itself still opens + auto-resolves so
			// the post-window timeline review is intact, only
			// the live channel spam is suppressed.
			// Notifier internally consults the maintenance-windows
			// table and skips fan-out when an active window matches
			// (service, severity). Problem itself still opens +
			// resolves normally — only the live channel spam is
			// suppressed.
			if e.notifier != nil {
				go e.notifier.SendProblemAlert(context.Background(), p)
			}
		}

	case breached && hasOpen:
		// Refresh the live value on the existing problem
		open.Value = value
		if err := e.store.UpsertProblem(ctx, *open); err != nil {
			log.Printf("[evaluator] refresh problem: %v", err)
		}

	case !breached && hasOpen:
		// Auto-resolve
		//
		// v0.9.977 — Value'ya DOKUNULMUYOR. Buraya `open.Value = value`
		// (toparlanmış değer) yazılıyordu: kapanan satır artık eşiğin
		// altında göründüğü için hem ihlalin büyüklüğü kayboluyor, hem de
		// aynı problem açılışta ve kapanışta FARKLI öncelik hesaplıyordu.
		chstore.MarkResolved(open, time.Now().UnixNano())
		if err := e.store.UpsertProblem(ctx, *open); err != nil {
			log.Printf("[evaluator] resolve problem: %v", err)
		} else {
			// Stamp the resolution so v0.5.129's CooldownSec
			// gate can suppress immediate re-opens — Redis-
			// mirrored so the gate survives failover (v0.8.354).
			e.stampResolved(ctx, key, time.Now(), r.CooldownSec)
			e.countResolved() // v0.9.550 — kalp atışı sayacı
			log.Printf("[evaluator] PROBLEM RESOLVED: %s · %s", service, r.Metric)
		}
	}
}

// evaluateLogQuery handles a saved-search alert (v0.5.242). The rule's
// LogQuery is a search string; we count matches in the window via the
// logstore and compare to Threshold. Open / resolve mirrors the metric
// path so the existing notification + incident-attach + cooldown
// machinery still applies.
//
// ⚠ v0.9.1384 — BU ŞERH BİR REÇETEYDİ VE YANLIŞTI. Eskiden şöyle
// bitiyordu: "Service is left empty on the resulting Problem — the KQL
// itself can scope to one service via service.name:\"X\"." Yani kod, kendi
// dokümantasyonunda, ClickHouse'da HİÇBİR ŞEYE eşleşmeyen bir yazımı
// ÖNERİYORDU.
//
// ClickHouse — varsayılan arka uç — Search alanını gövdede arıyor
// (`body LIKE '%…%'`). Canlı ölçüm, tek servis, 24s: yapısal filtre 858
// satır, `service.name:"x"` yazımı 0 satır, ve tüm tabloda
// `countIf(body LIKE '%service.name%') = 0`. Böyle bir kural daima 0
// sayar, eşiği asla aşmaz ve hata da vermez.
//
// İki taraflı savunma: yeni kurallar API'de reddediliyor
// (`rejectDeadLogQuery`), ZATEN KAYITLI olanlar burada sesli hâle
// getiriliyor — kural bu sürümden önce kaydedilmiş ya da ES'teyken
// kaydedilip arka uç CH'ye çevrilmiş olabilir.
func (e *Evaluator) evaluateLogQuery(ctx context.Context, r chstore.AlertRule) {
	if e.logs == nil {
		log.Printf("[evaluator] log_query %s: logs backend not wired", r.ID)
		return
	}
	window := time.Duration(r.WindowSec) * time.Second
	if window == 0 {
		window = time.Minute
	}
	// v0.8.3 — per-evaluation deadline so a slow ES Search for a
	// log_query alert rule can't hang the evaluator goroutine against
	// the process-lifetime ctx (no-op on CH; bounds the ES hang).
	ctx, cancel := context.WithTimeout(ctx, 30*time.Second)
	defer cancel()
	// Sessizliği bitir: bu kural bu arka uçta ASLA ateşlenemez.
	// Değerlendirmeyi yine de koşturuyoruz — sonucu uydurmak, sessizce
	// sıfır saymaktan farklı bir yalan olurdu; yapılan tek şey durumu
	// SÖYLEMEK. Tick başına bir satır: evaluator dakikada bir koşuyor ve
	// operatör bu satırı gördüğünde kuralı düzeltecek, susturmayacak.
	if logstore.LooksLikeFieldQuery(r.LogQuery) &&
		!logstore.BackendUnderstandsFieldQuery(e.logs.Backend()) {
		log.Printf("[evaluator] log_query %s: ALARM ÖLÜ — sorgu %q alan:değer yazımı, "+
			"%s arka ucu bunu ayrıştırmaz ve gövdede literal arar; eşleşme yapısal olarak "+
			"imkânsız, bu kural asla ateşlenmeyecek. Düz metin kullanın ya da log arka ucunu "+
			"elasticsearch'e alın.", r.ID, r.LogQuery, e.logs.Backend())
	}
	now := time.Now()
	page, err := e.logs.Search(ctx, logstore.Filter{
		Search: r.LogQuery,
		From:   now.Add(-window),
		To:     now,
		Limit:  1, // hits the cap but we only need .Total
	})
	if err != nil {
		log.Printf("[evaluator] log_query measure %s: %v", r.ID, err)
		return
	}
	// Sustained-breach + cooldown + open/refresh/resolve machinery is
	// shared with the imported-watcher path (v0.9.x) — see
	// settleCountAlert in watcher_eval.go, extracted verbatim from
	// this function. Key stays (rule, "" service); stamps ride the
	// same Redis mirror as the metric path (v0.8.354).
	desc := fmt.Sprintf("log_query matched %d in last %s (threshold %s %.0f) — query: %s",
		page.Total, window, r.Comparator, r.Threshold, r.LogQuery)
	// nil enricher: the log_query path embeds no fire-time samples —
	// behaviour pinned since v0.5.242.
	e.settleCountAlert(ctx, r, now, float64(page.Total), "log_query", desc, nil)
}

// escalateStaleProblems walks every open problem and bumps
// severity when it's lingered past the threshold. Per-tier
// guards mean each problem escalates at most twice end-to-end
// (info → warning → critical); the comparison is against the
// original started_at so an "info opened 45 min ago" goes
// straight to critical on the first sweep.
//
// Refires SendProblemAlert after writing the new severity so
// the next-tier channels (typically severity-gated to
// "critical only" for the on-call pager) light up.
// Acknowledged / resolved problems are skipped — only "open"
// status enters the sweep.
// sweepStaleProblems auto-resolves open/acknowledged problems
// whose source signal has gone silent. Detection: updated_at
// older than 3× the evaluator interval — the evaluator
// upserts the row every tick when the metric still produces
// a value (even at 0, that's a no-error refresh), so a
// frozen updated_at means the eval path bailed (MinSamples
// gate, measure() returned no data for a decommissioned
// service, the source service stopped emitting, etc.).
//
// 3× threshold tolerates one missed tick (leader transition,
// network blip) without false-resolves. Default eval
// interval = 1 min, so cutoff = ~3 min.
//
// v0.5.352 — operator-reported: problem for "svc-1" stayed
// open from 04.05.2026 17:00 onward even though no traces
// came in from that service. The eval path's measure()
// returned no data, so neither the breached nor the
// !breached branch ran, and the problem was orphaned.
func (e *Evaluator) sweepStaleProblems(ctx context.Context) {
	// v0.9.588 (operator-reported) — sessizliği GERÇEKTEN biz mi
	// gözledik? Rollout'ta worker inip kalkarken hiçbir dedektör tik
	// atamaz; yeni pod'un ilk tikinde her problem bayat görünür ve
	// süpürme bunu "kaynak sustu" diye okurdu. Kesintisiz koşma süresi
	// süpürme eşiğini doldurmadan karar vermek, kendi kör noktamızı
	// veri sanmaktır. Bkz. tick_continuity.go.
	if !e.sweepIsTrustworthy(time.Now()) {
		return
	}
	cutoff := time.Now().Add(-3 * e.interval)
	stale, err := e.store.ListStaleOpenProblems(ctx, cutoff)
	if err != nil {
		log.Printf("[evaluator] stale sweep: list: %v", err)
		return
	}
	// v0.10.592 — poller'ın sahiplendiği Problem'ler (ext-down / ext-cap)
	// süpürülmez: yaşam döngüleri poll anında touch/resolve ile yönetiliyor;
	// poll aralığı 3×interval'ı aşan kaynakta süpürme onları "source silent"
	// diye kapatıp bir sonraki poll'da yeniden açtırırdı — ayara bağlı
	// flapping. Karar SAF (staleSweepCandidates), testte pinli.
	toClose, skipped := staleSweepCandidates(stale, e.pollerSourceLive)
	if len(skipped) > 0 {
		log.Printf("[evaluator] stale sweep: %d poller-owned problem(s) skipped (lifecycle belongs to the source poller)", len(skipped))
	}
	resolved := 0
	for i := range toClose {
		p := toClose[i]
		chstore.MarkResolved(&p, time.Now().UnixNano())
		// Mark the resolution reason inline so an operator
		// auditing /problems sees why this row closed without
		// a corresponding threshold-crossing event.
		p.Description = appendStaleSuffix(p.Description)
		if err := e.store.UpsertProblem(ctx, p); err != nil {
			log.Printf("[evaluator] stale sweep: resolve %s: %v", p.ID, err)
			continue
		}
		// Clear the cooldown stamp so the next time the source
		// emits and breaches again, a fresh problem can open.
		// Mirror-delete included (v0.8.354) — a fresh leader must
		// clear stamps only the previous leader held in memory.
		e.clearResolved(ctx, breachKey{RuleID: p.RuleID, Service: p.Service})
		resolved++
		log.Printf("[evaluator] PROBLEM AUTO-RESOLVED (source silent): %s · %s", p.Service, p.Metric)
	}
	if resolved > 0 {
		log.Printf("[evaluator] stale sweep: resolved %d problem(s) with silent sources", resolved)
	}
}

// staleSweepCandidates — SAF: bayat listeden süpürülecekler ve poller'a ait
// olduğu için ATLANANLAR. Sıra korunur. chstore.PollerOwnedRule tek karar
// noktası; seri Problem'leri (anomaly:ext:…) süpürülmeye devam eder — kaynak
// susunca onların "source silent" kapanışı dürüst sinyaldir.
//
// v0.10.605 — muafiyet YAŞAYAN kaynağa bağlı: live(özne) false dönerse
// (kaynak silinmiş/kapatılmış) Problem süpürülür; kaynağı yaşatan poller
// yok, resolve edecek kimse yok. live nil = hepsi muaf (592).
func staleSweepCandidates(stale []chstore.Problem, live func(subject string) bool) (toClose, skipped []chstore.Problem) {
	for _, p := range stale {
		if subject, owned := chstore.PollerOwnedSubject(p.RuleID); owned && (live == nil || live(subject)) {
			skipped = append(skipped, p)
			continue
		}
		toClose = append(toClose, p)
	}
	return toClose, skipped
}

// appendStaleSuffix tags the resolution reason onto the
// problem's description so /problems history makes the
// silent-source close obvious. Idempotent — if the suffix is
// already present (the row got resolved-then-reopened-then-
// silently-closed once before) we don't double-tag.
func appendStaleSuffix(desc string) string {
	const suffix = " · auto-resolved: source silent"
	if strings.Contains(desc, "source silent") {
		return desc
	}
	return desc + suffix
}

// escalationCfg returns the age-escalation settings, memoised for
// escalationMemoTTL. The evaluator tick is longer than the TTL, so a
// settings change still lands within one tick while a single pass
// never re-reads.
func (e *Evaluator) escalationCfg(ctx context.Context) chstore.ProblemEscalationConfig {
	const escalationMemoTTL = 20 * time.Second
	e.escMu.Lock()
	defer e.escMu.Unlock()
	if !e.escAt.IsZero() && time.Since(e.escAt) < escalationMemoTTL {
		return e.escCfg
	}
	e.escCfg = e.store.GetProblemEscalation(ctx)
	e.escAt = time.Now()
	return e.escCfg
}

func (e *Evaluator) escalateStaleProblems(ctx context.Context) {
	// One read per sweep — every problem in this pass is judged
	// against the same snapshot, so a mid-sweep settings change can't
	// escalate half the fleet under old windows and half under new.
	esc := e.escalationCfg(ctx)
	if !esc.Enabled {
		return
	}
	// v0.10.156 — tick'in snapshot'ından (5 s memo), ayrı FINAL taraması yok.
	snap, err := e.store.OpenProblemsSnapshot(ctx)
	if err != nil {
		log.Printf("[evaluator] escalation sweep: list problems: %v", err)
		return
	}
	problems := snap.Filter("open", "", 500)
	now := time.Now()
	for i := range problems {
		p := problems[i]
		// v0.9.1294 — muaf kurallar yaşlanmayla şiddet kazanmaz
		// (escalationExempt, selfhealth_volume.go). Kelepçe hem burada
		// hem tazeleme dalında olmalı: yalnız birinde olsaydı süpürme
		// yükseltir, tazeleme geri indirir ve v0.8.309'un bildirim seli
		// geri gelirdi.
		if escalationExempt(p.RuleID) {
			continue
		}
		openFor := now.Sub(time.Unix(0, p.StartedAt))
		next := nextSeverity(p.Severity, openFor, esc)
		if next == "" || next == p.Severity {
			continue
		}
		old := p.Severity
		p.Severity = next
		if err := e.store.UpsertProblem(ctx, p); err != nil {
			log.Printf("[evaluator] escalate %s/%s: %v", p.Service, p.RuleID, err)
			continue
		}
		log.Printf("[evaluator] ESCALATED %s · %s · open %s · %s → %s",
			p.Service, p.RuleName, openFor.Round(time.Minute), old, next)
		// Refire so severity-gated channels (e.g. an oncall
		// pager that only subscribes to critical) get the
		// notification. SendProblemAlert publishes the SSE
		// event too, so live operator UIs pick up the
		// severity bump immediately.
		if e.notifier != nil {
			go e.notifier.SendProblemAlert(context.Background(), p)
		}
	}
}

// Promoted problems get rule_id = "anomaly-auto:<fingerprint>"
// so the same anomaly re-promoted on a later tick lands on
// the same Problem row (no duplicate noise). When the
// anomaly clears (last_seen ages out of the "active" window)
// the row stays "open" — operators ack it the same way as
// any other Problem.
//
// Promotion thresholds were hard-coded until v0.5.71; they
// now come from chstore.AnomalyPromotionConfig saved under
// system_settings. Defaults match the legacy constants so
// installs that never visit the settings page keep the
// v0.5.59 behaviour.
const promoteAnomalyRuleID = "anomaly-auto:"

// promoteStrongAnomalies converts strong, sustained
// AnomalyEvents into first-class Problems so the existing
// notify / incident-attach / SSE wiring picks them up. The
// thresholds above gate which events qualify. Idempotent —
// a re-promotion on a later sweep hits the same problem id
// and just bumps its last-seen via UpsertProblem.
//
// Severity ladder:
//   - peakRatio ≥ MinPeakRatio      → warning  (the auto-promote tier)
//   - peakRatio ≥ CriticalPeakRatio → critical (genuine "wake someone")
//
// Both come from the operator's anomaly-promotion settings
// (v0.9.247); the critical cut-off used to be a hard-coded 20.
//
// The escalation sweep above can still bump these higher
// over time if the operator doesn't ack.
func (e *Evaluator) promoteStrongAnomalies(ctx context.Context) {
	// Pull config from the store. Soft-fails to defaults
	// internally so a CH blip never accidentally disables
	// promotion in a long-running evaluator.
	cfg := e.store.GetAnomalyPromotion(ctx)
	if !cfg.Enabled {
		return
	}
	// Same snapshot discipline as the escalation sweep — the promoted
	// severity is clamped to the age floor, so it needs the windows.
	esc := e.escalationCfg(ctx)
	minSustained := time.Duration(cfg.MinSustainedSec) * time.Second

	events, err := e.store.ListAnomalyEvents(ctx, chstore.ListAnomalyEventsFilter{
		// Last hour is enough — the detector re-emits every
		// tick, so anything that should be a Problem will be
		// in this window. Wider lookback would just re-touch
		// already-promoted rows.
		SinceNs: time.Now().Add(-1 * time.Hour).UnixNano(),
		Limit:   500,
	})
	if err != nil {
		log.Printf("[evaluator] anomaly promotion: list events: %v", err)
		return
	}
	// v0.9.337 — honour the operator's mute HERE, not just on the two list
	// endpoints.
	//
	// Muting an anomaly wrote a row that only api.go:10132 and :10236 ever
	// read, so it hid the fingerprint from two lists and nothing else. The
	// promotion sweep never consulted it: a muted fingerprint kept becoming a
	// Problem, kept attaching to an incident, and kept paging. The operator
	// gave an explicit instruction and the loudest path ignored it — which is
	// a large part of "prodta çok anomali var".
	//
	// This is NOT learned suppression: no history, no score, no decay. It is
	// one operator gesture with an expiry that ActiveSilencedFingerprints
	// already enforces (until_at > now), so a lapsed mute stops suppressing
	// on the very next sweep with no un-learning to get wrong.
	//
	// Soft-fail to "nothing muted": a CH blip must never silently suppress
	// promotion. Failing OPEN here means the worst case is the noise the
	// operator already has, not a missed page.
	muted, mErr := e.store.ActiveSilencedFingerprints(ctx)
	if mErr != nil {
		log.Printf("[evaluator] anomaly promotion: silence list (promoting unfiltered): %v", mErr)
		muted = nil
	}
	now := time.Now()
	// v0.10.156 (inceleme D3) — süpürme başına TEK snapshot: döngü içindeki
	// her Upsert memo'yu düşürür, olay başına Get yeniden tarardı. Aynı
	// (kural, servis) bir süpürmede bir kez işlenir; süpürme-yerel görünüm
	// evaluateOne'ın tick-yerel snapshot disipliniyle aynı (v0.8.520).
	// v0.10.158 — TEMBEL: aktif olay yoksa tarama yok. Hata: nil snapshot →
	// ByKey nil → "yeni" kabul (eski `open, _ :=` dalı), bir kez loglanır.
	lazy := e.store.LazyOpenSnapshot()
	snapWarned := false
	for _, ev := range events {
		if ev.Status != "active" {
			continue
		}
		if muted[ev.ID] {
			// ev.ID IS the fingerprint (recorder.go builds it with
			// FingerprintAnomaly), the same key the mute was written under.
			// Logged rather than skipped in silence: a suppressed promotion
			// is a decision, and an operator debugging "why did this not
			// page" needs to find it.
			log.Printf("[evaluator] anomaly promotion SKIPPED (muted): %s · %s · %s",
				ev.Service, ev.Kind, ev.Pattern)
			continue
		}
		if ev.PeakRatio < cfg.MinPeakRatio {
			continue
		}
		if ev.CurrentCount < cfg.MinCount {
			continue
		}
		if now.Sub(time.Unix(0, ev.StartedAt)) < minSustained {
			continue
		}
		// v0.9.247 — cut-off comes from config (was a hard-coded 20).
		// GetAnomalyPromotion guarantees it is >= MinPeakRatio, so
		// "everything promoted is critical" only happens when the
		// operator actually asks for it.
		sev := "warning"
		if ev.PeakRatio >= cfg.CriticalPeakRatio {
			sev = "critical"
		}
		ruleID := promoteAnomalyRuleID + ev.ID
		// Re-use the existing open Problem row when one is
		// in flight for the same fingerprint — keeps the
		// notify channel from refiring on every sweep.
		isNew := false
		snap, snapErr := lazy.Get(ctx) // v0.10.158 — ilk ihtiyaçta bir kez
		if snapErr != nil && !snapWarned {
			log.Printf("[evaluator] anomaly promotion: open snapshot: %v", snapErr)
			snapWarned = true
		}
		open := snap.ByKey(ruleID, ev.Service) // v0.10.156 — süpürme-yerel snapshot, kopya
		if open == nil {
			isNew = true
		}
		desc := truncate(
			"Auto-promoted from anomaly: "+ev.Kind+" / "+ev.Pattern+
				" (peak ratio "+formatFloat(ev.PeakRatio, 1)+
				"×, count "+formatUint(ev.CurrentCount)+")",
			480,
		)
		var startedAt int64
		var id string
		if open != nil {
			id = open.ID
			startedAt = open.StartedAt
		} else {
			id = ruleID + ":" + ev.Service
			startedAt = ev.StartedAt
		}
		// v0.8.309 — clamp to the age-based escalation floor. The refresh
		// branch used to rewrite the sweep's critical back to the
		// ratio-derived severity every tick (page storm); the backdated
		// StartedAt on promotion also made a fresh problem double-page
		// (promote at warning + escalate to critical in one pass).
		sev = effectiveSeverity(sev, time.Since(time.Unix(0, startedAt)), esc)
		p := chstore.Problem{
			ID:          id,
			RuleID:      ruleID,
			RuleName:    "Anomaly · " + ev.Pattern,
			Severity:    sev,
			Service:     ev.Service,
			Metric:      "anomaly_ratio",
			Value:       ev.PeakRatio,
			Threshold:   cfg.MinPeakRatio,
			Status:      "open",
			Description: desc,
			StartedAt:   startedAt,
		}
		// v0.9.444 (hacim denetimi bulgusu) — tam-satır replace operatör
		// alanlarını İLERİ taşımalı: refresh dalı her tick Status:"open"
		// yazıp ack'i geri açıyor, boş Assignee/Pod alanları da mevcut
		// değerleri siliyordu (ReplacingMergeTree bütün-satır sözleşmesi).
		carryProblemOperatorState(&p, open)
		if err := e.store.UpsertProblem(ctx, p); err != nil {
			log.Printf("[evaluator] anomaly promote %s/%s: %v",
				ev.Service, ev.ID, err)
			continue
		}
		if isNew {
			log.Printf("[evaluator] AUTO-PROMOTED anomaly %s · %s · ratio %.1fx → %s",
				ev.Service, ev.Pattern, ev.PeakRatio, sev)
			if e.notifier != nil {
				go e.notifier.SendProblemAlert(context.Background(), p)
			}
		}
	}
	e.resolveClearedAnomalyPromotions(ctx, muted)
}

// carryProblemOperatorState — terfi refresh'inin saf çekirdeği: mevcut
// açık satırdan OPERATÖR + EXPLAINER alanlarını yeni gövdeye taşır.
// Status (ack hayatta kalır), Assignee, Pod ve AI özeti (v0.9.448:
// UpsertProblem artık ai kolonlarını yazıyor — taşımayan taze gövde
// özeti silerdi) taşınır; Severity/Value/Description BİLEREK taşınmaz
// — onlar her tick'in taze ölçümüdür.
func carryProblemOperatorState(p *chstore.Problem, open *chstore.Problem) {
	if open == nil {
		return
	}
	p.Status = open.Status
	p.Assignee = open.Assignee
	p.Pod = open.Pod
	p.AISummary = open.AISummary
	p.AISummaryAt = open.AISummaryAt
}

// resolveClearedAnomalyPromotions (v0.9.444, hacim denetimi #3) —
// anomali TEMİZLENİNCE terfi problemi hemen ve dürüst gerekçeyle
// kapanır. Eskiden kapanış dolaylıydı: promotion satıra dokunmayı
// bırakır, ~10dk aktif penceresi + 3×interval sonra stale sweep
// "source silent" damgasıyla kapatırdı — Dynatrace davranışı
// "koşul geçti → problem kapandı"dır ve gerekçe yalan söylememeli.
// Susturulmuş (mute) parmak izlerinin problemleri de kapanır:
// v0.9.337 mute'u en gürültülü yoldan düşürmüştü; açık satırı
// sonsuza dek taşımak aynı şikâyetin kuyruğuydu.
//
// Soft-fail her iki okumada: aktif seti alınamazsa HİÇBİR ŞEY
// kapatılmaz (kör resolve, kaçırılmış alarmdan beterdir).
func (e *Evaluator) resolveClearedAnomalyPromotions(ctx context.Context, muted map[string]bool) {
	events, err := e.store.ListAnomalyEvents(ctx, chstore.ListAnomalyEventsFilter{
		ActiveOnly: true,
		SinceNs:    time.Now().Add(-1 * time.Hour).UnixNano(),
		Limit:      5000,
	})
	if err != nil {
		log.Printf("[evaluator] anomaly resolve pass: list active: %v", err)
		return
	}
	active := make(map[string]bool, len(events))
	for _, ev := range events {
		active[ev.ID] = true
	}
	snap, err := e.store.OpenProblemsSnapshot(ctx)
	if err != nil {
		log.Printf("[evaluator] anomaly resolve pass: snapshot: %v", err)
		return
	}
	resolved := 0
	for _, p := range snap.All() {
		if !strings.HasPrefix(p.RuleID, promoteAnomalyRuleID) {
			continue
		}
		fp := strings.TrimPrefix(p.RuleID, promoteAnomalyRuleID)
		isMuted := muted[fp]
		if active[fp] && !isMuted {
			continue
		}
		reason := "anomaly cleared"
		if isMuted {
			reason = "anomaly muted"
		}
		q := *p
		chstore.MarkResolved(&q, time.Now().UnixNano())
		q.Description = appendResolveSuffix(q.Description, reason)
		if err := e.store.UpsertProblem(ctx, q); err != nil {
			log.Printf("[evaluator] anomaly resolve pass: %s: %v", q.ID, err)
			continue
		}
		resolved++
		log.Printf("[evaluator] PROBLEM AUTO-RESOLVED (%s): %s · %s", reason, q.Service, q.RuleName)
	}
	if resolved > 0 {
		log.Printf("[evaluator] anomaly resolve pass: closed %d promoted problem(s)", resolved)
	}
}

// appendResolveSuffix — appendStaleSuffix'in gerekçeli genellemesi.
// İdempotent: aynı gerekçe zaten damgalıysa yeniden eklenmez
// (resolved→reopened→re-resolved döngüsü çift damga üretmesin).
func appendResolveSuffix(desc, reason string) string {
	if strings.Contains(desc, reason) {
		return desc
	}
	return desc + " · auto-resolved: " + reason
}

// formatFloat / formatUint — tiny helpers used by promotion
// description so we don't pull fmt.Sprintf into the hot path
// (the rest of the file works in strconv-style for the same
// reason). One alloc each, no formatting locale weirdness.
func formatFloat(v float64, prec int) string {
	return strconv.FormatFloat(v, 'f', prec, 64)
}
func formatUint(v uint64) string { return strconv.FormatUint(v, 10) }

// truncate caps a description at n bytes so a runaway pattern
// label (e.g. a 30KB log message captured as the anomaly
// pattern) doesn't bloat the problems table row.
func truncate(s string, n int) string {
	if len(s) <= n {
		return s
	}
	return s[:n-1] + "…"
}

// effectiveSeverity clamps a freshly-RECOMPUTED severity to the age-based
// escalation floor (v0.8.309). Refresh paths that derive severity from the
// live gauge every tick (db-capacity, anomaly promotion) were silently
// undoing escalateStaleProblems' bump, and the sweep then re-escalated AND
// re-paged every tick — the critical-notification storm. Routing the
// recompute through this clamp means an escalated problem can never dip
// back below its floor, so the sweep finds nothing to re-fire on.
func effectiveSeverity(computed string, openFor time.Duration, cfg chstore.ProblemEscalationConfig) string {
	if next := nextSeverity(computed, openFor, cfg); next != "" {
		return next
	}
	return computed
}

// nextSeverity returns the new severity for a problem that's
// been open for `openFor`, or "" / unchanged when no
// escalation applies. The check is one-directional and
// idempotent: a problem already at critical never returns
// a higher tier; one that hasn't crossed any threshold yet
// returns "".
//
// v0.9.248 — windows come from the operator's escalation settings
// (were hard-coded 15 min / 30 min). cfg.Enabled == false disables
// the climb entirely: severity then stays wherever the rule that
// opened the Problem put it. Callers pass the config the sweep read
// once, so every problem in one pass is judged against the same
// snapshot.
func nextSeverity(cur string, openFor time.Duration, cfg chstore.ProblemEscalationConfig) string {
	if !cfg.Enabled {
		return ""
	}
	cfg = chstore.NormalizeProblemEscalation(cfg)
	toWarning := time.Duration(cfg.InfoToWarningSec) * time.Second
	toCritical := time.Duration(cfg.WarningToCriticalSec) * time.Second
	switch strings.ToLower(cur) {
	case "info":
		if openFor >= toCritical {
			return "critical"
		}
		if openFor >= toWarning {
			return "warning"
		}
	case "warning":
		if openFor >= toCritical {
			return "critical"
		}
	}
	return ""
}

// measure runs the per-service metric query for the given window.
// metricNeedsSampleFloor reports whether a metric's value is
// distorted by low sample counts (1 of 1 = 100% error rate)
// versus an absolute count whose value carries the signal
// directly. v0.5.128's MinSamples gate only applies to the
// former.
func metricNeedsSampleFloor(metric string) bool {
	// v0.8.314 — request_rate is ABSOLUTE (spans/second), not a ratio: at
	// low traffic it IS the signal, so gating it on MinSamples suppressed
	// traffic-drop rules exactly during the outage they exist to catch.
	// The generic "_rate" suffix below is for ratio-like custom metrics;
	// the known absolutes are exempted explicitly.
	switch metric {
	case "request_rate", "error_count":
		return false
	}
	if strings.HasSuffix(metric, "_rate") || strings.HasSuffix(metric, "_ms") {
		return true
	}
	switch metric {
	case "error_rate", "avg_ms", "p50_ms", "p95_ms", "p99_ms":
		return true
	}
	return false
}

// measureCount returns the total span count for a service over
// the window. Used by the MinSamples gate; one extra round-trip
// per rule per tick (skipped when MinSamples == 0).
// defaultAssignee resolves the team that should see a freshly-
// opened Problem before anyone manually claims it. Looks at the
// service's catalog metadata: owner_team wins (the team that
// builds + ships the service), sre_team is the fallback for
// services with no listed owner. Empty when no catalog row
// exists yet — the operator can still claim manually.
func (e *Evaluator) defaultAssignee(ctx context.Context, service string) string {
	if service == "" {
		return ""
	}
	md, err := e.store.GetServiceMetadata(ctx, service)
	if err != nil || md == nil {
		return ""
	}
	if md.OwnerTeam != "" {
		return md.OwnerTeam
	}
	return md.SRETeam
}

// useSummaryMV decides whether a measure() / measureCount() call for the
// given alert window can ride the 5-minute MV instead of scanning raw
// spans (v0.6.12). v0.8.352 — the boundary AND the v0.8.315 aligned-window
// math below moved to chstore/evaluator_reads.go so the batched
// (MeasureAllServices) and per-service paths share ONE implementation;
// these wrappers keep the evaluator's sub-5m raw path + the existing
// contract tests (mv_routing_test.go, mv_window_test.go) on the same
// single source.
func useSummaryMV(window time.Duration) bool {
	return chstore.UseSummaryMV(window)
}

// mvWindowStart aligns the window cutoff DOWN to the MV's 5m bucket grid
// (v0.8.315) — see chstore.MVWindowStart for the full incident story.
func mvWindowStart(now time.Time, window time.Duration) time.Time {
	return chstore.MVWindowStart(now, window)
}

// mvCoveredSeconds is the real span the aligned MV read covers — always
// ≥ the nominal window (window + up-to-299s drift).
func mvCoveredSeconds(now time.Time, window time.Duration) float64 {
	return chstore.MVCoveredSeconds(now, window)
}

// scaleToWindow normalizes an absolute count observed over `covered`
// seconds to the nominal window, so thresholds keep their configured
// meaning ("50 errors in 5 min" stays a 5-minute quantity even though the
// aligned read spans up to 5m+299s).
func scaleToWindow(n, windowSec, coveredSec float64) float64 {
	return chstore.ScaleToWindow(n, windowSec, coveredSec)
}

func (e *Evaluator) measureCount(ctx context.Context, service string, window time.Duration) (uint64, error) {
	now := time.Now()
	var n uint64
	if useSummaryMV(window) {
		// v0.8.315 — bucket-aligned cutoff + normalize back to the
		// nominal window (see mvWindowStart).
		err := e.store.TelemetryReadConn().QueryRow(ctx, `
			SELECT countMerge(span_count_state) FROM service_summary_5m
			WHERE service_name = ? AND time_bucket >= ?
			SETTINGS max_execution_time = 10`,
			service, mvWindowStart(now, window)).Scan(&n)
		if err != nil {
			return 0, err
		}
		return uint64(scaleToWindow(float64(n), window.Seconds(), mvCoveredSeconds(now, window))), nil
	}
	err := e.store.TelemetryReadConn().QueryRow(ctx, `
		SELECT count() FROM spans WHERE service_name = ? AND time >= ?
		SETTINGS max_execution_time = 10`,
		service, now.Add(-window)).Scan(&n)
	return n, err
}

func (e *Evaluator) measure(ctx context.Context, service, metric string, window time.Duration) (float64, error) {
	now := time.Now()
	cutoff := now.Add(-window)
	conn := e.store.TelemetryReadConn()
	mv := useSummaryMV(window)
	if mv {
		// v0.8.315 — the MV filter is on the bucket START; align down so
		// the cutoff's bucket is included (ratios/quantiles read a
		// deterministic full window; counts/rates normalize below).
		cutoff = mvWindowStart(now, window)
	}

	switch metric {
	case "error_rate":
		// v0.10.783 — giriş-span ilkesi: toplu yolla (measureAllServicesPlan)
		// aynı kaynak ve süzgeç; iki yol ayrışmasın.
		var v float64
		var sql string
		if mv {
			sql = `SELECT toFloat64(countMerge(error_state)) /
			              nullIf(toFloat64(countMerge(calls_state)),0) * 100
			       FROM spanmetrics_1m
			       WHERE service_name=? AND time_bucket>=? AND ` + chstore.EntrySpanKindsWhere + `
			       SETTINGS max_execution_time = 10`
		} else {
			sql = `SELECT countIf(status_code='error') / nullIf(count(),0) * 100
			       FROM spans WHERE service_name=? AND time>=? AND ` + chstore.EntrySpanKindsWhere + `
			       SETTINGS max_execution_time = 10`
		}
		err := conn.QueryRow(ctx, sql, service, cutoff).Scan(&v)
		if err != nil {
			return 0, err
		}
		return v, nil
	case "error_count":
		var n uint64
		var sql string
		if mv {
			sql = `SELECT countMerge(error_count_state) FROM service_summary_5m
			       WHERE service_name=? AND time_bucket>=?
			       SETTINGS max_execution_time = 10`
		} else {
			sql = `SELECT countIf(status_code='error') FROM spans
			       WHERE service_name=? AND time>=?
			       SETTINGS max_execution_time = 10`
		}
		err := conn.QueryRow(ctx, sql, service, cutoff).Scan(&n)
		if err != nil {
			return 0, err
		}
		if mv {
			// Absolute count over the aligned (over-covering) read —
			// normalize back to the nominal window (v0.8.315).
			return scaleToWindow(float64(n), window.Seconds(), mvCoveredSeconds(now, window)), nil
		}
		return float64(n), nil
	case "request_rate":
		var n uint64
		var sql string
		if mv {
			sql = `SELECT countMerge(span_count_state) FROM service_summary_5m
			       WHERE service_name=? AND time_bucket>=?
			       SETTINGS max_execution_time = 10`
		} else {
			sql = `SELECT count() FROM spans WHERE service_name=? AND time>=?
			       SETTINGS max_execution_time = 10`
		}
		err := conn.QueryRow(ctx, sql, service, cutoff).Scan(&n)
		if err != nil {
			return 0, err
		}
		if mv {
			// Rate over the REAL covered span, not the nominal window —
			// the pre-v0.8.315 partial-bucket count ÷ full window read as
			// low as ~20% of the true rate (false traffic-drop alerts).
			return float64(n) / mvCoveredSeconds(now, window), nil
		}
		return float64(n) / window.Seconds(), nil
	case "p50_ms", "p95_ms", "p99_ms", "avg_ms":
		var sql string
		if mv {
			// quantilesMerge returns the full tuple; arrayElement
			// picks the requested index. Indices match the MV's
			// quantilesState(0.5, 0.95, 0.99) ordering: 1=p50,
			// 2=p95, 3=p99. duration_q_state is the merge target.
			switch metric {
			case "avg_ms":
				sql = `SELECT toFloat64(sumMerge(duration_sum_state)) /
				              nullIf(toFloat64(countMerge(span_count_state)),0) / 1e6
				       FROM service_summary_5m
				       WHERE service_name=? AND time_bucket>=?
				       SETTINGS max_execution_time = 10`
			case "p50_ms":
				sql = `SELECT arrayElement(quantilesTDigestMerge(0.5,0.95,0.99)(duration_q_state), 1) / 1e6
				       FROM service_summary_5m
				       WHERE service_name=? AND time_bucket>=?
				       SETTINGS max_execution_time = 10`
			case "p95_ms":
				sql = `SELECT arrayElement(quantilesTDigestMerge(0.5,0.95,0.99)(duration_q_state), 2) / 1e6
				       FROM service_summary_5m
				       WHERE service_name=? AND time_bucket>=?
				       SETTINGS max_execution_time = 10`
			case "p99_ms":
				sql = `SELECT arrayElement(quantilesTDigestMerge(0.5,0.95,0.99)(duration_q_state), 3) / 1e6
				       FROM service_summary_5m
				       WHERE service_name=? AND time_bucket>=?
				       SETTINGS max_execution_time = 10`
			}
		} else {
			switch metric {
			case "avg_ms":
				sql = `SELECT avg(duration) / 1e6 FROM spans
				       WHERE service_name=? AND time>=?
				       SETTINGS max_execution_time = 10`
			default:
				q := metric[1 : len(metric)-3] // "50" / "95" / "99"
				sql = fmt.Sprintf(`SELECT quantile(0.%s)(duration) / 1e6
				                   FROM spans WHERE service_name=? AND time>=?
				                   SETTINGS max_execution_time = 10`, q)
			}
		}
		var v float64
		err := conn.QueryRow(ctx, sql, service, cutoff).Scan(&v)
		return v, err
	}

	// Transport-scoped metrics — narrow each query by an indexed
	// LowCardinality column (db_system / rpc_system / kind /
	// http_method) so the (service_name, time) primary key still
	// drives the scan and only relevant rows are aggregated. These
	// power the production-grade DB / RPC / HTTP / MQ alert
	// categories.
	//
	// For *_rate metrics the WHERE narrows the *denominator* (the
	// span population we're measuring against, e.g. all HTTP server
	// spans), and the *_rate's numerator condition counts within
	// that population (e.g. http_status >= 500). Conflating the two
	// — narrowing WHERE by 5xx — would produce 100% trivially.
	if where, numerator, ok := transportFilter(metric); ok {
		op := transportOp(metric)
		// v0.6.12 — every transport-scoped query stays on raw
		// spans because service_summary_5m has no breakdown by
		// http_method / db_system / rpc_system / kind. The
		// indexed (service_name, time) prefix still drives the
		// scan, but we now cap wall-clock at 10s so a CH lock
		// fight can't pin the evaluator tick.
		const settings = ` SETTINGS max_execution_time = 10`
		var sql string
		switch op {
		case "error_rate":
			sql = `SELECT countIf(` + numerator + `) * 100.0 / nullIf(count(),0)
				FROM spans WHERE service_name=? AND time>=? AND ` + where + settings
		case "p50_ms", "p95_ms", "p99_ms", "avg_ms":
			if op == "avg_ms" {
				sql = `SELECT avg(duration) / 1e6
					FROM spans WHERE service_name=? AND time>=? AND ` + where + settings
			} else {
				q := op[1 : len(op)-3]
				sql = fmt.Sprintf(`SELECT quantile(0.%s)(duration) / 1e6
					FROM spans WHERE service_name=? AND time>=? AND `, q) + where + settings
			}
		case "count":
			sql = `SELECT count() FROM spans WHERE service_name=? AND time>=? AND ` + where + settings
		default:
			return 0, fmt.Errorf("unknown transport op %q in %q", op, metric)
		}
		var v float64
		err := conn.QueryRow(ctx, sql, service, cutoff).Scan(&v)
		return v, err
	}
	return 0, fmt.Errorf("unknown metric %q", metric)
}

// transportFilter returns the denominator population predicate + the
// *_rate numerator predicate for a transport-scoped metric. v0.8.352 —
// the mapping moved to chstore.TransportFilter so the batched
// MeasureAllServices routing and this per-service raw path can never
// drift; this wrapper keeps the sub-5m path readable.
func transportFilter(metric string) (where, numerator string, ok bool) {
	return chstore.TransportFilter(metric)
}

// transportOp pulls the aggregate suffix off a transport metric
// (http_p99_ms → p99_ms). Single source: chstore.TransportOp (v0.8.352).
func transportOp(metric string) string {
	return chstore.TransportOp(metric)
}

func compare(value float64, op string, threshold float64) bool {
	switch op {
	case ">":
		return value > threshold
	case ">=":
		return value >= threshold
	case "<":
		return value < threshold
	case "<=":
		return value <= threshold
	}
	return false
}

func describeProblem(r chstore.AlertRule, service string, value float64) string {
	unit := metricUnit(r.Metric)
	return fmt.Sprintf("%s on %s — observed %.2f%s, threshold %s %.2f%s over %ds window.",
		r.Name, service, value, unit, r.Comparator, r.Threshold, unit, r.WindowSec)
}

func metricUnit(m string) string {
	if strings.HasSuffix(m, "_ms") {
		return "ms"
	}
	if strings.HasSuffix(m, "_rate") {
		// http_5xx_rate, db_error_rate, rpc_error_rate, … all
		// percent — request_rate is the one exception.
		if m == "request_rate" {
			return "/s"
		}
		return "%"
	}
	return ""
}

func newID() string {
	b := make([]byte, 12)
	rand.Read(b)
	return hex.EncodeToString(b)
}
