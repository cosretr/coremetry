package config

import (
	"log"
	"os"
	"strconv"
	"strings"
	"time"

	"gopkg.in/yaml.v3"
)

// splitCSV trims whitespace and drops empty entries.
func splitCSV(s string) []string {
	parts := strings.Split(s, ",")
	out := make([]string, 0, len(parts))
	for _, p := range parts {
		if p = strings.TrimSpace(p); p != "" {
			out = append(out, p)
		}
	}
	return out
}

type Config struct {
	Listen     ListenConfig     `yaml:"listen"`
	ClickHouse CHConfig         `yaml:"clickhouse"`
	Retention  RetentionConfig  `yaml:"retention"`
	Ingestion  IngestionConfig  `yaml:"ingestion"`
	Auth       AuthConfig       `yaml:"auth"`
	Redis      RedisConfig      `yaml:"redis"`
	Logs       LogsConfig       `yaml:"logs"`
	AI         AIConfig         `yaml:"ai"`
	Background BackgroundConfig `yaml:"background"`
	Exemplars  ExemplarsConfig  `yaml:"exemplars"`
	// PublicURL is the operator-facing base URL of this
	// Coremetry deployment (e.g. https://coremetry.bank.local).
	// Notification bodies (Slack / Teams / Zoom / email /
	// generic webhook) include deep-links to the relevant
	// problem / anomaly / incident detail when set. Empty
	// disables the linking — back-compat for deployments
	// where the URL isn't reachable from the recipient's
	// network.
	PublicURL string `yaml:"public_url"`
	// AllowedOrigins (v0.10.804, dış skill denetimi M4) — tarayıcı
	// çapraz-origin isteklerine CORS başlığı yazılacak origin'ler
	// (`https://apm.example.com` biçiminde; COREMETRY_ALLOWED_ORIGINS
	// virgülle). Boş = yalnız aynı-origin (Origin host == Host) ve
	// PublicURL'in origin'i. Eskiden her Origin yansıtılıp
	// Allow-Credentials: true yazılıyordu. Allowlist dışı Origin'de
	// /api/mcp* 403 döner.
	AllowedOrigins []string `yaml:"allowed_origins"`
}

// BackgroundConfig controls the cadence of every internal worker
// loop — anomaly detector, recorder, status probes, etc. Default
// values match what was hard-coded in main.go pre-v0.4.95. Tuning
// these matters at scale: a 2-min detector tick on a busy stack
// adds up to non-trivial CH load, and operators on slow CH
// clusters want to back off; operators on demo deployments
// often want to crank them down so anomalies surface quickly.
//
// Each field is a duration; zero means "use the default". The
// defaults() function applies them so a config file that names
// the section but omits a knob still gets the sensible value.
type BackgroundConfig struct {
	// Interval between anomaly-detector sweeps. Default 2m.
	AnomalyInterval time.Duration `yaml:"anomaly_interval"`
	// Recorder cadence + backfill window. Default 1m / 5m.
	AnomalyRecordInterval time.Duration `yaml:"anomaly_record_interval"`
	AnomalyRecordBackfill time.Duration `yaml:"anomaly_record_backfill"`
	// SMTP settings refresh TTL. Default 30s — short so the
	// operator's Settings change is picked up on the next
	// alert send without a restart.
	SMTPCacheTTL time.Duration `yaml:"smtp_cache_ttl"`
	// Status probe ceiling — hard timeout on /api/status so a
	// stuck CH/Redis client driver doesn't park the goroutine
	// forever. Default 5s, well above the per-probe 2s timeout.
	StatusProbeTimeout time.Duration `yaml:"status_probe_timeout"`
	// LogAnomalyEnabled gates the worker-role log-pattern anomaly
	// recorder + Drain template puller — the jobs that periodically
	// QUERY the logstore (ES at billion-doc scale: curated-pattern
	// _msearch, significant_text, sample pulls). Default true. Set
	// COREMETRY_LOG_ANOMALY_ENABLED=false to silence that ES traffic
	// when the operator doesn't want log-based anomalies. Metric
	// anomaly detection (CH-backed) is unaffected.
	LogAnomalyEnabled bool `yaml:"log_anomaly_enabled"`
}

// AIConfig wires the optional AI Copilot. Three providers supported:
//   - "anthropic" (default): APIKey is an `sk-ant-…` key from the
//     Anthropic console.
//   - "github":              APIKey is a GitHub OAuth token (`ghu_…`)
//     with Copilot access; Coremetry exchanges it for a session token
//     and calls api.githubcopilot.com (OpenAI-compatible).
//   - "openai":              Any OpenAI-compatible /v1/chat/completions
//     endpoint. Drives self-hosted local LLMs (Ollama, LM Studio,
//     vLLM, llama.cpp server) and the real OpenAI API. Set BaseURL
//     to your local endpoint (e.g. http://ollama:11434/v1) and
//     APIKey is optional for endpoints that don't gate on it.
//
// Env config is the boot-time default; the admin Settings tab can
// override at runtime, persisted to system_settings.
type AIConfig struct {
	Provider string `yaml:"provider"` // env: COREMETRY_AI_PROVIDER (anthropic|github|openai)
	APIKey   string `yaml:"api_key"`  // env: COREMETRY_AI_API_KEY
	Model    string `yaml:"model"`    // env: COREMETRY_AI_MODEL
	BaseURL  string `yaml:"base_url"` // env: COREMETRY_AI_BASE_URL (openai provider only)
}

// LogsConfig picks which read backend serves /api/logs. Ingest still
// always writes to ClickHouse — this only changes the read path so an
// operator can point Coremetry at an external ES that their existing
// shipping pipeline already populates, without re-indexing.
//
//	backend: clickhouse  → query the local CH `logs` table (default)
//	backend: elasticsearch → query Elasticsearch via Elastic.Addresses
type LogsConfig struct {
	Backend       string   `yaml:"backend"` // "clickhouse" (default) | "elasticsearch"
	Elasticsearch ESConfig `yaml:"elasticsearch"`
}

