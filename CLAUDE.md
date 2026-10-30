# SpellCheckingPrototype

Demo of **auto-completion and auto-correction** in Bright Pattern Agent Desktop, in English and Arabic: LLM spell check and auto-correction (PER #60254), and Smart Compose-style inline auto-completion (PER #60145).

## Commands

| Command | What it does |
|---|---|
| `npm run dev` | The demo page at http://localhost:5173 (bound to 127.0.0.1) from source with hot reload. Vite forwards `/api` to the Node server, so run `npm run server` next to it |
| `npm run server` | The Node backend (`server/index.ts`) at http://127.0.0.1:$PORT (8787 by default; the Vite proxy reads the same `PORT`): Basic auth on everything, `POST /api/autocorrection` and `POST /api/autocompletion` forwarded to the LLM with the key, and the built page from `dist/`. Reads `LLM_API_KEY`, `BASIC_AUTH_USER`, `BASIC_AUTH_PASSWORD` and `PORT` from `.env` (copy `.env.example`) |
| `npm start` | Build, then `npm run server`: one process serving the page and the API. To share: `ngrok http $PORT` |
| `npm run typecheck` | `tsc --noEmit` |
| `npm run build` | Typecheck + production build to `dist/` |
| `npm test` | Playwright tests (`src/**/*.spec.ts`) in Chrome with a fake LLM, no key or network needed |
| `npm run eval` | Spell check prompt eval against the real LLM: runs `eval/spell-check-cases.json` (drafts with the expected mistakes, English, Arabic and mixed) and prints pass rate, recall, precision, fix accuracy, dangerous `sure: true` reports and latency. Needs `LLM_API_KEY`, from `.env` (copy `.env.example`, ignored by git) or the environment. Flags: `--runs 3`, `--model`, `--url`, `--filter <name part>`, `--verbose`, `--concurrency 4` |

GitHub Actions: `test.yml` runs the typecheck and the tests on every push to `main` and every pull request.

## Layout

- `index.html` + `src/app/`: the demo page, React + Tailwind: settings spread over the page (context and word lists below the field; toggles in the field's header; in memory only, lost on reload; applied to the field 500 ms after the last change), one message field, the popover and auto-completion drawn from the assistant's state, the Debugger (`Debugger.tsx`: the LLM requests and answers, or every `AssistantEvent` with Verbose on; colored by area, long lines cut and expandable). Shared page state lives in two React contexts, not props, in `providers/` (each file holds its context, its hook and its provider): `SettingsProvider.tsx` with `useSettings()` (the settings and their applied copy) and `DebuggerProvider.tsx` with `useDebugger()` (the events); `App.tsx` is only layout. `components/` and `hooks/` only draw and call; `lib/` holds the non-UI parts: settings, `presets.ts` (the English, Arabic and Russian presets: each sets the LLM context, the custom dictionary and the ignored words together), `auto-completion-layout.ts` (where the auto-completion is drawn), and the contenteditable side of the assistant: `content-editable-editor-control.ts` (the `EditorControl` for a contenteditable div), `field-text.ts` (the field's text as one string, mapped back to DOM ranges and the caret), `llm-client.ts` (the page's `LLMClient`: posts the chat messages to `/api/autocorrection` or `/api/autocompletion` by the request kind, `API_ROUTES`), `browser.ts` (text replace as a native undo step with `execCommand('insertText')`, selection, rects, CSS highlights).
- `src/assistant/`: the part that is reused in other editors (a contenteditable div, a WYSIWYG editor). It never touches the DOM: the host passes an `EditorControl` (get and replace the text by offsets, get and set the caret, show underlines and flash the auto-corrected words) and an `LLMClient` (`ask(messages, signal, requestKind)`: sends the chat messages to whatever LLM the host uses, `requestKind` says whether it is the spell check or the auto-completion and returns `{ answer }` or `{ error }`), and calls the handlers with plain key and input objects. The assistant owns the prompts, the parsing and the 5 s timeout; the host owns the transport (model, key, endpoint). `createAssistant(editorControl, options)` in `index.ts` is the one entry point; it keeps the state the page draws (`popover`, `autoCompletion`, `requestStatus`) and makes the one `AssistantContext` that holds all the assistant's data. The other modules are plain functions that take that context; none keeps its own variables. The assistant never writes to the console: what it does goes out through `options.onEvent` as `AssistantEvent` notes (`area`, `message`, `details`), sent with `context.debug(area, message, details)`.
  - `types.ts`: everything the host sees (`EditorControl`, `LLMClient` with `ChatMessage` and `LLMResult`, `KeyPress`, `TextInput`, `AssistantOptions`, `AssistantState`, `AssistantEvent`) and the internal `AssistantContext`.
  - `words.ts`: finding whole words, text direction. `mistake-places.ts`: where the model's mistakes are in the text.
  - `llm.ts`: the two requests, sent in parallel after the same pause in typing (spell check: mistakes with fixes and how sure; auto-completion: the next sentence at the caret), the call to the `LLMClient` with its timeout, building the user messages, answer parsing. `spell-check-prompt.ts` and `auto-completion-prompt.ts`: each request's system message and examples.
  - `check-while-typing.ts`: `handleInput`, `handleKeyDown` and the other handlers the host calls; the debounced request (sent after a pause in typing); handing the answers on.
  - `spell-check.ts`: underlines, popover, auto-correction with each fixed word as one undo step (never for ignored words: the code enforces it, and ignored words are not sent to the LLM), keeping the caret and flashing the auto-corrected words, undo and redo of an auto-correction.
  - `auto-completion.ts`: the auto-completion shown after the caret and its keys; the host draws it.
- Tests sit next to the file they test, as `<file>.spec.ts`. The page tests fake the backend (`page.route('**/api/**')`), so no server runs in tests. In `src/assistant/` they run in Node, so with no DOM: the pure functions, and `index.spec.ts` drives the assistant through an in-memory `EditorControl`. `src/app/lib/field-text.spec.ts` reads a real contenteditable in the browser. `src/app/App*.spec.ts` open the whole page with a fake LLM (`src/app/demo-page.ts`): the page, spell check, auto-completion.
- `server/`: the backend, Express 5 (MIT): `index.ts` (Basic auth, the two API routes, statics from `dist/`, `index.html` for any other GET) and `openai-chat-client.ts` (the upstream `LLMClient`: OpenAI-style chat completions with the key, `LLM_URL`, `MODEL`; also used by the eval).
- `eval/`: the prompt eval, plain Node (`spell-check.ts` imports the real prompt, message builder and parser from `src/assistant/` and the upstream client from `server/`; a resolve hook adds `.ts` to the extensionless imports). The dataset is `spell-check-cases.json`: `preset` (a key of `PRESETS`), `draft`, optional `caretOffset` (default: end of the draft), `expected` mistakes with `word`, accepted `fixes`, and optional `sure` (left out when either value is fine).
- Code has no comments: names say what things are.

## Hard constraints

- **No browser extensions.** Everything is page code.
- **The page's only network calls are to its own backend** (`/api/autocorrection` and `/api/autocompletion`, `src/app/lib/llm-client.ts`). Only the server (`server/`) talks to the LLM (`LLM_URL` in `server/openai-chat-client.ts`, an OpenAI-compatible chat completions endpoint) and only the server knows the key: it never reaches the browser. `src/assistant/` makes no network calls itself.
- **Never write decorations into the editable DOM.** Use the CSS Custom Highlight API for underlines and an overlay for auto-completion. The assistant changes text only through `EditorControl.replaceText`, and each call must be one native undo step (the contenteditable `EditorControl` uses `replaceText` in `src/app/lib/browser.ts`).
- **`src/assistant/` never touches the DOM**: no `document`, `window`, DOM nodes, ranges or DOM events. Everything it needs comes through `EditorControl` and the handler arguments.
- **Licensing.** No GPL/LGPL terms. Any new dependency needs its license checked first.
- **English first, Arabic first-class.** Every text-processing behavior must work in English, Arabic and mixed text. Use `dir="auto"` / `unicode-bidi: plaintext` for direction.

## Conventions

- TypeScript strict with `erasableSyntaxOnly` (no enums, no parameter properties).
- No one-line `if` or `else`: every body goes in braces on its own line, even a single `return;` or call.
- An arrow function is either one line or has a braced body: never break the line right after `=>`.
- Avoid long lines. Shorten one with line breaks only: keep the logic exactly as it is, and do not pull parts out into new helpers, constants or variables just to make the line shorter.
- Break lines with judgment, not like a formatter: break only where it makes the code easier to read. Lines that read as a set (a column of similar `console.log` calls, similar cases) stay one line each, even if one is a bit longer.
- No comments to explain a block. When a block's purpose is not clear from the code, put it in a function whose name says what it does, and call it where it is needed.
- Boolean names start with `is`, `has`, `should`, `with`, `can` or a similar word (`isSure`, `withAutoCompletion`, `shouldReturnCaret`). The only exceptions are names fixed by something outside the code: the LLM's JSON keys, library options, and DOM event fields (`KeyPress` keeps `KeyboardEvent`'s `ctrlKey` and the others, so a DOM event can be passed as is).
- No more than 2 keys on one line: an object literal or object type with 3 or more keys puts each key on its own line.
- One React component per file in `src/app/components/` and `src/app/providers/`, named after the component. No second component in a file, not even a small helper one.
- The page is React + Tailwind (`src/app/`). `src/assistant/` is plain TypeScript with no React.
