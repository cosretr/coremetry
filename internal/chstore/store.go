package chstore

import (
	"context"
	"crypto/tls"
	"fmt"
	"log"
	"strings"
	"sync"
	"sync/atomic"
	"time"

	"github.com/ClickHouse/clickhouse-go/v2"
	"github.com/ClickHouse/clickhouse-go/v2/lib/driver"

	"github.com/cilcenk/coremetry/internal/config"
)

// roundRobinConnLifetime — RoundRobin havuzlarındaki (ingest + read)
// bağlantıların azami ömrü. v0.9.505.
//
// NEDEN sürücü varsayılanı (1 saat) yetmiyor: ConnOpenRoundRobin
// BAĞLANTI AÇILIŞINI dağıtır, sorguyu değil. Bir bağlantı açıldığı
// host'a ömrü boyunca bağlı kalır ve Go havuzu boştaki en son
// kullanılan bağlantıyı geri verir — yani trafik birkaç sıcak
// bağlantıya yığılır ve onların düştüğü host bir saat boyunca yükü
// taşır. Ölçüm (lokal 2 node, v0.9.504 sonrası 180sn'lik fark):
// giriş sorgularının %83'ü tek node'da, oysa okuma havuzu aktifti.
// Aynı mekanizma prod'daki INSERT eğriliğini de açıklıyor (2.31×,
// ingest havuzu v0.9.481'den beri RoundRobin olmasına rağmen).
//
// 5 dk: bağlantılar periyodik olarak kapanıp yeniden açılır, her
// açılış round-robin'in bir sonraki host'una düşer, yük zamanla
// düzleşir. Maliyet ihmal edilebilir — CH native protokol el sıkışması
// ucuz ve tavan 60 bağlantıda dakikada ≤12 yeniden bağlanma demek.
// ANA bağlantı bilinçli olarak 1 saatte kalır: o zaten in-order,
// hep ilk host'a gidiyor, çevrimden kazanacağı bir şey yok.
const roundRobinConnLifetime = 5 * time.Minute

type Store struct {
	// shardConns (v0.10.125) — backfill'in shard-yerel INSERT'i için host
	// başına doğrudan bağlantı (trace_backfill_shards.go); tembel, önbellekli.
	shardMu    sync.Mutex
	shardConns map[string]driver.Conn
	// mvCoverage (v0.10.124) — trace_summary_5m gün başına boşluk haritası,
	// 60 sn önbellek (trace_mv_coverage.go).
	mvCoverage traceMVCoverage
	// chOpts (v0.9.1191) — New()'daki bağlantı seçenekleri fabrikası.
	// Her çağrı TAZE bir Options üretir (Settings map'i sürücüde kalıyor;
	// paylaşmak iki havuzu birbirine bağlardı). Tek tüketici uzun-işlem
	// bağlantısı (spool_ops.go); nil (Store{} kuran testler) = özellik yok.
	chOpts func() *clickhouse.Options

	// v0.9.614 — DDL erteleme durumu (ddl_defer.go). YALNIZ boot
	// sırasında, tek goroutine'den dokunulur; New dönmeden
	// finishDeferredDDL ile temizlenir.
	deferDDL    bool
	deferredDDL []string

	// v0.9.1308 — state tablolarının kümede GÖZLENEN ZK yolları
	// (state_replication.go). adaptDDL buradan okur; sıfır değeri
	// "probe koşmadı" = eski (shard'lı) yol = v0.9.1308 öncesi
	// davranışın birebir aynısı.
	//
	// YALNIZ boot/migrate goroutine'inden yazılır — deferDDL ile aynı
	// sözleşme; okuma da aynı zincirden (execDDL → adaptDDL).
	stateObs stateObservation

	// canonicalTableDDL (v0.10.829) — migrate()'in kurduğu tablo
	// kataloğunun HAM CREATE metinleri. "İlk replikayı kur" sihirbazı
	// (replica_repair.go seedCanonicalArgs) ZK yolu sözleşmesini
	// buradan + adaptDDL'den okur, tahmin etmez.
	//
	// stateObs ile AYNI sözleşme: yalnız boot/migrate goroutine'i yazar,
	// sonrası salt okuma. Sıfır değeri (Store{} kuran testler) = katalog
	// yok = sihirbaz her tabloyu engeller (fail-closed).
	canonicalTableDDL []string

	// metricExclusions (v0.9.797) — operatörün route dışlama kuralları,
	// DERLENMİŞ hâlde. Okuma yolları (buildMetricQuerySQL, queryRateFrom,
	// route-tier) her sorguda buradan okur, yani bir CH okuması sıcak
	// yola giremez: blob boot'ta hidrate edilir, admin PUT'unda anında
	// değişir, çok-pod kurulumlarda 30 sn'lik yenilemeyle yakınsar
	// (exception_triage kablosunun aynısı — internal/api/metric_exclusions.go).
	//
	// Sıfır değeri (hiç Store edilmemiş) nil'dir ve TÜM metotlar
	// nil-güvenli: Store{} kuran testler kuralsız davranır.
	metricExclusions atomic.Pointer[CompiledMetricExclusions]

	// traceRootDef (v0.10.733, operatör onaylı spec 2026-09-16) — /traces
	// "Root" süzgecinin, şerit kök yükleminin ve kök kapsama ölçüsünün TANIMI:
	// 0 = strict (tam kök: parent boş + ad + servis), 1 = entry (giriş kökü:
	// tam kök YA DA en az bir server/consumer giriş span'i). system_settings
	// 'trace_root_def' blob'undan hidre edilir (api.LoadTraceRootDef +
	// 30 s yenileme); sıfır değeri strict = önceki davranış birebir.
	traceRootDef atomic.Int32

	// anomalyTracked (v0.9.800) — anomali dedektörünün ölçtüğü metrik
	// seti, AYNI kablo (anomaly_tracked.go). Dedektör her tikte buradan
	// okur: tik başına bir CH okuması daha eklemeden ayar canlı kalır.
	//
	// Sıfır değeri (hiç Store edilmemiş) nil'dir ve AnomalyTracked()
	// nil-güvenli: hidrasyondan önceki ilk tik varsayılan seti görür.
	anomalyTracked atomic.Pointer[AnomalyTrackedConfig]

	// anomalySensitivity (v0.9.826) — dedektörün EŞİKLERİ, AYNI kablo
	// (anomaly_sensitivity.go). anomalyTracked hangi metriğin ölçüleceğini
	// söylüyor; bu, ölçülenin ne zaman OLAY sayılacağını.
	//
	// Sıfır değeri (hiç Store edilmemiş) nil'dir ve AnomalySensitivity()
	// nil-güvenli: hidrasyondan önceki ilk tik varsayılanları görür.
	anomalySensitivity atomic.Pointer[AnomalySensitivityConfig]

	// memPlan (v0.9.975) — the per-query memory ceilings actually in
	// force, proportioned to the server's own max_server_memory_usage at
	// boot. Every SQL site that used to carry its own `max_memory_usage
	// = <literal>` reads from here via queryMemory/spillMemory. The zero
	// value (Store built without New — SQL-shape tests, tooling) has
	// ServerMax 0 and therefore fails OPEN: every clamp is a no-op and
	// the rendered SQL is byte-identical to pre-v0.9.975. Rationale and
	// the measurement that forced it: query_memory.go.
	memPlan queryMemoryPlan

	conn driver.Conn
	// ingest is the RoundRobin pool used ONLY for high-volume telemetry
	// INSERTs — see the two-pool rationale at the clickhouse.Open calls
	// (v0.9.486). nil in tests that build Store{} directly; use
	// ingestWriteConn(), never the field.
	ingest driver.Conn
	// read is the RoundRobin pool for high-volume telemetry SELECTs
	// (v0.9.496). Same safety argument as ingest: these queries hit
	// Distributed wrappers / MV'ler, so any node can coordinate and the
	// answer is identical. State tables must NEVER read through this —
	// use telemetryReadConn(), never the field.
	read driver.Conn
	cfg  config.CHConfig
	ret  config.RetentionConfig

	// service_version_5m coverage cache (v0.9.249, reshaped v0.9.493).
	// A materialized view only populates from inserts made after it
	// exists, so for the first lookback after an upgrade the rollup
	// can't answer "was this version already running before the
	// window?" — see deployMVCovers in deploys.go for why reading it
	// early would re-open the v0.9.205 phantom-marker bug. v0.9.493:
	// the old boolean latch ignored each call's `need` once ANY probe
	// succeeded (a 24h-need caller unlocked the 48h-need path early,
	// and historical windows older than the MV slipped through) — now
	// the probed EARLIEST datum is cached and every call compares its
	// own need against it; deployMVProbedAt throttles re-probes.
	deployMVMu       sync.Mutex
	deployMVEarliest time.Time
	deployMVProbedAt time.Time

	// hasClusterCol records whether the spans table the read path
	// actually resolves against carries the materialized `cluster`
	// column (v0.8.132). When chstore owns the DDL (single node, or a
	// cluster with cfg.ClusterName set) the migration adds it and this
	// is true. Against an EXTERNAL Distributed `spans` with ClusterName
	// unset — the operator manages spans_local's schema — the column
	// never reaches the per-shard table, so any query that references
	// `cluster` fails with code 47 ("cannot be resolved"). Probed once
	// at boot (see migrate); when false the cluster expression falls
	// back to the pure res/attr derive — correct everywhere, just
	// without the column short-circuit. (v0.8.162 — operator-reported:
	// distributed prod spammed code-47 on the cluster warm query.)
	hasClusterCol bool

	// hasOpGroupCol records whether the spans table the WRITE path
	// inserts into actually carries the `op_group` column (v0.8.172).
	// op_group is an EXPLICIT Go-written column (convert.go fills it
	// from templater.NormalizeOperation; the spans INSERT binds
	// sp.OpGroup), so unlike the materialized `cluster` it sits on the
	// INGEST path — if the column never reached the per-shard
	// spans_local the INSERT fails with code 16 ("No such column
	// op_group in table spans_local") and EVERY span batch is lost.
	// That is exactly what happened on an external Distributed install
	// with cfg.ClusterName unset (v0.8.186): chstore can't ON CLUSTER
	// the ALTER, so it lands on the Distributed wrapper definition only
	// and never on spans_local. When this is false the INSERT drops
	// op_group from its column list entirely, the operation_group
	// summary MV is dropped + not recreated, and the normalized
	// operations read soft-degrades to raw-name grouping. Probed once
	// at boot (see migrate). On a single node or a cluster with
	// ClusterName set (where adaptDDL owns spans_local) this is true
	// and the path is byte-identical to pre-v0.8.186.
	hasOpGroupCol bool
	// v0.9.1077 — system.distribution_queue.last_exception_time probe'u
	// (süreç ömründe bir kez; distribution_queue.go).
	distQueueLastAtOnce sync.Once
	distQueueHasLastAt  bool

	// hasSeriesFpCol records whether metric_points actually carries the
	// `series_fingerprint` column (v0.8.328, cross-signal pivot). Same
	// hazard class as hasOpGroupCol: it is an EXPLICIT Go-written column on
	// the INGEST path (convert.go computes it, the metric_points INSERT
	// binds it), so on an external Distributed install with
	// cfg.ClusterName unset the ALTER would land on the wrapper only,
	// never on metric_points_local, and EVERY metric batch would be lost
	// with code 16 — the exact failure that broke prod twice (cluster
	// v0.8.185, op_group v0.8.186). The ALTER is therefore gated on
	// tableIsExternalDistributed and this probe decides whether the
	// INSERT includes the column. When false, metric rows land without a
	// fingerprint (0 = legacy sentinel) and the exemplar pivot degrades
	// to the metric+service fallback read — ingest never breaks.
	hasSeriesFpCol bool

	// hasIsMonotonicCol records whether metric_points carries is_monotonic
	// (v0.9.106, F2). False on an external Distributed install where the ALTER
	// never reached the shards → INSERT omits it + rate() runs without the
	// UpDownCounter guard (best-effort). Probed once at boot.
	hasIsMonotonicCol bool

	// hasRCAVerdictBodyCol — rca_verdicts GERÇEKTEN body+source kolonlarını
	// taşıyor mu (v0.9.1281).
	//
	// rca_verdicts spans/metric_points sınıfında DEĞİL: chstore onu dış
	// Distributed kümelerde bile tek-node şeklinde yaratıyor, yani
	// wrapper/_local uyumsuzluğu (v0.8.185/186 prod kırılmaları) bu
	// tabloda oluşamaz. Probe yine de ŞART ve sebebi başka: küme kipinde
	// DDL ERTELENİR (ddlDeferred). Kolonu EKLEYEN boot, ALTER kuyruğa
	// alındığı için probe'u false okur — ve o boot boyunca INSERT kolonsuz
	// koşmalı, yoksa her verdict yazımı code 16 ile düşerdi. İkinci boot
	// true okur ve gövde yazılmaya başlar.
	//
	// false ⇒ INSERT body/source'u ATLAR (kayıt yine yazılır, yalnız gövde
	// taşımaz) ve kalıcı okuma boş gövde döner. Verdict ÜRETİMİ bundan
	// etkilenmez: muhasebe, tanıyı düşüremez.
	hasRCAVerdictBodyCol bool

	// hasDBStmtHashCol records whether the spans table actually carries the
	// `db_stmt_hash` column (v0.8.375, Stage-2 D1 — persistent DB-statement
	// identity). Unlike op_group / series_fingerprint the column is
	// MATERIALIZED (CH-computed at insert, the `cluster` precedent), so the
	// INSERT projection never mentions it and a wrapper/local mismatch can't
	// break ingest — this flag exists for the READ+MV side: it gates the
	// db_statement_summary_5m MV (whose SELECT references the column;
	// creating it without the column would code-16 every span INSERT — the
	// v0.8.186 class) and routes GetSlowQueriesGlobal between the MV read
	// and the raw-spans fallback.
	hasDBStmtHashCol bool
	// hasAlertRuleTargetCol — v0.10.331: alert_rules.target_json probu. v0.10.334:
	// atomic — ertelenmiş DDL boot'tan sonra indiğinde UpsertAlertRule yeniden
	// probe eder (tek restart yeter); okuma/yazma yarışsız.
	hasAlertRuleTargetCol atomic.Bool
	// hasAlertRuleNotifyCol — v0.10.519: alert_rules.notify_json probu (aynı
	// iki-boot sözleşmesi, alert_notify.go).
	hasAlertRuleNotifyCol atomic.Bool
	// v0.9.1097 — db_statement_summary_5m exemplar state kolonları var mı?
	// (0.5 Alternatif-B; okuma MV-önce, yoksa ham fallback.)
	hasDBStmtExemplarCols bool

	// hasExCols records whether spans carries the v0.8.566 exception
	// MATERIALIZED columns (ex_match/ex_type/ex_msg/ex_stack). False on an
	// external Distributed spans with cluster_name unset (ALTER skipped) —
	// the five exception query sites then fall back to the JSON_VALUE
	// expressions via exFragments(false).
	hasExCols bool

	// hasLdapUsernameCol records whether the `users` table carries the
	// `ldap_username LowCardinality(String)` column (v0.8.526, LDAP group
	// sync). Unlike op_group / series_fingerprint this is NOT a
	// highVolumeTables ingest column — `users` is a Coremetry-owned state
	// table (never operator-provisioned external Distributed), so the
	// ALTER rides the normal alters slice + execDDL→adaptDDL ON CLUSTER
	// and reaches the real table on every replica. The probe still gates
	// the WRITE path defensively: ldap_username is written by
	// TouchUserLogin on EVERY login (local + LDAP), so if the column were
	// somehow absent a naked INSERT column list would break auth
	// entirely. When false the INSERT/SELECT omit the column (LdapUsername
	// stays "") and the identity-overlap read falls back to email-only.
	hasLdapUsernameCol bool

	// hasProblemCmpCol — `problems` tablosunda comparator kolonu var mı
	// (v0.9.976). hasLdapUsernameCol ile AYNI sınıf: `problems` Coremetry'nin
	// kendi state tablosu, dış Distributed değil, yani ALTER normal alters
	// dilimiyle ON CLUSTER iniyor. Probe yine de şart, çünkü küme kipinde
	// migrate DDL'i ARKA PLANA erteliyor (v0.9.614): kolon henüz inmemişken
	// koşulsuz `SELECT comparator` her problem okumasını düşürürdü.
	//
	// false iken: SELECT ve INSERT kolonu ATLAR, Comparator boş kalır,
	// computePriority ters çevirme YAPMAZ — yani düşüş yönü GÜVENLİ tarafa
	// (sahte P1 üretmeyen tarafa). Kolon arka planda inince bir sonraki
	// boot'ta probe true okur (ddl_defer.go'nun bilinçli sonucu).
	hasProblemCmpCol bool

	// hasProblemKindCol — `problems` tablosunda kind kolonu var mı
	// (v0.9.1338). hasProblemCmpCol ile BİREBİR aynı sınıf ve aynı iki-boot
	// gerçeği: kolonu ekleyen boot DDL'i arka plana ertelediği için burayı
	// false okur.
	//
	// false hâlinin GÜVENLİ yönü: SELECT/INSERT kolonu atlar, Kind boş
	// scan edilir ve scanProblemRow onu ProblemKindService'e normalize eder
	// — yani o boot boyunca ürün bugünkü davranışın birebir aynısını
	// gösterir (db özneli satır da servis özneli görünür, bugünkü hâl).
	// Kolon inince bir sonraki boot true okur.
	hasProblemKindCol bool
	// openSnap (v0.10.156) — OpenProblemsSnapshot'ın 5 s'lik süreç-içi memo'su
	// (memo.go): arka plan işleri tick içinde tek FINAL taraması paylaşır;
	// UpsertProblem/UpsertProblemAISummary düşürür.
	openSnap *ttlMemo[*OpenProblems]
	// spreadMemo — v0.10.949 — ExceptionSpread'in 60 sn'lik memo'su (exception_spread.go).
	spreadMemo *ttlMemo[*ExceptionSpread]
	// v0.10.949 — yayılım okuması hata verdiyse bu ana kadar CH'a gidilmez (unix ns).
	// Sıfır değer = backoff yok; kurucu değişmez.
	spreadFailUntil atomic.Int64

	// hasTopoClusterCol — `topology_edges_5m` üstünde queue düğümünün
	// messaging cluster'ını taşıyan `cluster` kolonu var mı (v0.9.1025).
	// hasProblemCmpCol ile aynı sınıf ve aynı iki-boot gerçeği: küme
	// kipinde migrate DDL'i ertelendiği için kolonu EKLEYEN boot bu
	// probe'u false okur (v0.9.614 / ddl_defer.go).
	//
	// false hâli GÜVENLİ yön olacak şekilde tasarlandı: yazma pass'leri
	// kolonu INSERT kolon listesinden düşürür (aksi hâlde her topoloji
	// bucket'ı code 47 ile ölür ve graf tamamen durur), okuma yolu
	// cluster'ı boş görür ve kuyruk düğümü v0.9.972'nin daraltılmış
	// KATALOG köprüsünde kalır — yani en kötü hâl "eski davranış",
	// asla yanlış bir cluster'a açılan çekmece değil.
	hasTopoClusterCol bool
	// hasTraceEntrySvcCol — trace_summary_5m.entry_service_state okunabilir
	// mi (v0.10.97). false iken /traces okumaları eski zinciri kullanır.
	hasTraceEntrySvcCol bool
	// envSummary — v0.10.881: service_env_summary_5m kapsama probu (60 s).
	envSummary envSummaryProbe

	// neighborProvider is the optional 1-hop topology lookup used
	// by AttachProblemToIncident for rule 3 (cluster a new
	// problem into an existing incident on a service that calls
	// or is called by this one). Set via SetNeighborProvider —
	// kept on the store so the three auto-attach call sites
	// (evaluator, anomaly, monitor) don't need to thread it
	// through their constructors.
	neighborProvider NeighborProvider
	// incidentLifecycle — v0.10.748 incident açılış/çözüm bildirimi kancası
	// (incident_lifecycle.go); boot'ta SetIncidentLifecycleHook ile.
	incidentLifecycle IncidentLifecycleHook

	// smCov caches the earliest available time_bucket across the
	// spanmetrics_{1s,10s,1m} rollups (v0.8.51, doorway D2). This is
	// the forward-only "cutover floor" — the MVs only roll spans
	// inserted after their creation — and also the TTL floor as old
	// partitions drop. ResolveMetricQuery consults it to decide
	// whether a window is fully covered by the fine-grain tiers or
	// must dual-read the operation_summary_5m / raw fallback for the
	// portion predating cutover. Probed at most once per smCovTTL so
	// a chart render doesn't run min(time_bucket) every time.
	smCovMu  sync.RWMutex
	smCovAt  time.Time // when smCovVal was last probed
	smCovVal time.Time // earliest available spanmetrics bucket
	// metricIv caches each metric's observed export interval (v0.8.243,
	// granularity slice B) so the per-query min-step clamp costs one
	// bounded probe per metric per minute, not per chart refresh.
	metricIvMu sync.RWMutex
	metricIv   map[string]metricIvEntry

	// alertRules* (v0.8.x) — in-process cache of the tiny alert_rules
	// ReplacingMergeTree. The load-test profile showed ListAlertRules
	// (a FINAL scan) ran 1000+×/4min on the problems-enrichment +
	// evaluator hot paths; rules are tens of rows and mutate only on an
	// operator action. Short TTL + write-side invalidation keeps it fresh.
	// In distributed mode a peer pod's write is picked up within the TTL
	// (acceptable lag for alert-rule edits).
	alertRulesMu  sync.RWMutex
	alertRulesAt  time.Time // when alertRulesVal was last fetched
	alertRulesVal []AlertRule

	// v0.8.359 (perf P2-C): the /api/problems warm recompute measured
	// 145-580ms — dominated by three read-time enrichment lookups that
	// are near-static between 5s polls: the service→cluster map (raw
	// spans GROUP BY, ~120-220ms), the service catalog FINAL scan
	// (runbooks + teams read it back to back), and the deploys
	// GROUP BY (~80-130ms). Same TTL treatment as alertRules above;
	// svcMeta additionally invalidates on Upsert so a catalog edit
	// still lands on the operator's next refresh.
	svcMetaMu  sync.RWMutex
	svcMetaAt  time.Time
	svcMetaVal map[string]ServiceMetadata

	clusterMapMu  sync.RWMutex
	clusterMapAt  time.Time
	clusterMapFor time.Duration // the `since` clusterMapVal was built with
	clusterMapVal map[string][]string

	// envMap* (v0.8.387, env-separation Phase 3) — the service→envs
	// twin of clusterMap* above, backing the /problems env filter.
	// Same P2-C discipline: 60s single-entry cache keyed by `since`,
	// replace-never-mutate, returned SHARED (read-only callers).
	envMapMu  sync.RWMutex
	envMapAt  time.Time
	envMapFor time.Duration // the `since` envMapVal was built with
	envMapVal map[string][]string

	// dbOwn* (v0.9.1345) — db_system → en çok çağıran servisler anlık
	// görüntüsü, db-konulu problemlerin sahipliğini çözmek için
	// (db_ownership.go). svcMeta/clusterMap ile AYNI P2-C disiplini:
	// cevap sayfaya/filtreye/aralığa göre değişmiyor, dolayısıyla
	// problem başına sormak aynı filo-geneli okumayı N kez yapmaktır.
	// Tek girdi, TTL'li, değiştirilmeden DEĞİŞTİRİLİR (replace-never-
	// mutate) ve PAYLAŞILARAK döner — çağıranlar salt-okur.
	dbOwnMu  sync.RWMutex
	dbOwnAt  time.Time
	dbOwnVal map[string][]DBCaller

	deploysMu    sync.Mutex
	deploysCache map[string]deploysCacheEntry
}

// alertRulesCacheTTL bounds how stale a cached rule list can be when no
// write invalidates it first.
const alertRulesCacheTTL = 30 * time.Second

// v0.8.359 enrichment-lookup TTLs. Cluster membership is
// infrastructure-stable (a service joining a new cluster shows up
// within a minute — same tolerance the clusters warmer uses); the
// catalog mutates only on operator edits (write path invalidates);
// deploys are derived from span first_seen so they are already
// minutes-lagged — 15s staleness is invisible.
const (
	svcMetaCacheTTL    = 30 * time.Second
	clusterMapCacheTTL = 60 * time.Second
	envMapCacheTTL     = 60 * time.Second // v0.8.387 — env twin of clusterMapCacheTTL
	deploysCacheTTL    = 15 * time.Second
	deploysCacheMax    = 64 // distinct (service-set, window) keys kept
)

// ddlTaskTimeoutSeconds — sunucunun bir ON CLUSTER DDL için TÜM
// host'ları bekleme bütçesi (v0.9.606).
//
// Operator-reported (prod, v0.9.605 sonrası): CREATE DATABASE geçti ama
// ilk CREATE TABLE istemci tarafında öldü:
//
//	migrate: create table: ddl exec: … read tcp …: i/o timeout
//	SQL: CREATE TABLE IF NOT EXISTS spans_local ON CLUSTER `…`
//
// Bu bir ClickHouse hata KODU değil — sürücünün ReadTimeout'u.
// ClickHouse varsayılanı distributed_ddl_task_timeout = 180 sn;
// sürücününki ReadTimeout = 30 sn. v0.9.605 sunucunun İSTİSNA atmasını
// engelledi ama BEKLEMESİNİ engellemedi, dolayısıyla istemci hep önce
// ölüyordu ve hata "i/o timeout" diye görünüyordu — gerçek sebebi (DDL
// kuyruğu) hiç söylemeden.
//
// İki sayı iki ayrı yerde yaşıyordu ve aralarındaki ilişkiyi kimse
// kurmuyordu. Kural artık testle sabit: SUNUCUNUN BÜTÇESİ
// İSTEMCİNİNKİNDEN KISA OLMALI.
//
// 20 sn: 30 sn'lik ReadTimeout'un rahatça altında, ve sağlıklı bir
// kümede ON CLUSTER DDL saniyeler sürer. Kuyruk tıkalıysa zaten hiçbir
// bekleme yetmez — o hâlde HIZLI ve AÇIK başarısız olmak, 30 saniye
// bekleyip anlamsız bir soket hatası vermekten iyidir.
const ddlTaskTimeoutSeconds = 20

