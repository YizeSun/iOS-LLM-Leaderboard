import Foundation
import CryptoKit
import HuggingFace
import MLXLLM
import MLXLMCommon
import Tokenizers

actor ModelProcessIsolationGate {
    enum GateError: LocalizedError, Equatable {
        case differentModelAlreadyClaimed(
            claimedIdentity: String,
            requestedIdentity: String
        )

        var errorDescription: String? {
            switch self {
            case .differentModelAlreadyClaimed:
                "This App process has already prepared or attempted a different model. Fully close and relaunch before measuring another model."
            }
        }
    }

    static let shared = ModelProcessIsolationGate()

    private var claimedIdentity: String?

    func claim(_ requestedIdentity: String) throws {
        if let claimedIdentity, claimedIdentity != requestedIdentity {
            throw GateError.differentModelAlreadyClaimed(
                claimedIdentity: claimedIdentity,
                requestedIdentity: requestedIdentity
            )
        }
        claimedIdentity = requestedIdentity
    }
}

actor MLXSwiftRuntime: ModelPreparingRuntime {
    enum RuntimeError: LocalizedError {
        case modelNotLoaded
        case missingCompletionInfo
        case identityMismatch(String)
        case cacheVerificationFailed
        case exactInputLengthUnavailable(Int)

        var errorDescription: String? {
            switch self {
            case .modelNotLoaded:
                "The pinned MLX model has not been loaded."
            case .missingCompletionInfo:
                "MLX generation ended without completion information."
            case .identityMismatch(let message):
                "Runtime identity mismatch: \(message)"
            case .cacheVerificationFailed:
                "The downloaded model cache could not be verified as complete."
            case .exactInputLengthUnavailable(let target):
                "The fixture generator could not produce exactly \(target) post-template tokens."
            }
        }
    }

    func calibrateInputLengthFixtures(
        targets: [Int]
    ) async throws -> [InputLengthFixtureCalibration] {
        guard let modelContainer else { throw RuntimeError.modelNotLoaded }
        func prompt(repetitions: Int) -> String {
            InputLengthFixtureGenerator.prompt(paddingRepetitions: repetitions)
        }

        func tokenCount(repetitions: Int) async throws -> Int {
            let value = prompt(repetitions: repetitions)
            return try await modelContainer.perform { context in
                let input = try await context.processor.prepare(
                    input: UserInput(
                        prompt: value,
                        additionalContext: ["enable_thinking": false]
                    )
                )
                return input.text.tokens.size
            }
        }

        var results: [InputLengthFixtureCalibration] = []
        for target in targets {
            var low = 0
            var high = max(target * 2, 64)
            while try await tokenCount(repetitions: high) < target {
                high *= 2
            }
            while low <= high {
                let middle = (low + high) / 2
                let actual = try await tokenCount(repetitions: middle)
                if actual == target {
                    let value = prompt(repetitions: middle)
                    let digest = SHA256.hash(data: Data(value.utf8)).map {
                        String(format: "%02x", $0)
                    }.joined()
                    results.append(
                        InputLengthFixtureCalibration(
                            targetTokenCount: target,
                            actualTokenCount: actual,
                            paddingRepetitions: middle,
                            promptSHA256: digest
                        )
                    )
                    break
                } else if actual < target {
                    low = middle + 1
                } else {
                    high = middle - 1
                }
            }
            guard results.last?.targetTokenCount == target else {
                throw RuntimeError.exactInputLengthUnavailable(target)
            }
        }
        return results
    }

    func calibrateContextAssistanceFixtures(
        document: String,
        question: String,
        targets: [Int]
    ) async throws -> [InputLengthFixtureCalibration] {
        guard let modelContainer else { throw RuntimeError.modelNotLoaded }
        func prompt(_ repetitions: Int) -> String {
            ContextAssistanceFixtureGenerator.prompt(
                document: document,
                question: question,
                paddingRepetitions: repetitions
            )
        }
        func count(_ repetitions: Int) async throws -> Int {
            let value = prompt(repetitions)
            return try await modelContainer.perform { context in
                let input = try await context.processor.prepare(
                    input: UserInput(
                        prompt: value,
                        additionalContext: ["enable_thinking": false]
                    )
                )
                return input.text.tokens.size
            }
        }
        var results: [InputLengthFixtureCalibration] = []
        for target in targets {
            var low = 0
            var high = target * 2
            while low <= high {
                let middle = (low + high) / 2
                let actual = try await count(middle)
                if actual == target {
                    let value = prompt(middle)
                    let digest = SHA256.hash(data: Data(value.utf8)).map {
                        String(format: "%02x", $0)
                    }.joined()
                    results.append(.init(
                        targetTokenCount: target,
                        actualTokenCount: actual,
                        paddingRepetitions: middle,
                        promptSHA256: digest
                    ))
                    break
                } else if actual < target {
                    low = middle + 1
                } else {
                    high = middle - 1
                }
            }
            guard results.last?.targetTokenCount == target else {
                throw RuntimeError.exactInputLengthUnavailable(target)
            }
        }
        return results
    }

    nonisolated let identity =
        "MLX Swift LM 3.31.4 · Power 1.1 RC1 profiles"

    private static let cacheVerificationMethod =
        "huggingface_revision_manifest_cached_file_size_v1"
    private static let requiredFileSuffixes = [".safetensors", ".json", ".jinja"]

    private var modelContainer: ModelContainer?
    private var loadedModelIdentity: String?
    private var preparedPlan: PilotPlan?
    private let processIsolationGate: ModelProcessIsolationGate

    init(
        processIsolationGate: ModelProcessIsolationGate = .shared
    ) {
        self.processIsolationGate = processIsolationGate
    }

    func prepare(plan: PilotPlan) async -> ModelPreparationEvidence {
        let startedAt = ContinuousClock.now
        let preparedAt = Date()
        let model = plan.modelProfile
        var cacheState: ModelPreparationEvidence.CacheState = .unknown
        var downloadOccurred = false
        var preparationCompleted = false
        var modelLoadCompleted = false
        var reasons: [String] = []

        do {
            try Self.validateIdentity(plan)
            let inspector = HuggingFaceCacheInspector()
            let inspection = await inspector.inspect(
                artifactID: model.artifactId,
                revision: model.artifactRevision,
                requiredFileSuffixes: Self.requiredFileSuffixes
            )
            cacheState = inspection.state

            switch inspection.state {
            case .unknown:
                reasons = ["model_cache_state_unknown"]
            case .cached:
                try await load(
                    plan: plan,
                    localFilesOnly: true
                )
                preparationCompleted = true
                modelLoadCompleted = true
                preparedPlan = plan
            case .notCached, .incomplete:
                reasons.append(
                    inspection.state == .notCached
                        ? "model_artifact_not_cached"
                        : "model_artifact_incomplete"
                )
                try await inspector.download(
                    artifactID: model.artifactId,
                    revision: model.artifactRevision,
                    requiredFileSuffixes: Self.requiredFileSuffixes
                )
                downloadOccurred = true
                let afterDownload = await inspector.inspect(
                    artifactID: model.artifactId,
                    revision: model.artifactRevision,
                    requiredFileSuffixes: Self.requiredFileSuffixes
                )
                guard afterDownload.state == .cached else {
                    reasons.append(
                        afterDownload.state == .unknown
                            ? "model_cache_state_unknown"
                            : "model_artifact_incomplete"
                    )
                    throw RuntimeError.cacheVerificationFailed
                }
                try await load(
                    plan: plan,
                    localFilesOnly: true
                )
                preparationCompleted = true
                modelLoadCompleted = true
                preparedPlan = plan
                reasons.append("model_download_during_session")
                reasons.append("restart_required_after_download")
            }
        } catch is ModelProcessIsolationGate.GateError {
            reasons.append("different_model_claimed_in_process")
            reasons.append("restart_required_after_model_switch")
            reasons.append("model_preparation_failed")
        } catch let error as RuntimeError {
            if case .identityMismatch = error {
                reasons.append("runtime_identity_mismatch")
            } else if case .cacheVerificationFailed = error {
                // The specific cache-state reason was recorded above.
            } else {
                reasons.append("model_load_failed")
            }
            reasons.append("model_preparation_failed")
        } catch {
            if !downloadOccurred {
                reasons.append("model_load_failed")
            }
            reasons.append("model_preparation_failed")
        }

        let eligible = cacheState == .cached
            && !downloadOccurred
            && preparationCompleted
            && modelLoadCompleted
            && reasons.isEmpty
        return ModelPreparationEvidence(
            artifactID: model.artifactId,
            artifactRevision: model.artifactRevision,
            cacheStateBeforePreparation: cacheState,
            downloadOccurredDuringSession: downloadOccurred,
            preparationDurationMilliseconds: Double(
                startedAt.duration(to: .now).nanoseconds
            ) / 1_000_000,
            preparationCompleted: preparationCompleted,
            modelLoadCompleted: modelLoadCompleted,
            eligibleForPerformanceMeasurement: eligible,
            reasonCodes: Array(Set(reasons)).sorted(),
            cacheVerificationMethod: Self.cacheVerificationMethod,
            preparedAt: preparedAt
        )
    }

    private func load(plan: PilotPlan, localFilesOnly: Bool) async throws {
        let requestedIdentity =
            "\(plan.modelProfile.artifactId)@\(plan.modelProfile.artifactRevision)"
        if modelContainer != nil, loadedModelIdentity == requestedIdentity {
            return
        }
        try await processIsolationGate.claim(requestedIdentity)
        modelContainer = nil
        loadedModelIdentity = nil
        preparedPlan = nil
        let profile = ProductionModelProfile.matching(plan.modelProfile)
        let configuration = ModelConfiguration(
            id: plan.modelProfile.artifactId,
            revision: plan.modelProfile.artifactRevision,
            extraEOSTokens: profile?.extraEOSTokens ?? []
        )
        let loaded = try await loadModelContainer(
            from: HuggingFaceDownloader(localFilesOnly: localFilesOnly),
            using: HuggingFaceTokenizerLoader(),
            configuration: configuration,
            useLatest: false
        )
        modelContainer = loaded
        loadedModelIdentity = requestedIdentity
    }

    static func validateIdentity(_ plan: PilotPlan) throws {
        let model = plan.modelProfile
        let runtime = plan.runtimeProfile
        guard ProductionModelProfile.matching(model) != nil else {
            throw RuntimeError.identityMismatch("model artifact or revision")
        }
        guard runtime.runtimeName == "MLX Swift LM",
              runtime.packageVersion == "3.31.4",
              runtime.packageRevision == "bd4b7434e6bdb588c7ef55706ff8904cb7fd4c57",
              runtime.mlxSwiftVersion == "0.31.6",
              runtime.mlxSwiftRevision == "0bb916c67f4b9e5c682cbe02a42c701c93ab5021" else {
            throw RuntimeError.identityMismatch("MLX dependency identity")
        }
    }

    func generate(
        prompt: String,
        outputTokenLimit: Int,
        onToken: @Sendable (RuntimeToken) async -> Void
    ) async throws -> RuntimeGenerationResult {
        guard let modelContainer, let preparedPlan else {
            throw RuntimeError.modelNotLoaded
        }

        let clock = ContinuousClock()
        let requestStart = clock.now
        let parameters = GenerateParameters(
            maxTokens: outputTokenLimit,
            temperature: Float(preparedPlan.generation.temperature),
            topP: Float(preparedPlan.generation.topP ?? 1),
            topK: preparedPlan.generation.topK ?? 0,
            repetitionPenalty: preparedPlan.generation.repetitionPenalty.map(Float.init),
            seed: preparedPlan.generation.seed
        )

        let (stream, task, generationStart) = try await modelContainer.perform { context in
            let input = try await context.processor.prepare(
                input: UserInput(
                    prompt: prompt,
                    additionalContext: preparedPlan.generation.thinkingMode
                        == "disabled-via-chat-template"
                        ? ["enable_thinking": false]
                        : nil
                )
            )
            let generationStart = clock.now
            let (stream, task) = try generateTokensTask(
                input: input,
                parameters: parameters,
                context: context,
                includeStopToken: preparedPlan.generation.includeStopTokenInRawEvents
            )
            return (stream, task, generationStart)
        }

        var tokenIndex = 0
        var tokenIDs: [Int] = []
        var renderabilityRecorder = preparedPlan.measurementMode
            .userVisibleTtftAvailable
            ? FirstRenderableTraceRecorder(
                generationStartNanoseconds: requestStart.duration(to: generationStart)
                    .nanoseconds
            )
            : nil
        var completionInfo: GenerateCompletionInfo?
        let tokenizer = await modelContainer.tokenizer

        for await event in stream {
            switch event {
            case .token(let tokenID):
                let tokenReceived = clock.now
                let elapsed = generationStart.duration(to: tokenReceived)
                let requestElapsed = requestStart.duration(to: tokenReceived)
                tokenIDs.append(tokenID)
                if renderabilityRecorder?.shouldDecodeNextToken == true {
                    let decoded = tokenizer.decode(
                        tokenIds: tokenIDs,
                        skipSpecialTokens: true
                    )
                    renderabilityRecorder?.record(
                        tokenIndex: tokenIndex,
                        tokenID: tokenID,
                        tokenReceivedNanoseconds: requestElapsed.nanoseconds,
                        decodedAtNanoseconds: requestStart.duration(to: clock.now)
                            .nanoseconds,
                        decodedPrefix: decoded
                    )
                }
                await onToken(
                    RuntimeToken(
                        index: tokenIndex,
                        tokenID: tokenID,
                        elapsedNanoseconds: elapsed.nanoseconds
                    )
                )
                tokenIndex += 1
            case .info(let info):
                completionInfo = info
            }
        }

        await task.value
        guard let completionInfo else {
            throw RuntimeError.missingCompletionInfo
        }
        let renderabilityTrace = renderabilityRecorder?.finalize(
            outputTokenCount: tokenIDs.count
        )

        return RuntimeGenerationResult(
            promptTokenCount: completionInfo.promptTokenCount,
            outputTokenCount: completionInfo.generationTokenCount,
            stopReason: completionInfo.stopReason.runtimeStopReason,
            promptTimeSeconds: completionInfo.promptTime,
            generateTimeSeconds: completionInfo.generateTime,
            generationStartNanoseconds: requestStart.duration(to: generationStart)
                .nanoseconds,
            promptEvaluationNanoseconds: Self.nanoseconds(
                completionInfo.promptTime
            ),
            userVisibleTTFTNanoseconds: preparedPlan.measurementMode
                .userVisibleTtftAvailable
                ? renderabilityTrace?.firstRenderableDecodedAtNanoseconds
                : nil,
            requestCompletionNanoseconds: preparedPlan.measurementMode
                .userVisibleTtftAvailable
                ? requestStart.duration(to: clock.now).nanoseconds
                : nil,
            generatedText: preparedPlan.measurementMode.userVisibleTtftAvailable
                ? tokenizer.decode(tokenIds: tokenIDs, skipSpecialTokens: true)
                : nil,
            renderabilityTrace: renderabilityTrace
        )
    }

    private static func nanoseconds(_ seconds: Double) -> UInt64? {
        guard seconds.isFinite, seconds > 0 else { return nil }
        let value = seconds * 1_000_000_000
        guard value <= Double(UInt64.max) else { return nil }
        return UInt64(value.rounded())
    }
}

