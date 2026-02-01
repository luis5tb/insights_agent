# Usage Tracking and Metering

This document describes the usage tracking system for monitoring API usage, token consumption, and tool invocations.

## Overview

The Insights Agent uses the **ADK Plugin System** for usage tracking. This approach integrates directly with the agent's execution lifecycle, providing accurate metrics without external dependencies.

### What's Tracked

| Metric | Description | Source |
|--------|-------------|--------|
| `total_requests` | A2A requests processed | `before_run_callback` |
| `total_input_tokens` | LLM prompt tokens | `after_model_callback` |
| `total_output_tokens` | LLM response tokens | `after_model_callback` |
| `total_tokens` | Combined token count | Computed |
| `total_tool_calls` | MCP tool invocations | `after_tool_callback` |

## Architecture

```
┌─────────────────────────────────────────────────────────────────────────┐
│                           A2A Request                                    │
└─────────────────────────────────────────────────────────────────────────┘
                                    │
                                    ▼
┌─────────────────────────────────────────────────────────────────────────┐
│                           ADK Runner                                     │
│  ┌─────────────────────────────────────────────────────────────────┐   │
│  │                    UsageTrackingPlugin                           │   │
│  │                                                                   │   │
│  │  before_run_callback ────► Increment request counter             │   │
│  │                                                                   │   │
│  │  after_model_callback ───► Extract token counts from response    │   │
│  │                                                                   │   │
│  │  after_tool_callback ────► Increment tool call counter           │   │
│  │                                                                   │   │
│  └─────────────────────────────────────────────────────────────────┘   │
│                                    │                                     │
│                                    ▼                                     │
│                          AggregateUsage (in-memory)                      │
└─────────────────────────────────────────────────────────────────────────┘
                                    │
                                    ▼
┌─────────────────────────────────────────────────────────────────────────┐
│                         GET /usage endpoint                              │
└─────────────────────────────────────────────────────────────────────────┘
```

## ADK Plugin System

The Google Agent Development Kit (ADK) provides a powerful plugin system that allows you to observe and customize agent behavior at every stage of execution. The `UsageTrackingPlugin` uses this system to track metrics.

### Plugin Lifecycle Callbacks

ADK plugins can implement these callbacks:

| Callback | When It Runs | Use Case |
|----------|--------------|----------|
| `before_run_callback` | Start of agent execution | Request counting, context setup |
| `after_run_callback` | End of agent execution | Cleanup, final metrics |
| `before_model_callback` | Before LLM call | Request modification |
| `after_model_callback` | After LLM response | Token tracking, response modification |
| `on_model_error_callback` | On LLM error | Error tracking |
| `before_tool_callback` | Before tool execution | Tool call logging |
| `after_tool_callback` | After tool execution | Tool usage tracking |
| `on_tool_error_callback` | On tool error | Error tracking |
| `before_agent_callback` | Before sub-agent call | Sub-agent tracking |
| `after_agent_callback` | After sub-agent call | Sub-agent metrics |

### Plugin Registration

Plugins are registered when creating the ADK `App`:

```python
from google.adk.apps import App
from google.adk.plugins.base_plugin import BasePlugin

class UsageTrackingPlugin(BasePlugin):
    def __init__(self):
        super().__init__(name="usage_tracking")

    # ... callback implementations

# Register the plugin
app = App(
    name="insights-agent",
    root_agent=agent,
    plugins=[UsageTrackingPlugin()],  # Plugin registered here
)
```

## UsageTrackingPlugin Implementation

The `UsageTrackingPlugin` (`src/insights_agent/api/a2a/usage_plugin.py`) implements three callbacks:

### Request Counting

```python
async def before_run_callback(self, *, invocation_context) -> None:
    """Track request count at start of each run."""
    _aggregate_usage.total_requests += 1
    logger.debug(f"Request #{_aggregate_usage.total_requests} started")
    return None
```

This callback fires at the start of every A2A request, incrementing the global request counter.

