package main

import (
	"context"
	"encoding/json"
	"errors"
	"fmt"
	"io"
	"log"
	"net/http"
	"os"
	"strings"
	"time"
	"unicode/utf8"

	anthropic "github.com/anthropics/anthropic-sdk-go"
	"github.com/google/uuid"

	"travel-route-planner/store"
)

// planMaxIterations bounds the agent tool loop. A rich session (local recs +
// several place searches + flights/events/stays + one create_itinerary) runs
// 8–11 iterations; parallel tool calls share an iteration. Hitting the cap
// ends the stream gracefully instead of letting a pathological loop burn cost.
const planMaxIterations = 15

// planModelCallTimeout bounds a single streaming model call. The handler's own
// context is r.Context() (no server WriteTimeout, since SSE needs unlimited),
// so without this a hung/slow upstream Anthropic socket would stall the agent
// loop — and the client's SSE stream — indefinitely. Each call gets its own
// deadline; exceeding it surfaces as a friendly SSE error, not a hang.
const planModelCallTimeout = 120 * time.Second

// planMaxDuration is the overall wall-clock ceiling for a single /plan request.
// The server runs with WriteTimeout:0 so SSE can stream unbounded, and
// planModelCallTimeout only bounds one model call — so without this a stuck
// stream (client gone, agent loop wedged) could pin its goroutine and its
// concurrency slot indefinitely. Deriving the handler context from this closes
// the request after the ceiling and frees the slot. Generous: a rich multi-tool
// session with compaction stays well under it.
const planMaxDuration = 10 * time.Minute

// planMaxMessages / planMaxMessageChars bound the resent conversation history.
// Every agent-loop iteration (up to planMaxIterations) re-pays input tokens on
// the full history, so these bounds are a hard cost lever. The working limit
// is compaction (plan_compactor.go): histories reaching planCompactThreshold
// are summarized down before the turn runs, and an updated client keeps its
// wire history small by resending the summary instead of the folded messages.
// planMaxMessages is only the backstop above that — old clients that ignore
// the compaction events get re-compacted server-side every turn until this
// cap, so hitting it means a runaway or abusive client. Violations return a
// friendly SSE `error` event, not a 500.
const (
	planMaxMessages     = 60
	planMaxMessageChars = 20000
	// planMaxDisplayLabelRunes bounds the display-label metadata persisted in
	// transcripts. Labels are chip-sized UI strings; anything longer is
	// truncated (not rejected — best-effort metadata) to keep a hostile client
	// from bloating the JSONB column.
	planMaxDisplayLabelRunes = 200
)

// Image attachment caps. Per-image tracks Anthropic's 5 MB decoded limit
// (base64 is ~4/3 of that); the per-message/per-request counts bound token
// cost — like message text, every attached image is resent with the history
// on each agent-loop iteration. The 20 MiB /plan body lane (middleware.go) is
// the effective aggregate byte bound; these caps exist to fail single-message
// abuse and Anthropic-side rejections early with a friendly SSE error.
const (
	planMaxImagesPerMessage = 4
	planMaxImagesPerRequest = 12
	planMaxImageBase64Len   = 6_800_000
)

// planImageMediaTypes is the allowlist Anthropic accepts for image blocks.
var planImageMediaTypes = map[string]bool{
	"image/jpeg": true,
	"image/png":  true,
	"image/gif":  true,
	"image/webp": true,
}

// planDrainCtx is canceled when graceful shutdown begins (startServer's signal
// handler calls planDrainBegin before http.Server.Shutdown). Every in-flight
// /plan request watches it: Shutdown alone cannot end an SSE stream — it waits
// for active connections, and a stream mid-model-call would hold the process
// until the deploy's SIGKILL, exactly the torn-socket truncation the turn_end
// frame exists to prevent. Canceling each request's context instead unwinds
// the model call promptly, and the handler tells the drain apart from a client
// disconnect (planDraining) so it still writes the terminal frame to the live
// socket.
var planDrainCtx, planDrainBegin = context.WithCancel(context.Background())

// planDraining reports whether graceful shutdown has begun. On a drain the
// client's socket is still alive and is owed a turn_end frame; on a client
// disconnect — the other way a request context cancels — there is nobody to
// write to.
func planDraining() bool {
	select {
	case <-planDrainCtx.Done():
		return true
	default:
		return false
	}
}

type PlanRequest struct {
	Messages []PlanChatMessage `json:"messages"`
	// Summary is the compacted context from earlier turns, previously handed to
	// the client via the `compacted` SSE event; it stands in for the messages it
	// folded away and precedes Messages as established context.
	Summary string `json:"summary"`
	ChatID  string `json:"chat_id"`
	// TripID binds the session to an existing saved trip: the agent then refines
	// that trip in place (update_itinerary_section) and can never create a new
	// trip version. Requires an authenticated owner.
	TripID string `json:"trip_id"`
}

type PlanChatMessage struct {
	Role    string      `json:"role"`
	Content string      `json:"content"`
	Images  []PlanImage `json:"images,omitempty"`
	// DisplayLabel is the client's compact stand-in for machine-built seed
	// messages (e.g. the near-me chip's coordinate text). Metadata only: it
	// titles the persisted chat session and round-trips through transcripts so
	// resumed chats re-render the chip, but it is never sent to the model.
	DisplayLabel string `json:"display_label,omitempty"`
}

// PlanImage is one image attached to a user message. Persisted transcripts
// keep MediaType but blank Data (savePlanChatSession), so a resumed client can
// render an "image attached" placeholder without megabytes of base64 living in
// the JSONB transcript; empty-Data images are skipped when building the model
// request.
type PlanImage struct {
	MediaType string `json:"media_type"`
	Data      string `json:"data"` // base64, no data: URI prefix
}

func sendSSE(w http.ResponseWriter, eventType string, data any) {
	payload, _ := json.Marshal(map[string]any{"type": eventType, "data": data})
	fmt.Fprintf(w, "data: %s\n\n", payload)
	w.(http.Flusher).Flush()
}

