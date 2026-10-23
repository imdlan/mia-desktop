import Foundation

enum ChatRole: String, Codable {
    case user
    case assistant
    /// UI-only row for explicit errors/warnings — never sent to the API.
    case error
    /// UI-only row documenting tool use ("Searching: …") — never sent to the API.
    case activity
}

struct ChatMessage: Identifiable, Equatable, Codable {
    var id = UUID()
    let role: ChatRole
    var text: String
    /// What actually goes over the wire when it differs from the display text
    /// (slash-command expansion). Nil means `text` is the wire text.
    var wireText: String?
    var attachments: [Attachment] = []
    /// The model's thinking for an assistant turn, when the provider streams it.
    /// Persisted with the message (so reopening a chat keeps it) but never sent
    /// back: chat-completions history carries the answer only, and echoing a
    /// summary as if the model had said it would corrupt the next turn.
    /// Optional so conversations written before this existed still decode.
    var reasoning: String?
    /// Wall-clock of when the message was SENT (user) or the turn's task
    /// began (assistant). Optional — old transcripts decode as nil, and the
    /// UI only renders the user bubble's stamp anyway.
    var createdAt: Date?
    /// Measured cost of the turn that produced this reply, shown right-aligned
    /// in the assistant footer. Optional both because it didn't always exist
    /// (old transcripts decode fine) and because a provider that never reports
    /// usage leaves the token counts nil — duration alone still shows.
    var stats: TurnStats?
}

/// API-reported token usage for one turn. `total` includes the prompt (the
/// cost-facing number); `output` drives tok/s. Additive across the rounds of
/// a tool loop.
struct TurnUsage: Equatable {
    var total: Int
    var output: Int

    static func + (lhs: TurnUsage, rhs: TurnUsage) -> TurnUsage {
        TurnUsage(total: lhs.total + rhs.total, output: lhs.output + rhs.output)
    }
}

/// Persisted alongside its reply: "62518 tokens · 5m 42s · 51.6 tok/s".
/// `totalTokens`/`outputTokens` are nil when the provider didn't report usage
/// (duration alone still renders); `duration` is the NETWORK turn wall-clock —
/// request dispatch to final byte, tool rounds included, typewriter excluded.
struct TurnStats: Codable, Equatable {
    var totalTokens: Int?
    var outputTokens: Int?
    var duration: TimeInterval

    /// The footer line. Total tokens include the prompt (the cost-facing
    /// number); the rate divides OUTPUT tokens by the network duration, so a
    /// tool-heavy turn dilutes it — that is the stated simplicity, not a bug.
    var displayLine: String {
        var parts: [String] = []
        if let total = totalTokens, total > 0 {
            parts.append("\(total) tokens")
        }
        parts.append(Self.durationText(duration))
        if let output = outputTokens, output > 0, duration > 0.05 {
            parts.append(String(format: "%.1f tok/s", Double(output) / duration))
        }
        return parts.joined(separator: " · ")
    }

    /// "5m 42s" / "9.4s" / "850ms" — sub-second turns are real (cached or tiny
    /// replies) and "0s" would read as a bug.
    static func durationText(_ seconds: TimeInterval) -> String {
        if seconds < 1 { return String(format: "%.0fms", seconds * 1000) }
        if seconds < 10 { return String(format: "%.1fs", seconds) }
        if seconds < 60 { return String(format: "%.0fs", seconds) }
        return String(format: "%dm %ds", Int(seconds) / 60, Int(seconds) % 60)
    }
}

@MainActor
final class ChatStore: ObservableObject {
    @Published private(set) var messages: [ChatMessage] = []
    @Published private(set) var isStreaming = false
    /// Latest `.status` lifecycle note from the active turn ("Starting Codex…"),
    /// rendered inside the waiting row while the reply is still empty. Cleared
    /// the moment visible text arrives and at the end of every turn — it must
    /// never outlive the wait it describes.
    @Published private(set) var pendingStatus: String?
    /// The turn's thinking so far, while the reply is still empty — what the
    /// waiting row scrolls. Same lifecycle as `pendingStatus` (transient,
    /// empty-row-only, cleared on first text / turn end / stop); the durable
    /// copy is committed to `ChatMessage.reasoning` separately.
    @Published private(set) var pendingReasoning: String?
    @Published private(set) var recent: [ConversationMeta] = []
    private(set) var conversationID = UUID()

    /// Cross-chat search corpus, built once and reused until the stored set
    /// changes. It lives here rather than in the history popover because this is
    /// what knows when a conversation is written or deleted; rebuilding it per
    /// ⌘Y meant re-decoding every transcript — attachment base64 and all — on a
    /// keystroke-frequency user action.
    private var searchCorpus: [UUID: String]?

    /// Resolved text of every stored conversation, for the history popover's
    /// body search. Built off the main actor on first use after any change, so
    /// the popover's designed pop-in never waits on disk.
    func searchableText() async -> [UUID: String] {
        if let searchCorpus { return searchCorpus }
        let corpus = await Task.detached(priority: .userInitiated) {
            ConversationStore.fullTextIndex()
        }.value
        searchCorpus = corpus
        return corpus
    }

    /// Bumped whenever a STORED conversation replaces the current one (history
    /// pick, launch resume) — as opposed to messages arriving by chat. Drives the
    /// restore choreography of delta 3 (5d): the panel's slower growth curve and
    /// the transcript's one-group reveal. Both need to fire before `messages`
    /// changes, so `adopt` sets them first.
    @Published private(set) var restoreTick = 0
    /// Whether that restore landed in an empty panel (which is about to grow) or
    /// replaced a conversation already on screen (crossfade in place).
    private(set) var restoredIntoEmptyPanel = false

    // Fork state: `messages` always holds the full resolved transcript, but a
    // forked conversation persists only its divergent tail — the first
    // `sharedPrefixCount` messages belong to the parent chain.
    private var forkParentID: UUID?
    private var forkMessageID: UUID?
    private var sharedPrefixCount = 0

