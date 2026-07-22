import 'dart:convert';
import 'dart:io';
import 'dart:async';
import 'dart:collection';
import 'package:flutter/foundation.dart';
import 'package:langchain/langchain.dart';
import 'package:langchain_ollama/langchain_ollama.dart';
import 'package:langchain_openai/langchain_openai.dart';
import 'package:langchain_google/langchain_google.dart';

enum LlmProvider { ollama, openai, google, lmstudio }

// Represents basic information about an AI model.
class OllamaModelInfo {
  final String name;
  final String size;
  final String details;

  OllamaModelInfo(
      {required this.name, required this.size, required this.details});
}

// Represents a message exchanged with the LLM.
class LlmMsg {
  final String role;
  final String content;
  LlmMsg({required this.role, required this.content});
}

// Internal class to represent a queued request.
class _QueuedRequest {
  final List<LlmMsg> messages;
  final int maxTokens;
  final Completer<Stream<String>> completer;

  _QueuedRequest({
    required this.messages,
    required this.maxTokens,
    required this.completer,
  });
}

// Service that handles interactions with the Ollama LLM.
class LlmService {
  static final LlmService _instance = LlmService._internal();
  factory LlmService() => _instance;
  LlmService._internal();

  String? _selectedModelName;
  LlmProvider _activeProvider = LlmProvider.ollama;
  String? _apiKey;
  String _lmStudioBaseUrl = 'http://localhost:1234/v1';

  // Request queue to handle concurrent requests sequentially.
  final Queue<_QueuedRequest> _requestQueue = Queue<_QueuedRequest>();
  bool _isProcessing = false;

  static const String _ollamaBaseUrl = 'http://localhost:11434';

  // Sets the model to be used for inference.
  void setModel(String modelName) {
    _selectedModelName = modelName;
    debugPrint("🤖 [LlmService] Model set: $_selectedModelName");
  }

  // Configures the provider and API key.
  void setProvider(LlmProvider provider, {String? apiKey}) {
    _activeProvider = provider;
    if (apiKey != null) {
      _apiKey = apiKey;
    }
    debugPrint("🤖 [LlmService] Provider set: ${_activeProvider.name}");
  }

  // Sets the LM Studio server base URL.
  void setLmStudioBaseUrl(String url) {
    _lmStudioBaseUrl = url;
    debugPrint("🤖 [LlmService] LM Studio base URL set: $_lmStudioBaseUrl");
  }

  String? get currentModel => _selectedModelName;
  LlmProvider get currentProvider => _activeProvider;
  String get lmStudioBaseUrl => _lmStudioBaseUrl;

  // Checks if Ollama is installed and running.
  Future<bool> isOllamaAvailable() async {
    try {
      final client = HttpClient();
      client.connectionTimeout = const Duration(seconds: 2);

      final request =
          await client.getUrl(Uri.parse('$_ollamaBaseUrl/api/tags'));
      final response = await request.close();

      return response.statusCode == 200;
    } catch (e) {
      return false;
    }
  }

  // Checks if LM Studio is running and reachable.
  Future<bool> isLmStudioAvailable() async {
    try {
      final client = HttpClient();
      client.connectionTimeout = const Duration(seconds: 2);

      final modelsUrl = _getLmStudioModelsUrl();
      final request = await client.getUrl(Uri.parse(modelsUrl));
      if (_apiKey != null && _apiKey!.isNotEmpty) {
        request.headers.set('Authorization', 'Bearer $_apiKey');
      }
      final response = await request.close();

      return response.statusCode == 200;
    } catch (e) {
      return false;
    }
  }

  // Derives the LM Studio /api/v1/models URL from the base URL.
  // Base URL is typically http://localhost:1234/v1 (for OpenAI-compatible chat),
  // but the models listing endpoint is at /api/v1/models.
  String _getLmStudioModelsUrl() {
    final baseUri = Uri.parse(_lmStudioBaseUrl);
    return '${baseUri.scheme}://${baseUri.host}:${baseUri.port}/api/v1/models';
  }

