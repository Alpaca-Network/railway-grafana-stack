# GatewayZ Observability Stack

A production-ready observability solution for **GatewayZ AI Backend**, providing centralized logging, metrics collection, distributed tracing, and visualization. Deployed on Railway with Docker Compose support for local development.

## 🚀 Quick Links

- **Production Grafana:** [https://logs.gatewayz.ai](https://logs.gatewayz.ai)
- **Staging:** [gatewayz-staging.up.railway.app](https://gatewayz-staging.up.railway.app)
- **Quick Start:** [docs/deployment/RAILWAY_DEPLOYMENT_QUICK_START.md](docs/deployment/RAILWAY_DEPLOYMENT_QUICK_START.md)
- **Backend Integration:** [docs/backend/BACKEND_METRICS_REQUIREMENTS.md](docs/backend/BACKEND_METRICS_REQUIREMENTS.md)

---

## ✨ What's New (2025-12-31)

**🎯 NEW: Four Golden Signals Dashboard (Google SRE Methodology)**
- ✅ **17 panels** implementing Google's SRE best practices across 4 signal categories
- ✅ **SIGNAL 1 - LATENCY:** P50/P95/P99 percentiles with 24-hour trend visualization
- ✅ **SIGNAL 2 - TRAFFIC:** Request volume, rate, active requests, traffic trends
- ✅ **SIGNAL 3 - ERRORS:** Error rate gauge, total errors, 24-hour error trends
- ✅ **SIGNAL 4 - SATURATION:** CPU/Memory/Redis utilization + resource saturation trends
- ✅ **21 queries total:** 10 JSON API queries + 11 Prometheus queries
- ✅ **30-second auto-refresh** for real-time executive monitoring
- ✅ **All panels verified** with real backend endpoints

**Previous Updates:**
- ✅ **7 Production Dashboards** organized into logical folders (Executive, Backend, Gateway, Models, Logs)
- ✅ **Backend Health Dashboard:** 13 panels with Redis monitoring (6 panels) + automated health score alerts (<30%)
- ✅ **Gateway Comparison Dashboard:** Added Provider Health Status Grid for all 17 providers
- ✅ **Fixed Metrics:** Stable health score readings (fixed jsonPath: `$.avg_health_score`)
- ✅ **Fixed Redis Integration:** All Redis panels showing data (datasource UID: `grafana_prometheus`)

---

## 📊 Stack Components

| Service | Port(s) | Purpose | Status |
|---------|---------|---------|--------|
| **Grafana 11.5.2** | 3000 | Visualization & dashboarding | ✅ 7 production dashboards (folder-based) |
| **Prometheus v3.2.1** | 9090 | Time-series metrics collection | ✅ 4 scrape jobs |
| **Loki 3.4** | 3100 | Log aggregation | ✅ 30-day retention |
| **Tempo** | 3200, 4317, 4318 | Distributed tracing | ✅ Real instrumentation endpoints |
| **Redis Exporter** | 9121 | Redis metrics export | ✅ Integrated with Backend dashboard |

**All services are pre-configured, interconnected, and production-ready.**

---

## 📚 Documentation

### 🎯 Quick Reference (Start Here!)

All documentation is under [`docs/`](docs/) (no extra root-level markdown files).

- Start here: [docs/docs-index.md](docs/docs-index.md)

### 🔧 Troubleshooting & Diagnostics

See: [docs/troubleshooting/](docs/troubleshooting/)

### 📈 Backend Integration & Metrics

| Document | Description |
|----------|-------------|
| [docs/backend/BACKEND_METRICS_REQUIREMENTS.md](docs/backend/BACKEND_METRICS_REQUIREMENTS.md) | Required metrics for dashboards |
| [docs/dashboards/MODELS_MONITORING_SETUP.md](docs/dashboards/MODELS_MONITORING_SETUP.md) | AI model performance tracking |

---

## 🏗️ Architecture

```
┌──────────────────────────────────────────────────────────────────┐
│                    GatewayZ Backend API                           │
│         (api.gatewayz.ai, gatewayz-staging.up.railway.app)       │
└──────────┬──────────────┬──────────────┬────────────────────────┘
           │              │              │
    Metrics (Pull)   Logs (Push)   Traces (Push OTLP)
     /metrics      :3100/loki      :4317 (gRPC)
                                   :4318 (HTTP)
           │              │              │
    ┌──────▼──────┐ ┌─────▼─────┐ ┌──────▼──────┐
    │ Prometheus  │ │   Loki    │ │   Tempo     │
    │   :9090     │ │  :3100    │ │:3200/:4317/ │
    │             │ │           │ │    :4318    │
    │ 3 Jobs      │ │30d Retain │ │Metrics Gen  │
    │ 15-30s      │ │Compaction │ │Span Metrics │
    └──────┬──────┘ └─────┬─────┘ └──────┬──────┘
           │              │              │
           └──────────────┼──────────────┘
                          │
                   ┌──────▼──────┐
                   │   Grafana   │
                   │    :3000    │
                   │             │
                   │ 7 Dashboards│
                   │ 3 Datasources│
                   └─────────────┘
                   │
                   ├─ Executive Overview (10 panels, 30s refresh)
                   ├─ 🎯 Four Golden Signals (17 panels, Google SRE)
                   ├─ Backend Health & Status (13 panels, Redis + Alerts)
                   ├─ Redis & Backend Services (11 panels, Redis focus)
                   ├─ Gateway & Provider Comparison (9 panels, Provider Grid)
                   ├─ Model Performance Analytics (8 panels, 60s refresh)
                   └─ Logs & Diagnostics (9 panels, RED Method)
```

### Data Flow

1. **Metrics (Pull)**: Prometheus scrapes `/metrics` endpoints every 15-30s
2. **Logs (Push)**: Applications push JSON logs to Loki via HTTP
3. **Traces (Push)**: Applications send OTLP traces to Tempo (gRPC/HTTP)
4. **Visualization**: Grafana queries all three datasources

---

## 📊 Dashboards Available

### Production-Ready Dashboards (Folder-Based Organization)

All dashboards are organized into logical folders and use **REAL API endpoints** - no mock data. Each dashboard has been optimized for specific monitoring use cases with proper alert thresholds and auto-refresh intervals.

| Dashboard | Folder | Panels | Refresh | Key Features | Status |
|-----------|--------|--------|---------|--------------|--------|
| **Executive Overview** | Executive | 10 | 30s | Golden Signals, KPIs, Request Volume, Error Distribution | ✅ Production Ready |
| **🎯 The Four Golden Signals** | Executive | 17 | 30s | **Google SRE Methodology**, Latency (P50/P95/P99), Traffic, Errors, Saturation | ✅ Production Ready |
| **Backend Health & Service Status** | Backend | 13 | 10s | Health Score Alert (<30%), Redis Monitoring (6 panels), Circuit Breakers | ✅ Production Ready |
| **Redis & Backend Services** | Backend | 11 | 10s | Redis Operations, Latency Trends, Error Tracking, Cache Performance | ✅ Production Ready |
| **Gateway & Provider Comparison** | Gateway | 9 | 60s | Provider Health Grid (17 providers), Multi-metric Comparison | ✅ Production Ready |
| **Model Performance Analytics** | Models | 8 | 60s | Top Models, Cost Analysis, Latency Distribution | ✅ Production Ready |
| **Logs & Diagnostics** | Logs | 9 | 10s | RED Method, Log Search, Filtering, Aggregation | ✅ Production Ready |

**All 7 dashboards use REAL API endpoints from your monitoring backend - not mock data. See [docs/archive/root-md/ENDPOINT_VERIFICATION_REPORT.md](docs/archive/root-md/ENDPOINT_VERIFICATION_REPORT.md) for complete verification.**

> Note: the detailed verification report and historical summaries were moved to `docs/archive/root-md/`.

### 📊 Dashboard Features

**Executive Overview** (Executive Folder, 30s refresh)
- **Layout:** 4 stat cards at top (Active Requests, Avg Time, Daily Cost, Error Rate)
- **Request Volume:** Full-width time series showing request trends
- **Error Analysis:** Error rate distribution + Overall system health side-by-side
- **Critical Anomalies:** Active alerts table at bottom
- **Monitoring Framework:** Golden Signals (Latency, Traffic, Errors, Saturation)

**🎯 The Four Golden Signals** (Executive Folder, 30s refresh) **NEW**
- **SIGNAL 1 - LATENCY:** P50/P95/P99 percentile stat cards + 24-hour latency trend visualization
- **SIGNAL 2 - TRAFFIC:** Total requests, request rate (req/sec), active in-flight requests, traffic trends
- **SIGNAL 3 - ERRORS:** Error rate gauge (%), total error count, 24-hour error rate trend
- **SIGNAL 4 - SATURATION:** CPU/Memory/Redis utilization gauges + resource saturation trends
- **Data Sources:** 10 JSON API queries (backend metrics) + 11 Prometheus queries (system metrics)
- **Total Panels:** 17 panels organized across 4 signal categories
- **Monitoring Framework:** Google SRE Methodology (Site Reliability Engineering)
- **Real-time Monitoring:** 30-second auto-refresh with live data from production backend

**Backend Health & Service Status** (Backend Folder, 10s refresh)
- **Health Score Trend:** Full-width chart at top showing 24h health history
- **Alert System:** 🚨 Automated alerts when health score falls below 30%
- **Error Rate Trends:** Full-width error tracking over time
- **Circuit Breakers:** Real-time circuit breaker status table
- **Active Alerts & Anomalies:** Comprehensive anomaly detection
- **Redis Monitoring:** 6 dedicated panels (Connection Status, Memory Usage, Operations/sec, Keyspace, Hit Rate, Latency)
- **Monitoring Framework:** USE Method (Utilization, Saturation, Errors)

**Gateway & Provider Comparison** (Gateway Folder, 60s refresh)
- **Provider Health Grid:** Visual status grid for all 17 providers (✅ HEALTHY, ⚠️ DEGRADED, 🔴 UNHEALTHY)
- **Multi-metric Comparison:** Side-by-side provider performance comparison
- **Cost vs Reliability:** Bubble chart analysis
- **Request Distribution:** Provider usage breakdown
- **Latency & Cost Trends:** Historical performance tracking
- **Monitoring Framework:** Provider Hub

**Model Performance Analytics** (Models Folder, 60s refresh)
- **Top Models:** Top 5 models by request volume
- **Model Health:** Models with issues or degradation alerts
- **Request Trends:** Model-specific request volume over time
- **Cost Analysis:** Cost per request ranking
- **Latency Distribution:** p50, p95, p99 percentiles
- **Monitoring Framework:** AI/ML Focus

**Logs & Diagnostics** (Logs Folder, 10s refresh)
- **Log Search:** Real-time log filtering and search
- **Error Tracking:** Error rate monitoring with thresholds
- **Log Aggregation:** Count by level, service, and severity
- **Recent Errors:** Live tail of error logs
- **Monitoring Framework:** RED Method (Rate, Errors, Duration)

### ✅ Endpoint Verification

All 25+ endpoints backing these dashboards are verified as **REAL** (not mock data):

```bash
# Test all monitoring endpoints
./scripts/test_all_endpoints.sh "YOUR_API_KEY" https://api.gatewayz.ai

# Test instrumentation endpoints
./scripts/test_loki_instrumentation.sh "YOUR_API_KEY" https://api.gatewayz.ai

# Read detailed verification report
cat docs/archive/root-md/ENDPOINT_VERIFICATION_REPORT.md
```

**Core Monitoring Endpoints (12):**
- `/api/monitoring/health` - Provider health status
- `/api/monitoring/stats/realtime?hours=1` - Real-time metrics (1h)
- `/api/monitoring/stats/realtime?hours=24` - 24h historical stats
- `/api/monitoring/error-rates?hours=24` - Error rate trends
- `/api/monitoring/anomalies` - Active alerts & anomalies
- `/api/monitoring/circuit-breakers` - Circuit breaker status
- `/api/monitoring/providers/availability?days=1` - Provider uptime
- `/v1/models/trending?limit=5&sort_by=requests` - Top models
- `/api/monitoring/latency-trends/{provider}?hours=24` - Provider latency
- `/api/monitoring/errors/{provider}?limit=100` - Provider errors
- `/api/monitoring/cost-analysis?days=7` - Cost analytics
- `/api/tokens/efficiency` - Token efficiency metrics

**Instrumentation Endpoints (5):**
- `GET /api/instrumentation/health` - System health
- `GET /api/instrumentation/loki/status` - Loki connectivity
- `GET /api/instrumentation/tempo/status` - Tempo connectivity
- `POST /api/instrumentation/test-log` - Send real logs
- `POST /api/instrumentation/test-trace` - Send real traces

---

## 🔌 Service URLs

### Internal URLs (Within Railway Project)

```bash
# Datasource URLs (for Grafana)
PROMETHEUS_URL=http://prometheus:9090
LOKI_URL=http://loki:3100
TEMPO_URL=http://tempo:3200

# Push URLs (for your backend)
LOKI_PUSH_URL=http://loki:3100/loki/api/v1/push
TEMPO_OTLP_HTTP=http://tempo:4318
TEMPO_OTLP_GRPC=http://tempo:4317
PROMETHEUS_SCRAPE=http://your-backend:PORT/metrics  # Pulled by Prometheus
```

### Public URLs

| Service | URL |
|---------|-----|
| Grafana Production | https://logs.gatewayz.ai |
| Prometheus Production | https://prometheus-production-08db.up.railway.app |
| Staging Environment | https://gatewayz-staging.up.railway.app |

---

## 🧪 CI/CD Testing & Quality Assurance

### Comprehensive Test Coverage ✅

The stack includes automated testing for:
- **25+ Real API Endpoints** - Integration tests with performance validation
- **5 Production Dashboards** - Schema validation and configuration checks (folder-based)
- **90+ Test Methods** - Comprehensive coverage across all components
- **GitHub Actions Workflows** - Automated validation on every deployment

### Test Documentation

| Document | Purpose |
|----------|---------|
| [docs/archive/root-md/CI_CD_TESTING_REPORT.md](docs/archive/root-md/CI_CD_TESTING_REPORT.md) | **Complete testing breakdown** - What's tested, results, endpoints |
| [docs/archive/root-md/QA_REVIEW_REPORT.md](docs/archive/root-md/QA_REVIEW_REPORT.md) | **Quality Assurance sign-off** - 3 expert reviews, production approval |
| `.env.example` | **Configuration template** - API keys and test settings |

### Quick Testing Commands

```bash
# Setup (required once)
cp .env.example .env
# Edit .env and add your API keys

# Run all tests
pytest tests/ -v

# Dashboard validation
./scripts/validate_dashboards.sh strict

# Endpoint testing
export API_KEY="your_key_from_env"
./scripts/test_all_endpoints.sh "$API_KEY" https://api.gatewayz.ai

# Specific test categories
pytest tests/test_dashboards.py -v -m dashboard
pytest tests/test_api_endpoints.py -v -m endpoint
```

### Test Results Summary

**Real Endpoints Status:**
- ✅ 25+ endpoints verified as REAL (not mock)
- ✅ 12 core monitoring endpoints operational
- ✅ 5 instrumentation endpoints operational
- ✅ No synthetic or hardcoded data detected
- 📋 See [docs/archive/root-md/ENDPOINT_VERIFICATION_REPORT.md](docs/archive/root-md/ENDPOINT_VERIFICATION_REPORT.md) for full details

**Dashboard Validation:**
- ✅ 5/5 production dashboards valid (folder-based organization)
- ✅ 0 critical errors
- ✅ All panels properly configured with real API endpoints
- ✅ Health score alert system operational (<30% threshold)
- ✅ Redis monitoring integrated (6 panels in Backend Health)
- 🎯 All dashboards use real API endpoints (NO MOCK DATA)

### GitHub Actions Workflows

**Automatic validation on every deployment:**

1. **validate.yml** (Main branch)
   - JSON and YAML syntax validation
   - Dashboard structure and naming validation (strict mode)
   - Docker build validation
   - Configuration consistency checks

2. **test-staging.yml** (Staging branch)
   - Staging environment endpoint tests
   - Dashboard validation
   - Test reports with detailed results

3. **test-production.yml** (Production)
   - Production endpoint integration tests
   - Comprehensive dashboard validation
   - Scheduled health checks every 6 hours
   - Automated test reports

### GitHub Secrets Setup (Required)

Before CI/CD workflows can test endpoints:

```bash
# 1. Go to: https://github.com/Alpaca-Network/railway-grafana-stack/settings/secrets/actions
# 2. Click "New repository secret"
# 3. Add these secrets:

Secret Name: STAGING_API_KEY
Value: gw_staging_xxxxxxxxxxxxx

Secret Name: PRODUCTION_API_KEY
Value: gw_live_xxxxxxxxxxxxx
```

### Quality Assurance Approval ✅

**Three independent QA experts have reviewed and approved this implementation:**

1. **Test Coverage & Automation:** ⭐⭐⭐⭐⭐ EXCELLENT
2. **Security & Compliance:** ⭐⭐⭐⭐⭐ EXCELLENT
3. **Product Quality:** ⭐⭐⭐⭐ GOOD (endpoint contract verification pending)

**Overall Verdict:** ✅ **APPROVED FOR PRODUCTION DEPLOYMENT**

See [docs/archive/root-md/QA_REVIEW_REPORT.md](docs/archive/root-md/QA_REVIEW_REPORT.md) for complete expert assessments.

### Key Assurances

✅ **All Endpoints are REAL** - Not mock data
✅ **Security Best Practices** - No hardcoded credentials
✅ **Comprehensive Testing** - 90+ test methods
✅ **CI/CD Integration** - Automatic validation
✅ **Production Ready** - Approved by QA experts

---

## 🚀 Quick Start

### Option 1: Local Development (Docker Compose)

```bash
# Clone repository
git clone https://github.com/your-org/railway-grafana-stack.git
cd railway-grafana-stack

# Start all services
docker compose up --build

# Access services
open http://localhost:3000  # Grafana (admin/yourpassword123)
open http://localhost:9090  # Prometheus
curl http://localhost:3100/ready  # Loki health
curl http://localhost:3200/ready  # Tempo health
```

**See [docs/archive/root-md/QUICK_START.md](docs/archive/root-md/QUICK_START.md) for detailed local setup.**

### Option 2: Deploy to Railway

```bash
# Push to Railway
git push railway main

# Or use Railway CLI
railway up
```

**See [docs/deployment/RAILWAY_DEPLOYMENT_QUICK_START.md](docs/deployment/RAILWAY_DEPLOYMENT_QUICK_START.md) for detailed deployment steps.**

---

## ⚙️ Configuration

### Prometheus Scrape Jobs

**File:** [prometheus/prom.yml](prometheus/prom.yml)

| Job Name | Target | Interval | Environment |
|----------|--------|----------|-------------|
| `prometheus` | localhost:9090 | 15s | Self-monitoring |
| `gatewayz_production` | api.gatewayz.ai | 15s | Production API |
| `gatewayz_staging` | gatewayz-staging.up.railway.app | 15s | Staging API |
| `redis_exporter` | redis-exporter:9121 | 30s | Redis metrics |

### Loki Configuration

**File:** [loki/loki.yml](loki/loki.yml)

- **Retention:** 30 days (720h)
- **Compaction:** Enabled (every 10 minutes)
- **Max Ingestion:** 10 MB/s (burst: 20 MB/s)
- **Storage:** Local filesystem with TSDB index

### Tempo Configuration

**File:** [tempo/tempo.yml](tempo/tempo.yml)

- **Receivers:** OTLP gRPC (:4317), OTLP HTTP (:4318)
- **Metrics Generator:** ✅ Enabled (service graphs + span metrics)
- **Storage:** Local filesystem
- **Block Duration:** 5 minutes

### Grafana Datasources

**Directory:** [grafana/provisioning/datasources/](grafana/provisioning/datasources/)

| Datasource | UID | Type | URL |
|------------|-----|------|-----|
| Prometheus | `grafana_prometheus` | prometheus | `${PROMETHEUS_INTERNAL_URL}` |
| Loki | `grafana_loki` | loki | `${LOKI_URL}` |
| Tempo | `grafana_tempo` | tempo | `${TEMPO_INTERNAL_URL}` |

---

## 📈 Metrics Exported

### ✅ Available Metrics (Backend Already Exports)

**FastAPI:**
- `fastapi_requests_total` - Total HTTP requests
- `fastapi_requests_duration_seconds` - Request latency histogram
- `fastapi_requests_in_progress` - In-flight requests
- `fastapi_request_size_bytes`, `fastapi_response_size_bytes`

**Model Inference:**
- `model_inference_requests_total{model, provider, status}`
- `model_inference_duration_seconds{model, provider}`
- `tokens_used_total{model, provider}`
- `credits_used_total{model, provider}`

**Database & Cache:**
- `database_queries_total{operation}`
- `database_query_duration_seconds{operation}`
- `cache_hits_total`, `cache_misses_total`, `cache_size_bytes`

**Performance:**
- `backend_ttfb_seconds` - Time to first byte
- `streaming_duration_seconds` - Streaming duration
- `time_to_first_chunk_seconds{model, provider}` - TTFC

**User Metrics:**
- `active_api_keys`, `subscription_count`, `trial_active`
- `user_credit_balance{user_id}`

### ⚠️ Missing Metrics (Need Backend Implementation)

See [docs/backend/BACKEND_METRICS_REQUIREMENTS.md](docs/backend/BACKEND_METRICS_REQUIREMENTS.md) for:
- `provider_availability{provider}` - Provider health status
- `provider_error_rate{provider}` - Provider error rates
- `provider_response_time_seconds{provider}` - Provider latencies
- `gatewayz_provider_health_score{provider}` - Overall health score
- And more...

---

## 🔧 Backend Integration

### 1. Instrument Your FastAPI Backend

**Python Example:**
```python
from prometheus_client import Counter, Histogram, make_asgi_app
from fastapi import FastAPI

app = FastAPI()

# Add Prometheus metrics endpoint
metrics_app = make_asgi_app()
app.mount("/metrics", metrics_app)

# Define custom metrics
model_requests = Counter(
    'model_inference_requests_total',
    'Total model requests',
    ['model', 'provider', 'status']
)

# Use in your code
@app.post("/v1/chat/completions")
async def chat_completion(request: ChatRequest):
    # Your logic here
    model_requests.labels(
        model=request.model,
        provider=provider,
        status='success'
    ).inc()
```

### 2. Send Logs to Loki

**Python with Winston-Loki equivalent:**
```python
import logging
from python_loki_handler import LokiHandler

loki_handler = LokiHandler(
    url="http://loki:3100/loki/api/v1/push",
    tags={"app": "gatewayz", "env": "production"}
)

logger = logging.getLogger()
logger.addHandler(loki_handler)

logger.info("Request processed", extra={"user_id": "123", "duration_ms": 45})
```

### 3. Send Traces to Tempo

**Python with OpenTelemetry:**
```python
from opentelemetry import trace
from opentelemetry.exporter.otlp.proto.http.trace_exporter import OTLPSpanExporter
from opentelemetry.sdk.trace import TracerProvider
from opentelemetry.sdk.trace.export import BatchSpanProcessor

# Configure Tempo exporter
otlp_exporter = OTLPSpanExporter(endpoint="http://tempo:4318/v1/traces")

# Set up tracing
trace.set_tracer_provider(TracerProvider())
trace.get_tracer_provider().add_span_processor(
    BatchSpanProcessor(otlp_exporter)
)

tracer = trace.get_tracer(__name__)

# Use in your code
with tracer.start_as_current_span("model_inference"):
    result = await call_model_api()
```

**Full integration guide:** [docs/backend/BACKEND_METRICS_REQUIREMENTS.md](docs/backend/BACKEND_METRICS_REQUIREMENTS.md)

---

## 🐛 Common Issues & Fixes

### Issue: Dashboards show "No Data"

**Cause:** Backend not exporting metrics or Prometheus not scraping

**Fix:**
1. Verify backend exposes `/metrics`: `curl https://api.gatewayz.ai/metrics`
2. Check Prometheus targets: `http://localhost:9090/targets` (all should be "UP")
3. Verify job names in [prometheus/prom.yml](prometheus/prom.yml) match your backend

### Issue: Loki "400 Bad Request" in logs dashboard

**Cause:** Query syntax issues or no logs ingested

**Fix:**
1. Verify logs are being sent: `curl http://localhost:3100/metrics | grep loki_distributor_lines_received_total`
2. Check query syntax in dashboard (should use LogQL, not PromQL)
3. See [docs/troubleshooting/LOKI_FIX_GUIDE.md](docs/troubleshooting/LOKI_FIX_GUIDE.md)

### Issue: Tempo "Frame too large" error

**Cause:** Wrong port in frontend_worker config

**Fix:** Already fixed in [tempo/tempo.yml:63](tempo/tempo.yml#L63) - frontend uses port 3200 (HTTP)

### Issue: Grafana datasources not connecting

**Cause:** UID mismatch or wrong URLs

**Fix:** Datasource UIDs are now fixed:
- Prometheus: `grafana_prometheus`
- Loki: `grafana_loki`
- Tempo: `grafana_tempo`

See [docs/troubleshooting/GRAFANA_CONNECTIONS.md](docs/troubleshooting/GRAFANA_CONNECTIONS.md)

---

## 🧪 Testing & Staging

### Staging Workflow

1. Push to `staging/models-and-fixes` branch
2. Verify on staging: `https://gatewayz-staging.up.railway.app`
3. Test all dashboards load correctly
4. Merge to `main` for production

**See:** [docs/deployment/STAGING_WORKFLOW.md](docs/deployment/STAGING_WORKFLOW.md)

### Validate Configuration Locally

```bash
# Start stack
docker compose up -d

# Check service health
curl http://localhost:9090/-/healthy  # Prometheus
curl http://localhost:3100/ready      # Loki
curl http://localhost:3200/ready      # Tempo
curl http://localhost:3000/api/health # Grafana

# Verify Prometheus scraping
curl http://localhost:9090/api/v1/targets | jq '.data.activeTargets[] | {job: .labels.job, health: .health}'

# Send test log to Loki
curl -X POST http://localhost:3100/loki/api/v1/push \
  -H "Content-Type: application/json" \
  -d '{"streams":[{"stream":{"app":"test"},"values":[["'$(date +%s%N)'","test log message"]]}]}'

# Generate test traffic
for i in {1..20}; do curl http://localhost:8000/metrics; sleep 0.5; done
```

---

## 📦 Latest Optimizations & Improvements

### 🆕 Dashboard Reorganization (2025-12-31)

**Branch:** `refactor/dashboard-layout-reorganization`

✅ **Backend Health & Service Status Dashboard:**
- Reorganized layout with Health Score Trend at top (full width, 24h history)
- Error Rate Trend below (full width for better visibility)
- Active Alerts & Anomalies positioned for quick incident response
- **NEW:** 6 Redis monitoring panels (Connection Status, Memory, Operations/sec, Keyspace, Hit Rate, Latency)
- **NEW:** Health score alert system - automatically alerts when score falls below 30%
- Fixed jsonPath extraction: `$.avg_health_score` for stable metrics
- Fixed Redis datasource UIDs: `grafana_prometheus` (consistent with datasources.yml)
- **Total Panels:** 13 (previously 7)

✅ **Gateway & Provider Comparison Dashboard:**
- **NEW:** Provider Health Status Grid with visual status indicators (✅ HEALTHY, ⚠️ DEGRADED, 🔴 UNHEALTHY)
- Comprehensive 17-provider health monitoring at a glance
- **Total Panels:** 9 (added Provider Grid from Backend dashboard)

✅ **Executive Overview Dashboard:**
- Reorganized with 4 stat cards at top (Active Requests, Avg Time, Daily Cost, Error Rate)
- Request Volume full-width chart for trend visibility
- Error Rate + Overall System Health side-by-side for quick analysis
- Critical Anomalies table at bottom for incident awareness
- **Total Panels:** 10 (optimized layout)

✅ **Folder-Based Organization:**
- Dashboards organized into logical folders: Executive, Backend, Gateway, Models, Logs
- Improved navigation and dashboard discovery in Grafana UI
- Provisioning configuration updated for folder-based structure

### Railway Deployment Fixes (2025-12-27)

✅ **Railway Deployment:** Fixed datasource connectivity with explicit `.railway.internal` URLs
✅ **Loki & Tempo:** Configured explicit listen addresses (0.0.0.0) for inter-service communication
✅ **Prometheus:** Pre-configured for both production and staging backends
✅ **Documentation:** Cleaned up repo - kept essential guides, removed historical/redundant docs
✅ **Staging Metrics:** Diagnostics and troubleshooting guides for metric collection issues

---

## 🛠️ Development

### Project Structure

```
railway-grafana-stack/
├── grafana/
│   ├── Dockerfile
│   ├── dashboards/              # 5 production dashboards (folder-based)
│   │   ├── executive/
│   │   │   └── executive-overview-v1.json       # 10 panels, Golden Signals
│   │   ├── backend/
│   │   │   └── backend-health-v1.json           # 13 panels, Redis + Alerts
│   │   ├── gateway/
│   │   │   └── gateway-comparison-v1.json       # 9 panels, Provider Grid
│   │   ├── models/
│   │   │   └── model-performance-v1.json        # 8 panels, AI/ML Focus
│   │   └── logs/
│   │       └── logs-monitoring-v1.json          # 9 panels, RED Method
│   ├── provisioning/            # Datasource auto-configuration
│   │   └── dashboards/
│   │       └── dashboards.yml   # Folder-based provisioning config
├── prometheus/
│   ├── Dockerfile
│   ├── prom.yml                 # Scrape jobs (production, staging)
│   └── alert.rules.yml          # Alert rules
├── loki/
│   ├── Dockerfile
│   └── loki.yml                 # Storage, retention, compaction config
├── tempo/
│   ├── Dockerfile
│   └── tempo.yml                # OTLP receivers, metrics generation
├── tests/
│   ├── test_prometheus_metrics.py  # Configuration validation
│   └── test_health_check.py        # Service health checks
├── docs/
│   ├── backend/                 # Backend integration guides
│   ├── dashboards/              # Dashboard documentation
│   └── troubleshooting/         # Service-specific fix guides
├── docker-compose.yml           # Local development (all services)
├── .github/workflows/           # CI/CD pipelines (test on push)
├── docs/docs-index.md           # Documentation index
├── docs/archive/root-md/        # Former root docs (kept for reference)
└── README.md                    # This file
```

### Alert Configuration

**Health Score Alert (Backend Health Dashboard):**
- **Trigger:** When overall health score falls below 30%
- **Evaluation:** Every 1 minute
- **Alert Delay:** 5 minutes (prevents false positives)
- **Message:** "🚨 CRITICAL: System health score has fallen below 30%!"
- **Configuration:** Defined in [backend-health-v1.json](grafana/dashboards/backend/backend-health-v1.json)

Alert rules can be extended to additional metrics by adding similar configurations to dashboard panels.

### Deploying Dashboard Changes

**Current Branch:** `refactor/dashboard-layout-reorganization` (3 commits ahead of main)

**To deploy to production:**
```bash
# Option 1: Create Pull Request (Recommended)
git push origin refactor/dashboard-layout-reorganization
# Then create PR on GitHub: https://github.com/your-org/railway-grafana-stack/compare

# Option 2: Merge directly to main
git checkout main
git merge refactor/dashboard-layout-reorganization
git push origin main
```

**Verify deployment:**
1. Access Grafana: https://logs.gatewayz.ai (production) or http://localhost:3000 (local)
2. Check folder organization: Dashboards should appear under Executive, Backend, Gateway, Models, Logs folders
3. Open Backend Health dashboard:
   - Verify Health Score Trend is at top (full width)
   - Verify 6 Redis panels are showing data
   - Check that health score displays correctly (not fluctuating)
4. Open Gateway Comparison dashboard:
   - Verify Provider Health Grid displays all 17 providers
5. Test alert system (optional):
   ```bash
   # Simulate low health score by modifying backend API response temporarily
   # Alert should trigger if health score < 30% for 5 minutes
   ```

### Contributing

1. Create feature branch: `git checkout -b feature/my-feature`
2. Make changes and test locally with `docker compose up`
3. Push to staging branch for testing
4. Create pull request to `main`

---

## 📚 External Resources

- [Grafana Documentation](https://grafana.com/docs/grafana/latest/)
- [Prometheus Documentation](https://prometheus.io/docs/)
- [Loki Documentation](https://grafana.com/docs/loki/latest/)
- [Tempo Documentation](https://grafana.com/docs/tempo/latest/)
- [OpenTelemetry Documentation](https://opentelemetry.io/docs/)
- [Railway Documentation](https://docs.railway.app/)

---

## 📞 Support

### Documentation Issues
- Check [docs/troubleshooting/](docs/troubleshooting/) directory
- See [docs/archive/root-md/IMMEDIATE_ACTION_REQUIRED.md](docs/archive/root-md/IMMEDIATE_ACTION_REQUIRED.md) for quick fixes
- Search existing issues in repository

### Backend Integration Help
- See [docs/backend/BACKEND_METRICS_REQUIREMENTS.md](docs/backend/BACKEND_METRICS_REQUIREMENTS.md)
- Review [docs/archive/root-md/RAILWAY_DEPLOYMENT_GUIDE.md](docs/archive/root-md/RAILWAY_DEPLOYMENT_GUIDE.md) for deployment specifics

---

## 📄 License

Proprietary - GatewayZ Network

---

**GatewayZ Observability Stack** · Production-ready monitoring for AI infrastructure · Deployed on Railway