    // P3 auto-naming state. `customTitle` is the model-written (or any future
    // manually renamed) title; nil means the persisted title is still the
    // derived default, which is exactly the "still default" test the trigger
    // needs — persist() re-derives whenever this is nil, so the two can never
    // disagree. `titleAttempted` is the once-guard: set when the request is
    // DISPATCHED (not when it returns), so a failing provider never gets a
    // second, third, … try at the user's expense.
    private var customTitle: String?
    private var titleAttempted = false

    private let providerStore: ProviderStore
    private let shortcutStore: ShortcutStore
    private var streamTask: Task<Void, Never>?

    // Streaming reveal: partial snapshots land in `streamTarget`; a drain task
    // reveals them — per-character at a paced ~180 chars/s, per-sentence at
    // boundaries. The per-character pacing MUST be allowed to lag behind arrival
    // — see startDrain — or it is indistinguishable from mirroring the stream.
    // Stop flushes instantly.
    private var streamTarget = ""
    /// How much of the reply has ARRIVED, vs. how much of it the typewriter has
    /// revealed — `--smoke-input --live` compares the two to prove the composer is
    /// released mid-reveal rather than at the end of it.
    var streamTargetLength: Int { streamTarget.count }
    private var streamFinished = false
    private var streamingMessageID: UUID?
    private var drainTask: Task<Void, Never>?

    /// Delta 4: the trailing fade over text the drain has just committed, for the
    /// row currently revealing. Published so the streaming row repaints while the
    /// fade runs out even on ticks where no new characters landed — MessageRow is
    /// Equatable-gated on it, so no other row is touched.
    struct RevealState: Equatable {
        var messageID: UUID
        var fade: TextReveal
    }
    @Published private(set) var reveal: RevealState?

    /// Set when a send that carried image/file parts failed WITHOUT a structural
    /// attribution: the matching error row offers "don't send X to this model
    /// again" so manual exceptions are added where the problem appeared, not in
    /// Settings. Session-only — it names a specific rendered row.
    struct CapabilityFailureContext: Equatable {
        var errorMessageID: UUID
        var providerID: UUID
        var model: String
        var sentImages: Bool
        var sentFiles: Bool
    }
    @Published private(set) var capabilityFailure: CapabilityFailureContext?

    /// The error-row action: records the user's own diagnosis as a manual
    /// exception for the provider+model that just failed.
    func recordManualCapabilityException(_ capability: ContentCapability) {
        guard let context = capabilityFailure else { return }
        providerStore.recordCapabilityException(
            capability, supported: false, source: .manual,
            providerID: context.providerID, model: context.model
        )
        capabilityFailure = nil
    }

    init(providerStore: ProviderStore, shortcutStore: ShortcutStore) {
        self.providerStore = providerStore
        self.shortcutStore = shortcutStore
        // Resume the most recent conversation across app restarts. Only that
        // ONE file decodes synchronously (mtime-sorted first candidate); the
        // full recent list walks every transcript — attachment base64 and all —
        // and used to stall launch on attachment-heavy stores, so it is built
        // off the main actor and merged in when ready.
        if let newest = ConversationStore.newestConversationID(),
           let loaded = ConversationStore.loadResolved(id: newest) {
            adopt(loaded)
        }
        // Detached: the scan decodes every transcript (attachment base64 and
        // all) and must stay off the main actor. mergeRecent is MainActor-
        // isolated, so the hop back is explicit in the await.
        Task.detached(priority: .userInitiated) { [weak self] in
            let metas = ConversationStore.listRecent()
            await self?.mergeRecent(metas)
        }
    }

    /// Backfills `recent` from the off-thread scan without clobbering live
    /// updates: persist() has been keeping the list current since launch, so
    /// only entries it cannot yet know about are added, then the usual
    /// newest-first ordering and cap are restored.
    private func mergeRecent(_ metas: [ConversationMeta]) {
        let known = Set(recent.map(\.id))
        for meta in metas where !known.contains(meta.id) {
            recent.append(meta)
        }
        recent.sort { $0.updatedAt > $1.updatedAt }
        recent = Array(recent.prefix(ConversationStore.maxStored))
    }

    private func adopt(_ loaded: (conversation: Conversation, messages: [ChatMessage], missingParent: Bool)) {
        // Announced BEFORE `messages` changes: @Published sends in willSet, so
        // everything observing the message list already sees the restore flags
        // when it reacts (PanelController's growth curve, ChatView's reveal).
        restoredIntoEmptyPanel = messages.isEmpty
        restoreTick += 1
        conversationID = loaded.conversation.id
        messages = loaded.messages
        if loaded.missingParent {
            // Broken chain: continue as a standalone conversation, and say so.
            forkParentID = nil
            forkMessageID = nil
            sharedPrefixCount = 0
            let notice = "This fork's parent conversation is missing — showing only the messages added after the fork."
            if !messages.contains(where: { $0.role == .error && $0.text == notice }) {
                messages.append(ChatMessage(role: .error, text: notice))
            }
        } else {
            forkParentID = loaded.conversation.parentID
            forkMessageID = loaded.conversation.forkMessageID
            sharedPrefixCount = loaded.messages.count - loaded.conversation.messages.count
        }
        // `autoTitled` on disk is what distinguishes a model-written title
        // from the derived default across restarts; without it the reload
        // would re-derive and a named chat would silently lose its name.
        customTitle = loaded.conversation.autoTitled == true ? loaded.conversation.title : nil
        titleAttempted = loaded.conversation.autoTitled == true
    }

    static var webSearchEnabled: Bool {
        get { UserDefaults.standard.object(forKey: "webSearchEnabled") as? Bool ?? true }
        set { UserDefaults.standard.set(newValue, forKey: "webSearchEnabled") }
    }