### Token Tracking

```python
async def after_model_callback(
    self,
    *,
    callback_context,
    llm_response: LlmResponse,
) -> Optional[LlmResponse]:
    """Track token usage from LLM responses."""
    if llm_response.usage_metadata:
        usage = llm_response.usage_metadata
        input_tokens = getattr(usage, "prompt_token_count", 0) or 0
        output_tokens = getattr(usage, "candidates_token_count", 0) or 0

        _aggregate_usage.total_input_tokens += input_tokens
        _aggregate_usage.total_output_tokens += output_tokens

    return None  # Don't modify the response
```

This callback fires after every LLM call. The `usage_metadata` object contains:
- `prompt_token_count`: Tokens in the prompt (input)
- `candidates_token_count`: Tokens in the response (output)
- `total_token_count`: Combined count
- `thoughts_token_count`: Reasoning tokens (for thinking models)

### Tool Call Tracking

```python
async def after_tool_callback(
    self,
    *,
    tool: BaseTool,
    tool_args: dict[str, Any],
    tool_context,
    result: dict,
) -> Optional[dict]:
    """Track tool/MCP calls."""
    _aggregate_usage.total_tool_calls += 1
    tool_name = getattr(tool, "name", type(tool).__name__)
    logger.debug(f"Tool call: {tool_name}")
    return None  # Don't modify the result
```

This callback fires after every MCP tool invocation, tracking tool usage.

## Storage: AggregateUsage

Usage data is stored in a global dataclass:

```python
@dataclass
class AggregateUsage:
    total_input_tokens: int = 0
    total_output_tokens: int = 0
    total_requests: int = 0
    total_tool_calls: int = 0

    def to_dict(self) -> dict:
        return {
            "total_input_tokens": self.total_input_tokens,
            "total_output_tokens": self.total_output_tokens,
            "total_tokens": self.total_input_tokens + self.total_output_tokens,
            "total_requests": self.total_requests,
            "total_tool_calls": self.total_tool_calls,
        }
```

Access functions:
- `get_aggregate_usage()`: Get current usage statistics
- `reset_aggregate_usage()`: Reset counters (useful for testing)

## API Endpoint

### GET /usage

Returns aggregate usage statistics.

**Authentication**: Not required

```bash
curl http://localhost:8000/usage
```

**Response:**

```json
{
  "status": "ok",
  "usage": {
    "total_input_tokens": 12345,
    "total_output_tokens": 45678,
    "total_tokens": 58023,
    "total_requests": 150,
    "total_tool_calls": 75
  }
}
```

## Rate Limiting

The agent includes a separate in-memory rate limiter that works independently from usage tracking.

### Configuration

```bash
# Environment variables
RATE_LIMIT_REQUESTS_PER_MINUTE=60    # Max requests per minute
RATE_LIMIT_REQUESTS_PER_HOUR=1000    # Max requests per hour
```

### How It Works

The `RateLimitMiddleware` uses a sliding window algorithm:

1. Each request timestamp is recorded
2. Old timestamps (> window size) are pruned
3. Count is compared against configured limits
4. If exceeded, returns HTTP 429 with `Retry-After` header

### Rate Limited Paths

Only the A2A endpoint is rate limited:

| Path | Description |
|------|-------------|
| `/` | A2A JSON-RPC endpoint |

### Rate Limit Response

```http
HTTP/1.1 429 Too Many Requests
Retry-After: 60
X-RateLimit-Limit: 60
X-RateLimit-Remaining: 0
Content-Type: application/json

{
  "error": "rate_limit_exceeded",
  "message": "Rate limit exceeded (per_minute)",
  "retry_after": 60
}
```

See [Rate Limiting](rate-limiting.md) for more details.

## Extending for Production

### Per-Tool Metrics

To track usage per tool, extend the `after_tool_callback`:

```python
from collections import defaultdict

_tool_usage = defaultdict(int)

async def after_tool_callback(self, *, tool, tool_args, tool_context, result):
    tool_name = getattr(tool, "name", type(tool).__name__)
    _tool_usage[tool_name] += 1

    # Categorize by service
    if "advisor" in tool_name:
        _aggregate_usage.advisor_calls += 1
    elif "vulnerability" in tool_name:
        _aggregate_usage.vulnerability_calls += 1
    # etc.

    return None
```

### Database Persistence

Replace the in-memory `AggregateUsage` with a database-backed implementation:

```python
from sqlalchemy.ext.asyncio import AsyncSession

class DatabaseUsageTracker:
    async def increment_tokens(self, session: AsyncSession, input: int, output: int):
        await session.execute(
            update(UsageRecord)
            .values(
                input_tokens=UsageRecord.input_tokens + input,
                output_tokens=UsageRecord.output_tokens + output,
            )
        )
        await session.commit()
```

### OpenTelemetry Integration

ADK has built-in OpenTelemetry support. Enable it for distributed tracing:

```bash
# Enable OTEL export to Google Cloud
adk run --otel_to_cloud agents/rh_insights_agent
```

Or configure programmatically:

```python
from opentelemetry import trace
from opentelemetry.exporter.cloud_monitoring import CloudMonitoringMetricsExporter

# Export metrics to Cloud Monitoring
exporter = CloudMonitoringMetricsExporter(project_id="your-project")
```

### Google Cloud Service Control

For marketplace billing, implement a Service Control reporter:

```python
from google.cloud import servicecontrol_v1

class ServiceControlReporter:
    def __init__(self, service_name: str):
        self.client = servicecontrol_v1.ServiceControllerClient()
        self.service_name = service_name

    async def report_usage(self, consumer_id: str, tokens: int):
        operation = servicecontrol_v1.Operation(
            operation_id=str(uuid.uuid4()),
            consumer_id=consumer_id,
            metric_value_sets=[
                servicecontrol_v1.MetricValueSet(
                    metric_name="tokens",
                    metric_values=[
                        servicecontrol_v1.MetricValue(int64_value=tokens)
                    ],
                )
            ],
        )

        await self.client.report(
            service_name=self.service_name,
            operations=[operation],
        )
```

### BigQuery Analytics

ADK provides a BigQuery Agent Analytics Plugin for detailed analytics:

```python
from google.adk.plugins import BigQueryAnalyticsPlugin

app = App(
    name="insights-agent",
    root_agent=agent,
    plugins=[
        UsageTrackingPlugin(),
        BigQueryAnalyticsPlugin(
            project_id="your-project",
            dataset_id="agent_analytics",
        ),
    ],
)
```

## Limitations

The current in-memory implementation:
- Resets when the application restarts
- Is per-instance (not shared across replicas)
- Does not persist historical data
- Does not track per-user or per-order usage

For production deployments with multiple replicas or billing requirements, implement database persistence or use external metrics systems.

## Testing

```bash
# Start the server
python -m insights_agent.main

# Check initial usage
curl http://localhost:8000/usage

# Make A2A requests
curl -X POST http://localhost:8000/ \
  -H "Content-Type: application/json" \
  -H "Authorization: Bearer dev-token" \
  -d '{
    "jsonrpc": "2.0",
    "method": "message/send",
    "id": 1,
    "params": {
      "message": {
        "role": "user",
        "parts": [{"type": "text", "text": "What systems have critical vulnerabilities?"}]
      }
    }
  }'

# Check updated usage
curl http://localhost:8000/usage
```

## References

- [ADK Plugins Documentation](https://google.github.io/adk-docs/plugins/)
- [ADK Callbacks Documentation](https://google.github.io/adk-docs/callbacks/)
- [ADK OpenTelemetry Integration](https://docs.cloud.google.com/stackdriver/docs/instrumentation/ai-agent-adk)
- [BigQuery Agent Analytics Plugin](https://codelabs.developers.google.com/adk-bigquery-agent-analytics-plugin)
