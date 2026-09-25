// Anthropic provider — streams Claude API responses as ProviderStreamEvents.
//
// Uses raw fetch + SSE parsing (no SDK dependency). Supports:
// - Streaming text, thinking, and tool_use content blocks
// - Prompt caching via cache_control breakpoints
// - Error handling with retry-after parsing
// - Extended thinking (adaptive for Opus 4.6+, enabled for other thinking models)

import type { Provider, ProviderRequest, ProviderStreamEvent, Message } from '../../common/protocol.ts'
import { providerShared } from './shared.ts'
import { auth } from '../auth.ts'
import { anthropicUsage } from '../anthropic-usage.ts'
import { version } from '../version.ts'
import { STATE_DIR } from '../state.ts'
import { appendFileSync } from 'node:fs'
import { blob } from '../session/blob.ts'

// Per-API-call usage log. One JSON line per call: timestamp, sessionId,
// input (uncached), cacheRead, cacheCreation, output. Lets us diagnose cache
// hit rate at the finest available granularity (Anthropic reports usage per
// message, not per turn).
const USAGE_LOG_PATH = `${STATE_DIR}/anthropic-call-log.jsonl`
function logCall(entry: Record<string, unknown>): void {
	try {
		appendFileSync(USAGE_LOG_PATH, JSON.stringify(entry) + '\n')
	} catch {
		// Logging must never break a generate call.
	}
}

// The ?beta=true query parameter is required for OAuth tokens.
// Without it, requests hit a different backend pool that returns 529 overloaded
// errors far more frequently.
const API_URL = 'https://api.anthropic.com/v1/messages?beta=true'
const API_VERSION = '2023-06-01'
// Large enough for big file writes: current Claude models allow at least 64k output.
const MAX_TOKENS = 64000
// Stop reasons that end a turn normally; anything else is surfaced as an error.
const NORMAL_STOP_REASONS = ['end_turn', 'tool_use', 'stop_sequence', 'pause_turn']
// Claude Code version we report in the OAuth user-agent (see the header block in generate()).
// Tracks the version bundled with the Agent SDK we verified against.
const CLAUDE_CODE_VERSION = '2.1.280'

// Map Anthropic error types to HTTP status codes for consistent retry logic
const ERROR_TYPE_STATUS: Record<string, number> = {
	overloaded_error: 529,
	rate_limit_error: 429,
	api_error: 500,
	invalid_request_error: 400,
	authentication_error: 401,
	permission_error: 403,
	not_found_error: 404,
}

function errorTypeToStatus(type: unknown): number | undefined {
	return typeof type === 'string' ? ERROR_TYPE_STATUS[type] : undefined
}


// ── Message sanitization ──
// Strip or convert blocks that Anthropic doesn't understand (e.g. foreign
// thinking signatures from OpenAI reasoning models).

function isOpenAIReasoningSignature(signature: unknown): boolean {
	if (typeof signature !== 'string' || !signature.trim().startsWith('{')) return false
	try {
		const parsed = JSON.parse(signature)
		return parsed?.type === 'reasoning' && typeof parsed.encrypted_content === 'string'
	} catch {
		return false
	}
}

/** Convert non-Anthropic thinking blocks into plain text. */
function formatForeignThinking(thinking: unknown, sourceModel?: string): string | null {
	if (typeof thinking !== 'string') return null
	const text = thinking.trim()
	if (!text) return null
	const model = sourceModel ?? 'unknown'
	return `[model ${model} thinking]\n${text}`
}

/** Filter out orphaned web_search blocks. A server_tool_use (web_search) must be
 *  paired with a web_search_tool_result and vice versa — unpaired blocks cause API errors. */
function filterUnpairedWebSearch(blocks: any[]): any[] {
	if (!Array.isArray(blocks) || blocks.length === 0) return blocks
	const useIds = new Set<string>()
	const resultIds = new Set<string>()
	for (const b of blocks) {
		if (b?.type === 'server_tool_use' && b?.name === 'web_search' && typeof b?.id === 'string')
			useIds.add(b.id)
		if (b?.type === 'web_search_tool_result' && typeof b?.tool_use_id === 'string')
			resultIds.add(b.tool_use_id)
	}
	return blocks.filter((b: any) => {
		if (b?.type === 'server_tool_use' && b?.name === 'web_search')
			return typeof b.id === 'string' && resultIds.has(b.id)
		if (b?.type === 'web_search_tool_result')
			return typeof b.tool_use_id === 'string' && useIds.has(b.tool_use_id)
		return true
	})
}