  // Fetches the list of available models.
  Future<List<OllamaModelInfo>> fetchAvailableModels() async {
    if (_activeProvider == LlmProvider.openai) {
      return [
        OllamaModelInfo(name: 'gpt-3.5-turbo', size: '-', details: 'OpenAI'),
        OllamaModelInfo(name: 'gpt-4', size: '-', details: 'OpenAI'),
        OllamaModelInfo(name: 'gpt-4o', size: '-', details: 'OpenAI'),
        OllamaModelInfo(name: 'gpt-4o-mini', size: '-', details: 'OpenAI'),
      ];
    }

    if (_activeProvider == LlmProvider.lmstudio) {
      try {
        final client = HttpClient();
        client.connectionTimeout = const Duration(seconds: 3);

        final modelsUrl = _getLmStudioModelsUrl();
        final request = await client.getUrl(Uri.parse(modelsUrl));
        if (_apiKey != null && _apiKey!.isNotEmpty) {
          request.headers.set('Authorization', 'Bearer $_apiKey');
        }
        final response = await request.close();

        if (response.statusCode != 200) {
          throw Exception("LM Studio API error: ${response.statusCode}");
        }

        final jsonString = await response.transform(utf8.decoder).join();
        final data = jsonDecode(jsonString);

        List<OllamaModelInfo> models = [];
        // LM Studio native API format: { "models": [ { "key": "...", "display_name": "...", "type": "llm"|"embedding", ... } ] }
        if (data is Map && data['models'] is List) {
          for (var m in data['models']) {
            // Only include LLM models, skip embedding models
            if (m['type'] != 'llm') continue;

            final String modelKey = m['key'] ?? '';
            if (modelKey.isEmpty) continue;

            final String displayName = m['display_name'] ?? modelKey;
            final int sizeBytes = m['size_bytes'] ?? 0;
            final String? paramsString = m['params_string'];

            String sizeInfo = '-';
            if (paramsString != null && paramsString.isNotEmpty) {
              sizeInfo = paramsString;
              if (sizeBytes > 0) {
                final sizeGb = (sizeBytes / (1024 * 1024 * 1024)).toStringAsFixed(1);
                sizeInfo = '$paramsString · ${sizeGb} GB';
              }
            } else if (sizeBytes > 0) {
              sizeInfo = '${(sizeBytes / (1024 * 1024 * 1024)).toStringAsFixed(1)} GB';
            }

            models.add(OllamaModelInfo(
              name: modelKey,
              size: sizeInfo,
              details: displayName,
            ));
          }
        }
        return models;
      } catch (e) {
        throw Exception(
            "Unable to connect to LM Studio. Make sure the server is running at $_lmStudioBaseUrl");
      }
    }

    if (_activeProvider == LlmProvider.google) {
      if (_apiKey == null || _apiKey!.isEmpty) {
        throw Exception("Google API Key is missing.");
      }

      try {
        final client = HttpClient();
        final request = await client.getUrl(
          Uri.parse(
              'https://generativelanguage.googleapis.com/v1beta/models?key=$_apiKey'),
        );
        final response = await request.close();

        if (response.statusCode != 200) {
          throw Exception("Google API error: ${response.statusCode}");
        }

        final jsonString = await response.transform(utf8.decoder).join();
        final data = jsonDecode(jsonString);

        List<OllamaModelInfo> models = [];
        if (data['models'] != null) {
          for (var m in data['models']) {
            // Use 'name' field for API (e.g., "models/gemini-1.5-pro")
            // Use 'displayName' for UI display (e.g., "Gemini 1.5 Pro")
            final String modelName = m['name'] ?? '';
            final String displayName = m['displayName'] ?? modelName;

            final supportedMethods = m['supportedGenerationMethods'] as List?;
            if (supportedMethods != null &&
                supportedMethods.contains('generateContent')) {
              models.add(OllamaModelInfo(
                name: modelName,
                size: '-',
                details: displayName,
              ));
            }
          }
        }

        return models;
      } catch (e) {
        return [
          OllamaModelInfo(
              name: 'models/gemini-2.5-pro',
              size: '-',
              details: 'Gemini 2.5 Pro'),
          OllamaModelInfo(
              name: 'models/gemini-2.5-flash',
              size: '-',
              details: 'Gemini 2.5 Flash'),
        ];
      }
    }

    try {
      final client = HttpClient();
      client.connectionTimeout = const Duration(seconds: 2);

      final request =
          await client.getUrl(Uri.parse('$_ollamaBaseUrl/api/tags'));
      final response = await request.close();

      if (response.statusCode != 200) {
        throw Exception("Ollama replied with error: ${response.statusCode}");
      }

      final jsonString = await response.transform(utf8.decoder).join();
      final data = jsonDecode(jsonString);

      if (data['models'] == null) return [];

      List<OllamaModelInfo> models = [];
      for (var m in data['models']) {
        final int sizeBytes = m['size'] ?? 0;
        final String sizeGb =
            "${(sizeBytes / (1024 * 1024 * 1024)).toStringAsFixed(1)} GB";

        models.add(OllamaModelInfo(
          name: m['name'],
          size: sizeGb,
          details: m['details']?['family'] ?? 'Unknown',
        ));
      }
      return models;
    } catch (e) {
      throw Exception(
          "Unable to connect to Ollama. Make sure the app is running.");
    }
  }