    /// Teaches the model the pasteable-block format the renderer recognizes.
    /// Editable in Settings → Commands; an explicitly empty value means "send
    /// no system prompt".
    nonisolated static let defaultSystemPrompt = """
    You are a helpful assistant in a small desktop chat panel. Be concise and direct.

    When a reply includes content the user will copy and reuse verbatim — a prompt, template, \
    code snippet, configuration, or other reusable text — wrap exactly that content in a \
    pasteable block:

    <pasteable title="Short label">
    the exact reusable content
    </pasteable>

    Pasteable rules:
    - The tags go on their own lines, with a short descriptive title.
    - Inside the tags, put only the content to copy — no commentary.
    - Keep explanations outside the block, in normal prose.
    - Use pasteable blocks only for content meant to be copied; use normal markdown code \
    fences for illustrative code.
    """

    /// The system prompt for the next send: the ACTIVE persona's prompt when
    /// one is selected (P4), otherwise the user's free-text prompt exactly as
    /// before ("Custom"). Resolution is PersonaStore's pure law so the
    /// `--smoke-persona` harness can pin the priority; a persona id whose
    /// entry was deleted resolves as Custom.
    static var systemPrompt: String {
        PersonaStore.resolvePrompt(
            activeID: UserDefaults.standard.string(forKey: "activePersonaID"),
            personas: PersonaStore.stored(),
            fallback: UserDefaults.standard.string(forKey: "systemPrompt") ?? defaultSystemPrompt
        )
    }