/** Remove or transform blocks Anthropic can't handle. */
function sanitizeMessages(msgs: Message[]): any[] {
	if (!msgs.length) return msgs
	const out: any[] = []
	for (const msg of msgs) {
		if (!Array.isArray(msg.content)) {
			out.push(msg)
			continue
		}
		let content: any[] = []
		for (const block of msg.content as any[]) {
			if (block.type === 'thinking') {
				// Foreign thinking (e.g. OpenAI reasoning) → convert to text
				if (isOpenAIReasoningSignature(block.signature)) {
					const replayed = formatForeignThinking(block.thinking, block._model)
					if (replayed) content.push({ type: 'text', text: replayed })
					continue
				}
				// Native Anthropic thinking — pass through
				content.push({ type: 'thinking', thinking: block.thinking, signature: block.signature })
				continue
			}
			content.push(block)
		}
		// Drop orphaned web_search blocks (can happen after context compaction or aborted turns)
		content = filterUnpairedWebSearch(content)
		if (content.length > 0) out.push({ ...msg, content })
	}
	return out
}

// ── Prompt caching ──
// Mark the last user message (and second-to-last user message if conversation
// is long enough) with cache_control for Anthropic's prompt caching feature.

function applyCacheBreakpoints(msgs: any[]): any[] {
	if (!msgs.length) return msgs
	const out = structuredClone(msgs)

	const markLast = (m: any) => {
		if (typeof m.content === 'string') {
			m.content = [{ type: 'text', text: m.content, cache_control: { type: 'ephemeral' } }]
		} else if (Array.isArray(m.content) && m.content.length) {
			m.content[m.content.length - 1].cache_control = { type: 'ephemeral' }
		}
	}

	// Always mark the last message
	markLast(out[out.length - 1])

	// Also mark the second-to-last user message for better cache hit rates
	if (out.length >= 3) {
		for (let i = out.length - 2; i >= 0; i--) {
			if (out[i].role === 'user') {
				markLast(out[i])
				break
			}
		}
	}

	return out
}

// ── SSE stream parser ──