  // Internal method to configure the LangChain instance.
  BaseChatModel _getChatModel() {
    if (_selectedModelName == null || _selectedModelName!.isEmpty) {
      throw Exception("No AI model selected. Please select one in Settings.");
    }

    switch (_activeProvider) {
      case LlmProvider.openai:
        if (_apiKey == null || _apiKey!.isEmpty) {
          throw Exception(
              "OpenAI API Key is missing. Please set it in Settings.");
        }
        return ChatOpenAI(
          apiKey: _apiKey!,
          defaultOptions: ChatOpenAIOptions(
            model: _selectedModelName!,
            temperature: 0.7,
          ),
        );

      case LlmProvider.google:
        if (_apiKey == null || _apiKey!.isEmpty) {
          throw Exception(
              "Google API Key is missing. Please set it in Settings.");
        }
        // Remove "models/" prefix if present (Google API returns "models/gemini-1.5-pro")
        // Also handle old format (display names like "Gemini 1.5 Pro")
        String modelName = _selectedModelName!;
        if (modelName.startsWith('models/')) {
          modelName = modelName.substring(7); // Remove "models/" prefix
        } else if (!modelName.contains('-')) {
          // Old format detected (e.g., "Gemini 1.5 Pro"), use default
          modelName = 'gemini-2.5-flash';
          debugPrint('⚠️ Old model format detected, using default: $modelName');
        }
        return ChatGoogleGenerativeAI(
          apiKey: _apiKey!,
          defaultOptions: ChatGoogleGenerativeAIOptions(
            model: modelName,
            temperature: 0.7,
          ),
        );

      case LlmProvider.ollama:
        return ChatOllama(
          baseUrl: '$_ollamaBaseUrl/api',
          defaultOptions: ChatOllamaOptions(
            model: _selectedModelName!,
            temperature: 0.7,
            numCtx: 4096,
          ),
        );

      case LlmProvider.lmstudio:
        return ChatOpenAI(
          apiKey: (_apiKey != null && _apiKey!.isNotEmpty) ? _apiKey! : 'lm-studio',
          baseUrl: _lmStudioBaseUrl,
          defaultOptions: ChatOpenAIOptions(
            model: _selectedModelName!,
            temperature: 0.7,
          ),
        );
    }
  }

  // Streams the chat response from the LLM.
  // Requests are queued and processed sequentially to avoid conflicts.
  Future<Stream<String>> streamChat(List<LlmMsg> messages,
      {int maxTokens = 2048}) async {
    final completer = Completer<Stream<String>>();

    // Add request to queue.
    _requestQueue.add(_QueuedRequest(
      messages: messages,
      maxTokens: maxTokens,
      completer: completer,
    ));

    // Process queue if not already processing.
    _processQueue();

    return completer.future;
  }