func planHandler(w http.ResponseWriter, r *http.Request) {
	w.Header().Set("Content-Type", "text/event-stream")
	w.Header().Set("Cache-Control", "no-cache")
	w.Header().Set("Connection", "keep-alive")
	// Tell nginx to never buffer this response, independent of location
	// config — belt and braces with the gateway's dedicated /plan lane.
	w.Header().Set("X-Accel-Buffering", "no")

	if _, ok := w.(http.Flusher); !ok {
		http.Error(w, "streaming not supported", http.StatusInternalServerError)
		return
	}

	// Every stream this handler opens MUST end with one turn_end frame — the
	// terminal event that lets the client tell "the turn ended, and how" from
	// "the connection died". Without it both are just bytes stopping, and the
	// client resolved that by committing whatever partial text had arrived as
	// a finished reply — which the deferred save below then persisted, so the
	// next turn's model read its own half-sentence back as a completed
	// message. Closed stop_reason vocabulary: "end_turn" (the model finished
	// — the only reason a client may commit the streamed text), "error" (an
	// error frame preceded this), "server_restart" (graceful shutdown drained
	// the stream; retry cleanly).
	endTurn := func(stopReason string) {
		sendSSE(w, "turn_end", map[string]string{"stop_reason": stopReason})
	}
	// An error frame always ends the turn, so the terminal frame rides with
	// it. New exit paths must go through this (or endTurn), never a bare
	// sendSSE("error") — a return without a terminal frame reads as a dead
	// socket and makes the client discard a reply the server priced and sent.
	sendError := func(message string) {
		sendSSE(w, "error", map[string]string{"message": message})
		endTurn("error")
	}

	// Overall wall-clock ceiling on the whole request (see planMaxDuration): a
	// stuck stream eventually closes and frees its goroutine + concurrency slot.
	ctx, cancel := context.WithTimeout(r.Context(), planMaxDuration)
	defer cancel()
	r = r.WithContext(ctx)

	// Graceful drain: when shutdown begins, cancel this request's context so a
	// blocked model call unwinds now rather than at the deploy's SIGKILL. The
	// Canceled handling in the loop below tells the drain apart from a client
	// disconnect and writes the terminal frame that lets the client retry.
	stopDrainWatch := context.AfterFunc(planDrainCtx, cancel)
	defer stopDrainWatch()

	// INVARIANT: fully consume the request body BEFORE the first response
	// write or flush. Writing commits the response, and a reverse proxy
	// forwarding the request body unbuffered stops relaying it the moment
	// the upstream responds — a decode after the first flush then reads EOF
	// and every real-network request fails "invalid request body", while
	// loopback dev and buffered test bodies pass (prod incident, 2026-08-12;
	// TestPlanHandlerReadsBodyBeforeFirstWrite). The gateway now buffers
	// /plan request bodies (dockerize/*/nginx), but this ordering must hold
	// on its own; do not move the stream-open flush above this read.
	// io.ReadAll (not json.Decoder, which stops at the first JSON value)
	// drains to EOF; the body is MaxBytesReader-capped at 20 MiB
	// (bodyLimitMiddleware).
	raw, err := io.ReadAll(r.Body)
	if err != nil {
		log.Printf("plan body read: %v (read=%d content_length=%d)", err, len(raw), r.ContentLength)
		sendError("invalid request body")
		return
	}
	var req PlanRequest
	if err := json.Unmarshal(raw, &req); err != nil {
		log.Printf("plan body decode: %v (read=%d content_length=%d)", err, len(raw), r.ContentLength)
		sendError("invalid request body")
		return
	}

	// Priming SSE comment — flushed only after the body is fully consumed
	// (invariant above) but still before any DB work or model calls: commits
	// nginx/Cloudflare to streaming mode and keeps TTFB tight. The Dart
	// client only parses `data: ` lines, so a comment frame is invisible.
	fmt.Fprint(w, ": stream-open\n\n")
	w.(http.Flusher).Flush()

	// Protocol announcement: this server ends every turn with a terminal
	// turn_end frame. The client requires the terminator only after seeing
	// this, so a rolled-back API (sending neither event) degrades to the old
	// commit-on-close behavior instead of erroring on every reply.
	sendSSE(w, "stream_start", map[string]any{"protocol": 2})

	// Cap the conversation before any model call: the whole history is resent
	// on every agent-loop iteration, so these bounds are a hard cost lever.
	if len(req.Messages) > planMaxMessages {
		sendError("This conversation is too long to continue. Please start a new chat to keep planning.")
		return
	}
	totalImages := 0
	for i, m := range req.Messages {
		if utf8.RuneCountInString(m.Content) > planMaxMessageChars {
			sendError("One of the messages is too long for the planner. Please shorten it and try again.")
			return
		}
		if utf8.RuneCountInString(m.DisplayLabel) > planMaxDisplayLabelRunes {
			req.Messages[i].DisplayLabel = truncateRunes(m.DisplayLabel, planMaxDisplayLabelRunes)
		}
		if len(m.Images) > 0 && m.Role != "user" {
			sendError("Images can only be attached to your own messages.")
			return
		}
		if len(m.Images) > planMaxImagesPerMessage {
			sendError("A message can include at most 4 images. Please remove some and try again.")
			return
		}
		totalImages += len(m.Images)
		if totalImages > planMaxImagesPerRequest {
			sendError("This conversation has too many images to continue. Please start a new chat to keep planning.")
			return
		}
		for _, img := range m.Images {
			// Empty Data is the stripped placeholder shape from a resumed
			// transcript — valid on the wire, skipped at conversion time.
			if img.Data != "" && !planImageMediaTypes[img.MediaType] {
				sendError("That image format isn't supported. Please use a JPEG, PNG, GIF, or WebP image.")
				return
			}
			if len(img.Data) > planMaxImageBase64Len {
				sendError("One of the images is too large. Please attach images under 5 MB.")
				return
			}
		}
	}
	if utf8.RuneCountInString(req.Summary) > planMaxMessageChars {
		sendError("This conversation is too long to continue. Please start a new chat to keep planning.")
		return
	}

	// Resolve the caller once: anonymous sessions get no personalization and no
	// preference-writing tool; signed-in sessions get both.
	uid, authed, uerr := userIDFromRequest(r)
	if uerr != nil {
		// A token was presented but the DB was unreachable — don't silently
		// downgrade to anonymous (losing personalization + persistence). Ask
		// the client to retry rather than proceeding half-authenticated.
		sendError("The service is temporarily unavailable. Please try again in a moment.")
		return
	}

	// Anonymous /plan daily cap (abuse_caps.go): the money fix. Signed-in
	// callers are exempt and uncounted (their measure-only free cap in
	// free_cap.go is unchanged); anonymous callers get anonPlanPerDay() free AI
	// planning runs per IP per UTC day, then a friendly SSE error — never a 500.
	if !anonPlanAllowed(authed, clientIP(r), time.Now()) {
		safeGo("recordAnonPlanCap", func() {
			recordEventOpt(nil, "anon_plan_cap_hit", nil, map[string]any{"per_day": anonPlanPerDay()})
		})
		sendError("You've reached today's free planning limit. Sign in to keep planning, or check back tomorrow.")
		return
	}

	apiKey := os.Getenv("ANTHROPIC_API_KEY")
	if apiKey == "" {
		sendError("ANTHROPIC_API_KEY not configured")
		return
	}

	client := newAnthropicClient(apiKey)

	// Snapshot the wire history as the client sent it, BEFORE the compaction
	// block below rewrites req.Messages (or prepends the summary-as-message).
	// Session persistence must store what a live client would resend — never
	// the prepended summary message, which would duplicate context on resume.
	rawMessages, rawSummary := req.Messages, req.Summary

	// Compaction must rewrite req.Messages BEFORE the session below captures
	// req by value (the profile distiller reads session.req.Messages). On
	// threshold, fold the older messages into a summary and hand it back to
	// the client (`compacted`), which resends it as req.Summary instead of the
	// folded messages — so each stretch of history is summarized once. A
	// summarizer failure is never surfaced: the turn proceeds on the full
	// (≤ planMaxMessages) history and compaction retries next turn.
	var planCompacted, planCompactFailed bool
	if len(req.Messages) >= planCompactThreshold {
		sendSSE(w, "compacting", map[string]string{})
		cctx, cancel := context.WithTimeout(ctx, compactTimeout)
		newMsgs, summary, through, err := compactPlanMessages(cctx, client, req.Summary, req.Messages)
		cancel()
		if err != nil {
			log.Printf("plan compact: %v", err)
			planCompactFailed = true
			if strings.TrimSpace(req.Summary) != "" {
				req.Messages = append([]PlanChatMessage{summaryAsMessage(req.Summary)}, req.Messages...)
			}
		} else {
			req.Messages = newMsgs
			req.Summary = summary
			planCompacted = true
			sendSSE(w, "compacted", map[string]any{"summary": summary, "through_index": through})
		}
	} else if strings.TrimSpace(req.Summary) != "" {
		req.Messages = append([]PlanChatMessage{summaryAsMessage(req.Summary)}, req.Messages...)
	}

	// session carries the per-request state the tool dispatchers need
	// (plan_tool_registry.go) and the outcomes read back below: the persisted
	// or refined trip id, and whether the profile distiller already fired.
	session := &planSession{
		ctx:    ctx,
		w:      w,
		req:    req,
		client: client,
		authed: authed,
		uid:    uid,
	}

	// Session-level instrumentation for every caller — anonymous sessions
	// carry a null user id, so total AI spend and the authed/anonymous split
	// are both measurable. Completion carries token usage, tool calls, cache
	// hits and cap state. Deferred so it records however the stream ends.
	var planTokensIn, planTokensOut int64
	var planCacheRead, planCacheWrite int64
	var planToolCalls, planIterations int
	var planCapHit bool
	var planUID *uuid.UUID
	if authed {
		planUID = &uid
	}
	// Also runs the free-cap plan_runs crossing check (free_cap.go) — one
	// count query, entirely off the SSE hot path, skipped when unauthed or
	// degraded.
	safeGo("recordPlanSessionStart", func() { recordPlanSessionStart(planUID, authed) })
	defer func() {
		recordEventOpt(planUID, "plan_session_completed", session.tripID, map[string]any{
			"authenticated":         authed,
			"input_tokens":          planTokensIn,
			"output_tokens":         planTokensOut,
			"tool_calls":            planToolCalls,
			"iterations":            planIterations,
			"max_iterations_hit":    planCapHit,
			"cache_read_tokens":     planCacheRead,
			"cache_creation_tokens": planCacheWrite,
			"compacted":             planCompacted,
			"compaction_failed":     planCompactFailed,
		})
	}()

	// A trip-bound session must verifiably be editable by the caller (owner or
	// editor collaborator) before anything streams; failing closed here
	// guarantees a refine panel can never fall back to the version-creating
	// create_itinerary flow. Collaborator refines patch the owner's trip row
	// in place — the lineage never forks.
	var boundTripID *uuid.UUID
	var boundTripTravelMode *string
	if strings.TrimSpace(req.TripID) != "" {
		tid, err := uuid.Parse(req.TripID)
		if err != nil || !authed {
			sendError("sign in to refine this trip")
			return
		}
		boundTrip, err := store.New(dbPool).GetEditableTripByID(r.Context(), store.GetEditableTripByIDParams{ID: tid, UserID: uid})
		if err != nil {
			sendError("trip not found")
			return
		}
		boundTripID = &tid
		session.boundTripOwnerID = boundTrip.UserID
		boundTripTravelMode = boundTrip.TravelMode
	}
	session.boundTripID = boundTripID

	// Persist the conversation from its very first turn so leaving
	// mid-discussion never loses it (specs/continue-where-you-left-off).
	// Two best-effort writes: an async one started now (off the SSE hot
	// path), so the user's message survives even if the stream dies
	// immediately, and a deferred one — ordered strictly after it — that
	// appends whatever assistant text streamed — the same text the client
	// commits, on both its success and error paths. When compaction ran this
	// turn, the compacted history + new summary are stored instead of the raw
	// snapshot, matching the client's post-`compacted` wire state. Anonymous and
	// degraded sessions stay ephemeral, like anonymous trips.
	//
	// Every authenticated turn is resumable, but the two kinds land in different
	// tables (specs/trip-refine-memory). A freeform plan chat is stored under its
	// client-minted chat id. A trip-bound refine chat is stored under
	// (user, trip) in trip_refine_sessions, where it has NO chat id at all — so
	// it can never be reached by GET /chats/{chatId} or /plan/<chatId> and
	// resumed into the unbound Agent tab, which would silently drop the trip
	// binding. A bound turn therefore deliberately does NOT require req.ChatID:
	// the client mints a throwaway one per panel session and the server has no
	// use for it.
	//
	// saveTurn is nil when nothing is to be persisted; the block below is one
	// ordering implementation with two destinations.
	var saveTurn func(ctx context.Context, summary string, msgs []PlanChatMessage)
	switch {
	case authed && dbPool != nil && boundTripID != nil:
		tid := *boundTripID
		saveTurn = func(ctx context.Context, summary string, msgs []PlanChatMessage) {
			saveTripRefineSession(ctx, uid, tid, summary, msgs)
		}
	case authed && dbPool != nil && strings.TrimSpace(req.ChatID) != "":
		chatID := req.ChatID
		saveTurn = func(ctx context.Context, summary string, msgs []PlanChatMessage) {
			savePlanChatSession(ctx, uid, chatID, summary, msgs)
		}
	}
	persistSession := saveTurn != nil
	var turnText strings.Builder
	// Set on the exit paths where the CLIENT keeps none of the streamed text —
	// a graceful-shutdown drain (turn_end "server_restart" makes it discard)
	// or a client disconnect (stop button, closed tab: the client rolled the
	// turn back or is gone). The deferred save below then stores the
	// transcript WITHOUT the half-streamed assistant text, keeping the stored
	// history identical to what the client kept: a persisted half-reply is
	// what the next turn's model reads back as its own finished message and
	// apologises for. Error-frame paths deliberately still persist the
	// partial — the client commits it there too (plan_provider.dart's error
	// case), and the two sides must agree.
	var discardStreamedText bool
	// Set when an iteration ended in tool calls with text already streamed:
	// the next text delta opens a new paragraph, in the streamed bytes and
	// the persisted transcript alike, so live, resumed, and stale-client
	// renderings all agree. The client keeps a mirror of this rule
	// (plan_provider.dart) that sees the emitted newline and doesn't double
	// it, and still covers itself against older servers.
	turnNeedsSeparator := false
	if persistSession {
		persistMsgs, persistSummary := rawMessages, rawSummary
		if planCompacted {
			// compactPlanMessages returns [summary-as-message, ...kept tail];
			// the client's post-`compacted` wire state is the tail alone, with
			// the summary carried separately — store it the same way.
			persistMsgs, persistSummary = req.Messages[1:], req.Summary
		}
		// The start-of-turn save runs off the hot path: a whole-transcript
		// JSONB upsert before the model call would delay time-to-first-token.
		// It gets its own background context — a canceled stream (client
		// abort, timeout) must not cancel this write, because the user's
		// message surviving a dead stream is the entire point of it.
		//
		// Ordering contract (what a consumer observes after the turn): the
		// deferred end-of-turn save below awaits startSaved before writing, so
		// the two upserts always land start → final and the stored row after
		// the handler returns is the final assistant-text-bearing transcript —
		// a slow start upsert can never overwrite it. startSaved closes even
		// if the save panics (the deferred close unwinds before safeGo's
		// recover), so the final save can never deadlock; its wait is bounded
		// by the start save's own 5 s timeout.
		startSaved := make(chan struct{})
		safeGo("savePlanChatSessionStart", func() {
			defer close(startSaved)
			sctx, cancel := context.WithTimeout(context.Background(), 5*time.Second)
			defer cancel()
			saveTurn(sctx, persistSummary, persistMsgs)
		})
		defer func() {
			msgs := persistMsgs
			if t := turnText.String(); t != "" && !discardStreamedText {
				msgs = append(append([]PlanChatMessage{}, persistMsgs...),
					PlanChatMessage{Role: "assistant", Content: t})
			}
			<-startSaved // start → final ordering; see contract above
			// The request context is gone once the handler returns.
			dctx, cancel := context.WithTimeout(context.Background(), 5*time.Second)
			defer cancel()
			saveTurn(dctx, persistSummary, msgs)
		}()
	}

	// The tool table (plan_tool_registry.go) is the single source of truth for
	// what the agent can do: the tools slice sent to the API is generated from
	// it in registry order (order-stable — the tools array is part of the
	// prompt-cache prefix that the system-prompt cache breakpoint covers), and
	// tool_use blocks dispatch through it below. Trip-bound sessions get the
	// in-place section tool instead of create_itinerary, so a refinement can
	// never spawn a new trip version; personalization tools are signed-in only.
	tools := planSessionTools(session)

	var messages []anthropic.MessageParam
	for _, m := range req.Messages {
		if m.Role == "user" {
			var blocks []anthropic.ContentBlockParamUnion
			for _, img := range m.Images {
				if img.Data == "" {
					continue // stripped placeholder from a resumed transcript
				}
				blocks = append(blocks, anthropic.NewImageBlockBase64(img.MediaType, img.Data))
			}
			// Image-only messages carry no text block. A resumed image-only
			// message whose pixels were stripped would otherwise be empty —
			// the API rejects both empty content arrays and empty text
			// blocks — so it gets a marker keeping the transcript coherent.
			text := m.Content
			if strings.TrimSpace(text) == "" && len(blocks) == 0 {
				text = "[attached an image that is no longer available]"
			}
			if strings.TrimSpace(text) != "" {
				blocks = append(blocks, anthropic.NewTextBlock(text))
			}
			messages = append(messages, anthropic.NewUserMessage(blocks...))
		} else {
			messages = append(messages, anthropic.NewAssistantMessage(anthropic.NewTextBlock(m.Content)))
		}
	}

	today := time.Now()
	basePrompt := "You are Ferdinand, the Anemos travel planner — an expert travel agent and the traveler's partner in circumnavigating the globe. Don't introduce yourself or state your name — just help. If the traveler asks who you are, tell them. Today's date is " + today.Format("Monday, January 2, 2006") + " (" + today.Format("2006-01-02") + "). When a traveler gives a date without a year, assume the soonest upcoming occurrence on or after today — never a past year. Use dates in YYYY-MM-DD form when calling tools. A session opened on a trip that is already saved is past what follows — that trip has a shape, so go straight to what the traveler asked for. Otherwise plan in TWO passes and never skip the first. PASS 1 — AGREE THE SHAPE. Your first substantive reply about a new trip is the trip's SHAPE and nothing else: the cities in order, how many nights in each, the arrival and departure dates those nights imply, how they travel between them, and one line on why that order and that split. Do NOT research places in that turn — no search_local_recommendations, no search_places, no search_events, no find_parking — and do NOT call create_itinerary: nothing is saved until the traveler says yes. Route-level lookups that DECIDE the shape are still fine and often needed there (check_flight_connectivity before you name a city they didn't ask for, search_flights, suggest_ferries, get_weather), and set_travel_mode and set_trip_origin still fire the moment the traveler says something that sets them. End the turn by asking whether the shape works, and call suggest_replies with the changes they are most likely to want ('Fewer cities, more days each', 'More time in Rome', 'Swap the order', 'Looks good — build it'). This holds for a ONE-city trip too: there the shape is the dates and the length, so say it back and wait. If their own message already fixes every city, night and date, say the shape back in one line and still ask them to confirm — their yes is what you need, not the question. If something a shape needs is missing — how long they have, roughly when, who is going, where they set out from — then asking for THAT is pass 1; never invent it. PASS 2 — BUILD THE SPINE. Once they agree, call create_itinerary with the shape and only the shape: every city with its dates, ONE place on the day they ARRIVE in it, ONE easy place on the morning they move on when the departure leaves room for one, and the days in between left EMPTY on purpose. A three-city trip is about five places, not thirty — two per city except the LAST city, which gets only its arrival, because the day you move on from the last city is the journey home. That count is pacing advice, not a data rule: a city's dates hang on ARRIVALS — its own first day and the next city's first day — never on a place holding its last day, so an empty travel day renders correctly (the city still runs to the next city's arrival), an early departure such as a 7am flight is exactly when to leave the travel day empty, and you must NEVER add a place to an itinerary just to hold a date. Two places a city is the target, not a shortfall: do not pad the middle days to make the plan look finished. An anchor is one real, searched, named place that gives its day a reason to exist — on the arrival day something near where they are staying that still works when they are tired and carrying bags; on a travel morning something easy and skippable, near the lodging or on the way out of town. Give every place a day number and the city it is in. Then say in your reply which days you left open, and offer to fill in any city whenever they are ready. PASS 3 — FILL ONE CITY AT A TIME, AND ONLY WHEN ASKED. Plan the city they name and leave every other city exactly as it is; never expand the whole trip at once, and never re-plan a city they didn't ask about. In a conversation with no saved trip open, create_itinerary is your only writer and each call saves a NEW VERSION of the entire trip — so send the COMPLETE itinerary again: every city's existing places with their existing day numbers, plus the new ones, and the same start_date and end_date. A call carrying only the city you just filled would replace the whole trip with that one city. If the traveler asks up front for the full day-by-day — 'plan every day for me', 'just build the whole thing' — agree the shape first all the same, then fill it in completely in one go. Help users plan trips by searching for specific places and attractions. For each city, ALWAYS call search_local_recommendations FIRST — these are hand-curated picks from real locals, the legit info you can't get by googling. Whenever you are choosing places for a city — its two spine anchors, or a city you are filling in detail — ALWAYS call search_local_recommendations for that city FIRST — these are hand-curated picks from real locals, the legit info you can't get by googling. Prefer them over generic results, build the itinerary around them where they fit the traveler, and cite the local by name in your reply (e.g. 'Ana, a Lisbon chef, swears by…'). When a local pick becomes an itinerary place, carry its id into local_recommendation_id and its source_name into local_source_name. Then use search_places to fill gaps and find any other real locations with coordinates. Search for individual places (e.g. 'Louvre Museum Paris') rather than broad queries. Include a mix of activities/attractions and dining (restaurants), guided by the traveler's interests, budget, and pace. When you call create_itinerary, tag each location with category ('attraction' or 'restaurant'), a time_of_day ('morning', 'afternoon', or 'evening'), and a day (the 1-based trip day it falls on, increasing chronologically across the whole trip) so each day reads as a sensible schedule. The trip's LAST day is the day the traveler journeys home, so unless you know when they leave, put NOTHING on it — not one place, not even a light one — and say so in your reply: that you've left it open for the journey home and will fill it in once they tell you what time they travel. When you DO know the departure time, it decides how much of the day is theirs: an early or midday departure still leaves nothing, a late-afternoon one leaves the morning, an evening one leaves the morning and afternoon. Never schedule past that window. When it is only a part of the day, hold it to one easy place near where they're staying that they could skip — no timed tickets, tours or reservations; a whole open day before a late flight can be planned normally, just keep the last stop near the lodging or on the way to the airport, and remember they are carrying luggage. On a multi-city trip each city's last day is the day they move on, so it gets ONE easy nearby place instead of a full schedule — or nothing at all when the departure is early or the traveler wants it clear: an empty travel day is rendered correctly (a city's dates come from arrivals, so an empty last day never hands its nights to the next city), and you must never invent a place for it. Trips planned before this rule may carry a place that exists only to hold a date — an airport coffee stop on a travel morning; nothing depends on such a place anymore, so when a traveler questions one, offer to remove it. Fill the real days first: never leave a day in the middle of a stay empty while a travel day carries a full schedule — one anchor place on a travel day beside deliberately empty middle days is the spine, and is correct; a travel day carrying a full SCHEDULE while a day in the middle of the stay sits empty is the mistake this rule is about. At the other end of the trip, never state a date the traveler leaves home unless you actually know it: a long-haul outbound flight can depart the CALENDAR DAY BEFORE it lands, so the trip's first day is the day they ARRIVE, not the day they fly. When you do know it — you found the flight, or they told you — record BOTH dates with add_transport_segment's depart_date and arrive_date, and leave the trip's start date alone: it stays the arrival day. Only include specific named places — never emit a location whose name is just the city itself as a placeholder; a day with no planned activities should simply have no locations for that day. When you call create_itinerary, pass start_date AND end_date whenever the traveler has given or agreed to travel dates, with day 1 being the start date — the itinerary's last day no longer tells the trip when it ends, because the day they travel home may carry nothing. Call create_itinerary only once the traveler has AGREED to the shape you proposed — their yes is what authorizes it, never how many places you have found; if you cannot point to the message where they agreed, ask instead of building. Pass start_date AND end_date EVERY time, with day 1 being the start date: the shape they agreed to gave you both, and the itinerary's own days no longer tell the trip when it ends, because its middle days are empty by design and the day they travel home carries nothing. If the traveler changes the travel dates AFTER an itinerary has been saved this conversation, call set_trip_dates with the new start date — do not create a new itinerary just for a date change. Three tools change WHEN things happen; keep them distinct. set_trip_dates moves the WHOLE trip by the same delta. set_leg_dates moves ONE city while the others hold — 'make LA Sep 24 to 27': its start_date moves that city's arrival (itinerary days, stay and connecting transport together; when the previous city has a booked stay, that stay's check-out extends to meet the later arrival, while an item-dated neighbour needs no edit at all — its end follows the new arrival by itself). shift_days_from moves one city AND everything after it together: 'give Prague another night' is ONE shift_days_from call with the city after Prague and days=1 — never a chain of set_leg_dates calls city by city, which robs each city to pay the next. A city's departure day is the NEXT city's arrival, so 'leave LA a day later' means moving the next city's start_date (or shift_days_from when the rest of the trip should ride along). After any of these, relay every change and every warning the result reports — a zero-night city, a place left outside its city's dates, an overlap — and offer the fix the result names. The first city's arrival is the trip's start date — to change when the trip begins, use set_trip_dates, not set_leg_dates. Pay attention to how the traveler is getting around: the moment they state or imply a travel mode — 'we're driving', 'road trip', 'we'll have a car', 'taking the train' — call set_travel_mode with it. On a car, train, or bus trip do NOT call search_flights or check_flight_connectivity and never suggest flights; plan a route with sensible daily driving or rail legs instead, and when a saved trip is open add legs with add_transport_segment in that mode. When the traveler will have a car — driving travel mode, or they mention renting or driving — and the plan includes a beach, call find_parking with the beach's name (and its coordinates if you already have them from a search) to surface free or cheap parking; present flagged spots as 'listed as free — verify locally', never as guaranteed. If the travel mode is ambiguous and it would change the plan, ask. Between cities, decide HOW they travel before you plan the leg, and do not reach for a flight by default: on a short hop where the train or the road wins door-to-door — Rome to Florence, Amsterdam to Brussels, Tokyo to Kyoto, roughly anything under about four hours by rail — plan the train and do NOT call search_flights for that leg. Use suggest_transport with mode 'ground' to hand them a Rome2Rio route (trains, buses and driving), suggest_ferries for a sea crossing, and search_flights only for the legs that really are flights. The app derives each leg's mode itself and echoes it back to you after every itinerary write; when one of those legs is wrong for how they should actually travel — a sea crossing, an overnight train, a stretch they are driving — call set_leg_transport_mode for that leg rather than describing a different mode in your reply. Some itinerary cities are too small to have an airport; the app detects these and labels their flight legs with the nearest real one — the trip state shows them as 'X flies via Y (CODE)'. When the traveler says a city's airport is elsewhere or that the picked one is wrong — 'the airport is in Salzburg', 'fly into Vienna for that stop' — call set_leg_gateway with the city and the airport: it relabels the flight legs and their booking links in place, so never hand-edit titles for this and never tell the traveler the legs cannot be changed. When you search flights for such a leg, use the gateway airport's code, not the small city's name. Where a trip STARTS and ENDS is a property of the trip, not of the traveler: the moment they say where they set out from or change it — 'we're flying out of ALB instead', 'we leave from Albany but come home into Newark', 'we're driving up from Lake George' — call set_trip_origin with what they said, passing return_airport only when the trip comes home into a DIFFERENT airport, and place instead of airport when they set out from somewhere with no airport. It rewrites the trip's existing departure and return legs in place and keeps their booked state, so never add a second checklist item for a leg the trip already has. Do not call save_preferences for this: the saved home airport is where this traveler usually flies from, and only a traveler who says they have MOVED changes it. Otherwise, you can use search_flights to find real flight options — ask for the traveler's departure city/airport and dates if you don't know them, and pick optimize_for from their budget (budget→cost, luxury→time, otherwise balanced). Search one-way by default — omit return_date unless the traveler has asked for or agreed to a return flight. Whenever you quote flight prices, state whether they are one-way or round-trip totals and how many travelers they cover — never present a party or round-trip total as a per-person one-way fare. Summarize the top 2-3 options in your own words and help them choose — do not tell the traveler to look at cards or lists in the chat. Before recommending a destination or stopover the traveler didn't ask for by name, call check_flight_connectivity with your 2-5 candidates (and the onward destination for stopovers) — prefer well-connected options, and if you still suggest a poorly connected one, say so plainly with the typical price and total travel time. Also run the check when the traveler proposes a stopover themselves, so you can warn them early if the route is long or expensive. Never present a stopover as convenient without having checked it. When the traveler needs somewhere to stay, call search_hotels with the city and their check-in/check-out dates — it returns real properties with live nightly rates, ratings and photos. Quote its prices as per-night figures in the currency it states, and when it reports that prices were not checked, never quote, estimate, or imply a price for those results — ask for their dates instead. suggest_stays is only for handing the traveler a browse link when they want to shop Airbnb or Booking.com themselves. For travel between Greek islands, use suggest_ferries (ferries are the primary way to island-hop); note that in Greece search_events returns curated source links rather than ticketed listings. Use get_weather when weather changes the advice — packing, outdoor days, beach or ski viability, seasonal closures; for far-off dates it returns last year's weather as a seasonal guide, so present it as 'typically', never as a forecast. For signed-in travelers: when they reference a trip you've already planned together, call get_trip to read what's saved instead of asking them to repeat it; and when you give time-sensitive booking advice about a saved trip (book the ferry, reserve that restaurant), call add_booking_todo so it lands on their checklist instead of getting lost in chat; and when the plan changes so a checklist item is stale or wrong (different destination, moved dates, a booking that no longer applies), call update_booking_todo or remove_booking_todo to fix the checklist yourself — never tell the traveler to clean it up manually; get_trip shows each item's todo_id, and items marked 'auto' track the itinerary automatically and can't be edited directly — change what they track instead (set_trip_origin for the departure and return legs, set_trip_dates or set_leg_dates for their dates, set_travel_mode for how they travel), and NEVER duplicate an auto item with add_booking_todo or tell the traveler to ignore one. A saved trip's DESCRIPTION — the short overview shown under its title — is yours to keep true as well: when the traveler asks for different wording, call set_trip_description with reason 'traveler_asked', and when a change you just made has left the description describing a trip that no longer exists (a city added or dropped, the dates moved), call it with reason 'trip_changed'. get_trip and every update_itinerary_section result show you the current description and who wrote it: one the TRAVELER wrote is theirs, so offer to rewrite it instead of replacing it, and never restate a description that still fits. After any reply that ends by asking the traveler a question or offering a choice, call suggest_replies with 2-4 short tappable answers (each under 60 characters, phrased in the traveler's own voice, in the same language as your reply — e.g. 'Mid-range budget', 'More food, fewer museums'). Call it at most once per reply, only AFTER your question text is complete, and end your turn right after its result without repeating the options in text. Do NOT call suggest_replies in a turn where you call create_itinerary, update_itinerary_section, set_trip_dates, set_leg_dates, or shift_days_from, and not when your reply asks the traveler nothing. When the traveler shares their current GPS coordinates or asks what's near them right now, call search_nearby with those exact coordinates instead of search_places, lead with the closest good options and rough distances, and once the result addresses reveal the city, also call search_local_recommendations for it. Never tell the traveler a change to their saved trip was made unless a tool call in THIS turn succeeded in making it — if the tool errored or wasn't available, say plainly what you couldn't do. Be conversational and helpful — ask clarifying questions if needed before searching. Format replies with light markdown — short paragraphs, **bold** for place names, hyphen lists — no headings or tables."

	// Fold the signed-in traveler's saved preferences into the system prompt.
	// The profile-keeping instruction applies even before any row exists, so
	// the first durable fact a traveler reveals gets captured.
	systemPrompt := basePrompt
	if authed {
		if prefs, err := store.New(dbPool).GetPreferences(ctx, uid); err == nil {
			systemPrompt = personalizedSystemPrompt(basePrompt, &prefs)
			// The saved bag tier is ALSO carried on the session: search_flights
			// resolves it server-side (specs/traveler-baggage) rather than
			// hoping the model relays it out of the prompt.
			session.bagPref = prefs.Baggage
		}
		systemPrompt += profileNotesInstruction
	}
	if boundTripID != nil {
		systemPrompt += "\n\nYou are refining an existing saved trip in place. This conversation is saved and may be resumed days later, so its earlier messages describe the itinerary AS IT WAS, not as it is — the traveler or a co-planner may have changed the trip since, and an earlier message may have been superseded by a later one in this same conversation. Before you apply ANY change with update_itinerary_section, build the complete list of places from the CURRENT TRIP STATE block in your context — or, when a tool call in THIS turn has already changed the trip, from that tool's result — never from an earlier message. Earlier messages still tell you which section the traveler is working on. Apply changes by calling update_itinerary_section with the targeted scope and the COMPLETE updated list of places for that section — include unchanged places with their existing coordinates, city, day, time_of_day and category tags so they aren't lost. Use search_places to find real coordinates for any new place before adding it. Only change the section the traveler asked about unless they broaden the request. Replacing one city with a DIFFERENT city — 'replace Copenhagen with Belgrade', 'let's do Porto instead of Seville' — is replace_leg, never a whole-trip rewrite. Call replace_leg with the old city, the new city, and the new city's places in visit order, and send NO day numbers: it keeps the trip days the old city occupied, so the swapped city inherits its dates and every other city's dates and night counts are left exactly as they are. It also removes the old city's stay, its transport and its checklist rows and names each one in its result — relay that to the traveler and offer to rebook. It changes only WHICH city it is, not when: if they also want different dates or a different number of nights there, follow up in the same turn with set_leg_dates (or shift_days_from, when the cities after it should move too). A REORDER is a different edit — the same cities in a new order, e.g. Rome before Florence instead of after — and that, along with shifting one stop from one city to another, is a whole-trip change: call update_itinerary_section with scope 'trip' and the complete itinerary in the new order, never scope 'city' or 'day' with another section's places mixed in. A reorder genuinely moves which dates each city occupies, so re-author the day numbers deliberately and then check the 'page now renders' ranges the result reports against what the traveler asked for. A section rewrite replaces its section in place and cannot move places across sections, so mixing them in would duplicate those places rather than move them, and the call will be rejected. When they ask you to fill in a city whose middle days are empty, that is a per-city job: call update_itinerary_section with scope 'city' and that city's COMPLETE new list, keeping the places already sitting on its arrival and travel days, and keep the city's FIRST item day exactly where it is — that day is the city's arrival, which is what places the city on the calendar (and what the previous city's end follows). Its LAST day is not load-bearing: filling it, emptying it, or moving a place off it changes no city's dates. A day with nothing on it yet is not a section of its own, so scope 'day' cannot fill one; use scope 'city'. Fill the one city they asked about and leave the other cities' empty days alone until they ask. The traveler may also ask questions about the trip without wanting changes — answer those directly from the CURRENT TRIP STATE block and your search tools, without announcing any need to fetch, pull, or look up the trip; only call update_itinerary_section when they explicitly ask for a modification. If the traveler changes WHEN the trip happens — 'shift everything a week later', 'we actually start June 12' — call set_trip_dates with the new start date (and end date if the length changes): it moves the trip and every dated stay, transport leg, and booking to-do together. If only ONE city's dates change, call set_leg_dates for that city instead — its start_date moves that city's arrival (days, stay and connecting transport; a booked previous stay's check-out extends to meet a later arrival, and the result says so), and everything its result states comes from the page — relay every range and warning and offer the fix the result names. If a city should get longer or shorter and the rest of the trip should move with it, that is ONE shift_days_from call — everything from the named city's arrival onward moves, and the city before it gains or loses the nights — never a chain of set_leg_dates calls city by city. A change to when the FIRST city begins is a change to the trip's start — use set_trip_dates. Never rebuild sections with update_itinerary_section just to change dates — its day numbers are positional (a city's dates hang on ARRIVALS: the page runs each leg from its own first item day to the next city's first item day), so recomputing day numbers will not produce the calendar dates you intend and can undo earlier date moves. To change WHEN anything happens, use set_trip_dates, set_leg_dates, or shift_days_from with calendar dates, and always verify the 'page now renders' ranges a tool result reports against what the traveler asked for before replying."
		if boundTripTravelMode != nil && *boundTripTravelMode != "" {
			systemPrompt += "\n\nThis trip's travel mode is " + *boundTripTravelMode + "; keep new transport suggestions in that mode."
		}
	}
	// Response language (specs/i18n-spanish). Appended ONLY for non-English
	// locales, so an English request's prompt is byte-for-byte what it was
	// before this feature existed — see TestSystemPromptEnglishUnchanged.
	//
	// This is deliberately NOT a save_preferences field: plan_tool_registry.go
	// is part of the prompt-cache prefix and must stay byte-stable, and the
	// agent must not be able to overwrite the traveler's language. Spanish
	// conversations simply get their own cache line, which caches normally
	// across turns because the locale is constant within a conversation.
	systemPrompt += responseLanguageInstruction(requestLocale(ctx))

	// For a conversation bound to a saved trip — the dock on the trip page —
	// read the trip fresh and put it IN CONTEXT for the whole turn, as a
	// second system block. It reuses runGetTripTool's renderer byte-for-byte,
	// so the block says exactly what a get_trip call would say — one render
	// truth. This exists because every other itinerary source the model has
	// is a frozen copy: the seed message describes the trip as it was when
	// the chat began, and the compaction summary replays "the agreed trip
	// SHAPE" as established context — which is how a question about a city
	// added after those copies froze ("the plan for Prague?") drew a
	// confident "there's no Prague in your trip". The old guard (call
	// get_trip first) covered only writes, and made the model narrate "let
	// me pull your trip" on reads. Fetched once per turn: iterations share
	// bytes, so within-turn prompt caching is untouched, and the
	// instructions block keeps its own breakpoint below, so a trip change
	// between turns re-reads only this block and the messages. A tool that
	// changes the trip mid-turn outranks this block via its own result, and
	// the preamble says so. On a read failure the block is simply absent —
	// exactly the pre-feature context — and get_trip remains available.
	var tripStateBlock string
	if authed && boundTripID != nil && dbPool != nil {
		if rendered, failed := runGetTripTool(ctx, authed, uid, boundTripID, json.RawMessage(`{}`)); !failed {
			tripStateBlock = "CURRENT TRIP STATE — read fresh from the database for this turn. This is the trip exactly as the traveler's trip page renders it right now, and it SUPERSEDES anything earlier messages or the conversation summary claim about the itinerary: cities, dates, places, stays, transport, bookings. Answer questions about the trip from this block directly. Do not call get_trip to read THIS trip, and never tell the traveler you are fetching, pulling, or looking up their trip — you already have it (get_trip remains how you read their OTHER saved trips). When a tool call in THIS turn changes the trip, that tool's result is newer than this block — trust the result for what changed.\n\n" + rendered
		}
	}
	systemBlocks := []anthropic.TextBlockParam{{
		Text:         systemPrompt,
		CacheControl: anthropic.NewCacheControlEphemeralParam(),
	}}
	if tripStateBlock != "" {
		// After the cached instructions block, so a between-turns trip change
		// invalidates the cache from here on, never the instructions.
		systemBlocks = append(systemBlocks, anthropic.TextBlockParam{Text: tripStateBlock})
	}

	// prevCacheMarker tracks the conversation cache breakpoint set on the
	// newest tool-results message; it must be cleared before setting the next
	// one (the API allows at most 4 breakpoints per request).
	var prevCacheMarker *anthropic.CacheControlEphemeralParam

	for {
		planIterations++
		if planIterations > planMaxIterations {
			planCapHit = true
			sendError("This planning session hit its step limit. Send another message to continue from where we left off.")
			return
		}

		params := anthropic.MessageNewParams{
			Model:     aiModel(),
			MaxTokens: 8192,
			System:    systemBlocks,
			Tools:     tools,
			Messages:  messages,
		}

		// The model is (re)entering a thinking window: nothing will hit the
		// wire until its first token, which on later iterations sits behind a
		// full history re-read. The client shows a typing indicator until the
		// next event of any other type arrives (specs/chat-working-indicator).
		// Emitting before every call also replaces a stale "summarizing" chip
		// when compaction failed without sending `compacted`.
		sendSSE(w, "thinking", map[string]string{})

		callCtx, cancelCall := context.WithTimeout(ctx, planModelCallTimeout)
		stream := client.Messages.NewStreaming(callCtx, params)
		resp := anthropic.Message{}
		// Tool calls announced from content_block_start, keyed by block index,
		// so the execution loop below doesn't emit a second `tool_call` (the
		// client counts chips per event; a duplicate would leave one stuck).
		announced := map[int64]bool{}

		for stream.Next() {
			event := stream.Current()
			resp.Accumulate(event)

			if ev, ok := event.AsAny().(anthropic.ContentBlockStartEvent); ok {
				// Announce the tool the moment its block starts streaming:
				// large inputs (a full create_itinerary) take tens of seconds
				// to generate, and this is the only signal during that window.
				// Registry-gated so an unknown tool never shows a chip that no
				// tool_result would clear.
				if block, ok := ev.ContentBlock.AsAny().(anthropic.ToolUseBlock); ok && planToolByName[block.Name] != nil {
					sendSSE(w, "tool_call", map[string]string{"name": block.Name})
					announced[ev.Index] = true
				}
			}
			if ev, ok := event.AsAny().(anthropic.ContentBlockDeltaEvent); ok {
				if delta, ok := ev.Delta.AsAny().(anthropic.TextDelta); ok {
					text := delta.Text
					if text != "" && turnNeedsSeparator {
						// Skip only when a newline already sits on either
						// side of the boundary; a plain space still gets
						// the paragraph break.
						if !strings.HasPrefix(text, "\n") && !strings.HasSuffix(turnText.String(), "\n") {
							text = "\n\n" + text
						}
						turnNeedsSeparator = false
					}
					turnText.WriteString(text)
					sendSSE(w, "text_delta", map[string]string{"text": text})
				}
			}
		}
		streamErr := stream.Err()
		cancelCall() // the deadline only needs to cover the streaming call above
		// The request context cancels mid-call in exactly two ways, told apart
		// because only one leaves a live socket to write to. A graceful-
		// shutdown drain (planDraining) owes the client the terminal frame so
		// it discards the half-reply and offers a clean retry. A client gone
		// (stop button / closed tab) was a deliberate teardown — not an AI
		// failure: no health record, no ERROR log (Sentry tee), no SSE to a
		// dead socket. Either way the client keeps none of the streamed text,
		// so the deferred save must not either. Canceled-only, on the request
		// ctx: planModelCallTimeout and planMaxDuration expiries surface as
		// DeadlineExceeded (here or on callCtx) and keep recording as before.
		if errors.Is(ctx.Err(), context.Canceled) {
			discardStreamedText = true
			if planDraining() {
				endTurn("server_restart")
			}
			return
		}
		// Exactly one health record per model call (ai_health.go); nil records
		// a success, so the first good call after an outage flips recovery.
		aiClass, aiReason := recordAIResult(streamErr)
		if streamErr != nil {
			// Redact: the raw Anthropic/transport error can carry internal
			// detail and is unhelpful to the user. Log it server-side (tees to
			// Sentry via slog) and send a generic, friendly message — honest
			// about fatal (billing/auth) failures, which "try again in a
			// moment" would misrepresent.
			ctxLog(ctx).Error("plan: anthropic stream error",
				"error", streamErr, "class", string(aiClass), "reason", aiReason)
			msg := "The planner hit a problem reaching the AI service. Please try again in a moment."
			if aiClass == aiClassFatal {
				msg = "The AI planning service is temporarily unavailable. Please try again later."
			}
			sendError(msg)
			return
		}
		planTokensIn += resp.Usage.InputTokens
		planTokensOut += resp.Usage.OutputTokens
		planCacheRead += resp.Usage.CacheReadInputTokens
		planCacheWrite += resp.Usage.CacheCreationInputTokens

		// A max_tokens stop mid-tool-call means truncated tool input JSON —
		// previously this failed silently and produced an empty itinerary.
		// Surface it instead of continuing with garbage.
		if resp.StopReason == anthropic.StopReasonMaxTokens {
			sendError("The response was cut off before it finished. Try asking for a shorter plan or fewer places at once.")
			return
		}
		if resp.StopReason != anthropic.StopReasonToolUse {
			break
		}
		if turnText.Len() > 0 {
			turnNeedsSeparator = true
		}

		messages = append(messages, resp.ToParam())
		var toolResults []anthropic.ContentBlockParamUnion

		for i, block := range resp.Content {
			variant, ok := block.AsAny().(anthropic.ToolUseBlock)
			if !ok {
				continue
			}
			planToolCalls++

			entry := planToolByName[variant.Name]
			if entry == nil {
				// Matches the old switch's no-case fallthrough: an unknown tool
				// name gets no result block (the API only calls defined tools).
				// No tool_call either — nothing would ever clear its chip.
				continue
			}
			if !announced[int64(i)] {
				sendSSE(w, "tool_call", map[string]string{"name": variant.Name})
			}
			result, isErr := entry.run(session, variant.Input)
			if !entry.noResultEvent {
				sendSSE(w, "tool_result", map[string]string{"name": variant.Name})
			}
			toolResults = append(toolResults, anthropic.NewToolResultBlock(variant.ID, result, isErr))
		}

		messages = append(messages, anthropic.NewUserMessage(toolResults...))

		// Move the conversation cache breakpoint onto the newest tool-results
		// message so each iteration re-reads the growing history from cache
		// instead of paying full input cost for it. The system-prompt
		// breakpoint (above) covers tools + system; this one covers the turn
		// transcript.
		if prevCacheMarker != nil {
			*prevCacheMarker = anthropic.CacheControlEphemeralParam{}
			prevCacheMarker = nil
		}
		if blocks := messages[len(messages)-1].Content; len(blocks) > 0 {
			if cc := blocks[len(blocks)-1].GetCacheControl(); cc != nil {
				*cc = anthropic.NewCacheControlEphemeralParam()
				prevCacheMarker = cc
			}
		}

		select {
		case <-ctx.Done():
			switch {
			case errors.Is(ctx.Err(), context.DeadlineExceeded):
				// planMaxDuration expired between model calls. The client is
				// still connected — say so rather than just closing the pipe.
				sendError("This planning session ran too long and was stopped. Send another message to continue from where we left off.")
			case planDraining():
				discardStreamedText = true
				endTurn("server_restart")
			default:
				// Client gone between iterations — dead socket, nothing to say.
				discardStreamedText = true
			}
			return
		default:
		}
	}

	// The model finished the turn (the loop's one success exit): the terminal
	// frame with stop_reason "end_turn" is what authorizes the client to
	// commit the streamed text as a finished reply rather than guessing from
	// the connection closing.
	endTurn("end_turn")
}