// ESConfig mirrors logstore.ESConfig. Kept here so the config package
// stays the single source of truth for env-var bindings; main.go copies
// these fields into the logstore.ESConfig at construction time.
type ESConfig struct {
	Addresses          []string `yaml:"addresses"`
	Username           string   `yaml:"username"`
	Password           string   `yaml:"password"`
	APIKey             string   `yaml:"api_key"`
	InsecureSkipVerify bool     `yaml:"insecure_skip_verify"`
	Index              string   `yaml:"index"`
	// IndexTemplate (v0.8.231) narrows service-scoped queries to the
	// concrete per-service index instead of fanning out over Index.
	// Placeholders: {service} = the queried service name verbatim,
	// {namespace} = the service's namespace resolved from span resource
	// attributes (k8s.namespace.name / service.namespace); unresolved →
	// "*". Example: "app-{service}.{namespace}". Empty = disabled.
	IndexTemplate string `yaml:"index_template"` // env: COREMETRY_ES_INDEX_TEMPLATE
	// MLEnabled turns on the v0.5.120 read-only ML anomaly job
	// poller — Coremetry calls /_ml/anomaly_detectors and ingests
	// significant records into anomaly_events so existing Elastic
	// ML jobs surface on the /anomalies page alongside the native
	// detectors. Read-only against Elastic.
	MLEnabled bool `yaml:"ml_enabled"`
	// MLMinScore overrides the per-record score threshold (default
	// 75 — Elastic's "critical" band; lower brings more noise).
	MLMinScore float64 `yaml:"ml_min_score"`
	// Fields pins Coremetry's ES query to the operator's document
	// mapping (field paths). Empty members fall back to the ECS-ish
	// defaults in logstore (@timestamp / trace.id / span.id /
	// service.name / message / log.level). Set these when the log
	// pipeline uses different paths so Coremetry queries the right
	// fields WITHOUT re-indexing — e.g. trace_id instead of trace.id.
	Fields ESFieldsConfig `yaml:"fields"`
}

// ESFieldsConfig is the env/yaml binding for the ES document field
// map. Mirrors logstore.ESFieldMap; main.go copies it across at
// construction. Each member maps to a COREMETRY_ES_FIELD_<NAME> env
// var (see Load). Leaving one empty keeps the logstore default.
type ESFieldsConfig struct {
	Timestamp      string `yaml:"timestamp"`       // env: COREMETRY_ES_FIELD_TIMESTAMP   (default @timestamp)
	TraceID        string `yaml:"trace_id"`        // env: COREMETRY_ES_FIELD_TRACE_ID    (default trace.id)
	SpanID         string `yaml:"span_id"`         // env: COREMETRY_ES_FIELD_SPAN_ID     (default span.id)
	Service        string `yaml:"service"`         // env: COREMETRY_ES_FIELD_SERVICE     (default service.name)
	Message        string `yaml:"message"`         // env: COREMETRY_ES_FIELD_MESSAGE     (default message)
	SeverityText   string `yaml:"severity_text"`   // env: COREMETRY_ES_FIELD_SEVERITY_TEXT   (default log.level)
	SeverityNumber string `yaml:"severity_number"` // env: COREMETRY_ES_FIELD_SEVERITY_NUMBER (default "" — skipped)
	// Environment (v0.8.400 — env-separation Phase 4): the document
	// field the ?env= filter targets. Default "" = SELF-DISCOVER via a
	// cached field_caps over the candidate shapes (logstore
	// es_env_field.go); set only when the pipeline uses a custom path.
	Environment string `yaml:"environment"` // env: COREMETRY_ES_FIELD_ENV (default "" — self-discover)
}

// ExemplarsConfig gates OTLP metric-exemplar ingest (v0.8.328, cross-signal
// pivot). RequireTraceContext (yaml exemplars.require_trace_context, default
// TRUE) drops exemplars that carry no trace_id — a stored exemplar exists to
// be clicked through to its trace, so trace-less ones are dead weight unless
// the operator explicitly wants them.
//
// Zero-value handling: the default lives in the `defaults` var (true) and
// Load unmarshals the YAML ON TOP of it — an absent key keeps true while an
// explicit `require_trace_context: false` is honoured. A post-load zero-fill
// (the retention-days pattern) would be WRONG for a bool: it can't tell
// "unset" from "operator said false". Same mechanism as
// Background.LogAnomalyEnabled.
type ExemplarsConfig struct {
	RequireTraceContext bool `yaml:"require_trace_context"`
	// MaxPerSeriesPerMinute (v0.8.433, exemplar audit Faz C) — ingest-side
	// cap: at most N exemplars per series_fingerprint per wall-clock
	// minute; excess is dropped (intentional, counted separately from
	// data loss). 0 = unlimited (the default and the pre-Faz-C behavior:
	// exemplar volume is producer-bounded — SDKs keep ~1 per series per
	// export — so most installs never need this). Set it when a
	// misbehaving SDK or a custom exporter floods the exemplars table.
	MaxPerSeriesPerMinute int `yaml:"max_per_series_per_minute"` // env: COREMETRY_EXEMPLARS_MAX_PER_SERIES_MIN
}

// RedisConfig is fully optional. When URL is empty Coremetry runs in
// single-instance mode: no cache (always misses) and the in-process
// "always-leader" lock — meaning background workers always run.
type RedisConfig struct {
	URL string `yaml:"url"` // e.g. "redis://localhost:6379/0"
}

// AuthConfig drives JWT + initial-admin bootstrap. The HMAC secret is
// generated on first run if neither config nor env supply one — but that
// rotates every restart and invalidates sessions, so production deployments
// should set it explicitly.
type AuthConfig struct {
	JWTSecret       string        `yaml:"jwt_secret"`       // HS256 key — set via COREMETRY_JWT_SECRET in prod
	TokenTTL        time.Duration `yaml:"token_ttl"`        // session lifetime (default 24h)
	InitialAdmin    string        `yaml:"initial_admin"`    // email — seeded if users table is empty
	InitialPassword string        `yaml:"initial_password"` // bcrypted on first boot
	// AdminReset (COREMETRY_ADMIN_RESET) makes the env creds authoritative for
	// the bootstrap admin: when true, InitialAdmin's password is reconciled
	// from InitialPassword on EVERY boot, even if the users table already has
	// rows. Set once to recover a locked-out admin (then remove), or leave on
	// for GitOps installs where the secret is the source of truth. Default off
	// preserves the seed-once behaviour (UI password rotation survives restart).
	AdminReset    bool                `yaml:"admin_reset"`
	OIDC          OIDCConfig          `yaml:"oidc"`
	TrustedHeader TrustedHeaderConfig `yaml:"trusted_header"`

	// Demo only — when true, /api/auth/config exposes the initial admin
	// credentials so the login page can pre-fill them. NEVER enable in
	// production: anyone hitting /api/auth/config gets the admin password.
	DemoMode bool `yaml:"demo_mode"`
}

// TrustedHeaderConfig wires the oauth2-proxy / IAP / Cloudflare Access
// pattern: an upstream proxy validates SSO and sets identity headers
// on the request, and Coremetry trusts them without re-doing the
// OIDC dance itself. Common for banks running oauth2-proxy + Dex /
// Keycloak in front of every internal service so each app doesn't
// need its own OIDC client registration.
//
// SECURITY: this mode is only safe behind a proxy that strips +
// re-injects the headers. Anyone able to send a raw request to
// Coremetry on a network where the proxy isn't enforced could
// spoof `X-Auth-Request-Email: admin@bank.com` and become admin.
// TrustedProxies enforces source-IP gating; we refuse to honour
// the headers from any other source.
type TrustedHeaderConfig struct {
	Enabled bool `yaml:"enabled"`
	// Header names — defaults match oauth2-proxy (which is the
	// dominant implementation in the OAuth-proxy-fronts-app
	// pattern). Operators using a different proxy override.
	EmailHeader  string `yaml:"email_header"`  // default "X-Auth-Request-Email"
	UserHeader   string `yaml:"user_header"`   // default "X-Auth-Request-User"
	GroupsHeader string `yaml:"groups_header"` // default "X-Auth-Request-Groups"
	// AutoProvision: first-sight user lands in the users table
	// with DefaultRole. Without it, an unmapped email returns
	// 403 — admins pre-create accounts.
	AutoProvision bool   `yaml:"auto_provision"`
	DefaultRole   string `yaml:"default_role"` // default "viewer"
	// TrustedProxies — CIDR blocks the headers are accepted
	// from. Required when Enabled is true; an empty list with
	// Enabled=true is a config error (the validate step refuses
	// to boot to keep operators from accidentally opening a
	// header-spoofing hole).
	TrustedProxies []string `yaml:"trusted_proxies"`
}