    @discardableResult
    func send(_ text: String, attachments: [Attachment] = []) -> Bool {
        let text = text.trimmingCharacters(in: .whitespacesAndNewlines)
        guard !text.isEmpty || !attachments.isEmpty, !isStreaming else { return false }
        // Recorded here rather than in the composer: this is where a prompt
        // becomes a SENT prompt, so ↑ also offers back anything a retry or a
        // future send path put through. Before the guards below, because a send
        // that fails is exactly one you want to recall and fix.
        PromptHistory.record(text)
        // A previous reply may still be typing itself out; complete it instantly
        // rather than letting the new turn's rows appear above a half-revealed one.
        flushTypewriter()

        // Slash-command expansion: display stays compact, the template goes on the wire.
        var wireText: String?
        if text.hasPrefix("/") {
            let body = text.dropFirst()
            let name = String(body.prefix { !$0.isWhitespace })
            let input = String(body.dropFirst(name.count)).trimmingCharacters(in: .whitespaces)
            guard let shortcut = shortcutStore.match(name: name) else {
                messages.append(ChatMessage(role: .user, text: text, createdAt: Date()))
                messages.append(ChatMessage(
                    role: .error,
                    text: "Unknown shortcut “/\(name)”. Define it in Settings → Slash Commands, or escape the leading slash."
                ))
                persist()
                return false
            }
            wireText = shortcut.expand(input: input)
        }

        messages.append(ChatMessage(role: .user, text: text, wireText: wireText, attachments: attachments, createdAt: Date()))

        // Explicit-warning policy: catch misconfiguration up front, with a pointer to
        // the fix, rather than surfacing an opaque HTTP failure.
        guard let config = providerStore.currentConfig() else {
            messages.append(ChatMessage(role: .error, text: "No provider selected — open Settings…"))
            persist()
            return false
        }
        let providerName = providerStore.selectedProvider?.name ?? "provider"
        if config.model.isEmpty {
            messages.append(ChatMessage(
                role: .error,
                text: "No model set for \(providerName). Pick one from the model menu (fetch the list first) or Settings."
            ))
            persist()
            return false
        }
        switch config.kind {
        case .chatGPT:
            if !ChatGPTAuth.isSignedIn {
                messages.append(ChatMessage(
                    role: .error,
                    text: "Not signed in to ChatGPT. Right-click the menu bar icon → Settings… → Providers → Sign in with ChatGPT."
                ))
                persist()
                return false
            }
        case .codexAppServer:
            // No pre-flight here on purpose. CodexAppServerClient resolves the
            // executable itself and reports a missing install / missing
            // `codex login` as an error EVENT, which lands in the transcript
            // through the same path this branch would use. Repeating the check
            // duplicates its message (they had already drifted) and puts its
            // filesystem probing on the main thread in the send path.
            break
        case .openAICompatible:
            let isLocal = config.baseURL.contains("localhost") || config.baseURL.contains("127.0.0.1")
            if config.apiKey.isEmpty && !isLocal {
                messages.append(ChatMessage(
                    role: .error,
                    text: "No API key for \(providerName). Add one in Settings → Providers (right-click the menu bar icon), or pick a configured provider from the model pill above."
                ))
                persist()
                return false
            }
        }

        // Codex owns its own tool loop, so Mia's client-side tools can't be
        // injected into it. Don't resolve the engine choice (which can append a
        // fallback warning) for a provider that cannot consume it — the globe
        // instead switches Codex's NATIVE web_search on at launch.
        let codexWebSearch = config.kind == .codexAppServer && Self.webSearchEnabled
        let webAccess = config.kind == .codexAppServer
            ? nil
            : resolveWebAccess(providerBaseURL: config.baseURL)

        // Capability is resolved at SEND time against the live provider+model —
        // attachments load at drop time and the user can switch in between.
        let sendProviderID = providerStore.selectedID
        let capabilities = providerStore.attachmentCapabilities(for: sendProviderID, model: config.model)
        capabilityFailure = nil

        var history = messages
            .filter { $0.role == .user || $0.role == .assistant }
            .map { OpenAIChatClient.WireMessage(role: $0.role.rawValue, content: Self.wireContent(for: $0, capabilities: capabilities)) }
        let systemPrompt = Self.systemPrompt.trimmingCharacters(in: .whitespacesAndNewlines)
        if !systemPrompt.isEmpty {
            history.insert(OpenAIChatClient.WireMessage(role: "system", content: .text(systemPrompt)), at: 0)
        }
        // What this request actually carries, for the unattributed-failure action
        // ("don't send images to this model again") on the error row.
        var sentImages = false
        var sentFiles = false
        for message in history {
            guard case .parts(let parts) = message.content else { continue }
            for part in parts {
                if part.type == "image_url" { sentImages = true }
                if part.type == "file" { sentFiles = true }
            }
        }

        persist()
        let assistantMessage = ChatMessage(role: .assistant, text: "", createdAt: Date())
        messages.append(assistantMessage)
        isStreaming = true
        pendingStatus = nil

        let typewriter = StreamingMode(rawValue: UserDefaults.standard.string(forKey: "streamingMode") ?? "")
            ?? .perCharacter
        streamTarget = ""
        streamFinished = false
        streamingMessageID = assistantMessage.id

        // Same event stream either way — only the wire protocol differs.
        let stream: AsyncStream<ChatStreamEvent>
        switch config.kind {
        case .chatGPT:
            stream = CodexResponsesClient.run(
                history: history, config: config, webAccess: webAccess,
                sessionID: conversationID.uuidString.lowercased()
            )
        case .codexAppServer:
            stream = CodexAppServerClient.run(history: history, config: config, webSearch: codexWebSearch)
        case .openAICompatible:
            stream = OpenAIChatClient.run(history: history, config: config, webAccess: webAccess)
        }

        streamTask = Task {
            // The streaming assistant row stays last; activity rows are inserted above it.
            var assistantIndex = messages.count - 1
            var reasoning = ""
            var reasoningShown = false
            // Wall-clock of the NETWORK turn (request dispatch → final byte),
            // measured from task start to the end of the stream loop — tool
            // rounds included, the typewriter reveal excluded.
            let turnStart = Date()
            // Last usage report of the turn, if the provider sent one.
            var usage: TurnUsage?
            // Last error text of the turn, if any — the stream tail turns it
            // into the failure notification (both .error and .contentRejected
            // append a visible error row, so both count as a dangling turn).
            var failure: String?
            for await event in stream {
                switch event {
                case .partial(let text), .done(let text):
                    streamTarget = text
                    // The wait these described is over — real text is arriving.
                    if !text.isEmpty {
                        pendingStatus = nil
                        pendingReasoning = nil
                        // Hand the thinking over to the message's own disclosure
                        // as the waiting row stops showing it, so it stays
                        // visible for the whole answer rather than reappearing
                        // when the turn ends. Once per turn, not per chunk.
                        if !reasoning.isEmpty, !reasoningShown {
                            reasoningShown = true
                            commit(reasoning: reasoning, to: assistantMessage.id)
                        }
                    }
                    startDrain(messageID: assistantMessage.id, mode: typewriter)
                case .status(let text):
                    pendingStatus = text
                case .usage(let u):
                    usage = u
                case .reasoning(let text):
                    // The visible copy: a plain @Published string, NOT a write
                    // into `messages`. Publishing the array per chunk would
                    // COW-copy it and re-diff every row many times a second; the
                    // waiting row is the only thing that reads this, and it is
                    // Equatable-gated to itself. The durable copy is committed
                    // once, where the answer takes over.
                    reasoning = text
                    pendingReasoning = text
                case .activity(let text):
                    messages.insert(ChatMessage(role: .activity, text: text), at: assistantIndex)
                    assistantIndex += 1
                case .error(let message):
                    failure = message
                    let row = ChatMessage(role: .error, text: message)
                    messages.append(row)
                    // The rejection wasn't attributable, but the request carried
                    // typed parts — offer the manual exception on this row.
                    if sentImages || sentFiles {
                        capabilityFailure = CapabilityFailureContext(
                            errorMessageID: row.id, providerID: sendProviderID,
                            model: config.model, sentImages: sentImages, sentFiles: sentFiles
                        )
                    }
                case .contentRejected(let capability, let message):
                    failure = message
                    providerStore.recordCapabilityException(
                        capability, supported: false, source: .learned,
                        providerID: sendProviderID, model: config.model
                    )
                    let noun = capability == .images ? "images" : "PDF files"
                    messages.append(ChatMessage(
                        role: .error,
                        text: "\(message)\n\nRecorded: \(config.model) didn't accept \(noun) — the composer will warn before sending it \(noun) again. Clear this in Settings → Providers if the rejection was transient."
                    ))
                }
            }
            let finalText = streamTarget
            streamFinished = true
            let turnDuration = Date().timeIntervalSince(turnStart)
            // Hand the composer back the moment the NETWORK turn ends. The
            // typewriter can still be revealing seconds of tail (typewriterStep
            // deliberately lags), and holding isStreaming across it left the send
            // button stuck as Stop and Return doing nothing long after the reply
            // had actually arrived.
            isStreaming = false
            pendingStatus = nil
            pendingReasoning = nil
            // Pull the user back if they left during the turn (the panel hides
            // on every deactivation, so "away" is the common case). A
            // cancelled task is a stop — the user is already here, so it
            // stays silent. An error row or an empty reply is a dangling
            // question, not a finished one; the notifier itself stays quiet
            // while Mia is the active app.
            if !Task.isCancelled {
                if let failure {
                    CompletionNotifier.shared.turnFailed(failure)
                } else if finalText.isEmpty {
                    CompletionNotifier.shared.turnFailed("")
                } else {
                    CompletionNotifier.shared.turnFinished()
                }
            }
            await drainTask?.value
            // "Still ours": flushTypewriter() clears streamingMessageID when a new
            // turn takes over mid-reveal, so this must not clobber its bookkeeping.
            let stillOurs = streamingMessageID == assistantMessage.id
            // The drain has returned by now, so any fade it left is stale — it
            // exits without clearing when the row it was revealing is gone.
            if stillOurs { drainTask = nil; reveal = nil }
            // By id, not by index, and with the text captured above: the user can
            // now start another turn while this tail reveals, so neither the row
            // nor `streamTarget` is guaranteed to still be ours.
            if let index = messages.firstIndex(where: { $0.id == assistantMessage.id }) {
                if finalText.isEmpty {
                    messages.remove(at: index)
                } else {
                    messages[index].text = finalText
                    // The turn's final thinking. Also runs on Stop (cancelling
                    // the stream ends the loop, not the tail), so a stopped turn
                    // keeps the reasoning it had produced, and it picks up
                    // anything a tool loop thought after the first text.
                    if !reasoning.isEmpty { messages[index].reasoning = reasoning }
                    // Token/duration footer for this reply. A stopped turn has
                    // no meaningful total (usage may not have arrived), so it
                    // stays unmeasured; usage-less providers still get the
                    // duration.
                    if !Task.isCancelled {
                        messages[index].stats = TurnStats(
                            totalTokens: usage?.total,
                            outputTokens: usage?.output,
                            duration: turnDuration
                        )
                    }
                }
            }
            if stillOurs { streamingMessageID = nil }
            persist()
            // The turn produced a real answer: this is the one moment a
            // default-titled conversation becomes worth naming (P3).
            maybeAutoTitle(producedAnswer: !finalText.isEmpty)
        }
        // The turn actually started — the composer clears its draft/attachments.
        return true
    }

