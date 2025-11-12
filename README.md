# CBI-V14 Commodity Forecasting Platform

**INSTITUTIONAL-GRADE soybean oil futures forecasting with Vertex AI AutoML and comprehensive intelligence gathering**

## 🎯 Project Overview

**GOLDMAN SACHS / JP MORGAN STANDARD** soybean oil (ZL) futures forecasting platform delivering actionable BUY/WAIT/MONITOR signals for Chris Stacy (US Oil Solutions, Las Vegas). Features Vertex AI AutoML neural networks trained on 209 features including Big 8 signals, China imports, Argentina crisis tracking, and industrial demand indicators. Dashboard translates institutional signals into procurement-focused business language.

## 🔥 CURRENT STATUS (November 5, 2025)

### **🚀 PRODUCTION BQML MODELS ACTIVE:**
- ✅ **4 MODELS TRAINED** - bqml_1w (275 feat), bqml_1m (274), bqml_3m (268), bqml_6m (258)
- ✅ **PREDICTIONS WORKING** - Last generated Nov 4, 2025 at 21:56:18 UTC
- ✅ **EXCELLENT ACCURACY** - MAPE: 0.70-1.29% (institutional grade <2%)
- ✅ **DATA BACKFILLED** - News/Trump/policy columns now have 20-99% coverage
- ✅ **PRODUCTION FOLDER** - `/bigquery-sql/PRODUCTION_HORIZON_SPECIFIC/`
- ✅ **NULL STATUS VERIFIED** - All features checked, no 100% NULL columns

### **🎯 CHRIS-FOCUSED DASHBOARD ARCHITECTURE:**
- ✅ **PROCUREMENT SIGNALS** - BUY/WAIT/MONITOR with confidence levels and price targets
- ✅ **CHRIS'S FOUR FACTORS** - China status, harvest progress, biofuel demand, palm oil spread
- ✅ **VEGAS INTEL FOR KEVIN** - Event-driven upsell engine for casino customers
- ✅ **TRANSLATION LAYER** - UBS/GS institutional signals → business language
- ✅ **100% MODEL-DRIVEN** - No fake data, all values from trained models/warehouse
- ✅ **GLIDE APP INTEGRATION** - Customer data, relationship status, historical volumes

### **🎯 PRODUCTION CONFIGURATION:**
**Location:** `/bigquery-sql/PRODUCTION_HORIZON_SPECIFIC/`

**Training SQL:**
```bash
# Production BQML training files:
# TRAIN_BQML_1W_PRODUCTION.sql (275 features)
# TRAIN_BQML_1M_PRODUCTION.sql (274 features)
# TRAIN_BQML_3M_PRODUCTION.sql (268 features)
# TRAIN_BQML_6M_PRODUCTION.sql (258 features)
```

**Prediction SQL:**
```bash
# Generate all predictions:
# GENERATE_PREDICTIONS_PRODUCTION.sql
# Output: predictions_uc1.production_forecasts
```

**Data Flow:**
```bash
# 1. Ingestion (hourly/daily crons)
forecasting_data_warehouse.* (raw data)
       ↓
# 2. Feature engineering (daily 6 AM)
neural.vw_big_eight_signals (view with 275+ features)
       ↓
# 3. Materialization
models_v4.training_dataset_super_enriched (table)
       ↓
# 4. Training/Prediction
bqml_1w, bqml_1m, bqml_3m, bqml_6m → predictions_uc1.production_forecasts
```

**CRITICAL TECHNICAL LESSONS:**
- 🎯 **NULL Target Validation** - Vertex AI regression requires non-NULL targets
- 🎯 **BigQuery Direct Integration** - Use `bq://` URI, not GCS exports
- 🎯 **Sequential Launch** - Google Cloud quota limits concurrent AutoML jobs
- ✅ **Pilot Validated** - 1W model proves architecture works (1.72% MAPE)

### **🏆 PRODUCTION MODEL PERFORMANCE:**
| Model | Horizon | Features | Training Loss | Eval Loss | MAPE | Status |
|-------|---------|----------|---------------|-----------|------|--------|
| **bqml_1w** | 1-Week | 275 | 0.303 | 1.290 | 1.21% | ✅ PRODUCTION |
| **bqml_1m** | 1-Month | 274 | 0.304 | 1.373 | 1.29% | ✅ PRODUCTION |
| **bqml_3m** | 3-Month | 268 | 0.300 | 1.260 | 0.70% | ✅ PRODUCTION |
| **bqml_6m** | 6-Month | 257 | 0.288 | 1.234 | 1.21% | ✅ PRODUCTION |

