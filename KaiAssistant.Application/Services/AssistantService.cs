using System.Text.Json;
using System.Text.Json.Nodes;
using System.Diagnostics;
using System.Diagnostics.Metrics;
using System.Security.Cryptography;
using System.Text;
using System.Text.RegularExpressions;
using System.Runtime.CompilerServices;
using KaiAssistant.Application.Diagnostics;
using KaiAssistant.Application.Interfaces;
using KaiAssistant.Application.Options;
using KaiAssistant.Domain.Entities;
using Microsoft.Extensions.Logging;
using Microsoft.Extensions.Options;

namespace KaiAssistant.Application.Services;

public class AssistantService : IAssistantService
{
    private static readonly Meter Meter = new("KaiAssistant.AssistantService", "1.0.0");
    private static readonly Counter<long> AssistantRequests = Meter.CreateCounter<long>("assistant_requests_total");
    private static readonly Histogram<double> AssistantLatency = Meter.CreateHistogram<double>("assistant_response_latency", "ms");
    private static readonly Counter<long> AssistantStreamRequests = Meter.CreateCounter<long>("assistant_stream_requests_total");
    private static readonly Histogram<double> AssistantStreamTtft = Meter.CreateHistogram<double>("assistant_stream_ttft_ms", "ms");
    private static readonly Histogram<double> AssistantStreamDuration = Meter.CreateHistogram<double>("assistant_stream_duration_ms", "ms");
    private static readonly Histogram<double> AssistantStreamThroughput = Meter.CreateHistogram<double>("assistant_stream_throughput_tps", "tokens_per_second");

    private static readonly Meter AiModelsMeter = new("KaiAssistant.AiModels", "1.0.0");
    private static readonly Counter<long> AiModelRequests = AiModelsMeter.CreateCounter<long>("ai_model_requests_total");
    private static readonly Counter<long> AiModelFailures = AiModelsMeter.CreateCounter<long>("ai_model_failures_total");
    private static readonly Counter<long> AiFallbackCount = AiModelsMeter.CreateCounter<long>("ai_fallback_count");
    private static readonly Counter<double> AiCostEstimateTotal = AiModelsMeter.CreateCounter<double>("ai_cost_estimate_total");
    private static readonly Histogram<double> AiModelLatencyMs = AiModelsMeter.CreateHistogram<double>("ai_model_latency_ms", "ms");

    private readonly IResumeContextProvider _resumeProvider;
    private readonly IAiPromptBuilder _promptBuilder;
    private readonly IAiModelGateway _gateway;
    private readonly IOptions<GeminiSettings> _options;
    private readonly IModelOrchestrator _orchestrator;
    private readonly IOptionsMonitor<AiGovernanceOptions>? _governanceOptions;
    private readonly IOptionsMonitor<AiStreamingOptions>? _streamingOptions;
    private readonly ICacheService? _cache;
    private readonly IFeatureFlagService? _featureFlags;
    private readonly IModelHealthService? _modelHealth;
    private readonly ILogger<AssistantService> _logger;

    public AssistantService(
        IResumeContextProvider resumeProvider,
        IAiPromptBuilder promptBuilder,
        IAiModelGateway gateway,
        IModelOrchestrator orchestrator,
        IOptions<GeminiSettings> options,
        ILogger<AssistantService> logger,
        IOptionsMonitor<AiGovernanceOptions>? governanceOptions = null,
        IOptionsMonitor<AiStreamingOptions>? streamingOptions = null,
        ICacheService? cache = null,
        IFeatureFlagService? featureFlags = null,
        IModelHealthService? modelHealth = null)
    {
        _resumeProvider = resumeProvider;
        _promptBuilder = promptBuilder;
        _gateway = gateway;
        _orchestrator = orchestrator;
        _options = options;
        _governanceOptions = governanceOptions;
        _streamingOptions = streamingOptions;
        _cache = cache;
        _featureFlags = featureFlags;
        _modelHealth = modelHealth;
        _logger = logger;
    }

