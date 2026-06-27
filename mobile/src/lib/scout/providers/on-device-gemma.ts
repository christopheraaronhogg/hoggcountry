import type {
	ProviderCapabilities,
	ProviderRequest,
	ProviderResponse,
	ScoutProvider,
	TokenSink
} from '../types.ts';

export type GemmaTier = 'fast' | 'balanced' | 'small';

export interface GemmaModelDescriptor {
	tier: GemmaTier;
	modelId: string;
	maxContextTokens: number;
}

export interface OnDeviceGemmaBridge {
	isAvailable(): Promise<boolean>;
	describeModel(): Promise<GemmaModelDescriptor | null>;
	/**
	 * Optional: eagerly initialize the native engine so the FIRST real chat turn
	 * doesn't pay (or risk) the heavy, sometimes-flaky lazy LiteRT init. Best-effort
	 * and safe to call repeatedly; resolves whether or not warm-up succeeded.
	 */
	warmUp?(): Promise<void>;
	generate(
		input: {
			prompt: string;
			systemContext: string;
			maxTokens: number;
		},
		onToken?: (chunk: string) => void
	): Promise<{ text: string; truncated: boolean }>;
}

export interface OnDeviceGemmaProviderOptions {
	bridge?: OnDeviceGemmaBridge;
	tier?: GemmaTier;
}

const TIER_TO_CHARS: Record<GemmaTier, number> = {
	fast: 24_000,
	balanced: 16_000,
	small: 8_000
};

export class OnDeviceGemmaProvider implements ScoutProvider {
	private bridge?: OnDeviceGemmaBridge;
	private cachedDescriptor: GemmaModelDescriptor | null = null;
	// Only a confirmed-true result is cached. A false/unknown result is left as
	// null so the next call re-probes the (cheap) native isAvailable(). This
	// ensures that after a model download completes and the native engine flips
	// to available the router picks on-device without requiring an app restart.
	private availability: true | null = null;

	capabilities: ProviderCapabilities;

	constructor(options: OnDeviceGemmaProviderOptions = {}) {
		this.bridge = options.bridge;
		const tier = options.tier ?? 'balanced';
		this.capabilities = {
			id: 'on-device-gemma',
			mode: 'on-device',
			requiresNetwork: false,
			supportsToolCalls: false,
			maxContextChars: TIER_TO_CHARS[tier]
		};
	}

	/**
	 * Reset the positive-availability cache so the next available() call
	 * re-probes the native bridge. Call this after a model download completes
	 * or whenever the caller knows the model state has changed.
	 */
	invalidateAvailability(): void {
		this.availability = null;
	}

	/**
	 * Best-effort: ask the native bridge to initialize the engine ahead of the
	 * first chat turn. Never throws — warm-up failure just means the first turn
	 * pays the cost as before.
	 */
	async warmUp(): Promise<void> {
		try {
			await this.bridge?.warmUp?.();
		} catch {
			// Ignore — warming is an optimization, not a requirement.
		}
	}

	async available(): Promise<boolean> {
		if (!this.bridge) {
			// No bridge — never cache; a bridge could be wired later.
			return false;
		}
		// Return the cached positive result immediately.
		if (this.availability === true) return true;

		// Re-probe every time we don't have a confirmed positive.
		try {
			const result = await this.bridge.isAvailable();
			if (result) {
				this.availability = true;
			}
			// Do NOT cache false — leave availability null so next call re-probes.
			return result;
		} catch {
			// Transient error — do not cache; re-probe next time.
			return false;
		}
	}

	async describe(): Promise<GemmaModelDescriptor | null> {
		if (this.cachedDescriptor) return this.cachedDescriptor;
		if (!this.bridge) return null;
		try {
			this.cachedDescriptor = await this.bridge.describeModel();
		} catch {
			this.cachedDescriptor = null;
		}
		return this.cachedDescriptor;
	}