    /// Writes a turn's thinking onto its assistant row, by id — a new turn can
    /// already have appended rows by the time this runs.
    private func commit(reasoning: String, to messageID: UUID) {
        guard let index = messages.firstIndex(where: { $0.id == messageID }) else { return }
        messages[index].reasoning = reasoning
    }

    /// Typewriter reveal speed. The per-tick step is this divided by the tick rate,
    /// so the granularity floor is a perf consequence (~6 chars at 33ms), not a
    /// choice: every tick re-lays out the growing message.
    nonisolated private static let typewriterCharsPerSecond = 180

    /// Tick period. Each tick re-renders and re-lays-out the growing message, and
    /// that cost scales with its length — so long texts tick less often (and take
    /// proportionally bigger steps to hold the same feel).
    nonisolated static func typewriterInterval(forLength count: Int) -> Int {
        count > 12_000 ? 100 : count > 4_000 ? 66 : 33
    }

    /// Characters to reveal on one tick.
    ///
    /// Pace at a FIXED rate while the answer is still arriving, and let the backlog
    /// grow. Any catch-up term proportional to the backlog settles at an equilibrium
    /// where the reveal rate EQUALS the arrival rate — which is why this mode used to
    /// look exactly like `.byChunk` on a fast model. Lag is the only lever that keeps
    /// the typewriter feel. It stays bounded two ways: the rate floors at "drain the
    /// backlog in 6s" (so a 20k-char answer isn't a two-minute wait), and it triples
    /// once the stream is done, so the tail types out instead of stranding the user.
    /// Extracted from the drain so `--smoke-typewriter` can assert all of that.
    nonisolated static func typewriterStep(backlog: Int, interval: Int, finished: Bool) -> Int {
        var rate = max(typewriterCharsPerSecond, backlog / 6)
        if finished { rate *= 3 }
        return min(backlog, max(1, rate * interval / 1000))
    }

    /// Generations of the current step that the per-character fade spans (6a).
    nonisolated static let revealGenerations = 6

    /// 6b pacing. A commit every ≥140 ms so a fast model can't dump the whole
    /// answer at once; 60 ms once the stream is done so the tail drains.
    nonisolated static let sentenceGapMs = 140
    nonisolated static let sentenceTailGapMs = 60
    /// How long one committed group takes to fade in (6b).
    nonisolated static let sentenceFadeMs = 350
    /// Past this much backlog, per-sentence commits whole paragraphs rather than
    /// accelerating — the entrance must never speed up (a faster fade reads as
    /// flicker, not as speed).
    nonisolated static let sentenceParagraphBacklog = 1_500

    private func startDrain(messageID: UUID, mode: StreamingMode) {
        guard drainTask == nil else { return }
        drainTask = Task { [weak self] in
            // 6a state: characters currently under the ramp, and the step that
            // built it (which is also the rate the ramp runs out at).
            var head = 0
            var lastStep = 0
            // 6b state: in-flight sentence groups, newest first, with their age
            // in ms; plus time since the last commit.
            var groups: [(length: Int, age: Int)] = []
            var sinceCommit = Int.max

            while let self, !Task.isCancelled {
                guard let index = self.messages.firstIndex(where: { $0.id == messageID }) else { return }
                let displayed = self.messages[index].text
                let target = self.streamTarget
                let interval = Self.typewriterInterval(forLength: target.count)
                let finished = self.streamFinished

                if !target.hasPrefix(displayed) {
                    // Non-monotonic snapshot (new tool round) — jump to it, and
                    // drop any fade: the text it described no longer exists.
                    self.messages[index].text = target
                    head = 0
                    groups = []
                } else if displayed.count >= target.count {
                    // Nothing to commit: either the stream is done or we are
                    // waiting on the network. Either way the fade must keep
                    // running out, or the head would stay dimmed indefinitely.
                    head = max(0, head - max(lastStep, 1))
                    if head == 0, groups.isEmpty, finished {
                        self.reveal = nil
                        return
                    }
                } else if mode == .perCharacter {
                    let step = Self.typewriterStep(
                        backlog: target.count - displayed.count,
                        interval: interval,
                        finished: finished
                    )
                    self.messages[index].text = String(target.prefix(displayed.count + step))
                    lastStep = step
                    head = min(displayed.count + step, step * Self.revealGenerations)
                } else if sinceCommit >= (finished ? Self.sentenceTailGapMs : Self.sentenceGapMs) {
                    let commit = Self.sentenceCommitLength(
                        in: target, revealed: displayed.count, finished: finished
                    )
                    if commit > displayed.count {
                        self.messages[index].text = String(target.prefix(commit))
                        groups.insert((length: commit - displayed.count, age: 0), at: 0)
                        sinceCommit = 0
                    }
                }

                if mode == .perSentence {
                    for i in groups.indices { groups[i].age += interval }
                    groups.removeAll { $0.age >= Self.sentenceFadeMs }
                    sinceCommit = sinceCommit >= Int.max - interval ? Int.max : sinceCommit + interval
                    self.reveal = groups.isEmpty
                        ? nil
                        : RevealState(messageID: messageID, fade: .groups(groups, duration: Self.sentenceFadeMs))
                } else {
                    self.reveal = head > 0
                        ? RevealState(messageID: messageID, fade: .ramp(head: head))
                        : nil
                }
                try? await Task.sleep(for: .milliseconds(interval))
            }
        }
    }

