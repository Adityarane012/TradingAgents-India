<p align="center">
  <img src="assets/TauricResearch.png" style="width: 60%; height: auto;">
</p>

<div align="center" style="line-height: 1;">
  <a href="https://arxiv.org/abs/2412.20138" target="_blank"><img alt="arXiv" src="https://img.shields.io/badge/arXiv-2412.20138-B31B1B?logo=arxiv"/></a>
  <a href="https://discord.com/invite/hk9PGKShPK" target="_blank"><img alt="Discord" src="https://img.shields.io/badge/Discord-TradingResearch-7289da?logo=discord&logoColor=white&color=7289da"/></a>
  <a href="https://x.com/TauricResearch" target="_blank"><img alt="X Follow" src="https://img.shields.io/badge/X-TauricResearch-white?logo=x&logoColor=white"/></a>
  <a href="https://github.com/TauricResearch/" target="_blank"><img alt="Community" src="https://img.shields.io/badge/GitHub_Community-TauricResearch-14C290?logo=discourse"/></a>
</div>
<br>
<div align="center">
  <a href="https://github.com/TauricResearch" target="_blank"><img alt="TradingAgents #1 Repository of the Day" src="https://trendshift.io/api/badge/repositories/16192" width="250" height="55"/></a>
</div>
<br>
<div align="center">
  <!-- Keep these links. Translations will automatically update with the README. -->
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=de">Deutsch</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=es">Español</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=fr">français</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=ja">日本語</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=ko">한국어</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=pt">Português</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=ru">Русский</a> | 
  <a href="https://www.readme-i18n.com/TauricResearch/TradingAgents?lang=zh">中文</a>
</div>

---

# TradingAgents-India