// OIDCConfig is fully optional — when Enabled is false, only local
// username/password auth is offered. Local auth is never disabled, even
// when OIDC is on, so admins always have a fallback path.
type OIDCConfig struct {
	Enabled        bool     `yaml:"enabled"`
	IssuerURL      string   `yaml:"issuer_url"` // e.g. https://accounts.google.com
	ClientID       string   `yaml:"client_id"`
	ClientSecret   string   `yaml:"client_secret"`
	RedirectURL    string   `yaml:"redirect_url"`    // public URL of /api/auth/oidc/callback
	Scopes         []string `yaml:"scopes"`          // default: ["openid", "email", "profile"]
	DisplayName    string   `yaml:"display_name"`    // shown on login button (default: "SSO")
	DefaultRole    string   `yaml:"default_role"`    // role for first-time OIDC users (default: viewer)
	AllowedDomains []string `yaml:"allowed_domains"` // optional email-domain whitelist (e.g. ["acme.com"])
}

type ListenConfig struct {
	HTTP string `yaml:"http"`
	GRPC string `yaml:"grpc"`
	// OTLPHTTP is a DEDICATED OTLP/HTTP listener (POST /v1/{traces,logs,metrics}),
	// bound separately from HTTP (which also serves the Web UI + REST API on the
	// same socket). Default ":4318" — the OTel-convention port — so external
	// collectors push OTLP/HTTP to the standard port WITHOUT reaching the
	// login-gated UI that shares :8088. Empty disables it (OTLP/HTTP still
	// answers on HTTP/:8088). Only started in the ingest role. Serves plain
	// HTTP — TLS is terminated at the edge (OpenShift Route edge termination /
	// Ingress / LB), never in-binary. v0.9.168.
	OTLPHTTP string `yaml:"otlp_http"`
}

// CHConfig describes the ClickHouse connection. `Addr` accepts either
// a single endpoint or a comma-separated list of seeds (e.g.
// "ch1.example:9440,ch2.example:9440,ch3.example:9440,ch4.example:9440") — driver
// load-balances + fails over across them, so an external N-node
// cluster can be configured without an upstream LB.
//
// `Secure` toggles native-TLS (port 9440); leave false for plain
// 9000.  `InsecureSkipVerify` is the escape hatch for self-signed
// internal certs — set false in production once a CA bundle is in
// place.
type CHConfig struct {
	Addr               string `yaml:"addr"` // comma-separated for cluster
	Database           string `yaml:"database"`
	Username           string `yaml:"username"`
	Password           string `yaml:"password"`
	Secure             bool   `yaml:"secure"`               // native-TLS (9440)
	InsecureSkipVerify bool   `yaml:"insecure_skip_verify"` // self-signed CA escape hatch
	MaxOpenConns       int    `yaml:"max_open_conns"`
	DialTimeout        string `yaml:"dial_timeout"`

	// ClusterName turns on Distributed-CH mode. When non-empty:
	//   - All DDL gets `ON CLUSTER <ClusterName>` so schema is
	//     applied across every node in the named ZK-coordinated
	//     cluster (cluster definition lives in CH's remote_servers).
	//   - High-volume tables (spans, logs, metric_points, profiles)
	//     are created as `<name>_local` ReplicatedMergeTree on each
	//     shard plus a `<name>` Distributed wrapper that fans out
	//     inserts and queries.
	//   - Materialized views feed the *_local tables; their
	//     Distributed wrappers re-export.
	// When empty (default), single-node MergeTree behaviour is
	// preserved exactly — existing deployments keep working.
	ClusterName string `yaml:"cluster_name"`
	// ReplicaPath is the ZooKeeper / Keeper prefix used for
	// ReplicatedMergeTree path argument. {shard}/{replica} macros
	// are appended automatically. Default: "/clickhouse/tables".
	ReplicaPath string `yaml:"replica_path"`
	// ShardKey: the SQL expression used as the Distributed shard
	// key. Defaults to "rand()" — even distribution, no locality
	// guarantee. Set to "cityHash64(trace_id)" if you want all
	// spans of a trace to land on the same shard (faster joins,
	// at the cost of slightly less even rows-per-shard).
	ShardKey string `yaml:"shard_key"`
	// AllowUnsetCluster (COREMETRY_CH_ALLOW_UNSET_CLUSTER) is the escape hatch
	// for the genuinely-broken external-Distributed-unset state: `spans` is an
	// external Distributed table but ClusterName is empty, so Coremetry can't
	// own spans_local — MV insert-triggers never fire (empty dashboards) and
	// op_group ALTERs can't reach the shards. By default boot HARD-ERRORS there
	// with the cluster to set; set this true to run in degraded mode anyway
	// (raw-spans reads only). v0.8.213.
	AllowUnsetCluster bool `yaml:"allow_unset_cluster"`
	// InsertDistributedSync (COREMETRY_CH_INSERT_DISTRIBUTED_SYNC, v0.10.778) —
	// Distributed tablolara INSERT'i SENKRON yapar (insert_distributed_sync=1):
	// satırlar shard'lara sorgu içinde gider, yerel spool'a YAZILMAZ. Prod
	// 2026-09-17: gönderici asılı kaldı, 514K dosya aranamaz oldu; operatör
	// kararıyla İMAJDA VARSAYILAN AÇIK (Dockerfile ENV=1, v0.10.779). Bedeli:
	// hedef shard erişilmezse INSERT hata verir (write_failed sayacı; spool'a
	// düşmez) ve ingest podunun insert'i shard'ların MV kaskadını bekler. Eski
	// spool davranışı için env 0. Kod varsayılanı kapalı (env yoksa).
	InsertDistributedSync bool `yaml:"insert_distributed_sync"`
	// v0.10.790 — replika-duyarlı okuma/yazma ayarları (operatör 2026-09-19,
	// test ortamı: aynı sorgu her yenilemede farklı sayı; replikalar
	// ıraksamıştı). Deployment bu ayarları taşımayabilir; imaj varsayılanı
	// taşır, chart/ortam env'i ezer.
	//
	// ReadMaxReplicaDelayS (COREMETRY_CH_READ_MAX_REPLICA_DELAY, saniye) —
	// Distributed SELECT'te replikasyon gecikmesi bu eşiği aşan replika
	// seçimden düşer (max_replica_delay_for_distributed_queries; CH varsayılanı
	// 300). İmajda 60. Tüm replikalar geçmişse yine de bayat olan kullanılır
	// (fallback_to_stale_replicas_for_distributed_queries=1, CH varsayılanı) —
	// erişilebilirlik korunur. 0 = CH varsayılanı. AYRI ZK yolunda yaşayan
	// (birbirini replike etmeyen) replikalara çare DEĞİL; o küme yapılandırması.
	ReadMaxReplicaDelayS int `yaml:"read_max_replica_delay_s"`
	// MVDedupBlocks (COREMETRY_CH_MV_DEDUP_BLOCKS) — Replicated tablo aynı
	// bloğu ikinci kez görünce (zaman aşımı sonrası yeniden deneme) ham satırı
	// tekilleştirir; MV'ler bunu VARSAYILANDA yapmaz ve MV sayımı ham'ı aşar.
	// deduplicate_blocks_in_dependent_materialized_views=1 ikisini hizalar.
	// İmajda 1.
	MVDedupBlocks bool `yaml:"mv_dedup_blocks"`
	// InsertQuorum (COREMETRY_CH_INSERT_QUORUM, ≥2) — INSERT en az N
	// replikaya yazılana dek döner (insert_quorum, paralel, 60 sn). Replika
	// düşükken INSERT hata verir (write_failed); erişilebilirlik bedeli
	// olduğu için İMAJDA AÇIK DEĞİL, bilinçli opt-in. 0/1 = kapalı.
	InsertQuorum int `yaml:"insert_quorum"`

	// Per-query memory limits (v0.9.184) — env-tunable so a large
	// external cluster can raise the conservative built-in defaults
	// (4GB cap / 1GB spill / 1GB sort) without a rebuild. 0 = keep the
	// default. A fleet-wide aggregation (errors-inbox refresh) hit the
	// 4GB cap with CH code 241 "memory limit exceeded" on a big prod
	// cluster whose nodes have far more RAM than 4GB.
	//   COREMETRY_CH_MAX_MEMORY_USAGE
	//   COREMETRY_CH_MAX_BYTES_EXTERNAL_GROUP_BY
	//   COREMETRY_CH_MAX_BYTES_EXTERNAL_SORT
	MaxMemoryUsage          int64 `yaml:"max_memory_usage"`
	MaxBytesExternalGroupBy int64 `yaml:"max_bytes_external_group_by"`
	MaxBytesExternalSort    int64 `yaml:"max_bytes_external_sort"`

	// MemFraction (v0.9.975) — the share of the server's OWN ceiling
	// (max_server_memory_usage) a single query may claim. The limits
	// above are only a request now: boot reads the server ceiling and
	// applies min(requested, MemFraction × serverMax), because a
	// per-query cap larger than the server total never fires — CH hits
	// its server-wide OvercommitTracker first and that kills a VICTIM,
	// not the greedy query. 0 = default 0.6; clamped to [0.1, 0.9].
	// Fail-open when the server ceiling can't be read.
	//   COREMETRY_CH_MEM_FRACTION
	MemFraction float64 `yaml:"mem_fraction"`
	// DisableParallelViews (v0.10.511, dış denetim C6 ölçümü) — spans
	// INSERT'inde 19 MV'nin PARALEL itilmesini kapatır
	// (parallel_view_processing=0 → sıralı). Varsayılan KAPALI DEĞİL: sıfır
	// değer = paralel (v0.10.240 davranışı aynen). Yalnız prod A/B ölçümü
	// için rebuild'siz anahtar; karar kuralı docs/RELEASE-1.0.md §Env.
	//   COREMETRY_CH_PARALLEL_VIEWS=0|false|off → kapalı
	DisableParallelViews bool `yaml:"disable_parallel_views"`
}