    /// 6b. Character index the per-sentence reveal may commit up to — the end of
    /// a sentence, line, or paragraph — or `revealed` when the text has not
    /// reached a boundary yet, so a half-sentence never shows.
    ///
    /// Boundaries: `.` `!` `?` followed by whitespace, and any newline (which is
    /// what makes list items and closing code fences boundaries too). Positions
    /// inside an OPEN code fence are never boundaries — a half-written fence must
    /// not commit. Extracted from the drain so `--smoke-typewriter` can assert it.
    nonisolated static func sentenceCommitLength(in text: String, revealed: Int, finished: Bool) -> Int {
        let chars = Array(text)
        guard revealed < chars.count else { return revealed }

        var boundaries: [Int] = []
        var paragraphEnds: Set<Int> = []
        var insideFence = false
        var atLineStart = true
        var index = 0
        while index < chars.count {
            if atLineStart, chars[index...].starts(with: ["`", "`", "`"]) {
                insideFence.toggle()
            }
            atLineStart = false
            let char = chars[index]
            if char == "\n" {
                atLineStart = true
                // The newline ENDING a fence line is a boundary when that line
                // closed the fence (insideFence is already false by then).
                if !insideFence {
                    boundaries.append(index + 1)
                    if index + 1 < chars.count, chars[index + 1] == "\n" {
                        paragraphEnds.insert(index + 1)
                    } else if index + 1 == chars.count {
                        paragraphEnds.insert(index + 1)
                    }
                }
            } else if !insideFence, char == "." || char == "!" || char == "?" {
                let next = index + 1
                if next == chars.count {
                    if finished { boundaries.append(next) }
                } else if chars[next].isWhitespace {
                    boundaries.append(next)
                }
            }
            index += 1
        }
        // Once the stream is over, the end of the text is ALWAYS a boundary —
        // including inside a fence the reply never closed. "An unclosed fence
        // never half-commits" is a rule about mid-stream text, and applying it
        // here instead strands the drain: it would spin without ever committing,
        // and the streamTask tail awaits that drain.
        if finished, boundaries.last != chars.count {
            boundaries.append(chars.count)
            paragraphEnds.insert(chars.count)
        }

        let pending = boundaries.filter { $0 > revealed }
        guard let last = pending.last else { return revealed }

        // Long answers coalesce instead of accelerating: the same 6 s ceiling as
        // per-character, spent on MORE PER BEAT rather than a faster entrance.
        let backlog = chars.count - revealed
        if backlog > sentenceParagraphBacklog {
            return pending.last { paragraphEnds.contains($0) } ?? last
        }
        let beats = max(1, 6_000 / sentenceGapMs)
        let perBeat = max(1, Int((Double(pending.count) / Double(beats)).rounded(.up)))
        let candidate = pending[min(perBeat, pending.count) - 1]
        // Groups never span a paragraph break — units stay semantic.
        return pending.first { paragraphEnds.contains($0) && $0 < candidate } ?? candidate
    }

    /// Inlines text attachments ahead of the typed text; images become content
    /// parts. Stays a bare string when there are no typed parts, for maximum
    /// provider compatibility. Capability-aware and re-decided EVERY send: images
    /// are ALWAYS sent (Mia does no image→text conversion — a known-refusing
    /// model warns in the composer instead), and a PDF goes as the original file
    /// exactly when the provider+model resolved to `files == true`, else as its
    /// extracted text. Non-private (and nonisolated — it's pure) for the
    /// attach-caps harness.
    nonisolated static func wireContent(
        for message: ChatMessage, capabilities: AttachmentCapabilities
    ) -> OpenAIChatClient.WireContent {
        let base = message.wireText ?? message.text
        var textBlocks: [String] = []
        var typedParts: [OpenAIChatClient.WirePart] = []
        for attachment in message.attachments {
            // Only real warnings travel to the model (it should know data is partial);
            // routine processing notes are user-facing only.
            let suffix = (attachment.noteKind == .warning ? attachment.note : nil).map { " — \($0)" } ?? ""
            switch attachment.content {
            case .text(let text):
                textBlocks.append("[File: \(attachment.filename)\(suffix)]\n\(text)")
            case .image(let dataURL):
                typedParts.append(.imageDataURL(dataURL))
            case .pdf(let dataURL, let extractedText):
                if capabilities.files == true {
                    typedParts.append(.fileDataURL(filename: attachment.filename, dataURL: dataURL))
                } else if !extractedText.isEmpty {
                    textBlocks.append("[File: \(attachment.filename)\(suffix)]\n\(extractedText)")
                } else {
                    // Never silent: a scanned PDF on a text-only path states its
                    // absence instead of contributing an empty block.
                    textBlocks.append("[File: \(attachment.filename) — a PDF with no extractable text; its content could not be included because this model does not accept PDF files directly]")
                }
            }
        }
        let combined = (textBlocks + [base]).filter { !$0.isEmpty }.joined(separator: "\n\n")
        if typedParts.isEmpty {
            return .text(combined)
        }
        return .parts(typedParts + [.text(combined.isEmpty ? "See the attached file(s)." : combined)])
    }