// resolveIATA turns a city name or IATA code into an IATA code for flight
// search. A 3-letter alphabetic input is treated as a code; anything else is
// looked up via Duffel, preferring a city (metropolitan) code so the search
// spans all of a city's airports. Returns "" when nothing resolves.
func resolveIATA(ctx context.Context, s string) string {
	s = strings.TrimSpace(s)
	if len(s) == 3 && isAlpha(s) {
		return strings.ToUpper(s)
	}
	results, err := duffelService.SearchAirports(ctx, s)
	if err != nil || len(results) == 0 {
		return ""
	}
	for _, a := range results {
		if a.SubType == "city" && a.IataCode != "" {
			return a.IataCode
		}
	}
	return results[0].IataCode
}

func isAlpha(s string) bool {
	for _, r := range s {
		if !((r >= 'a' && r <= 'z') || (r >= 'A' && r <= 'Z')) {
			return false
		}
	}
	return s != ""
}

// parseOfferTime reads a provider timestamp. Both providers hand back the
// airport's LOCAL wall time with no zone ("2026-08-25T06:40:00" — Duffel's
// departing_at, and serpapiTimeToISO's normalization of Google Flights'
// "2026-08-25 06:40"), so this deliberately parses zone-free first and only
// falls back to RFC3339. ok=false on anything else, which is what keeps a
// timeless offer's summary line byte-identical to its pre-times form.
func parseOfferTime(ts string) (time.Time, bool) {
	for _, layout := range []string{"2006-01-02T15:04:05", time.RFC3339} {
		if t, err := time.Parse(layout, strings.TrimSpace(ts)); err == nil {
			return t, true
		}
	}
	return time.Time{}, false
}