func New(cfg config.CHConfig, ret config.RetentionConfig) (*Store, error) {
	dialTimeout, _ := time.ParseDuration(cfg.DialTimeout)
	if dialTimeout == 0 {
		dialTimeout = 5 * time.Second
	}
	maxConns := cfg.MaxOpenConns
	if maxConns == 0 {
		// Fallback only — config.Load (resolveMaxOpenConns, v0.8.205) is the
		// primary sizer and derives this from Ingestion.Workers (3 signals ×
		// workers + read headroom) before New is ever called. This branch
		// just guards callers that build a CHConfig directly (tests, tooling)
		// without going through Load. 24 = the fan-out at the default 8
		// workers. The driver opens lazily, so api-only pods that never flush
		// pay nothing for the higher ceiling.
		maxConns = 24
	}

	ctx := context.Background()

	// Comma-split address — driver round-robins / fails over across
	// the seeds, so a 4-node external cluster can be configured
	// without a separate LB. Falls back to the raw string when no
	// commas are present.
	hosts := cfg.Hosts()
	if len(hosts) == 0 {
		return nil, fmt.Errorf("clickhouse addr is required")
	}
	var tlsCfg *tls.Config
	if cfg.Secure {
		tlsCfg = &tls.Config{InsecureSkipVerify: cfg.InsecureSkipVerify}
	}
	if cfg.Secure {
		log.Printf("[chstore] connecting to %d host(s) over native TLS (insecure=%v): %v",
			len(hosts), cfg.InsecureSkipVerify, hosts)
	} else if len(hosts) > 1 {
		log.Printf("[chstore] connecting to %d host(s) (driver fail-over enabled): %v", len(hosts), hosts)
	}

	// Create database using default DB connection. CH may still be coming
	// up (Helm-managed StatefulSet, fresh container, etc.) so retry the
	// initial CREATE DATABASE for up to ~2 minutes before giving up.
	var setup driver.Conn
	openSetup := func() error {
		c, err := clickhouse.Open(&clickhouse.Options{
			Addr:        hosts,
			Auth:        clickhouse.Auth{Database: "default", Username: cfg.Username, Password: cfg.Password},
			TLS:         tlsCfg,
			DialTimeout: dialTimeout,
			// v0.9.605 — PROD'DA PATLAYAN BAĞLANTI TAM BURASI.
			//
			// `CREATE DATABASE … ON CLUSTER` bu setup bağlantısından
			// çalışıyor ve varsayılan output_mode 'throw' olduğu için
			// istemci dört host'un da bitirmesini 180 sn bekleyip
			// istisna atıyordu. Ana bağlantıdaki ayarı buraya da koymak
			// ŞART — asıl arıza ana bağlantıya sıra gelmeden oluyordu.
			Settings: clickhouse.Settings{
				"distributed_ddl_output_mode": "null_status_on_timeout",
				// v0.9.606 — sunucunun bekleme bütçesi İSTEMCİNİNKİNDEN
				// kısa olmalı; gerekçe ddlTaskTimeoutSeconds'ta.
				"distributed_ddl_task_timeout": ddlTaskTimeoutSeconds,
			},
		})
		if err != nil {
			return err
		}
		if err := c.Ping(ctx); err != nil {
			c.Close()
			return err
		}
		setup = c
		return nil
	}
	{
		const attempts = 24
		var lastErr error
		for i := 0; i < attempts; i++ {
			if err := openSetup(); err == nil {
				lastErr = nil
				break
			} else {
				lastErr = err
				log.Printf("[chstore] waiting for ClickHouse at %s (%d/%d): %v", cfg.Addr, i+1, attempts, err)
				time.Sleep(5 * time.Second)
			}
		}
		if lastErr != nil {
			return nil, fmt.Errorf("setup connect after retries: %w", lastErr)
		}
	}
	// v0.8.280 — validate a SET cluster_name against system.clusters BEFORE any
	// ON CLUSTER DDL (the other half of the v0.8.213 fail-fast: 213 catches
	// UNSET against external-Distributed spans; this catches SET WRONG). A typo
	// otherwise dies inside CREATE DATABASE with a raw code-170 and no guidance.
	// Probe failures never block boot — see validateClusterName.
	if name := strings.TrimSpace(cfg.ClusterName); name != "" {
		if err := validateClusterName(ctx, setup, name); err != nil {
			setup.Close()
			return nil, fmt.Errorf("cluster_name validation: %w", err)
		}
	}
	// v0.9.975 — read the server's OWN memory ceiling while the setup
	// connection is still open. The per-query caps built into chOpts()
	// below are meaningless unless they sit UNDER this number; see the
	// measurement in query_memory.go. Fail-open: 0 = couldn't read.
	//
	// v0.9.984 — moved AHEAD of the DDL phase. It used to sit directly
	// after `CREATE DATABASE … ON CLUSTER`, and on the operator's live
	// cluster that read timed out at 5.86 s while the distributed DDL it
	// had just queued was still working through its ~20 s round — which
	// silently disarmed the whole clamp (fail-open). system.server_settings
	// needs no database, so this is the quietest moment in boot to ask:
	// connection up, cluster name validated, nothing queued yet.
	//
	// It cannot move any LATER. After migrate() would be the genuinely
	// idle point, but the clamp is baked into the driver's Settings map
	// when chOpts() opens the pools below, and migrate() runs ON those
	// pools — probing afterwards would mean either running every
	// migration unclamped or reopening both pools, a far bigger change
	// than this bug warrants.
	serverMaxMem := probeServerMaxMemory(ctx, setup, cfg.ClusterName)

	// v0.5.420 — operator-reported: "Database coremetry does not
	// exist" during cluster boot. Root cause: CREATE DATABASE was
	// emitted without ON CLUSTER, so the database appeared only
	// on the coordinator node Coremetry happened to connect to.
	// Subsequent CREATE TABLE ON CLUSTER statements then failed
	// on every OTHER replica with UNKNOWN_DATABASE because they
	// didn't have the database yet.
	// Cluster mode prepends ON CLUSTER `<name>` so every replica
	// creates the database in lock-step before any table DDL.
	// Standalone mode unchanged.
	onCluster := ""
	if name := strings.TrimSpace(cfg.ClusterName); name != "" {
		onCluster = " ON CLUSTER `" + name + "`"
	}
	if err := setup.Exec(ctx, fmt.Sprintf("CREATE DATABASE IF NOT EXISTS `%s`%s", cfg.Database, onCluster)); err != nil {
		// v0.9.604 (operator-reported, prod v0.9.603 rollout'u) — dağıtık
		// DDL "zamanaşımı" boot'u öldürüyordu.
		//
		// Kod 159 bir başarısızlık DEĞİL; mesajın kendisi "arka planda
		// çalıştıracaklar" diyor. Ama biz ölümcül sayıp pod'u
		// düşürüyorduk ve bu KENDİNİ BESLİYORDU: pod ölür, yeniden
		// başlar, tüm DDL kümesini zaten tıkalı kuyruğa yeniden
		// gönderir. Rollout sırasında birden çok pod aynı anda boot
		// ettiği için tam o an en kötü hâline geliyordu.
		//
		// Körlemesine YUTMUYORUZ: KOŞULU DOĞRULUYORUZ. Veritabanı
		// gerçekten oradaysa devam etmek doğru; değilse hata aynen
		// yükselir. "Hata yoktu" demekle "sonuç oluştu" demek farklı
		// şeyler ve burada ikincisini kontrol ediyoruz.
		if !isDistributedDDLQueued(err) || !databaseExists(ctx, setup, cfg.Database) {
			setup.Close()
			return nil, fmt.Errorf("create database: %w", err)
		}
		log.Printf("[chstore] dağıtık CREATE DATABASE kuyruğa alındı ama veritabanı %q ZATEN VAR — boot sürüyor (kod 159 arka plan uygulamasını anlatır, arıza değil)", cfg.Database)
	}
	setup.Close()

	// Connect to target database.
	//
	// Per-query memory + execution defaults. Pegged here so every
	// statement issued through this driver inherits them — protects
	// against any single read swallowing the whole CH heap.
	//
	//   max_memory_usage (4 GB)
	//     Hard cap per query. Without it, a runaway GROUP BY /
	//     DISTINCT on a billion-span table can spike to 15-20 GB
	//     and trip the server-wide total — surfacing as
	//     "memory limit (total) exceeded" (CH error 241) and
	//     blocking unrelated reads.
	//
	//   max_bytes_before_external_group_by (1 GB)
	//   max_bytes_before_external_sort     (1 GB)
	//     Spill thresholds. When in-memory state crosses 1 GB,
	//     CH writes to a temp file on disk. Slower but the query
	//     finishes — vs. OOM'ing the whole pool.
	//
	//   distributed_aggregation_memory_efficient
	//     Streams partial aggregates instead of buffering whole
	//     result sets — irrelevant on single-node setups but
	//     harmless and improves big external CH clusters.
	// v0.9.184 — per-query memory limits, env-overridable (cfg.*, default
	// to the built-ins). On a big external cluster the 4GB default cap
	// tripped CH code 241 on a fleet-wide aggregation; operators raise
	// COREMETRY_CH_MAX_MEMORY_USAGE to match node RAM without a rebuild.
	// v0.9.975 — the configured/default numbers above are only a REQUEST
	// now. resolveQueryMemory folds them against the server's own
	// ceiling: cfg still wins when it asks for LESS, but it can no
	// longer ask for more than the server has (a cap above the server
	// total never fires — the OvercommitTracker shoots a bystander
	// instead). Fail-open when serverMaxMem is 0.
	memPlan := resolveQueryMemory(
		cfg.MaxMemoryUsage, cfg.MaxBytesExternalGroupBy, cfg.MaxBytesExternalSort,
		serverMaxMem, cfg.MemFraction)
	// v0.10.511 (C6 ölçümü) — MV paralel itişi; etkin değer boot'ta görünür
	// ki prod A/B'de hangi kolda olduğumuz tek satırdan okunsun.
	SetParallelViewProcessing(!cfg.DisableParallelViews)
	if cfg.InsertDistributedSync {
		log.Printf("[chstore] insert_distributed_sync=1 (COREMETRY_CH_INSERT_DISTRIBUTED_SYNC; imaj varsayılanı v0.10.779) — Distributed INSERT'ler senkron, yerel spool'a yazılmaz")
	}
	// v0.10.790 — replika-duyarlı ayarlar boot'ta görünür (prod'da hangi
	// değerle koştuğumuz tek satırdan okunsun).
	log.Printf("[chstore] max_replica_delay_for_distributed_queries=%d (0 = CH varsayılanı 300; COREMETRY_CH_READ_MAX_REPLICA_DELAY) mv_dedup_blocks=%v (COREMETRY_CH_MV_DEDUP_BLOCKS) insert_quorum=%d (COREMETRY_CH_INSERT_QUORUM; <2 kapalı)",
		cfg.ReadMaxReplicaDelayS, cfg.MVDedupBlocks, cfg.InsertQuorum)
	// v0.10.822 — okuma tarafı replika seçimi. ETKİN değer loglanır (geçersiz
	// bir env "uygulanmış" gibi görünmesin) ve ayarlar aşağıda YALNIZ ana
	// bağlantı + okuma havuzuna eklenir; ingest havuzu dokunulmaz.
	readBalancing, rbWarns := chReadBalancingSettings(cfg.ReadLoadBalancing, cfg.ReadPreferLocalhost)
	for _, w := range rbWarns {
		log.Printf("[chstore] WARNING: %s", w)
	}
	rbLB, rbPrefer := chReadBalancingEffective(readBalancing)
	log.Printf("[chstore] okuma replika seçimi: load_balancing=%s prefer_localhost_replica=%s (ETKİN; COREMETRY_CH_READ_LOAD_BALANCING / COREMETRY_CH_READ_PREFER_LOCALHOST) — yalnız ana bağlantı + okuma havuzu, ingest havuzuna uygulanmaz. Deterministik okuma için İKİSİ birlikte: in_order + 0 (varsayılan 1, koordinatörün kendi shard'ında load_balancing'i devre dışı bırakır). Iraksamış replikaları GİZLER, düzeltmez: Admin → ClickHouse → Replika tutarlılığı / Replika onarımı",
		rbLB, rbPrefer)
	log.Printf("[chstore] parallel_view_processing=%d (COREMETRY_CH_PARALLEL_VIEWS; v0.10.511 ölçüm anahtarı)", map[bool]int{true: 1, false: 0}[!cfg.DisableParallelViews])
	maxMem, extGroupBy, extSort := memPlan.MaxMemory, memPlan.GroupBy, memPlan.Sort
	// v0.9.185 — surface the EFFECTIVE per-query limits at boot so an
	// operator can confirm a COREMETRY_CH_MAX_MEMORY_USAGE override
	// actually took (a rejected value logs a [config] WARNING and this
	// line still shows the default — the two together make a failed
	// override unmistakable). v0.9.975 adds the server ceiling and the
	// ratio, so "why is my 12 GB override showing as 1.8 GB" is
	// answerable from this one line.
	log.Printf("[chstore] per-query memory limits: max_memory_usage=%d, external_group_by=%d, external_sort=%d bytes "+
		"(server max_server_memory_usage=%d, fraction=%.2f)",
		maxMem, extGroupBy, extSort, memPlan.ServerMax, memPlan.Fraction)
	switch {
	case memPlan.ServerMax <= 0:
		log.Printf("[chstore] WARNING: max_server_memory_usage okunamadı — per-query bellek kelepçesi " +
			"ORANTILANAMADI. Yapılandırılan değerler aynen uygulanıyor; sunucu tavanından BÜYÜKlerse " +
			"hiç devreye girmez ve kod-241 masum sorguları öldürür (bkz. query_memory.go).")
	case memPlan.Clamped():
		log.Printf("[chstore] WARNING: yapılandırılan max_memory_usage=%d, sunucunun kendi tavanı olan "+
			"%d bayttan BÜYÜK — bu hâliyle ASLA devreye giremezdi (ClickHouse önce sunucu-geneli "+
			"OvercommitTracker'ı tetikler ve KURBAN seçer). %d bayta kelepçelendi (%.0f%%). "+
			"Oranı COREMETRY_CH_MEM_FRACTION ile değiştirebilirsiniz.",
			memPlan.Configured, memPlan.ServerMax, memPlan.MaxMemory, memPlan.Fraction*100)
	}
	// chOpts builds a FRESH options struct per call — two pools must not
	// share the Settings map (the driver retains it).
	chOpts := func() *clickhouse.Options {
		o := &clickhouse.Options{
			Addr:        hosts,
			Auth:        clickhouse.Auth{Database: cfg.Database, Username: cfg.Username, Password: cfg.Password},
			TLS:         tlsCfg,
			Compression: &clickhouse.Compression{Method: clickhouse.CompressionLZ4},
			DialTimeout: dialTimeout,
			// v0.8.340 (HA audit H2) — the driver's default ReadTimeout is
			// 300s: a CH that ACCEPTS the TCP connection and never answers
			// (keeper pause, asymmetric partition) held every query — and
			// every ingest flusher — for five minutes. Server-side
			// max_execution_time never fires when the query never executes.
			// 30s covers the slowest legitimate reads (heatmap budget is 3s,
			// bulk inserts single-digit seconds) with generous margin.
			ReadTimeout:     30 * time.Second,
			MaxOpenConns:    maxConns,
			MaxIdleConns:    maxConns / 2,
			ConnMaxLifetime: time.Hour,
			Settings: clickhouse.Settings{
				"max_execution_time":                       60,
				"max_memory_usage":                         maxMem,
				"max_bytes_before_external_group_by":       extGroupBy,
				"max_bytes_before_external_sort":           extSort,
				"distributed_aggregation_memory_efficient": 1,
				// v0.9.605 (operator-reported, prod v0.9.603 rollout'u) —
				// dağıtık DDL zamanaşımı ARTIK İSTİSNA DEĞİL.
				//
				// Varsayılan `distributed_ddl_output_mode='throw'`:
				// istemci TÜM host'ların DDL'i bitirmesini
				// distributed_ddl_task_timeout (180 sn) kadar bekler ve
				// bitmezse İSTİSNA atar. Boot 158 bildirimsel DDL
				// çalıştırıyor ve rollout'ta birkaç pod aynı anda boot
				// ediyor; kuyruk tıkandığında bu bekleme pod'u
				// öldürüyordu (v0.9.604 semptomu yumuşattı, bu ayar
				// SEBEBİ kaldırıyor).
				//
				// `null_status_on_timeout` DAR bir gevşetme ve doğru
				// olanı: YALNIZ zamanaşımı hâli istisna yerine NULL
				// durum döner. Sözdizimi hatası, izin reddi, tip
				// uyuşmazlığı gibi GERÇEK DDL hataları AYNEN fırlar.
				//
				// `never_throw` KASTEN seçilmedi: o, gerçek hataları da
				// yutardı ve boot bozuk bir şemayla sessizce devam
				// ederdi — crashloop'tan kötüsü.
				//
				// Doğruluk kaybı yok: DDL'in hepsi IF NOT EXISTS ve
				// ClickHouse kuyruğa alınanı arka planda uyguluyor.
				"distributed_ddl_output_mode": "null_status_on_timeout",
				// v0.9.606 — sunucunun bekleme bütçesi İSTEMCİNİNKİNDEN
				// kısa olmalı; gerekçe ddlTaskTimeoutSeconds'ta.
				"distributed_ddl_task_timeout": ddlTaskTimeoutSeconds,
				// v0.10.777 (prod 2026-09-17: spans spool'u 514K dosya / 391 GiB,
				// dört düğümde de gönderici 7 hatadan sonra sustu; START etkisiz,
				// FLUSH ilerlemedi) — DAĞITIK GÖNDERİCİ TAVANI. INSERT'in ayarları
				// spool dosyasının başlığına yazılır ve arka plan göndericisi o
				// dosyayı hedefe gönderirken BUNLARI kullanır. connection_pool_
				// max_wait_ms varsayılanı 0 = havuzdan bağlantı beklerken SÜRESİZ:
				// gönderici asılır, hata üretmez, FLUSH de arkasında bekler.
				// Tavanlı bekleme = hata + geri çekilme + yeniden deneme, yani
				// kendi kendine iyileşme; sayaç artar, panel "gönderici asılı"
				// yerine gerçek hatayı gösterir. Yalnız YENİ dosyalar bu başlığı
				// taşır — eski spool restart'la boşalır. Replika hata takibi
				// (distributed_replica_error_half_life 60 sn, ignored 0) zaten
				// varsayılan; hatalı replika seçimden düşer, sağlıklı eşe geçilir.
				"connection_pool_max_wait_ms": 30000,
			},
		}
		// v0.10.778/779 — COREMETRY_CH_INSERT_DISTRIBUTED_SYNC: Distributed INSERT
		// senkron, spool'a yazılmaz (imaj varsayılanı 1; gerekçe config.CHConfig).
		// insert_distributed_timeout 60 sn: hedef shard yanıt vermezse INSERT
		// süresiz beklemek yerine hata verir (write_failed görünür).
		if cfg.InsertDistributedSync {
			o.Settings["insert_distributed_sync"] = 1
			o.Settings["insert_distributed_timeout"] = 60
		}
		// v0.10.790 — replika-duyarlı ayarlar; her biri kendi bayrağının
		// altında, gerekçe config.CHConfig. Aynı haritada: her havuz taşır.
		if cfg.ReadMaxReplicaDelayS > 0 {
			o.Settings["max_replica_delay_for_distributed_queries"] = cfg.ReadMaxReplicaDelayS
		}
		if cfg.MVDedupBlocks {
			o.Settings["deduplicate_blocks_in_dependent_materialized_views"] = 1
		}
		if cfg.InsertQuorum >= 2 {
			o.Settings["insert_quorum"] = cfg.InsertQuorum
			o.Settings["insert_quorum_parallel"] = 1
			o.Settings["insert_quorum_timeout"] = 60000 // ms
		}
		// v0.10.822 — okuma tarafı replika seçimi BU PAYLAŞILAN kapanışta
		// UYGULANMAZ: buradan ingest havuzu da doğardı ve her iki ayar
		// Distributed INSERT'te de replika seçer (gerekçe:
		// read_balancing.go başlığı). Ana bağlantı + okuma havuzu için
		// aşağıda applyReadBalancing ile eklenir.
		return o
	}
	// Main conn: strategy DELIBERATELY left at the driver default
	// (ConnOpenInOrder — every connection goes to the first healthy host).
	// v0.9.486 (operator-reported, prod: "/users her refresh'te farklı
	// sayıda kullanıcı — 2, sonra 205"): admin/state tabloları (users,
	// teams, system_settings, alert_rules…) her kurulumda tek tutarlı
	// tablo DEĞİL — cluster_name'siz kurulumlarda ve cluster moduna
	// GEÇİŞTEN ÖNCE yaratılmış tablolarda node-lokaldirler (ON CLUSTER
	// IF NOT EXISTS mevcut lokal tabloyu Replicated'a çevirmez). v0.9.481
	// RoundRobin'i ANA bağlantıya koyunca her state okuması farklı node'un
	// kopyasına düştü. State doğruluğu > okuma dağıtımı: ana bağlantı
	// in-order kalır, RoundRobin aşağıdaki ingest havuzuna taşındı.
	mainOpts := chOpts()
	applyReadBalancing(mainOpts, readBalancing) // v0.10.822
	conn, err := clickhouse.Open(mainOpts)
	if err != nil {
		return nil, fmt.Errorf("connect: %w", err)
	}
	if err := conn.Ping(ctx); err != nil {
		return nil, fmt.Errorf("ping: %w", err)
	}
	// Ingest conn: RoundRobin — the actual v0.9.481 fix, now scoped to
	// where it is SAFE. High-volume telemetry INSERTs (spans / logs /
	// metric_points / profiles / exemplars / span_links) target Distributed
	// wrappers (or a single node in monolithic mode), so any coordinator
	// works and spreading them fixes the first-node saturation the
	// operator reported (CPU climb + ingest "buffer full" drops). Reads
	// and state writes stay on the in-order main conn. SQL console
	// (runquery.go) remains deliberately in-order on its own conn.
	ingestOpts := chOpts()
	ingestOpts.ConnOpenStrategy = clickhouse.ConnOpenRoundRobin
	ingestOpts.ConnMaxLifetime = roundRobinConnLifetime
	ingest, err := clickhouse.Open(ingestOpts)
	if err != nil {
		conn.Close()
		return nil, fmt.Errorf("connect (ingest pool): %w", err)
	}
	if err := ingest.Ping(ctx); err != nil {
		conn.Close()
		return nil, fmt.Errorf("ping (ingest pool): %w", err)
	}
	// Read conn: RoundRobin — v0.9.496, operatör direktifi ("4 node var,
	// yük eşit dağılmalı"). v0.9.481 INSERT koordinasyonunu dağıttı,
	// v0.9.486 state doğruluğunu kurtardı; ARADA kalan analitik
	// SELECT'lerdi. Onlar da ana bağlantıda kaldığı için parse +
	// fan-out + partial-state merge + final aggregation/sort/limit hep
	// ilk node'da birikiyordu (tarama Distributed sayesinde zaten
	// yayılıyor — biriken koordinatör yükü).
	//
	// Güvenlik argümanı ingest havuzuyla BİREBİR aynı: bu havuzdan yalnız
	// Distributed sarmalayıcılara / MV'lere giden telemetri okumaları
	// geçer, dolayısıyla hangi node koordine ederse etsin cevap aynıdır.
	// State tabloları (users/teams/system_settings/alert_rules) her
	// kurulumda replicate DEĞİL — onlar in-order ana bağlantıda kalır,
	// yoksa v0.9.486'nın /users tutarsızlığı geri gelir. Sözleşme
	// conn_strategy_test.go'da dosya-yüzeyi testiyle pinli.
	//
	// Havuz boyutu: üçü de maxConns tavanına sahip, yani tavan 3×.
	// Sürücü bağlantıları TEMBEL açar ve bu dilimle trafik ana
	// bağlantıdan buraya TAŞINIR — gerçek açık soket sayısı yaklaşık
	// sabit kalır, yalnız tavan büyür. Ana bağlantının payı, son
	// okuma dilimi de taşındığında küçültülecek (o güne kadar ana
	// bağlantı hâlâ taşınmamış okumaları taşıyor; şimdi kısmak onları
	// aç bırakırdı).
	readOpts := chOpts()
	readOpts.ConnOpenStrategy = clickhouse.ConnOpenRoundRobin
	readOpts.ConnMaxLifetime = roundRobinConnLifetime
	// v0.10.822 — replika seçimi burada devreye girer: RoundRobin
	// koordinatörü döndürür, prefer_localhost_replica=0 + in_order olmadan
	// ardışık SELECT'ler farklı replikalardan cevaplanır.
	applyReadBalancing(readOpts, readBalancing)
	readConn, err := clickhouse.Open(readOpts)
	if err != nil {
		conn.Close()
		ingest.Close()
		return nil, fmt.Errorf("connect (read pool): %w", err)
	}
	if err := readConn.Ping(ctx); err != nil {
		conn.Close()
		ingest.Close()
		return nil, fmt.Errorf("ping (read pool): %w", err)
	}

	// v0.6.42 — wrap conn so every Query/Exec/QueryRow/PrepareBatch
	// becomes a child span under the inbound request span (when
	// selfobs is enabled). Noop tracer when disabled — essentially
	// zero overhead. See internal/chstore/traced_conn.go.
	s := &Store{
		conn:   newTracedConn(conn, poolMain),
		ingest: newTracedConn(ingest, poolIngest),
		read:   newTracedConn(readConn, poolRead),
		cfg:    cfg, ret: ret,
		// v0.9.1191 — bağlantı fabrikası Store'da kalır: spool runbook'unun
		// FLUSH DISTRIBUTED'ı saatler sürebilir ve ana havuzun 30 sn'lik
		// ReadTimeout'u (v0.8.340) onu keserdi. Uzun işlemler kendi TEK
		// bağlantısını bu fabrikadan, uzun zaman aşımıyla açar (spool_ops.go).
		chOpts: chOpts,
		// v0.9.975 — the SQL sites (topology/backtrace writers, the heavy
		// raw-spans scans, the SQL playground) clamp against this.
		memPlan:    memPlan,
		openSnap:   newTTLMemo[*OpenProblems](openSnapshotTTL),
		spreadMemo: newTTLMemo[*ExceptionSpread](spreadMemoTTL), // v0.10.949
	}
	// v0.5.437 — self-heal pass. Detects HighVolumeTables `_local`
	// MVs/aggregates that exist in system.tables (engine
	// Replicated*) but are missing from system.replicas — a state
	// where the table metadata is present but ZK replica
	// registration didn't complete. Pushes from MV triggers to such
	// tables fail with "Transaction failed (no node)" ZK errors,
	// which under default CH semantics abort the source INSERT too
	// (no new spans/logs/metrics land → /traces, /databases etc.
	// empty for recent windows). Pre-migrate cleanup; the
	// follow-on CREATE TABLE IF NOT EXISTS rebuilds cleanly with a
	// fresh ZK registration. Scoped to HighVolumeTables `_local`
	// names only so admin-data tables (users / alert_rules /
	// system_settings) can never get nuked by this path even if
	// they somehow land in broken state.
	if err := s.healBrokenReplicatedTables(ctx); err != nil {
		log.Printf("[chstore] self-heal pass: %v", err)
	}
	// v0.8.213 — fail FAST (before creating MVs that will never populate) on the
	// genuinely-broken external-Distributed-unset state: `spans` is an external
	// Distributed table but cluster_name is empty, so Coremetry can't own
	// spans_local. This is the root of the "local passes / prod-distributed
	// breaks" class. Hard-error with the cluster to set; an operator who really
	// wants degraded (raw-spans-only) mode opts in via COREMETRY_CH_ALLOW_UNSET_CLUSTER.
	if externalDistributedFatal(s.spansIsExternalDistributed(ctx), cfg.AllowUnsetCluster) {
		conn.Close()
		return nil, fmt.Errorf("%s To boot anyway in degraded mode (raw-spans reads only, "+
			"empty summary dashboards), set COREMETRY_CH_ALLOW_UNSET_CLUSTER=true",
			externalDistributedWarning(s.discoverSpansCluster(ctx)))
	}
	if err := s.migrate(ctx); err != nil {
		conn.Close()
		return nil, fmt.Errorf("migrate: %w", err)
	}
	// v0.10.762 — sarkan MV dedektörü (log; onarım sihirbazdan). Boot'u
	// bloklamaz: 10 s tavan, hata yalnız log.
	s.LogDanglingMVs(ctx)
	// v0.10.823 — küme tanımında kendini is_local görmeyen host: ON CLUSTER
	// DDL orada SESSİZCE atlanır (tablo hiç kurulmaz / düz MergeTree kalır).
	// Aynı yaşam döngüsü: 10 s tavan, DDL koşmaz, hata yalnız log.
	s.LogDDLBlindHosts(ctx)
	// v0.5.421 — boot-time reconciliation. In cluster mode the
	// migration loop normally creates both the `<name>_local`
	// table and its Distributed wrapper at `<name>`. If a prior
	// boot crashed between those two CREATEs (network blip, ZK
	// lag, mid-migration failure), the wrapper goes missing and
	// every read against the bare name 500s with UNKNOWN_TABLE.
	// This pass detects + repairs that drift on every boot —
	// idempotent, cheap (just system.tables lookups + zero or
	// more wrapper CREATEs).
	if err := s.ensureDistributedWrappers(ctx); err != nil {
		// Non-fatal — log + continue. Without this guard a single
		// wrapper failure would prevent the pod from coming up
		// at all, which is worse than a missing wrapper that an
		// operator can fix manually.
		log.Printf("[chstore] reconcile distributed wrappers: %v", err)
	}
	// v0.9.1076 — Distributed göndericide batch modu (2026-08-16 prod
	// spool olayı; gerekçe distributed_batching.go başlığında).
	// Soft-fail; tek-düğüm kurulumda Distributed tablo yok → no-op.
	s.ensureDistributedBatching(ctx)
	// v0.9.614 — ertelenenler arka plana. finishDeferredDDL bayrağı
	// listeden ÖNCE temizler: yürütücü aynı execDDL'den geçiyor,
	// bayrak açık kalsaydı her ifade yeniden birikir ve hiçbir şey
	// uygulanmazdı.
	if deferred := s.finishDeferredDDL(); len(deferred) > 0 {
		go s.runDeferredDDL(deferred)
	}
	return s, nil
}

func (s *Store) Close() error {
	if s.ingest != nil {
		s.ingest.Close()
	}
	if s.read != nil {
		s.read.Close()
	}
	return s.conn.Close()
}
func (s *Store) Conn() driver.Conn { return s.conn }

// TelemetryReadConn — telemetryReadConn'un paket DIŞI hali (v0.9.504).
// anomaly/evaluator gibi arka plan işçileri chstore paketinde değil ama
// okudukları şey tamamen telemetri; RoundRobin havuzunu kullanmaları
// gerekiyor. AYNI KURAL geçerli: yalnız Distributed sarmalayıcı / MV
// okumaları. Bir state tablosu (users, teams, system_settings,
// alert_rules, problems, incidents…) bu bağlantıdan okunursa v0.9.486'nın
// operatör bug'ı geri gelir. Yeni bir paket bunu kullanacaksa
// conn_strategy_test.go'daki paket beyaz listesine BİLİNÇLİ eklenir.
func (s *Store) TelemetryReadConn() driver.Conn { return s.telemetryReadConn() }

// ingestWriteConn returns the RoundRobin pool for high-volume telemetry
// INSERTs, falling back to the main conn when the second pool was never
// opened (zero-value Store in tests). State tables must NEVER write
// through this — see the v0.9.486 two-pool rationale in New.
func (s *Store) ingestWriteConn() driver.Conn {
	if s.ingest != nil {
		return s.ingest
	}
	return s.conn
}

// telemetryReadConn returns the RoundRobin pool for high-volume
// telemetry SELECTs, falling back to the main conn when the pool was
// never opened (zero-value Store in tests).
//
// KULLANIM KURALI: yalnız Distributed sarmalayıcılara / MV'lere giden
// telemetri okumaları. Bir state tablosu okuması (users, teams,
// system_settings, alert_rules, saved_views, problems…) buradan
// geçerse v0.9.486'nın operatör bug'ı geri gelir: o tablolar her
// kurulumda replicate değildir, RoundRobin her çağrıda başka node'un
// kopyasına düşer ve liste refresh'ten refresh'e değişir. Yeni bir
// dosya bu havuzu kullanacaksa conn_strategy_test.go'daki beyaz
// listeye BİLİNÇLİ olarak eklenir.
func (s *Store) telemetryReadConn() driver.Conn {
	if s.read != nil {
		return s.read
	}
	return s.conn
}

// ClusterName returns the configured CH cluster identifier (e.g.
// the value that lands inside `ON CLUSTER`) when the operator set
// COREMETRY_CH_CLUSTER_NAME, or "" for a single-shard standalone
// install. Used by /admin/clickhouse to render the topology
// banner so the operator can confirm at a glance whether the
// running pod is talking to a cluster vs a single CH node.
func (s *Store) ClusterName() string { return s.cfg.ClusterName }

// DatabaseName returns the configured CH database name (used in
// the ON CLUSTER + ON DATABASE clauses). Exposed for the same
// admin surfaces — the operator needs to see which DB the
// running build is bound to without ssh'ing into the container.
func (s *Store) DatabaseName() string { return s.cfg.Database }

// ConnectedHosts returns the configured comma-separated CH host
// list parsed into individual entries. With cluster mode this is
// the driver-side fan-out (the connection pool round-robins
// across them); with standalone it's usually a single host.
func (s *Store) ConnectedHosts() []string { return s.cfg.Hosts() }

// Ping reports CH liveness. Used by /api/status — wraps the driver's
// own Ping so we don't expose the driver type to callers.
func (s *Store) Ping(ctx context.Context) error { return s.conn.Ping(ctx) }

// mvDDLByName returns the `CREATE MATERIALIZED VIEW IF NOT EXISTS <name>`
// statement for `name` from a slice of DDL strings, matching the name exactly:
// the character after the name must be whitespace or end-of-string so a query
// for "spanmetrics_1" never matches "spanmetrics_1m"/"spanmetrics_1s". Returns
// "" when absent. The drop+recreate upgrade migrations in migrate() use this
// to reference MVs by name rather than positional index — immune to slice
// reordering (v0.8.52 — doorway D1 shifted indices and silently broke the
// db_summary_5m migration; name lookup removes the whole class of bug).
func mvDDLByName(mvs []string, name string) string {
	needle := "CREATE MATERIALIZED VIEW IF NOT EXISTS " + name
	for _, q := range mvs {
		i := strings.Index(q, needle)
		if i < 0 {
			continue
		}
		rest := q[i+len(needle):]
		if rest == "" || rest[0] == ' ' || rest[0] == '\n' || rest[0] == '\t' || rest[0] == '\r' {
			return q
		}
	}
	return ""
}

// innerDropStmt builds the guard-bypassing DROP for a combined
// MaterializedView's hidden inner storage table (`.inner_id.<uuid>`,
// a plain AggregatingMergeTree). It carries max_table_size_to_drop +
// max_partition_size_to_drop = 0 so the drop succeeds no matter how
// large the MV's inner storage has grown. Pure for testability.
func innerDropStmt(uuid, onCluster string) string {
	// Ad TEK GÖVDEDEN (innerTableName, v0.10.832): uuid VIEW satırının uuid
	// kolonundan gelir, DDL metnindeki nesne uuid'sinden değil.
	return "DROP TABLE IF EXISTS `" + innerTableName(uuid) + "`" + onCluster + " SYNC" +
		" SETTINGS max_table_size_to_drop = 0, max_partition_size_to_drop = 0"
}

// dropCombinedMV drops a combined MaterializedView (created without an
// explicit TO table, so its storage is a hidden `.inner_id.<uuid>`
// table) at ANY accumulated size, then recreate is safe.
//
// v0.8.190 — operator-reported PRODUCTION boot abort (external
// Distributed cluster): the trace_summary_5m entry_route_state upgrade
// (v0.8.52) issued a bare `DROP TABLE <mv> ... SYNC`, which tripped
// CH's max_table_size_to_drop guard (default 50 GB) on a 65 GB inner
// table (`.inner_id.<uuid>`) → code 359 → migrate() error → crash loop.
// These upgrades INTEND to drop past buckets and repopulate forward
// (every call already logs "past buckets will be dropped"); the guard
// exists only to catch an *accidental* DROP and is pure friction here.
//
// Verified against CH 24.8 (the prod version): a per-query
// `SETTINGS max_table_size_to_drop=0` on `DROP TABLE <combined_mv>`
// does NOT work — the override covers only the 0-byte MV object while
// the internal inner-table drop still uses the SERVER default guard
// and aborts with code 359. The override DOES apply when the inner
// table is dropped DIRECTLY. So resolve the inner from system.tables
// (uuid → `.inner_id.<uuid>`) and drop it first with the override,
// then drop the now-empty MV object. Same override the explicit reset
// path uses (reset.go, v0.5.382 — 171 GB partition tripped the guard).
func (s *Store) dropCombinedMV(ctx context.Context, mv string) error {
	onCluster := s.onCluster()
	var uuid string
	// uuid of the MV's hidden inner AggregatingMergeTree storage.
	err := s.conn.QueryRow(ctx,
		"SELECT toString(uuid) FROM system.tables "+
			"WHERE database = currentDatabase() AND name = ?", mv).Scan(&uuid)
	if err == nil && uuid != "" && uuid != "00000000-0000-0000-0000-000000000000" {
		if e := s.conn.Exec(ctx, innerDropStmt(uuid, onCluster)); e != nil {
			return fmt.Errorf("drop inner storage of %s: %w", mv, e)
		}
	}
	// The MV object itself is metadata-only now (0 bytes) — a bare
	// drop never trips the size guard.
	if e := s.conn.Exec(ctx, "DROP TABLE IF EXISTS "+mv+onCluster+" SYNC"); e != nil {
		return fmt.Errorf("drop mv %s: %w", mv, e)
	}
	// v0.10.762 — ON CLUSTER drop bir node'da yarım kaldıysa artık view o
	// node'da INSERT kaskadını kırar (prod 2026-09-17: spool 398 GiB).
	// Best-effort temizlik; sonraki CREATE IF NOT EXISTS o node'da taze kurar.
	s.dropLeftoverViewObjects(ctx, mv)
	return nil
}