    public async IAsyncEnumerable<AiStreamChunk> StreamQuestionAsync(
        string question,
        ConversationMessage[]? history = null,
        AssistantContext? context = null,
        [EnumeratorCancellation] CancellationToken cancellationToken = default)
    {
        var sw = Stopwatch.StartNew();
        var messageId = Guid.NewGuid().ToString("N");
        var streaming = _streamingOptions?.CurrentValue ?? new AiStreamingOptions();

        if (string.IsNullOrWhiteSpace(question))
        {
            yield return new AiStreamChunk
            {
                Type = "error",
                MessageId = messageId,
                ErrorCode = "INVALID_INPUT",
                Retryable = false,
                ErrorMessage = "Please provide a question."
            };
            yield break;
        }

        if ((_featureFlags is not null && !_featureFlags.EnableStreaming) || !streaming.Enabled)
        {
            var buffered = await AskQuestionAsync(question, history, context, cancellationToken).ConfigureAwait(false);
            yield return new AiStreamChunk
            {
                Type = "delta",
                MessageId = messageId,
                Text = buffered.Text,
                ModelUsed = buffered.ModelUsed,
                FallbackUsed = buffered.FallbackUsed,
                EstimatedCostUsd = buffered.EstimatedCostUsd
            };

            yield return new AiStreamChunk
            {
                Type = "completed",
                MessageId = messageId,
                ModelUsed = buffered.ModelUsed,
                FallbackUsed = buffered.FallbackUsed,
                LatencyMs = buffered.LatencyMs,
                ThroughputTokensPerSecond = buffered.LatencyMs > 0
                    ? EstimateTokens(buffered.Text) / (buffered.LatencyMs / 1000d)
                    : null,
                EstimatedCostUsd = buffered.EstimatedCostUsd
            };
            yield break;
        }

        AssistantStreamRequests.Add(1, KeyValuePair.Create<string, object?>("endpoint", "assistant.stream"));

        var (payloadJson, routing) = await BuildPromptPayloadAsync(question, history, context, cancellationToken).ConfigureAwait(false);
        if (routing.CandidateModels.Count == 0)
        {
            yield return new AiStreamChunk
            {
                Type = "error",
                MessageId = messageId,
                ErrorCode = "MODEL_NOT_CONFIGURED",
                Retryable = false,
                ErrorMessage = "Service configuration error. Please try again later."
            };
            yield break;
        }

        var ttftMs = (double?)null;
        var emittedTokens = 0;
        var anyDelta = false;
        var lastModel = routing.SelectedPrimaryModel;
        var fallbackUsed = false;

        _logger.LogInformation(
            "AI stream started: messageId={MessageId} selectedModel={SelectedModel}",
            messageId,
            routing.SelectedPrimaryModel);

        try
        {
            await foreach (var gatewayChunk in _gateway.StreamGenerationRequestAsync(
                               payloadJson,
                               routing.CandidateModels,
                               streaming.MaxStreamDurationSeconds,
                               streaming.MaxTokensPerStream,
                               cancellationToken).ConfigureAwait(false))
            {
                cancellationToken.ThrowIfCancellationRequested();

                if (gatewayChunk.IsCompleted)
                {
                    lastModel = gatewayChunk.UsedModel ?? lastModel;
                    fallbackUsed = gatewayChunk.FallbackUsed;
                    continue;
                }

                var delta = gatewayChunk.DeltaText;
                if (string.IsNullOrWhiteSpace(delta))
                {
                    continue;
                }

                anyDelta = true;
                lastModel = gatewayChunk.UsedModel ?? lastModel;
                fallbackUsed = gatewayChunk.FallbackUsed;

                if (!ttftMs.HasValue)
                {
                    ttftMs = sw.Elapsed.TotalMilliseconds;
                    AssistantStreamTtft.Record(ttftMs.Value, KeyValuePair.Create<string, object?>("model", lastModel ?? "unknown"));
                }

                emittedTokens += EstimateTokens(delta);
                _logger.LogDebug(
                    "AI stream delta: messageId={MessageId} model={Model} chars={Chars} emittedTokens={EmittedTokens}",
                    messageId,
                    lastModel,
                    delta.Length,
                    emittedTokens);

                yield return new AiStreamChunk
                {
                    Type = "delta",
                    MessageId = messageId,
                    Text = delta,
                    ModelUsed = lastModel,
                    FallbackUsed = fallbackUsed,
                    EstimatedCostUsd = routing.EstimatedCostUsd
                };
            }

            sw.Stop();
            if (!anyDelta)
            {
                yield return new AiStreamChunk
                {
                    Type = "error",
                    MessageId = messageId,
                    ErrorCode = "EMPTY_STREAM",
                    Retryable = true,
                    ErrorMessage = "I am temporarily unavailable. Please try again later."
                };
                yield break;
            }

            var throughput = sw.Elapsed.TotalSeconds > 0
                ? emittedTokens / sw.Elapsed.TotalSeconds
                : 0d;

            if (!string.IsNullOrWhiteSpace(lastModel) && routing.EstimatedCostUsd > 0m)
            {
                _modelHealth?.RecordUsage(lastModel, DateTimeOffset.UtcNow, routing.EstimatedInputTokens, emittedTokens, routing.EstimatedCostUsd);
                AiCostEstimateTotal.Add((double)routing.EstimatedCostUsd, KeyValuePair.Create<string, object?>("model", lastModel));
            }

            AssistantStreamDuration.Record(sw.Elapsed.TotalMilliseconds, KeyValuePair.Create<string, object?>("model", lastModel ?? "unknown"));
            AssistantStreamThroughput.Record(throughput, KeyValuePair.Create<string, object?>("model", lastModel ?? "unknown"));

            _logger.LogInformation(
                "AI stream completed: messageId={MessageId} model={Model} fallback={FallbackUsed} durationMs={DurationMs} ttftMs={TtftMs} throughputTps={ThroughputTps}",
                messageId,
                lastModel,
                fallbackUsed,
                sw.Elapsed.TotalMilliseconds,
                ttftMs,
                throughput);

            yield return new AiStreamChunk
            {
                Type = "completed",
                MessageId = messageId,
                ModelUsed = lastModel,
                FallbackUsed = fallbackUsed,
                TtftMs = ttftMs,
                LatencyMs = sw.Elapsed.TotalMilliseconds,
                ThroughputTokensPerSecond = throughput,
                EstimatedCostUsd = routing.EstimatedCostUsd
            };
        }
        finally
        {
            if (cancellationToken.IsCancellationRequested)
            {
                _logger.LogInformation(
                    "AI stream cancelled: messageId={MessageId} durationMs={DurationMs} model={Model}",
                    messageId,
                    sw.Elapsed.TotalMilliseconds,
                    lastModel);
            }
        }
    }