private struct HuggingFaceDownloader: Downloader {
    enum DownloadError: LocalizedError {
        case invalidRepositoryID(String)

        var errorDescription: String? {
            switch self {
            case .invalidRepositoryID(let id):
                "Invalid Hugging Face repository ID: \(id)"
            }
        }
    }

    private let client = HuggingFace.HubClient()
    let localFilesOnly: Bool

    func download(
        id: String,
        revision: String?,
        matching patterns: [String],
        useLatest: Bool,
        progressHandler: @Sendable @escaping (Progress) -> Void
    ) async throws -> URL {
        guard let repository = HuggingFace.Repo.ID(rawValue: id) else {
            throw DownloadError.invalidRepositoryID(id)
        }
        return try await client.downloadSnapshot(
            of: repository,
            revision: revision ?? "main",
            matching: patterns,
            localFilesOnly: localFilesOnly
        ) { @MainActor progress in
            progressHandler(progress)
        }
    }
}

private struct HuggingFaceCacheInspector: Sendable {
    struct Inspection: Sendable {
        let state: ModelPreparationEvidence.CacheState
    }

    private let client = HuggingFace.HubClient()

    func inspect(
        artifactID: String,
        revision: String,
        requiredFileSuffixes: [String]
    ) async -> Inspection {
        guard let repository = HuggingFace.Repo.ID(rawValue: artifactID),
              let cache = client.cache else {
            return Inspection(state: .unknown)
        }
        do {
            let entries = try await client.listFiles(
                in: repository,
                revision: revision,
                recursive: true
            ).filter { entry in
                requiredFileSuffixes.contains { entry.path.hasSuffix($0) }
            }
            let expectedFiles = Dictionary(
                uniqueKeysWithValues: entries.map { ($0.path, $0.size) }
            )
            var cachedFileSizes: [String: Int] = [:]
            for entry in entries {
                guard let url = cache.cachedFilePath(
                    repo: repository,
                    kind: .model,
                    revision: revision,
                    filename: entry.path
                ) else { continue }
                let resolved = url.resolvingSymlinksInPath()
                let actualSize = try resolved.resourceValues(
                    forKeys: [.fileSizeKey]
                ).fileSize
                if let actualSize {
                    cachedFileSizes[entry.path] = actualSize
                }
            }
            return Inspection(
                state: ModelCacheVerification.classify(
                    expectedFiles: expectedFiles,
                    cachedFileSizes: cachedFileSizes
                )
            )
        } catch {
            return Inspection(state: .unknown)
        }
    }