// Hosts splits Addr on commas and trims surrounding whitespace, so
// the chart can hand us a single env var with multiple seeds.
func (c CHConfig) Hosts() []string { return splitCSV(c.Addr) }

// chBytesEnv reads a positive plain-integer byte count from env into
// dst. On a non-integer / non-positive value it WARNS (v0.9.185) rather
// than silently discarding — operators reach for k8s "12Gi"/"12G"
// memory syntax, which ParseInt rejects; a silent drop would leave the
// default 4GB cap (and the code-241 empty-inbox symptom) in place with
// zero diagnostic. Empty (unset) is the normal no-op — no warning.
func chBytesEnv(key string, dst *int64) {
	v := os.Getenv(key)
	if v == "" {
		return
	}
	if n, err := strconv.ParseInt(v, 10, 64); err == nil && n > 0 {
		*dst = n
		return
	}
	log.Printf("[config] WARNING: %s=%q geçersiz — bayt cinsinden düz tamsayı bekleniyor "+
		"(ör. 12000000000; \"12Gi\"/\"12G\" DEĞİL). Yoksayılıyor, mevcut varsayılan korunuyor.", key, v)
}

// chFractionEnv reads a 0-1 ratio from env into dst (v0.9.975). Same
// contract as chBytesEnv: WARN rather than silently discard, because an
// operator reaching for "60" or "60%" instead of "0.6" would otherwise
// get the default with zero diagnostic. Out-of-band values are NOT
// rejected here — chstore clamps them to [0.1, 0.9] and logs the
// effective ratio at boot, so the two logs together tell the story.
func chFractionEnv(key string, dst *float64) {
	v := os.Getenv(key)
	if v == "" {
		return
	}
	if f, err := strconv.ParseFloat(v, 64); err == nil && f > 0 {
		*dst = f
		return
	}
	log.Printf("[config] WARNING: %s=%q geçersiz — 0 ile 1 arasında ondalık bir oran bekleniyor "+
		"(ör. 0.6; \"60\"/\"60%%\" DEĞİL). Yoksayılıyor, varsayılan oran korunuyor.", key, v)
}

type RetentionConfig struct {
	SpansDays   int `yaml:"spans_days"`
	LogsDays    int `yaml:"logs_days"`
	MetricsDays int `yaml:"metrics_days"`
}

type IngestionConfig struct {
	BatchSize     int           `yaml:"batch_size"`
	BufferSize    int           `yaml:"buffer_size"`
	FlushInterval time.Duration `yaml:"flush_interval"`
	Workers       int           `yaml:"workers"`
	// ByteBudgetMB caps the APPROXIMATE megabytes EACH signal consumer
	// may hold in memory — channel backlog + accumulating and in-flight
	// batches (v0.8.355, HA audit 🟡#1). BufferSize alone bounds item
	// COUNT; with fat items (15-25KB Java stack-trace log bodies) a
	// 500k-item buffer behind a stalled ClickHouse is multi-GB and the
	// kubelet OOMKill destroys ALL buffered signals — a counted drop
	// loses less. ×5 math: the budget is PER consumer and there are 5
	// (spans / logs / metrics / exemplars / span_links), so worst-case
	// buffered memory ≈ 5 × ByteBudgetMB — the 512 default bounds it at
	// ~2.5GB, sized for typical 4-8GB pods. Explicit 0 disables the
	// byte cap (count-only, pre-v0.8.355 behavior).
	ByteBudgetMB int `yaml:"byte_budget_mb"`
}