// flightWindow renders one slice's departure→arrival as local clock times
// ("06:40→11:15", suffixed "+1" when it lands on a later calendar day). The
// departure alone when the arrival is missing; empty when the departure is.
func flightWindow(departTS, arriveTS string) string {
	dep, ok := parseOfferTime(departTS)
	if !ok {
		return ""
	}
	arr, ok := parseOfferTime(arriveTS)
	if !ok {
		return dep.Format("15:04")
	}
	w := dep.Format("15:04") + "→" + arr.Format("15:04")
	depDay := time.Date(dep.Year(), dep.Month(), dep.Day(), 0, 0, 0, 0, time.UTC)
	arrDay := time.Date(arr.Year(), arr.Month(), arr.Day(), 0, 0, 0, 0, time.UTC)
	if days := int(arrDay.Sub(depDay).Hours() / 24); days > 0 {
		w += fmt.Sprintf("+%d", days)
	}
	return w
}

// summarizeOffers builds a compact text summary of ranked offers for the model,
// so it can describe and compare them without re-sending the full payload (the
// UI already received it via the "flights" event, shown as a count-only summary
// chip — no prices, so the model's prose is the traveler's only record).
//
// The header states the price semantics explicitly — trip type, dates, and
// party size — because both providers return totals for the WHOLE party, and a
// round-trip search returns round-trip totals (SerpApi type=1 phase-1
// semantics): an unlabeled number reads as a per-person one-way fare and
// misquotes the trip by 2x or more.
//
// Clock times are here because the model plans the traveler's FIRST and LAST
// day around them: a 06:00 flight home leaves nothing to do that day and a
// 22:00 one leaves most of it, and without times those two offers read
// identically (same price, same stops, same duration). The offers have carried
// DepartTime/ArriveTime all along — only this summary withheld them.
func summarizeOffers(req FlightSearchRequest, offers []FlightOffer) string {
	travelers := req.Adults + len(req.ChildAges)
	if travelers < 1 {
		travelers = 1
	}
	travelerPhrase := "1 traveler"
	partyPhrase := "1 traveler"
	if travelers > 1 {
		travelerPhrase = fmt.Sprintf("%d travelers", travelers)
		partyPhrase = fmt.Sprintf("all %d travelers", travelers)
	}
	if len(offers) == 0 {
		if req.ReturnDate != "" {
			return fmt.Sprintf("No flights found from %s to %s for %s → %s (round trip).", req.Origin, req.Destination, req.DepartDate, req.ReturnDate)
		}
		return fmt.Sprintf("No flights found from %s to %s departing %s (one-way).", req.Origin, req.Destination, req.DepartDate)
	}
	// What the prices cover with respect to bags is identical for every offer,
	// so it is stated ONCE here rather than repeated per line. Without it the
	// model quotes a "cheapest" fare whose bag basis it cannot know — the
	// unlabeled-total failure of PR #355, one dimension over.
	tier := normalizeBaggage(req.Baggage)
	bagBasis := baggageBasisClause(tier, offers, baggageNoteCode(tier, offers))
	var b strings.Builder
	tripType := "one-way"
	if req.ReturnDate != "" {
		tripType = "round-trip"
		fmt.Fprintf(&b, "Found %d ranked flight options %s⇄%s round trip %s → %s, %s — prices are round-trip totals for %s; %s; stops and durations describe the outbound leg (best first):\n",
			len(offers), req.Origin, req.Destination, req.DepartDate, req.ReturnDate, travelerPhrase, partyPhrase, bagBasis)
	} else {
		fmt.Fprintf(&b, "Found %d ranked flight options %s→%s one-way %s, %s — prices are one-way totals for %s; %s (best first):\n",
			len(offers), req.Origin, req.Destination, req.DepartDate, travelerPhrase, partyPhrase, bagBasis)
	}
	for i, o := range offers {
		airline := "—"
		if len(o.Airlines) > 0 {
			airline = strings.Join(o.Airlines, "/")
		}
		stops := "nonstop"
		if o.Stops == 1 {
			stops = "1 stop"
		} else if o.Stops > 1 {
			stops = fmt.Sprintf("%d stops", o.Stops)
		}
		// On baggage-aware searches the model must talk in effective totals —
		// quoting the bare fare would recreate exactly the misleading price
		// the baggage tier exists to fix.
		bag := ""
		switch o.BaggageStatus {
		case baggageStatusIncluded:
			bag = " (bag included)"
		case baggageStatusPaid:
			bag = fmt.Sprintf(" (incl. %s %.0f bag fee)", o.Currency, o.BagFee)
		case baggageStatusInPrice:
			bag = " (bag fee already in this price)"
		case baggageStatusUnknown:
			bag = " (bag NOT included; fee unknown — warn the traveler)"
		}
		// The top-level times describe the OUTBOUND slice only (see
		// FlightOffer). On a round trip the return slice's departure is the
		// one that bounds the traveler's last day, so it gets its own label
		// rather than being folded into the outbound window.
		when := flightWindow(o.DepartTime, o.ArriveTime)
		if len(o.ReturnSegments) > 0 {
			back := flightWindow(o.ReturnSegments[0].DepartTime, o.ReturnSegments[len(o.ReturnSegments)-1].ArriveTime)
			switch {
			case when != "" && back != "":
				when = "out " + when + ", back " + back
			case back != "":
				when = "back " + back
			}
		}
		if when != "" {
			when = ", " + when
		}
		fmt.Fprintf(&b, "%d. %s — %s %.0f%s, %s, %dh%02dm%s (score %.1f)\n",
			i+1, airline, o.Currency, scoringPrice(o), bag, stops, o.DurationMin/60, o.DurationMin%60, when, o.Score)
	}
	fmt.Fprintf(&b, "Summarize the top 2-3 options in your own words and help the traveler choose. The traveler sees only a result count in the chat — your summary is their only record of these options — so state that every price you quote is a %s total for %s, never a per-person fare, and say what bags it covers. Any clock times shown are local to each airport; use the departure home to decide how much of the traveler's last day is theirs. A '+N' means the flight lands N calendar days after it leaves — on the outbound that makes its departure date EARLIER than the trip's first day, so say both days plainly and record them with add_transport_segment's depart_date and arrive_date rather than only the day they land.", tripType, partyPhrase)
	return b.String()
}