// canonicalMVs — boot'ta yaratılan materialized view kataloğu (TEK GÖVDE).
//
// v0.10.564: katalog migrate() içinde YEREL bir dilimdi. Admin → ClickHouse
// sihirbazları (bugün dangling_mv_admin.go; messaging_opdim_admin.go
// v0.10.766'da kalktı) kanonik CREATE'i node'a özel yeniden kurmak için
// okuyor ve o DDL'in boot'takiyle BİREBİR aynı olması şart — ikinci bir
// kopya yazmak "aynalı kural iki gövde" sınıfı (kopyalar ayrışır, kimse
// fark etmez). Bu yüzden katalog paket düzeyine çıkarıldı; migrate()
// yalnız `mvs := canonicalMVs()` çağırır ve koşullu
// eklemeleri (entity_seen, workload_revision) üstüne append eder.
//
// DİKKAT: `mvs := []string{…}` literali BU DOSYADA kalmak zorunda —
// mv_positional_test.go store.go'yu AST ile ayrıştırıp kataloğu tam bu
// literalden okuyor (v0.9.1319 pozisyonel-indeks muhafızı). Başka bir
// dosyaya taşımak muhafızı sessizce kör eder.
func canonicalMVs() []string {
	// Materialized views — pre-aggregate the high-volume spans table into
	// summary tables that read paths can hit instead of scanning raw rows.
	// New MVs go here; AggregatingMergeTree lets us combine count/sum/quantile
	// states across partitions cheaply at query time via *Merge() finalisers.
	//
	// service_summary_5m: per-(service, 5min) counts + duration quantiles.
	// Used by /services and the anomaly baseline scan to avoid touching the
	// raw spans table for time-bucketed queries that span hours/days.
	// Apdex thresholds — keep in sync with the raw-spans path in
	// repo.go (GetServices). 200ms satisfied / 800ms tolerating is the
	// industry-standard default; making them MV-baked means /api/services
	// can serve 10s of thousands of services in sub-second time.
	const apdexT = 200 * 1_000_000  // ns
	const apdex4T = 800 * 1_000_000 // ns
	mvs := []string{
		fmt.Sprintf(`CREATE MATERIALIZED VIEW IF NOT EXISTS service_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)  AS time_bucket,
		   countState()                                AS span_count_state,
		   countIfState(status_code = 'error')         AS error_count_state,
		   sumState(duration)                          AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)   AS duration_q_state,
		   countIfState(duration <= %d)                AS apdex_satisfied_state,
		   countIfState(duration > %d AND duration <= %d) AS apdex_tolerating_state
		 FROM spans
		 GROUP BY service_name, time_bucket`, apdexT, apdexT, apdex4T),

		// operation_summary_5m: per-(service, operation, 5min) pre-
		// aggregation that powers the OperationsTable on the
		// service detail page. Pre-v0.4.99 GetOperationSummary
		// scanned raw spans GROUP BY name over the entire window,
		// which on a billion-spans/day service detail page took
		// ~500ms cold. Reading the MV instead drops it to single-
		// digit ms because the projection is already pre-aggregated
		// by name within each 5-min slot. Same aggregate states as
		// service_summary_5m (count + error + sum/duration +
		// quantiles + apdex satisfied/tolerating) so the read path
		// can compute the same numeric set the raw-spans query
		// produced, just from a much smaller dataset.
		fmt.Sprintf(`CREATE MATERIALIZED VIEW IF NOT EXISTS operation_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)  AS time_bucket,
		   countState()                                AS span_count_state,
		   countIfState(status_code = 'error')         AS error_count_state,
		   sumState(duration)                          AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)   AS duration_q_state,
		   countIfState(duration <= %d)                AS apdex_satisfied_state,
		   countIfState(duration > %d AND duration <= %d) AS apdex_tolerating_state
		 FROM spans
		 GROUP BY service_name, name, time_bucket`, apdexT, apdexT, apdex4T),

		// operation_group_summary_5m: per-(service, op_group, 5min)
		// pre-aggregation — the normalized-operation-clustering twin of
		// operation_summary_5m (group_id rel B). Where operation_summary_5m
		// keys by the RAW operation name, this one keys by op_group, the
		// normalized operation-shape column the ingest normalizer
		// (templater.NormalizeOperation) writes per span (group_id rel A,
		// v0.8.x). The whole point is to fold the long tail of
		// high-cardinality raw names (GET /orders/8421, GET /orders/9134, …)
		// into one shape row (GET /orders/:id), so the operator's
		// Operations table groups by behaviour, not by accidental id
		// variance. Same aggregate states as operation_summary_5m (count +
		// error + sum/duration + quantiles + apdex satisfied/tolerating) so
		// the read path computes the identical numeric set, just keyed by
		// shape. ORDER BY mirrors the GROUP BY (service_name, op_group,
		// time_bucket) with op_group in name's slot — service filters get a
		// tight prefix prune, exactly like operation_summary_5m.
		//
		// Forward-only (like every MV here): rolls ONLY spans inserted after
		// this CREATE runs. Pre-Release-A spans have op_group = '' and the
		// read path excludes that bucket (WHERE op_group != '') so the
		// normalized list is clean — the ungrouped '' rows are never
		// surfaced as a phantom operation. Issued through execDDL so external
		// Distributed installs get the spans_local + ON CLUSTER + Replicated
		// rewrite, identical to operation_summary_5m's issuance.
		fmt.Sprintf(`CREATE MATERIALIZED VIEW IF NOT EXISTS operation_group_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, op_group, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   op_group,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)  AS time_bucket,
		   countState()                                AS span_count_state,
		   countIfState(status_code = 'error')         AS error_count_state,
		   sumState(duration)                          AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)   AS duration_q_state,
		   countIfState(duration <= %d)                AS apdex_satisfied_state,
		   countIfState(duration > %d AND duration <= %d) AS apdex_tolerating_state
		 FROM spans
		 GROUP BY service_name, op_group, time_bucket`, apdexT, apdexT, apdex4T),

		// spanmetrics_{1m,10s,1s}: "every metric is a doorway" multi-grain
		// span-metrics rollups (v0.8.50, doorway Phase D). A SUPERSET of
		// operation_summary_5m's dims — adds kind / status_code / http_route so
		// the Metric Explorer can filter/group on any of them, at finer grains
		// (the resolver reads the coarsest tier that satisfies the range/step).
		// Native latency histogram via quantilesState; exemplars via
		// argMax(State)/argMaxIfState(trace_id,…) so a bucket hands back a slow /
		// errored trace_id ("click metric → see the trace"). Forward-only
		// (combined MV+target): only spans inserted after creation roll in; the
		// resolver falls back to operation_summary_5m / raw for older windows
		// during cutover. 1s DROPS http_route to bound cardinality (route
		// filters fall to the 10s tier). 1s TTL is ROW-LEVEL
		// (time_bucket + INTERVAL 6 HOUR) — never toDate()+INTERVAL hours, the
		// v0.6.36 unit-mixing trap.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_1m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, name, kind, status_code, http_route, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 30 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name, name, kind, status_code, http_route,
		   toStartOfInterval(time, INTERVAL 1 MINUTE)      AS time_bucket,
		   countState()                                    AS calls_state,
		   countIfState(status_code = 'error')             AS error_state,
		   sumState(duration)                              AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.9, 0.95, 0.99)(duration)  AS duration_q_state,
		   argMaxState(trace_id, duration)                 AS slow_exemplar_state,
		   argMaxIfState(trace_id, duration, status_code = 'error') AS error_exemplar_state
		 FROM spans
		 GROUP BY service_name, name, kind, status_code, http_route, time_bucket`,

		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_10s
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, name, kind, status_code, http_route, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 2 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name, name, kind, status_code, http_route,
		   toStartOfInterval(time, INTERVAL 10 SECOND)     AS time_bucket,
		   countState()                                    AS calls_state,
		   countIfState(status_code = 'error')             AS error_state,
		   sumState(duration)                              AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.9, 0.95, 0.99)(duration)  AS duration_q_state,
		   argMaxState(trace_id, duration)                 AS slow_exemplar_state,
		   argMaxIfState(trace_id, duration, status_code = 'error') AS error_exemplar_state
		 FROM spans
		 GROUP BY service_name, name, kind, status_code, http_route, time_bucket`,

		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_1s
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, name, kind, status_code, time_bucket)
		 TTL time_bucket + INTERVAL 6 HOUR
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name, name, kind, status_code,
		   toStartOfInterval(time, INTERVAL 1 SECOND)      AS time_bucket,
		   countState()                                    AS calls_state,
		   countIfState(status_code = 'error')             AS error_state,
		   sumState(duration)                              AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.9, 0.95, 0.99)(duration)  AS duration_q_state,
		   argMaxState(trace_id, duration)                 AS slow_exemplar_state,
		   argMaxIfState(trace_id, duration, status_code = 'error') AS error_exemplar_state
		 FROM spans
		 GROUP BY service_name, name, kind, status_code, time_bucket`,

		// trace_summary_1d: per-day distinct trace count via HLL.
		// Lets /admin/stats history show traces-per-day without a
		// uniqExact pass over billions of rows. uniqState writes a
		// HLL12 sketch (~2.5 KiB per day per service); merging across
		// 30 days is sub-millisecond.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS trace_summary_1d
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toYYYYMM(day)
		 ORDER BY day
		 TTL day + INTERVAL 365 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   toDate(time)        AS day,
		   uniqState(trace_id) AS trace_count_state
		 FROM spans
		 GROUP BY day`,

		// db_summary_5m: per-(db_system, peer_service, 5-min) pre-
		// aggregation powering /api/databases. Pre-v0.5.9 every
		// page load issued two raw-spans GROUP BYs over a 1h
		// window — ~40M rows scanned twice on a billion-span/day
		// deployment. Reading the MV instead drops that to
		// thousands of rows. Aggregate states (countState /
		// quantilesState / sumState) compose across partitions
		// so 1h / 6h / 24h all merge sub-millisecond.
		//
		// The COALESCE for "unknown" mirrors the raw query so the
		// MV's instance column is comparable to the raw output —
		// keeps the read path's SQL near-identical.
		// v0.5.327 — db.name dimension added so one DB host
		// serving multiple databases (Oracle SIDs, PostgreSQL /
		// MongoDB / MSSQL databases) doesn't collapse into a
		// single row. Replaces the raw-spans GROUP BY path
		// v0.5.315 used as a stopgap. The MV expression
		// coalesces missing db.name to 'default' so spans
		// without the attr still surface.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS db_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (db_system, instance, db_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   db_system,
		   -- v0.5.349 — extended fallback chain. peer.service is
		   -- the canonical OTel attr but many SDK auto-instrumentations
		   -- (Spring Cloud Sleuth on JDBC, .NET activity source,
		   -- pg / mysql clients without DI-time service wiring) emit
		   -- it empty. server.address / net.peer.name / db.host
		   -- cover the autoinstrumented path; db.name surfaces the
		   -- database identity when even the host is anonymous;
		   -- service_name caller is the last resort so a row never
		   -- collapses to 'unknown' if there's any signal to attribute.
		   coalesce(
		     nullIf(peer_service, ''),
		     nullIf(attr_values[indexOf(attr_keys, 'server.address')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'net.peer.name')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'db.host')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'db.name')], ''),
		     nullIf(service_name, ''),
		     'unknown'
		   )                                                                       AS instance,
		   coalesce(nullIf(attr_values[indexOf(attr_keys, 'db.name')], ''), 'default') AS db_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)    AS time_bucket,
		   countState()                                  AS span_count_state,
		   countIfState(status_code = 'error')           AS error_count_state,
		   sumState(duration)                            AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)     AS duration_q_state
		 FROM spans
		 WHERE db_system != ''
		 GROUP BY db_system, instance, db_name, time_bucket`,

		// db_caller_summary_5m: per-(db_system, peer_service,
		// service_name, host_name, 5-min) — drives the row-click
		// detail drawer on /databases. host_name carries the
		// resource.host.name = k8s pod name in containerised
		// deployments, which is the resolution the drawer's
		// per-pod breakdown wants.
		//
		// v0.5.327 — db.name dim added here too so the per-DB
		// caller list is precise. Frontend drawer can render
		// "service X calls postgresql/host-A/billing" vs
		// "service X calls postgresql/host-A/orders" separately.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS db_caller_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (db_system, instance, db_name, service_name, host_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   db_system,
		   -- v0.5.349 — same fallback chain as db_summary_5m so
		   -- row identities match across the two MVs.
		   coalesce(
		     nullIf(peer_service, ''),
		     nullIf(attr_values[indexOf(attr_keys, 'server.address')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'net.peer.name')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'db.host')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'db.name')], ''),
		     nullIf(service_name, ''),
		     'unknown'
		   )                                                                       AS instance,
		   coalesce(nullIf(attr_values[indexOf(attr_keys, 'db.name')], ''), 'default') AS db_name,
		   service_name,
		   coalesce(nullIf(host_name, ''), '(unknown)')  AS host_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)    AS time_bucket,
		   countState()                                  AS span_count_state,
		   countIfState(status_code = 'error')           AS error_count_state,
		   sumState(duration)                            AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)     AS duration_q_state
		 FROM spans
		 WHERE db_system != ''
		 GROUP BY db_system, instance, db_name, service_name, host_name, time_bucket`,

		// db_statement_summary_5m — v0.8.375, Stage-2 D1: per-(db_system,
		// db.name, service, statement-hash, 5-min) rollup keyed by the
		// PERSISTENT statement identity spans.db_stmt_hash (xxHash64 of the
		// literal-normalized db.statement, computed at insert — dbstmt.go).
		// Gives the /slow-queries global catalog an MV read — the raw path
		// regex-normalized + GROUP BY'd every db-span in the window per page
		// load — and gives D2 its statement detail/trend/caller source
		// (service is a dim, so per-statement caller breakdown is a GROUP BY
		// away). Dims follow the db_caller_summary_5m style (db_system +
		// db.name + service); stmt_hash carries the identity. One capped
		// sample statement per bucket via anyState — the read path
		// re-normalizes the sample Go-side (NormalizeDBStatement) for the
		// display form, which is hash-consistent with the grouping by
		// construction (the parity contract in dbstmt.go). duration_max_state
		// keeps the catalog's MaxMs column intact — quantile states can't
		// produce a true max. WHERE db_stmt_hash != 0 ⇔ db_statement != ''
		// (the raw path's filter; the 0 sentinel is pinned in dbstmt_test.go).
		//
		// GATED: created ONLY while hasDBStmtHashCol is true (see the
		// creation loop) — its SELECT references db_stmt_hash, so creating it
		// against a column-less spans table would code-16 every span INSERT
		// and block ALL ingest (the op_group / v0.8.186 lesson). In cluster
		// mode this is a proper highVolumeTables member (_local + Distributed
		// wrapper via adaptDDL) — NOT the spanmetrics_* per-shard mistake
		// (v0.8.356/358 one-shard undercount class).
		`CREATE MATERIALIZED VIEW IF NOT EXISTS db_statement_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (db_system, db_name, service_name, stmt_hash, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   db_system,
		   coalesce(nullIf(attr_values[indexOf(attr_keys, 'db.name')], ''), 'default') AS db_name,
		   service_name,
		   db_stmt_hash                                  AS stmt_hash,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)    AS time_bucket,
		   anyState(substring(db_statement, 1, 8192))    AS sample_stmt_state,
		   countState()                                  AS span_count_state,
		   countIfState(status_code = 'error')           AS error_count_state,
		   sumState(duration)                            AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)  AS duration_q_state,
		   maxState(duration)                            AS duration_max_state,
		   argMaxState(trace_id, duration)               AS slow_exemplar_state,
		   argMaxIfState(trace_id, duration, status_code = 'error') AS error_exemplar_state
		 FROM spans
		 WHERE db_stmt_hash != 0
		 GROUP BY db_system, db_name, service_name, stmt_hash, time_bucket`,

		// service_version_5m (v0.9.249) — per-(service, version, 5min)
		// deploy rollup. Exists because GetServiceDeploys had to scan RAW
		// spans over a 48h lookback (deployLookback, the v0.9.205
		// phantom-marker fix) and burned its whole 15s budget on every
		// prod service, gating the /bundle response behind it.
		//
		// The cost was never the row scan — measured on live CH, a bare
		// count over the same window is ~30ms while the version
		// expression pushes it to ~430ms, because effectiveVersionExpr
		// runs 14 indexOf() array probes PER ROW. An MV moves that work
		// to insert time, once per incoming block, and collapses the
		// read to (service, version, bucket) rows: ~2 versions x 288
		// buckets per service per day instead of tens of millions of
		// spans.
		//
		// minState(time) rather than min(time_bucket) so a deploy marker
		// keeps exact placement — the bucket alone would round every
		// rollout to a 5-minute grid.
		//
		// Registered in highVolumeTables + defaultShardPolicy +
		// tablesWithoutTraceID day one (v0.5.426 / v0.8.375 lesson).
		`CREATE MATERIALIZED VIEW IF NOT EXISTS service_version_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, version, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 45 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   ` + effectiveVersionExpr + `                 AS version,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)    AS time_bucket,
		   minState(time)                                AS first_seen_state,
		   countState()                                  AS span_count_state
		 FROM spans
		 WHERE (has(res_keys, 'service.version')
		     OR has(res_keys, 'container.image.tag')
		     OR has(res_keys, 'k8s.container.image.tag')
		     OR has(res_keys, 'k8s.deployment.labels.app_kubernetes_io_version')
		     OR has(res_keys, 'k8s.pod.labels.app_kubernetes_io_version')
		     OR has(res_keys, 'k8s.deployment.labels.version')
		     OR has(res_keys, 'helm.chart.version'))
		 GROUP BY service_name, version, time_bucket`,

		// spanmetrics_calls_5m: per-(service, status_code, 5min)
		// pre-aggregation of the spanmetrics processor's calls
		// counter. v0.5.357 — the v0.5.355 top-N workaround keeps
		// the /span-metrics page fast at 10k+ services by hard-
		// capping the result; this MV is the proper fix —
		// aggregates at INSERT time so even an "all services"
		// scan reads pre-aggregated state instead of every
		// metric_point row in the window.
		//
		// Why TWO MVs (calls + duration) instead of one: a
		// spanmetrics processor's counter emits a single
		// `value` column; the duration histogram emits
		// (count, sum_value, max_value). Combining both shapes
		// in one MV would inflate the row size and force the
		// read path to filter on metric name regardless. Keeping
		// them separate lets each MV use the smallest possible
		// aggregate states.
		//
		// Trigger filter (in the WHERE) covers the four spanmetrics
		// naming conventions across processor versions: the
		// fully-qualified dotted form, the underscored form,
		// the bare "spanmetrics.*" form, and the bare
		// "calls" / "duration". metric is LowCardinality so
		// the predicate evaluates once per distinct name.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_calls_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 30 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   sumState(value)                            AS calls_state,
		   sumIfState(value,
		     attr_values[indexOf(attr_keys, 'status.code')] = 'STATUS_CODE_ERROR'
		   )                                          AS errors_state
		 FROM metric_points
		 WHERE metric IN (
		     'traces.spanmetrics.calls.total',
		     'traces_spanmetrics_calls_total',
		     'spanmetrics.calls',
		     'spanmetrics_calls_total',
		     'calls'
		   )
		 GROUP BY service_name, time_bucket`,

		// spanmetrics_hist_5m: per-(service, 5min) pre-aggregation
		// of the histogram bucket layout. v0.5.359 — the
		// v0.5.358 quantile stage reads raw metric_points
		// (sumForEach across the window); at scale that's the
		// slowest of the four stages. This MV moves the
		// element-wise bucket sum into the aggregating engine
		// via sumMapState so the read collapses to a single
		// sumMapMerge — sub-second even on the full top-N set.
		//
		// bounds is anyState: we assume the (service, metric)
		// tuple uses one consistent bucket layout per emitter
		// run. If the layout ever changes mid-run the MV's
		// reduce picks the first one — same trade-off the
		// histQuantile() consumer already accepts.
		//
		// counts uses sumMapState(keys, values) — element-wise
		// sum keyed by bucket index. Different-length bucket
		// arrays across data points (rare but possible) sum
		// cleanly via the map abstraction.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_hist_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 30 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   anyState(bucket_bounds)                    AS bounds_state,
		   sumMapState(
		     arrayMap(i -> toUInt32(i), range(0, toUInt32(length(bucket_counts)))),
		     bucket_counts
		   )                                          AS counts_state
		 FROM metric_points
		 WHERE metric IN (
		     'traces.spanmetrics.duration',
		     'traces.spanmetrics.duration.seconds.sum',
		     'traces_spanmetrics_duration',
		     'spanmetrics.duration',
		     'duration'
		   )
		   AND length(bucket_counts) > 0
		 GROUP BY service_name, time_bucket`,

		// spanmetrics_duration_5m: per-(service, 5min)
		// pre-aggregation of the histogram-shaped duration
		// metric. Stores sum + count + max from the
		// metric_points columns the OTLP convert path fills
		// in for histogram data points (otlp/convert.go).
		// avgMs is derived at read time as sum/count×1000;
		// maxMs is max×1000.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_duration_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 30 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   sumState(sum_value)  AS sum_state,
		   sumState(count)      AS count_state,
		   maxState(max_value)  AS max_state
		 FROM metric_points
		 WHERE metric IN (
		     'traces.spanmetrics.duration',
		     'traces.spanmetrics.duration.seconds.sum',
		     'traces_spanmetrics_duration',
		     'spanmetrics.duration',
		     'duration'
		   )
		 GROUP BY service_name, time_bucket`,

		// messaging_summary_5m: structural parallel for /api/messaging.
		// Cluster + destination are derived expressions in the source
		// query because the dimension lives in attr_keys/attr_values
		// rather than dedicated columns. We materialise the resolved
		// values so the read path joins on plain string equality.
		//
		// v0.10.563 — `operation` boyutu eklendi (Faz 4b). Zincir
		// dependencies.go'daki msgOperationExpr ile BİREBİR aynı sırada:
		// messaging.operation.type → .operation.name → .operation → ''.
		// Boş dize SDK'nın hiçbirini yaymadığı anlamına gelir ve satır
		// KALIR — okuma tarafı onu '(bilinmiyor)'a çevirmez, boş bırakır
		// (etiketleme frontend'in işi). Boyut ORDER BY'da destination'dan
		// SONRA duruyor: filtre öznesi msg_system önde kalsın ve mevcut
		// (system, cluster, destination) okumaları PK önekini kaybetmesin.
		//
		// ⚠ GEÇİŞ MALİYETİ: bu boyutu eklemek DROP + RECREATE gerektirir
		// (boot geçişi aşağıda, mvDimMigrations) ve 90 günlük messaging
		// kovalarını SİLER; MV ileriye doğru yeniden dolar. Kesintisiz
		// alternatif yerinde geçiştir: depo tablosuna (`.inner_id.<uuid>`,
		// cluster modunda `_local`) `ALTER TABLE … ADD COLUMN operation
		// String AFTER destination` + `ALTER TABLE … MODIFY ORDER BY` +
		// `ALTER TABLE … MODIFY QUERY <yeni SELECT>`. DİKKAT: MODIFY ORDER BY
		// yalnız anahtarın SONUNA kolon ekleyebilir, yani yerinde geçen bir
		// kurulumun sıralama anahtarı (…, destination, time_bucket, operation)
		// olur — buradaki taze DDL'den (…, destination, operation, time_bucket)
		// AYRIŞIR. Sıralama anahtarına eklemek şart: operation anahtarda
		// olmazsa AggregatingMergeTree birleşmesi farklı operasyonları TEK
		// satıra çökertir ve boyut sessizce yok olur. Emsal:
		// `reference-ch-inplace-mv-column-add`. Kolon zaten varsa boot geçişi
		// HİÇ dokunmaz (no-op) — yerinde geçen kurulum ikinci kez düşmez.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS messaging_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (msg_system, cluster, destination, operation, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   msg_system,
		   coalesce(
		     nullIf(attr_values[indexOf(attr_keys, 'server.address')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.kafka.bootstrap.servers')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.kafka.cluster.name')], ''),
		     '(default)'
		   ) AS cluster,
		   coalesce(
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.destination.name')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.destination')], ''),
		     nullIf(peer_service, ''),
		     'unknown'
		   ) AS destination,
		   coalesce(
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.operation.type')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.operation.name')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.operation')], ''),
		     ''
		   ) AS operation,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   countState()                               AS span_count_state,
		   countIfState(status_code = 'error')        AS error_count_state,
		   sumState(duration)                         AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)  AS duration_q_state
		 FROM spans
		 WHERE msg_system != ''
		 GROUP BY msg_system, cluster, destination, operation, time_bucket`,

		// messaging_caller_summary_5m: per-(msg_system, cluster,
		// destination, service_name, host_name, kind, 5-min). Kind
		// rides the dim so the messaging drawer can split
		// Producers / Consumers without a second pass.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS messaging_caller_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (msg_system, cluster, destination, service_name, host_name, kind, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   msg_system,
		   coalesce(
		     nullIf(attr_values[indexOf(attr_keys, 'server.address')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.kafka.bootstrap.servers')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.kafka.cluster.name')], ''),
		     '(default)'
		   ) AS cluster,
		   coalesce(
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.destination.name')], ''),
		     nullIf(attr_values[indexOf(attr_keys, 'messaging.destination')], ''),
		     nullIf(peer_service, ''),
		     'unknown'
		   ) AS destination,
		   service_name,
		   coalesce(nullIf(host_name, ''), '(unknown)') AS host_name,
		   kind,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)   AS time_bucket,
		   countState()                                 AS span_count_state,
		   countIfState(status_code = 'error')          AS error_count_state,
		   sumState(duration)                           AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)    AS duration_q_state
		 FROM spans
		 WHERE msg_system != ''
		 GROUP BY msg_system, cluster, destination, service_name, host_name, kind, time_bucket`,

		// trace_summary_5m — per-(trace_id, 5min bucket) rollup
		// of everything the /traces list needs: root span info,
		// span count, error flag, duration. The /traces query
		// used to GROUP BY trace_id over raw spans, which on a
		// 7-day window with one service touched 10–100M rows
		// even with the (service_name, time) primary key prune.
		// Reading the MV slashes that to thousands of state rows
		// — sub-second 7-day queries at billion-spans/day scale.
		//
		// A single trace can span multiple 5-min buckets when
		// it's long-running (background jobs / batch ETL); the
		// read path GROUPs BY trace_id across buckets and
		// merges state. The merge is closed under * so 6
		// buckets of one trace produce identical results to
		// scanning the spans directly.
		//
		// argMaxIfState picks the value from the *root* span
		// (parent_id empty/zero) when present, falling back to
		// any span's value via the secondary maxStateIf branch.
		// Traces with no root span (orphans / Tempo-style
		// partials) still get a service name from this fallback
		// instead of rendering as "(unknown)".
		//
		// entry_route_state (v0.8.52, doorway D3) carries the root
		// span's http.route — the trace's entry endpoint — via the
		// same root-span argMaxIf predicate. It's the one field the
		// §6 trace-level metrics table was missing: the tracemetrics
		// source (D4) re-aggregates these per-trace rows by
		// (root_service, entry_route) at read time for trace-level
		// RED-by-endpoint without a second rollup.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS trace_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (time_bucket, trace_id)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   trace_id,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   argMaxIfState(service_name, time,
		     (parent_id = '' OR parent_id = '0000000000000000') AND name != '') AS root_service_state,
		   argMaxIfState(name, time,
		     (parent_id = '' OR parent_id = '0000000000000000') AND name != '') AS root_name_state,
		   minState(time)                            AS trace_start_state,
		   maxState(toUnixTimestamp64Nano(time) + duration) AS trace_end_state,
		   countState()                              AS span_count_state,
		   countIfState(status_code = 'error')       AS error_count_state,
		   argMaxIfState(http_route, time,
		     (parent_id = '' OR parent_id = '0000000000000000') AND name != '') AS entry_route_state,
		   -- entry_service_state (v0.10.97, operatör-raporlu "iframe
		   -- trace'leri"): EN ERKEN server/consumer span'in servisi —
		   -- entry-span ilkesinin trace-listesi yarısı. Mobil web/iframe
		   -- telemetrisi service.name'siz span'i trace'in MUTLAK köküne
		   -- koyunca liste "unknown" basıyordu; görüntüleme zinciri kök
		   -- 'unknown'/boşken buna düşer (traceDisplaySvcExpr). argMIN:
		   -- giriş = ilk sunucu tarafı span; 'unknown' bilinçli dışarıda.
		   argMinIfState(service_name, time,
		     (kind = 'server' OR kind = 'consumer')
		     AND service_name != '' AND service_name != 'unknown') AS entry_service_state
		 FROM spans
		 GROUP BY trace_id, time_bucket`,

		// trace_service_index_5m — sparse (service_name,
		// trace_id) mapping. Lets a service-filtered /traces
		// query find the relevant trace_ids without scanning
		// spans. Two-stage read pattern:
		//   1. SELECT trace_id FROM this MV WHERE service_name=?
		//      AND time_bucket >= ? GROUP BY trace_id ORDER BY
		//      latest_bucket DESC LIMIT N — uses the
		//      (service_name, time_bucket) prefix for partition
		//      + sort access.
		//   2. SELECT * FROM trace_summary_5m WHERE
		//      trace_id IN (Stage 1) GROUP BY trace_id — bounded
		//      to N traces, uses the bloom filter on trace_id.
		//
		// Both stages bypass the raw spans table entirely. End-
		// to-end time on a 7-day window with service filter
		// drops from ~30-60s (raw scan) to <1s.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS trace_service_index_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, time_bucket, trace_id)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   toStartOfInterval(time, INTERVAL 5 MINUTE) AS time_bucket,
		   trace_id,
		   countState()                          AS span_count_state,
		   maxState(time)                        AS last_seen_state
		 FROM spans
		 GROUP BY service_name, time_bucket, trace_id`,

		// metric_catalog — v0.8.396 (operator-reported PROD bug:
		// /api/metrics/names errored — the picker's GROUP BY metric over
		// RAW metric_points with the 7-day v0.8.311 lookback outgrew
		// max_execution_time at 1B+ points/day). One row per
		// (service_name, metric): the picker/catalogue read becomes an
		// instant scan over a few thousand rows at ANY ingest volume.
		// No PARTITION BY / TTL on purpose — cardinality is bounded by
		// the metric catalogue itself (state-table sized); freshness is
		// enforced read-side via maxMerge(last_seen_state) >= now()-7d,
		// so a long-silent metric ages out of the PICKER without ever
		// leaving the table. Registered in highVolumeTables +
		// defaultShardPolicy + tablesWithoutTraceID day one (the D1
		// v0.8.375 rule; the spanmetrics per-shard undercount is the
		// counter-example). Reads fall back to the bounded raw scan
		// while the catalog is empty (first minutes after upgrade —
		// the MV populates forward only).
		`CREATE MATERIALIZED VIEW IF NOT EXISTS metric_catalog
		 ENGINE = AggregatingMergeTree
		 ORDER BY (service_name, metric)
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   metric,
		   anyState(description)  AS description_state,
		   anyState(unit)         AS unit_state,
		   anyState(instrument)   AS instrument_state,
		   maxState(time)         AS last_seen_state
		 FROM metric_points
		 GROUP BY service_name, metric`,

		// span_links_reverse_mv — v0.8.329, cross-signal pivot Phase 1b.
		// Copies every span_links row into span_links_reverse verbatim so the
		// backlink direction ("what links TO this trace") has its own primary
		// key — see the span_links CREATE for the both-directions-as-PK-scan
		// rationale. TO-form ON PURPOSE (the first in this codebase; every
		// other MV is combined): the target is a real table we also TTL /
		// purge / retain independently, and the MV itself keeps no storage.
		// Cluster mode (adaptDDL): the FROM rewrites to span_links_local
		// (each shard triggers on its own slice) while the TO target stays
		// the bare span_links_reverse — the Distributed wrapper — so reverse
		// rows RE-SHARD by cityHash64(linked_trace_id) and LinksToTrace stays
		// a single-shard PK scan. No ENGINE clause, so the Replicated engine
		// swap correctly never touches it.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS span_links_reverse_mv
		 TO span_links_reverse
		 AS SELECT
		   trace_id, span_id, linked_trace_id, linked_span_id,
		   time, service_name, attr_keys, attr_values
		 FROM span_links`,

		// service_seen — v0.9.1317, entity-model slice A2
		// (docs/audit/entity-model-audit-2026-08-23.md §7.2). The service
		// LIFECYCLE pair: first_seen / last_seen, Dynatrace's
		// firstSeenTms/lastSeenTms equivalent. Until this MV, the only
		// answer to "was this service here yesterday?" was "does it have a
		// row in the window", which cannot distinguish a service that
		// never existed from one that died.
		//
		// NO time dimension in the key. ORDER BY (service_name) alone, so
		// the table collapses to ONE row per service ever seen — thousands
		// of rows, not millions. Shape precedent: metric_catalog
		// (v0.8.396), the other catalogue-sized MV here with no PARTITION
		// BY and no TTL. State precedent: service_version_5m (v0.9.249),
		// which already uses minState(time) — and for the same reason
		// v0.9.250 spells out: the state's own min is EXACT, while a
		// bucket label would round every birth to a 5-minute grid.
		//
		// NO TTL and NO PARTITION BY, deliberately and load-bearing. A
		// disappeared service MUST stay in this table — "which services
		// vanished" is precisely the question the MV exists to answer, and
		// a row that ages out takes the answer with it. Bucketing by time
		// and adding a TTL would silently redefine first_seen as "first
		// seen within the retention window": a number that reads like a
		// fact, is a lie, and that an operator would act on.
		//
		// The growth that buys: one row per distinct service.name ever
		// observed. Two 8-byte DateTime64(9) aggregate states plus a
		// LowCardinality name — call it ~50 B/row with part overhead, so
		// 10k services ≈ 500 KB and even 100k (10x the design ceiling)
		// ≈ 5 MB. Cardinality carries no NEW risk either: service_summary_5m
		// is already keyed on service_name, so a fleet that could blow this
		// up would have broken that MV first. The one honest difference is
		// that service_summary_5m sheds names at its 90-day TTL and this
		// table does not — a fleet that churns service NAMES (svc-v1,
		// svc-v2, ...) accumulates here forever. At ~50 B/row that is a
		// rounding error against a single day of spans.
		//
		// Insert-side cost, which is the number that actually matters at
		// 1B spans/day: this MV emits one row per distinct service IN THE
		// INCOMING BLOCK, which is the same per-block row count
		// service_summary_5m already emits (that one groups by service +
		// bucket, and a single block spans one or two buckets). So the
		// write amplification is a proven quantity here, not an estimate —
		// and unlike its sibling this MV's merge target collapses to N
		// rows instead of N x buckets, so the steady state it settles into
		// is strictly SMALLER than the MV beside it.
		//
		// NO kind filter, unlike every RED-metric MV in this file. The
		// entry-span principle (kind IN ('server','consumer')) governs
		// METRICS — throughput, error rate, latency — because those need a
		// consistent population. Existence is not a metric: any span a
		// service emits proves it was alive, including a purely internal
		// one. Borrowing the server+consumer filter here would make a
		// worker that only ever emits internal spans look like it was
		// never born.
		//
		// NO countState(). Nothing reads it — a lifetime span count over
		// an unbounded window is not a number any surface asks for — and
		// min/max are the only states whose cross-shard merge is
		// idempotent by construction, so keeping the column set to exactly
		// what a read consumes is also the safest set.
		//
		// Registered in highVolumeTables + defaultShardPolicy +
		// tablesWithoutTraceID day one (the v0.5.426 / v0.8.375 rule that
		// v0.8.185 and v0.8.186 both broke prod by skipping). Shard key
		// cityHash64(service_name) is inside ORDER BY, so rule O5 holds.
		`CREATE MATERIALIZED VIEW IF NOT EXISTS service_seen
		 ENGINE = AggregatingMergeTree
		 ORDER BY (service_name)
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   minState(time)  AS first_seen_state,
		   maxState(time)  AS last_seen_state
		 FROM spans
		 GROUP BY service_name`,

		// v0.10.881 (Dynatrace paritesi #8, spec onaylı 2026-09-23) — service_summary_5m'in
		// cluster + deploy_env boyutlu ikizi. /api/services cluster/env filtresiyle ve
		// /api/services/{name}/clusters bugün ham spans tarıyor (servicesUseMV: "MV'de
		// boyut yok"); bu MV o iki okumaya MV-first yol açar (dilim 2/3). State kolonları
		// kardeşle BİREBİR (aynı *Merge okuyucuları; service_env_summary_test pinler).
		// cluster: messaging MV'leriyle aynı sınıf türetme (clusterDeriveExpr — MATERIALIZED
		// kolona bağımlı değil, harici CH'de de doğar). deploy_env ingest'in koşulsuz
		// yazdığı kolon. DİLİMİN SONUNDA: konumsal indeks pinleri eski sırayı korur.
		// Geriye dolmaz: okuyucular EnvSummaryCovers ile pencereyi ölçer, kapsamıyorsa ham yol.
		fmt.Sprintf(`CREATE MATERIALIZED VIEW IF NOT EXISTS service_env_summary_5m
		 ENGINE = AggregatingMergeTree
		 PARTITION BY toDate(time_bucket)
		 ORDER BY (service_name, cluster, deploy_env, time_bucket)
		 TTL toDate(time_bucket) + INTERVAL 90 DAY
		 SETTINGS index_granularity = 8192
		 AS SELECT
		   service_name,
		   ifNull(%s, '') AS cluster,
		   deploy_env,
		   toStartOfInterval(time, INTERVAL 5 MINUTE)  AS time_bucket,
		   countState()                                AS span_count_state,
		   countIfState(status_code = 'error')         AS error_count_state,
		   sumState(duration)                          AS duration_sum_state,
		   quantilesTDigestState(0.5, 0.95, 0.99)(duration)   AS duration_q_state,
		   countIfState(duration <= %d)                AS apdex_satisfied_state,
		   countIfState(duration > %d AND duration <= %d) AS apdex_tolerating_state
		 FROM spans
		 GROUP BY service_name, cluster, deploy_env, time_bucket`, clusterDeriveExpr, apdexT, apdexT, apdex4T),
	}
	return mvs
}

// canonicalMVDDL — katalogdan ada göre TEK MV'nin CREATE metni ("" = yok).
// Sihirbazların (yerinde geçiş) kanonik SELECT kaynağı; ad eşleşmesi tam
// (mvDDLByName: "spanmetrics_1" asla "spanmetrics_1m" ile eşleşmez).
func canonicalMVDDL(name string) string { return mvDDLByName(canonicalMVs(), name) }

// mvNameFromDDL — SAF: "CREATE MATERIALIZED VIEW IF NOT EXISTS <ad>" önekinden
// nesne adı ("" = tanınmayan biçim). mvDDLByName'in TERS yönü; ikisi aynı
// öneki okur, ayrışamazlar.
func mvNameFromDDL(ddl string) string {
	const pfx = "CREATE MATERIALIZED VIEW IF NOT EXISTS "
	i := strings.Index(ddl, pfx)
	if i < 0 {
		return ""
	}
	rest := ddl[i+len(pfx):]
	if j := strings.IndexAny(rest, " \t\r\n("); j >= 0 {
		rest = rest[:j]
	}
	return rest
}

// mvGuardedOff — bir kanonik MV boot'ta BİLEREK atlanıyor mu (kaynak
// kolonu yok). migrate()'in create döngüsündeki iki kapının TEK GÖVDESİ:
//
//	operation_group_summary_5m — SELECT'i op_group okur (v0.8.186)
//	db_statement_summary_5m    — SELECT'i db_stmt_hash okur (v0.8.375)
//
// Kolon yokken bu MV'leri yaratmak insert-trigger'ı kod 16 ile düşürür ve
// TÜM ingest'i bloklar. v0.10.825: MV kapsama kartı (mv_coverage.go) aynı
// kararı okumak ZORUNDA — okumazsa kolonu olmayan kurulumda iki MV her
// host'ta "eksik" görünür ve "Yeniden kur" düğmesi tam da burada
// engellenen DDL'i koşar. İki kopya kural ayrışır; tek gövde.
func (s *Store) mvGuardedOff(name string) bool {
	switch name {
	case "operation_group_summary_5m":
		return !s.hasOpGroupCol
	case "db_statement_summary_5m":
		return !s.hasDBStmtHashCol
	}
	return false
}

// canonicalMVNames — SAF: katalogdaki her MV'nin nesne adı (boot'taki
// sırayla). v0.10.825 MV kapsama kartının EKSENİ: katalogda olup bir
// host'ta bulunmayan MV "eksik"tir; katalog dışındakinin eksikliği diye
// bir şey yoktur. Küme depolama adı için çağıran s.mvStorageName uygular.
func canonicalMVNames() []string {
	mvs := canonicalMVs()
	out := make([]string, 0, len(mvs))
	for _, ddl := range mvs {
		if n := mvNameFromDDL(ddl); n != "" {
			out = append(out, n)
		}
	}
	return out
}

// canonicalTables — boot'ta yaratılan TABLO kataloğu (TEK GÖVDE, v0.10.846).
//
// canonicalMVs()'in emsali ve aynı gerekçe: katalog paket düzeyinde
// erişilebilir olmadan ÖLÇÜLEMİYORDU. Somut ihtiyaç, kaldırılmış tablolar
// defteriyle (removed_tables.go) arasındaki KESİŞİM KAPISI:
//
//	dropRemovedTables, `tables` dilimi KOŞTUKTAN SONRA çalışır. Deftere
//	YAŞAYAN bir ad düşerse boot o tabloyu KURAR ve hemen ardından
//	`DROP … ON CLUSTER … SYNC` ile küme genelinde SİLER — her boot,
//	sessizce, hata vermeden. Bugün kesişim yok ama bunu tutan bir şey
//	YOKTU; TestLedgerNeverNamesALivingTable artık GERÇEK katalogla tutuyor.
//
// SAF: tek girdisi saklama gün sayıları (sd/ld/md), tek çıktısı DDL metinleri.
// migrate() gövdesinden TAŞINDI, metni değişmedi.
func canonicalTables(sd, ld, md int) []string {
	tables := []string{
		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS spans (
			trace_id      String       CODEC(ZSTD(3)),
			span_id       String       CODEC(ZSTD(3)),
			parent_id     String       DEFAULT '' CODEC(ZSTD(3)),
			name          LowCardinality(String),
			kind          LowCardinality(String) DEFAULT 'internal',
			service_name  LowCardinality(String),
			host_name     LowCardinality(String) DEFAULT '',
			deploy_env    LowCardinality(String) DEFAULT '',
			status_code   LowCardinality(String) DEFAULT 'unset',
			status_msg    String       DEFAULT '' CODEC(ZSTD(3)),
			time          DateTime64(9) CODEC(Delta, ZSTD(3)),
			duration      Int64        CODEC(T64, ZSTD(3)),
			db_system     LowCardinality(String) DEFAULT '',
			db_statement  String       DEFAULT '' CODEC(ZSTD(3)),
			http_method   LowCardinality(String) DEFAULT '',
			http_route    LowCardinality(String) DEFAULT '',
			http_status   UInt16       DEFAULT 0,
			rpc_system    LowCardinality(String) DEFAULT '',
			rpc_method    LowCardinality(String) DEFAULT '',
			peer_service  LowCardinality(String) DEFAULT '',
			msg_system    LowCardinality(String) DEFAULT '',
			attr_keys     Array(LowCardinality(String)),
			attr_values   Array(String) CODEC(ZSTD(3)),
			res_keys      Array(LowCardinality(String)),
			res_values    Array(String) CODEC(ZSTD(3)),
			events        String       DEFAULT '[]' CODEC(ZSTD(3)),
			scope_name    LowCardinality(String) DEFAULT '',
			op_group      LowCardinality(String) DEFAULT '',
			cluster       LowCardinality(String) MATERIALIZED %s,
			INDEX idx_trace  trace_id  TYPE bloom_filter(0.01) GRANULARITY 4,
			INDEX idx_name   name      TYPE set(0) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (service_name, time)
		TTL toDate(time) + INTERVAL %d DAY
		SETTINGS index_granularity = 8192`, clusterDeriveExpr, sd),

		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS logs (
			trace_id      String       DEFAULT '',
			span_id       String       DEFAULT '',
			time          DateTime64(9) CODEC(Delta, ZSTD(3)),
			severity_num  UInt8        DEFAULT 0,
			severity_text LowCardinality(String) DEFAULT '',
			body          String       CODEC(ZSTD(3)),
			service_name  LowCardinality(String),
			host_name     LowCardinality(String) DEFAULT '',
			attr_keys     Array(LowCardinality(String)),
			attr_values   Array(String),
			res_keys      Array(LowCardinality(String)),
			res_values    Array(String),
			scope_name    LowCardinality(String) DEFAULT '',
			INDEX idx_body body TYPE tokenbf_v1(32768, 3, 0) GRANULARITY 4,
			INDEX idx_logs_trace trace_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (service_name, severity_num, time)
		TTL toDate(time) + INTERVAL %d DAY
		SETTINGS index_granularity = 8192`, ld),

		`CREATE TABLE IF NOT EXISTS users (
			id            String,
			email         String,
			password_hash String,
			role          LowCardinality(String) DEFAULT 'viewer',  -- admin | viewer
			disabled      UInt8        DEFAULT 0,
			auth_provider LowCardinality(String) DEFAULT 'local',   -- local | oidc
			created_at    DateTime64(9) DEFAULT now64(9),
			-- v0.8.450 — son başarılı login anı (operatör isteği: Users
			-- sayfasında görünür). Epoch(0) = hiç giriş yapmadı.
			last_login_at DateTime64(9) DEFAULT toDateTime64(0, 9),
			-- v0.8.526 — LDAP group sync: the directory sAMAccountName,
			-- lowercased, persisted so the authz hot path can join a
			-- group snapshot's members (sAMAccountName) to a Coremetry
			-- user in O(1). Email stays the canonical identity; empty for
			-- local/OIDC accounts. See hasLdapUsernameCol on the Store.
			ldap_username LowCardinality(String) DEFAULT '',
			version       UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS last_login_at DateTime64(9) DEFAULT toDateTime64(0, 9)`,

		// v0.8.526 — LDAP/AD group-membership snapshot (state table, RMT +
		// FINAL like users/saved_views). DDL + Upsert/Hydrate/tombstone +
		// identity-overlap live in ldap_groups.go.
		ldapGroupsDDL,

		// RAG chunk deposu (v0.8.438) — doküman soru-cevap. DDL
		// rag.go'da (ragChunksDDL) yaşar; içerik + embedding tek
		// tabloda, ReplacingMergeTree(version) ile senkron diff'i
		// bedava. saved_views istisnasının savunması rag.go başında.
		ragChunksDDL,
		// API token'ları (v0.8.444) — harici agent platformları (GenAI
		// Studio) için iptal edilebilir servis kimlikleri; DDL api_tokens.go'da.
		apiTokensDDL,
		// v0.10.599 — Oracle Aşama 2: ERROR_LOG satırları (idempotent RMT);
		// DDL oracle_error_log.go'da, /clickhouse-schema §1 state yolu.
		oracleErrorLogDDL,
		// Service catalog metadata — operator-curated per-service
		// info (owner team, oncall channel, runbook URL, repo,
		// description) that the spans table doesn't carry. Joins
		// against service_name as the primary key. Plain
		// ReplacingMergeTree because rows change once per
		// reorg, not per request — version is just for last-
		// write-wins on edit.
		`CREATE TABLE IF NOT EXISTS service_metadata (
			service       String,
			owner_team    String DEFAULT '',
			sre_team      String DEFAULT '',
			-- *_team_auto: the last value the span-attr team-deriver wrote
			-- (v0.8.100). It owns owner_team/sre_team while they're empty or
			-- still equal these; a human edit (value != auto) pins the field.
			owner_team_auto String DEFAULT '',
			sre_team_auto   String DEFAULT '',
			description   String DEFAULT '',
			repository    String DEFAULT '',
			runbook_url   String DEFAULT '',
			oncall_url    String DEFAULT '',
			-- chat_channel was renamed from slack_channel — we
			-- preserve the legacy column for upgraded installs
			-- (see ALTER below) and write to the new one going
			-- forward.
			chat_channel  String DEFAULT '',
			slack_channel String DEFAULT '',
			-- custom_links — JSON array of {label, url} entries.
			-- Lets operators bolt on Grafana dashboards, Kibana
			-- searches, internal apps, status pages, etc. per
			-- service without us baking each surface in as a
			-- column.
			custom_links  String DEFAULT '[]',
			updated_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY service`,

		`CREATE TABLE IF NOT EXISTS system_settings (
			key        String,
			value      String,                          -- JSON-encoded
			updated_at DateTime64(9) DEFAULT now64(9),
			version    UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY key`,

		`CREATE TABLE IF NOT EXISTS notification_channels (
			id         String,
			name       String,
			type       LowCardinality(String),          -- email | slack | webhook
			config     String,                           -- JSON, schema depends on type
			enabled    UInt8 DEFAULT 1,
			min_severity LowCardinality(String) DEFAULT 'warning',  -- info | warning | critical
			-- match_rules — JSON predicates that gate delivery
			-- per channel: services / sreTeams / ownerTeams.
			-- Empty / {} means "catch-all"; populated arrays
			-- AND'd against the problem's service catalog.
			match_rules String DEFAULT '{}',
			created_at DateTime64(9) DEFAULT now64(9),
			version    UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		`CREATE TABLE IF NOT EXISTS exception_groups (
			fingerprint    String,                              -- sha1(type|message|service)
			ex_type        String,
			ex_message     String,
			service        LowCardinality(String),
			state          LowCardinality(String) DEFAULT 'new', -- new | acknowledged | resolved | ignored
			assignee       String       DEFAULT '',              -- user id, or '' for unassigned
			first_seen     DateTime64(9),
			last_seen      DateTime64(9),
			resolved_at    Nullable(DateTime64(9)),
			occurrences    UInt64       DEFAULT 0,
			notes          String       DEFAULT '',
			ai_summary     String       DEFAULT '',              -- v0.9.415 proaktif kök-sebep özeti
			-- v0.9.530 — özetin YAZILDIĞI an. problems.ai_summary_at'in
			-- ikizi; onsuz UI bayat bir özeti canlı sayıların altında
			-- taze gibi gösteriyordu. Epoch(0) = özet yok / yaş bilinmiyor.
			ai_summary_at  DateTime64(9) DEFAULT toDateTime64(0, 9),
			version        UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY fingerprint`,

		`CREATE TABLE IF NOT EXISTS slos (
			id            String,
			name          String,
			service       LowCardinality(String),
			sli_type      LowCardinality(String),  -- availability | latency
			target        Float64,                  -- e.g. 0.99 for 99%
			window_days   UInt16  DEFAULT 30,
			threshold_ms  Float64 DEFAULT 0,        -- only used by latency SLIs
			operation     String  DEFAULT '',       -- optional span name filter
			created_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		`CREATE TABLE IF NOT EXISTS dashboards (
			id           String,
			name         String,
			description  String       DEFAULT '',
			panels       String       DEFAULT '[]' CODEC(ZSTD(3)),
			variables    String       DEFAULT '[]' CODEC(ZSTD(3)),
			-- tags (v0.9.780): panoya ait, PAYLAŞILAN etiketler. JSON
			-- dizisi olarak saklanıyor (Array(LowCardinality(String))
			-- değil) çünkü etiketler serbest metin: operatör "ödeme",
			-- "prod", "gece nöbeti" yazar, kardinalite düşük olsa da
			-- kümesi kapalı değil. panels/variables ile aynı biçim
			-- kalması okuma/yazma yolunun tek tip olmasını sağlıyor —
			-- json.RawMessage üçü için de aynı nil/boş ayrımını taşıyor.
			tags         String       DEFAULT '[]' CODEC(ZSTD(3)),
			created_at   DateTime64(9) DEFAULT now64(9),
			updated_at   DateTime64(9) DEFAULT now64(9),
			version      UInt64       DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,
		// Forward-compat: add the variables column to installs that
		// pre-date the Grafana-style variable system.
		`ALTER TABLE dashboards ADD COLUMN IF NOT EXISTS variables String DEFAULT '[]' CODEC(ZSTD(3))`,
		// v0.9.780 — aynı forward-compat, etiketler için.
		`ALTER TABLE dashboards ADD COLUMN IF NOT EXISTS tags String DEFAULT '[]' CODEC(ZSTD(3))`,

		// maintenance_windows: operator-declared time ranges that
		// suppress alert notifications + auto-incident attach.
		// Match-mode is one of:
		//   • service = '*'             → global silence
		//   • service = '<exact name>'  → single-service silence
		//   • service ends with '*'     → prefix match
		// Active while start_at <= now() <= end_at. Problems
		// still open + auto-resolve normally; only the
		// notification fan-out is skipped, so the operator can
		// review what happened during the window via the
		// /anomalies + /incidents pages after the fact.
		`CREATE TABLE IF NOT EXISTS maintenance_windows (
			id          String,
			service     String,                       -- '*', exact, or 'name*' prefix
			severity    LowCardinality(String) DEFAULT '*',  -- '*', 'info', 'warning', 'critical'
			start_at    DateTime64(9),
			end_at      DateTime64(9),
			reason      String        DEFAULT '',
			created_by  String        DEFAULT '',
			created_at  DateTime64(9) DEFAULT now64(9),
			disabled    UInt8         DEFAULT 0,
			version     UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// anomaly_silences: per-fingerprint mute. Active while
		// until_at > now(). Silenced anomalies still get recorded
		// in anomaly_events (so the history table shows them) but
		// are suppressed in the live sections + skip notifications.
		`CREATE TABLE IF NOT EXISTS anomaly_silences (
			id           String,
			fingerprint  String,                       -- matches anomaly_events.id
			kind         LowCardinality(String),
			pattern      String,
			service      LowCardinality(String),
			created_by   String,                        -- user email
			created_at   DateTime64(9),
			until_at     DateTime64(9),
			reason       String        DEFAULT '',
			version      UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// v0.10.181 — anomaly_verdicts: operatörün OLAYA kararı («anomali» /
		// «değil»; etüt «anomali işaretleri» dilim 2, geri bildirim akışı).
		// Düşük hacimli state (/clickhouse-schema §1): RMT(version), ORDER BY =
		// event_id (tek dedup anahtarı — olay başına son karar), PARTITION YOK
		// (Kural P1), okuma FINAL. fingerprint = kanonik sha1 (silenceFingerprint)
		// → desen düzeyi istatistik («kaç kez değil dendi») ileride. Susturmadan
		// AYRI: susturma akışı/terfiyi kapatır, karar yalnız kayıt + görünüm.
		`CREATE TABLE IF NOT EXISTS anomaly_verdicts (
			event_id     String,
			fingerprint  String,
			kind         LowCardinality(String),
			pattern      String,
			service      LowCardinality(String),
			verdict      LowCardinality(String),      -- 'anomaly' | 'not_anomaly'
			note         String        DEFAULT '',
			created_by   String,                        -- user email
			created_at   DateTime64(9),
			version      UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY event_id
		TTL toDate(created_at) + INTERVAL 180 DAY`,
		// v0.10.193 — ROLLOUTS Faz 1a: olay tablosu + reconciler koşu kaydı
		// (rollout_schema.go). Düşük hacimli state: shard EDİLMEZ (üç kayda
		// GİRMEZ → stateTableDDL birleşik grup); prod'da 0012 ADIM 5.
		workloadRolloutsDDL,
		rolloutReconcileRunsDDL,
		// v0.10.959 — ROLLOUTS v2 P1.7: sekiz state tablosu (rollout_v2_schema.go,
		// v2-audit §10.3; sıra rolloutV2TableDDLs ile aynı). Shard EDİLMEZ →
		// birleşik state grubu; prod'da migrations/0015 (sihirbaz, boot değil).
		rolloutEventsDDL,
		rolloutWorkloadStateDDL,
		argocdAppStatusDDL,
		argocdSyncEventsDDL,
		argocdAppMappingDDL,
		rolloutClassificationDDL,
		adoCommitEnrichmentDDL,
		rolloutWorkerRunsDDL,

		// audit_log: who did what, when. Append-only event stream.
		// Used by admin compliance flow + the /admin/audit page.
		// Partitioned monthly so the TTL (1 year) drops whole
		// partitions instead of mutating rows.
		`CREATE TABLE IF NOT EXISTS audit_log (
			id           String,
			time         DateTime64(9),
			actor_id     String,                        -- user.id
			actor_email  String,
			actor_role   LowCardinality(String),
			action       LowCardinality(String),       -- e.g. "alert_rule.update"
			target_kind  LowCardinality(String),
			target_id    String        DEFAULT '',
			ip           String        DEFAULT '',
			details      String        DEFAULT ''     -- JSON: before/after diff or freeform
		) ENGINE = MergeTree()
		PARTITION BY toYYYYMM(time)
		ORDER BY (time, id)
		TTL toDate(time) + INTERVAL 365 DAY`,

		// saved_views: per-user named query / filter combos for
		// /traces, /logs, /anomalies, /metrics, etc. Stored as
		// the raw URL query string so applying a view = restoring
		// the URL, no schema coupling between server and SPA.
		`CREATE TABLE IF NOT EXISTS saved_views (
			id           String,
			owner_id     String,                        -- user.id; '' = team-shared
			name         String,
			page         LowCardinality(String),       -- "traces" | "logs" | "anomalies" | …
			query_string String,                        -- raw URL search (?from=…&to=…&filter=…)
			pinned       UInt8         DEFAULT 0,       -- pin to sidebar / topbar chip strip
			created_at   DateTime64(9) DEFAULT now64(9),
			version      UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// PARTITION BY YOK ve bu bilinçli (v0.9.1335, Kural P1 — emsal
		// root_cause_hypotheses/v0.9.1304, ai_feedback, rca_verdicts).
		// Tablo v0.9.1334'e dek `PARTITION BY toDate(started_at)`
		// taşıyordu ve started_at ORDER BY'da DEĞİL. mergeAnomalyCarry
		// started_at'i taşımaya söz veriyor ama sözü tutamadığı İKİ dal
		// var ve ikisi de bugün canlı:
		//   (a) taşıma SELECT'i hata verirse `prev` boş kalır (yumuşak
		//       düşüş, anomaly_event.go) → o tikin TÜM olayları "ilk
		//       görülme" gibi yazılır, started_at TAZELENİR;
		//   (b) satır 30 günlük TTL ile düştükten sonra aynı parmak izi
		//       yeniden ateşlerse started_at yeni pencereden gelir.
		// İkisinde de aynı id ikinci bir GÜN partition'ına düşer ve
		// ReplacingMergeTree'nin arka plan birleştirmesi partition
		// sınırını AŞMAZ → kopya TTL'e kadar ölümsüz. Doğruluk tek bir
		// SUNUCU AYARINA asılı kalır: do_not_merge_across_partitions_
		// select_final=1 açıldığı an FINAL iki satırı da döndürür.
		//
		// ÖLÇÜM (lokal chc-0, 2026-08-24, 0009 birleştirmesi SONRASI):
		// 186 id'nin 32'si hâlâ >1 gün-partition'ında. v0.9.1306'nın
		// shard-kayması teşhisi 0009 ile KAPANDI (birleştirmeden bu yana
		// yeni bölünme 0), ama yukarıdaki iki dal topolojiden bağımsız.
		//
		// TTL 30g artık partition-hizalı değil, SATIR düzeyinde (merge
		// sırasında) — root_cause_hypotheses ile aynı şekil. toDate(...)
		// + INTERVAL N DAY formu korunuyor: gün granülünde sarmalamak
		// v0.6.36 birim-karıştırma kuralına UYGUN.
		//
		// MEVCUT KURULUM KENDİLİĞİNDEN DÜZELMEZ: `CREATE TABLE IF NOT
		// EXISTS` var olan tabloya dokunmaz. Göç operatörde —
		// migrations/0010_state_repartition.sql. Boot'ta yalnız SALT
		// OKUNUR bir uyarı basılır (state_repartition.go).
		//
		// anomaly_events: persistent record of detected log-pattern
		// + trace-op anomalies. ReplacingMergeTree(version) keeps
		// only the latest row per id; the recorder upserts on every
		// detector tick so last_seen advances continuously while a
		// pattern is firing. The /anomalies page derives "active"
		// vs "cleared" status from last_seen freshness in the query
		// layer — no separate sweep needed.
		`CREATE TABLE IF NOT EXISTS anomaly_events (
			id            String,
			kind          LowCardinality(String),     -- log_pattern | trace_op
			pattern       String,                      -- pattern name OR operation name
			service       LowCardinality(String),
			started_at    DateTime64(9),
			last_seen     DateTime64(9),
			peak_ratio    Float64,
			current_ratio Float64,
			current_count UInt64,
			sample        String        DEFAULT '',
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id
		TTL toDate(started_at) + INTERVAL 30 DAY`,

		// root_cause_hypotheses: the persisted, pre-computed root-cause
		// ranking per anchor (an anomaly OR a critical problem). The
		// anomaly→root-cause worker synthesizes correlator.Synthesize over
		// the same bounded evidence the on-demand /rootcause fan-out gathers
		// and upserts here on a leader-gated tick, so /anomalies + /problems
		// can render a "Root cause: <suspect> (NN%)" ribbon with NO per-row
		// fetch. COMPUTED state (not operator-saved) — a dedicated table like
		// anomaly_events above, NOT the saved_views catch-all (invariant #5
		// is for USER state). ReplacingMergeTree(version) keeps the latest
		// synthesis per anchor; reads use FINAL. ORDER BY is the dedup key
		// ONLY: (anchor_kind, anchor_id). candidates is a JSON String blob
		// (the small ScoredCause list, read whole, never queried by
		// sub-field) — no nested/Array-of-Tuple schema.
		//
		// PARTITION BY YOK ve bu bilinçli (v0.9.1304 — Kural P1 ihlaliydi;
		// emsal ai_feedback / rca_verdicts). Tablo v0.9.1303'e kadar
		// `PARTITION BY toYYYYMM(computed_at)` taşıyordu ve computed_at
		// ORDER BY'da DEĞİL: her tik satırı `now` ile yeniden yazıyor, yani
		// ay sınırını geçen her AÇIK anchor ikinci bir satır kazanıyordu.
		// ReplacingMergeTree'nin arka plan birleştirmesi partition SINIRINI
		// AŞMAZ → o kopya fiziksel olarak ÖLÜMSÜZ (TTL'e kadar), ve
		// doğruluğu ayakta tutan tek şey `SELECT … FINAL`'in sorgu anında
		// partition'lar arası birleştirme yapması. Bu bir SUNUCU AYARINA
		// bağlı: `do_not_merge_across_partitions_select_final=1` (yaygın bir
		// FINAL hızlandırma vidası) kurulduğu anda FINAL iki satırı da
		// döndürür ve GetHypotheses'in map yazımı son satırı kazandırır —
		// ribbon SESSİZCE bayat şüpheli gösterirdi. Ölçüm için CH 24.8.14'te
		// iki kol da doğrulandı.
		//
		// Bedeli yok: hiçbir okuma zamanla budamıyor (iki okuma da ORDER BY
		// anahtarına eşitlikle giriyor), retention_enforce.go bu tabloyu
		// yönetmiyor, ve satır sayısı açık anchor sayısıyla sınırlı.
		//
		// TTL 30g artık partition-hizalı değil, SATIR düzeyinde (merge
		// sırasında) uygulanır — ai_feedback/rca_verdicts'in 90g TTL'iyle
		// aynı şekil. toDate(...) + INTERVAL N DAY formu korunuyor: gün
		// granülünde sarmalamak v0.6.36 birim-karıştırma kuralına UYGUN
		// (yasak olan sub-day matematiğin etrafına toDate koymak).
		`CREATE TABLE IF NOT EXISTS root_cause_hypotheses (
			anchor_kind   LowCardinality(String),     -- anomaly | problem
			anchor_id     String,                      -- AnomalyEvent.id OR Problem.id
			service       LowCardinality(String),
			computed_at   DateTime64(9),
			top_suspect   String        DEFAULT '',    -- #1 candidate's service ('' = no clear cause)
			top_score     Float64       DEFAULT 0,
			confidence    Float64       DEFAULT 0,
			candidates    String        DEFAULT '[]',  -- JSON-encoded []ScoredCause, best first
			recent_deploy String        DEFAULT '',    -- JSON-encoded *RecentDeploy or ''
			deep_evidence String        DEFAULT '' CODEC(ZSTD(3)), -- v0.9.516: JSON DeepEvidence (P1 soruşturma kanıtı + denetim izi)
			exemplar_trace_id String    DEFAULT '',  -- v0.9.1057: temsilî trace (Faz 1.2)
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY (anchor_kind, anchor_id)
		TTL toDate(computed_at) + INTERVAL 30 DAY`,
		// v0.9.516 — mevcut kurulumlar için in-place kolon ekleme. Taze
		// kurulumda CREATE zaten taşıyor, bu no-op. ZSTD: kanıt bloğu
		// tekrarlı metin, sıkışması yüksek. Düşük hacimli state tablosu
		// (anchor başına bir satır, 30 gün TTL) — spans sınıfı değil.
		`ALTER TABLE root_cause_hypotheses ADD COLUMN IF NOT EXISTS deep_evidence String DEFAULT '' CODEC(ZSTD(3))`,
		// v0.9.1057 (Faz 1.2) — aynı v0.9.516 deseni: state tablosuna
		// boot-ALTER, taze kurulumda no-op.
		`ALTER TABLE root_cause_hypotheses ADD COLUMN IF NOT EXISTS exemplar_trace_id String DEFAULT ''`,

		`CREATE TABLE IF NOT EXISTS alert_rules (
			id           String,
			name         String,
			service      String       DEFAULT '',
			metric       LowCardinality(String),
			comparator   LowCardinality(String),
			threshold    Float64,
			window_sec   UInt32,
			severity     LowCardinality(String) DEFAULT 'warning',
			enabled      UInt8        DEFAULT 1,
			built_in     UInt8        DEFAULT 0,
			runbook_url  String       DEFAULT '',
			for_sec      UInt32       DEFAULT 0,
			min_samples  UInt32       DEFAULT 0,
			cooldown_sec UInt32       DEFAULT 0,
			log_query    String       DEFAULT '',     -- saved-search log alert (v0.5.242)
			watcher_json String       DEFAULT '',     -- imported ES Watcher definition, verbatim (v0.9.x)
			target_json  String       DEFAULT '',     -- v0.10.331 hedefli kural (RuleTarget JSON)
			notify_json  String       DEFAULT '',     -- v0.10.519 kural bazında ekip bildirimi (RuleNotify JSON)
			created_at   DateTime64(9) DEFAULT now64(9),
			version      UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// PARTITION BY YOK ve bu bilinçli (v0.9.1335, Kural P1 — aynı
		// gerekçe anomaly_events'te uzun uzun yazılı). problems'ın kendi
		// yeniden-yazım dalı AYRI ve anomaly'den bağımsız: problem id'si
		// birçok dedektörde DETERMİNİSTİK (fatalExcProblemID,
		// capacityProblemID, runtimeProblemID, sharedBurstProblemID,
		// `anomaly-auto:<fp>:<servis>`), yani KAPANIP sonra yeniden AÇILAN
		// bir problem AYNI id'yi geri alır — ama açılış dalı started_at'i
		// o anki `now`/`FirstSeen` ile yazar (evaluator/fatal_exception.go,
		// db_capacity.go, runtime_vm.go, selfhealth.go). Kapanış ile
		// yeniden açılış arasına bir gece sıkıştığı an aynı id ikinci bir
		// gün-partition'ına düşer ve FINAL onları asla birleştiremez.
		// (Rastgele id üreten ana kural yolu — evaluator.go `newID()` —
		// bu sınıfa girmez: yeni id, yeni satır, çakışma yok.)
		//
		// started_at kozmetik DEĞİL: P1 açık-saat eşiğini ve
		// effectiveSeverity'nin yaş tabanlı yükseltmesini besliyor.
		// Bayat bir satırın kazanması yaşlanmış bir problemi sessizce
		// GERİ indirir.
		//
		// ÖLÇÜM (lokal chc-0, 2026-08-24): 4819 id'nin 21'i >1
		// gün-partition'ında. TTL YOK — partition düşmesi zaten hiçbir
		// şeyi temizlemiyordu (EnforceRetention bu tabloyu yönetmiyor),
		// yani partition'ı sökmenin retention maliyeti SIFIR.
		//
		// Göç operatörde: migrations/0010_state_repartition.sql.
		`CREATE TABLE IF NOT EXISTS problems (
			id           String,
			rule_id      String,
			rule_name    String,
			severity     LowCardinality(String),
			service      LowCardinality(String),
			metric       LowCardinality(String),
			value        Float64,
			threshold    Float64,
			status       LowCardinality(String),       -- open | resolved
			description  String,
			assignee     String        DEFAULT '',     -- owner_team OR email after manual claim
			pod          String        DEFAULT '',     -- v0.9.403: runtime pod denetimlerinin pod kimliği; service artık birleşik ad taşımaz
			started_at   DateTime64(9),
			resolved_at  Nullable(DateTime64(9)),
			updated_at   DateTime64(9) DEFAULT now64(9),
			version      UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// ── Synthetic monitoring ─────────────────────────────────────
		// Definitions for HTTP probes and passive heartbeats. Probed by
		// the runner loop in the background; results stream into
		// monitor_results below for status timeline + uptime% calc.
		`CREATE TABLE IF NOT EXISTS monitors (
			id            String,
			name          String,
			type          LowCardinality(String),         -- http | tcp | ssl-cert | keyword | heartbeat
			-- HTTP + keyword fields (ignored for other types):
			url           String        DEFAULT '',
			method        LowCardinality(String) DEFAULT 'GET',
			expected_status UInt16      DEFAULT 200,
			timeout_sec   UInt16        DEFAULT 5,
			-- Common:
			interval_sec  UInt32        DEFAULT 60,        -- probe interval (active) or grace window (heartbeat)
			enabled       UInt8         DEFAULT 1,
			-- Heartbeat-only:
			heartbeat_token String      DEFAULT '',        -- random; appears in /api/heartbeats/{token}
			-- tcp + ssl-cert (v0.8.283):
			target         String       DEFAULT '',        -- host:port to dial
			cert_warn_days UInt16        DEFAULT 14,        -- ssl-cert: DOWN when days-remaining < this
			-- keyword (v0.8.283):
			keyword        String        DEFAULT '',        -- substring asserted in the response body
			keyword_invert UInt8         DEFAULT 0,          -- 1 = must NOT contain
			created_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// One row per probe attempt — keeps a 30d (default) timeline
		// the UI can render as a status bar. status = up | down |
		// degraded; latency_ms = wall-clock probe time. message holds
		// the failure reason for down/degraded rows.
		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS monitor_results (
			monitor_id  String,
			time        DateTime64(9) CODEC(Delta, ZSTD(3)),
			status      LowCardinality(String),
			latency_ms  Int64         CODEC(T64, ZSTD(3)),
			http_code   UInt16        DEFAULT 0,
			message     String        CODEC(ZSTD(3)),
			detail      Int64         DEFAULT 0 CODEC(T64, ZSTD(3)),  -- ssl-cert: days remaining (v0.8.283)
			INDEX idx_mid monitor_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (monitor_id, time)
		TTL toDate(time) + INTERVAL %d DAY
		SETTINGS index_granularity = 8192`, 30),

		// ── Incident management ──────────────────────────────────────
		// One row per declared incident. Multiple Problems / Monitor
		// flips auto-attach to a single Incident when they share the
		// same service + severity within a short window — gives the
		// oncall one place to track the whole event end-to-end.
		`CREATE TABLE IF NOT EXISTS incidents (
			id          String,
			title       String,
			severity    LowCardinality(String),       -- info | warning | critical
			status      LowCardinality(String),       -- open | acknowledged | resolved
			service     LowCardinality(String) DEFAULT '',
			summary     String        DEFAULT '',
			assignee    String        DEFAULT '',
			postmortem  String        DEFAULT '',     -- markdown body, blameless template
			started_at  DateTime64(9),
			ack_at      Nullable(DateTime64(9)),
			resolved_at Nullable(DateTime64(9)),
			updated_at  DateTime64(9) DEFAULT now64(9),
			version     UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toDate(started_at)
		ORDER BY id`,

		// Append-only timeline of events on each incident — Problem
		// attachments, state changes, manual notes from oncall. Drives
		// the "what happened when" UI on the incident detail page.
		`CREATE TABLE IF NOT EXISTS incident_events (
			incident_id String,
			time        DateTime64(9) DEFAULT now64(9) CODEC(Delta, ZSTD(3)),
			kind        LowCardinality(String),       -- created | ack | resolved | note | problem_attached | problem_resolved
			actor       String        DEFAULT '',     -- user email or 'system'
			body        String        DEFAULT '',
			ref_id      String        DEFAULT '',     -- problem id, etc.
			INDEX idx_iid incident_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (incident_id, time)
		SETTINGS index_granularity = 8192`,

		// problem_id → incident_id mapping for auto-grouping.
		// ReplacingMergeTree on problem_id keeps only the latest
		// assignment when a problem gets re-grouped.
		`CREATE TABLE IF NOT EXISTS incident_problems (
			problem_id  String,
			incident_id String,
			attached_at DateTime64(9) DEFAULT now64(9),
			version     UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY problem_id`,

		// ── Runtime settings (key/value, admin-set overrides) ───────
		// Holds anything the operator can change live without a config
		// reload — currently retention TTLs per signal table. Schema
		// is intentionally generic so adding new keys later doesn't
		// need a migration.
		`CREATE TABLE IF NOT EXISTS system_settings (
			key        String,
			value      String,
			updated_at DateTime64(9) DEFAULT now64(9),
			updated_by String        DEFAULT '',
			version    UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY key`,
		// Forward-compat: add updated_by to installs that pre-date it.
		// Idempotent — IF NOT EXISTS makes re-running a no-op.
		`ALTER TABLE system_settings ADD COLUMN IF NOT EXISTS updated_by String DEFAULT ''`,

		// ── Public status page ──────────────────────────────────────
		// Single-row config table — operator-customizable header for
		// the public /public-status page. ID always 'default'.
		`CREATE TABLE IF NOT EXISTS status_page_config (
			id          String,
			title       String        DEFAULT 'Service Status',
			description String        DEFAULT '',
			support_url String        DEFAULT '',
			updated_at  DateTime64(9) DEFAULT now64(9),
			version     UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// Curated list of components shown on the public status page.
		// Each component derives its current state from EITHER:
		//   - a monitor (HTTP probe / heartbeat) — if monitor_id set
		//   - the absence of open critical incidents on a service —
		//     if service_name set
		// display_order controls top-to-bottom rendering.
		`CREATE TABLE IF NOT EXISTS status_page_components (
			id            String,
			name          String,
			description   String        DEFAULT '',
			monitor_id    String        DEFAULT '',
			service_name  String        DEFAULT '',
			display_order Int32         DEFAULT 0,
			created_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// ai_calls — every Copilot LLM call logged for native AI
		// observability (v0.5.162). Captures provider/model/latency/
		// tokens/status + a small prompt+response sample so the
		// operator can see "is the AI helpful here?" and "what did
		// it actually generate?" without exporting to a third-party
		// LLM-trace tool. 90d TTL keeps the table bounded — for
		// older artifact retention export to S3 or extend the TTL.
		`CREATE TABLE IF NOT EXISTS ai_calls (
			id              String,
			created_at      DateTime64(9) DEFAULT now64(9),
			surface         LowCardinality(String),
			exchange_id     String DEFAULT '',
			provider        LowCardinality(String),
			model           LowCardinality(String),
			base_url        String DEFAULT '',
			duration_ms     UInt32,
			input_tokens    UInt32 DEFAULT 0,
			output_tokens   UInt32 DEFAULT 0,
			status          LowCardinality(String),
			error_msg       String DEFAULT '',
			prompt_chars    UInt32 DEFAULT 0,
			response_chars  UInt32 DEFAULT 0,
			user_id         String DEFAULT '',
			user_email      String DEFAULT '',
			prompt_sample   String DEFAULT '' CODEC(ZSTD(3)),
			response_sample String DEFAULT '' CODEC(ZSTD(3))
		) ENGINE = MergeTree
		PARTITION BY toYYYYMM(created_at)
		ORDER BY (created_at, surface, provider)
		TTL toDate(created_at) + INTERVAL 90 DAY`,

		// ai_feedback — operator thumbs up/down on AI answers
		// (v0.8.399, AI audit feedback slice). One row per rated
		// exchange, keyed by the exchange_id the chat handler mints
		// and emits in the SSE answer event; the same id lands on the
		// ai_calls row so quality joins back to cost/latency. Mutable
		// state (the user can flip their verdict) → ReplacingMergeTree
		// (version), latest wins, reads use FINAL. ORDER BY is the
		// dedup key EXCLUSIVELY (house rule — extra columns would
		// silently break dedup), and there is deliberately NO
		// PARTITION BY: a re-verdict across a partition boundary
		// would survive FINAL as a duplicate. TTL matches ai_calls'
		// 90d so orphaned verdicts age out with the calls they rate
		// (trace_snapshots precedent for TTL on a state table).
		`CREATE TABLE IF NOT EXISTS ai_feedback (
			exchange_id String,
			surface     LowCardinality(String),
			verdict     Int8,
			user_email  String        DEFAULT '',
			created_at  DateTime64(9) DEFAULT now64(9),
			version     UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY exchange_id
		TTL toDate(created_at) + INTERVAL 90 DAY`,

		// v0.9.1193 (AI Faz 5.1) — 👎'nin YORUMU. "Faydasız" tek başına
		// madencilik için zayıf sinyal: /ai negatif paneli hangi soru
		// şekillerinin kötü cevap aldığını gösteriyor ama NEDEN kötü
		// olduğunu operatör söyleyemiyordu. Tam-satır replace sözleşmesi
		// gereği HER yazıcı bu kolonu taşır; flip'te korunması API
		// katmanında (ai_feedback.go preserve yolu).
		`ALTER TABLE ai_feedback ADD COLUMN IF NOT EXISTS comment String DEFAULT '' CODEC(ZSTD(3))`,
		// v0.10.409 (CoSRE denetimi E2/O3/O4) — ai_calls: prompt sürümü,
		// profil, hata sınıfı, TTFT, akış düşüşü, kalkan isabeti. Düşük
		// hacimli state tablosu; küme kipinde ertelenen DDL → INSERT probe
		// görene dek eski kolon listesi (iki-boot sözleşmesi, operatör onayı).
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS prompt_version LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS profile_id LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS error_class LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS ttft_ms UInt32 DEFAULT 0`,
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS stream_fallback UInt8 DEFAULT 0`,
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS shield_hits UInt8 DEFAULT 0`,
		// v0.10.807 (dış skill denetimi L2) — önek önbelleğinden gelen giriş
		// token'ı; aynı iki-boot sözleşmesi, AYRI probe (409 kolonları var,
		// bu yokken INSERT kırılmasın).
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS cached_tokens UInt32 DEFAULT 0`,

		// rca_verdicts — kök-neden hakem kararının KALICI kaydı
		// (v0.9.591). Öncesinde verdict istek başına üretilip
		// yalnızca HTTP yanıtında yaşıyordu: ne kararın kendisi ne de
		// kalkanların ne yaptığı hiçbir yere düşüyordu. Tek kalıcı iz
		// ai_calls.response_sample'daki modelin HAM çıktısıydı — yani
		// kalkanlardan ÖNCEKİ hâli, ki operatörün gördüğü o değil.
		//
		// İki şeyi birden mümkün kılıyor:
		//   1. ölçüm — kalkanlar ne sıklıkla devreye giriyor, model
		//      ne sıklıkla çözümlenemiyor, kaç karar insufficient
		//   2. geri bildirim — exchange_id ai_feedback'e join olur ve
		//      "hangi verdict'e 👎 verildi" cevaplanabilir hale gelir
		//
		// ORDER BY exchange_id: ai_feedback ile AYNI anahtar, join
		// bedavaya gelsin diye. Dedup anahtarı MÜNHASIRAN bu (ev
		// kuralı — ek kolon dedup'ı sessizce bozar).
		//
		// PARTITION BY yok ve bu bilinçli: ai_feedback emsali. Bir
		// yeniden-yazım partition sınırını aşarsa FINAL onu kopya
		// olarak sağ bırakırdı.
		//
		// TTL 90g — ai_calls ve ai_feedback ile hizalı; öksüz kalan
		// verdict, derecelendirdiği çağrıyla birlikte yaşlanıp düşsün.
		`CREATE TABLE IF NOT EXISTS rca_verdicts (
			exchange_id   String,
			anchor_kind   LowCardinality(String),
			anchor_id     String,
			service       LowCardinality(String) DEFAULT '',
			verdict       LowCardinality(String),
			-- v0.9.595 — İMZA alanları. Bir verdict'i "kök neden şu
			-- varlıkta, şu arıza kipiyle" diye özetleyen ikili; LEARN
			-- katmanı geçmiş vakaları bununla eşleştiriyor.
			-- LowCardinality(entity): servis/host adı, binlerce mertebe.
			-- failure_mode serbest metin — modelin cümlesi, sınırlı değil.
			rc_entity     LowCardinality(String) DEFAULT '',
			rc_fail_mode  String DEFAULT '',
			confidence    Float64 DEFAULT 0,
			model_conf    Float64 DEFAULT 0,
			hypo_conf     Float64 DEFAULT 0,
			hypo_version  UInt64  DEFAULT 0,
			parsed        UInt8   DEFAULT 0,
			repaired      UInt8   DEFAULT 0,
			shield_notes  Array(String),
			-- v0.9.1281 — operatöre GÖSTERİLEN gövde + onu kim tetikledi.
			--
			-- Öncesinde verdict'in METNİ yalnız 30dk'lık explain
			-- önbelleğinde yaşıyordu: enum/güven/kalkanlar kalıcıydı ama
			-- "ne yazıyordu" önbellek düşünce yok oluyordu. Yani üretilen
			-- bir tanının ömrü bir önbellek TTL'iydi.
			--
			-- body serbest metin (prose; model çözümlenemediyse
			-- deterministik summary) — LowCardinality DEĞİL, CODEC(ZSTD(3))
			-- (ai_feedback.comment emsali). Yazan taraf 8KB'a kırpar
			-- (trimRCAVerdictBody).
			-- source iki değerli: 'operator' (✨ Explain tıklaması) |
			-- 'auto' (derin soruşturma kapısı) → LowCardinality.
			body          String        DEFAULT '' CODEC(ZSTD(3)),
			source        LowCardinality(String) DEFAULT '',
			created_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY exchange_id
		TTL toDate(created_at) + INTERVAL 90 DAY`,

		// v0.10.940 — ai_eval_runs: Settings › AI › Değerlendirme panelinin
		// koşu kaydı (ai_eval_runs.go). Koşu sunucuda sürer; satır başta
		// (running), HER vakadan sonra (sayaçlar + summary, cases BOŞ — yazım
		// küçük kalsın) ve sonda (son durum + cases) YENİDEN yazılır → state
		// sınıfı: ReplacingMergeTree(version), ORDER BY id MÜNHASIRAN, FINAL
		// okuma. version istemci damgası (settings.go v0.10.129 emsali —
		// Replicated INSERT dedup'u özdeş bloğu düşürmesin).
		// PARTITION BY YOK (ai_feedback/rca_verdicts emsali; Kural P1).
		// finished_at sentinel'i epoch (C4 — Nullable yok). Saklama: liste
		// en yeni 20'yi gösterir; fiziksel silme 180g TTL — ALTER DELETE
		// mutasyonu YOK. cases/summary serbest JSON → ZSTD(3), LC değil.
		`CREATE TABLE IF NOT EXISTS ai_eval_runs (
			id             String,
			started_at     DateTime64(9),
			updated_at     DateTime64(9),
			finished_at    DateTime64(9) DEFAULT toDateTime64(0, 9),
			status         LowCardinality(String),
			started_by     String  DEFAULT '',
			app_version    String  DEFAULT '',
			prompt_version String  DEFAULT '',
			model          String  DEFAULT '',
			profile_id     String  DEFAULT '',
			surfaces       Array(String),
			total          UInt32  DEFAULT 0,
			done           UInt32  DEFAULT 0,
			pass           UInt32  DEFAULT 0,
			fail           UInt32  DEFAULT 0,
			skipped        UInt32  DEFAULT 0,
			rubric_mean    Float64 DEFAULT 0,
			error          String  DEFAULT '',
			summary        String  DEFAULT '' CODEC(ZSTD(3)),
			cases          String  DEFAULT '' CODEC(ZSTD(3)),
			version        UInt64  DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id
		TTL toDateTime(started_at) + INTERVAL 180 DAY`,

		// Email subscribers — get notified when a public-visible
		// incident opens or resolves on the configured components.
		// Double opt-in: public submissions land with verified=0
		// and a confirm_token; the operator's manual add path
		// bypasses (verified=1, empty token).
		`CREATE TABLE IF NOT EXISTS status_page_subscribers (
			id              String,
			email           String,
			verified        UInt8         DEFAULT 0,
			confirm_token   String        DEFAULT '',
			confirm_sent_at DateTime64(9) DEFAULT toDateTime64(0, 9),
			created_at      DateTime64(9) DEFAULT now64(9),
			version         UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY email`,

		// Service dependency contracts (v0.5.191). Operator-curated
		// architectural assertions: "auth-service must call audit-log"
		// (must-call) or "billing-api must NOT call user-profile
		// directly" (forbidden). Evaluator checks every minute
		// against topology_edges_5m; violations surface on the
		// admin /admin/contracts page. Severity drives whether a
		// violation is informational or paged.
		`CREATE TABLE IF NOT EXISTS service_contracts (
			id             String,
			name           String,
			service        String,
			rule_type      LowCardinality(String),
			target_service String,
			description    String         DEFAULT '',
			severity       LowCardinality(String) DEFAULT 'warning',
			enabled        UInt8          DEFAULT 1,
			created_by     String         DEFAULT '',
			created_at     DateTime64(9)  DEFAULT now64(9),
			version        UInt64         DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// Trace snapshots — Grafana-style "share publicly" links for
		// the trace detail page. Each row mints a URL-safe token that
		// resolves to a trace_id, gated by `expires_at`. Public route
		// (no auth) reads by token. Token is the primary key so we can
		// revoke or list per-trace cheaply.
		//
		// TTL drops expired rows during background merges so the table
		// doesn't grow unboundedly with one-off shares. 7-day grace
		// past expires_at leaves forensics room (who minted what for
		// which trace) before the row physically goes away.
		`CREATE TABLE IF NOT EXISTS trace_snapshots (
			token        String,
			trace_id     String,
			created_by   String        DEFAULT '',
			created_at   DateTime64(9) DEFAULT now64(9),
			expires_at   DateTime64(9),
			version      UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY token
		TTL toDateTime(expires_at) + INTERVAL 7 DAY`,

		// Marks an existing incident as visible on the public status
		// page. Operator toggles via the admin UI. Kept as a separate
		// table so the existing incidents row schema stays untouched
		// (ALTER on ReplacingMergeTree is awkward).
		`CREATE TABLE IF NOT EXISTS status_page_published (
			incident_id   String,
			published     UInt8         DEFAULT 1,
			public_title  String        DEFAULT '',  -- override the internal title for public display
			public_body   String        DEFAULT '',  -- markdown explanation suitable for end users
			updated_at    DateTime64(9) DEFAULT now64(9),
			version       UInt64        DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY incident_id`,

		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS profiles (
			profile_id    String       CODEC(ZSTD(3)),
			service_name  LowCardinality(String),
			host_name     LowCardinality(String) DEFAULT '',
			profile_type  LowCardinality(String),
			start_time    DateTime64(9) CODEC(Delta, ZSTD(3)),
			duration_ns   Int64        CODEC(T64, ZSTD(3)),
			pprof_data    String       CODEC(ZSTD(6)),
			sample_count  UInt32       DEFAULT 0,
			labels_keys   Array(LowCardinality(String)),
			labels_values Array(String),
			INDEX idx_pid profile_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(start_time)
		ORDER BY (service_name, profile_type, start_time)
		TTL toDate(start_time) + INTERVAL %d DAY
		SETTINGS index_granularity = 8192`, md),

		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS metric_points (
			metric        LowCardinality(String),
			instrument    LowCardinality(String),
			description   String       DEFAULT '' CODEC(ZSTD(1)),
			unit          LowCardinality(String) DEFAULT '',
			service_name  LowCardinality(String),
			host_name     LowCardinality(String) DEFAULT '',
			time          DateTime64(9) CODEC(Delta, ZSTD(3)),
			start_time    DateTime64(9) DEFAULT time CODEC(Delta, ZSTD(3)),
			value         Float64      CODEC(Gorilla, ZSTD(3)),
			count         UInt64       DEFAULT 0,
			sum_value     Float64      DEFAULT 0 CODEC(Gorilla, ZSTD(3)),
			min_value     Float64      DEFAULT 0,
			max_value     Float64      DEFAULT 0,
			attr_keys     Array(LowCardinality(String)),
			attr_values   Array(String) CODEC(ZSTD(1)),
			res_keys      Array(LowCardinality(String)),
			res_values    Array(String) CODEC(ZSTD(1)),
			-- v0.5.358 — explicit histogram bucket bounds + per-bucket
			-- counts. Required for read-time quantile estimation; the
			-- OTLP ingest path fills these for Histogram data points
			-- (otlp/convert.go Metric_Histogram). Default [] keeps
			-- old data + non-histogram instruments compatible.
			bucket_bounds Array(Float64) DEFAULT [],
			bucket_counts Array(UInt64)  DEFAULT [],
			-- v0.6.56 — OTLP aggregation temporality ('delta' |
			-- 'cumulative' | ''). Captured so the histogram read path
			-- can delta cumulative series before bucketing; without it
			-- a cumulative heatmap grows monotonically to the right
			-- (wrong). Empty = legacy rows / producer didn't report it.
			temporality   LowCardinality(String) DEFAULT ''
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (service_name, metric, time)
		TTL toDate(time) + INTERVAL %d DAY
		SETTINGS index_granularity = 8192`, md),

		// exemplars — v0.8.328, cross-signal pivot Phase 1a. One row per
		// OTLP metric exemplar (previously dropped at ingest). The
		// metric→trace pivot reads WHERE series_fingerprint IN (…) AND a
		// timestamp window — a pure primary-key scan on this ORDER BY, no
		// JOIN. series_fingerprint is the same xxhash64 identity stored on
		// metric_points.series_fingerprint (otlp.SeriesFingerprint).
		//   - trace_id / span_id: plain String (hex, same encoding as
		//     spans.trace_id → same-type joins). NOT LowCardinality:
		//     high-cardinality IDs make the dict overhead exceed its value.
		//   - filtered_attributes: Map — exemplar attr sets are tiny and
		//     read whole; no per-key indexOf() access pattern to serve.
		//   - TTL from retention.spans (%[1]d, NOT MetricsDays) ON PURPOSE:
		//     an exemplar's payload IS its trace link, so an exemplar that
		//     outlives its trace is a dead click. SetRetention keeps this
		//     in lockstep with operator edits to retention.spans.
		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS exemplars (
			series_fingerprint UInt64,
			metric_name   LowCardinality(String),
			service_name  LowCardinality(String),
			timestamp     DateTime64(9) CODEC(Delta, ZSTD(3)),
			value         Float64      CODEC(Gorilla, ZSTD(3)),
			trace_id      String       DEFAULT '' CODEC(ZSTD(3)),
			span_id       String       DEFAULT '' CODEC(ZSTD(3)),
			filtered_attributes Map(LowCardinality(String), String)
		) ENGINE = MergeTree()
		PARTITION BY toDate(timestamp)
		ORDER BY (series_fingerprint, timestamp)
		TTL toDate(timestamp) + INTERVAL %[1]d DAY
		SETTINGS index_granularity = 8192`, sd),

		// span_links — v0.8.329, cross-signal pivot Phase 1b. One row per
		// OTel span link (previously dropped at ingest, pivot-audit §2).
		// Both pivot directions are point-lookups by ONE trace id, so BOTH
		// get their own primary key (the operator-approved storage call):
		// this table serves "what does this trace link TO" as a pure PK
		// scan on ORDER BY (trace_id, time); the reverse MV below copies
		// every row into span_links_reverse whose ORDER BY (linked_trace_id,
		// time) makes "what links TO this trace" a PK scan too — no full
		// scan, no JOIN in either direction. A nested column on `spans` was
		// rejected: the reverse direction would need a spans full-scan or a
		// separate index table anyway, and link rows are ~1-5% of span
		// volume — cheap to duplicate.
		//   - trace/span ids: plain String DEFAULT '' (hex, same encoding as
		//     spans.trace_id → same-type lookups). NOT LowCardinality:
		//     high-cardinality IDs make the dict overhead exceed its value.
		//   - idx_linked bloom filter: belt-and-braces for ad-hoc backlink
		//     queries against THIS table (the reverse table is the real
		//     answer; the bloom keeps a mis-routed query survivable).
		//   - attr arrays: the spans layout (LC keys + ZSTD values) — link
		//     attr sets are tiny ("follows_from", batch ids), read whole.
		//   - TTL from retention.spans (%[1]d) — a span link outliving its
		//     spans is a dead edge in both directions. SetRetention keeps
		//     this in lockstep with operator edits to retention.spans.
		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS span_links (
			trace_id        String DEFAULT '' CODEC(ZSTD(3)),
			span_id         String DEFAULT '' CODEC(ZSTD(3)),
			linked_trace_id String DEFAULT '' CODEC(ZSTD(3)),
			linked_span_id  String DEFAULT '' CODEC(ZSTD(3)),
			time            DateTime64(9) CODEC(Delta, ZSTD(3)),
			service_name    LowCardinality(String),
			attr_keys       Array(LowCardinality(String)),
			attr_values     Array(String) CODEC(ZSTD(3)),
			INDEX idx_linked linked_trace_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (trace_id, time)
		TTL toDate(time) + INTERVAL %[1]d DAY
		SETTINGS index_granularity = 8192`, sd),

		// span_links_reverse — the SAME rows as span_links with the reverse
		// direction as the primary key (v0.8.329, rationale above). A real
		// MergeTree table (not a combined MV) so the MV below can be a
		// storage-less TO-form trigger: in cluster mode the TO target stays
		// the bare Distributed name, which is exactly what re-shards reverse
		// rows by linked_trace_id (cluster.go defaultShardPolicy). Never
		// written directly — ingest only touches span_links. No skip index:
		// its ORDER BY prefix IS the one query it exists to serve.
		fmt.Sprintf(`CREATE TABLE IF NOT EXISTS span_links_reverse (
			trace_id        String DEFAULT '' CODEC(ZSTD(3)),
			span_id         String DEFAULT '' CODEC(ZSTD(3)),
			linked_trace_id String DEFAULT '' CODEC(ZSTD(3)),
			linked_span_id  String DEFAULT '' CODEC(ZSTD(3)),
			time            DateTime64(9) CODEC(Delta, ZSTD(3)),
			service_name    LowCardinality(String),
			attr_keys       Array(LowCardinality(String)),
			attr_values     Array(String) CODEC(ZSTD(3))
		) ENGINE = MergeTree()
		PARTITION BY toDate(time)
		ORDER BY (linked_trace_id, time)
		TTL toDate(time) + INTERVAL %[1]d DAY
		SETTINGS index_granularity = 8192`, sd),

		// Pre-aggregated topology edges (v0.5.108). The service-
		// level topology view used to run a self-join on the spans
		// table per request — at billions-of-spans-per-day scale
		// that's a non-starter. A background aggregator goroutine
		// runs the join once per 5-min bucket and stores results
		// here; API reads from this table instead of spans. 14d
		// retention is plenty for an overview surface; ReplacingMergeTree
		// dedupes re-runs over the same bucket (idempotent backfills).
		`CREATE TABLE IF NOT EXISTS topology_edges_5m (
			time_bucket     DateTime CODEC(DoubleDelta, ZSTD(3)),
			parent_service  LowCardinality(String),
			child_node      String,
			node_kind       LowCardinality(String),  -- service|db|queue|external
			protocol        LowCardinality(String),  -- http|rpc|db|kafka|internal
			top_labels      Array(String),
			distinct_labels UInt32,
			calls           UInt64,
			-- Latency per bucket (v0.5.118). sum_duration_ns lets
			-- the reader rebuild a window-wide avg = sum/calls;
			-- p99_ms is bucket-local approximate, the reader takes
			-- max(p99_ms) across buckets which is a conservative
			-- (slightly pessimistic) merge — acceptable given the
			-- "spot the slow strand" use case.
			sum_duration_ns UInt64 DEFAULT 0,
			p99_ms          Float64 DEFAULT 0,
			-- v0.5.367 — per-edge error count so GetServiceGraph
			-- can read from the MV instead of self-joining
			-- raw spans at every request.
			errors          UInt64 DEFAULT 0,
			-- v0.5.410 — display-only environment annotation
			-- (deployment.environment / service.namespace /
			-- k8s.namespace.name resolved at aggregation time).
			-- NOT part of ORDER BY by design — keeping it out of
			-- the dedup key means existing installs ALTER cleanly;
			-- multi-env-in-single-CH operators who need strict
			-- separation can rebuild the table. Default '' so old
			-- rows stay valid.
			parent_env      LowCardinality(String) DEFAULT '',
			child_env       LowCardinality(String) DEFAULT '',
			-- v0.9.1025 — messaging cluster of a QUEUE node, so the
			-- topology→/messaging bridge can open the drawer directly
			-- instead of the narrowed catalogue (v0.9.972). Written by
			-- the two passes that emit queue nodes (infra/producer +
			-- async consumer); every other edge keeps DEFAULT ''.
			--
			-- NOT in ORDER BY, and — the load-bearing half — NOT in the
			-- writers' GROUP BY either. Adding it to GROUP BY would make
			-- ONE aggregation run emit two rows that differ only outside
			-- the dedup key, and ReplacingMergeTree would then DELETE one
			-- of them on the FINAL read: calls silently lost. As an
			-- any()-picked annotation the counts stay exact and only the
			-- LABEL is arbitrary when one topic name lives on two
			-- clusters. Measured on the live local cluster before
			-- shipping: 555 producer queue nodes over 3h, max distinct
			-- clusters per node = 1, zero collisions. Strict per-cluster
			-- separation needs an ORDER BY redesign (new table +
			-- backfill + swap) — deliberately deferred.
			cluster         LowCardinality(String) DEFAULT '',
			version         UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toDate(time_bucket)
		ORDER BY (time_bucket, parent_service, child_node, node_kind, protocol)
		TTL toDate(time_bucket) + INTERVAL 14 DAY`,

		// Op-level edges per 5-min bucket. Powers the operation
		// deep-dive view. Higher row cardinality than the service-
		// level table (every distinct op pair) but still bounded
		// because ops are LowCardinality in practice (HTTP routes,
		// gRPC methods). Same aggregator goroutine fills it.
		// service_callers_5m (v0.5.368) — per-(receiver_service,
		// caller pod / client IP / UA) RED rollup. Powers the
		// /service/backtrace "who is hammering me" panel. Same
		// 5-min bucketing as topology_edges_5m; same
		// ReplacingMergeTree(version) so re-aggregation across
		// the topology batch correlator's retries dedups
		// naturally on the FINAL read.
		//
		// Ordering choice rationale at scale:
		// service first → FINAL reads on the most common path
		//   (/api/backtrace/{name}) hit a tight index prefix.
		// caller_service, caller_host, caller_instance follow
		//   from least-card to medium-card so each subsequent
		//   key narrows the partition slice further.
		// client_address last → highest cardinality, sorted at
		//   the leaf so its variance doesn't bloat upstream
		//   index granules.
		`CREATE TABLE IF NOT EXISTS service_callers_5m (
			time_bucket      DateTime CODEC(DoubleDelta, ZSTD(3)),
			service          LowCardinality(String),
			caller_service   LowCardinality(String),
			caller_host      LowCardinality(String),
			caller_instance  String,
			client_address   String,
			user_agent       String,
			calls            UInt64,
			errors           UInt64,
			sum_duration_ns  UInt64,
			-- Per-bucket quantiles. The reader takes max()
			-- across buckets — a conservative (slightly
			-- pessimistic) merge that's the right semantic for
			-- a "where is my SLO breached" view.
			p50_ms           Float64,
			p95_ms           Float64,
			p99_ms           Float64,
			last_seen_ns     UInt64,
			version          UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toDate(time_bucket)
		ORDER BY (time_bucket, service, caller_service,
		         caller_host, caller_instance,
		         client_address, user_agent)
		TTL toDate(time_bucket) + INTERVAL 14 DAY`,

		`CREATE TABLE IF NOT EXISTS topology_op_edges_5m (
			time_bucket     DateTime CODEC(DoubleDelta, ZSTD(3)),
			parent_service  LowCardinality(String),
			parent_op       String,
			child_service   LowCardinality(String),
			child_op        String,
			calls           UInt64,
			version         UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toDate(time_bucket)
		ORDER BY (time_bucket, parent_service, parent_op, child_service, child_op)
		TTL toDate(time_bucket) + INTERVAL 14 DAY`,

		// Business-flow rollup (v0.5.112). One row per 5-min
		// bucket per (root_service, root_op) — i.e. one entry per
		// entry-point per slice. Drives the /topology Flows view.
		// services is the unique set the flow's traces touched in
		// that bucket; merged at read time across buckets.
		`CREATE TABLE IF NOT EXISTS topology_root_flows_5m (
			time_bucket   DateTime CODEC(DoubleDelta, ZSTD(3)),
			root_service  LowCardinality(String),
			root_op       String,
			trace_count   UInt64,
			services      Array(String),
			version       UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toDate(time_bucket)
		ORDER BY (time_bucket, root_service, root_op)
		TTL toDate(time_bucket) + INTERVAL 14 DAY`,
		// v0.8.240 — community-feedback özelliği KALDIRILDI (operatör
		// isteği). `feedbacks` tablosunun (v0.8.106) düşürülmesi artık
		// BURADA satır içi bir dize DEĞİL: removed_tables.go defterinden
		// üretiliyor ve küme kipinde ON CLUSTER + SYNC koşuyor
		// (v0.10.846). Satır içi hâli ON CLUSTER taşımıyordu ve adaptDDL
		// DROP'u yeniden yazmaz — kaldırma yalnız koordinatör host'ta
		// koşmuş, prod'da bir shard temizlenip öteki shard'da tablo
		// kalmıştı; kart bunu "eksik replika" diye raporluyordu.
		// v0.9.1301 — BU BEŞ CREATE TABLE `alters` LİSTESİNDEYDİ, buraya
		// TAŞINDI. DDL metni AYNEN korundu; değişen tek şey hangi dilimde
		// durdukları.
		//
		// Gerekçe: `alters` planAlterDDL'den geçer ve o eleyici YALNIZ
		// `ALTER TABLE … ADD COLUMN IF NOT EXISTS` kalıbına bakar
		// (addColumnRe, ddl_skip_existing.go). Bir CREATE TABLE o regex'e
		// uymadığı için ELENMİYORDU — tablo aylardır yerinde olsa bile her
		// boot'ta gönderiliyordu. `tables` ise planDeclarativeDDL'den geçer
		// ve o eleyici tam olarak `CREATE … IF NOT EXISTS <ad>` kalıbını
		// tanır (ddlObjectRe): nesne varsa ifade HİÇ gönderilmez.
		//
		// Ödenen bedel tıkalı dağıtık DDL kuyruğunda 5 × ddlTaskTimeoutSeconds
		// ≈ 100 sn — sonucu tanım gereği no-op olan beş kuyruk turu.
		//
		// SIRA GÜVENLİ: `tables` dilimi `alters`'tan ÖNCE koşuyor, yani
		// runbooks CREATE'i kendi iki ADD COLUMN'undan (alters'ta kaldılar)
		// hâlâ önce gidiyor. Beşi de highVolumeTables'ta DEĞİL, dolayısıyla
		// adaptDDL'in `_local` + Distributed sarmalayıcı kolu onlara zaten
		// uygulanmıyordu ve taşıma bunu değiştirmiyor (adaptDDL SQL metnine
		// bakar, ifadenin hangi dilimden geldiğine değil).
		// v0.5.244 — Drain-extracted log templates ledger. Puller
		// goroutine pulls a sample of recent logs every 5min,
		// runs them through the Drain-3 templater, upserts the
		// resulting templates here. first_seen is sticky (the
		// upsert path reads + preserves the earliest value)
		// so the "new template since X" signal stays meaningful
		// across restarts.
		`CREATE TABLE IF NOT EXISTS log_templates (
			id             String,
			template       String,
			first_seen     DateTime64(9),
			last_seen      DateTime64(9),
			total_count    UInt64,
			services       Array(LowCardinality(String)),
			exception_type LowCardinality(String) DEFAULT '',
			sample         String,
			version        UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// v0.5.476 — operator events. Manual time markers
		// ("deploy v1.2.3", "feature flag X rollout", "incident
		// #5 started") that surface as vertical lines on every
		// time-series chart in Coremetry. Datadog Events /
		// Honeycomb Markers / Grafana Annotations are the
		// reference primitives — operators have built mental
		// models around having these everywhere, and the gap
		// shows up most during incident retros ("what was
		// happening 4 min before the spike?").
		//
		// ORDER BY (time, id) so /api/events?from=X&to=Y prunes
		// down to the window via the primary index instead of
		// scanning all events. Service is LowCardinality since
		// most events scope to one service (or empty = global).
		`CREATE TABLE IF NOT EXISTS events (
			id          String,
			kind        LowCardinality(String),  -- deploy | config | incident | maintenance | custom
			label       String,                   -- short operator-typed title
			time        DateTime64(9),            -- when the event happened (operator-supplied)
			service     LowCardinality(String) DEFAULT '',
			link        String DEFAULT '',        -- optional URL (PR, ticket, runbook)
			owner       String,                   -- creator email
			created_at  DateTime64(9) DEFAULT now64(9),
			version     UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY (time, id)`,

		// v0.7.0 — Runbooks: operator-authored, executable operational
		// procedures (OneUptime model). DEDICATED table, NOT saved_views:
		// a runbook is a first-class SHARED operational entity (same class
		// as alert_rules / problems — invariant #4), with its own
		// lifecycle, executions that reference it, and audit coverage — it
		// is not a per-user VIEW/preset (which is what saved_views /
		// invariant #5 covers). steps are an ordered JSON blob (no per-step
		// rows, mirrors OneUptime). See docs/runbooks-agent-design.md.
		`CREATE TABLE IF NOT EXISTS runbooks (
			id          String,
			title       String,
			description String        DEFAULT '',     -- markdown (the "knowledge")
			steps_json  String        DEFAULT '[]',   -- ordered []RunbookStep, marshaled
			enabled     UInt8         DEFAULT 1,
			labels      Array(LowCardinality(String)),
			created_by  String        DEFAULT '',     -- creator email
			notify_on_complete UInt8   DEFAULT 0,     -- v0.7.7 — fire a completion notification
			notify_channels Array(LowCardinality(String)),  -- v0.7.22 — which channel TYPES (empty = email)
			created_at  DateTime64(9) DEFAULT now64(9),
			updated_at  DateTime64(9) DEFAULT now64(9),
			version     UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY id`,

		// v0.7.0 — Runbook executions: one tracked RUN of a runbook (the
		// audit record of "who ran what when, which steps executed"). Steps
		// are SNAPSHOTTED onto the execution at start (step_states_json) so
		// editing/deleting the template never rewrites a historical run —
		// audit integrity, and removes the need for a runbook version table.
		// Low-volume long-retention (operator runs), so PARTITION BY month
		// (not day) per /clickhouse-schema; no TTL — executions are the
		// audit trail. completed_at uses an epoch-0 sentinel (not Nullable)
		// per the no-Nullable rule; 0 = not yet completed.
		`CREATE TABLE IF NOT EXISTS runbook_executions (
			id               String,
			runbook_id       String,
			title_snapshot   String,
			status           LowCardinality(String),   -- running|waiting_for_user|completed|failed|cancelled
			started_by       String        DEFAULT '',
			started_at       DateTime64(9),
			completed_at     DateTime64(9) DEFAULT toDateTime64(0, 9),  -- 0 = not completed
			problem_id       String        DEFAULT '',
			step_states_json String        DEFAULT '[]',  -- snapshot of steps + live per-step state
			updated_at       DateTime64(9) DEFAULT now64(9),
			version          UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toYYYYMM(started_at)
		ORDER BY id`,

		// v0.8.241 — notification dispatch history. Append-only audit
		// trail of every channel send (email / slack / teams / zoom /
		// webhook / whatsapp) fanned out by internal/notify — success
		// AND failure. The row is IMMUTABLE (a send happened at an
		// instant), so this is a PLAIN MergeTree, NOT ReplacingMergeTree:
		// there is no state to dedup and reads never need FINAL. Powers
		// the /events "Notifications sent" surface so an operator can
		// answer "did the 03:00 page actually go out, and to whom?"
		// without SSHing into the box.
		//
		// target is stored PRE-MASKED by the notifier (email local-part
		// shortened, webhook URL reduced to host) — the log is an
		// operational record, not a recipient directory.
		//
		// Low-volume long-retention → PARTITION BY month (day would make
		// near-empty partitions). ORDER BY (sent_at, id) so the
		// time-bounded /api/notifications/log read prunes via the
		// primary index. 90-day day-granularity TTL is partition-aligned
		// (toDate wrap on a DAY interval — the correct form per the
		// v0.6.36 unit-mixing rule; NEVER wrap a sub-day calc).
		`CREATE TABLE IF NOT EXISTS notification_log (
			id            String,
			sent_at       DateTime64(9) DEFAULT now64(9),
			channel_kind  LowCardinality(String),           -- email|slack|mattermost|teams|zoomchat|webhook|whatsapp
			channel_name  String,
			target        String,                            -- MASKED recipient / webhook host
			subject       String        DEFAULT '',
			body_preview  String        DEFAULT '',          -- first ~200 chars of the body
			related_kind  LowCardinality(String) DEFAULT '', -- problem|incident|alert|monitor|test|runbook
			related_id    String        DEFAULT '',
			ok            UInt8         DEFAULT 0,
			error         String        DEFAULT ''
		) ENGINE = MergeTree()
		PARTITION BY toYYYYMM(sent_at)
		ORDER BY (sent_at, id)
		TTL toDate(sent_at) + INTERVAL 90 DAY`,
		// ── v0.10.127 — K8s ENTITY KATMANI (docs/plans/entity-layer-design-2026-08-28.md §2) ──
		//
		// Üç state tablosu. ORDER BY = dedup anahtarı; ömür ayrımı
		// valid_from'da (aynı pod adı yeniden kullanılınca YENİ satır, eski
		// ömür valid_to ile kapanır). PARTITION BY BİLİNÇLİ YOK (Kural P1:
		// last_seen her tazelemede yeniden yazılır — partition'da olsaydı
		// FINAL kopyaları asla temizleyemezdi; ai_feedback/rca_verdicts
		// emsali). entity_id hiçbir shard/önbellek anahtarına girmez —
		// state tablosu, tek replikasyon grubu (v0.9.1308). Etiketler
		// allow-list'li Array çifti (hassas etiket taşınmaz).
		`CREATE TABLE IF NOT EXISTS entities (
			entity_type  LowCardinality(String),
			cluster_id   LowCardinality(String),
			entity_id    String,
			valid_from   DateTime,
			valid_to     DateTime DEFAULT 0,
			namespace    LowCardinality(String) DEFAULT '',
			name         String,
			uid          String DEFAULT '',
			parent_id    String DEFAULT '',
			label_keys   Array(LowCardinality(String)),
			label_values Array(String),
			source       LowCardinality(String),
			first_seen   DateTime,
			last_seen    DateTime,
			stale        UInt8 DEFAULT 0,
			version      UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY (entity_type, cluster_id, entity_id, valid_from)
		TTL last_seen + INTERVAL 180 DAY`,
		// rel_type: parent (cluster→node, cluster→ns, ns→wl, wl→pod, pod→ctr)
		// | runs_on (pod→node) | runs (pod→service). Ters yön nokta araması
		// child_id üzerinde bloom (idx_child).
		`CREATE TABLE IF NOT EXISTS entity_relations (
			rel_type   LowCardinality(String),
			cluster_id LowCardinality(String),
			parent_id  String,
			child_id   String,
			valid_from DateTime,
			valid_to   DateTime DEFAULT 0,
			last_seen  DateTime,
			source     LowCardinality(String),
			version    UInt64 DEFAULT toUnixTimestamp64Nano(now64(9)),
			INDEX idx_child child_id TYPE bloom_filter(0.01) GRANULARITY 4
		) ENGINE = ReplacingMergeTree(version)
		ORDER BY (rel_type, cluster_id, parent_id, child_id, valid_from)
		TTL last_seen + INTERVAL 180 DAY`,
		// Sync koşu kaydı: kısmi başarı + eşlenemeyen cluster değeri
		// sayaçları. started_at yeniden yazılmaz → partition P1-güvenli.
		`CREATE TABLE IF NOT EXISTS entity_sync_runs (
			cluster_id        LowCardinality(String),
			started_at        DateTime,
			finished_at       DateTime,
			status            LowCardinality(String),
			entities_written  UInt32 DEFAULT 0,
			relations_written UInt32 DEFAULT 0,
			closed            UInt32 DEFAULT 0,
			unmapped_keys     Array(String),
			unmapped_counts   Array(UInt32),
			thanos_ms         UInt32 DEFAULT 0,
			ch_ms             UInt32 DEFAULT 0,
			error             String DEFAULT '',
			version           UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toYYYYMM(started_at)
		ORDER BY (cluster_id, started_at)
		TTL started_at + INTERVAL 30 DAY`,

		// v0.10.767 — ingest_ledger (trace bütünlüğü Faz B): ingest podlarının
		// DAKİKALIK sayaç deltaları (spans consumer accepted/dropped/
		// write_failed). Sayaçlar pod-içi, kümülatif, restart'ta sıfır; bu
		// yüzden delta + boot_id yazılır, filo toplamı okuma anında alınır ve
		// Trace hattı sağlığı CH'de saklanan span sayısıyla mutabakat eder.
		// Kural P1: bucket ORDER BY'da → partition sürüklenmesi yok. Distributed
		// sarmalayıcı YOK (state sınıfı; küme kipinde birleşik grup). Yazıcı ve
		// okuyucu ingest_ledger.go (pod başına, lider kilidi yok).
		`CREATE TABLE IF NOT EXISTS ingest_ledger (
			signal         LowCardinality(String),
			pod            LowCardinality(String),
			bucket         DateTime,
			boot_id        String,
			accepted       UInt64 DEFAULT 0,
			dropped        UInt64 DEFAULT 0,
			write_failed   UInt64 DEFAULT 0,
			accepted_total UInt64 DEFAULT 0,
			version        UInt64 DEFAULT toUnixTimestamp64Nano(now64(9))
		) ENGINE = ReplacingMergeTree(version)
		PARTITION BY toYYYYMM(bucket)
		ORDER BY (signal, pod, bucket)
		TTL bucket + INTERVAL 30 DAY`,
	}
	return tables
}

func (s *Store) migrate(ctx context.Context) error {
	sd, ld, md := s.ret.SpansDays, s.ret.LogsDays, s.ret.MetricsDays
	if sd == 0 {
		sd = 30
	}
	if ld == 0 {
		ld = 30
	}
	if md == 0 {
		md = 7
	}

	tables := canonicalTables(sd, ld, md)

	// v0.10.829 — kanonik tablo kataloğu, boot sonrası da erişilebilir.
	// "İlk replikayı kur" sihirbazı (replica_repair.go) bir tablonun ZK
	// yolu sözleşmesini UYDURMAZ: katalogdaki CREATE'i adaptDDL'den
	// geçirir ve motor argümanlarını ORADAN okur. Katalogda olmayan ad
	// engeldir. Dilim burada yazılır, sonra yalnız OKUNUR (aynı sözleşme:
	// deferDDL/stateObs — tek boot goroutine'i yazar).
	s.canonicalTableDDL = tables

	// v0.9.1308 — state tablolarının ZK yolu KODDAN değil KÜMEDEN
	// okunur (state_replication.go). Bu boot'un İLK DDL'inden ÖNCE
	// koşmak ZORUNDA: hemen aşağıdaki repartition da bir state
	// tablosunu (root_cause_hypotheses) execDDL→adaptDDL üzerinden
	// yeniden kurar ve ona bir ZK yolu yazar.
	s.resolveStateReplicaPaths(ctx)

	// v0.9.1304 — root_cause_hypotheses'in PARTITION BY'sız yeniden kurulumu
	// (Kural P1; gerekçe rootcause_repartition.go). Anlık görüntüden ÖNCE ve
	// deferDDL kararından ÖNCE: müdahale SENKRON koşmalı, ve `existing`
	// bundan sonra okunduğu için sonuç ne olursa olsun tutarlı kalır.
	s.repartitionRootCauseHypotheses(ctx, tableDDLByName(tables, "root_cause_hypotheses"))

	// v0.9.1335 — problems + anomaly_events SALT OKUNUR teşhisi. Bu iki
	// tablo geri getirilemez operatör durumu taşıyor, o yüzden yukarıdaki
	// gibi yeniden KURULMAZLAR; göç migrations/0010 ile operatörde. Boot
	// yalnız eski şemayı görürse söyler (state_repartition.go).
	s.warnStatePartitionDrift(ctx)

	// v0.9.607 — ZATEN VAR OLAN nesne için DDL GÖNDERİLMEZ.
	//
	// Hepsi `IF NOT EXISTS`, yani nesne varsa ifadenin etkisi ZATEN
	// yok. Ödenen tek şey, sonucu baştan belli olan bir dağıtık DDL
	// kuyruğu turu — ve tıkalı bir kuyrukta o tur bütçesini (20 sn)
	// doluyor. 158 ifade × 20 sn ≈ 53 dakika: pod ölmüyor ama hiç
	// hazır olmuyor (operator-reported, prod).
	//
	// Taze kurulumda hiçbir şey elenmez; davranış birebir aynı kalır.
	existing := s.existingObjects(ctx)
	// v0.9.614 — şema yerindeyse (küme modu + spans mevcut) kalan TÜM
	// DDL arka plana ertelenir; boot hiçbir kuyruk turunu beklemez.
	// Taze kurulumda ve tek düğümde davranış birebir eski (senkron).
	if deferMigrationDDL(s.clusterMode(), existing["spans"]) {
		s.deferDDL = true
		log.Printf("[chstore] şema yerinde — kalan DDL arka plana ertelenecek, boot beklemeyecek")
	}
	// v0.9.1302 — eleme DİLİMDEN BAĞIMSIZ. Bu dilim CREATE'lerin yanında
	// yedi `ALTER TABLE … ADD COLUMN IF NOT EXISTS` de taşıyor ve onlar
	// v0.9.1301'e kadar HİÇ elenmiyordu (planDeclarativeDDL yalnız CREATE
	// kalıbına bakıyordu). Artık ikisi de planDDL'den geçiyor.
	//
	// Kolon kümesi BURADA okunuyor — yani bu dilimin kendi CREATE'lerinden
	// ÖNCE. Taze kurulumda küme boş olur, hiçbir ALTER elenmez ve davranış
	// birebir eski kalır; yükseltmede kolon zaten yerinde olduğu için
	// eleme ısırır. Bayatlık yalnız "fazladan bir no-op gönder" yönünde
	// hata yapabilir, "gerekeni atla" yönünde değil.
	plan, skippedObjects, skippedColumns := planDDL(tables, existing, s.existingColumns(ctx))
	logDDLPlan("tables", len(tables), skippedObjects, skippedColumns)
	for _, q := range plan {
		if err := s.execDDL(ctx, q); err != nil {
			return fmt.Errorf("create table: %w", err)
		}
	}

	// v0.10.846 — ÜRÜNÜN KALDIRDIĞI tabloların temizliği (removed_tables.go).
	// `tables` diliminden SONRA: kaldırma yaratmanın tersidir, sıra okunur
	// kalsın. `alters` diliminin anlık görüntüsünden ÖNCE: o plan kendi
	// system.tables/system.columns okumasını aşağıda TAZE yapıyor, yani
	// burada düşen bir nesne bayat bir "zaten var" kaydıyla elenemez
	// (store.go'daki "İKİ ANLIK GÖRÜNTÜ DE BURADA TAZE OKUNUYOR" sözleşmesi).
	//
	// HATA DÖNDÜRMEZ: temizlik bir onarım değil; okuyucusu olmayan bir
	// kalıntının kalması boot'u düşürmeyi hak etmiyor (erteleme KAPALI
	// kipte — taze kurulum / RESET_SCHEMA — düşürürdü). Yüksek sesle
	// loglanır, bir sonraki boot yeniden dener.
	s.dropRemovedTables(ctx)

	// In-place column additions for upgrades. ADD COLUMN IF NOT EXISTS is a
	// no-op on fresh installs (column already in CREATE TABLE) and on
	// already-migrated databases.
	//
	// Skip indexes on the spans hot path. The (service_name, time)
	// primary key already drives most queries, but the transport-aware
	// alert metrics filter on `kind`, `db_system`, and `http_status`
	// in additional WHERE predicates. Adding granule-level skip
	// indexes lets ClickHouse drop unrelated 8k-row blocks before
	// reading them — meaningful at 1B spans/day where each daily
	// partition holds ~150k granules.
	//   - idx_kind / idx_db_system: set(0) → bitmap of distinct values
	//     per granule. Filter `kind='server'` or `db_system != ''`
	//     skips most internal-only granules instantly.
	//   - idx_http_status: minmax → granule's status range. Filter
	//     `http_status >= 500` skips granules of pure 200s (the
	//     overwhelming majority).
	// New data benefits immediately; existing data isn't rewritten
	// (MATERIALIZE INDEX is too heavy on a 36B-row table) but ages
	// out via TTL inside the retention window.
	alters := []string{
		// v0.8.x — cluster promoted from a read-time res_values/attr_values
		// array scan (clusterDeriveExpr, the 6-key coalesce) to a MATERIALIZED
		// column so /endpoints + topology cluster filters/derivations hit an
		// indexed LowCardinality col instead of indexOf() over the attr arrays.
		// Forward-only: fills NEW parts at insert; old parts read '' and the
		// callers fall back to clusterDeriveExpr via clusterColExpr (no backfill
		// MATERIALIZE mutation — that would stress the RAM-bound CH). The column
		// references the SAME const as the fallback so new/old parts never drift.
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS cluster LowCardinality(String) MATERIALIZED ` + clusterDeriveExpr,
		// NOTE: the op_group ALTER (an EXPLICIT Go-written column on the
		// INGEST path) is NOT in this list — it is gated separately below
		// (see opGroupAlter) because on an external Distributed install
		// with cfg.ClusterName unset the ALTER lands on the wrapper only,
		// never on spans_local, and the next INSERT then loses every span
		// batch with code 16 (v0.8.186). Materialized columns like
		// `cluster` are safe to leave here: they aren't bound in the INSERT
		// column list, so a wrapper/local mismatch can't break ingest.
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS auth_provider LowCardinality(String) DEFAULT 'local'`,
		// team — operator-curated grouping (e.g. "platform-sre",
		// "fraud", "payments"). LowCardinality because each
		// install has tens to low-hundreds of teams; values
		// repeat heavily across the user list.
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS team LowCardinality(String) DEFAULT ''`,
		// custom_role — optional pointer into the operator-defined
		// custom role catalog (system_settings key "custom_roles").
		// Only meaningful when the base role is viewer; the custom
		// role's `pages` list further restricts which sidebar
		// entries the user sees. Empty = use base role unrestricted.
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS custom_role LowCardinality(String) DEFAULT ''`,
		// v0.8.238 — LDAP profile photo (thumbnailPhoto/jpegPhoto bytes,
		// ≤512 KB, refreshed each login). CH String is binary-safe; ZSTD
		// because JPEG headers still squeeze a little and the column is
		// cold (read only by the photo endpoints).
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS photo String DEFAULT '' CODEC(ZSTD(3))`,
		// v0.8.266 — LDAP directory identity: full name (displayName)
		// + organization (company/o). department/ou lands in the
		// existing team column. Refreshed on each directory login.
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS full_name String DEFAULT ''`,
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS org LowCardinality(String) DEFAULT ''`,
		// v0.8.526 — LDAP group sync join key (see hasLdapUsernameCol). A
		// plain state-table ALTER: `users` is Coremetry-owned, never an
		// external Distributed wrapper, so execDDL→adaptDDL ON CLUSTER
		// reaches every replica (the op_group external-Distributed skip
		// branch is N/A here). The hasLdapUsernameCol probe below then
		// keeps the auth-critical INSERT column list honest regardless.
		`ALTER TABLE users ADD COLUMN IF NOT EXISTS ldap_username LowCardinality(String) DEFAULT ''`,
		// v0.5.254 — Problem AI auto-explain. The background
		// problemExplainer goroutine fills these for open critical
		// problems within ~30s of opening; the UI surfaces the
		// summary as an "AI insight" chip. Empty = no explanation
		// yet (or AI Copilot disabled).
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS ai_summary String DEFAULT ''`,
		// v0.9.403 — runtime pod problemlerinin pod kimliği yapısal alana
		// indi (401'in ID-parse köprüsünün emekliliği). Idempotent;
		// Coremetry-yönetimli cluster'da adaptDDL ON CLUSTER uygular.
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS pod String DEFAULT ''`,
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS ai_summary_at DateTime64(9) DEFAULT toDateTime64(0, 9)`,
		// v0.9.976 — ihlalin YÖNÜ (kuralın comparator'ı) problem satırına
		// iniyor: öncelik hesabındaki ters-çevirme kolu buna bakacak.
		// Idempotent, ORDER BY DIŞINDA (kimlik değil, GÖSTERİM/hesap alanı —
		// dedup anahtarı `id` olarak kalıyor), LowCardinality çünkü evren
		// dört dizgi. Eski satırlar DEFAULT '' okur = "ters çevirme yok".
		// `problems` Coremetry'nin kendi state tablosu (monitors/users/
		// alert_rules ile aynı şekil), dış Distributed wrapper değil —
		// adaptDDL küme kipinde ON CLUSTER'ı kendisi enjekte eder, spans
		// sınıfındaki _local tehlikesi yok. hasProblemCmpCol probe'u yine de
		// SELECT/INSERT listelerini dürüst tutuyor (v0.9.614 erteleme).
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS comparator LowCardinality(String) DEFAULT ''`,
		// v0.9.1338 (entity-model Faz 4b) — problemin ÖZNESİ hangi varlık
		// TÜRÜ. Bugüne dek `service` kolonu sorgusuz bir servis adı sayılıyordu
		// ve bu YANLIŞTI: db_capacity.go v0.9.402'den beri oraya bir receiver
		// INSTANCE adı (`corebank-scan.prod`) yazıyor, yani /inbox o satıra
		// hiçbir şeyle eşleşmeyen bir `/service?name=` linki kuruyordu.
		//
		// DEFAULT 'service' BİLİNÇLİ (boş sentinel DEĞİL): var olan 4800+
		// satır ve — küme kipinde kolonu EKLEYEN boot'un probe'u false
		// okuduğu için — o boot boyunca yazılan HER satır bugünkü anlamı
		// birebir korur. "Çözülmemiş dal bayt-bayt bugünküyle aynı" kırmızı
		// çizgisi tam olarak buradan geçiyor.
		//
		// ORDER BY DIŞINDA: dedup anahtarı `id` olarak KALIYOR (varlık
		// kimliği hiçbir ORDER BY / shard / cache anahtarına girmez —
		// entity-model §7.4 kırmızı çizgisi). LowCardinality çünkü evren iki
		// dizgi. `problems` Coremetry'nin kendi state tablosu, dış Distributed
		// wrapper değil — comparator ALTER'ıyla birebir aynı sınıf.
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS kind LowCardinality(String) DEFAULT 'service'`,
		// v0.9.415 — P1 exception gruplarına proaktif kök-sebep özeti
		// (ExceptionExplainer, problems ai_summary'nin exception ikizi).
		`ALTER TABLE exception_groups ADD COLUMN IF NOT EXISTS ai_summary String DEFAULT ''`,
		// v0.9.530 — özetin yazıldığı an. exception_groups Coremetry'nin
		// KENDİ state tablosu (ReplacingMergeTree, düşük hacim), spans gibi
		// dış Distributed değil — adaptDDL cluster deploy'unda ON CLUSTER'ı
		// kendisi enjekte eder, _local tehlikesi yok (monitors/users
		// ALTER'larıyla aynı şekil). problems.ai_summary_at ile birebir tip.
		`ALTER TABLE exception_groups ADD COLUMN IF NOT EXISTS ai_summary_at DateTime64(9) DEFAULT toDateTime64(0, 9)`,
		// v0.8.283 — synthetic monitor types beyond http+heartbeat: tcp,
		// ssl-cert, keyword. Additive columns on the existing monitors
		// state table (no new schema). `monitors` isn't a high-volume
		// table so adaptDDL only injects ON CLUSTER on a cluster deploy —
		// no spans-style _local hazard (same shape as the users ALTERs).
		`ALTER TABLE monitors ADD COLUMN IF NOT EXISTS target String DEFAULT ''`,
		`ALTER TABLE monitors ADD COLUMN IF NOT EXISTS cert_warn_days UInt16 DEFAULT 14`,
		`ALTER TABLE monitors ADD COLUMN IF NOT EXISTS keyword String DEFAULT ''`,
		`ALTER TABLE monitors ADD COLUMN IF NOT EXISTS keyword_invert UInt8 DEFAULT 0`,
		// ssl-cert records days-remaining here so the UI shows "37d left".
		`ALTER TABLE monitor_results ADD COLUMN IF NOT EXISTS detail Int64 DEFAULT 0 CODEC(T64, ZSTD(3))`,
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS runbook_url String DEFAULT ''`,
		// v0.5.126 sustained-breach gate. 0 = open immediately
		// (legacy behaviour). When > 0 the evaluator only opens a
		// problem after the threshold has been breached for this
		// many seconds in a row.
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS for_sec UInt32 DEFAULT 0`,
		// v0.5.128 sample-count floor. 0 = no floor. When > 0
		// the evaluator skips evaluation entirely if the window
		// saw fewer than N requests — kills percentile / error-
		// rate flapping on low-traffic services.
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS min_samples UInt32 DEFAULT 0`,
		// v0.5.129 post-resolution cooldown. 0 = re-open
		// immediately. When > 0 the evaluator suppresses re-
		// opens within N seconds of the last resolution —
		// kills threshold-jitter flapping at the boundary.
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS cooldown_sec UInt32 DEFAULT 0`,
		// v0.5.242 — saved-search log alerts. Empty for the
		// existing span-metric rules; populated for "operator-
		// defined KQL → rate-threshold" rules. Evaluator
		// switches paths based on len(log_query) > 0.
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS log_query String DEFAULT ''`,
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS target_json String DEFAULT ''`, // v0.10.331
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS notify_json String DEFAULT ''`, // v0.10.519
		// v0.9.x — ES Watcher birebir-JSON import (Faz-1). The verbatim
		// PUT _watcher/watch body; empty for native rules. The evaluator
		// switches to the watcher path on len(watcher_json) > 0, exactly
		// like the log_query switch above. alert_rules is a low-volume
		// state table (not in highVolumeTables) so adaptDDL injects
		// ON CLUSTER on distributed installs — no _local hazard, same
		// shape as the runbook_url/for_sec ALTERs. Plain String (free
		// JSON text — never LowCardinality).
		`ALTER TABLE alert_rules ADD COLUMN IF NOT EXISTS watcher_json String DEFAULT ''`,
		// v0.9.1301 — `runbooks` CREATE TABLE buradan `tables` dilimine
		// taşındı (eleme gerekçesi orada). Bu iki ADD COLUMN burada KALIYOR:
		// planAlterDDL onları zaten eliyor.
		//
		// v0.7.7 — runbook completion notifications: existing installs backfill.
		`ALTER TABLE runbooks ADD COLUMN IF NOT EXISTS notify_on_complete UInt8 DEFAULT 0`,
		// v0.7.22 — per-runbook notification channel TYPES (empty = email only).
		`ALTER TABLE runbooks ADD COLUMN IF NOT EXISTS notify_channels Array(LowCardinality(String))`,

		// v0.9.1301 — `runbook_executions` + `notification_log` CREATE
		// TABLE'ları `tables` dilimine taşındı (gerekçe orada).

		// v0.5.209 — triage assignee. Populated from service
		// metadata's owner_team when the problem opens, then
		// overridable by an operator claim via PATCH
		// /api/problems/{id}/assignee. Empty = unassigned.
		`ALTER TABLE problems ADD COLUMN IF NOT EXISTS assignee String DEFAULT ''`,
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS sre_team String DEFAULT ''`,
		// chat_channel — successor to slack_channel. Existing
		// rows with a populated slack_channel keep showing it
		// in the UI through the read-time fallback in
		// GetServiceMetadata; new edits write to chat_channel.
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS chat_channel String DEFAULT ''`,
		// custom_links — operator-bolted-on links per service
		// (Grafana board, Kibana saved search, internal SRE
		// app, status page, etc.). Stored as a JSON array so
		// the schema doesn't grow per surface.
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS custom_links String DEFAULT '[]'`,
		// *_team_auto (v0.8.100) — the span-attr team-deriver's last write per
		// field, so a team rename in the attrs propagates while manual edits
		// (value != auto) stay pinned.
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS owner_team_auto String DEFAULT ''`,
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS sre_team_auto String DEFAULT ''`,
		// namespace (+ deriver provenance) — v0.8.436, flow-graph
		// namespace grouping's backend precondition. Derived from
		// service.namespace / k8s.namespace.name span resource attrs by
		// the same scheduler tick as the team deriver; human edits pin
		// exactly like owner/sre teams (value != auto).
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS namespace String DEFAULT ''`,
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS namespace_auto String DEFAULT ''`,
		// deployment (+ deriver provenance) — v0.9.25, deployment audit
		// S3: Servis→Cluster pivotunun iş-yükü hassasiyeti. Span
		// resource attr k8s.deployment.name'den namespace deriver'ının
		// tick'iyle türetilir; human edit aynı auto-sözleşmeyle pinler.
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS deployment String DEFAULT ''`,
		`ALTER TABLE service_metadata ADD COLUMN IF NOT EXISTS deployment_auto String DEFAULT ''`,
		// Notification routing — one column carrying a JSON
		// blob with predicates: { "services": [...],
		// "sreTeams": [...], "ownerTeams": [...] }. Empty /
		// {} = catch-all. Same shape regardless of channel
		// type so an admin can target any of email / slack /
		// teams / zoomchat / webhook to a specific team.
		`ALTER TABLE notification_channels ADD COLUMN IF NOT EXISTS match_rules String DEFAULT '{}'`,
		// source_hash (v0.9.174) — RAG doküman dedup/senkron hash'i. Wiki-crawler
		// v2 için ragChunksDDL'e sonradan eklendi ama eski kurulumların rag_chunks
		// tablosu onsuz oluşturulmuştu (CREATE TABLE IF NOT EXISTS mevcut tabloyu
		// ALTER etmez) → ReplaceDocumentChunks'ın INSERT'i (source_hash bound)
		// external kurulumda code-16 "No such column source_hash" ile 500 dönüyordu
		// (operatör-bildirimi: düz .txt upload + "Doküman listesi yüklenemedi").
		// rag_chunks hv-değil (wrapper/_local ayrımı YOK) → execDDL→adaptDDL yalnız
		// ON CLUSTER enjekte eder; INSERT-bound kolon güvenli çünkü op_group'un
		// wrapper-only tehlikesi (v0.8.186) burada geçerli değil. DEFAULT '' eski
		// satırları doldurur.
		`ALTER TABLE rag_chunks ADD COLUMN IF NOT EXISTS source_hash String DEFAULT ''`,
		// Spans columns needed by v0.5.102+ topology queries. Older
		// installs whose spans table was created before these
		// fields existed in CREATE TABLE would otherwise return
		// "Missing column" on the service-level topology join. All
		// default to '' so existing rows behave as if the field is
		// unset — same as ingestion paths that don't populate them.
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS kind         LowCardinality(String) DEFAULT 'internal'`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS peer_service LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS msg_system   LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS rpc_system   LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS rpc_method   LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS http_method  LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS http_route   LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS db_system    LowCardinality(String) DEFAULT ''`,
		// v0.5.118 latency overlay — backfill columns onto installs
		// whose topology_edges_5m predates them. ReplacingMergeTree
		// keeps the schema additive-safe.
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS sum_duration_ns UInt64  DEFAULT 0`,
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS p99_ms          Float64 DEFAULT 0`,
		// v0.5.367 — per-edge error counts so GetServiceGraph can
		// quit the raw-spans self-join and serve from the MV. The
		// writer's GROUP BY shape stays the same; we just add a
		// countIf alongside count(). Existing rows default to 0
		// (acceptable — old buckets show 0 errors until they age
		// out via the 14-day TTL).
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS errors UInt64 DEFAULT 0`,
		// v0.5.410 — multi-key service identity (display-only).
		// Forward-compat add: env columns default '' so rows from
		// older versions remain valid. ORDER BY untouched — strict
		// per-env dedup would require a full table rebuild and is
		// deferred until operator demand justifies the migration.
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS parent_env LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS child_env  LowCardinality(String) DEFAULT ''`,
		// v0.9.1025 — queue-node messaging cluster (see the CREATE above
		// for why it is outside ORDER BY *and* outside the writers'
		// GROUP BY). Distributed-safe by construction: topology_edges_5m
		// is registered in highVolumeTables, so adaptDDL rewrites this to
		// `topology_edges_5m_local ON CLUSTER` AND re-emits it against the
		// Distributed wrapper (cluster.go step 4, v0.5.362) — without that
		// second fragment the wrapper keeps its old column list and every
		// read of `cluster` fails with "no such column".
		`ALTER TABLE topology_edges_5m ADD COLUMN IF NOT EXISTS cluster    LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE spans ADD INDEX IF NOT EXISTS idx_kind        kind        TYPE set(0)    GRANULARITY 4`,
		`ALTER TABLE spans ADD INDEX IF NOT EXISTS idx_db_system   db_system   TYPE set(0)    GRANULARITY 4`,
		`ALTER TABLE spans ADD INDEX IF NOT EXISTS idx_http_status http_status TYPE minmax    GRANULARITY 4`,
		// idx_status powers the per-operation error-anomaly
		// detector (anomaly/trace_ops.go) — countIf(status_code='error')
		// over a 5-min window otherwise touches every granule
		// in the slice. status_code is LowCardinality with 3
		// values (ok / error / unset) so a set(0) index is
		// near-zero overhead and lets CH skip granules whose
		// status set doesn't include 'error'.
		`ALTER TABLE spans ADD INDEX IF NOT EXISTS idx_status      status_code TYPE set(0)    GRANULARITY 4`,
		// v0.8.348 — pivot Phase 1c: the trace→log pivot
		// (/api/logs?traceId=, Trace Logs tab) filters `WHERE
		// trace_id = ?`, but the logs ORDER BY is (service_name,
		// severity_num, time) and the only skip index was idx_body —
		// a bare trace-id lookup scanned every granule in the window.
		// Same bloom_filter shape as spans.idx_trace. NEW PARTS ONLY:
		// existing parts aren't rewritten (no MATERIALIZE INDEX — too
		// heavy at billion-log scale); old data ages out via TTL. On
		// an external Distributed `logs` with cluster_name unset this
		// ALTER returns CH error 48 and the isClusterUnsupportedAlter
		// branch below logs + skips it — a pure query-time
		// optimisation, never a correctness dependency (same gating
		// as the spans skip indexes above).
		`ALTER TABLE logs ADD INDEX IF NOT EXISTS idx_logs_trace trace_id TYPE bloom_filter(0.01) GRANULARITY 4`,
		// v0.8.214 — ZSTD(3) on the free-text columns that lacked an explicit
		// codec. attr_values alone is ~25% of the spans table at only ~5.9x with
		// the default LZ4; ZSTD(3) pushes free text to ~8-11x. db_statement (SQL)
		// and events (JSON) compress especially well under ZSTD. Forward-only —
		// MODIFY COLUMN codec is metadata-only (no rewrite of existing parts), so
		// it's cheap + safe; new parts get the better ratio. Idempotent (re-applying
		// the same codec is a no-op). Distributed-safe: execDDL→adaptDDL emits the
		// MODIFY to spans_local ON CLUSTER + the Distributed wrapper (CH accepts a
		// codec on the wrapper harmlessly — verified on 24.8).
		`ALTER TABLE spans MODIFY COLUMN attr_values  Array(String) CODEC(ZSTD(3))`,
		`ALTER TABLE spans MODIFY COLUMN res_values   Array(String) CODEC(ZSTD(3))`,
		`ALTER TABLE spans MODIFY COLUMN db_statement String DEFAULT '' CODEC(ZSTD(3))`,
		`ALTER TABLE spans MODIFY COLUMN status_msg   String DEFAULT '' CODEC(ZSTD(3))`,
		`ALTER TABLE spans MODIFY COLUMN events       String DEFAULT '[]' CODEC(ZSTD(3))`,
		// v0.10.381 (dış skill denetimi C7) — logs'un attr/res dizileri spans
		// ile aynı kodeğe: LZ4 varsayılanı kalmıştı. Aynı metadata-only,
		// idempotent, distributed-safe sınıf (LC'ye GEÇİRİLMEDİ: logs res
		// değerleri ölçülmedi, C3 kuralı).
		`ALTER TABLE logs MODIFY COLUMN attr_values Array(String) CODEC(ZSTD(3))`,
		`ALTER TABLE logs MODIFY COLUMN res_values  Array(String) CODEC(ZSTD(3))`,
		// v0.10.381 (dış skill denetimi C3) — metric_points ORDER BY
		// (service_name, metric, time); Hat-B okumaları service_name'i
		// opsiyonel bırakır (metricrate.go: WHERE metric = ? AND time …) ve
		// birincil indeks önek olmadan budamaz. `metric` granül içinde
		// yerel olarak kümelenmiş → set(0) neredeyse ideal. Yalnız yeni
		// part'lar; 7g retention'da bir haftada dolar.
		`ALTER TABLE metric_points ADD INDEX IF NOT EXISTS idx_mp_metric metric TYPE set(0) GRANULARITY 4`,
		// v0.10.381 (dış skill denetimi C2) — TTL partition sınırına hizalı
		// (toDate(time) günlük); ttl_only_drop_parts olmadan CH süresi dolan
		// part'ı düşürmeden önce TTL-merge ile yeniden yazıyordu (rollup
		// migration'ları 0001-0008 bunu zaten taşıyor). MODIFY SETTING
		// metadata-only, idempotent; Distributed sarmalayıcı reddederse
		// isClusterUnsupportedAlter yutar.
		`ALTER TABLE spans MODIFY SETTING ttl_only_drop_parts = 1`,
		`ALTER TABLE logs MODIFY SETTING ttl_only_drop_parts = 1`,
		`ALTER TABLE metric_points MODIFY SETTING ttl_only_drop_parts = 1`,
		// Apply the trace_snapshots TTL to installs that created
		// the table before v0.5.91. MODIFY TTL is metadata-only;
		// repeated applies are idempotent.
		`ALTER TABLE trace_snapshots MODIFY TTL toDateTime(expires_at) + INTERVAL 7 DAY`,
		// v0.8.252 — public trace shares carry a LOG SNAPSHOT taken at
		// share time ("o andaki" loglar): the public viewer renders
		// exactly what the sharer saw, without the anonymous route ever
		// querying the live logstore (no ES load, no drift after log
		// TTL). JSON array of log records, ≤500 lines, ZSTD'd.
		`ALTER TABLE trace_snapshots ADD COLUMN IF NOT EXISTS logs String DEFAULT '' CODEC(ZSTD(3))`,
		// Status page double opt-in (v0.5.158). Rows from the
		// public subscribe endpoint land with verified=0 and a
		// confirm_token; clicking the emailed link clears the
		// token and flips verified=1. Operator-curated rows
		// inserted via the admin UI bypass the flow (verified=1,
		// token=''). confirm_sent_at gates re-sends so a refresh-
		// spam attack can't drown a real subscriber in mail.
		`ALTER TABLE status_page_subscribers ADD COLUMN IF NOT EXISTS confirm_token String DEFAULT ''`,
		`ALTER TABLE status_page_subscribers ADD COLUMN IF NOT EXISTS confirm_sent_at DateTime64(9) DEFAULT toDateTime64(0, 9)`,
		// v0.6.56 — OTLP aggregation temporality on metric_points, so the
		// histogram read path can delta cumulative series before bucketing.
		// IF NOT EXISTS makes this a no-op on fresh installs (already in the
		// CREATE) and re-runs.
		`ALTER TABLE metric_points ADD COLUMN IF NOT EXISTS temporality LowCardinality(String) DEFAULT ''`,
		// v0.8.399 — feedback correlation key on ai_calls: the chat
		// handler mints an exchange_id per answer and the thumbs
		// up/down (ai_feedback) joins back through it. Plain String
		// (crypto/rand hex, high cardinality — not LowCardinality).
		// ai_calls is NOT in highVolumeTables: chstore owns it
		// single-node style everywhere (created by us even against
		// external Distributed clusters), so this is the same safe
		// shape as the monitors/users ALTERs above — no spans-style
		// wrapper/_local hazard. Insert failures on ai_calls are
		// log-and-drop observability rows, never span ingest.
		`ALTER TABLE ai_calls ADD COLUMN IF NOT EXISTS exchange_id String DEFAULT ''`,
		// v0.9.595 — rca_verdicts'e İMZA alanları. v0.9.591-594
		// çalıştırmış bir kurulumda tablo bu kolonlar OLMADAN yaratıldı;
		// CREATE'e eklemek yeni kurulumları kapsar, bu ALTER eskileri.
		// IF NOT EXISTS ikisini de idempotent yapıyor.
		//
		// rca_verdicts highVolumeTables'ta DEĞİL (ai_calls emsali):
		// chstore onu dış Distributed kümelerde bile tek-node şeklinde
		// yaratıyor, yani spans-tarzı wrapper/_local tuzağı yok.
		`ALTER TABLE rca_verdicts ADD COLUMN IF NOT EXISTS rc_entity LowCardinality(String) DEFAULT ''`,
		`ALTER TABLE rca_verdicts ADD COLUMN IF NOT EXISTS rc_fail_mode String DEFAULT ''`,
		// v0.9.1281 — GÖVDE + KAYNAK. Aynı gerekçe: CREATE yeni
		// kurulumları, bu iki ALTER v0.9.591-1280 çalıştırmış olanları
		// kapsar. IF NOT EXISTS ikisini de idempotent yapar ve
		// planAlterDDL zaten var olanı hiç göndermez.
		//
		// Eski satırlar DEFAULT '' okur — yani "bu verdict gövdesiz
		// üretildi", uydurulmuş bir metin değil. Kalıcı okuma bunu boş
		// gövde olarak döner ve frontend gövdesiz satırı çizmez.
		`ALTER TABLE rca_verdicts ADD COLUMN IF NOT EXISTS body String DEFAULT '' CODEC(ZSTD(3))`,
		`ALTER TABLE rca_verdicts ADD COLUMN IF NOT EXISTS source LowCardinality(String) DEFAULT ''`,
		// v0.8.20 — drop the dead topology-mute setting. The
		// "Mute on topology" chip was removed from the service detail
		// page in v0.8.19; this migration removes the now-orphaned
		// system_settings row so a stale exclude list can't silently
		// keep filtering topology edges. Pure data cleanup — there is
		// no schema column / table / MV for the feature, only this
		// settings key. ALTER ... DELETE is a lightweight mutation on
		// the small system_settings ReplacingMergeTree; a no-op when
		// the key was never set. execDDL → adaptDDL injects ON CLUSTER
		// in distributed mode (system_settings is not high-volume, so
		// it stays at its bare name — no _local rewrite).
		`ALTER TABLE system_settings DELETE WHERE key = 'topology.exclude'`,
		// In-binary head/tail sampling was removed in v0.8.73 (Coremetry
		// stores 100% of received spans; sampling moves to the collector).
		// Drop the orphaned persisted sampling policy so a stale row can't
		// confuse anything. Same lightweight-mutation / no-op-when-absent
		// semantics as the topology.exclude cleanup above.
		`ALTER TABLE system_settings DELETE WHERE key = 'sampling'`,
	}
	// v0.9.608 — kolonu ZATEN VAR olan `ADD COLUMN IF NOT EXISTS`
	// gönderilmez. v0.9.607'nin CREATE'ler için kurduğu kanıtın aynısı:
	// kolon varsa ifadenin etkisi tanım gereği yok, ödenen tek şey
	// tıkalı kuyrukta bir bütçe turu (~20 sn × 69 ALTER ≈ 23 dakika,
	// operator-reported: pod hiç ready olmuyordu).
	//
	// MODIFY COLUMN / MODIFY TTL / DELETE ELENMEZ — no-op oldukları
	// kanıtlanamaz ve yanlış eleme sessizce uygulanmamış bir tip
	// değişikliği bırakır.
	//
	// v0.9.1302 — bu dilim de artık planDDL'den geçiyor: buraya bir CREATE
	// düşerse (v0.9.1301'de beş tanesi düşmüştü) sessizce her boot'ta
	// gönderilmek yerine elenir.
	//
	// İKİ ANLIK GÖRÜNTÜ DE BURADA TAZE OKUNUYOR, `tables` diliminin
	// kümeleri yeniden KULLANILMIYOR: aradaki DDL nesne/kolon yaratmış ya
	// da DÜŞÜRMÜŞ olabilir (v0.10.846'dan beri bunun adı var:
	// dropRemovedTables, removed_tables.go — `tables` ile bu satır ARASINDA
	// koşuyor, tam da bu tazeliğe dayanarak) ve bayat
	// bir "zaten var" kaydı, düşürülmüş bir nesnenin CREATE'ini eler —
	// sessiz ve kalıcı kayıp. Taze okuma her zaman güvenli taraf; iki
	// system-tablosu sorgusunun boot'taki maliyeti ölçülemez.
	alterPlan, alterObjSkipped, alterColSkipped := planDDL(alters, s.existingObjects(ctx), s.existingColumns(ctx))
	logDDLPlan("alters", len(alters), alterObjSkipped, alterColSkipped)
	for _, q := range alterPlan {
		if err := s.execDDL(ctx, q); err != nil {
			// Skip-index ALTERs against a Distributed engine return
			// CH error 48 ("Alter of type 'ADD_INDEX' is not
			// supported by storage Distributed"). That happens when
			// the operator points Coremetry at a cluster but didn't
			// set chstore.cluster_name, so adaptDDL can't rewrite
			// to <table>_local ON CLUSTER. These indexes are pure
			// query-time optimisations; missing them slows some
			// scans but never breaks correctness, so we log and
			// continue instead of crash-looping the pod. The
			// operator can run them by hand against the per-shard
			// local tables.
			if isClusterUnsupportedAlter(err) {
				log.Printf("[chstore] skip-index alter not supported on Distributed engine (config.clickhouse.cluster_name not set?). Skipping: %.80s", q)
				continue
			}
			// Column ALTERs (auth_provider, runbook_url, etc.) on
			// pre-existing tables that were created by an older
			// version are idempotent via IF NOT EXISTS. A genuine
			// failure here (DDL syntax error, permissions) still
			// crashes — we only soften the specific Distributed
			// limitation.
			return fmt.Errorf("alter table: %w", err)
		}
	}

	// ldap_username probe (v0.8.526) — confirm the column reached the
	// table the WRITE path inserts into. Mirrors the hasOpGroupCol shape:
	// on a healthy Coremetry-managed `users` (single node, or cluster with
	// ClusterName set) the ALTER above lands ON CLUSTER and this reads
	// true. If it ever reads false (an unexpected shape / mid-rolling-
	// deploy skew) the INSERT/SELECT drop the column so logins keep
	// working. maybeCloseRows so a query error never nil-derefs Close()
	// (v0.8.185 boot-panic discipline).
	luRows, luErr := s.conn.Query(ctx, `SELECT ldap_username FROM users LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(luRows, luErr)
	s.hasLdapUsernameCol = luErr == nil
	if !s.hasLdapUsernameCol {
		log.Printf("[chstore] `ldap_username` column not present on users (%v) — INSERT/SELECT omit it, LDAP group-sync identity overlap falls back to email-only", luErr)
	}

	// comparator probe (v0.9.976) — ldap_username ile birebir aynı şekil.
	// `problems` okuma yolu HER sayfada çalışıyor (inbox, /problems, SSE,
	// evaluator snapshot), yani kolon henüz inmemişken koşulsuz bir
	// projeksiyon bütün triyaj yüzeyini karartırdı. false iken SELECT/INSERT
	// kolonu atlar; öncelik hesabı ters-çevirmesiz (güvenli) tarafta kalır.
	// rca_verdicts body/source probe (v0.9.1281) — comparator ile birebir
	// aynı şekil. İKİ kolon TEK probe'la: ikisi aynı ALTER turunda
	// gönderiliyor, dolayısıyla ayrı ayrı düşmeleri gözlenebilir bir durum
	// değil; tek bir SELECT ikisini de kanıtlar.
	//
	// Bu probe'un asıl işi dağıtık/ertelenmiş DDL kipini yakalamak: kolonu
	// EKLEYEN boot ALTER'ı kuyruğa aldığı için burayı false okur ve o boot
	// boyunca INSERT gövdesiz koşar (yazım code 16 ile düşmez). İkinci
	// boot true okur — "yeni kolon iki boot ister" davranışı, bilinçli.
	rvRows, rvErr := s.conn.Query(ctx, `SELECT body, source FROM rca_verdicts LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(rvRows, rvErr)
	s.hasRCAVerdictBodyCol = rvErr == nil
	if !s.hasRCAVerdictBodyCol {
		log.Printf("[chstore] `body`/`source` columns not present on rca_verdicts (%v) — INSERT omits them; verdict rows still record the decision, only the persisted narration is skipped until the next boot", rvErr)
	}

	cmpRows, cmpErr := s.conn.Query(ctx, `SELECT comparator FROM problems LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(cmpRows, cmpErr)
	s.hasProblemCmpCol = cmpErr == nil
	if !s.hasProblemCmpCol {
		log.Printf("[chstore] `comparator` column not present on problems (%v) — INSERT/SELECT omit it; priority ratio-flip stays OFF (safe direction, no false P1s)", cmpErr)
	}

	// kind probe (v0.9.1338) — comparator ile birebir aynı şekil. AYRI bir
	// probe, comparator'a bindirilmedi: iki kolon FARKLI sürümlerde eklendi,
	// yani prod'da comparator'ı olup kind'ı olmayan bir tablo TAMAMEN
	// olağan bir ara durum. Tek probe onları birbirine bağlasaydı kind'ın
	// yokluğu comparator'ı da kapatır ve öncelik hesabını sessizce geri
	// alırdı (rca_verdicts'in çift-kolon tek-probe'u ancak İKİ kolon AYNI
	// ALTER turunda gittiği için meşru).
	kindRows, kindErr := s.conn.Query(ctx, `SELECT kind FROM problems LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(kindRows, kindErr)
	s.hasProblemKindCol = kindErr == nil
	if !s.hasProblemKindCol {
		log.Printf("[chstore] `kind` column not present on problems (%v) — INSERT/SELECT omit it; every problem reads back as kind=service, i.e. exactly the pre-v0.9.1338 behaviour", kindErr)
	}

	// topology_edges_5m.cluster probe (v0.9.1025) — comparator ile birebir
	// aynı şekil. Kritik fark: burada probe'un koruduğu şey bir OKUMA değil,
	// YAZMA. WriteTopologyBucket kolonu koşulsuz INSERT kolon listesine
	// yazsaydı, kolon inmeden önceki her 5-dk bucket'ı code 47 ile ölür ve
	// topoloji grafiği tamamen boş kalırdı. false iken pass'ler kolonu
	// atlar (satırlar DEFAULT '' alır) ve köprü katalog dalında kalır.
	tcRows, tcErr := s.conn.Query(ctx, `SELECT cluster FROM topology_edges_5m LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(tcRows, tcErr)
	s.hasTopoClusterCol = tcErr == nil
	// entry_service_state okuma probe'u (v0.10.97) — BARE ada sorar,
	// çünkü koruduğu okumalar bare addan geçiyor. Cluster'da sarmalayıcı
	// bu migrate'in İÇİNDE düşürülüp boot'un ilerisinde (ensure) yeniden
	// kurulduğundan İLK boot false kalabilir: okumalar o süreçte ESKİ
	// zinciri kullanır (davranış bit-bit eski, 500 yok), sonraki boot
	// true'ya döner — kendini iyileştiren pencere, sessiz değil (log).
	// v0.10.111 — probe KOLON VARLIĞINI ölçer, sürücü çözülebilirliğini
	// DEĞİL. 10.97'nin şekli (SELECT entry_service_state … LIMIT 1) ham
	// state kolonunu tele bindiriyordu; clickhouse-go AggregateFunction
	// tipini hiçbir sürümde çözemez → probe HER kümede false kalıyor ve
	// 'unknown' düşüşü hiç açılmıyordu (lokalde ölçüldü: "unsupported
	// column type AggregateFunction(argMinIf, String, DateTime64(9),
	// UInt8)"). Korunan okumaların hepsi sunucu tarafında argMinIfMerge
	// ile finalize eder — ihtiyaçları kolonun ŞEMADA olması (code 47
	// yememek), teleden çözülebilmesi değil. system.columns metadata
	// okumasıdır: veri hacminden bağımsız, yoğun kümede 3s cap'in
	// yanlış-false ürettiği v0.5.388 sınıfına da kapalı.
	var esOne uint8
	esErr := s.conn.QueryRow(ctx, `SELECT 1 FROM system.columns WHERE database = currentDatabase() AND table = 'trace_summary_5m' AND name = 'entry_service_state' LIMIT 1 SETTINGS max_execution_time = 3`).Scan(&esOne)
	s.hasTraceEntrySvcCol = esErr == nil
	if !s.hasTraceEntrySvcCol {
		log.Printf("[chstore] `entry_service_state` not readable on trace_summary_5m (%v) — /traces kök-servis 'unknown' düşüşü bu süreçte devre dışı (eski davranış)", esErr)
	}
	if !s.hasTopoClusterCol {
		log.Printf("[chstore] `cluster` column not present on topology_edges_5m (%v) — topology passes omit it; queue nodes keep the narrowed /messaging catalogue link instead of the drawer deep-link", tcErr)
	}

	// op_group — the normalized operation-shape column (group_id rel A,
	// v0.8.172). EXPLICIT Go-written, NOT MATERIALIZED: convert.go computes
	// it per-span via templater.NormalizeOperation and the spans INSERT
	// binds sp.OpGroup. Because it's on the INGEST path, a wrapper/local
	// mismatch is catastrophic (code 16 on every flush → zero ingest), so
	// it's gated OUT of the alters slice above and added here only when
	// chstore actually owns spans_local:
	//   • cfg.ClusterName set  → adaptDDL rewrites the ALTER to
	//     `spans_local ON CLUSTER` (clusterMode); safe.
	//   • single-node MergeTree spans → the bare `spans` IS the data table;
	//     safe.
	//   • external Distributed spans, ClusterName unset → the ALTER would
	//     land on the wrapper only, never on spans_local → SKIP + log
	//     (v0.8.186 prod: this exact inconsistent state lost every span
	//     batch). The hasOpGroupCol probe below then reads false, the
	//     INSERT drops op_group from its column list, and the read path
	//     soft-degrades to raw-name grouping.
	// Forward-only: old parts read '' (the MV + UI tolerate the empty group).
	const opGroupAlter = `ALTER TABLE spans ADD COLUMN IF NOT EXISTS op_group LowCardinality(String) DEFAULT ''`
	if s.spansIsExternalDistributed(ctx) {
		log.Printf("[chstore] external Distributed `spans` with cluster_name unset — SKIPPING op_group ALTER (it can't reach spans_local; adding it to the wrapper only would break every INSERT with code 16). op_group features degrade gracefully; set config.clickhouse.cluster_name to enable them.")
	} else if err := s.execDDL(ctx, opGroupAlter); err != nil {
		return fmt.Errorf("alter table (op_group): %w", err)
	}

	// op_group VARLIK probe'u — v0.10.834 (inceleme, KRİTİK 1): METADATA'dan.
	//
	// Eskiden bu bir VERİ okumasıydı (`SELECT op_group FROM spans … LIMIT 1
	// SETTINGS max_execution_time = 3`) ve `hasOpGroupCol = err == nil`
	// deniyordu. Tek bir geçici hata — kod 159 zaman aşımı, 241 bellek, 202
	// eşzamanlılık, readonly replika — "kolon YOK" anlamına geliyordu; o
	// boot'ta aşağıdaki kurtarma dalı ateşleyip MV'yi düşürüyor,
	// hasOpGroupCol=false olduğu için aynı boot'ta yeniden kurulmasını da
	// engelliyordu → tarihçe geri gelmiyordu. Emsal: hasTraceEntrySvcCol
	// (v0.10.111) aynı sebeple system.columns'a çevrilmişti.
	//
	// Hedef ŞEKLİ ÖLÇÜLMÜŞ depo adı: küme kipinde `spans_local`, AMA yalnız
	// çıplak `spans` gerçekten Distributed sarmalayıcıysa. Uyuşmazlıkta
	// (cluster_name dolu + tek düğüm şekli) `mvStorageName` var olmayan
	// `spans_local`e sorar, "kolon yok" cevabı üretir ve kurtarmayı YANLIŞ
	// yere ateşlerdi.
	//
	// HATA = "BİLMİYORUM": hasOpGroupCol false'a düşer (INSERT kolonu atlar,
	// ingest güvende) ama ogProbeErr dolu kalır ve yıkıcı dal KOŞMAZ.
	var ogProbeErr error
	ogTarget, ogShapeErr := s.resolvedStorageName(ctx, "spans")
	if ogShapeErr != nil {
		ogProbeErr = ogShapeErr
	} else {
		present, err := s.columnPresentAllHosts(ctx, ogTarget, "op_group")
		ogProbeErr = err
		s.hasOpGroupCol = err == nil && present
	}
	if !s.hasOpGroupCol {
		log.Printf("[chstore] `op_group` column not present on %s (probe err: %v) — INSERT omits it, operation_group_summary_5m MV disabled, normalized operations read falls back to raw operation names (expected on an external Distributed cluster with cluster_name unset)", ogTarget, ogProbeErr)
	}

	// Boot self-heal (v0.8.187): op_group absent on spans_local while `spans` is
	// an external Distributed table. A pre-fix boot (≤ v0.8.172) added op_group
	// to the WRAPPER only; the Distributed engine then fills the wrapper's
	// DEFAULT '' and forwards a column spans_local lacks → `code 16: No such
	// column op_group in …spans_local` on EVERY flush (CH PR #7377: DEFAULT
	// columns are forwarded, only MATERIALIZED are erased). v0.8.186's named-
	// INSERT omit can't reach the wrapper's schema, so reconcile the SCHEMA
	// here: discover the cluster the Distributed table fans to (config first,
	// else parse it out of the engine def) and ADD op_group to spans_local AND
	// the wrapper ON CLUSTER — this reaches every shard, makes the structures
	// consistent, and ENABLES the feature (better than dropping the wrapper
	// column, which heals one host + keeps the feature off). Best-effort: any
	// failure logs and leaves hasOpGroupCol=false so the v0.8.186 degrade path
	// keeps ingest alive. Never crash-loops. Only fires on the broken external-
	// Distributed shape, so healthy installs are untouched.
	if !s.hasOpGroupCol && s.spansIsExternalDistributed(ctx) {
		cluster := strings.TrimSpace(s.cfg.ClusterName)
		if cluster == "" {
			cluster = s.discoverSpansCluster(ctx)
		}
		if cluster == "" {
			log.Printf("[chstore] op_group self-heal: spans is Distributed but no cluster name (config or discoverable from its engine def) — cannot reconcile; set config.clickhouse.cluster_name. op_group features stay degraded.")
		} else {
			q := "'" + strings.ReplaceAll(cluster, "'", "''") + "'"
			for _, tbl := range []string{"spans_local", "spans"} {
				ddl := fmt.Sprintf("ALTER TABLE %s ON CLUSTER %s ADD COLUMN IF NOT EXISTS op_group LowCardinality(String) DEFAULT ''", tbl, q)
				if err := s.conn.Exec(ctx, ddl); err != nil {
					log.Printf("[chstore] op_group self-heal: ALTER %s ON CLUSTER %s failed (non-fatal): %v", tbl, cluster, err)
				} else {
					log.Printf("[chstore] op_group self-heal: added op_group to %s ON CLUSTER %s", tbl, cluster)
				}
			}
			// Re-probe: did op_group reach spans_local on the shards?
			rRows, rErr := s.conn.Query(ctx,
				`SELECT op_group FROM spans WHERE time >= now() - INTERVAL 1 SECOND LIMIT 1 SETTINGS max_execution_time = 3`)
			maybeCloseRows(rRows, rErr)
			s.hasOpGroupCol = rErr == nil
			if s.hasOpGroupCol {
				log.Printf("[chstore] op_group self-heal succeeded — op_group now resolvable on spans_local (cluster %s); INSERT writes it + features enabled", cluster)
			} else {
				log.Printf("[chstore] op_group self-heal: still not resolvable after ALTER (%v) — features stay degraded; verify cluster '%s' and spans_local on all shards", rErr, cluster)
			}
		}
	}

	// Defensive recovery (v0.8.186): when op_group is genuinely absent, DROP
	// operation_group_summary_5m if it lingers from a prior boot. The MV's
	// SELECT references op_group, so its insert-trigger fires on every span
	// INSERT and FAILS with code 16 — which under default CH semantics
	// aborts the source INSERT too, blocking ALL ingest. Dropping it lets
	// spans land again. Idempotent; only fires when the column is truly
	// missing so the healthy path never touches the MV. The creation loop
	// below also skips recreating it while hasOpGroupCol is false.
	//
	// v0.10.834 (inceleme, KRİTİK 1) — iki değişiklik:
	//   • `ogProbeErr == nil` ŞARTI: "kolon yok" kararı GERÇEKTEN okunmuş
	//     olmalı. Geçici bir probe hatası artık MV düşürmez.
	//   • ham `DROP VIEW <çıplak ad>` yerine dropIngestBlockingMV: şekli ölçer
	//     (resolvedStorageName) ve guard-safe dropCombinedMV'den geçer. Eski
	//     ifade execDDL'den değiştirilmeden geçiyordu (adaptDDL DROP tanımaz),
	//     yani `_local`'a çevrilmiyor, ON CLUSTER almıyor ve şekil kapısının
	//     yanından bile geçmiyordu. execDDL artık o şekli yapısal olarak
	//     reddediyor (bareDestructiveTarget).
	if !s.hasOpGroupCol && ogProbeErr == nil {
		s.dropIngestBlockingMV(ctx, "operation_group_summary_5m", "op_group")
	}

	// series_fingerprint — v0.8.328 cross-signal pivot: the persisted metric
	// series identity (see hasSeriesFpCol on the Store struct). EXPLICIT
	// Go-written column on the metric_points INGEST path, so it gets the
	// op_group treatment, NOT a slot in the generic alters slice: on an
	// external Distributed `metric_points` with cfg.ClusterName unset the
	// ALTER would reach the wrapper only — CH forwards DEFAULT columns to
	// the shards (PR #7377) and every metric INSERT would die with code 16
	// (the v0.8.186 failure shape, this class broke prod twice). Skip + log
	// there; the probe below then keeps the INSERT column list honest.
	// Forward-only: old parts read the DEFAULT 0 (= "no identity" sentinel).
	const seriesFpAlter = `ALTER TABLE metric_points ADD COLUMN IF NOT EXISTS series_fingerprint UInt64 DEFAULT 0`
	if s.tableIsExternalDistributed(ctx, "metric_points") {
		log.Printf("[chstore] external Distributed `metric_points` with cluster_name unset — SKIPPING series_fingerprint ALTER (it can't reach metric_points_local; adding it to the wrapper only would break every metric INSERT with code 16). Exemplar pivots degrade to the metric+service fallback; set config.clickhouse.cluster_name to enable them.")
	} else if err := s.execDDL(ctx, seriesFpAlter); err != nil {
		return fmt.Errorf("alter table (series_fingerprint): %w", err)
	}

	// Probe whether series_fingerprint is genuinely present on the table the
	// WRITE path inserts into — in distributed mode this select routes to
	// metric_points_local, so it correctly reads false when the column never
	// reached the shards (skipped ALTER above, or an operator-managed schema
	// that pre-dates it). Mirrors the hasOpGroupCol probe exactly, incl. the
	// maybeCloseRows error-path discipline (v0.8.185 boot-panic).
	sfRows, sfErr := s.conn.Query(ctx,
		`SELECT series_fingerprint FROM metric_points WHERE time >= now() - INTERVAL 1 SECOND LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(sfRows, sfErr)
	s.hasSeriesFpCol = sfErr == nil
	if !s.hasSeriesFpCol {
		log.Printf("[chstore] `series_fingerprint` column not present on metric_points (%v) — INSERT omits it; exemplar reads fall back to metric+service (expected on an external Distributed cluster with cluster_name unset)", sfErr)
	}

	// is_monotonic — v0.9.106 (F2, PromQL rate/increase). OTLP Sum'ın
	// d.Sum.IsMonotonic'i (monotonic counter mı, yoksa UpDownCounter mı —
	// active_requests/queue-depth). metric_points instrument='sum'u İKİSİ için
	// de basıyor; rate() UpDownCounter'da her düşüşü "reset" sanıp garbage
	// üretiyordu (adversarial review, major). Kolon rate'i is_monotonic=1'e
	// gate eder. DEFAULT 1 = eski data + gauge/histogram monotonic sayılır
	// (rate zaten instrument='sum'a filtreli). series_fingerprint'in BİREBİR
	// distributed-safe deseni: external Distributed + cluster_name unset'te
	// ALTER metric_points_local'e ulaşmaz → wrapper-only ALTER her INSERT'i
	// code 16 ile öldürür (v0.8.186 sınıfı, prod'u 2× kırdı) → SKIP + log;
	// probe INSERT kolon listesini dürüst tutar.
	const isMonotonicAlter = `ALTER TABLE metric_points ADD COLUMN IF NOT EXISTS is_monotonic UInt8 DEFAULT 1`
	if s.tableIsExternalDistributed(ctx, "metric_points") {
		log.Printf("[chstore] external Distributed `metric_points` with cluster_name unset — SKIPPING is_monotonic ALTER (can't reach metric_points_local; wrapper-only would break every metric INSERT with code 16). rate()/increase() degrades to no-monotonicity-guard; set config.clickhouse.cluster_name to enable it.")
	} else if err := s.execDDL(ctx, isMonotonicAlter); err != nil {
		return fmt.Errorf("alter table (is_monotonic): %w", err)
	}
	imRows, imErr := s.conn.Query(ctx,
		`SELECT is_monotonic FROM metric_points WHERE time >= now() - INTERVAL 1 SECOND LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(imRows, imErr)
	s.hasIsMonotonicCol = imErr == nil
	if !s.hasIsMonotonicCol {
		log.Printf("[chstore] `is_monotonic` column not present on metric_points (%v) — INSERT omits it; rate()/increase() runs WITHOUT the monotonic guard (UpDownCounter rate may be wrong; expected on an external Distributed cluster with cluster_name unset)", imErr)
	}

	// db_stmt_hash — v0.8.375, Stage-2 D1: persistent DB-statement identity
	// (pages-enhancement-audit §2 / Faz D, approved default: INGEST-TIME
	// fingerprint). xxHash64 over the literal-normalized db.statement,
	// computed AT INSERT by ClickHouse via a MATERIALIZED expression — the
	// `cluster` column precedent (v0.8.132), deliberately NOT the
	// op_group/series_fingerprint explicit-INSERT shape:
	//   • MATERIALIZED columns are never part of the INSERT projection and
	//     are ERASED when a Distributed wrapper forwards blocks (CH PR
	//     #7377), so the wrapper/local-mismatch class that broke prod twice
	//     (v0.8.185 cluster, v0.8.186 op_group) physically cannot kill
	//     ingest here.
	//   • Rolling deploy has NO data gap: old pods' INSERTs never mention
	//     the column, and the server computes it for their rows the moment
	//     the ALTER lands — an explicit column would have written DEFAULT 0
	//     for every old-pod span until the fleet converged.
	//   • New pods against an un-migrated schema are equally safe: the
	//     INSERT doesn't name the column, so nothing can code-16.
	// The expression is hash-parity-PINNED with the Go normalizer
	// (NormalizeDBStatement / DBStmtHash, dbstmt.go — vectors captured from
	// live CH 24.8), so read paths compute the same identity Go-side.
	// Gated like op_group: on an external Distributed `spans` with
	// cluster_name unset the ALTER can't reach spans_local — skip + log,
	// and the probe below keeps the MV + read dispatch honest.
	dbStmtHashAlter := `ALTER TABLE spans ADD COLUMN IF NOT EXISTS db_stmt_hash UInt64 MATERIALIZED ` + dbStmtHashExpr
	if s.spansIsExternalDistributed(ctx) {
		log.Printf("[chstore] external Distributed `spans` with cluster_name unset — SKIPPING db_stmt_hash ALTER (it can't reach spans_local). Statement-identity MV disabled, /slow-queries stays on the raw-spans path; set config.clickhouse.cluster_name to enable it.")
	} else if err := s.execDDL(ctx, dbStmtHashAlter); err != nil {
		return fmt.Errorf("alter table (db_stmt_hash): %w", err)
	}

	// db_stmt_hash VARLIK probe'u — v0.10.834 (inceleme, KRİTİK 1): op_group
	// ile AYNI sözleşme, aynı sebeple METADATA'dan (geçici bir okuma hatası
	// "kolon yok" sayılıp aşağıdaki kurtarma dalını ateşliyordu). Hedef şekli
	// ölçülmüş depo adı; HATA = "bilmiyorum" → bayrak false (okuma ham yola
	// düşer) ama yıkıcı dal KOŞMAZ. db_stmt_hash MATERIALIZED bir kolon ve
	// system.columns onu da listeler.
	var dhProbeErr error
	dhTarget, dhShapeErr := s.resolvedStorageName(ctx, "spans")
	if dhShapeErr != nil {
		dhProbeErr = dhShapeErr
	} else {
		present, err := s.columnPresentAllHosts(ctx, dhTarget, "db_stmt_hash")
		dhProbeErr = err
		s.hasDBStmtHashCol = err == nil && present
	}
	dhErr := dhProbeErr
	// v0.10.331 — alert_rules.target_json probu: küme kipinde kolon ertelenmiş
	// DDL ile bir sonraki boot'ta gelir; gelene dek hedefli kural kaydı 409,
	// okumalar '' ile sürer (iki-boot sözleşmesi, CLAUDE.md §3).
	if !s.probeAlertRuleTargetCol(ctx) {
		log.Printf("[chstore] alert_rules.target_json not yet present — DB-statement alert rules re-probe on save once the deferred DDL lands")
	}
	// v0.10.519 — notify_json aynı sözleşme.
	if !s.probeAlertRuleNotifyCol(ctx) {
		log.Printf("[chstore] alert_rules.notify_json not yet present — team-routed alert rules re-probe on save once the deferred DDL lands")
	}
	if !s.hasDBStmtHashCol {
		log.Printf("[chstore] `db_stmt_hash` column not resolvable on spans (%v) — db_statement_summary_5m MV disabled, /slow-queries reads stay on the raw-spans path (expected on an external Distributed cluster with cluster_name unset)", dhErr)
	}

	// ex_* — v0.8.566, perf #19: exception tip/mesaj/stack/match INSERT
	// anında MATERIALIZED kolonlara iner; beş sorgu sitesi düz kolon okur
	// (exFragments). Ölçülen kazanç okuma tarafında (ifade yolu ZSTD'li
	// `events` blob'unu her satırda açıyordu); MATERIALIZED şekli
	// db_stmt_hash emsali — INSERT projeksiyonunda yok, Distributed
	// forwarding'de silinir, eski part'lar okuma anında hesaplar.
	// ex_match AYRI kolon, `ex_type != ''` sentinel'i DEĞİL: JSON_VALUE
	// eksik anahtarda '' döner, yani '' KABUL EDİLMİŞ satırlar için
	// geçerli bir tip değeridir (exception event'i var ama exception.type
	// attr'ı yok) — sentinel o satırları sessizce düşürürdü.
	exAlters := []string{
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS ex_match UInt8 MATERIALIZED ` + exMatchDefExpr,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS ex_type LowCardinality(String) MATERIALIZED ` + exTypeDefExpr,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS ex_msg String MATERIALIZED ` + exMsgDefExpr + ` CODEC(ZSTD(3))`,
		`ALTER TABLE spans ADD COLUMN IF NOT EXISTS ex_stack String MATERIALIZED ` + exStackDefExpr + ` CODEC(ZSTD(3))`,
	}
	if s.spansIsExternalDistributed(ctx) {
		log.Printf("[chstore] external Distributed `spans` with cluster_name unset — SKIPPING exception column ALTERs; exception reads stay on the JSON_VALUE expression path (set config.clickhouse.cluster_name to enable them)")
	} else {
		for _, a := range exAlters {
			if err := s.execDDL(ctx, a); err != nil {
				return fmt.Errorf("alter table (exception cols): %w", err)
			}
		}
	}
	exRows, exErr := s.conn.Query(ctx,
		`SELECT ex_match, ex_type, ex_msg, ex_stack FROM spans WHERE time >= now() - INTERVAL 1 SECOND LIMIT 1 SETTINGS max_execution_time = 3`)
	maybeCloseRows(exRows, exErr)
	s.hasExCols = exErr == nil
	if !s.hasExCols {
		log.Printf("[chstore] exception columns not resolvable on spans (%v) — exception reads fall back to the JSON_VALUE expression path (expected on an external Distributed cluster with cluster_name unset)", exErr)
	}

	// attr_channel_code / attr_function_code — v0.9.198 (FAZ 2C,
	// docs/audit/traces-attribute-columns.md §10): the two operator-promoted
	// trace-list attribute columns. MATERIALIZED from the attr arrays so the
	// /traces extras phase-2 reads ONE narrow LowCardinality column instead
	// of decompressing the 4 fat array columns (measured 6.97x read_bytes on
	// the array path). ex_*/db_stmt_hash precedent end to end: no INSERT
	// projection change, Distributed forwarding drops them, old parts compute
	// at read time, external-Distributed-unset skips the ALTER, and the boot
	// probe below gates the read side (distributed-column-safety — the map
	// stays EMPTY and the projection falls back to the array path when the
	// columns aren't resolvable).
	// v0.9.621 — ifade artık İKİ yazımı da okuyor ve gerekiyorsa var olan
	// kolon DROP+ADD ile onarılıyor (promoted_attr.go: neden MODIFY değil,
	// neden `alters` listesine konulamaz).
	//
	// Ayrıca artık boot'u DÜŞÜRMÜYOR: eskiden ALTER hatası
	// `return fmt.Errorf(...)` ile migrate'i kesiyordu. Terfi kolonu saf
	// bir hız optimizasyonu ve okuma tarafı probe ile kapalı — başarısızlık
	// "yavaş" demek, "yanlış" değil. v0.9.604-615 boot krizinden sonra
	// isteğe bağlı bir optimizasyonun pod'u ready olmaktan alıkoyması
	// kabul edilemez.
	// v0.10.302 — operatör facet kaydı (system_settings) yerleşik listeye
	// katılır; DDL/probe aynı makineden geçer. Bozuk blob boot'u durdurmaz.
	// v0.10.345 — dış link şablonları (trace sayfası düğmeleri); bozuk blob
	// boot'u durdurmaz.
	if err := s.LoadExternalLinks(ctx); err != nil {
		log.Printf("[chstore] external_links yüklenemedi (boş liste ile devam): %v", err)
	}
	if err := s.LoadTraceFacets(ctx); err != nil {
		log.Printf("[chstore] trace facets yüklenemedi (yerleşik liste ile devam): %v", err)
	}
	ensuredPromoted := s.repairPromotedAttrCols(ctx)
	// v0.9.439 (Uptrace uyarlamaları — LC/kodek denetimi) — metric_points
	// serbest kolonlarına ZSTD(1) (metadata-only MODIFY; v0.8.214 spans
	// emsali). Taban ölçümü (lokal, 2026-07-30): res_values 34.5MiB
	// sıkıştırılmış / 568MiB ham, oran 16.5 — kodeksiz LZ4'ün en kötüsü.
	// TİP-PROBE'lu: operatör 0006 ile LC mutasyonunu uyguladıysa (tip
	// LowCardinality içerir) bu MODIFY'lar KOŞULMAZ — aksi halde tipi
	// String'e GERİ mutasyonlarlardı (migrations sahiplik sözleşmesi).
	// Soft-fail: kodek saf optimizasyon, boot'u asla düşürmez.
	var mpAttrType string
	if mrow := s.conn.QueryRow(ctx,
		`SELECT type FROM system.columns WHERE database = currentDatabase() AND table = 'metric_points' AND name = 'attr_values'`); mrow != nil {
		_ = mrow.Scan(&mpAttrType)
	}
	if !strings.Contains(mpAttrType, "LowCardinality") {
		for _, a := range []string{
			`ALTER TABLE metric_points MODIFY COLUMN description String DEFAULT '' CODEC(ZSTD(1))`,
			`ALTER TABLE metric_points MODIFY COLUMN attr_values Array(String) CODEC(ZSTD(1))`,
			`ALTER TABLE metric_points MODIFY COLUMN res_values Array(String) CODEC(ZSTD(1))`,
		} {
			if err := s.execDDL(ctx, a); err != nil {
				log.Printf("[chstore] metric_points codec ALTER (soft-fail): %v", err)
			}
		}
	}

	// v0.9.621 — kayıt artık VERİYLE kanıtlanıyor, varlıkla değil.
	//
	// Eski probe `SELECT attr_channel_code … LIMIT 1` idi: kolonun VAR
	// olduğunu kanıtlıyordu, DOLU olduğunu değil. Kolon v0.9.198'den beri
	// boştu ve probe her boot'ta geçti. probePromotedAttrs her yazım için
	// ayrı ayrı "kolon, dizi aramasının verdiği değerin aynısını mı
	// veriyor?" sorusunu veriyle cevaplıyor.
	registerTraceAttrMaterialized(s.probePromotedAttrs(ctx))
	// v0.10.299 — attribute hash indeksi (attr_kvh/res_kvh + bloom): DDL +
	// probe (küme kipinde ertelenir → ddl_defer.go yeniden probe eder).
	s.repairAttrIndexCols(ctx)
	registerAttrIndex(s.probeAttrIndex(ctx))
	// v0.10.409 — ai_calls genişletilmiş kolon probe'u (iki-boot).
	s.probeAICallsColumns(ctx)
	s.probeAICallsCachedColumn(ctx) // v0.10.807

	// v0.10.127 — entity_seen MV'leri k8s_pod terfi kolonunu OKUR; kolon
	// yoksa (dış Distributed: repairPromotedAttrCols atlandı, ya da DDL
	// ertelendi) MV'yi yaratmak her span INSERT'ini kod 47 ile düşürürdü
	// (v0.5.361 sınıfı). O yüzden MV'ler yalnız kolon VARSA listeye girer;
	// prod'da kolon + MV 0011 migration'ıyla operatörde.
	_, k8sPodColExists := s.spansColumnExpr(ctx, "k8s_pod")
	hasK8sPodCol := k8sPodColExists || ensuredPromoted["k8s_pod"]
	// v0.10.198 — ROLLOUTS Faz 1b: workload_revision_activity_1m MV altı terfi
	// kolonunun hepsini VE 0011'in cluster + k8s_namespace kolonlarını OKUR
	// (rollout_schema.go); biri bile yoksa CREATE kod 47 ile düşer ya da MV
	// her span INSERT'ini düşürürdü → yalnız hepsi varsa listeye girer.
	// Dış Distributed prod'da kolon + MV 0012 sihirbazıyla operatörde.
	hasRolloutCols := true
	for _, col := range []string{"k8s_deployment", "k8s_statefulset", "k8s_daemonset", "k8s_replicaset", "container_image", "container_image_tag", "k8s_namespace", "cluster"} {
		if _, ok := s.spansColumnExpr(ctx, col); !ok && !ensuredPromoted[col] {
			hasRolloutCols = false
		}
	}

	// Defensive recovery (mirrors the op_group guard, v0.8.186): when
	// db_stmt_hash is genuinely absent, DROP db_statement_summary_5m if it
	// lingers from a prior boot. Its SELECT references db_stmt_hash, so its
	// insert-trigger would fail with code 16 on every span INSERT — which
	// under default CH semantics aborts the source INSERT too, blocking ALL
	// ingest. Idempotent; only fires when the column is truly missing, so
	// the healthy path never touches the MV. The creation loop below also
	// skips recreating it while hasDBStmtHashCol is false.
	//
	// v0.10.834 (inceleme, KRİTİK 1) — op_group kardeşiyle AYNI iki değişiklik:
	// karar gerçekten okunmuş olmalı (`dhProbeErr == nil`) ve düşürme şekli
	// ölçen, guard-safe yoldan geçmeli (dropIngestBlockingMV).
	if !s.hasDBStmtHashCol && dhProbeErr == nil {
		s.dropIngestBlockingMV(ctx, "db_statement_summary_5m", "db_stmt_hash")
	}

	// Materialized views — katalog canonicalMVs() içinde (v0.10.564: sihirbaz
	// da AYNI gövdeyi okuyor). Koşullu eklemeler aşağıda append edilir.
	mvs := canonicalMVs()
	// v0.5.361 — bug-fix: the spanmetrics_hist_5m MV (added in
	// v0.5.359) references metric_points.bucket_counts. On an
	// existing install the column doesn't exist yet at this
	// point — it's added by the ALTER block further down. The
	// MV creation loop blew up with CH error 47
	// (UNKNOWN_IDENTIFIER) before reaching the migration. Run
	// the bucket-column ALTER first so every MV creation that
	// follows sees the schema it expects.
	var hasBucketCols uint8
	if err := s.conn.QueryRow(ctx, `
		SELECT count() = 2
		FROM system.columns
		WHERE database = currentDatabase()
		  AND table    = 'metric_points'
		  AND name IN ('bucket_bounds', 'bucket_counts')`).Scan(&hasBucketCols); err == nil && hasBucketCols == 0 {
		log.Println("[chstore] adding bucket_bounds + bucket_counts columns to metric_points")
		// v0.5.362 — let execDDL→adaptDDL inject ON CLUSTER. Hand-
		// concatenating s.onCluster() here doubled the clause on
		// cluster-mode installs (CH syntax error → ALTER never
		// applied → "no such column bucket_bounds" at runtime).
		if err := s.execDDL(ctx,
			"ALTER TABLE metric_points"+
				" ADD COLUMN IF NOT EXISTS bucket_bounds Array(Float64) DEFAULT [],"+
				" ADD COLUMN IF NOT EXISTS bucket_counts Array(UInt64) DEFAULT []"); err != nil {
			return fmt.Errorf("add bucket columns: %w", err)
		}
	}

	// v0.8.408 — promote the spanmetrics doorway tiers on existing
	// cluster installs (RENAME bare MV → _local + Distributed wrapper,
	// data preserved) BEFORE the create loop below: with the new
	// highVolumeTables registration adaptDDL now emits
	// spanmetrics_1m_local etc., and creating that beside a still-live
	// bare MV would double-aggregate every spans insert.
	if err := s.promoteCombinedMVs(ctx, []string{
		"spanmetrics_1m", "spanmetrics_10s", "spanmetrics_1s",
		// v0.9.350 — joins the promotion list with its highVolumeTables
		// registration. An install that already created it bare-name (any
		// cluster-mode boot with op_group present) gets the data-preserving
		// RENAME → _local + Distributed wrapper. Installs where it was never
		// created — the common case, op_group absent → MV dropped at boot —
		// hit promoteCombinedMVs' missing-table branch and no-op.
		"operation_group_summary_5m",
	}); err != nil {
		return fmt.Errorf("promote doorway MVs: %w", err)
	}

	// v0.10.127 — K8s entity katmanı: entity_seen_1m/5m (entity_schema.go).
	if hasK8sPodCol {
		mvs = append(mvs,
			entitySeenMVDDL("entity_seen_1m", "1 MINUTE", entitySeen1mTTLDays),
			entitySeenMVDDL("entity_seen_5m", "5 MINUTE", entitySeen5mTTLDays))
	} else {
		log.Println("[chstore] k8s_pod terfi kolonu yok — entity_seen MV'leri ATLANDI (dış Distributed'da 0011 migration'ı)")
	}
	// v0.10.198 — ROLLOUTS Faz 1b: workload_revision_activity_1m (rollout_schema.go).
	if hasRolloutCols && hasK8sPodCol {
		mvs = append(mvs, workloadRevisionActivityMVDDL())
	} else {
		log.Println("[chstore] rollout terfi kolonları eksik — workload_revision_activity_1m MV ATLANDI (dış Distributed'da 0012 sihirbazı)")
	}

	for _, q := range mvs {
		// Skip the operation_group_summary_5m MV when op_group isn't on the
		// table (v0.8.186): its SELECT reads op_group, so creating it would
		// install an insert-trigger that fails code 16 on every span INSERT
		// and blocks ALL ingest. The defensive DROP above already removed any
		// stale copy; don't recreate what we just dropped. Every other MV is
		// op_group-agnostic and created unconditionally. Cheap substring
		// match on the CREATE — the MV name is unique in the statement.
		// Same guard class for db_statement_summary_5m (v0.8.375, Stage-2
		// D1): its SELECT reads db_stmt_hash — creating it while the column
		// is absent (external Distributed cluster, cluster_name unset) would
		// block ALL ingest with code 16. The defensive DROP above already
		// removed any stale copy.
		//
		// v0.10.825 — iki kapı mvGuardedOff'a çıkarıldı: MV kapsama kartı
		// (mv_coverage.go) AYNI kararı okumak zorunda, yoksa kolonu olmayan
		// kurulumda bu iki MV'yi her host'ta "eksik" gösterir ve "Yeniden
		// kur" düğmesi tam da burada engellenen DDL'i koşardı.
		if s.mvGuardedOff(mvNameFromDDL(q)) {
			continue
		}
		if err := s.execDDL(ctx, q); err != nil {
			return fmt.Errorf("create MV: %w", err)
		}
	}

	// The drop+recreate upgrade migrations below reference MVs BY NAME (via
	// mvDDLByName), not by positional index. v0.8.52: doorway D1 inserted three
	// spanmetrics tiers near the top of mvs, which silently shifted the
	// hardcoded db_summary_5m/db_caller_summary_5m indices (3/4 → 6/7) — a
	// pre-v0.5.327 upgrade would have recreated the wrong MV. Name lookup
	// removes the whole class of index-shift bug.
	findMV := func(name string) string { return mvDDLByName(mvs, name) }
	// Forward-compat: ClickHouse doesn't support ADD COLUMN on
	// MaterializedView storage, so on an upgrade from a pre-apdex MV we
	// detect the missing column and drop+recreate. The raw `spans` table
	// still has every source row, so the MV repopulates from new ingest
	// immediately; old buckets are gone but a one-time backfill via
	// `INSERT INTO service_summary_5m SELECT ... FROM spans WHERE
	// time < <cutoff>` can restore them if the operator wants.
	var hasApdex uint8
	// v0.10.834 (inceleme, ÖNEMLİ 4) — probe hedefi STORAGE adı.
	// Çıplak ad küme kipinde Distributed sarmalayıcıdır ve YOK olabilir
	// (ensureDistributedWrappers migrate'ten SONRA koşar). Çıplak ada soran
	// probe o pencerede 0 satır görüp "kolon eksik" der; dal ateşler ve
	// dropCombinedMV CANLI `_local`i emniyet KAPALI düşürür — yamanın
	// kapatmak için yazıldığı kaybın AYNISI, roller ters. Emsal: v0.9.1098
	// bu sınıfı db_statement için kapatmıştı.
	probeSQL := fmt.Sprintf(`
		SELECT count() > 0
		FROM system.columns
		WHERE database = currentDatabase()
		  AND table    = '%s'
		  AND name     = 'apdex_satisfied_state'`, s.mvStorageName("service_summary_5m"))
	// v0.10.834 — AYNI SINIF, ikinci yarı: bu dal çıplak adı DROP etmiyor
	// ama küme şeklini VARSAYIYOR. Tek düğüm şeklinde (cluster_name dolu,
	// `_local` yok) dropCombinedMV("…_local") sessiz no-op olur ve
	// execDDL gövdesi `FROM spans_local` olan ÖLÜ bir `_local` MV kurar —
	// gerçek MV'nin yanında, kimsenin okumadığı. Kapı dalı tümden keser.
	if err := s.conn.QueryRow(ctx, probeSQL).Scan(&hasApdex); err == nil && hasApdex == 0 &&
		s.mvMigrationShapeOK(ctx, "service_summary_5m", effectApdex) {
		log.Println("[chstore] upgrading service_summary_5m MV (adding apdex states) — past summary buckets will be dropped")
		// In cluster mode the local table is named with a _local
		// suffix, so we drop both flavours; DROP IF EXISTS makes
		// the second a no-op when single-node.
		dropTarget := "service_summary_5m"
		if s.clusterMode() {
			dropTarget = "service_summary_5m_local"
		}
		// v0.5.436 — SYNC waits for ZK metadata cleanup before
		// returning. Without it the immediate re-CREATE hits
		// REPLICA_ALREADY_EXISTS (error 253) because the ZK znode
		// for the dropped Replicated*MergeTree hasn't been
		// reaped yet. Single-node no-op (no ZK to wait for).
		if err := s.dropCombinedMV(ctx, dropTarget); err != nil {
			return fmt.Errorf("drop old MV for upgrade: %w", err)
		}
		// Re-run the create now that the old one is gone.
		if err := s.execDDL(ctx, findMV("service_summary_5m")); err != nil {
			return fmt.Errorf("recreate MV with apdex: %w", err)
		}
	}

	// Sonradan BOYUT kazanan MV'ler — tek döngü, tek defter
	// (mvDimMigrations). Her satır bir system.columns probe'u: kolon
	// yoksa MV DROP + RECREATE edilir, adı findMV ile çözülür (v0.8.52
	// — asla dilim pozisyonuyla). Geçmiş 5 dakikalık kovalar düşer;
	// yalnız yakın pencereler operatöre görünür olduğundan maliyet bir
	// sonraki birleşme döngüsünde (~5 dk) kapanır.
	for _, m := range mvDimMigrations {
		var hasCol uint8
		// v0.10.834 (inceleme, ÖNEMLİ 4) — probe hedefi STORAGE adı.
		// Eski yorum "çıplak adın kolon listesi yerel tabloyla aynıdır"
		// diyordu; doğru ama EKSİK: sarmalayıcı HİÇ YOKSA (henüz kurulmadı)
		// probe 0 satır görüp "kolon eksik" der, dal ateşler ve
		// dropCombinedMV CANLI `_local`i emniyet KAPALI düşürür.
		probe := fmt.Sprintf(`
			SELECT count() > 0
			FROM system.columns
			WHERE database = currentDatabase()
			  AND table    = '%s'
			  AND name     = '%s'`, s.mvStorageName(m.Table), m.Column)
		if err := s.conn.QueryRow(ctx, probe).Scan(&hasCol); err == nil && mvDimNeedsMigration(hasCol != 0) {
			// v0.10.834 — göç dalının GÖVDESİ mv_shape_guard.go'da
			// (upgradeMVDim). İki sebep: (1) dal çıplak adı DROP ediyor,
			// yani "küme kipindeyim → çıplak ad sarmalayıcıdır" varsayımı
			// yanlışsa VERİ KAYBI; kapı orada. (2) migrate() tek parça
			// olduğu için dalın davranışı test edilemiyordu — ayrı metot
			// sahte driver.Conn ile koşturulabiliyor.
			if err := s.upgradeMVDim(ctx, m, findMV(m.Table)); err != nil {
				return err
			}
		}
	}

	// v0.9.1097 (0.5 Alternatif-B, exemplar-pivot unification audit) —
	// db_statement_summary_5m gained MV-embedded exemplar states
	// (argMax slow + argMaxIf error). Sebep yapısal: statement class'ı
	// SERVİSLER ARASI olduğundan ham exemplar taraması service_name
	// predicate'i koyamıyor → PK prefix yok → 1B span/gün ölçeğinde
	// 24h penceresi ~22s (audit §5.3, timeout "veri yok" gibi
	// görünüyordu). MV okuma iki soruyu (slow+error) tek küçük sorguda
	// cevaplar. Aynı drop+recreate şekli (apdex/db_name emsali; CH,
	// MaterializedView'a ADD COLUMN desteklemez) — geçmiş 5dk kovaları
	// düşer, akış ileriye dolar; in-place koruma isteyen operatör için
	// .inner_id ALTER + MODIFY QUERY reçetesi trace_summary_5m notunda.
	if s.hasDBStmtHashCol {
		// v0.9.1098 — probe hedefi STORAGE adı (TDigest emsali,
		// mvStorageName). v0.9.1097 çıplak adı problamıştı; cluster
		// modunda çıplak ad Distributed WRAPPER'dır ve kolonu asla
		// kazanmaz → hasEx hep 0 → upgrade HER BOOT yeniden koşup
		// statement geçmişini siliyordu (canlı doğrulamanın yakaladığı
		// veri-kaybı sınıfı) ve bayrak hiç true olmuyordu.
		var hasEx uint8
		exProbe := fmt.Sprintf(`
			SELECT count() > 0
			FROM system.columns
			WHERE database = currentDatabase()
			  AND table    = '%s'
			  AND name     = 'slow_exemplar_state'`,
			s.mvStorageName("db_statement_summary_5m"))
		// v0.10.834 — şekil kapısı (aynı sınıf; gerekçe mv_shape_guard.go).
		if err := s.conn.QueryRow(ctx, exProbe).Scan(&hasEx); err == nil && hasEx == 0 &&
			s.mvMigrationShapeOK(ctx, "db_statement_summary_5m", effectDBStmtEx) {
			log.Println("[chstore] upgrading db_statement_summary_5m MV (adding exemplar states) — past 5-min buckets will be dropped")
			if err := s.dropCombinedMV(ctx, s.mvStorageName("db_statement_summary_5m")); err != nil {
				return fmt.Errorf("drop old db_statement_summary_5m for upgrade: %w", err)
			}
			if err := s.execDDL(ctx, findMV("db_statement_summary_5m")); err != nil {
				return fmt.Errorf("recreate db_statement_summary_5m with exemplars: %w", err)
			}
		}
		// v0.9.1098 — WRAPPER KOLON KAYMASI iyileştiricisi (upgrade'den
		// BAĞIMSIZ, her boot): Distributed wrapper kolon listesini CREATE
		// anında dondurur; _local iki kolon kazanınca wrapper 11 kolonda
		// kalır ve MV okuması wrapper üzerinden Code 47 ("Unknown
		// identifier slow_exemplar_state") yer. reconcile yalnız EKSİK
		// wrapper'ı onarır, kaymayı asla. Upgrade'e bağlamıyoruz çünkü
		// _local recreate'i deferred-DDL kuyruğuna düşebilir (canlı
		// doğrulamada görüldü) — o boot'ta wrapper tazelenemez; sonraki
		// boot'ta upgrade artık koşmaz ama bu iyileştirici kaymayı görüp
		// kapatır. Soft-fail: wrapper süs değil ama boot'u düşürmeye
		// değmez; başarısızlık her boot yeniden denenir.
		if s.clusterMode() {
			var localHas, wrapperHas uint8
			_ = s.conn.QueryRow(ctx, exProbe).Scan(&localHas)
			_ = s.conn.QueryRow(ctx, `
				SELECT count() > 0
				FROM system.columns
				WHERE database = currentDatabase()
				  AND table    = 'db_statement_summary_5m'
				  AND name     = 'slow_exemplar_state'`).Scan(&wrapperHas)
			// v0.10.834 — şekil kapısı: aşağıdaki DROP çıplak ADI hedefler.
			// localHas==1 şartı çoğu hâlde şekli zaten kanıtlar, ama YARIM
			// TERFİ edilmiş kurulumda (`_local` VAR + çıplak ad hâlâ gerçek
			// MV, v0.10.830 "kalıntı MV" sınıfı) o DROP iç tabloya kaskad
			// ederdi. Kapı çıplak adın Distributed olduğunu şart koşar.
			if localHas == 1 && wrapperHas == 0 && s.mvMigrationShapeOK(ctx, "db_statement_summary_5m", effectDBStmtDrift) {
				log.Println("[chstore] db_statement_summary_5m wrapper kolon kayması — _local'da exemplar state var, wrapper'da yok; wrapper yenileniyor")
				// v0.9.1099 — DOĞRUDAN s.conn.Exec, execDDL DEĞİL (canlı
				// doğrulamanın yakaladığı 1098 regresyonu): bu iki ifade
				// ON CLUSTER'ı ZATEN taşıyor; execDDL→adaptDDL yüksek-hacim
				// tablo adını görüp hedefi _local'a çevirip İKİNCİ bir
				// ON CLUSTER enjekte ediyordu → CREATE code 62 (syntax) ile
				// ölüyor, DROP ise geçiyor ve her boot wrapper'ı silip geri
				// koyamıyordu (Slow Queries UNKNOWN_TABLE). Kardeş onarım
				// yolu cluster.go'da aynı sebepten conn.Exec kullanır.
				on := s.onCluster()
				if err := s.conn.Exec(ctx,
					"DROP TABLE IF EXISTS db_statement_summary_5m"+on+" SYNC"); err != nil {
					log.Printf("[chstore] wrapper drop düştü (sonraki boot yeniden dener): %v", err)
				} else if err := s.conn.Exec(ctx, fmt.Sprintf(
					"CREATE TABLE IF NOT EXISTS db_statement_summary_5m%s AS db_statement_summary_5m_local ENGINE = Distributed(`%s`, currentDatabase(), db_statement_summary_5m_local, %s)",
					on, s.cfg.ClusterName, s.shardKeyFor("db_statement_summary_5m"))); err != nil {
					log.Printf("[chstore] wrapper recreate düştü (sonraki boot yeniden dener): %v", err)
				}
			}
		}
		// Bayrak her boot'ta VERİDEN: upgrade koştuysa da, in-place
		// (elle) eklendiyse de aynı yoldan true olur; dış-dağıtık
		// kurulumda (hasDBStmtHashCol=false) hiç probelanmaz ve okuma
		// ham fallback'te kalır. Cluster modunda probe STORAGE'ı ölçer;
		// okuma wrapper'dan geçtiği için kayma iyileştiricisi yukarıda.
		if err := s.conn.QueryRow(ctx, exProbe).Scan(&hasEx); err == nil {
			s.hasDBStmtExemplarCols = hasEx == 1
		}
	}

	// v0.8.52 (doorway D3) — trace_summary_5m gained entry_route_state (the
	// root span's http.route) so the tracemetrics source can break trace-level
	// RED down by entry endpoint. Same drop+recreate shape as apdex/db_name
	// above (CH can't ADD COLUMN to MaterializedView storage). NOTE: on a
	// running install the column can be added non-destructively in-place —
	// ALTER the .inner_id.<uuid> storage table then `ALTER TABLE
	// trace_summary_5m MODIFY QUERY ...` — which preserves the 90d of per-trace
	// history; this codified path is the robust, cluster-safe (_local +
	// ON CLUSTER + SYNC) fallback that repopulates forward from raw spans. The
	// guard no-ops when the column is already present, so an install migrated
	// in-place keeps its history.
	var hasEntryRoute uint8
	// v0.10.834 (inceleme, ÖNEMLİ 4) — probe hedefi STORAGE adı; gerekçe
	// apdex probe'unda.
	entryRouteProbe := fmt.Sprintf(`
		SELECT count() > 0
		FROM system.columns
		WHERE database = currentDatabase()
		  AND table    = '%s'
		  AND name     = 'entry_route_state'`, s.mvStorageName("trace_summary_5m"))
	// v0.10.834 — şekil kapısı (aynı sınıf; gerekçe mv_shape_guard.go).
	if err := s.conn.QueryRow(ctx, entryRouteProbe).Scan(&hasEntryRoute); err == nil && hasEntryRoute == 0 &&
		s.mvMigrationShapeOK(ctx, "trace_summary_5m", effectEntryRoute) {
		log.Println("[chstore] upgrading trace_summary_5m MV (adding entry_route_state) — past 5-min buckets will be dropped")
		dropTarget := "trace_summary_5m"
		if s.clusterMode() {
			dropTarget = "trace_summary_5m_local"
		}
		// v0.5.436 — SYNC; see apdex upgrade above.
		if err := s.dropCombinedMV(ctx, dropTarget); err != nil {
			return fmt.Errorf("drop old trace_summary_5m for upgrade: %w", err)
		}
		if err := s.execDDL(ctx, findMV("trace_summary_5m")); err != nil {
			return fmt.Errorf("recreate trace_summary_5m with entry_route: %w", err)
		}
	}

	// v0.10.97 (operatör-raporlu "iframe trace'leri") — trace_summary_5m
	// entry_service_state kazandı. v0.8.52 ile aynı drop+recreate şekli;
	// yerinde koruma reçetesi (inner ALTER + MODIFY QUERY, 90g tarihçeyi
	// korur) yukarıdaki notta — prod'da migration'dan ÖNCE elle uygulanırsa
	// bu blok no-op kalır ve tarihçe yaşar.
	//
	// ⚠ DAĞITIK İKİNCİ YARI (bu sınıf prod'u iki kez kırdı): _local'i
	// yeniden yaratmak yetmez — BARE Distributed sarmalayıcı ESKİ şemayla
	// kalır ve yeni kolonu okuyan her sorgu UNKNOWN_COLUMN ile ölür.
	// Sarmalayıcı burada düşürülür; boot sırası migrate →
	// ensureDistributedWrappers olduğundan AYNI boot'ta yeni şemayla
	// (CREATE ... AS _local) geri kurulur.
	var hasEntrySvc uint8
	entrySvcProbe := `
		SELECT count() > 0
		FROM system.columns
		WHERE database = currentDatabase()
		  AND table    = 'trace_summary_5m'
		  AND name     = 'entry_service_state'`
	if s.clusterMode() {
		entrySvcProbe = `
		SELECT count() > 0
		FROM system.columns
		WHERE database = currentDatabase()
		  AND table    = 'trace_summary_5m_local'
		  AND name     = 'entry_service_state'`
	}
	if err := s.conn.QueryRow(ctx, entrySvcProbe).Scan(&hasEntrySvc); err == nil && hasEntrySvc == 0 {
		// v0.10.834 — göç dalının GÖVDESİ mv_shape_guard.go'da
		// (upgradeTraceSummaryEntryService). Bu dal sınıfın en
		// tehlikelisiydi: küme kipinde probe `trace_summary_5m_local`e
		// bakıyor, o tablo YOKSA (tek düğüm şekli) "kolon eksik" çıkıyor,
		// dal ateşliyor ve çıplak `trace_summary_5m` purgeGuard ile
		// DROP ediliyordu — 90 günlük trace tarihçesi, sessizce.
		if err := s.upgradeTraceSummaryEntryService(ctx, findMV("trace_summary_5m")); err != nil {
			return err
		}
	}

	// v0.5.349 — db_summary_5m + db_caller_summary_5m gained an
	// extended peer-service fallback chain (server.address,
	// net.peer.name, db.host, db.name, service_name) so rows
	// no longer collapse to literal "unknown" when peer.service
	// is empty. Probe via system.tables.create_table_query for
	// the new fallback markers; drop + recreate when missing.
	// Past 5-min buckets are dropped (same trade-off as the
	// v0.5.327 db_name migration).
	for _, table := range []string{"db_summary_5m", "db_caller_summary_5m"} {
		// v0.9.1319 — bug-fix: this loop was the ONE upgrade path the
		// v0.8.52 by-name migration missed. It resolved the recreate DDL
		// as mvs[3] / mvs[4], and the slice has grown twice since those
		// constants were written: today index 3 is spanmetrics_1m and 4
		// is spanmetrics_10s, while db_summary_5m sits at 7 and
		// db_caller_summary_5m at 8. On a genuine pre-v0.5.349 upgrade
		// the branch therefore dropped db_summary_5m and then ran
		// `CREATE MATERIALIZED VIEW IF NOT EXISTS spanmetrics_1m`, which
		// no-ops because that MV already exists — so the table stayed
		// GONE for the rest of the process lifetime with no error
		// anywhere and /databases rendered empty. Name lookup kills the
		// whole index-shift class; execDDL now also rejects an empty DDL
		// so a renamed/removed MV fails the boot loudly instead.
		// v0.5.436 — bug-fix: probe the right object in cluster mode.
		// Pre-v0.5.435 the bare name was the MV itself, so
		// create_table_query contained the SELECT body and the
		// 'server.address' string match worked. After v0.5.435 the
		// MV joined highVolumeTables and the bare name is now the
		// Distributed wrapper (whose create_table_query is just
		// `AS <name>_local ENGINE = Distributed(...)` — no SELECT
		// body, no 'server.address' marker). Probe was returning
		// false on every boot → drop-and-recreate fired every
		// startup → ZK collisions (error 253) AND constant 5-min
		// bucket loss. Probe the `_local` flavour in cluster mode
		// so we read the actual MV definition.
		probeTarget := table
		if s.clusterMode() {
			probeTarget = table + "_local"
		}
		var hasNewFallback uint8
		probe := fmt.Sprintf(`
			SELECT count() > 0
			FROM system.tables
			WHERE database = currentDatabase()
			  AND name     = '%s'
			  AND positionUTF8(create_table_query, 'server.address') > 0`, probeTarget)
		// v0.10.834 — şekil kapısı (aynı sınıf; gerekçe mv_shape_guard.go).
		// Bu dalda tetikleme çift yönlü: tek düğüm şeklinde `_local` YOK,
		// probe 0 satır görür ve "eski fallback zinciri" sanıp HER BOOT
		// ateşler.
		if err := s.conn.QueryRow(ctx, probe).Scan(&hasNewFallback); err == nil && hasNewFallback == 0 &&
			s.mvMigrationShapeOK(ctx, table, effectPeerChain) {
			log.Printf("[chstore] upgrading %s MV (peer.service fallback chain) — past 5-min buckets will be dropped", table)
			dropTarget := table
			if s.clusterMode() {
				dropTarget = table + "_local"
			}
			// SYNC — see apdex upgrade above.
			if err := s.dropCombinedMV(ctx, dropTarget); err != nil {
				return fmt.Errorf("drop old %s for upgrade: %w", table, err)
			}
			if err := s.execDDL(ctx, findMV(table)); err != nil {
				return fmt.Errorf("recreate %s with fallback chain: %w", table, err)
			}
		}
	}

	// v0.8.194 — migrate duration_q_state from the reservoir quantilesState to
	// quantilesTDigestState. At billion-span scale each 5-min bucket fills the
	// 8192-sample reservoir (~64 KiB/row, measured on CH 24.8), so merging the
	// column over a wide window scanned ~18 GiB and blew CH's per-query memory
	// limit (code 241) + the execution timeout (code 159) — operator-reported
	// PRODUCTION OOM that left /services + /service-ops rendering only the tiny
	// self-obs service. TDigest state is ~4.3 KiB/row, fixed-size and
	// parallel-safe (~15x smaller). The column NAME is unchanged, so probe the
	// column TYPE: if it's still a reservoir 'quantiles' aggregate (no 'TDigest'
	// in the type signature) drop + recreate with the new TDigest DDL.
	// dropCombinedMV is the prod-proven (v0.8.190) guard-safe drop; recreate
	// repopulates forward (same bounded trade-off as the MV upgrades above). A
	// fresh install already CREATEd these as TDigest in the loop above, so the
	// probe sees TDigest and skips — only an existing reservoir install migrates.
	for _, mv := range []string{
		"service_summary_5m", "operation_summary_5m", "operation_group_summary_5m",
		"db_summary_5m", "db_caller_summary_5m", "messaging_summary_5m",
		"messaging_caller_summary_5m", "spanmetrics_1m", "spanmetrics_10s", "spanmetrics_1s",
	} {
		// CRITICAL guard (mirrors the CREATE-loop + drop guards): the
		// operation_group_summary_5m MV is DISABLED when the spans table lacks
		// the op_group column (external Distributed cluster, cluster_name unset).
		// It was never created, so system.columns returns 0 rows → the TDigest
		// probe below would read isTDigest=0 and RECREATE it — re-adding an
		// insert-trigger that references the missing op_group and failing every
		// span INSERT with code 16, which blocks ALL ingest (the v0.8.186 prod
		// incident). There's nothing to migrate when the MV doesn't exist; skip.
		if mv == "operation_group_summary_5m" && !s.hasOpGroupCol {
			continue
		}
		probeTarget := s.mvStorageName(mv)
		var isTDigest uint8
		probe := fmt.Sprintf(`
			SELECT count() > 0
			FROM system.columns
			WHERE database = currentDatabase()
			  AND table    = '%s'
			  AND name     = 'duration_q_state'
			  AND positionUTF8(type, 'TDigest') > 0`, probeTarget)
		// v0.10.834 — şekil kapısı (aynı sınıf; gerekçe mv_shape_guard.go).
		if err := s.conn.QueryRow(ctx, probe).Scan(&isTDigest); err == nil && isTDigest == 0 &&
			s.mvMigrationShapeOK(ctx, mv, effectTDigest) {
			log.Printf("[chstore] upgrading %s MV (reservoir quantilesState → quantilesTDigestState, ~15x smaller) — past buckets dropped", mv)
			dropTarget := s.mvStorageName(mv)
			if err := s.dropCombinedMV(ctx, dropTarget); err != nil {
				return fmt.Errorf("drop %s for TDigest upgrade: %w", mv, err)
			}
			if err := s.execDDL(ctx, findMV(mv)); err != nil {
				return fmt.Errorf("recreate %s with TDigest state: %w", mv, err)
			}
		}
	}

	// v0.8.162 — operator-reported (external Distributed cluster): the
	// cluster-filter warm query spammed code 47 ("Identifier
	// '__table1.cluster' cannot be resolved") on a fixed cadence. The
	// materialized `cluster` column (v0.8.132) is only added when chstore
	// owns the DDL; against an external Distributed `spans` (ClusterName
	// unset → no ON CLUSTER) it never reaches spans_local, so every query
	// referencing `cluster` fails. Probe the ACTUAL read path — a tiny
	// recent-window select that routes to spans_local in distributed mode.
	// A non-trivial predicate (not 1=0) forces shard analysis so the
	// optimizer can't fold the query away before resolving the column.
	// On resolve-error every cluster expression falls back to the pure
	// res/attr derive (see clusterExpr).
	probeRows, probeErr := s.conn.Query(ctx,
		`SELECT cluster FROM spans WHERE time >= now() - INTERVAL 1 SECOND LIMIT 1 SETTINGS max_execution_time = 3`)
	// v0.8.185 — operator-reported PRODUCTION PANIC (external distributed):
	// on a Query ERROR clickhouse-go returns a NON-NIL but half-initialised
	// *rows, so the old `if probeRows != nil { Close() }` nil-derefs inside
	// Close() and crash-loops the pod at boot. NEVER touch the rows on error.
	maybeCloseRows(probeRows, probeErr)
	s.hasClusterCol = probeErr == nil
	if !s.hasClusterCol {
		log.Printf("[chstore] `cluster` column not resolvable on spans (%v) — cluster filter queries use the res/attr derive (expected on an external Distributed cluster with cluster_name unset)", probeErr)
	}

	// v0.8.211 — surface the silent empty-MV state: when `spans` is an external
	// Distributed table but cluster_name is unset, adaptDDL can't rewrite MV
	// bodies to FROM spans_local ON CLUSTER, so their per-shard insert trigger
	// never fires and every summary MV stays EMPTY → reads return no/partial
	// results. Previously this only manifested as mysteriously empty dashboards;
	// now it's a loud boot WARNING (with the cluster to set) + a /admin/stats
	// health flag (SystemHealth.ExternalDistributedSpansUnset).
	if s.spansIsExternalDistributed(ctx) {
		log.Printf("[chstore] WARNING: %s", externalDistributedWarning(s.discoverSpansCluster(ctx)))
	}

	log.Println("[chstore] migrations complete")
	return nil
}

// externalDistributedWarning builds the operator-facing guidance for the
// empty-MV-risk state (spans is an external Distributed table with cluster_name
// unset, so MV insert-triggers never fire). cluster is the discovered cluster
// name the external `spans` fans to (may be "" if unparseable). Pure so the
// actionable fix string is unit-tested (v0.8.211).
// externalDistributedFatal reports whether boot should HARD-ERROR on the
// external-Distributed-unset state. Pure so the gate is unit-tested. Fatal when
// `spans` is an external Distributed table (isExternal) AND the operator has NOT
// opted into degraded mode (allowUnset). Never fatal otherwise — single-node and
// Coremetry-owned-cluster installs are unaffected. v0.8.213.
func externalDistributedFatal(isExternal, allowUnset bool) bool {
	return isExternal && !allowUnset
}

func externalDistributedWarning(cluster string) string {
	fix := "set COREMETRY_CH_CLUSTER_NAME to the cluster the external spans fans to"
	if cluster != "" {
		fix = "set COREMETRY_CH_CLUSTER_NAME=" + cluster
	}
	return "external Distributed `spans` detected but COREMETRY_CH_CLUSTER_NAME is unset — " +
		"materialized views read FROM the Distributed wrapper, so their per-shard insert trigger " +
		"never fires and summary MVs (service_summary_5m, trace_service_index_5m, …) stay EMPTY, " +
		"making reads return no/partial results. Fix: " + fix + "."
}

// rowsCloser is the Close half of driver.Rows — narrowed so maybeCloseRows is
// unit-testable with a fake.
type rowsCloser interface{ Close() error }

// maybeCloseRows closes a Query's rows ONLY when the query SUCCEEDED. On a
// query error clickhouse-go (v2.46) returns a NON-NIL but partially-
// initialised *rows whose Close() nil-dereferences — so guarding on `rows !=
// nil` alone still panics (the production crash-loop on the external distributed
// cluster, v0.8.185, where `SELECT cluster FROM spans` errors because the
// materialized column never reached spans_local). Gate on the error: never
// touch the rows when the query failed.
func maybeCloseRows(rows rowsCloser, queryErr error) {
	if queryErr == nil && rows != nil {
		_ = rows.Close()
	}
}