async function* parseStream(
	body: ReadableStream<Uint8Array>,
	logContext?: { sessionId?: string; model?: string },
): AsyncGenerator<ProviderStreamEvent> {
	// Tool calls are assembled across content_block_start / delta / stop events
	const tools = new Map<number, { id: string; name: string; json: string; input?: Record<string, unknown> }>()
	const serverTools = new Map<number, { block: any; json: string }>()
	const usage = { input: 0, output: 0, cacheRead: 0, cacheCreation: 0 }
	let gotStop = false

	for await (const ev of providerShared.iterateJsonSse(body)) {
		if (ev.type === 'content_block_start') {
			const b = ev.content_block
			if (b.type === 'tool_use') {
				tools.set(ev.index, { id: b.id, name: b.name, json: '', input: b.input })
			} else if (b.type === 'server_tool_use') {
				// Server-side tool input streams as input_json_delta after this empty block.
				serverTools.set(ev.index, { block: b, json: '' })
			} else if (b.type === 'web_search_tool_result') {
				yield { type: 'server_tool', serverBlocks: [b] }
			}
		} else if (ev.type === 'content_block_delta') {
			const d = ev.delta
			if (d.type === 'thinking_delta') yield { type: 'thinking', text: d.thinking }
			else if (d.type === 'signature_delta') yield { type: 'thinking_signature', signature: d.signature }
			else if (d.type === 'text_delta') yield { type: 'text', text: d.text }
			else if (d.type === 'input_json_delta') {
				// Accumulate partial JSON for local and server-side tool input.
				const t = tools.get(ev.index)
				if (t) t.json += d.partial_json
				const st = serverTools.get(ev.index)
				if (st) st.json += d.partial_json
			}
		} else if (ev.type === 'content_block_stop') {
			const t = tools.get(ev.index)
			if (t) {
				// Anthropic sends the complete start input for argument-less tools without JSON deltas.
				const parsed = providerShared.parseToolInput(t.json || (t.input && typeof t.input === 'object' && !Array.isArray(t.input) ? JSON.stringify(t.input) : ''))
				yield { type: 'tool_call', id: t.id, name: t.name, input: parsed.input, rawJson: t.json, ...(parsed.parseError ? { parseError: parsed.parseError } : {}) }
				tools.delete(ev.index)
			}
			const st = serverTools.get(ev.index)
			if (st) {
				const parsed = providerShared.parseToolInput(st.json)
				if (!parsed.parseError) st.block.input = parsed.input
				yield { type: 'server_tool', serverBlocks: [st.block] }
				serverTools.delete(ev.index)
			}
		} else if (ev.type === 'message_start' && ev.message?.usage) {
			// Keep input, cacheRead, and cacheCreation separate — they bill at
			// very different rates (full / ~10% / ~125%). Mashing them together
			// hides cache misses. Log each API call so we can audit post-hoc.
			const u = ev.message.usage
			const inputDelta = u.input_tokens ?? 0
			const cacheReadDelta = u.cache_read_input_tokens ?? 0
			const cacheCreationDelta = u.cache_creation_input_tokens ?? 0
			usage.input += inputDelta
			usage.cacheRead += cacheReadDelta
			usage.cacheCreation += cacheCreationDelta
			logCall({
				ts: new Date().toISOString(),
				sessionId: logContext?.sessionId,
				model: logContext?.model,
				input: inputDelta,
				cacheRead: cacheReadDelta,
				cacheCreation: cacheCreationDelta,
			})
		} else if (ev.type === 'message_delta') {
			if (ev.usage) usage.output += ev.usage.output_tokens ?? 0
			const stopReason = ev.delta?.stop_reason
			if (stopReason === 'refusal') {
				const details = { stop_reason: 'refusal', stop_details: ev.delta.stop_details }
				const explanation = ev.delta.stop_details?.explanation ?? 'The request was blocked by Anthropic policy.'
				yield { type: 'error', message: `Claude refused the request: ${explanation}`, body: JSON.stringify(details) }
			} else if (stopReason && !NORMAL_STOP_REASONS.includes(stopReason)) {
				// e.g. max_tokens: a tool call cut off mid-input is dropped, so the turn would look empty.
				yield { type: 'error', message: `Response stopped: ${stopReason} (max_tokens is ${MAX_TOKENS})`, body: JSON.stringify(ev.delta) }
			}
		} else if (ev.type === 'message_stop') {
			gotStop = true
		} else if (ev.type === 'error') {
			const msg = ev.error?.message ?? 'Stream error'
			const body = JSON.stringify(ev.error ?? ev)
			const status = errorTypeToStatus(ev.error?.type)
			yield { type: 'error', message: msg, status, body }
		}
	}

	if (!gotStop) return
	yield { type: 'done', doneStatus: 'completed', usage }
}

// ── Generate ──

