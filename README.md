# Igor

Chrome side panel for Element Web: a chat with a local Ollama model that sees the room you have open.

## Installation

Requirements: Chrome (or a Chromium browser with side panel support), [Ollama](https://ollama.com) running locally with at least one model pulled, and an Element Web account. No build step or dependencies.

1. Get the code:
   ```sh
   git clone https://github.com/pmatos/igor.git
   ```
2. Pull a model if you have none, for example `ollama pull gemma4:12b`. Pick one that supports tools if you want web search; others fall back to plain chat.
3. Load the extension: open `chrome://extensions`, enable **Developer mode**, click **Load unpacked** and select the cloned `igor` directory. Command-line flags like `--load-extension` are ignored by recent branded Chrome, so use this UI. Note the ID shown on the Igor card (32 letters); Chrome derives it from the folder's path, so it stays the same until you move the folder.
4. Let Ollama accept requests from Igor, otherwise it answers 403. Set `OLLAMA_ORIGINS=chrome-extension://<Igor's ID>` and restart Ollama:
   - systemd user service: `systemctl --user edit ollama`, add `[Service]` and `Environment=OLLAMA_ORIGINS=chrome-extension://<Igor's ID>`, then `systemctl --user restart ollama`
   - macOS launch agent: set `OLLAMA_ORIGINS` under `EnvironmentVariables` in its plist, then reload it with `launchctl bootout gui/$(id -u)/<its label>` and `launchctl bootstrap gui/$(id -u) <the plist>` (`kickstart` keeps the old settings)
   - manual: `OLLAMA_ORIGINS='chrome-extension://<Igor's ID>' ollama serve`

   Don't use `chrome-extension://*`: it lets every extension you install use Ollama, including its commands to delete and download models. If Igor cannot reach Ollama, the panel shows the exact value to set.
5. Open Element Web in a tab and click the Igor toolbar icon. The panel docks beside the page. The first time, click **Allow this site** in the panel: Igor only reads rooms on Element sites you approve. Choose a model in the dropdown; the room you have open is picked up automatically.

Updating: `git pull`, then click the reload icon on the Igor card in `chrome://extensions`.

Ollama is expected at `http://localhost:11434`; change it under **Settings** in the panel. Igor asks for access one Element site at a time (**Allow this site**; **Forget approved Element sites** in Settings removes them), and for access to all sites only when you turn on **Web tools**, which need it to search and read pages. It never runs anything in a site you have not approved as your Element, so other sites cannot pose as Element or notice Igor.

First questions in a long room can be slow on modest hardware because the whole context is processed. Lower **Max room messages** in Settings, or use a smaller or MoE model. Follow-up questions are faster: Igor keeps the start of each request the same, so Ollama reuses its work on the room, and asks Ollama to keep the model loaded for 30 minutes after an answer instead of its default 5 (**Keep the model loaded** in Settings). A loaded model holds its memory the whole time.

## Usage

- **Room context** checkbox (under the input, like **Web tools**; both only affect typed questions): include recent messages of the open room in each question.
- **Web tools** checkbox: let the model search the web and fetch pages. Once room messages are in the chat, Igor shows each search query with **Search** / **Skip** buttons first, because queries go to Brave and a model steered by room text could put messages into one; turn that off with **Ask before the model searches the web** in Settings. The room tools (older messages, room search) are offered whenever room context is on. The text of the pages an answer opened, and its search snippets, stay in the conversation for one more question and are then dropped, so a page cannot keep steering later answers or fill the context window. A question right after can still use them; later ones need the model to open the page again, which it does not always do on its own, so ask it to if needed.
- **Search** next to **Send**: lists the room's messages that contain all the typed words, as `#N` links, without asking the model. Unencrypted rooms are searched by the homeserver across the whole history; encrypted rooms over the newest 3000 events. The results stay in the chat, so a follow-up question can use them. The model can also search on its own (`search_room`, below).
- **Quick buttons** above the input (always use the open room, regardless of the Room context checkbox):
  - **Unread**: what you missed since your read marker. Element moves the marker seconds after you open a room, so the panel remembers where it was when it first saw the room; keep the panel open while switching rooms.
  - **Day / Week / Month**: summary of the last 24 hours, 7 days or 30 days (week and month start at midnight).
  - **Mentions**: messages from the last 7 days that ask you something or need your reply. Only messages that mention you (name, user id, `@room`), reply to you, or come from the other person in a direct chat are considered.
  - Windowed buttons load the whole period regardless of **Max room messages**. When it does not fit the context window, each calendar week (or day) is handled separately and the answer is built from those notes; this is slow for a busy month on modest hardware, and **Stop** works. Notes for finished weeks are cached, so repeating a month summary only redoes the recent part. They are kept on disk for 60 days after their last use; change that with **Days to keep part summaries on disk** in Settings, where 0 keeps them in memory only, until Chrome restarts. Notes on encrypted rooms always stay in memory. **Forget cached part summaries** in Settings clears them all. If the start of the period cannot be loaded, the panel says where coverage begins.
  - Edit the buttons in **Settings**, one per line: `label | period | prompt`, where period is empty (recent messages, like a normal question), `unread`, or days like `14d`, optionally with `mentions`; `{period}` in the prompt becomes the time span. Empty the box to restore the defaults.
- **Copy** under an answer copies it as Markdown, with `#12` citations turned into message links.
- The line under an answer shows which model wrote it, how long loading the room's messages took, and the time to the first word and in total.
- **Message links**: answers cite room messages as `#12` links with a hover tooltip (sender, time). Clicking one jumps the Element tab to that message, so you can ask for a summary and read the parts that matter.
- **One chat per room**: switching rooms in Element switches the conversation, and coming back to a room (even after closing the panel) brings its chat back. Chats are kept in memory only (`chrome.storage.session`) and are gone after a browser restart or when the extension is reloaded or updated. While an answer is streaming the panel stays on its room and switches when it ends.
- **Clear** empties the current room's chat (and stops an answer in progress).

## How it works

- Room context comes from Element's own `window.mxMatrixClientPeg` (matrix-js-sdk client), read via a `world: "MAIN"` script injected on each send. Decrypted events work; no second Matrix login. This is an internal global and may change between Element versions.
- The room is taken from the URL hash (`#/room/...`). Older history is back-paginated up to "Max room messages", or for summaries up to the start of the period (at most 5000 events).
- Replies are encoded as `Name (replying to [#N] Other): ...` (from the Matrix reply relation; the legacy quoted fallback is stripped), because a bare reply body is ambiguous: see `benchmarks/` (reply understanding rose from 73% to 100% for `gemma4:26b-a4b-it-qat`).
- Default model is `gemma4:26b-a4b-it-qat` when installed (falls back to `gemma4:e4b-it-qat`, then the first model); a model you pick in the dropdown stays pinned. Picking another model unloads the previous one from Ollama, so the two do not hold memory at the same time.
- Model list comes from `GET /api/tags`; chat uses `/api/chat` with streaming, `think: false`, `temperature: 0` (same answer for the same input, as in the benchmarks) and an explicit `num_ctx`.

## Tools

The model can call (toggle "Web tools" in the panel; models without tool support fall back automatically):

- `web_search` — Brave Search HTML results, no API key (DuckDuckGo blocks extension requests)
- `fetch_url` — page text, truncated to 8k chars
- `get_older_messages` — back-paginates the room via the Matrix client for history beyond the initial window
- `search_room` — finds messages containing all the given words. Unencrypted rooms use the homeserver's search index, which covers the whole history; encrypted rooms are not indexed, so the newest 3000 events are paged and matched locally. The result always says how far back it looked, so the model does not mistake "not found in the last month" for "never discussed".

The extension requests `https://*/*` host access so `fetch_url` and Element on any host work.

## Layout

- `src/panel.*` — side panel UI
- `src/extract.js` — room extraction (injected into the page)
- `src/background.js` — opens the panel on icon click
- `tests/` — Node tests and a browser harness with fake Chrome, Element and Ollama (see AGENTS.md)

## Benchmarks

Default model choice and raw results live in [`benchmarks/`](benchmarks/README.md), including a plan for harder synthetic tests.