> ### A fork of [TradingAgents](https://github.com/TauricResearch/TradingAgents) by [Tauric Research](https://tauric.ai)
>
> **Essentially all of this framework is their work.** The multi-agent
> architecture, the analyst/researcher/trader/risk agents, the LangGraph
> orchestration, the data-vendor routing, the CLI and every provider
> integration were built by Tauric Research and are used here under the
> Apache 2.0 licence. Please star and cite [the original
> repository](https://github.com/TauricResearch/TradingAgents) and
> [their paper](https://arxiv.org/abs/2412.20138) — the citation block at the
> bottom of this README is theirs and is reproduced unchanged.
>
> **What this fork adds** is a data layer for Indian equities: NSE
> institutional flows, India VIX, the Nifty put-call ratio, promoter
> shareholding and exchange filings; RBI policy rates; an optional FII/DII
> ownership split; and a zero-cost configuration that runs the whole pipeline
> on free API tiers. `NOTICE` lists every file added or changed, as Apache 2.0
> §4(b) requires.
>
> Tracks upstream through **v0.5.0**. Not financial advice — see the original
> project's [disclaimer](https://tauric.ai/disclaimer/).

---

# TradingAgents: Multi-Agents LLM Financial Trading Framework

## News
- [2026-09] **TradingAgents v0.5.0** released with point-in-time integrity across every dated path, SEC EDGAR fundamentals served as filed, backtesting over a ticker and date grid, portfolio-aware runs, and current model lineups across every provider. See [CHANGELOG.md](CHANGELOG.md) for the full list.
- [2026-08] **TradingAgents v0.4.0** released with look-ahead / point-in-time fixes across FRED macro, social sentiment, and the decision-log memory; clearer decision signals; working CLI checkpoint resume; Trader price grounding; and the GPT-5.6 and GLM-5.3 models.
- [2026-07] **TradingAgents v0.3.1** released with correctness and stability fixes: Alpha Vantage look-ahead filtering, graph-router crash-safety, graph-shape-aware checkpoint resume, working crypto sentiment sources, a configurable LLM retry budget, Bedrock API-key auth, and Claude Sonnet 5 / Fable 5 support.

<details>
<summary>Earlier releases</summary>

- [2026-06] **TradingAgents v0.3.0** released with a verified data-access contract, an expanded provider registry (NVIDIA, Kimi, Groq, Mistral, Bedrock, and any OpenAI-compatible endpoint), FRED and Polymarket data vendors, a current-generation model catalog, and a CI gate.
- [2026-05] **TradingAgents v0.2.5** released with the grounded Sentiment Analyst, GPT-5.5 etc. model coverage, Qwen/GLM/MiniMax dual-region support, `TRADINGAGENTS_*` env-var configurability with API-key auto-detection, remote Ollama support, non-US alpha benchmarks, and ticker path-traversal hardening.
- [2026-04] **TradingAgents v0.2.4** released with structured-output agents (Research Manager, Trader, Portfolio Manager), LangGraph checkpoint resume, persistent decision log, DeepSeek/Qwen/GLM/Azure provider support, Docker, and a Windows UTF-8 encoding fix.
- [2026-03] **TradingAgents v0.2.3** released with multi-language support, GPT-5.4 family models, unified model catalog, backtesting date fidelity, and proxy support.
- [2026-03] **TradingAgents v0.2.2** released with GPT-5.4/Gemini 3.1/Claude 4.6 model coverage, five-tier rating scale, OpenAI Responses API, Anthropic effort control, and cross-platform stability.
- [2026-02] **TradingAgents v0.2.0** released with multi-provider LLM support (GPT-5.x, Gemini 3.x, Claude 4.x, Grok 4.x) and improved system architecture.
- [2026-01] **Trading-R1** [Technical Report](https://arxiv.org/abs/2509.11420) released, with [Terminal](https://github.com/TauricResearch/Trading-R1) expected to land soon.

</details>

<div align="center">

🚀 [TradingAgents](#tradingagents-framework) | ⚡ [Installation & CLI](#installation-and-cli) | 🎬 [Demo](https://www.youtube.com/watch?v=90gr5lwjIho) | 📦 [Package Usage](#tradingagents-package) | 🤝 [Contributing](#contributing) | 📄 [Citation](#citation)

</div>

> 🎉 **TradingAgents** officially released! We have received numerous inquiries about the work, and we would like to express our thanks for the enthusiasm in our community.
>
> So we decided to fully open-source the framework. Looking forward to building impactful projects with you!

## TradingAgents Framework

TradingAgents is a multi-agent trading framework that mirrors the dynamics of real-world trading firms. By deploying specialized LLM-powered agents: from fundamental analysts, sentiment experts, and technical analysts, to trader, risk management team, the platform collaboratively evaluates market conditions and informs trading decisions. Moreover, these agents engage in dynamic discussions to pinpoint the optimal strategy.

<p align="center">
  <img src="assets/schema.png" style="width: 100%; height: auto;">
</p>

> TradingAgents framework is designed for research purposes. Trading performance may vary based on many factors, including the chosen backbone language models, model temperature, trading periods, the quality of data, and other non-deterministic factors. [It is not intended as financial, investment, or trading advice.](https://tauric.ai/disclaimer/)

Our framework decomposes complex trading tasks into specialized roles.

### Analyst Team
- Fundamentals Analyst: Evaluates company financials and performance metrics, identifying intrinsic values and potential red flags.
- Sentiment Analyst: Aggregates news headlines, StockTwits, and Reddit chatter into a single sentiment read to gauge short-term market mood.
- News Analyst: Monitors global news and macroeconomic indicators, interpreting the impact of events on market conditions.
- Technical Analyst: Utilizes technical indicators (like MACD and RSI) to detect trading patterns and forecast price movements.

<p align="center">
  <img src="assets/analyst.png" width="100%" style="display: inline-block; margin: 0 2%;">
</p>

### Researcher Team
- Comprises both bullish and bearish researchers who critically assess the insights provided by the Analyst Team. Through structured debates, they balance potential gains against inherent risks.

<p align="center">
  <img src="assets/researcher.png" width="70%" style="display: inline-block; margin: 0 2%;">
</p>

### Trader Agent
- Composes reports from the analysts and researchers to make informed trading decisions, determining the timing and magnitude of trades.

<p align="center">
  <img src="assets/trader.png" width="70%" style="display: inline-block; margin: 0 2%;">
</p>

### Risk Management and Portfolio Manager
- Continuously evaluates portfolio risk by assessing market volatility, liquidity, and other risk factors. The risk management team evaluates and adjusts trading strategies, providing assessment reports to the Portfolio Manager for final decision.
- The Portfolio Manager approves/rejects the transaction proposal. If approved, the order will be sent to the simulated exchange and executed.

<p align="center">
  <img src="assets/risk.png" width="70%" style="display: inline-block; margin: 0 2%;">
</p>

## Installation and CLI

### Installation

Clone TradingAgents:
```bash
git clone https://github.com/TauricResearch/TradingAgents.git
cd TradingAgents
```

Create a virtual environment in any of your favorite environment managers:
```bash
conda create -n tradingagents python=3.12
conda activate tradingagents
```

Or with [uv](https://docs.astral.sh/uv/):
```bash
uv venv --python 3.12
source .venv/bin/activate
```

Install the package and its dependencies (`uv pip install .` with uv):
```bash
pip install .
```

### Docker

Alternatively, run with Docker:
```bash
cp .env.example .env  # add your API keys
docker compose run --rm tradingagents
```

After updating the repository, rebuild the image with `docker compose build`.

For local models with Ollama:
```bash
docker compose --profile ollama run --rm tradingagents-ollama
```

### Required APIs

TradingAgents supports multiple LLM providers. Set the API key for your chosen provider:

```bash
export OPENAI_API_KEY=...          # OpenAI (GPT)
export GOOGLE_API_KEY=...          # Google (Gemini)
export ANTHROPIC_API_KEY=...       # Anthropic (Claude)
export XAI_API_KEY=...             # xAI (Grok)
export DEEPSEEK_API_KEY=...        # DeepSeek
export DASHSCOPE_API_KEY=...       # Qwen — International (dashscope-intl.aliyuncs.com)
export DASHSCOPE_CN_API_KEY=...    # Qwen — China (dashscope.aliyuncs.com)
export ZHIPU_API_KEY=...           # GLM via Z.AI (international)
export ZHIPU_CN_API_KEY=...        # GLM via BigModel (China, open.bigmodel.cn)
export MINIMAX_API_KEY=...         # MiniMax — Global (api.minimax.io)
export MINIMAX_CN_API_KEY=...      # MiniMax — China (api.minimaxi.com)
export OPENROUTER_API_KEY=...      # OpenRouter
export MISTRAL_API_KEY=...         # Mistral
export MOONSHOT_API_KEY=...        # Kimi (Moonshot)
export GROQ_API_KEY=...            # Groq
export NVIDIA_API_KEY=...          # NVIDIA NIM
```

### Optional data vendors

Alpha Vantage and FRED are market-data vendors, not LLM providers — neither is required. `yfinance` is the zero-config default for prices, fundamentals, and news; FRED (macro indicators) is the default in `data_vendors`, but the news analyst degrades to a clear "unavailable" message without a key rather than failing the run.

```bash
export ALPHA_VANTAGE_API_KEY=...   # Alternative vendor for prices, fundamentals, news.
                                    # Free tier: 25 requests/day, 5 requests/minute —
                                    # https://www.alphavantage.co/support/#api-key
export FRED_API_KEY=...            # Macro indicators (CPI, Fed funds rate, yields, ...).
                                    # Free: https://fred.stlouisfed.org/docs/api/api_key.html
export REDDIT_CLIENT_ID=...        # Sentiment analyst's Reddit fetch. Without these, it uses
export REDDIT_CLIENT_SECRET=...    # Reddit's public RSS feed, which shares a strict per-IP rate
                                    # limit across every analysis on your network — fine for one
                                    # ticker, but a multi-ticker batch run (e.g.
                                    # scripts/analyze_india_universe.py) will hit repeated 429s
                                    # and slow backoffs. With these set it switches to Reddit's
                                    # OAuth API instead, which has its own per-app budget and also
                                    # returns real upvote/comment counts RSS can't. A "script" app
                                    # from reddit.com/prefs/apps; Reddit may require approval via
                                    # its Data Access Request form before you can create one.
```

Without those credentials the anonymous RSS path is used, and it now reads Reddit's own rate-limit headers and waits exactly as long as Reddit asks (typically 12-60s) instead of failing. That makes a single-ticker run return real posts rather than `<unavailable>`, at roughly 40s per subreddit; a fetch needing longer than `reddit_max_wait_seconds` (default 75) is reported unavailable rather than stalling the run. For a multi-ticker batch, `--no-reddit` is still the better answer.

For Azure OpenAI, copy `.env.enterprise.example` to `.env.enterprise` and fill in your credentials.

For AWS Bedrock, install the extra with `pip install ".[bedrock]"`, set `llm_provider: "bedrock"`, configure AWS credentials (environment variables, `~/.aws/credentials`, or an IAM role) and `AWS_DEFAULT_REGION`, and use a Bedrock model ID, e.g. `us.anthropic.claude-opus-4-8-v1:0`.

For local models, configure Ollama with `llm_provider: "ollama"`. The default endpoint is `http://localhost:11434/v1`; set `OLLAMA_BASE_URL` to point at a remote `ollama-serve`. Pull models with `ollama pull <name>`, and pick "Custom model ID" in the CLI for any model not listed by default.

For any other OpenAI-compatible server (vLLM, LM Studio, llama.cpp, or a custom relay), use `llm_provider: "openai_compatible"` and set the endpoint via `backend_url` (or `TRADINGAGENTS_LLM_BACKEND_URL`), e.g. `http://localhost:8000/v1` for vLLM or `http://localhost:1234/v1` for LM Studio. The model is whatever your server serves. No key is needed for local servers; set `OPENAI_COMPATIBLE_API_KEY` when the endpoint requires one.

Alternatively, copy `.env.example` to `.env` and fill in your keys:
```bash
cp .env.example .env
```

### Running at zero cost

Every data source this project needs is keyless: yfinance for prices and statements, NSE/RBI/screener.in for the India context, Reddit RSS and StockTwits for sentiment. The only thing that costs money is the LLM, and one free tier is large enough to run a whole universe.

```bash
python scripts/analyze_india_universe.py --free --resume --no-reddit
```

`--free` selects Gemini's free tier, restricts data to keyless vendors, and halves the per-ticker token cost. It needs `GOOGLE_API_KEY` — free, no card, from [aistudio.google.com/apikey](https://aistudio.google.com/apikey).

Why Gemini and not the others. A ticker costs about **15 requests**, and the binding limit is **requests per day**. Read your own cap off a 429 rather than a docs page: published guides say 1,000/day for flash-lite, but the error returned by this key said `PerDay, limit: 500`. At 500 a day that is ~33 tickers, measured on a real 50-ticker run:

| Free tier | Limits | Verdict for a batch |
|---|---|---|
| **Gemini flash-lite** | **500 req/day (measured on this key)** · 15 rpm · 250k tokens/min | **Workable** — about 33 tickers/day |
| Groq | 30 rpm · **6k tokens/min** | A single market-analyst turn can exceed the token budget |
| OpenRouter `:free` | 20 rpm · **50 req/day** at zero balance | About 3 tickers/day |
| Ollama (local) | Unlimited, offline | Free forever, but small local models are unreliable at the structured output and tool calls this pipeline needs |

Ollama is still worth having for development — set `llm_provider: "ollama"` and any model you have pulled; no key is required and `OLLAMA_BASE_URL` points at a remote host if you have one. On a 4 GB laptop GPU expect 3B-class models, which are fine for exercising the plumbing and weak at the analysis itself.

**Where the tokens actually go.** The data is not the expensive part — every tool together returns about 6,100 tokens. The cost is the tool-call loop: the agent re-sends its whole message history each round, so the market analyst's 8 indicators mean ~10 rounds and roughly 22,000 tokens. `market_indicator_budget` is the lever; `--free` sets it to 4, which roughly halves tokens per ticker and costs little, since the prompt already asks for non-redundant indicators.

A 50-name universe therefore needs two days, or `--limit 30` today and `--resume` tomorrow. `--resume` skips only tickers that already succeeded, so re-running the same command picks up exactly the ones the quota cut off.

Alpha Vantage is deliberately unused here: its free tier is 25 requests/day, which a single ticker can exhaust. FRED needs a free key but degrades to a sentinel without one, so the run continues either way.

### CLI Usage

Launch the interactive CLI:
```bash
tradingagents          # installed command
python -m cli.main     # alternative: run directly from source
```
You will see a screen where you can select your desired tickers, analysis date, LLM provider, research depth, and more. Your previous run's answers come back as the defaults, so pressing Enter accepts them. The `TRADINGAGENTS_*` variables in `.env` still skip their step entirely.

### Markets and tickers

TradingAgents works with any market Yahoo Finance covers, using the exchange-suffixed ticker. Company identity and the alpha benchmark resolve automatically per market.

- US: `AAPL`, `SPY`
- Hong Kong: `0700.HK` · Tokyo: `7203.T` · London: `AZN.L`
- India: `RELIANCE.NS`, `.BO` · Canada: `.TO` · Australia: `.AX`
- China A-shares: Shanghai `.SS`, Shenzhen `.SZ` (e.g. `600519.SS` for Kweichow Moutai)
- Crypto: `BTC-USD`, `ETH-USD`

For `.NS`/`.BO` tickers, the sentiment analyst automatically routes to Indian subreddits and the news/market/fundamentals analysts get India-specific prompt guidance (India VIX, FRED's India macro series, currency/governance caveats), plus pre-computed blocks: the stock's 1/3/6-month return beside its sector and the Nifty 50 (market analyst) and Brent crude and USD/INR (news analyst) — no config needed. Company news comes from Google News' India edition (`google_news`, no key), which is first in the news chain: for 15-22 Sep 2026 Yahoo returned zero articles for NESTLEIND, BHARTIARTL, ULTRACEMCO and TCS, while Google News returned 36-100 per stock from 30-70 outlets. Duplicates, quote pages and group-company stories are filtered out, and each story keeps the number of outlets that carried it. Set `local_sentiment="finbert"` (as the `--free` preset does, with `pip install "tradingagents[sentiment]"`) to have headlines scored locally by FinBERT before the LLM reads them. `"data_vendors": {"news_data": "india_rss,yfinance"}` additionally serves Economic Times/Mint RSS for macro headlines.

#### NSE market data for Indian tickers

`.NS` tickers additionally get live NSE data pasted into two analysts' prompts, with no key and no setup:

| Analyst | Data |
|---|---|
| News | FII/DII net institutional flows, India VIX, Nifty 50 level, Nifty put-call ratio, and the company's recent exchange announcements |
| Fundamentals | Promoter/public shareholding across recent quarters, and corporate actions (dividends, bonuses, splits) |

Promoter holding matters here because the alternative is wrong: yfinance's `heldPercentInsiders` reports 51.8% for Reliance against the 50.48% actually filed. Promoter *pledging* and the FII/DII split within public holding remain unavailable from any free source, and the prompt says so rather than inviting the model to guess.

This data is read from NSE's public JSON endpoints, which are undocumented and can change. Guard rails: every figure carries its own as-of date; a snapshot dated after the analysis date is refused so a historical run cannot see post-decision data; values are sanity-checked (institutional net must equal buy minus sell, VIX within range, shareholding summing to 100%); and any failure appears in the prompt as an explicit `<... unavailable ...>` marker, never as a silent gap the model might read as "nothing happened".

Check the sources against independent ones at any time:

```bash
python scripts/verify_india_sources.py                      # today, four large-caps
python scripts/verify_india_sources.py --date 2026-09-18 --tickers RELIANCE.NS,TCS.NS
```

It cross-checks Nifty and India VIX against Yahoo Finance and exits non-zero if anything disagrees. Turn the whole feature off with `india_data_enabled: false`, `TRADINGAGENTS_INDIA_DATA_ENABLED=false`, or `--no-india-data` on the batch runner — worth doing if NSE blocks your network, since each blocked fetch costs a timeout first. `.BO`-only tickers are skipped: a BSE ticker's root is not assumed to name the same company on NSE.

RBI's current policy rates (repo, SDF, MSF, bank rate, CRR, SLR) are included too, scraped from `rbi.org.in`. FRED has no live India policy-rate series — its `india_discount_rate` alias was removed because the series behind it stopped updating in July 2022 and would have reported 5.15% against an actual repo rate of 5.25%. Because RBI's page states current values with no as-of date, these are refused on historical runs rather than risk asserting a rate that was not then in force.

#### Optional: screener.in for the FII/DII split

NSE's filings report promoter versus public as a single split, and never break the public half into foreign (FII) and domestic (DII) institutions — often the more interesting half. Reliance's FII holding fell from 21.30% to 17.19% over eight quarters while DII rose from 17.61% to 21.10%, a rotation neither the aggregate nor the price reveals. [screener.in](https://www.screener.in) publishes that split, along with P/E, ROCE, ROE and book value.

It is **off by default**, being a third-party site with no API whose terms cover personal, non-commercial use:

```python
config = {"screener_enabled": True}     # or TRADINGAGENTS_SCREENER_ENABLED=true
```

When enabled, requests are throttled and cached, sent with an identified user agent, and NSE stays the primary source — if the two disagree on promoter holding, the prompt says so and tells the model to prefer the exchange filing. Like the RBI rates, it is live-only: screener labels shareholding by quarter end rather than filing date, so there is no way to know what was public on a past date.

Promoter *pledging* remains unavailable from every free source tried, and the fundamentals prompt states that outright rather than inviting the model to guess.

<p align="center">
  <img src="assets/cli/cli_init.png" width="100%" style="display: inline-block; margin: 0 2%;">
</p>

An interface will appear showing results as they load, letting you track the agent's progress as it runs.

<p align="center">
  <img src="assets/cli/cli_news.png" width="100%" style="display: inline-block; margin: 0 2%;">
</p>

<p align="center">
  <img src="assets/cli/cli_transaction.png" width="100%" style="display: inline-block; margin: 0 2%;">
</p>

## TradingAgents Package

### Implementation Details

We built TradingAgents with LangGraph to ensure flexibility and modularity. The framework supports multiple LLM providers: OpenAI, Google, Anthropic, xAI, DeepSeek, Qwen (Alibaba DashScope, international and China endpoints), GLM (Zhipu), MiniMax (global + China), OpenRouter, Ollama for local models, and Azure OpenAI for enterprise.

### Python Usage

To use TradingAgents inside your code, you can import the `tradingagents` module and initialize a `TradingAgentsGraph()` object. The `.propagate()` function will return a decision. You can run `main.py`, here's also a quick example:

```python
from tradingagents.graph.trading_graph import TradingAgentsGraph
from tradingagents.default_config import DEFAULT_CONFIG

ta = TradingAgentsGraph(debug=True, config=DEFAULT_CONFIG.copy())

# forward propagate
_, decision = ta.propagate("NVDA", "2026-09-01")
print(decision)
```

You can also adjust the default configuration to set your own choice of LLMs, debate rounds, etc.

```python
from tradingagents.graph.trading_graph import TradingAgentsGraph
from tradingagents.default_config import DEFAULT_CONFIG

config = DEFAULT_CONFIG.copy()
config["llm_provider"] = "openai"        # e.g. openai, google, anthropic, deepseek, groq, ollama; openai_compatible covers any OpenAI-compatible endpoint (vLLM, LM Studio, llama.cpp, ...)
config["deep_think_llm"] = "gpt-5.6"      # Model for complex reasoning
config["quick_think_llm"] = "gpt-5.6-luna" # Model for quick tasks
config["max_debate_rounds"] = 2

ta = TradingAgentsGraph(debug=True, config=config)
_, decision = ta.propagate("NVDA", "2026-09-01")
print(decision)
```

See `tradingagents/default_config.py` for all configuration options.

### Fundamentals as filed

US company statements can come from SEC EDGAR, which records the date every figure was filed. A run dated in the past then reads the statements exactly as they stood that day: a fiscal year that has ended but has not been filed yet is not served, and a figure restated later still reads as first reported. Apple's 2008 total assets were filed as $39.6B and restated to $36.2B in 2010, so a run dated in between reads $39.6B.

EDGAR needs no account or API key. Add the vendor to the chain:

```python
config["data_vendors"]["fundamental_data"] = "sec_edgar,yfinance"
```

SEC asks callers to identify themselves and refuses requests that carry no contact address, so a default one is sent. Set your own so SEC can reach you rather than the project:

```bash
SEC_EDGAR_USER_AGENT="Your Name your@email.com"
```

It covers companies that file with the SEC, including foreign companies listed in the US. Anything else, such as Hong Kong or A-share listings, falls through to the next vendor in the chain. EDGAR's machine-readable filings begin in 2009, and a fourth quarter is reported as unavailable rather than derived, because filers publish it only inside the annual figure.

### Current holdings

By default the agents do not know what you hold, so their guidance is written for a reader who applies it to their own position. Pass a portfolio to have the trader, the risk analysts and the portfolio manager work against your actual book.

```python
from tradingagents.portfolio import PortfolioContext

portfolio = PortfolioContext.model_validate({
    "cash": 25000.0,
    "currency": "USD",
    "positions": [{"ticker": "NVDA", "quantity": 120, "average_price": 150.0}],
})
_, decision = ta.propagate("NVDA", "2026-09-01", portfolio=portfolio)
```

The CLI takes the same content as a JSON file: `tradingagents --portfolio my_book.json`.

An empty `positions` list means a flat book, which is different from passing nothing. A run without a portfolio is never treated as flat.

## Persistence and Recovery

TradingAgents persists two kinds of state across runs.

### Decision log

The decision log is always on. Each completed run appends its decision to `~/.tradingagents/memory/trading_memory.md`. On the next run for the same ticker, TradingAgents fetches the realised return (raw, and alpha against the instrument's regional benchmark), generates a one-paragraph reflection, and injects the most recent same-ticker decisions plus recent cross-ticker lessons into the Portfolio Manager prompt, so each analysis carries forward what worked and what didn't.

Override the path with `TRADINGAGENTS_MEMORY_LOG_PATH`.

### Checkpoint resume

Checkpoint resume is opt-in via `--checkpoint`. When enabled, LangGraph saves state after each node so a crashed or interrupted run resumes from the last successful step instead of starting over. The run view says whether it resumed a saved run or started fresh. Checkpoints are cleared automatically on successful completion.

Per-ticker SQLite databases live at `~/.tradingagents/cache/checkpoints/<TICKER>.db` (override the base with `TRADINGAGENTS_CACHE_DIR`). Use `--clear-checkpoints` to reset all of them before a run.

```bash
tradingagents --checkpoint           # enable for this run
tradingagents --clear-checkpoints    # reset before running
```

```python
config = DEFAULT_CONFIG.copy()
config["checkpoint_enabled"] = True
ta = TradingAgentsGraph(config=config)
_, decision = ta.propagate("NVDA", "2026-09-01")
```

## Evaluating decisions over time

One run gives one decision, which cannot tell you whether the system decides well. `run_backtest` runs the same pipeline over a grid of tickers and dates, writes to a decision log of its own, and scores the decisions whose holding window has since traded.

```python
from tradingagents.backtest import iter_grid, run_backtest, summarize
from tradingagents.agents.utils.memory import TradingMemoryLog

dates = iter_grid("2026-06-01", "2026-08-01", every_n_days=7)
result = run_backtest(["NVDA", "AAPL"], dates, config, selected_analysts=["market", "news"])
print(summarize(TradingMemoryLog({"memory_log_path": str(result.log_path)})).render())
```

From the CLI:

```bash
tradingagents backtest NVDA,AAPL --start 2026-06-01 --end 2026-08-01 --every 7
```

Each cell is scored on realized alpha against the instrument's regional benchmark, grouped by rating. Your own decision log is never written to, and re-running the same grid with `run_id=result.run_id` skips the cells that already ran, so an interrupted sweep continues where it stopped.

## Reproducibility

TradingAgents is LLM-driven, so two runs of the same ticker and date can differ. This is expected for a research tool built on language models, not a defect. The variation comes from a few distinct sources, and it helps to separate them.

Language model sampling is non-deterministic. Even at a fixed temperature, providers do not guarantee byte-identical output across calls, and reasoning models (the default GPT-5.x family, and any thinking-mode model) vary the most because their internal reasoning is itself sampled.

Live data moves. News, StockTwits, and Reddit return different content as time passes, so a run today sees different inputs than a run last week even for the same historical trade date. Pin the analysis date to hold the price and indicator window fixed, but the social and news sources still reflect "now".

To reduce variation you can lower the sampling temperature. Set `temperature` in your config (or `TRADINGAGENTS_TEMPERATURE` in `.env`); lower values make models that honor it more repeatable. The current curated models are reasoning-first and largely ignore temperature, so for tighter reproducibility name a non-reasoning model in your config, or in `TRADINGAGENTS_DEEP_THINK_LLM` and `TRADINGAGENTS_QUICK_THINK_LLM`. Any model ID your provider serves is accepted, whether or not the picker lists it.

```python
config = DEFAULT_CONFIG.copy()
config["llm_provider"] = "openai"
config["temperature"] = 0.0
# Reasoning models ignore temperature. For tighter reproducibility, name a
# non-reasoning model in deep_think_llm / quick_think_llm.
```

What does not vary anymore: the analyzed company identity is resolved deterministically from the ticker before any agent runs, and the market analyst grounds exact price and indicator claims in a verified data snapshot. Earlier reports of "different companies" or fabricated price levels across runs are addressed by these two mechanisms.

Backtest results are not guaranteed to match any published figure. Returns depend on the model, the temperature, the date range, data quality, and the sampling above. Treat the framework as a research scaffold for studying multi-agent analysis, not as a strategy with a fixed, replicable return.

## Contributing

Contributions are welcome: bug fixes, documentation, and feature ideas; past contributions are credited per release in [`CHANGELOG.md`](CHANGELOG.md).

## Citation

The citation below is for the original TradingAgents work by Tauric Research.
If this framework helps you, please cite **their** paper — not this fork.

```
@misc{xiao2025tradingagentsmultiagentsllmfinancial,
      title={TradingAgents: Multi-Agents LLM Financial Trading Framework}, 
      author={Yijia Xiao and Edward Sun and Di Luo and Wei Wang},
      year={2025},
      eprint={2412.20138},
      archivePrefix={arXiv},
      primaryClass={q-fin.TR},
      url={https://arxiv.org/abs/2412.20138}, 
}
```