	async generate(request: ProviderRequest, onToken?: TokenSink): Promise<ProviderResponse> {
		const ready = await this.available();
		if (!ready || !this.bridge) {
			throw new OnDeviceModelUnavailableError(
				'OnDeviceGemmaProvider invoked but no native bridge is wired. Wire a LiteRT-LM adapter before asking Scout to answer.'
			);
		}

		const systemContext = renderSystemContext(request);
		const result = await this.bridge.generate(
			{ prompt: request.prompt, systemContext, maxTokens: 512 },
			onToken
		);

		// A blank/whitespace generation is a failure, not an answer. Treat it as
		// unavailable so the user gets an honest retry rather than an empty bubble
		// dressed up with a confidence badge.
		if (!result.text || !result.text.trim()) {
			throw new OnDeviceModelUnavailableError('On-device model returned an empty response.');
		}

		return {
			answer: result.text,
			confidence: 'medium',
			mode: 'on-device',
			provider: 'on-device-gemma',
			additionalReceipts: [],
			additionalConfirmations: result.truncated
				? [
					{
						id: 'on-device-truncated',
						prompt: 'On-device context was truncated — verify the answer matches the cached trail pack.',
						reason: 'low-confidence'
					}
				]
				: [],
			contextUsed: ['on-device-gemma']
		};
	}
}

export class OnDeviceModelUnavailableError extends Error {
	constructor(message: string) {
		super(message);
		this.name = 'OnDeviceModelUnavailableError';
	}
}

export function renderSystemContext(request: ProviderRequest): string {
	const { pack, toolInvocations } = request;
	const toolLines = toolInvocations.map((tool) => `- [${tool.toolId}] ${tool.summary}`);
	const conversationLines = (request.conversationHistory ?? []).map((message) => {
		const speaker = message.role === 'user' ? 'Hiker' : 'Scout';
		const timestamp = message.timestamp ? ` (${message.timestamp})` : '';
		return `${speaker}${timestamp}: ${message.content}`;
	});
	return [
		`You are Scout, an Appalachian Trail field companion for thru-hikers.`,
		`Voice: calm, capable, plain-spoken, and human. Sound like a thoughtful trail partner, not a chatbot, cowboy, coach, marketer, or emergency dispatcher.`,
		`Do not use "howdy", "partner", "well now", fake dialect, hype, or repeated self-introductions. Do not echo the hiker's question unless you need to clarify it.`,
		`Answer the hiker's immediate question first. Keep most replies short: 2-5 tight paragraphs or a few short lines. If the hiker sounds uncertain, steady them and give the next practical decision.`,
		`Use plain text only. Do not use Markdown headings, bold markers, tables, or long bullet lists; this chat renders plain text.`,
		`Be honest about uncertainty. Use "candidate", "verify", or "I don't know" when the pack cannot prove something. Never turn candidate water, shelters, towns, or weather into guarantees.`,
		`For water questions, use the next_water tool finding as the answer's spine. Lead with the nearest actionable water option or next reliable source from the tool finding. If no reliable water is loaded, say that after the source hierarchy; do not start with a generic refusal.`,
		`When source_search or open_source_doc findings are labeled as source skills, treat them as topic-specific documents Scout intentionally read for this answer. Use them to shape caveats and next-step advice.`,
		`When preparation or training questions have pretrip, terrain, loadout, safety, or offline setup findings, give Dad a concrete short plan. For "what should I focus on first" prompts, include an immediate first-week checklist, not only general training advice. Include shakedown hikes, foot care/blister practice, conservative early mileage, gear/loadout checks, water treatment habits, and an offline app/model rehearsal when those appear in the findings.`,
		`For resupply or mail-drop questions, avoid firm mail-ahead advice until the missing inputs are named: diet restrictions, expected pace, next town timing, store/post-office hours, hostel or shuttle access, and whether the item is hard to find locally. Give the default rule after that: buy common food in town, mail only constrained or hard-to-find items to verified stops.`,
		`For injury or pain questions, do not tell the hiker to train through pain. Lead with pain-free load reduction, low-impact conditioning, strength/mobility work, and clinician/physical-therapist guidance when pain persists, worsens, swells, or changes gait.`,
		`Use the strongest 2-4 tool findings visibly in the answer. Convert source-skill discipline into specific actions; do not answer with generic outdoor advice when Scout supplied concrete findings.`,
		conversationLines.length
			? `Recent conversation before the current prompt:\n${conversationLines.join('\n')}\nUse this for follow-ups like "last question", "that", "the message before", or "what did I just ask". The current user prompt is not part of this history.`
			: '',
		`Hiker mile: ${pack.hiker.currentMile.toFixed(1)} of ${pack.frame.totalMiles.toFixed(1)} (${pack.hiker.direction}).`,
		`Day ${pack.hiker.dayNumber}. Target miles today: ${pack.hiker.targetMilesToday ?? 'unset'}.`,
		toolLines.length ? `Trail tool findings:\n${toolLines.join('\n')}` : '',
		`Cite sources from these findings. Do not invent landmarks. If a fact is volatile, ask the hiker to confirm it.`
	]
		.filter(Boolean)
		.join('\n\n');
}