    /// Resolves the Settings search-engine choice against the active provider,
    /// falling back with an explicit warning row when the choice can't apply.
    private func resolveWebAccess(providerBaseURL: String) -> OpenAIChatClient.WebAccess? {
        guard Self.webSearchEnabled else { return nil }

        let choice = SearchEngineChoice(rawValue: UserDefaults.standard.string(forKey: "searchEngine") ?? "")
            ?? .duckduckgo

        func keyedEngine(_ choice: SearchEngineChoice, make: (String) -> SearchEngineConfig) -> OpenAIChatClient.WebAccess {
            guard let account = choice.apiKeyAccount,
                  let key = SecretStore.get(account: account), !key.isEmpty else {
                messages.append(ChatMessage(
                    role: .error,
                    text: "\(choice.label) needs an API key (Settings → Web Search) — using DuckDuckGo for this message."
                ))
                return .localTools(.duckduckgo)
            }
            return .localTools(make(key))
        }

        switch choice {
        case .duckduckgo:
            return .localTools(.duckduckgo)
        case .tavily:
            return keyedEngine(.tavily) { .tavily(key: $0) }
        case .brave:
            return keyedEngine(.brave) { .brave(key: $0) }
        case .providerNative:
            if providerBaseURL.contains("openrouter") {
                return .openRouterPlugin
            }
            messages.append(ChatMessage(
                role: .error,
                text: "Provider-native search only works on OpenRouter — using DuckDuckGo for this message."
            ))
            return .localTools(.duckduckgo)
        }
    }

    func stop() {
        streamTask?.cancel()
        // Don't wait for the cancelled task's tail to clear these — the waiting
        // row must not keep pulsing "Reasoning…" after the user said stop.
        pendingStatus = nil
        pendingReasoning = nil
        flushTypewriter()
    }

    /// The complete text of a message: for the row a typewriter is still
    /// revealing, everything that has ARRIVED rather than the characters typed
    /// out so far. Copy would otherwise hand back a truncated reply while
    /// claiming to copy the whole response.
    func fullText(of messageID: UUID) -> String {
        if messageID == streamingMessageID, !streamTarget.isEmpty { return streamTarget }
        return messages.first { $0.id == messageID }?.text ?? ""
    }

    /// Ends any typewriter still revealing a reply, showing it in full. Called by
    /// stop() and at the head of send(): once the composer is usable again during
    /// the reveal (see the streamTask tail), a new turn can begin mid-tail, and it
    /// must not inherit the previous one's drain or `streamTarget`.
    private func flushTypewriter() {
        drainTask?.cancel()
        drainTask = nil
        // The fade describes a reveal that is over; leaving it would strand the
        // flushed tail translucent with nothing left to tick it back to opaque.
        reveal = nil
        if let id = streamingMessageID, let index = messages.firstIndex(where: { $0.id == id }) {
            messages[index].text = streamTarget
        }
        streamingMessageID = nil
    }

    /// Start a new conversation that shares history up to and including
    /// `messageID` — stored as a tree branch (parent pointer + divergent tail
    /// only), so the shared prefix is never duplicated on disk.
    func fork(at messageID: UUID) {
        guard !isStreaming else { return }
        guard let index = messages.firstIndex(where: { $0.id == messageID }) else { return }
        // A reply can still be typing itself out here (isStreaming tracks the
        // network turn, not the reveal). Complete it FIRST: the persist() below
        // writes the parent, and everything after re-points the store at the
        // branch — so a partial row would be frozen into the parent's file and
        // never corrected, truncating the reply permanently.
        flushTypewriter()
        persist() // parent must be current on disk before the branch points into it
        forkParentID = conversationID
        forkMessageID = messageID
        conversationID = UUID()
        sharedPrefixCount = index + 1
        messages = Array(messages.prefix(index + 1))
        messages.append(ChatMessage(
            role: .activity,
            text: "Forked here — this branch diverges from the original conversation."
        ))
        persist()
    }

    // MARK: - Re-running the last turn

    /// The last user message, if there is one and nothing is in flight — the
    /// turn both Retry and Edit act on. Only the LAST turn is re-runnable on
    /// purpose: re-running an earlier one would silently discard every message
    /// after it, and the non-destructive way to revisit an earlier point in a
    /// conversation already exists (Fork).
    private var lastUserIndex: Int? {
        guard !isStreaming else { return nil }
        return messages.lastIndex { $0.role == .user }
    }

    var canRerunLastTurn: Bool { lastUserIndex != nil }

    /// Re-send the last user message unchanged, dropping whatever it produced.
    /// The provider and model are resolved fresh by `send`, so switching the
    /// pill and hitting Retry is how you ask a different model the same thing.
    ///
    /// Retry IS Edit-without-the-editing, so it goes through the same take —
    /// one place has to keep the truncate-before-resend order right.
    func retryLastTurn() {
        guard let prompt = takeLastUserMessageForEditing() else { return }
        // The display text, not `wireText`: send() re-expands a slash command
        // from it, so a retry of "/explain foo" resolves against the CURRENT
        // template rather than freezing the one that ran the first time.
        send(prompt.text, attachments: prompt.attachments)
    }

    /// Pull the last user message back out of the transcript for editing,
    /// dropping it and its reply. The caller owns putting it in the composer;
    /// nothing is re-sent until the user sends it.
    func takeLastUserMessageForEditing() -> (text: String, attachments: [Attachment])? {
        guard let index = lastUserIndex else { return nil }
        let prompt = messages[index]
        truncate(to: index)
        return (prompt.text, prompt.attachments)
    }