    public async Task<AiResponse> AskQuestionAsync(
        string question,
        ConversationMessage[]? history = null,
        AssistantContext? context = null,
        CancellationToken cancellationToken = default)
    {
        var sw = Stopwatch.StartNew();
        var governance = _governanceOptions?.CurrentValue ?? new AiGovernanceOptions();

        // Validate input
        if (string.IsNullOrWhiteSpace(question))
        {
            AssistantRequests.Add(1,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"),
                KeyValuePair.Create<string, object?>("success", false));
            AssistantLatency.Record(sw.Elapsed.TotalMilliseconds,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"));
            return new AiResponse { Text = "Please provide a question." };
        }

        var normalizedQuestion = _promptBuilder.NormalizeInput(question);
        var normalizedHistory = history?
            .Select(x => new ConversationMessage
            {
                Role = _promptBuilder.NormalizeInput(x.Role),
                Content = _promptBuilder.NormalizeInput(x.Content)
            })
            .ToArray();

        var snapshot = await _resumeProvider.GetResumeChunksAsync(cancellationToken).ConfigureAwait(false);
        var resumeMissing = snapshot.Length == 0;
        if (resumeMissing)
        {
            _logger.LogInformation("No resume loaded; answering without resume context.");
        }

        bool includePersonalDetails = _options.Value.IncludePersonalDetails;
        var relevantChunks = await _resumeProvider.GetRelevantChunksAsync(question, cancellationToken).ConfigureAwait(false);
        var filteredChunks = includePersonalDetails
            ? relevantChunks
            : relevantChunks.Where(c => !c.Label.Contains("Personal", StringComparison.OrdinalIgnoreCase)).ToArray();

        if (!includePersonalDetails && filteredChunks.Length < relevantChunks.Length)
        {
            _logger.LogInformation("Personal resume fields filtered per settings");
        }
        else if (filteredChunks.Length > 0)
        {
            _logger.LogInformation("Resume chunks loaded");
        }

        var combinedResume = string.Join("\n\n", filteredChunks.Select(c => $"{c.Label}: {c.Content}"));

        var contextBlock = _promptBuilder.NormalizeContextBlock(context);

        int maxChars = _options.Value.PromptMaxChars;
        if (combinedResume.Length > maxChars)
        {
            combinedResume = combinedResume.Substring(0, maxChars) + "\n\n...[truncated resume context]";
        }

        var maxPromptChars = Math.Max(1000, maxChars * 2);
        if (normalizedQuestion.Length > maxPromptChars)
        {
            normalizedQuestion = normalizedQuestion[..maxPromptChars];
        }

        var promptHash = _promptBuilder.ComputePromptHash(normalizedQuestion, normalizedHistory, combinedResume, context);
        var cacheKey = $"ai-response:{governance.CacheKeyVersion}:{promptHash}";

        if (CanUseResponseCache(governance))
        {
            var cached = await _cache!.GetAsync<string>(cacheKey, cancellationToken).ConfigureAwait(false);
            if (!string.IsNullOrWhiteSpace(cached))
            {
                return new AiResponse
                {
                    Text = ApplyResponseTruncation(cached, governance),
                    LatencyMs = sw.Elapsed.TotalMilliseconds
                };
            }
        }

        var systemPrompt = _promptBuilder.BuildSystemPrompt();
        if (resumeMissing)
        {
            systemPrompt += "\n\nNote: I don't have access to the user's resume. Answer based on general knowledge and be explicit when information is missing. Offer concise suggestions for follow-up questions to get more details.";
        }

        var genConfig = _promptBuilder.BuildGenerationConfig(normalizedQuestion);
        var genConfigNode = JsonSerializer.SerializeToNode(genConfig) as JsonObject ?? new JsonObject();

        // Gemini payload: contents array with role/parts structure
        var contentsArray = new JsonArray();

        // Add system prompt as a model message (system-equivalent)
        contentsArray.Add(new JsonObject
        {
            ["role"] = "model",
            ["parts"] = new JsonArray(new JsonObject { ["text"] = systemPrompt })
        });

        // Add conversation history if provided (limit to last 10 messages to avoid token limits)
        int historyChars = 0;
        if (normalizedHistory != null && normalizedHistory.Length > 0)
        {
            var recentHistory = normalizedHistory.Skip(Math.Max(0, normalizedHistory.Length - 10));
            foreach (var msg in recentHistory)
            {
                if (string.IsNullOrWhiteSpace(msg.Content)) continue;
                historyChars += msg.Content.Length;

                // Normalize roles: Gemini accepts only 'user' and 'model'.
                string normalizedRole;
                if (string.Equals(msg.Role, "user", StringComparison.OrdinalIgnoreCase))
                {
                    normalizedRole = "user";
                }
                else if (string.Equals(msg.Role, "model", StringComparison.OrdinalIgnoreCase) || string.Equals(msg.Role, "assistant", StringComparison.OrdinalIgnoreCase))
                {
                    normalizedRole = "model";
                }
                else
                {
                    // Unexpected role value - coerce to 'model' and log a warning
                    _logger.LogWarning("Unrecognized role '{Role}' in conversation history; coercing to 'model'.", msg.Role);
                    normalizedRole = "model";
                }

                contentsArray.Add(new JsonObject
                {
                    ["role"] = normalizedRole,
                    ["parts"] = new JsonArray(new JsonObject { ["text"] = msg.Content })
                });
            }
        }

        if (!string.IsNullOrWhiteSpace(contextBlock))
        {
            contentsArray.Add(new JsonObject
            {
                ["role"] = "model",
                ["parts"] = new JsonArray(new JsonObject { ["text"] = contextBlock })
            });
        }

        // Simple payload-size estimate and guard. If payload seems too large, ask user to clear chat to continue.
        var estimatedSize = systemPrompt.Length + normalizedQuestion.Length + historyChars + combinedResume.Length + contextBlock.Length;
        var sizeThreshold = Math.Max(20000, maxChars * 2);
        if (estimatedSize > sizeThreshold)
        {
            return new AiResponse
            {
                Text = "Our conversation is getting long and may exceed server limits. Please clear chat history to start a fresh conversation (sorry, we're still poor xD).",
                LatencyMs = sw.Elapsed.TotalMilliseconds
            };
        }

        // Add resume/context as a model message (system-equivalent), then add the user's question as a user message
        if (!string.IsNullOrWhiteSpace(combinedResume))
        {
            contentsArray.Add(new JsonObject
            {
                ["role"] = "model",
                ["parts"] = new JsonArray(new JsonObject { ["text"] = $"Resume context:\n{combinedResume}" })
            });
        }

        // Add current user question
        contentsArray.Add(new JsonObject
        {
            ["role"] = "user",
            ["parts"] = new JsonArray(new JsonObject { ["text"] = normalizedQuestion })
        });

        var generationConfig = new JsonObject();
        if (genConfigNode.TryGetPropertyValue("temperature", out var tempNode)) 
            generationConfig["temperature"] = JsonNode.Parse(tempNode!.ToJsonString());
        if (genConfigNode.TryGetPropertyValue("topK", out var topKNode)) 
            generationConfig["topK"] = JsonNode.Parse(topKNode!.ToJsonString());
        if (genConfigNode.TryGetPropertyValue("topP", out var topPNode)) 
            generationConfig["topP"] = JsonNode.Parse(topPNode!.ToJsonString());
        if (genConfigNode.TryGetPropertyValue("maxOutputTokens", out var maxNode)) 
            generationConfig["maxOutputTokens"] = JsonNode.Parse(maxNode!.ToJsonString());
        if (genConfigNode.TryGetPropertyValue("candidateCount", out var candNode)) 
            generationConfig["candidateCount"] = JsonNode.Parse(candNode!.ToJsonString());

        var payloadNode = new JsonObject
        {
            ["contents"] = contentsArray,
            ["generationConfig"] = generationConfig,
            ["safetySettings"] = new JsonArray(
                new JsonObject { ["category"] = "HARM_CATEGORY_HARASSMENT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_HATE_SPEECH", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_SEXUALLY_EXPLICIT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_DANGEROUS_CONTENT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" }
            )
        };

        var json = payloadNode.ToJsonString();
        _logger.LogDebug(
            "Prepared Gemini request: questionLength={QuestionLength}, historyCount={HistoryCount}, chunkCount={ChunkCount}, estimatedSize={EstimatedSize}",
            normalizedQuestion.Length,
            normalizedHistory?.Length ?? 0,
            filteredChunks.Length,
            estimatedSize);

        var estimatedInputTokens = (int)Math.Ceiling((normalizedQuestion.Length + historyChars + combinedResume.Length + contextBlock.Length) / 4d);
        var routing = await _orchestrator
            .BuildDecisionAsync(normalizedQuestion, estimatedInputTokens, cancellationToken)
            .ConfigureAwait(false);

        var modelsToTry = routing.CandidateModels.ToList();
        if (modelsToTry.Count == 0)
        {
            _logger.LogError("No Gemini models configured");
            return new AiResponse { Text = "Service configuration error. Please try again later." };
        }

        var modelCallSw = Stopwatch.StartNew();
        AiModelRequests.Add(1, KeyValuePair.Create<string, object?>("model", routing.SelectedPrimaryModel ?? modelsToTry[0]));

        (string? responseBody, string? usedModel) = await _gateway
            .SendGenerationRequestAsync(json, modelsToTry.Distinct(StringComparer.OrdinalIgnoreCase), cancellationToken)
            .ConfigureAwait(false);
        modelCallSw.Stop();

        if (string.IsNullOrWhiteSpace(responseBody))
        {
            _logger.LogWarning("No successful response received from Gemini models");
            AiModelFailures.Add(1, KeyValuePair.Create<string, object?>("model", routing.SelectedPrimaryModel ?? modelsToTry[0]));
            AssistantRequests.Add(1,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"),
                KeyValuePair.Create<string, object?>("success", false));
            AssistantLatency.Record(sw.Elapsed.TotalMilliseconds,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"));
            return new AiResponse
            {
                Text = "I'm temporarily unavailable. Please try again later.",
                ModelUsed = routing.SelectedPrimaryModel,
                LatencyMs = sw.Elapsed.TotalMilliseconds,
                EstimatedCostUsd = routing.EstimatedCostUsd
            };
        }

        try
        {
            _logger.LogDebug("Gemini response body: {Body}", responseBody);
            using var doc = JsonDocument.Parse(responseBody);

            // Try to extract a text reply from multiple possible response shapes returned by Gemini
            string? TryExtractText(JsonElement el, int depth = 0)
            {
                if (depth > 10) return null;
                switch (el.ValueKind)
                {
                    case JsonValueKind.Object:
                        if (el.TryGetProperty("text", out var t) && t.ValueKind == JsonValueKind.String)
                            return t.GetString();
                        if (el.TryGetProperty("output_text", out var ot) && ot.ValueKind == JsonValueKind.String)
                            return ot.GetString();
                        if (el.TryGetProperty("parts", out var parts) && parts.ValueKind == JsonValueKind.Array && parts.GetArrayLength() > 0)
                        {
                            foreach (var p in parts.EnumerateArray())
                            {
                                var r = TryExtractText(p, depth + 1);
                                if (!string.IsNullOrWhiteSpace(r)) return r;
                            }
                        }
                        if (el.TryGetProperty("content", out var content) )
                        {
                            var r = TryExtractText(content, depth + 1);
                            if (!string.IsNullOrWhiteSpace(r)) return r;
                        }
                        if (el.TryGetProperty("output", out var output) && output.ValueKind == JsonValueKind.Array)
                        {
                            foreach (var o in output.EnumerateArray())
                            {
                                var r = TryExtractText(o, depth + 1);
                                if (!string.IsNullOrWhiteSpace(r)) return r;
                            }
                        }
                        if (el.TryGetProperty("candidates", out var cands) && cands.ValueKind == JsonValueKind.Array)
                        {
                            foreach (var c in cands.EnumerateArray())
                            {
                                var r = TryExtractText(c, depth + 1);
                                if (!string.IsNullOrWhiteSpace(r)) return r;
                            }
                        }
                        break;
                    case JsonValueKind.Array:
                        foreach (var item in el.EnumerateArray())
                        {
                            var r = TryExtractText(item, depth + 1);
                            if (!string.IsNullOrWhiteSpace(r)) return r;
                        }
                        break;
                }
                return null;
            }

            var root = doc.RootElement;
            var replyText = TryExtractText(root);
            if (string.IsNullOrWhiteSpace(replyText))
            {
                _logger.LogWarning("Could not extract reply text from model response");
                AiModelFailures.Add(1, KeyValuePair.Create<string, object?>("model", usedModel ?? routing.SelectedPrimaryModel ?? "unknown"));
                AssistantRequests.Add(1,
                    KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"),
                    KeyValuePair.Create<string, object?>("success", false));
                AssistantLatency.Record(sw.Elapsed.TotalMilliseconds,
                    KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"));
                return new AiResponse
                {
                    Text = "I couldn't generate a suitable response right now.",
                    ModelUsed = usedModel,
                    FallbackUsed = !string.Equals(usedModel, routing.SelectedPrimaryModel, StringComparison.OrdinalIgnoreCase),
                    LatencyMs = sw.Elapsed.TotalMilliseconds,
                    EstimatedCostUsd = routing.EstimatedCostUsd
                };
            }

            AssistantRequests.Add(1,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"),
                KeyValuePair.Create<string, object?>("success", true));
            AssistantLatency.Record(sw.Elapsed.TotalMilliseconds,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"));

            var modelUsed = usedModel ?? routing.SelectedPrimaryModel;
            if (!string.IsNullOrWhiteSpace(modelUsed))
            {
                AiModelLatencyMs.Record(modelCallSw.Elapsed.TotalMilliseconds, KeyValuePair.Create<string, object?>("model", modelUsed));
            }

            var finalResponse = ApplyResponseTruncation(replyText.Trim(), governance);
            var estimatedOutputTokens = EstimateTokens(finalResponse);
            if (CanUseResponseCache(governance))
            {
                await _cache!
                    .SetAsync(
                        cacheKey,
                        finalResponse,
                        TimeSpan.FromSeconds(Math.Max(5, governance.ResponseCacheTtlSeconds)),
                        cancellationToken)
                    .ConfigureAwait(false);
            }

            var fallbackUsed = !string.Equals(modelUsed, routing.SelectedPrimaryModel, StringComparison.OrdinalIgnoreCase);
            if (fallbackUsed)
            {
                AiFallbackCount.Add(1,
                    KeyValuePair.Create<string, object?>("from", routing.SelectedPrimaryModel ?? "unknown"),
                    KeyValuePair.Create<string, object?>("to", modelUsed ?? "unknown"));
            }

            _logger.LogInformation(
                "AI model decision: class={RequestClass} selected={Selected} used={Used} fallback={Fallback} estimatedCostUsd={EstimatedCostUsd} inputTokens={InputTokens} scoreTop={ScoreTop}",
                routing.RequestClass,
                routing.SelectedPrimaryModel,
                modelUsed,
                fallbackUsed,
                routing.EstimatedCostUsd,
                estimatedInputTokens,
                routing.ScoreBreakdown.FirstOrDefault()?.FinalScore);

            if (!string.IsNullOrWhiteSpace(modelUsed) && routing.EstimatedCostUsd > 0m)
            {
                _modelHealth?.RecordUsage(modelUsed, DateTimeOffset.UtcNow, routing.EstimatedInputTokens, estimatedOutputTokens, routing.EstimatedCostUsd);
                AiCostEstimateTotal.Add((double)routing.EstimatedCostUsd, KeyValuePair.Create<string, object?>("model", modelUsed));
            }

            return new AiResponse
            {
                Text = finalResponse,
                ModelUsed = modelUsed,
                FallbackUsed = fallbackUsed,
                LatencyMs = sw.Elapsed.TotalMilliseconds,
                EstimatedCostUsd = routing.EstimatedCostUsd
            };
        }
        catch (Exception ex)
        {
            _logger.LogError(ex, "Failed to parse model response");
            AiModelFailures.Add(1, KeyValuePair.Create<string, object?>("model", usedModel ?? routing.SelectedPrimaryModel ?? "unknown"));
            AssistantRequests.Add(1,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"),
                KeyValuePair.Create<string, object?>("success", false));
            AssistantLatency.Record(sw.Elapsed.TotalMilliseconds,
                KeyValuePair.Create<string, object?>("endpoint", "assistant.ask"));
            return new AiResponse
            {
                Text = "I couldn't parse the response from the AI model.",
                ModelUsed = usedModel,
                LatencyMs = sw.Elapsed.TotalMilliseconds,
                EstimatedCostUsd = routing.EstimatedCostUsd
            };
        }
    }

    private bool CanUseResponseCache(AiGovernanceOptions governance)
    {
        return governance.EnableResponseCache &&
               _cache is not null &&
               _featureFlags is not null &&
               _featureFlags.EnableCache &&
               _featureFlags.EnableAiResponseCache;
    }

    private static string ApplyResponseTruncation(string response, AiGovernanceOptions governance)
    {
        if (!governance.EnableResponseTruncation)
        {
            return response;
        }

        var maxChars = Math.Max(200, governance.MaxResponseChars);
        if (response.Length <= maxChars)
        {
            return response;
        }

        return response[..maxChars] + "\n\n[Response truncated for safety.]";
    }

    private async Task<(string PayloadJson, AiRoutingDecision Routing)> BuildPromptPayloadAsync(
        string question,
        ConversationMessage[]? history,
        AssistantContext? context,
        CancellationToken cancellationToken)
    {
        var normalizedQuestion = _promptBuilder.NormalizeInput(question);
        var normalizedHistory = history?
            .Select(x => new ConversationMessage
            {
                Role = _promptBuilder.NormalizeInput(x.Role),
                Content = _promptBuilder.NormalizeInput(x.Content)
            })
            .ToArray();

        var snapshot = await _resumeProvider.GetResumeChunksAsync(cancellationToken).ConfigureAwait(false);
        var includePersonalDetails = _options.Value.IncludePersonalDetails;
        var relevantChunks = await _resumeProvider.GetRelevantChunksAsync(question, cancellationToken).ConfigureAwait(false);
        var filteredChunks = includePersonalDetails
            ? relevantChunks
            : relevantChunks.Where(c => !c.Label.Contains("Personal", StringComparison.OrdinalIgnoreCase)).ToArray();

        var combinedResume = string.Join("\n\n", filteredChunks.Select(c => $"{c.Label}: {c.Content}"));
        var contextBlock = _promptBuilder.NormalizeContextBlock(context);

        var maxChars = _options.Value.PromptMaxChars;
        if (combinedResume.Length > maxChars)
        {
            combinedResume = combinedResume[..maxChars] + "\n\n...[truncated resume context]";
        }

        var systemPrompt = _promptBuilder.BuildSystemPrompt();
        if (snapshot.Length == 0)
        {
            systemPrompt += "\n\nNote: I don't have access to the user's resume. Answer based on general knowledge and be explicit when information is missing. Offer concise suggestions for follow-up questions to get more details.";
        }

        var contentsArray = new JsonArray
        {
            new JsonObject
            {
                ["role"] = "model",
                ["parts"] = new JsonArray(new JsonObject { ["text"] = systemPrompt })
            }
        };

        var historyChars = 0;
        if (normalizedHistory is { Length: > 0 })
        {
            foreach (var msg in normalizedHistory.Skip(Math.Max(0, normalizedHistory.Length - 10)))
            {
                if (string.IsNullOrWhiteSpace(msg.Content))
                {
                    continue;
                }

                historyChars += msg.Content.Length;
                var role = string.Equals(msg.Role, "user", StringComparison.OrdinalIgnoreCase)
                    ? "user"
                    : "model";

                contentsArray.Add(new JsonObject
                {
                    ["role"] = role,
                    ["parts"] = new JsonArray(new JsonObject { ["text"] = msg.Content })
                });
            }
        }

        if (!string.IsNullOrWhiteSpace(contextBlock))
        {
            contentsArray.Add(new JsonObject
            {
                ["role"] = "model",
                ["parts"] = new JsonArray(new JsonObject { ["text"] = contextBlock })
            });
        }

        if (!string.IsNullOrWhiteSpace(combinedResume))
        {
            contentsArray.Add(new JsonObject
            {
                ["role"] = "model",
                ["parts"] = new JsonArray(new JsonObject { ["text"] = $"Resume context:\n{combinedResume}" })
            });
        }

        contentsArray.Add(new JsonObject
        {
            ["role"] = "user",
            ["parts"] = new JsonArray(new JsonObject { ["text"] = normalizedQuestion })
        });

        var genConfig = _promptBuilder.BuildGenerationConfig(normalizedQuestion);
        var genConfigNode = JsonSerializer.SerializeToNode(genConfig) as JsonObject ?? new JsonObject();
        var generationConfig = new JsonObject();
        if (genConfigNode.TryGetPropertyValue("temperature", out var tempNode))
        {
            generationConfig["temperature"] = JsonNode.Parse(tempNode!.ToJsonString());
        }

        if (genConfigNode.TryGetPropertyValue("topK", out var topKNode))
        {
            generationConfig["topK"] = JsonNode.Parse(topKNode!.ToJsonString());
        }

        if (genConfigNode.TryGetPropertyValue("topP", out var topPNode))
        {
            generationConfig["topP"] = JsonNode.Parse(topPNode!.ToJsonString());
        }

        if (genConfigNode.TryGetPropertyValue("maxOutputTokens", out var maxNode))
        {
            generationConfig["maxOutputTokens"] = JsonNode.Parse(maxNode!.ToJsonString());
        }

        if (genConfigNode.TryGetPropertyValue("candidateCount", out var candNode))
        {
            generationConfig["candidateCount"] = JsonNode.Parse(candNode!.ToJsonString());
        }

        var payloadNode = new JsonObject
        {
            ["contents"] = contentsArray,
            ["generationConfig"] = generationConfig,
            ["safetySettings"] = new JsonArray(
                new JsonObject { ["category"] = "HARM_CATEGORY_HARASSMENT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_HATE_SPEECH", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_SEXUALLY_EXPLICIT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" },
                new JsonObject { ["category"] = "HARM_CATEGORY_DANGEROUS_CONTENT", ["threshold"] = "BLOCK_MEDIUM_AND_ABOVE" })
        };

        var estimatedInputTokens = (int)Math.Ceiling((normalizedQuestion.Length + historyChars + combinedResume.Length + contextBlock.Length) / 4d);
        var routing = await _orchestrator
            .BuildDecisionAsync(normalizedQuestion, estimatedInputTokens, cancellationToken)
            .ConfigureAwait(false);

        return (payloadNode.ToJsonString(), routing);
    }

    private static int EstimateTokens(string input)
    {
        if (string.IsNullOrWhiteSpace(input))
        {
            return 0;
        }

        var withoutControls = Regex.Replace(input, "[\\u0000-\\u0008\\u000B\\u000C\\u000E-\\u001F]", string.Empty);
        var normalized = Regex.Replace(withoutControls, "\\s+", " ").Trim();
        return (int)Math.Ceiling(normalized.Length / 4d);
    }
}