var defaults = Config{
	Listen: ListenConfig{HTTP: ":8088", GRPC: ":4317", OTLPHTTP: ":4318"},
	ClickHouse: CHConfig{
		Addr: "127.0.0.1:9000", Database: "coremetry",
		// MaxOpenConns 0 = "derive from the ingest flush fan-out" — see
		// resolveMaxOpenConns. A non-zero value here would shadow that
		// derivation; the v0.8.205 prod incident was exactly that (a
		// hardcoded 10 starved 24+ flushers of connections).
		Username: "default", MaxOpenConns: 0, DialTimeout: "5s",
	},
	// v0.8.246 — operator default: 7 days across all signals ("default
	// data retention 7 gün olsun"). Fresh installs create table TTLs at
	// 7d; the retention enforcer uses these when no operator override
	// is persisted (system_settings retention.* always wins). Raise via
	// config.yaml retention block or the admin Retention tab.
	Retention: RetentionConfig{SpansDays: 7, LogsDays: 7, MetricsDays: 7},
	// Defaults tuned for production-grade ingest at ~1B spans/day
	// (12k/sec average, 50k/sec burst). Workers parallelise the CH
	// insert path so a 200ms stall on one flush doesn't queue up
	// behind it. BufferSize 500k gives ~10s of burst headroom even
	// when all workers are mid-flush. ByteBudgetMB 512 additionally
	// caps each of the 5 consumers by BYTES (≈2.5GB total worst case)
	// so fat items can't turn that headroom into an OOMKill (v0.8.355).
	// v0.10.695 — BatchSize 10k → 50k VARSAYILAN (operatör kararı 2026-09-12; CH mimari
	// denetimi 646 öneri 1: resmî rehber 10k–100k, 10k alt sınırdaydı). Prod ölçüm
	// paneli (683) tek koordinatör host'ta 46 günde DelayedInserts 116K + RejectedInserts
	// 1.8K gösterdi — parça baskısı; daha büyük batch = daha az parça. Byte bütçesi
	// (512 MB) ve tampon (500k) aynen; COREMETRY_INGEST_BATCH_SIZE ile geçersiz kılınır.
	Ingestion: IngestionConfig{BatchSize: 50_000, BufferSize: 500_000, FlushInterval: 5 * time.Second, Workers: 8, ByteBudgetMB: 512}, // v0.10.240 — 2 s → 5 s: part churn (perf audit ING-3); COREMETRY_INGEST_FLUSH_INTERVAL ile geçersiz kılınır
	Auth: AuthConfig{
		TokenTTL:        24 * time.Hour,
		InitialAdmin:    "admin@coremetry.local",
		InitialPassword: "admin",
	},
	Background: BackgroundConfig{
		AnomalyInterval:       2 * time.Minute,
		AnomalyRecordInterval: 1 * time.Minute,
		AnomalyRecordBackfill: 5 * time.Minute,
		SMTPCacheTTL:          30 * time.Second,
		StatusProbeTimeout:    5 * time.Second,
		LogAnomalyEnabled:     true,
	},
	// v0.8.328 — exemplars without trace context are dropped by default;
	// yaml merges over this so only an explicit false disables the gate.
	Exemplars: ExemplarsConfig{RequireTraceContext: true},
}

// applyBackgroundDefaults fills zero-valued duration fields on
// the loaded BackgroundConfig with their canonical defaults.
// Called after YAML parse so a partial config (e.g. only
// AnomalyInterval set) keeps reasonable values for the rest.
func applyBackgroundDefaults(b *BackgroundConfig) {
	if b.AnomalyInterval == 0 {
		b.AnomalyInterval = defaults.Background.AnomalyInterval
	}
	if b.AnomalyRecordInterval == 0 {
		b.AnomalyRecordInterval = defaults.Background.AnomalyRecordInterval
	}
	if b.AnomalyRecordBackfill == 0 {
		b.AnomalyRecordBackfill = defaults.Background.AnomalyRecordBackfill
	}
	if b.SMTPCacheTTL == 0 {
		b.SMTPCacheTTL = defaults.Background.SMTPCacheTTL
	}
	if b.StatusProbeTimeout == 0 {
		b.StatusProbeTimeout = defaults.Background.StatusProbeTimeout
	}
}

// resolveLogAnomalyEnabled applies the COREMETRY_LOG_ANOMALY_ENABLED
// override on top of the current (default-true) value. The detector
// defaults ON; only an explicit "false"/"0" silences the worker-role
// log-pattern recorder + Drain templater (the periodic logstore/ES
// traffic). Anything else — unset, "true", "1", or garbage — leaves
// the current value untouched, so the default stays on.
func resolveLogAnomalyEnabled(env string, current bool) bool {
	switch env {
	case "false", "0":
		return false
	case "true", "1":
		return true
	default:
		return current
	}
}

// resolveOTLPHTTPAddr applies COREMETRY_OTLP_HTTP_ADDR to the dedicated
// OTLP/HTTP listener's address. Empty env → keep current (the :4318 default);
// "off"/"none"/"-" (case-insensitive) → disable the listener (""); anything
// else → the new listen address. An env var can't express an empty-string
// override, hence the sentinel tokens. v0.9.168.
func resolveOTLPHTTPAddr(env, current string) string {
	// Trim FIRST so both the disable tokens AND the address are whitespace-
	// tolerant — a k8s Secret populated via `echo ":4318" | base64` delivers a
	// trailing "\n" that would otherwise reach net.Listen verbatim and
	// crashloop the ingest pod at boot (v0.9.168 review). Whitespace-only →
	// treated as unset (keep current default).
	env = strings.TrimSpace(env)
	if env == "" {
		return current
	}
	switch strings.ToLower(env) {
	case "off", "none", "-":
		return ""
	}
	return env
}