    /// Cut the transcript down to its first `count` messages.
    ///
    /// Two things have to happen before anything is dropped, or the tree breaks:
    /// direct children are MATERIALIZED (they resolve against the transcript
    /// being cut — the same never-orphan-a-fork rule that governs deletion), and
    /// a cut reaching into the shared prefix makes this conversation standalone,
    /// since its own file stores only the tail and could not otherwise represent
    /// a shorter history than its parent's.
    private func truncate(to count: Int) {
        guard count < messages.count else { return }
        // A reply may still be typing itself out; freeze it before persisting,
        // or the partial text is what the children absorb (the fork(at:) trap).
        stop()
        persist()
        // Unconditional, and it stays that way. Skipping this when no meta in
        // `recent` is a fork was tried and reverted: it makes never-orphan-a-fork
        // depend on `recent` mirroring the store exactly, and the failure mode of
        // that drifting is silent loss of a branch. The cost is one full decode
        // on a click, which is the cheaper side of that trade.
        ConversationStore.materializeChildren(of: conversationID)
        if count < sharedPrefixCount {
            forkParentID = nil
            forkMessageID = nil
            sharedPrefixCount = 0
        }
        messages = Array(messages.prefix(count))
        if messages.isEmpty {
            // persist() skips empty conversations, so the file would otherwise
            // keep serving the pre-truncation transcript to the next launch.
            ConversationStore.delete(id: conversationID)
            recent.removeAll { $0.id == conversationID }
        } else {
            persist()
        }
    }

    func deleteConversation(_ id: UUID) {
        searchCorpus = nil
        ConversationStore.deleteMaterializingChildren(id: id)
        recent = ConversationStore.listRecent()
        if id == conversationID {
            stop()
            conversationID = UUID()
            messages.removeAll()
            forkParentID = nil
            forkMessageID = nil
            sharedPrefixCount = 0
            customTitle = nil
            titleAttempted = false
        } else if forkParentID == id {
            // Our file was just materialized as standalone; align memory with it.
            forkParentID = nil
            forkMessageID = nil
            sharedPrefixCount = 0
        }
    }

    func newChat() {
        stop()
        persist()
        conversationID = UUID()
        messages.removeAll()
        forkParentID = nil
        forkMessageID = nil
        sharedPrefixCount = 0
        customTitle = nil
        titleAttempted = false
    }

    func loadConversation(_ id: UUID) {
        guard id != conversationID else { return }
        stop()
        persist()
        guard let loaded = ConversationStore.loadResolved(id: id) else {
            recent.removeAll { $0.id == id }
            messages.append(ChatMessage(role: .error, text: "Couldn't load that conversation — its file is missing or corrupt."))
            return
        }
        adopt(loaded)
    }

    /// Writes the current conversation to disk (a fork stores only its
    /// divergent tail) and refreshes its slot in the recent list. No-op for
    /// empty conversations (avoids junk files).
    private func persist() {
        guard !messages.isEmpty else { return }
        searchCorpus = nil // the stored set changed; rebuild on the next search
        let title = customTitle ?? Self.title(for: messages)
        let conversation = Conversation(
            id: conversationID,
            title: title,
            updatedAt: Date(),
            messages: Array(messages.dropFirst(sharedPrefixCount)),
            parentID: forkParentID,
            forkMessageID: forkMessageID,
            autoTitled: customTitle != nil
        )
        ConversationStore.save(conversation)
        recent.removeAll { $0.id == conversationID }
        recent.insert(ConversationMeta(
            id: conversationID,
            title: title,
            updatedAt: conversation.updatedAt,
            snippet: ConversationMeta.snippet(for: messages),
            isFork: forkParentID != nil
        ), at: 0)
    }

    /// First user message → display title: flattened to one line, cut at 40
    /// characters with an ellipsis. Internal + nonisolated (it is pure string
    /// work) so the titling harness can assert the exact default a
    /// conversation must still carry before auto-naming may fire — same
    /// test-hook pattern as `ConversationStore.overrideDirectory`.
    nonisolated static func title(for messages: [ChatMessage]) -> String {
        let firstUserText = messages.first { $0.role == .user }?.text ?? "New chat"
        let flattened = firstUserText.replacingOccurrences(of: "\n", with: " ")
        return flattened.count > Titling.maxTitleLength ? String(flattened.prefix(Titling.maxTitleLength)) + "…" : flattened
    }

    // MARK: - Auto-naming (P3)

    /// Settings › Chat switch, default ON. `object(forKey:)`, not
    /// `bool(forKey:)`: an unset key must read as ON, and bool() reports
    /// missing keys as false — the inverse default.
    static var autoTitleEnabled: Bool {
        get { UserDefaults.standard.object(forKey: "autoTitleEnabled") as? Bool ?? true }
        set { UserDefaults.standard.set(newValue, forKey: "autoTitleEnabled") }
    }

    /// After a completed turn, maybe ask the current provider once for a
    /// short title. Fire-and-forget by design (R3.2): failures are swallowed
    /// — no error row, no retry — because a nicer history label is never
    /// worth interrupting the chat it describes.
    private func maybeAutoTitle(producedAnswer: Bool) {
        guard let config = providerStore.currentConfig(),
              Titling.shouldTitle(
                  enabled: Self.autoTitleEnabled,
                  hasCustomTitle: customTitle != nil,
                  alreadyAttempted: titleAttempted,
                  producedAnswer: producedAnswer,
                  kind: config.kind
              ) else { return }
        guard let firstUser = messages.first(where: { $0.role == .user })?.text,
              !firstUser.trimmingCharacters(in: .whitespacesAndNewlines).isEmpty else { return }

        let request = Titling.requestMessages(firstUserText: firstUser)
        // Set at dispatch: the once-guard must hold even if the request never
        // comes back, or a flaky provider gets re-charged every turn.
        titleAttempted = true
        let namedConversation = conversationID
        Task { [weak self] in
            let raw: String
            do {
                raw = try await Titling.fetchTitle(messages: request, config: config)
            } catch {
                return // silent by design
            }
            let title = Titling.sanitize(raw)
            guard !title.isEmpty else { return }
            guard let self, self.conversationID == namedConversation, self.customTitle == nil else { return }
            self.customTitle = title
            // Mid-turn would persist the empty streaming placeholder row; the
            // turn's own end-of-turn persist() carries the title instead.
            if !self.isStreaming {
                self.persist()
            }
        }
    }
}
