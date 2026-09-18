# [Realtime (speech-to-speech)](https://pydantic.dev/docs/ai/realtime/overview/)

# Realtime (speech-to-speech)

Pydantic AI's realtime support lets an agent hold a live, spoken conversation. It streams the user's audio to a speech-to-speech model and streams the model's spoken reply back over one persistent connection, so latency is low and interruptions feel natural.

A realtime session uses the same agent [tools](https://pydantic.dev/docs/ai/realtime/tools/), [dependencies](https://pydantic.dev/docs/ai/core-concepts/dependencies/), [instructions](https://pydantic.dev/docs/ai/core-concepts/agent/#instructions), [message history](https://pydantic.dev/docs/ai/core-concepts/message-history/), [capabilities](https://pydantic.dev/docs/ai/realtime/capabilities/), [usage limits](https://pydantic.dev/docs/ai/core-concepts/agent/#usage-limits), and [observability](https://pydantic.dev/docs/ai/realtime/observability/) as the rest of Pydantic AI, and that's the point: mid-call the agent can look up an order, check availability, or act on the logged-in user's data with the same tools and dependencies a text agent would use. The call itself becomes ordinary message history that you can [hand to `Agent.run()`](https://pydantic.dev/docs/ai/realtime/history/#handing-off-to-a-text-agent) for summarization or structured follow-up, the same code runs against [four providers](#provider-support), and usage limits and [Logfire](https://pydantic.dev/docs/ai/integrations/logfire/) tracing are built in. Your application owns the audio transport -- bridged through your backend, or [browser-direct over WebRTC](https://pydantic.dev/docs/ai/realtime/deployment/#browser-webrtc-server-sideband) on OpenAI and Azure -- while Pydantic AI runs the provider-agnostic agent loop.

## Quickstart

Install Pydantic AI with the OpenAI realtime dependencies, and set `OPENAI_API_KEY`:

-   [pip](#tab-panel-267)
-   [uv](#tab-panel-268)

Terminal

```bash
pip install "pydantic-ai-slim[openai-realtime]"
```

Terminal

```bash
uv add "pydantic-ai-slim[openai-realtime]"
```

A complete voice agent is one agent, one session, and three small loops -- microphone in, speaker out, and a transcript log. The model hears the user, calls your tool on your backend, and answers out loud:

reservations.py

```python
import asyncio
import contextlib
from collections.abc import AsyncIterator

from pydantic_ai import Agent

agent = Agent(instructions='You take reservations for The Terrace. Keep replies short.')


@agent.tool_plain
async def check_availability(day: str, party_size: int) -> str:
    """Check whether a table is free."""
    return f'One table for {party_size} is free at 7 pm {day}.'


async def microphone_chunks() -> AsyncIterator[bytes]:
    yield b'...'  # capture signed 16-bit mono PCM chunks from your microphone


async def play_audio(chunks: AsyncIterator[bytes]) -> None:
    async for chunk in chunks:
        ...  # write the PCM chunk to your speaker


async def main():
    async with agent.realtime('openai:gpt-realtime').session() as session:
        microphone = asyncio.create_task(session.send_audio(microphone_chunks()))
        speaker = asyncio.create_task(play_audio(session.stream_audio()))

        async for part in session.stream_transcripts():
            print(f'{part.speaker}: {part.transcript}')
            #> user: Hi! Do you have a table for two tomorrow night?
            #> assistant: We do: 7 pm, table for two. Want me to book it?
            if part.speaker == 'assistant':
                break  # keep listening in a real call; we stop after one exchange

    # Leaving the `async with` block closes the session, which ends the speaker's audio stream --
    # but the microphone reads an external source, so stop it explicitly.
    microphone.cancel()
    with contextlib.suppress(asyncio.CancelledError):
        await microphone
    await speaker


if __name__ == '__main__':
    asyncio.run(main())
```

_(This example is complete, it can be run "as is" -- after filling in the two audio placeholders, which depend on your audio stack)_

Capture and play at the sample rates the model expects -- they're reported by the model's profile and can differ between input and output (see [Provider support](#provider-support) below). The [voice assistant example](https://pydantic.dev/docs/ai/examples/realtime/realtime-voice/) fills the placeholders in with [`listentome`](https://github.com/Kludex/listentome) for a runnable microphone-and-speaker loop; the [text-to-audio example](https://pydantic.dev/docs/ai/examples/realtime/realtime-text-to-audio/) skips audio input entirely by sending a text prompt and saving the spoken reply to a WAV file.

## How sessions work

Your backend opens the provider connection and runs a [`RealtimeSession`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession). Stream content in with [`send()`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession.send) or [`send_audio()`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession.send_audio), and iterate the session for its [event stream](https://pydantic.dev/docs/ai/realtime/events/) -- content, tool, turn, error, and reconnect events -- or consume the dedicated [`stream_audio()`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession.stream_audio) and [`stream_transcripts()`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession.stream_transcripts) views as the quickstart does.

```text
device ↔ media bridge ↔ RealtimeSession ↔ provider
                         ├── typed tools
                         └── message history
                         (your backend)
```

The _media bridge_ is whatever moves audio between the user's device and your backend -- a browser WebSocket or a telephony bridge. It's how you deploy this beyond a local microphone; see [Connecting a frontend](https://pydantic.dev/docs/ai/realtime/deployment/) for each setup. On OpenAI and Azure the browser can instead exchange media with the provider directly over [WebRTC](https://pydantic.dev/docs/ai/realtime/deployment/#browser-webrtc-server-sideband), with your backend running this same loop over a control-plane sideband rather than a media bridge.

## Learn by task

-   [Audio, images, and transcripts](https://pydantic.dev/docs/ai/realtime/audio/) covers the PCM wire contract, playback, captions, input transcription, and image input.
-   [Events](https://pydantic.dev/docs/ai/realtime/events/) covers the session event vocabulary, which events are shared with standard runs, and the turn boundary.
-   [Turns and interruptions](https://pydantic.dev/docs/ai/realtime/turns/) covers automatic turn detection, barge-in, output truncation, and push-to-talk.
-   [Tools](https://pydantic.dev/docs/ai/realtime/tools/) covers function tools, provider-native tools, concurrency, approval, and delegation during a call.
-   [Capabilities and hooks](https://pydantic.dev/docs/ai/realtime/capabilities/) covers how capabilities and their hooks map onto a session.
-   [History and handoff](https://pydantic.dev/docs/ai/realtime/history/) covers retained transcripts, audio and images, session seeding, and continuing with a standard text agent.
-   [Connecting a frontend](https://pydantic.dev/docs/ai/realtime/deployment/) covers the transport options between user devices and your backend.
-   [Connection lifecycle](https://pydantic.dev/docs/ai/realtime/lifecycle/) covers the session lifecycle, reconnection, session limits, and errors.
-   [Usage and observability](https://pydantic.dev/docs/ai/realtime/observability/) covers usage limits, cost accounting, Logfire, and gateway trace propagation.
-   [Troubleshooting](https://pydantic.dev/docs/ai/realtime/troubleshooting/) indexes common problems by symptom.
-   The [API reference](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/) lists session and codec types and explains how to implement another provider.

## Provider support

All providers implement the same [`RealtimeModel`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeModel) interface. Provider pages are the canonical source for installation, model names, settings, feature support, and quirks:

Provider

Audio output

Image input

Text output

[Browser WebRTC](https://pydantic.dev/docs/ai/realtime/deployment/#browser-webrtc-server-sideband)

Async tool calls

[Thinking](https://pydantic.dev/docs/ai/capabilities/thinking/)

State-restoring reconnect

[OpenAI](https://pydantic.dev/docs/ai/realtime/openai/)

✓

✓

✓

✓

✓

`gpt-realtime-2*` models

Replays local history

[Azure OpenAI](https://pydantic.dev/docs/ai/realtime/azure/)

✓

✓

✓

✓

✓

`gpt-realtime-2*` models

Replays local history

[Google Gemini](https://pydantic.dev/docs/ai/realtime/gemini/)

✓

✓

✗

✗

Opt-in, native-audio models

Native-audio and 3.x models

✓, with a `reconnect` policy

[xAI](https://pydantic.dev/docs/ai/realtime/xai/)

✓

✗

✗

✗

✗

`grok-voice-latest` and `-think-` models

✓, with a `reconnect` policy

For portable branching, inspect [`RealtimeModel.profile`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeModel.profile) or [`RealtimeSession.profile`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeSession.profile): the [`RealtimeModelProfile`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeModelProfile) reports the audio sample rates to capture and play at, plus one flag per capability in the table above and beyond. Profiles resolve the same way as for a standard [`Model`](https://pydantic.dev/docs/ai/api/models/base/#pydantic_ai.models.Model) (see [Inspecting a model's profile](https://pydantic.dev/docs/ai/models/overview/#inspecting-a-models-profile)) -- defaults, then the provider's knowledge of the model name, then your `profile=` argument on top. Pass `profile=` when the model name doesn't identify the model and the inferred facts are wrong, most often with an Azure deployment named something other than its model:

```python
from pydantic_ai.realtime.azure import AzureRealtimeModel

# The deployment serves a reasoning model, but nothing in its name says so.
model = AzureRealtimeModel('voice-prod', profile={'supports_thinking': True})
```

A partial dict is merged over the resolved profile; pass a callable `(resolved) -> RealtimeModelProfile` instead to replace it wholesale.

## Shared settings

Realtime sessions have their own settings type, playing the role that [model run settings](https://pydantic.dev/docs/ai/core-concepts/agent/#model-run-settings) play for standard runs: [`RealtimeModelSettings`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.RealtimeModelSettings) defines the settings shared across realtime providers, from `tool_choice` to [`turn_detection`](https://pydantic.dev/docs/ai/api/pydantic-ai/realtime/#pydantic_ai.realtime.TurnDetection). Set defaults with `settings=` on the realtime model constructor, or pass `realtime(model_settings=...)` for one session; per-session values override model defaults:

```python
from pydantic_ai import Agent
from pydantic_ai.realtime import RealtimeModelSettings

agent = Agent(instructions='You are a helpful voice assistant.')
realtime = agent.realtime(
    'openai:gpt-realtime', model_settings=RealtimeModelSettings(output_modality='audio')
)
```

Voices and detailed controls are provider-specific -- `openai_voice`, `google_voice`, `xai_voice` and friends live on the corresponding provider settings classes, with defaults and limitations on the provider pages.

The agent's regular `model_settings` and capability `get_model_settings()` contributions do not configure realtime sessions. Unsupported shared settings are ignored, matching request-response models, with one deliberate exception:

Asking for text on a speech-only model fails fast

`output_modality='text'` on a model whose profile reports `supports_text_output=False` (Gemini Live and xAI) raises a `UserError` before connecting: silently answering with speech would be worse than not starting.

## Relationship to standard agent runs

`Agent.realtime()` is the long-lived, bidirectional sibling of [`run()`](https://pydantic.dev/docs/ai/api/pydantic-ai/agent/#pydantic_ai.agent.AbstractAgent.run) and [`iter()`](https://pydantic.dev/docs/ai/api/pydantic-ai/agent/#pydantic_ai.agent.AbstractAgent.iter), and its parameters mirror theirs:

```python
agent.realtime(
    model,                # 'openai:gpt-realtime', or a RealtimeModel instance
    deps=...,             # dependencies, as in run()/iter()
    model_settings=...,   # RealtimeModelSettings
    instructions=...,     # combined with the agent's instructions
    toolsets=...,         # additional toolsets for the session
    capabilities=...,     # additional capabilities for the session
    usage=..., usage_limits=...,
    message_history=...,  # prior conversation to seed the session with
)
```

It accepts the same [dependencies](https://pydantic.dev/docs/ai/core-concepts/dependencies/), [instructions](https://pydantic.dev/docs/ai/core-concepts/agent/#instructions), [toolsets](https://pydantic.dev/docs/ai/tools-toolsets/toolsets/), [capabilities](https://pydantic.dev/docs/ai/capabilities/overview/), [usage limits](https://pydantic.dev/docs/ai/core-concepts/agent/#usage-limits), and [`message_history`](https://pydantic.dev/docs/ai/core-concepts/message-history/) as a standard run. Input arrives through the live session instead of a single `user_prompt`:

Standard-run feature

In a realtime session

Function tools and [tool hooks](https://pydantic.dev/docs/ai/realtime/capabilities/#capability-stages-in-a-session)

✓ -- validation, retries, and execution hooks run as in a standard run

[Run hooks](https://pydantic.dev/docs/ai/realtime/capabilities/#run-hooks) (`before_run`, `after_run`, `wrap_run`, `on_run_error`)

✓ -- once around the session

[Capabilities](https://pydantic.dev/docs/ai/realtime/capabilities/), including third-party

✓ -- resolved once at connect

[Event stream](https://pydantic.dev/docs/ai/realtime/events/)

✓ -- iterate the session, or attach [`ProcessEventStream`](https://pydantic.dev/docs/ai/api/pydantic-ai/capabilities/#pydantic_ai.capabilities.ProcessEventStream)

`output_type` and output validators

✗ -- [delegate to a text agent](https://pydantic.dev/docs/ai/realtime/tools/#delegating-work-during-a-call)

Graph node and model-request hooks (e.g. `before_model_request`)

✗ -- no agent graph

History processors at seeding

✗ -- [preprocess before opening](https://pydantic.dev/docs/ai/realtime/capabilities/#seeded-history-is-not-processed)

`event_stream_handler` parameter

✗ -- use [`ProcessEventStream`](https://pydantic.dev/docs/ai/api/pydantic-ai/capabilities/#pydantic_ai.capabilities.ProcessEventStream)

See [Capabilities and hooks](https://pydantic.dev/docs/ai/realtime/capabilities/) for the full mapping, and [hand off to a text agent](https://pydantic.dev/docs/ai/realtime/history/#handing-off-to-a-text-agent) for structured output or deeper reasoning.

## Other ways to build voice

The same realtime loop deploys to a browser or phone over [WebRTC or a WebSocket relay](https://pydantic.dev/docs/ai/realtime/deployment/) without changing the agent code. If the realtime agent loop isn't the right fit for a product, two alternatives sit outside it:

-   **Batch STT → text agent → TTS.** Compose a standard [agent](https://pydantic.dev/docs/ai/core-concepts/agent/) with your own speech-to-text and text-to-speech services when you want a specific text model, structured output, or independently chosen speech components.
-   **Browser directly to the provider.** A provider-native, UI-only experience using an ephemeral token: the provider's own SDK owns the session, so there is no server-side agent loop, tools, or shared history -- unlike the [WebRTC sideband](https://pydantic.dev/docs/ai/realtime/deployment/#browser-webrtc-server-sideband), where the browser owns the media but your backend still runs the agent. Pydantic AI can still power separate backend workflows.

## Limitations

Limitation

Tracking

SIP is not built in; bridge telephony through a provider such as Twilio.

[Connecting a frontend](https://pydantic.dev/docs/ai/realtime/deployment/#siptelephony-bridge)

New tools cannot be advertised mid-session, so `defer_loading=True` tools and tool-contributing capabilities are [rejected](https://pydantic.dev/docs/ai/realtime/capabilities/#deferred-capability-loading).

[#7288](https://github.com/pydantic/pydantic-ai/issues/7288)

Realtime-specific exchange hooks are not yet available; use supported [tool hooks](https://pydantic.dev/docs/ai/realtime/capabilities/) and [session events](https://pydantic.dev/docs/ai/realtime/events/).

[#7190](https://github.com/pydantic/pydantic-ai/issues/7190), [#7191](https://github.com/pydantic/pydantic-ai/issues/7191)

Provider resumption handles cannot be persisted and resumed in another process.

[#7302](https://github.com/pydantic/pydantic-ai/issues/7302)

Dynamic instructions are resolved once when the session connects.

[#7303](https://github.com/pydantic/pydantic-ai/issues/7303)

History processors do not transform `message_history` before realtime seeding; [preprocess it](https://pydantic.dev/docs/ai/realtime/capabilities/#seeded-history-is-not-processed) before opening the session when filtering or redaction is required.

[#7299](https://github.com/pydantic/pydantic-ai/issues/7299)

Interactive human-in-the-loop tool approval is not supported: a [`HandleDeferredToolCalls`](https://pydantic.dev/docs/ai/api/pydantic-ai/capabilities/#pydantic_ai.capabilities.HandleDeferredToolCalls) handler resolves approvals [from policy, immediately](https://pydantic.dev/docs/ai/realtime/tools/#deferred-and-approval-required-tools).

[#7301](https://github.com/pydantic/pydantic-ai/issues/7301)

Realtime [`enqueue()`](https://pydantic.dev/docs/ai/realtime/tools/#enqueuing-prompts) accepts text parts and system prompt parts, which are joined into one live-input turn; multimodal content and model responses are unsupported.

[#7300](https://github.com/pydantic/pydantic-ai/issues/7300)

Gemini Live tool results are JSON-only: binary content attached to a [tool return](https://pydantic.dev/docs/ai/realtime/tools/#function-tools) raises.

[#7362](https://github.com/pydantic/pydantic-ai/issues/7362)

---