func Load(path string) (*Config, error) {
	cfg := defaults
	data, err := os.ReadFile(path)
	if err != nil && !os.IsNotExist(err) {
		return nil, err
	}
	if err == nil {
		if err := yaml.Unmarshal(data, &cfg); err != nil {
			return nil, err
		}
	}

	// Environment variable overrides (Docker / k8s friendly)
	if v := os.Getenv("COREMETRY_CH_ADDR"); v != "" {
		cfg.ClickHouse.Addr = v
	}
	if v := os.Getenv("COREMETRY_CH_DATABASE"); v != "" {
		cfg.ClickHouse.Database = v
	}
	if v := os.Getenv("COREMETRY_CH_USERNAME"); v != "" {
		cfg.ClickHouse.Username = v
	}
	if v := os.Getenv("COREMETRY_CH_PASSWORD"); v != "" {
		cfg.ClickHouse.Password = v
	}
	if v := os.Getenv("COREMETRY_CH_SECURE"); v == "true" || v == "1" {
		cfg.ClickHouse.Secure = true
	}
	if v := os.Getenv("COREMETRY_CH_INSECURE_SKIP_VERIFY"); v == "true" || v == "1" {
		cfg.ClickHouse.InsecureSkipVerify = true
	}
	if v := os.Getenv("COREMETRY_EXEMPLARS_MAX_PER_SERIES_MIN"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n >= 0 {
			cfg.Exemplars.MaxPerSeriesPerMinute = n
		}
	}
	// Distributed-CH overrides — env-only deployment shouldn't
	// have to ship a config.yaml just to flip cluster mode on.
	if v := os.Getenv("COREMETRY_CH_CLUSTER_NAME"); v != "" {
		cfg.ClickHouse.ClusterName = v
	}
	if v := os.Getenv("COREMETRY_CH_REPLICA_PATH"); v != "" {
		cfg.ClickHouse.ReplicaPath = v
	}
	if v := os.Getenv("COREMETRY_CH_SHARD_KEY"); v != "" {
		cfg.ClickHouse.ShardKey = v
	}
	// CH connection pool — env knob (v0.8.205). The pool must exceed the
	// ingest flush fan-out (3 signals × Ingestion.Workers goroutines, each
	// holding a conn during INSERT) plus read-path headroom, or flushers
	// starve each other → "acquire conn timeout" + dropped batches. Leave
	// UNSET to auto-derive from Workers (resolveMaxOpenConns); set explicitly
	// only to cap against the CH server's own max_connections.
	if v := os.Getenv("COREMETRY_CH_MAX_OPEN_CONNS"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n > 0 {
			cfg.ClickHouse.MaxOpenConns = n
		}
	}
	if v := os.Getenv("COREMETRY_CH_DIAL_TIMEOUT"); v != "" {
		if _, err := time.ParseDuration(v); err == nil {
			cfg.ClickHouse.DialTimeout = v
		}
	}
	if v := os.Getenv("COREMETRY_CH_ALLOW_UNSET_CLUSTER"); v == "true" || v == "1" {
		cfg.ClickHouse.AllowUnsetCluster = true
	}
	if v := os.Getenv("COREMETRY_CH_INSERT_DISTRIBUTED_SYNC"); v == "true" || v == "1" {
		cfg.ClickHouse.InsertDistributedSync = true // v0.10.778 — geçici köprü, bkz. CHConfig
	}
	// v0.10.790 — replika-duyarlı ayarlar (bkz. CHConfig). Sayısal değer
	// bozuksa uyar ve yok say (chBytesEnv ile aynı dürüstlük).
	if v := os.Getenv("COREMETRY_CH_READ_MAX_REPLICA_DELAY"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n >= 0 {
			cfg.ClickHouse.ReadMaxReplicaDelayS = n
		} else {
			log.Printf("[config] COREMETRY_CH_READ_MAX_REPLICA_DELAY=%q geçersiz (saniye, ≥0) — yok sayıldı", v)
		}
	}
	if v := os.Getenv("COREMETRY_CH_MV_DEDUP_BLOCKS"); v == "true" || v == "1" {
		cfg.ClickHouse.MVDedupBlocks = true
	}
	if v := os.Getenv("COREMETRY_CH_INSERT_QUORUM"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n >= 0 {
			cfg.ClickHouse.InsertQuorum = n
		} else {
			log.Printf("[config] COREMETRY_CH_INSERT_QUORUM=%q geçersiz (tam sayı, ≥2 açar) — yok sayıldı", v)
		}
	}
	// v0.9.184 — per-query CH memory limits, env-tunable (bytes). Prod's
	// external cluster raises these to match node RAM; local/default keep
	// the conservative 4GB/1GB/1GB built-ins. v0.9.185 — chBytesEnv WARNS
	// on a non-integer value instead of silently discarding it (operators
	// reach for k8s "12Gi" syntax; a silent drop leaves the 4GB cap and
	// the code-241 symptom in place with no diagnostic).
	chBytesEnv("COREMETRY_CH_MAX_MEMORY_USAGE", &cfg.ClickHouse.MaxMemoryUsage)
	chBytesEnv("COREMETRY_CH_MAX_BYTES_EXTERNAL_GROUP_BY", &cfg.ClickHouse.MaxBytesExternalGroupBy)
	chBytesEnv("COREMETRY_CH_MAX_BYTES_EXTERNAL_SORT", &cfg.ClickHouse.MaxBytesExternalSort)
	// v0.9.975 — the ratio the three limits above are held under. See
	// CHConfig.MemFraction / internal/chstore/query_memory.go.
	chFractionEnv("COREMETRY_CH_MEM_FRACTION", &cfg.ClickHouse.MemFraction)
	// v0.10.511 — MV paralel itişi (C6 ölçüm anahtarı). Bilinmeyen değer
	// WARNING + varsayılan (paralel açık); sessiz düşüş yok.
	if v, ok := os.LookupEnv("COREMETRY_CH_PARALLEL_VIEWS"); ok {
		switch strings.ToLower(strings.TrimSpace(v)) {
		case "0", "false", "off", "no":
			cfg.ClickHouse.DisableParallelViews = true
		case "1", "true", "on", "yes", "":
			cfg.ClickHouse.DisableParallelViews = false
		default:
			log.Printf("[config] WARNING: COREMETRY_CH_PARALLEL_VIEWS=%q geçersiz — 0/1 bekleniyor; paralel itiş AÇIK kaldı", v)
		}
	}
	if v := os.Getenv("COREMETRY_HTTP_ADDR"); v != "" {
		cfg.Listen.HTTP = v
	}
	// COREMETRY_PUBLIC_URL — deployment's externally-reachable
	// base URL. Notification bodies include deep links when set.
	// e.g. https://coremetry.bank.local
	if v := os.Getenv("COREMETRY_PUBLIC_URL"); v != "" {
		cfg.PublicURL = v
	}
	// v0.10.804 — COREMETRY_ALLOWED_ORIGINS: virgülle ayrılmış origin
	// listesi; boşluklar kırpılır, boş parçalar düşer. Dolu env config
	// dosyasındaki listeyi DEĞİŞTİRİR (birleştirmez).
	if v := os.Getenv("COREMETRY_ALLOWED_ORIGINS"); v != "" {
		cfg.AllowedOrigins = splitOrigins(v)
	}
	if v := os.Getenv("COREMETRY_GRPC_ADDR"); v != "" {
		cfg.Listen.GRPC = v
	}
	// COREMETRY_OTLP_HTTP_ADDR — dedicated OTLP/HTTP listen address (default
	// :4318). Set to "off" / "none" / "-" to disable the listener entirely
	// (an env var can't express an empty-string override). v0.9.168.
	cfg.Listen.OTLPHTTP = resolveOTLPHTTPAddr(os.Getenv("COREMETRY_OTLP_HTTP_ADDR"), cfg.Listen.OTLPHTTP)
	// Ingest capacity (v0.8.204) — tunable WITHOUT a config file, for installs
	// where apps push OTLP straight to :4317. The gRPC receiver returns
	// ResourceExhausted ("buffer full") when the queue can't drain to CH fast
	// enough; raise the buffer (burst headroom, default 500k) and/or workers
	// (parallel CH inserts, default 8) here. If the buffer keeps filling, CH is
	// the bottleneck — scale CH, don't just grow the buffer.
	if v := os.Getenv("COREMETRY_INGEST_BUFFER_SIZE"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n > 0 {
			cfg.Ingestion.BufferSize = n
		}
	}
	if v := os.Getenv("COREMETRY_INGEST_WORKERS"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n > 0 {
			cfg.Ingestion.Workers = n
		}
	}
	if v := os.Getenv("COREMETRY_INGEST_BATCH_SIZE"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n > 0 {
			cfg.Ingestion.BatchSize = n
		}
	}
	if v := os.Getenv("COREMETRY_INGEST_FLUSH_INTERVAL"); v != "" {
		if d, err := time.ParseDuration(v); err == nil && d > 0 {
			cfg.Ingestion.FlushInterval = d
		}
	}
	// Byte budget per consumer (v0.8.355) — n >= 0 accepted: an explicit
	// 0 DISABLES the byte cap (unlike the knobs above, zero is a valid
	// operator choice here, not a missing value).
	if v := os.Getenv("COREMETRY_INGEST_BYTE_BUDGET_MB"); v != "" {
		if n, err := strconv.Atoi(v); err == nil && n >= 0 {
			cfg.Ingestion.ByteBudgetMB = n
		}
	}
	if v := os.Getenv("COREMETRY_JWT_SECRET"); v != "" {
		cfg.Auth.JWTSecret = v
	}
	if v := os.Getenv("COREMETRY_INITIAL_ADMIN"); v != "" {
		cfg.Auth.InitialAdmin = v
	}
	if v := os.Getenv("COREMETRY_INITIAL_PASSWORD"); v != "" {
		cfg.Auth.InitialPassword = v
	}
	if v := os.Getenv("COREMETRY_OIDC_ENABLED"); v == "true" || v == "1" {
		cfg.Auth.OIDC.Enabled = true
	}
	if v := os.Getenv("COREMETRY_OIDC_ISSUER_URL"); v != "" {
		cfg.Auth.OIDC.IssuerURL = v
	}
	if v := os.Getenv("COREMETRY_OIDC_CLIENT_ID"); v != "" {
		cfg.Auth.OIDC.ClientID = v
	}
	if v := os.Getenv("COREMETRY_OIDC_CLIENT_SECRET"); v != "" {
		cfg.Auth.OIDC.ClientSecret = v
	}
	if v := os.Getenv("COREMETRY_OIDC_REDIRECT_URL"); v != "" {
		cfg.Auth.OIDC.RedirectURL = v
	}
	// Trusted-header auth env overrides — typical Helm shape is
	// to set TRUSTED_HEADER_ENABLED + TRUSTED_PROXIES from
	// values.yaml so the proxy CIDR is part of the deployment
	// definition, not buried in a ConfigMap.
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_ENABLED"); v == "true" || v == "1" {
		cfg.Auth.TrustedHeader.Enabled = true
	}
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_EMAIL"); v != "" {
		cfg.Auth.TrustedHeader.EmailHeader = v
	}
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_USER"); v != "" {
		cfg.Auth.TrustedHeader.UserHeader = v
	}
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_GROUPS"); v != "" {
		cfg.Auth.TrustedHeader.GroupsHeader = v
	}
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_AUTO_PROVISION"); v == "true" || v == "1" {
		cfg.Auth.TrustedHeader.AutoProvision = true
	}
	if v := os.Getenv("COREMETRY_TRUSTED_HEADER_DEFAULT_ROLE"); v != "" {
		cfg.Auth.TrustedHeader.DefaultRole = v
	}
	if v := os.Getenv("COREMETRY_TRUSTED_PROXIES"); v != "" {
		cfg.Auth.TrustedHeader.TrustedProxies = splitCSV(v)
	}
	if v := os.Getenv("COREMETRY_DEMO_MODE"); v == "true" || v == "1" {
		cfg.Auth.DemoMode = true
	}
	if v := os.Getenv("COREMETRY_ADMIN_RESET"); v == "true" || v == "1" {
		cfg.Auth.AdminReset = true
	}
	// Default-ON gate; only an explicit "false"/"0" disables the
	// worker-role log-pattern detector + Drain templater.
	cfg.Background.LogAnomalyEnabled = resolveLogAnomalyEnabled(
		os.Getenv("COREMETRY_LOG_ANOMALY_ENABLED"), cfg.Background.LogAnomalyEnabled)
	if v := os.Getenv("COREMETRY_REDIS_URL"); v != "" {
		cfg.Redis.URL = v
	}
	if v := os.Getenv("COREMETRY_LOGS_BACKEND"); v != "" {
		cfg.Logs.Backend = v
	}
	if v := os.Getenv("COREMETRY_ES_ADDRESSES"); v != "" {
		// Comma-separated list, e.g. "http://es-0:9200,http://es-1:9200".
		cfg.Logs.Elasticsearch.Addresses = splitCSV(v)
	}
	if v := os.Getenv("COREMETRY_ES_USERNAME"); v != "" {
		cfg.Logs.Elasticsearch.Username = v
	}
	if v := os.Getenv("COREMETRY_ES_PASSWORD"); v != "" {
		cfg.Logs.Elasticsearch.Password = v
	}
	if v := os.Getenv("COREMETRY_ES_API_KEY"); v != "" {
		cfg.Logs.Elasticsearch.APIKey = v
	}
	if v := os.Getenv("COREMETRY_ES_INDEX"); v != "" {
		cfg.Logs.Elasticsearch.Index = v
	}
	if v := os.Getenv("COREMETRY_ES_INDEX_TEMPLATE"); v != "" {
		cfg.Logs.Elasticsearch.IndexTemplate = v
	}
	if v := os.Getenv("COREMETRY_ES_INSECURE"); v == "true" || v == "1" {
		cfg.Logs.Elasticsearch.InsecureSkipVerify = true
	}
	if v := os.Getenv("COREMETRY_ES_ML_ENABLED"); v == "true" || v == "1" {
		cfg.Logs.Elasticsearch.MLEnabled = true
	}
	if v := os.Getenv("COREMETRY_ES_ML_MIN_SCORE"); v != "" {
		if f, err := strconv.ParseFloat(v, 64); err == nil {
			cfg.Logs.Elasticsearch.MLMinScore = f
		}
	}
	// ES document field mapping (v0.8.228). Override the per-document
	// field paths so Coremetry queries whatever the operator's log
	// pipeline produces (e.g. trace_id, @timestamp, message) without
	// re-indexing. Empty → logstore default.
	if v := os.Getenv("COREMETRY_ES_FIELD_TIMESTAMP"); v != "" {
		cfg.Logs.Elasticsearch.Fields.Timestamp = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_TRACE_ID"); v != "" {
		cfg.Logs.Elasticsearch.Fields.TraceID = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_SPAN_ID"); v != "" {
		cfg.Logs.Elasticsearch.Fields.SpanID = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_SERVICE"); v != "" {
		cfg.Logs.Elasticsearch.Fields.Service = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_MESSAGE"); v != "" {
		cfg.Logs.Elasticsearch.Fields.Message = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_SEVERITY_TEXT"); v != "" {
		cfg.Logs.Elasticsearch.Fields.SeverityText = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_SEVERITY_NUMBER"); v != "" {
		cfg.Logs.Elasticsearch.Fields.SeverityNumber = v
	}
	if v := os.Getenv("COREMETRY_ES_FIELD_ENV"); v != "" {
		cfg.Logs.Elasticsearch.Fields.Environment = v
	}
	if v := os.Getenv("COREMETRY_AI_PROVIDER"); v != "" {
		cfg.AI.Provider = v
	}
	if v := os.Getenv("COREMETRY_AI_API_KEY"); v != "" {
		cfg.AI.APIKey = v
	}
	if v := os.Getenv("COREMETRY_AI_MODEL"); v != "" {
		cfg.AI.Model = v
	}
	if v := os.Getenv("COREMETRY_AI_BASE_URL"); v != "" {
		cfg.AI.BaseURL = v
	}
	if cfg.Auth.TokenTTL == 0 {
		cfg.Auth.TokenTTL = defaults.Auth.TokenTTL
	}
	if cfg.Auth.OIDC.Enabled {
		if len(cfg.Auth.OIDC.Scopes) == 0 {
			cfg.Auth.OIDC.Scopes = []string{"openid", "email", "profile"}
		}
		if cfg.Auth.OIDC.DisplayName == "" {
			cfg.Auth.OIDC.DisplayName = "SSO"
		}
		if cfg.Auth.OIDC.DefaultRole == "" {
			cfg.Auth.OIDC.DefaultRole = "viewer"
		}
	}
	// apply defaults for zero values
	if cfg.Ingestion.BatchSize == 0 {
		cfg.Ingestion.BatchSize = defaults.Ingestion.BatchSize
	}
	if cfg.Ingestion.BufferSize == 0 {
		cfg.Ingestion.BufferSize = defaults.Ingestion.BufferSize
	}
	if cfg.Ingestion.FlushInterval == 0 {
		cfg.Ingestion.FlushInterval = defaults.Ingestion.FlushInterval
	}
	if cfg.Ingestion.Workers == 0 {
		cfg.Ingestion.Workers = defaults.Ingestion.Workers
	}
	if cfg.Retention.SpansDays == 0 {
		cfg.Retention.SpansDays = defaults.Retention.SpansDays
	}
	if cfg.Retention.LogsDays == 0 {
		cfg.Retention.LogsDays = defaults.Retention.LogsDays
	}
	if cfg.Retention.MetricsDays == 0 {
		cfg.Retention.MetricsDays = defaults.Retention.MetricsDays
	}
	// CH pool sizing — MUST run AFTER Ingestion.Workers is settled so the
	// fan-out math uses the effective worker count (v0.8.205). An unset pool
	// (0) derives to ingestSignals*workers + read headroom; an explicit value
	// is honored but warned about when it's below the fan-out (the operator
	// may be capping against CH max_connections, or may have a footgun).
	fanout := ingestFanout(cfg.Ingestion.Workers)
	cfg.ClickHouse.MaxOpenConns = resolveMaxOpenConns(cfg.ClickHouse.MaxOpenConns, cfg.Ingestion.Workers)
	if cfg.ClickHouse.MaxOpenConns < fanout {
		log.Printf("[config] WARNING: ch.max_open_conns=%d is below the ingest flush fan-out "+
			"(%d signals × %d workers = %d). Flushers will contend for connections under load → "+
			"'acquire conn timeout' + dropped batches. Raise COREMETRY_CH_MAX_OPEN_CONNS or lower COREMETRY_INGEST_WORKERS.",
			cfg.ClickHouse.MaxOpenConns, ingestSignals, cfg.Ingestion.Workers, fanout)
	}
	applyBackgroundDefaults(&cfg.Background)
	return &cfg, nil
}