  // Processes the request queue sequentially.
  Future<void> _processQueue() async {
    if (_isProcessing || _requestQueue.isEmpty) return;

    _isProcessing = true;

    while (_requestQueue.isNotEmpty) {
      final request = _requestQueue.removeFirst();
      final streamDone = Completer<void>();

      try {
        final stream = await _executeStreamChat(
            request.messages, request.maxTokens, streamDone);
        request.completer.complete(stream);
      } catch (e) {
        request.completer.completeError(e);
        if (!streamDone.isCompleted) streamDone.complete();
      }

      // Wait for the current stream to complete before processing next request.
      try {
        await streamDone.future;
      } catch (_) {
        // Ignore errors
      }
    }

    _isProcessing = false;
  }

  // Internal method that executes a single chat request.
  Future<Stream<String>> _executeStreamChat(List<LlmMsg> messages,
      int maxTokens, Completer<void> doneCompleter) async {
    late StreamController<String> controller;

    controller = StreamController<String>(
      onCancel: () {
        if (!doneCompleter.isCompleted) doneCompleter.complete();
      },
    );

    try {
      final chatModel = _getChatModel();
      final List<ChatMessage> langchainMessages = [];
      String? pendingSystemInstruction;

      for (var m in messages) {
        if (m.role == 'system') {
          pendingSystemInstruction = m.content;
        } else if (m.role == 'user') {
          if (pendingSystemInstruction != null) {
            final combinedContent = """
### INSTRUCTIONS:
$pendingSystemInstruction

### CONTEXT/INPUT:
${m.content}

### REQURESTED ANSWER:
""";
            langchainMessages.add(ChatMessage.humanText(combinedContent));
            pendingSystemInstruction = null;
          } else {
            langchainMessages.add(ChatMessage.humanText(m.content));
          }
        } else if (m.role == 'assistant') {
          langchainMessages.add(ChatMessage.ai(m.content));
        }
      }

      if (pendingSystemInstruction != null) {
        langchainMessages.add(ChatMessage.humanText(pendingSystemInstruction));
      }

      final stream = chatModel.stream(PromptValue.chat(langchainMessages));

      stream.listen(
        (ChatResult res) {
          final chunk = res.output.content;
          controller.add(chunk);
        },
        onDone: () {
          if (!controller.isClosed) controller.close();
          if (!doneCompleter.isCompleted) doneCompleter.complete();
        },
        onError: (e) {
          if (!controller.isClosed) controller.addError(e);
          if (!doneCompleter.isCompleted) doneCompleter.complete();
        },
      );
    } catch (e) {
      if (!controller.isClosed) {
        controller.addError(e);
        controller.close();
      }
      if (!doneCompleter.isCompleted) doneCompleter.complete();
    }

    return controller.stream;
  }

  // Generates a summary for the given video content.
  Future<Stream<String>> generateSummary({
    required String subtitleText,
    required String videoTitle,
    String videoDescription = '',
    String targetLanguageName = 'English',
    int maxCharacters = 15000,
  }) async {
    String safeSubtitle = subtitleText;
    if (safeSubtitle.length > maxCharacters) {
      safeSubtitle =
          "${safeSubtitle.substring(0, maxCharacters)}\n[...TRUNCATED...]";
    }

    final contextBase = '''
CONTEXT SECTION

Video Title: 
"""
$videoTitle
"""
Video Description: 
"""
$videoDescription
"""
Video Transcript:
"""
$safeSubtitle
"""
''';

    String taskDescription = targetLanguageName == 'Italian'
        ? "Genera un riassunto RIASSUNTO del video basandoti sul contesto, evidenziando i punti chiave."
        : "Generate a SUMMARY of the video based on the context, highlighting key points.";

    final prompt = """
TASK:
Analyze the transcript provided in the context and answer the user's request.

USER REQUEST:
"$taskDescription"

RESPONSE INSTRUCTIONS:
1. Answer exclusively in language: $targetLanguageName.
2. Do not repeat instructions. Go straight to the point.
3. Do not start with any introductory phrases or title. Write only the summary.
4. Do not use Markdown formatting, tables, or bullet points. The text should be plain and easy to read.

RESPONSE:
""";

    final messages = [
      LlmMsg(role: 'system', content: contextBase),
      LlmMsg(role: 'user', content: prompt),
    ];

    return streamChat(messages, maxTokens: 2048);
  }
}
