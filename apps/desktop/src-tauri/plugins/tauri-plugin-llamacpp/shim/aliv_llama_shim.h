// C ABI over llama.cpp's server-context. Everything OpenAI-shaped -- chat
// templates, tool-call parsing, reasoning, sampling, slots, prompt cache,
// multimodal -- stays inside libserver-context.a; this only moves bytes.
#ifndef ALIV_LLAMA_SHIM_H
#define ALIV_LLAMA_SHIM_H

#include <stddef.h>

#ifdef __cplusplus
extern "C" {
#endif

typedef struct aliv_llama_engine   aliv_llama_engine;
typedef struct aliv_llama_response aliv_llama_response;

// Load-lifecycle notifications, called on the thread driving the load (and
// later, for a sleep/resume, on the engine's own loop thread). `state` is
// llama.cpp's server state ("loading", "ready", ...) and `payload` its JSON --
// for "loading" that is {"stages":[..],"current":..,"value":0..1}, which is
// the only source of real load progress. Must not throw and must stay valid
// until the engine is stopped. NULL for no notifications.
typedef void (*aliv_llama_state_cb)(const char * state,
                                  const char * payload,
                                  void *       user_data);

// argv is llama-server's own flag set (common_params_parse), so callers reuse
// the upstream arg table instead of mirroring common_params across the FFI.
// Returns NULL on failure and writes a message into err.
aliv_llama_engine * aliv_llama_engine_start(const char * const * argv,
                                          int                  argc,
                                          aliv_llama_state_cb   on_state,
                                          void *               user_data,
                                          char *               err,
                                          size_t               err_len);

// Starts from a router.preset.ini section, exactly as ALIV already generates it:
// the [*] section is applied first, then the named one overrides it.
aliv_llama_engine * aliv_llama_engine_start_from_preset(const char *       ini_path,
                                                     const char *       preset_name,
                                                     aliv_llama_state_cb on_state,
                                                     void *             user_data,
                                                     char *             err,
                                                     size_t             err_len);

// Returns 1 when the server loop did not stop in time and was detached, so the
// engine (and the state callback the detached loop can still reach) is leaked
// rather than freed; 0 on the clean join. The caller owns the `user_data` it
// passed to start, and must leak it too on a 1 -- freeing it would leave the
// detached loop calling into freed memory.
int aliv_llama_engine_stop(aliv_llama_engine * engine);

// route names match server_routes members, e.g. "post_chat_completions".
// Never returns NULL: transport failures come back as a 5xx response.
//
// `query` is a url query string ("id_slot=0&action=save"), parsed into the
// request's param map. llama.cpp reads slot actions and a few flags from there
// rather than from the body, so a route like post_slots is unreachable without
// it. NULL or "" means no params.
aliv_llama_response * aliv_llama_engine_request(aliv_llama_engine * engine,
                                              const char *       route,
                                              const char *       query,
                                              const char *       body,
                                              size_t             body_len);

int          aliv_llama_response_status(const aliv_llama_response * res);
const char * aliv_llama_response_content_type(const aliv_llama_response * res);
const char * aliv_llama_response_body(const aliv_llama_response * res, size_t * len);
int          aliv_llama_response_is_stream(const aliv_llama_response * res);

// 1 = chunk written (valid until the next call on this response), 0 = finished,
// -1 = the generator threw. Empty chunks are legal and mean "nothing yet".
int aliv_llama_response_next(aliv_llama_response * res, const char ** chunk, size_t * len);

void aliv_llama_response_free(aliv_llama_response * res);

// Asks the in-flight generator to stop; safe to call from another thread.
void aliv_llama_response_cancel(aliv_llama_response * res);

// Registers the ggml compute backends. `dir` names a directory of backend
// modules; NULL uses ggml's own search (the executable's directory, then the
// cwd), which is what a packaged install wants.
//
// Only call this with a non-NULL `dir` when the executable has no backend
// modules beside it: ggml's loader has no already-loaded guard, so a directory
// pre-load followed by its internal search would register a backend twice.
void aliv_llama_load_backends(const char * dir);

// The devices this build can offload to, as a JSON array of
// {id, name, mem, free} with memory in MiB -- the same fields the old
// `llama-server --list-devices` stdout was parsed into, so the Rust and TS
// sides are unchanged. Needs no engine: ggml devices are process-global.
// Never NULL; free the result with aliv_llama_string_free.
char * aliv_llama_devices_json(void);

// The same devices as {id, name} only, never asking one for its memory. A
// worker that stays up lists its devices with this: for a CUDA device the
// memory query in aliv_llama_devices_json creates a context that the process
// then holds for as long as it runs. Names need no such call.
// Never NULL; free the result with aliv_llama_string_free.
char * aliv_llama_device_identities_json(void);

void aliv_llama_string_free(char * s);

// The llama.cpp the shim was compiled against, for the pin assertion in
// build.rs / engine::assert_pinned_version.
const char * aliv_llama_version(void);       // e.g. "0.7.0"
int          aliv_llama_build_number(void);  // e.g. 11669
const char * aliv_llama_commit(void);

#ifdef __cplusplus
}
#endif
#endif