// summarizeEvents renders the events returned for a city into a compact text
// block for the model (the events themselves are streamed to the UI, shown as
// a summary chip).
func summarizeEvents(city string, events []Event) string {
	if len(events) == 0 {
		return fmt.Sprintf("No events found in %s for those dates.", city)
	}
	var b strings.Builder
	fmt.Fprintf(&b, "Found %d events in %s (soonest first):\n", len(events), city)
	for i, e := range events {
		when := e.StartDate
		if e.StartTime != "" {
			when += " " + e.StartTime
		}
		line := fmt.Sprintf("%d. %s — %s", i+1, e.Name, when)
		if e.Venue != "" {
			line += " @ " + e.Venue
		}
		if e.Category != "" {
			line += " (" + e.Category + ")"
		}
		b.WriteString(line + "\n")
	}
	// Nothing here is persisted — events are a live lookup, and no itinerary
	// item can even hold one (allowedItemCategories is {attraction,
	// restaurant}). The old closing line claimed "the full list is saved with
	// their trip", so the model could truthfully-soundingly tell a traveler
	// their events were saved. Same false-persistence claim summarizeOffers
	// already dropped. Naming the date and venue is what actually survives the
	// turn, so the reply has to carry them.
	b.WriteString("In your reply, highlight the events that fit the traveler's interests and dates. Nothing here is saved — these are live listings — so name the date and venue of any event you recommend.")
	return b.String()
}