async function* generate(req: ProviderRequest): AsyncGenerator<ProviderStreamEvent> {
	await auth.ensureFresh('anthropic')
	const cred = auth.getCredential('anthropic')
	anthropicUsage.setCurrentCredential(cred)
	if (!cred) {
		yield { type: 'error', message: 'No Anthropic credentials. Run /login claude (or set ANTHROPIC_API_KEY).' }
		return
	}

	// Manual budget_tokens is rejected by Opus 4.7+, Sonnet 5, and Fable 5.
	const isAdaptive = /^claude-(?:opus-(?:4-[678]|5(?:-|$))|sonnet-(?:4-6|5(?:-|$))|fable-5(?:-|$))/.test(req.model)
	const supportsThinking = /^claude-(opus|sonnet|fable)/.test(req.model)

	const isOAuth = cred.type === 'token'


	// Build system blocks with cache control.
	// OAuth requires the Claude Code identity prefix — without it, the API rejects the request.
	const system: any[] = []
	if (isOAuth) {
		system.push({ type: 'text', text: "You are Claude Code, Anthropic's official CLI for Claude." })
	}
	system.push({ type: 'text', text: req.systemPrompt, cache_control: { type: 'ephemeral' } })

	// Sanitize messages (handle foreign thinking blocks) then add cache breakpoints
	const messages = applyCacheBreakpoints(sanitizeMessages(req.messages))

	const body: any = {
		model: req.model,
		max_tokens: MAX_TOKENS,
		stream: true,
		system,
		messages,
	}

	// Enable extended thinking for capable models
	if (supportsThinking) {
		body.thinking = isAdaptive
			? { type: 'adaptive' }
			: { type: 'enabled', budget_tokens: Math.min(10000, MAX_TOKENS - 1) }
	}

	if (req.tools?.length) {
		// Append web_search as a server-side tool — Claude searches the web itself,
		// no local execution needed. Results come back as server_tool_use /
		// web_search_tool_result content blocks in the stream.
		body.tools = [
			...req.tools,
			{ type: 'web_search_20250305', name: 'web_search', max_uses: 5 },
		]
	}

	const url = API_URL
	const halVersion = version.state.combined ? `hal/${version.state.combined}` : 'hal'
	const headers: Record<string, string> = {
		'Content-Type': 'application/json',
		...(isOAuth ? { Authorization: `Bearer ${cred.value}` } : { 'x-api-key': cred.value }),
		'anthropic-version': API_VERSION,
		'anthropic-beta': isOAuth
			? 'claude-code-20250219,oauth-2025-04-20,fine-grained-tool-streaming-2025-05-14'
			: 'fine-grained-tool-streaming-2025-05-14',
		// Anthropic's own Agent SDK ships the Claude Code binary
		// (@anthropic-ai/claude-agent-sdk-<platform>/claude) and, for subscription tokens, sends the
		// same `claude-code-20250219,oauth-2025-04-20` beta list, `x-app: cli`, and a user-agent of
		// the form `claude-cli/<version> (external, <entrypoint>[, agent-sdk/<version>])`. The SDK
		// puts its own entrypoint (`sdk-ts`) in that slot rather than pretending to be the CLI, so we
		// do the same with `hal/<head>+<working-copy-hash>` — same client contract, honest about who
		// is calling, and precise about which build, since Hal has no releases. Probed against
		// the live endpoint: the entrypoint string is not validated, so this is disclosure, not a
		// workaround.
		//
		// Anthropic's usage policy (https://code.claude.com/docs/en/legal-and-compliance,
		// "Authentication and credential use") allows OAuth for ordinary personal use of Claude Code
		// by a subscriber; what it forbids is offering claude.ai login to other people or routing
		// third parties' requests through Free/Pro/Max credentials. Hal is a personal tool signing in
		// with its own user's subscription, so it stays on the personal-use side of that line.
		// Terms change — consult the page above before shipping Hal as a product to other users, and
		// use an API key (x-api-key branch above) for anything beyond personal use.
		...(isOAuth ? { 'user-agent': `claude-cli/${CLAUDE_CODE_VERSION} (external, ${halVersion})`, 'x-app': 'cli' } : {}),
	}

	let res: Response
	try {
		res = await fetch(url, {
			method: 'POST',
			headers,
			body: JSON.stringify(body),
			signal: req.signal,
		})
	} catch (err) {
		if (req.signal?.aborted) throw err
		yield { type: 'error', message: providerShared.formatNetworkError(err), endpoint: url }
		return
	}

	if (!res.ok) {
		const text = (await res.text()).slice(0, 2000)
		const retryAfterMs = providerShared.parseRetryDelay(res, text)
		if (isOAuth && res.status === 401) {
			yield {
				type: 'error',
				message: 'Claude login expired or was revoked. Run /login claude.',
				status: res.status,
				body: text,
				endpoint: url,
			}
		} else if (res.status === 429) {
			const cooldownMs = retryAfterMs ?? 10 * 60_000
			auth.markCooldown(cred, cooldownMs)
			const fast = auth.hasAvailableCredential('anthropic')
			const nextCredential = auth.getCredential('anthropic')
			yield {
				type: 'error',
				message: providerShared.formatRotationMessage('Anthropic', cred, nextCredential, fast ? 1_000 : cooldownMs, fast),
				status: res.status,
				body: text,
				endpoint: url,
				retryAfterMs: fast ? 1_000 : cooldownMs,
			}
		} else {
			yield { type: 'error', message: `Anthropic API ${res.status}`, status: res.status, body: text, endpoint: url, retryAfterMs }
		}
		return
	}

	const rawOutput = res.clone().text()
	try {
		for await (const event of parseStream(res.body!, { sessionId: req.sessionId, model: req.model })) {
			if (event.type === 'done' && cred.type === 'token') await anthropicUsage.refreshAll().catch(() => {})
			yield event
		}
	} catch (err) {
		if (req.signal?.aborted) throw err
		yield { type: 'error', message: providerShared.formatNetworkError(err), endpoint: url }
	} finally {
		// Keep the wire response: the parser drops malformed SSE, so only this shows
		// whether absent or truncated tool JSON produced an empty tool input.
		const raw = await rawOutput.catch(() => '')
		if (req.sessionId && raw) await blob.writeRawProviderOutput(req.sessionId, 'anthropic', raw).catch(() => {})
	}
}

export const anthropicProvider: Provider = { generate }