    func download(
        artifactID: String,
        revision: String,
        requiredFileSuffixes: [String]
    ) async throws {
        guard let repository = HuggingFace.Repo.ID(rawValue: artifactID) else {
            throw HuggingFaceDownloader.DownloadError.invalidRepositoryID(artifactID)
        }
        let patterns = requiredFileSuffixes.map { "*\($0)" }
        _ = try await client.downloadSnapshot(
            of: repository,
            revision: revision,
            matching: patterns
        )
    }
}

private struct HuggingFaceTokenizerLoader: TokenizerLoader {
    func load(from directory: URL) async throws -> any MLXLMCommon.Tokenizer {
        let tokenizer = try await Tokenizers.AutoTokenizer.from(modelFolder: directory)
        return HuggingFaceTokenizer(tokenizer)
    }
}

private struct HuggingFaceTokenizer: MLXLMCommon.Tokenizer {
    private let upstream: any Tokenizers.Tokenizer

    init(_ upstream: any Tokenizers.Tokenizer) {
        self.upstream = upstream
    }

    func encode(text: String, addSpecialTokens: Bool) -> [Int] {
        upstream.encode(text: text, addSpecialTokens: addSpecialTokens)
    }

    func decode(tokenIds: [Int], skipSpecialTokens: Bool) -> String {
        upstream.decode(tokens: tokenIds, skipSpecialTokens: skipSpecialTokens)
    }