// summarizeHotels renders the model-facing result for search_hotels.
//
// The load-bearing part is not the list, it is the sentence that says WHICH
// question was answered. A no-rates result looks exactly like a rates result
// with the prices left off, and a model that cannot tell them apart will fill
// the gap with a plausible nightly figure — which is a made-up price
// presented to a traveler as research. So the tier is stated in words, up
// front, and the no-rates branch carries an explicit prohibition rather than
// merely omitting the numbers. (docs/zen.md: a tool result states the
// post-state its consumer will observe; errors never pass silently.)
func summarizeHotels(res HotelSearchResult) string {
	if len(res.Stays) == 0 {
		return fmt.Sprintf("No stays found in %s. Check the city name, or try a nearby city.", res.City)
	}

	var b strings.Builder
	if res.RatesLive {
		currency := ""
		if res.Stays[0].Currency != nil {
			currency = " in " + *res.Stays[0].Currency
		}
		fmt.Fprintf(&b, "Found %d stays in %s for %s to %s, %d %s, with live prices%s:\n",
			len(res.Stays), res.City, res.CheckIn, res.CheckOut,
			res.Adults, pluralGuests(res.Adults), currency)
	} else {
		fmt.Fprintf(&b, "Found %d well-rated stays in %s. PRICES WERE NOT CHECKED (%s):\n",
			len(res.Stays), res.City, hotelRatesNoteText(res.RatesNote))
	}

	for i, s := range res.Stays {
		line := fmt.Sprintf("%d. %s", i+1, s.Name)
		if s.Kind == "vacation_rental" {
			line += " (vacation rental)"
		}
		if s.StarClass != nil {
			line += fmt.Sprintf(" — %d-star", *s.StarClass)
		}
		if s.Rating != nil {
			line += fmt.Sprintf(" — rated %.1f", *s.Rating)
			if s.Reviews != nil {
				line += fmt.Sprintf(" (%d reviews)", *s.Reviews)
			}
		}
		if s.RatePerNight != nil && s.Currency != nil {
			line += fmt.Sprintf(" — %s %.0f/night", *s.Currency, *s.RatePerNight)
			if s.TotalRate != nil {
				line += fmt.Sprintf(", %s %.0f total", *s.Currency, *s.TotalRate)
			}
		}
		b.WriteString(line + "\n")
	}

	if res.RatesLive {
		b.WriteString("Recommend a couple that fit the traveler's budget and area, and say the nightly price and rating of each. " +
			"Every price above is PER NIGHT for the whole party of " + fmt.Sprint(res.Adults) + " — never present one as a per-person or whole-stay figure, and always name the currency. " +
			"Prices are for the dates given and are not held — they can move. " +
			"Nothing here is saved to the trip; use add_accommodation once the traveler picks one.")
	} else {
		b.WriteString("These are real, well-rated properties, but you have NO price information for them. " +
			"Do not state, estimate, or imply a nightly price, a total, or a price range for any of them. " +
			"If the traveler wants prices, ask for their check-in and check-out dates and call search_hotels again with both.")
	}
	return b.String()
}