// resolveMaxOpenConns sizes the ClickHouse connection pool to the ingest
// flush fan-out. Each of the 3 signal consumers (spans / logs / metrics)
// runs `workers` flusher goroutines, and every flusher holds a pool
// connection for the duration of its INSERT — sharing the pool with all
// read-path queries. If the pool is smaller than that fan-out the flushers
// starve each other (and the reads), surfacing as the clickhouse-go
// "acquire conn timeout" error and dropped batches.
//
// v0.8.205 prod incident: the config default of 10 shadowed the intended
// sizing, so 3×8=24 flushers fought over 10 connections even at default
// Workers; bumping Workers to 16 made it 48-vs-10 and ~every flush was lost.
//
// An explicit operator value (COREMETRY_CH_MAX_OPEN_CONNS / yaml
// max_open_conns) is honored as-is — the operator may be capping against
// their CH server's max_connections ceiling. When unset (0), derive
// ingestSignals*workers plus 8 connections of read-path headroom.
//
// v0.8.351 — the multiplier tracks the CONSUMER COUNT, which the "3×"
// literal silently stopped doing when v0.8.328/329 added the exemplars
// and span_links consumers: 5 signals × 8 workers = 40 flushers were
// again fighting over 3×8+8=32 connections — the exact v0.8.205 starvation
// shape, reintroduced by feature growth. The constant lives here (not a
// magic number) so the next signal bumps it consciously.
const ingestSignals = 5 // spans, logs, metrics, exemplars, span_links

// ingestFanout — total concurrent ingest flushers: every one of the
// ingestSignals consumers runs `workers` flusher goroutines, each holding a
// pool connection for the duration of its INSERT. Single definition shared
// by the derivation (resolveMaxOpenConns) and the explicit-override warning
// so the two can't drift apart again (v0.8.572: the warning kept a stale 3×
// literal after v0.8.351 grew the consumer count to 5 — an explicit pool of
// 32 with 8 workers sat silently below the real 40-flusher fan-out).
func ingestFanout(workers int) int { return ingestSignals * workers }

func resolveMaxOpenConns(configured, workers int) int {
	if configured > 0 {
		return configured
	}
	if workers <= 0 {
		workers = 8
	}
	return ingestSignals*workers + 8
}

// splitOrigins — SAF (v0.10.804): "a, b,,c" → [a b c]; hiç parça yoksa nil
// (yalnız virgül/boşluk verilmiş env "boş liste" sayılır, allowlist kapanmaz).
func splitOrigins(v string) []string {
	var out []string
	for _, part := range strings.Split(v, ",") {
		if p := strings.TrimSpace(part); p != "" {
			out = append(out, p)
		}
	}
	return out
}
