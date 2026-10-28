# Scribe

Speech to text for Citadel and Ember. A user attaches an English audio file (mp3, wav, m4a, ogg, flac, webm) in chat; the agent calls `scribe__tool_scribe_transcribe` and answers with the transcript. Runs locally with faster-whisper on CPU.

- Upload: `POST /api/files` (raw bytes, `X-Requester-Username`, `X-Filename`), reached only through ember_api.
- Tool: `tool_scribe_transcribe(file_id, timestamps=false)` over MCP at `/mcp`.
- Limits: 25 MB, 150 s of audio, 200 MB per user. Uploads and transcripts are deleted after 24 hours.
- Run: `.venv_scribe/Scripts/python.exe -m src.run`. Docker: `docker compose up -d --build` (the Citadel network must exist).
- Privacy: user audio sits on this machine for 24 hours.

- Dictation: `POST /api/transcribe` accepts the same raw audio and identity headers as `/api/files`, reuses upload validation, quota and cached transcription, and returns `{text, duration_s}`. Ember records WebM for up to 150 s and appends the transcript to the editable draft through `/api/attachments/dictate` (`files.upload`, 20 MB cap). It never sends the draft automatically.

- Live dictation: `WS /api/stream` uses `X-Internal-Token` (when configured) and `X-Requester-Username`, checked before acceptance. Send binary 16 kHz mono signed 16-bit little-endian PCM; send `{"type":"stop"}` to finish. Responses are `{"type":"partial","text":"..."}`, `{"type":"final","text":"..."}` or `{"type":"error","message":"..."}`. Text is the complete current transcript. Roughly each second of received PCM triggers a new pass. Consecutive passes commit agreeing words and trim their timestamped audio; stop transcribes the remaining window once more.
- Fallback: `POST /api/transcribe-partial` accepts a complete encoded audio snapshot with the same headers and returns `{text, duration_s}`. It deletes its staging file after decoding and retains neither audio nor transcript. Live PCM is also never stored. Both paths honor the per-user quota, including retained uploads and concurrent transient audio.
- Live limits: 150 s total audio (or lower `SCRIBE_MAX_SECONDS`), `SCRIBE_MAX_BYTES`, 64,000 bytes per frame, 15 s idle. The wall deadline allows the audio limit plus `SCRIBE_TIMEOUT_S` for inference. Unstable speech that cannot commit within the 30 s audio window ends with a sanitized error; it is never silently discarded. Saturated WebSockets accept then close with 1013 so proxies can detect fallback; unauthorized sockets close before acceptance. Fallback HTTP requests return 503 when their own admission pool is full.
- Settings: `SCRIBE_STREAM_CAPACITY=2` caps simultaneous WebSockets and separately caps ephemeral HTTP requests, allowing fallback when sockets are full. `SCRIBE_STREAM_MAX_FRAME_BYTES=64000`, `SCRIBE_STREAM_IDLE_S=15`, and `SCRIBE_STREAM_WINDOW_S=30` tune the other bounds. Both paths share `SCRIBE_CONCURRENCY` with ordinary transcription. A timed-out worker keeps its inference slot until it actually finishes. The server queues at most four incoming WebSocket messages per connection.
- Decoding is bounded before transcription: ffmpeg emits at most one second beyond the audio limit (to detect oversize input), rejects that oversize PCM, and is killed and reaped on cancellation or `SCRIBE_TIMEOUT_S` decode timeout.