**Vertex AI AutoML Models (Alternative):**
| Model ID | Horizon | Status |
|----------|---------|--------|
| 575258986094264320 | 1-Week | ✅ Endpoint |
| 3157158578716934144 | 3-Month | ✅ Endpoint |
| 3788577320223113216 | 6-Month | ✅ Endpoint |

**🎯 TARGET PERFORMANCE (Chris's Requirements):**
- **<2% MAPE** for all horizons (institutional grade)
- **>0.95 R²** for confidence in predictions
- **Daily updates** with fresh market data
- **BUY/WAIT/MONITOR signals** with clear confidence levels

### **DATA QUALITY ASSURANCE:**
- ✅ **Cross-Validation:** All prices verified against Yahoo Finance (<7% difference)
- ✅ **Corruption Detection:** Automated guardrails catch impossible values
- ✅ **Freshness Monitoring:** Economic data <30 days, prices <2 days
- ✅ **Range Validation:** All commodities within realistic price ranges

### **PERMANENT DATA MAPPING (NEVER SEARCH AGAIN):**
```
📊 EXISTING TABLES (38 total in forecasting_data_warehouse):
✅ soybean_oil_prices (1,261 rows) - PRIMARY TARGET
✅ corn_prices (1,261 rows) 
✅ crude_oil_prices (1,258 rows)
✅ palm_oil_prices (1,229 rows)
✅ currency_data (59,102 rows) - Schema: from_currency, to_currency, rate
✅ economic_indicators (71,821 rows) - Schema: time, indicator, value
✅ social_sentiment (661 rows) - Schema: timestamp, sentiment_score
✅ news_intelligence - Schema: published, intelligence_score
✅ trump_policy_intelligence - NOT ice_trump_intelligence
✅ weather_brazil_daily, weather_argentina_daily, weather_us_midwest_daily

❌ TABLES THAT DON'T EXIST:
- ice_trump_intelligence (use trump_policy_intelligence)
- silver_prices (use economic_indicators WHERE indicator = 'silver')
```

### **RECURRING ISSUE FIXES:**
- **Wrong table names:** Scripts reference non-existent tables
- **Schema confusion:** Currency uses from_currency/to_currency, NOT indicator
- **Date columns vary:** time (prices), date (currency), timestamp (sentiment)
- **Storage errors:** Use WRITE_APPEND, not WRITE_TRUNCATE + schema_update_options

### **ELIMINATED BULLSHIT:**
- ❌ **DELETED** - 15+ duplicate/conflicting API endpoints
- ❌ **DELETED** - `neural_signal_engine.py` (Trump-focused bullshit)
- ❌ **DELETED** - `generate_signal.py` (simplified bullshit)
- ❌ **DELETED** - `api.vw_ultimate_adaptive_signal` (simple math bullshit)
- ❌ **DELETED** - `neural.vw_regime_detector_daily` (simple CASE statements)

### **CRITICAL VIEWS (ACADEMIC RIGOR):**
- `api.vw_market_intelligence` - Market intelligence aggregation (REAL DATA)
- `signals.vw_comprehensive_signal_universe` - 847+ variables (HEAVY DATA)
- `signals.vw_master_signal_processor` - Signal processing engine
- `signals.vw_vix_stress_signal` - VIX stress calculations
- `curated.vw_biofuel_policy_us_daily` - Biofuel mandate tracking

### **📊 SIGNAL SCORING DOCUMENTATION:**
- **[SIGNAL SCORING MANUAL](docs/operations/SIGNAL_SCORING_MANUAL.md)** - Complete scoring formulas for all signals
- **Big 7 Primary Signals** - VIX, Harvest, China, Tariff, GVI, BSC, HCI
- **Crisis Thresholds** - 0.8 triggers for regime changes
- **Neural Network Weights** - Tier 1 (2.5x), Tier 2 (1.5x), Tier 3 (1.0x)
- **16 News Categories** - Sentiment integration framework

## 📊 Current Data Architecture

### **Factor-Specific Tables (Production Ready)**
- `soybean_oil_prices`: 519 ZL futures rows (PRIMARY TARGET)
- `soybean_meal_prices`: 519 ZM co-product rows  
- `soybean_prices`: 519 ZS raw soybean rows
- `palm_oil_prices`: 421 FCPO substitute rows
- `corn_prices`: 519 ZC competing crop rows
- `cotton_prices`: 519 CT competing crop rows
- `cocoa_prices`: 441 CC soft commodity rows
- `treasury_prices`: 136 ZN interest rate proxy rows
- `weather_data`: 9,505 weather observations (US + Brazil)
- `volatility_data`: 776 IV/HV volatility metrics
- `economic_indicators`: 3,220 macro indicators (FRED)
- `staging.trump_policy_intelligence`: 188 Trump policy events
- `staging.ice_enforcement_intelligence`: 4 ICE enforcement events
- `feature_metadata`: 29 semantic features (NEW)

### **Semantic Metadata System (NEW)**
- **29 features** with economic context and neural understanding
- **6 categories**: POLICY, COMMODITY, MACRO, WEATHER, SENTIMENT, VOLATILITY
- **8 political features** with impact scores (40-85) and affected commodities
- **9 futures contracts** mapped (ZL, ZM, ZS, FCPO, ZC, CT, CC, ZN, CL)
- **Source reliability scoring** (0.65-0.98) for confidence weighting
- **Geographic context** with top producing countries
- **Natural language aliases** for AI chat interfaces

### **Intelligence Collection System**
- News sentiment monitoring (18 categories)
- Economic indicator tracking (Fed, BLS, Treasury)
- Weather intelligence (NOAA + professional models)
- Social sentiment analysis (Reddit, forums)
- ICE enforcement impact monitoring
- Trump policy effect tracking
- Shipping/logistics intelligence

## 🚀 Quick Start

### **Prerequisites**
- Python 3.8+ with pip
- Google Cloud SDK with BigQuery access
- Project: `cbi-v14`
- BigQuery dataset: `forecasting_data_warehouse`

### **Setup Environment**
```bash
# Clone and setup
git clone [repository-url]
cd CBI-V14

# Install dependencies
pip install -r requirements.txt

# Set up Google Cloud authentication
gcloud auth login
gcloud config set project cbi-v14

# Test BigQuery connection
python3 -c "from google.cloud import bigquery; print('✅ BigQuery connected')"
```

### **Run Intelligence Collection**
```bash
# Start comprehensive data collection
cd cbi-v14-ingestion
python3 run_ingestion.py

# Test feature registry (NEW)
python3 feature_registry.py
```

## 🎉 Recent Accomplishments (Latest Update)

### **SIGNAL SYSTEM CLEANUP (ACADEMIC RIGOR)**
- ✅ **ELIMINATED BULLSHIT** - Removed 15+ duplicate/conflicting endpoints
- ✅ **SINGLE SIGNAL SYSTEM** - Consolidated to ONE academic-rigor system
- ✅ **HEAVY FUCKING DATA** - All signals backed by 847+ variables from comprehensive universe
- ✅ **REAL DATA ONLY** - Eliminated all simple math bullshit and placeholder values
- ✅ **ACADEMIC RIGOR** - Market signal engine with proper BigQuery calculations
- ✅ **CLEAN API** - Only 6 endpoints remaining, all with academic rigor

### **Semantic Metadata System (ENHANCED)**
- ✅ **29 features** documented with economic context
- ✅ **8 political features** with impact scores (40-85) and affected commodities
- ✅ **6 enhancement columns** added (policy_impact_score, affected_commodities, source_reliability_score, related_futures_contract, is_crush_component, top_producing_countries)
- ✅ **9 futures contracts** mapped (ZL, ZM, ZS, FCPO, ZC, CT, CC, ZN, CL)
- ✅ **Source reliability scoring** (0.65-0.98) for confidence weighting
- ✅ **Geographic context** with top producing countries
- ✅ **Natural language aliases** for AI chat interfaces
- ✅ **Feature registry Python module** updated to support all enhancements

### **Data Quality Improvements**
- ✅ **Palm oil data** loaded (421 rows, Feb 2024 - Oct 2025)
- ✅ **Ghost tables cleaned** (deleted empty fed_rates, currency_data, intelligence_cycles)
- ✅ **TradingEconomics scraper** fixed and stopped (was returning wrong prices)
- ✅ **Canonical metadata** added to 4 critical tables
- ✅ **Temperature conversion** deferred (too risky for production data)

### **Architecture Enhancements**
- ✅ **Feature registry** with 8 key methods for neural/AI access
- ✅ **Natural language translation** ('interest rates' → fed_funds_rate)
- ✅ **AI explanation generation** for chat interfaces
- ✅ **Cross-asset relationship mapping** (crush margins, substitution dynamics)
- ✅ **Political impact quantification** (trade war = 85, legal challenges = 40)

## 📈 Current Status

### **Data Volume**
- **Total BigQuery tables**: 22 (with data)
- **Total rows**: ~20,000+ across all tables
- **Data sources**: FRED, NOAA, TradingEconomics, Barchart, INMET, White House, ICE
- **Update frequency**: Hourly (TradingEconomics), Daily (FRED, NOAA), Real-time (political events)

### **Feature Coverage**
- **Commodities**: Soybean oil (ZL), soybeans (ZS), soybean meal (ZM), palm oil (FCPO), corn (ZC), cotton (CT), cocoa (CC), treasury (ZN)
- **Macro**: Fed funds rate, 10-year treasury, CPI, dollar index, USD/BRL, USD/CNY
- **Weather**: Temperature, precipitation (US + Brazil)
- **Political**: 8 Trump/ICE categories with impact scoring
- **Sentiment**: News intelligence, social sentiment, ICE/Trump intelligence
- **Volatility**: Implied volatility, IV/HV ratio

### **Neural Network Readiness**
- ✅ **Semantic understanding** - All features have economic context
- ✅ **Impact weighting** - Political features scored 40-85
- ✅ **Reliability scoring** - Source confidence 0.65-0.98
- ✅ **Cross-asset mapping** - Futures contracts and relationships
- ✅ **Geographic context** - Producing countries for each commodity
- ✅ **Natural language** - Chat aliases for AI interfaces

## 🔧 Development

### **Key Files**
- `cbi-v14-ingestion/feature_registry.py` - Semantic metadata access
- `cbi-v14-ingestion/bigquery_utils.py` - Data ingestion utilities
- `cbi-v14-ingestion/run_ingestion.py` - Main collection orchestrator
- `forecast/main.py` - FastAPI forecast service
- `create_intelligence_tables.sql` - BigQuery schema definitions

### **Testing**
```bash
# Test feature registry
python3 cbi-v14-ingestion/feature_registry.py

# Test BigQuery connection
python3 -c "from google.cloud import bigquery; client = bigquery.Client(); print('✅ Connected')"

# Test data ingestion
cd cbi-v14-ingestion
python3 run_ingestion.py
```

## 📁 Project Structure (CLEANED UP - Oct 20, 2025)

```
CBI-V14/
├── forecast/                           # FastAPI forecasting service
│   ├── main.py                        # Clean API with academic rigor (6 endpoints)
│   ├── market_signal_engine.py        # Market signal engine with proper calculations
│   └── requirements.txt               # Python dependencies
├── cbi-v14-ingestion/                 # Intelligence collection system (CLEANED)
│   ├── master_intelligence_controller.py    # Central coordinator
│   ├── economic_intelligence.py             # Economic data collection
│   ├── social_intelligence.py              # Social sentiment analysis
│   ├── multi_source_news.py                # 18-category news monitoring
│   ├── ingest_weather_noaa.py             # Weather data collection
│   ├── ingest_volatility.py               # Volatility metrics
│   ├── ingest_cftc_positioning_REAL.py    # CFTC data (real data)
│   ├── ingest_social_intelligence_comprehensive.py  # Social intelligence
│   ├── feature_registry.py               # Semantic metadata access
│   ├── bigquery_utils.py                 # Data ingestion utilities
│   └── run_ingestion.py                  # Main collection orchestrator
├── bigquery_sql/                       # SQL feature engineering
│   ├── signals/                        # Signal processing views
│   └── curated_facade/                 # Curated data views
├── dashboard/                          # React/Vite dashboard
│   ├── src/pages/                      # Dashboard pages
│   └── package.json                    # Frontend dependencies
├── scripts/                            # Organized scripts
│   ├── audits/                         # Audit scripts
│   ├── ci/                            # CI/CD scripts
│   └── scrapers/                      # Data scraping scripts
├── docs/                              # Documentation (CLEANED)
│   ├── plans/                         # Project plans
│   ├── audits/                        # Audit reports
│   ├── operations/                    # Operations documentation
│   ├── research/                      # Research documents
│   └── rules/                         # Development rules
├── data/                              # Data files (CLEANED)
│   ├── twitter/                       # Social intelligence data
│   ├── facebook/                      # Social intelligence data
│   ├── linkedin/                      # Social intelligence data
│   ├── youtube/                       # Social intelligence data
│   ├── reddit/                        # Social intelligence data
│   ├── tiktok/                        # Social intelligence data
│   └── truth_social/                  # Social intelligence data
└── PROJECT_STRUCTURE.md              # Complete project structure
```

### **DELETED BULLSHIT:**
- ❌ `cache/` - 100+ outdated API responses
- ❌ `archive/` - Old audit files
- ❌ `data/uploads/` - Old CSV uploads
- ❌ `data/snapshots/` - Old snapshots
- ❌ `cbi-v14-ingestion/trump_*` - Trump-focused bullshit
- ❌ `cbi-v14-ingestion/ice_trump_intelligence.py` - Trump bullshit
- ❌ `cbi-v14-ingestion/monitor_vix_trump_correlation.py` - Trump bullshit
- ❌ `cbi-v14-ingestion/*_FIXED.py` - Fixed versions
- ❌ `cbi-v14-ingestion/secrets.json` - Should be in Secret Manager

## 🔒 Core Rules

### **CRITICAL: NO MOCK DATA EVER**
- All data sources are real BigQuery tables
- No hardcoded arrays or fake data
- Empty states show "No data available" instead of mock content

### **Data Quality Standards**
- Factor-specific tables for neural network training
- Multiple backup sources per data category
- Automated correlation discovery and source hunting
- Real-time monitoring with graceful failure handling

## 🧠 Intelligence Architecture

### **18-Category Monitoring System**
1. China Demand (60% of trade)
2. Brazil Policy (50% of exports)  
3. Argentina Policy (export tax effects)
4. US Policy (Farm Bill, RFS, tariffs)
5. Biofuel Policy (46% of US production)
6. Palm Oil Geopolitics (substitution effects)
7. Weather Intelligence (35-45% price variance)
8. Trade Wars & Disputes
9. Shipping/Logistics (chokepoints)
10. Energy Markets (processing costs)
11. Macro/FX (15-20% variance)
12. Crop Disease (demand effects)
13. ESG/Regulation (EUDR compliance)
14. Labor Unrest (strikes, protests)
15. **ICE Labor Enforcement** (agricultural labor disruption)
16. **Trump Effect** (policy volatility, trade changes)
17. Technology (precision agriculture)
18. Financial Flows (fund positioning)

### **Neural Network Source Discovery**
- Automatic correlation analysis across all data sources
- AI-powered hunting for new data sources based on discovered patterns
- Quality scoring and automatic integration of high-value sources

## 📈 Forecasting Capabilities

### **Current Models**
- **SARIMAX**: Statistical model with weather and economic factors
- **BigQuery ML**: Auto-ARIMA baseline (planned)
- **Neural Networks**: LSTM/Transformer models (development)

### **Features Available**
- Price data: Daily OHLCV for 8 commodities
- Weather factors: Argentina + US precipitation/temperature  
- Technical indicators: SMA_5, SMA_20, volatility
- Volatility metrics: IV/HV ratios, implied volatility
- Economic indicators: Fed rates, employment data
- Sentiment analysis: Multi-source news categorization

## 🛠 Development Commands

```bash
# Check project rules compliance
make check-rules

# Run linting and formatting  
make lint && make format

# Clean build artifacts
make clean

# Test Docker build
docker-compose up --build

# Run intelligence collection
cd cbi-v14-ingestion && python3 master_intelligence_controller.py
```

## 📚 Documentation

- `PROJECT_RULES.md` - Development standards and rules
- `CURSOR_RULES.md` - AI assistant guidelines  
- `INTELLIGENCE_ARCHITECTURE.md` - Intelligence system design
- `CONTRIBUTING.md` - How to contribute
- `plan-detailed.todo` - Detailed implementation plan

## 🎁 Key Achievements (Today)

- ✅ **Factor-based BigQuery architecture** (8 specialized commodity tables)
- ✅ **Real data ingestion** (4,017 rows commodity data, 2,008 weather observations)
- ✅ **Intelligence collection system** (18 categories, 50+ sources)
- ✅ **Neural network correlation discovery** (automated source hunting)
- ✅ **ICE & Trump effect monitoring** (political/labor intelligence)
- ✅ **Production rules enforcement** (NO MOCK DATA compliance)

## 🔜 Next Steps

**IMMEDIATE PRIORITIES (Phase 2.3):**
1. **Create filtered BigQuery views** for NULL-free Vertex AI training
2. **Relaunch 1M/3M/6M AutoML training** with research-based parameters
3. **Monitor training completion** and extract model performance metrics
4. **Deploy AutoML endpoints** for real-time predictions

**PHASE 3-6 ROADMAP:**
5. **Dashboard Implementation** - Chris's Decision Hub + Kevin's Vegas Intel
6. **Glide App Integration** - Customer data pipeline for sales intelligence
7. **Production Deployment** - Automated daily forecasts and alerts
8. **Performance Monitoring** - MAPE tracking and model drift detection

---

**Designed for information superiority in commodity markets**  
**Built with production-grade data architecture and comprehensive intelligence gathering**