    func convertTokenToId(_ token: String) -> Int? {
        upstream.convertTokenToId(token)
    }

    func convertIdToToken(_ id: Int) -> String? {
        upstream.convertIdToToken(id)
    }

    var bosToken: String? { upstream.bosToken }
    var eosToken: String? { upstream.eosToken }
    var unknownToken: String? { upstream.unknownToken }

    func applyChatTemplate(
        messages: [[String: any Sendable]],
        tools: [[String: any Sendable]]?,
        additionalContext: [String: any Sendable]?
    ) throws -> [Int] {
        do {
            return try upstream.applyChatTemplate(
                messages: messages,
                tools: tools,
                additionalContext: additionalContext
            )
        } catch Tokenizers.TokenizerError.missingChatTemplate {
            throw MLXLMCommon.TokenizerError.missingChatTemplate
        }
    }
}

private extension GenerateStopReason {
    var runtimeStopReason: RuntimeGenerationResult.StopReason {
        switch self {
        case .stop: .endOfSequence
        case .length: .outputTokenLimit
        case .cancelled: .cancelled
        }
    }
}

private extension Duration {
    var nanoseconds: UInt64 {
        let parts = components
        let seconds = UInt64(max(0, parts.seconds))
        let attoseconds = UInt64(max(0, parts.attoseconds))
        return seconds * 1_000_000_000 + attoseconds / 1_000_000_000
    }
}