func pluralGuests(n int) string {
	if n == 1 {
		return "guest"
	}
	return "guests"
}

// hotelRatesNoteText turns the stable RatesNote code into the half-sentence
// the model reads. Kept beside the summarizer because it exists only to make
// the "why no prices" honest rather than vague.
func hotelRatesNoteText(note string) string {
	switch note {
	case "no_dates":
		return "no check-in/check-out dates were given"
	case "quota":
		return "today's price-lookup allowance is used up"
	case "not_configured":
		return "price lookup is not configured"
	default:
		return "the price provider was unavailable"
	}
}

// profileNotesInstruction is the standing profile-keeping rule appended to every
// authenticated session's system prompt, whether or not notes exist yet.
//
// This list is for facts with NO column of their own. Travel companions used to
// be on it and no longer is: migration 00063 gave it one, and naming it here too
// would tell the agent to write the same fact in two places — the exact
// duplication that migration cleaned up (docs/zen.md, one obvious way).
const profileNotesInstruction = "\n\nWhen you learn something durable about this traveler — dietary needs, accommodation style, accessibility needs, likes or dislikes — call save_preferences with profile_notes set to the COMPLETE updated profile: your current notes merged with the new fact, de-duplicated, as short bullet lines (max ~15). Never send only the new fact. Don't store one-off trip details or sensitive information (health, religion, politics) unless the traveler explicitly asks you to remember it."

// responseLanguageInstruction tells the agent which language to write in.
// Returns "" for English so the English prompt is unchanged; structured tool
// arguments are pinned to their canonical formats because the tool schemas and
// the database expect them regardless of the traveler's language. The trailing
// clause keeps the agent following a traveler who writes in a third language
// rather than fighting them.
func responseLanguageInstruction(locale string) string {
	if locale == defaultLocale {
		return ""
	}
	return "\n\nRespond in " + languageName(locale) + ": all prose, trip titles, day summaries and place descriptions. Keep structured tool arguments in their required formats — dates as YYYY-MM-DD, IATA airport codes, and enum values (time_of_day, category, budget, pace, mode) exactly as the tool schemas specify. If the traveler writes in another language, follow their language instead."
}

// personalizedSystemPrompt appends the traveler's saved preferences and
// AI-maintained profile notes to the base prompt, omitting any fields that are
// unset. Returns base unchanged when there is nothing to add.
func personalizedSystemPrompt(base string, p *store.TravelerPreference) string {
	if p == nil {
		return base
	}
	var parts []string
	if p.Budget != nil && *p.Budget != "" {
		parts = append(parts, "budget: "+*p.Budget)
	}
	if p.Pace != nil && *p.Pace != "" {
		parts = append(parts, "pace: "+*p.Pace)
	}
	if len(p.Interests) > 0 {
		parts = append(parts, "interests: "+strings.Join(p.Interests, ", "))
	}
	var homeNote string
	if p.HomeAirport != nil && *p.HomeAirport != "" {
		parts = append(parts, "home airport: "+*p.HomeAirport)
		homeNote = " When searching flights, default the origin to the traveler's home airport (" +
			*p.HomeAirport + ") and state the assumption (e.g. 'flying from " + *p.HomeAirport +
			"'); only use a different origin if the trip clearly starts elsewhere or they say so." +
			" Skip this flying default when the trip's travel mode is car, train, or bus — then the home airport only tells you roughly where home is."
	}
	var workNote string
	if p.WorkStyle != nil && *p.WorkStyle != "" {
		switch *p.WorkStyle {
		case "digital_nomad":
			parts = append(parts, "work style: digital nomad (works remotely while traveling)")
			workNote = " This traveler works remotely on the road: favor stays with reliable wifi and a real workspace (desk, coworking nearby, weekly or monthly rates), suggest longer stays in fewer places, and shape days so work blocks and sightseeing don't collide. Mention laptop-friendly cafes or coworking spaces where relevant, and flag digital-nomad visas for longer international stays."
		case "workation":
			parts = append(parts, "work style: sometimes works on trips")
			workNote = " When a trip involves working days, prefer stays with reliable wifi and a usable desk, and leave some unscheduled blocks for work."
		case "leisure_only":
			parts = append(parts, "work style: leisure only — trips are time off")
		}
	}
	// Fitness is a constraint on where they sleep and how the day opens, not a
	// taste (tastes are interests) — so each value names a concrete thing to do
	// rather than a mood to match. "none" is an answer: parts line, no note,
	// the same shape leisure_only takes above.
	var fitnessNote string
	if p.FitnessRoutine != nil && *p.FitnessRoutine != "" {
		const freeBlock = " Leave a block free at the start of most days rather than scheduling from wake-up"
		switch *p.FitnessRoutine {
		case "gym":
			parts = append(parts, "fitness: needs gym access")
			fitnessNote = " This traveler keeps a gym routine on the road: prefer stays with an on-site gym or one a few minutes' walk away and say which it is; when a stay has neither, call search_nearby with the stay's coordinates and name an actual gym, including whether it sells drop-in day passes." +
				freeBlock + ", and add gym kit with add_packing_item."
		case "running":
			parts = append(parts, "fitness: runs while traveling")
			fitnessNote = " This traveler runs while traveling: for each place they stay, name a specific route nearby — a park loop, waterfront, riverside path or track — with a rough distance, and say when a neighborhood is a poor place to run." +
				freeBlock + ", and add running shoes and kit with add_packing_item."
		case "both":
			parts = append(parts, "fitness: gym and running")
			fitnessNote = " This traveler trains and runs while traveling: prefer stays with an on-site gym or one a few minutes' walk away and say which (when a stay has neither, call search_nearby with the stay's coordinates and name an actual gym with its drop-in options), and name a specific running route nearby — park loop, waterfront, riverside path or track — with a rough distance." +
				freeBlock + ", and add running shoes and gym kit with add_packing_item."
		case "none":
			parts = append(parts, "fitness: not a factor — don't plan around it")
		}
	}
	// Intensity is a separate axis from pace: pace is how MANY things happen in
	// a day, this is how hard they are. Every band carries the same
	// state-the-numbers rule so a mismatched suggestion shows up as a figure the
	// traveler can reject instead of prose that reads fine either way
	// (docs/zen.md — contracts the model consumes must fail loudly).
	var outdoorNote string
	if p.OutdoorIntensity != nil && *p.OutdoorIntensity != "" {
		switch *p.OutdoorIntensity {
		case "easy":
			parts = append(parts, "outdoor days: easy")
			outdoorNote = " Keep active outings gentle: flat or paved walks, viewpoints reachable without a climb, trails under about 5 km. Offer the cable car or the drive rather than the ascent."
		case "moderate":
			parts = append(parts, "outdoor days: moderate")
			outdoorNote = " Half-day outings are welcome: hikes up to roughly 10 km with moderate climbing, bike days, paddling."
		case "challenging":
			parts = append(parts, "outdoor days: challenging")
			outdoorNote = " This traveler wants demanding outings: full-day hikes, 15 km or more, 1000 m of ascent, exposed or technical trails where they exist. Don't pad the day with filler around them."
		}
		if outdoorNote != "" {
			outdoorNote += " For every hike, ride, climb or paddle you suggest, state the distance, the elevation gain and roughly how long it takes, so a mismatch is obvious rather than implied."
		}
	}
	// Companions used to live as a "- Travels with: X" bullet inside the profile
	// notes; migration 00063 gave it a column so the distiller can't reword it
	// away. profileNotesInstruction no longer names it — one home only.
	var companionsNote string
	if p.Companions != nil && *p.Companions != "" {
		switch *p.Companions {
		case "solo":
			parts = append(parts, "traveling: solo")
			companionsNote = " They travel alone: quote prices and rooms for one person unless told otherwise, and favor places that are comfortable to visit solo — counter seating, walkable evenings, joinable day tours when they want company."
		case "partner":
			parts = append(parts, "traveling: as a couple")
		case "friends":
			parts = append(parts, "traveling: with friends")
			companionsNote = " Favor group-friendly tables and shared apartments over single rooms."
		case "family_with_kids":
			parts = append(parts, "traveling: with kids")
			companionsNote = " Favor shorter transfers and places that work with children, and flag age limits, long queues and anything that will eat a nap."
		case "varies":
			parts = append(parts, "traveling: varies by trip")
		}
	}
	// The bag tier is the ONE preference the model doesn't have to act on:
	// search_flights resolves it server-side from the same column, so this note
	// exists to explain the prices the tool hands back — not to ask the model to
	// pass a parameter it can forget (specs/traveler-baggage).
	var bagNote string
	if p.Baggage != nil && *p.Baggage != "" {
		switch *p.Baggage {
		case baggagePersonalItem:
			parts = append(parts, "packs: one personal item")
			bagNote = " They fly with one small under-seat bag, so flight prices are quoted as bare fares; if they mention bringing more, say the fare will not cover it."
		case baggageCarryOn:
			parts = append(parts, "packs: a carry-on")
			bagNote = " Flight prices you are given already cover their cabin bag."
		case baggageChecked:
			parts = append(parts, "packs: a checked bag")
			bagNote = " They check a bag, so a fare that excludes it is not the price they pay — relay whatever the flight results say about which bag fees are and aren't included."
		}
	}
	out := base
	if len(parts) > 0 {
		out += "\n\nTraveler preferences — " + strings.Join(parts, "; ") +
			". Tailor your suggestions accordingly." + homeNote + workNote + fitnessNote + outdoorNote + companionsNote + bagNote
	}
	if p.ProfileNotes != nil && strings.TrimSpace(*p.ProfileNotes) != "" {
		out += "\n\nTraveler profile notes (maintained by you):\n" + strings.TrimSpace(*p.ProfileNotes)
	}
	return out
}

// notesPreview returns a short excerpt of saved notes for the profile_updated
// SSE event; empty when no notes were part of the save.
func notesPreview(notes *string) string {
	if notes == nil {
		return ""
	}
	r := []rune(strings.TrimSpace(*notes))
	if len(r) > 80 {
		return string(r[:80]) + "…"
	}
	return string(r)
}
