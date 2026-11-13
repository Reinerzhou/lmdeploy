# Copyright (c) OpenMMLab. All rights reserved.
"""Opt-in request phase timing. No model inputs or generated text are recorded."""

import asyncio
import atexit
import contextvars
import functools
import json
import logging
import math
import os
import queue
import socket
import threading
import time
import uuid
from datetime import datetime, timezone
from pathlib import Path

from lmdeploy.serve.observability import otel_trace
from lmdeploy.trace import ENABLED, LOG_ENABLED

logger = logging.getLogger(__name__)
request_outcome_context = contextvars.ContextVar('observability_request_outcome', default=None)
HEADER = 'x-request-id'
_decode_json = json.JSONDecoder().decode


def enabled():
    return ENABLED


class JsonlWriter:
    """Bounded background writer; batch up to 64 records per flush."""

    def __init__(self, root, max_bytes=256 * 1024 * 1024, capacity=8192):
        root = Path(root).expanduser()
        if not root.is_absolute():
            raise ValueError('LMDEPLOY_TRACE_LOG_DIR must be an absolute writable directory')
        if max_bytes <= 0 or capacity <= 0:
            raise ValueError('observability size and queue capacity must be positive')
        self.directory = root / 'lmdeploy' / socket.gethostname()
        self.directory.mkdir(parents=True, exist_ok=True)
        self.max_bytes = max_bytes
        self.queue = queue.Queue(maxsize=capacity)
        self.dropped = self.io_errors = 0
        self.closed = False
        self.pid = os.getpid()
        self._lock = threading.Lock()
        self._stop = threading.Event()
        self._file = None
        self._size = 0
        self._day = None
        self._reported_dropped = self._reported_errors = 0
        self._last_warning = float('-inf')
        self._retry_at = 0.0
        self._retry_delay = 1.0
        self._reported_emit_errors = 0
        self._open()  # Fail at startup for an invalid destination.
        self.thread = threading.Thread(target=self._run, name='request-jsonl', daemon=True)
        self.thread.start()

    def _open(self):
        now = datetime.now(timezone.utc)
        stem = f'{now:%Y%m%dT%H%M%S.%fZ}.{os.getpid()}'
        for collision in range(10000):
            suffix = f'.{collision}' if collision else ''
            try:
                self._file = (self.directory / f'{stem}{suffix}.jsonl').open('x', encoding='utf-8')
                break
            except FileExistsError:
                continue
        else:
            raise FileExistsError('observability filename collision limit reached')
        self._day = now.date()
        self._size = 0

    def submit(self, record):
        with self._lock:
            if self.closed:
                return
            try:
                self.queue.put_nowait(record)
            except queue.Full:
                self.dropped += 1

    def _report_errors(self):
        if ((self.dropped != self._reported_dropped or self.io_errors != self._reported_errors
             or _emit_failures != self._reported_emit_errors)
                and time.monotonic() - self._last_warning >= 60):
            logger.warning('Request trace writer: dropped=%d io_errors=%d emit_errors=%d',
                           self.dropped, self.io_errors, _emit_failures)
            self._reported_dropped = self.dropped
            self._reported_errors = self.io_errors
            self._reported_emit_errors = _emit_failures
            self._last_warning = time.monotonic()

    def _discard_file(self):
        if self._file is not None:
            try:
                self._file.close()
            except OSError:
                pass
            self._file = None

    def _io_failure(self):
        self.io_errors += 1
        self._retry_at = time.monotonic() + self._retry_delay
        self._retry_delay = min(60.0, self._retry_delay * 2)
        self._discard_file()

    def _run(self):
        while not self._stop.is_set() or not self.queue.empty():
            self._report_errors()
            try:
                record = self.queue.get(timeout=0.1)
            except queue.Empty:
                continue
            batch = [record]
            for _ in range(63):
                try:
                    batch.append(self.queue.get_nowait())
                except queue.Empty:
                    break
            for record in batch:
                try:
                    if time.monotonic() < self._retry_at:
                        with self._lock:
                            self.dropped += 1
                        continue
                    line = json.dumps(record, ensure_ascii=True, allow_nan=False) + '\n'
                    # ensure_ascii makes character count equal to UTF-8 byte count.
                    size = len(line)
                    if self._file is None:
                        self._open()
                    if self._size and (self._size + size > self.max_bytes
                                       or self._day != datetime.now(timezone.utc).date()):
                        self._file.close()
                        self._file = None
                        self._open()
                    self._file.write(line)
                    self._size += size
                except (OSError, ValueError, TypeError):
                    self._io_failure()
                finally:
                    self.queue.task_done()
            try:
                if self._file is not None:
                    self._file.flush()
                    self._retry_delay = 1.0
                    self._retry_at = 0.0
            except (OSError, ValueError):
                self._io_failure()
        self._report_errors()
        self._discard_file()

    def close(self):
        if self.pid != os.getpid():
            return
        with self._lock:
            self.closed = True
            self._stop.set()
        self.thread.join(timeout=5)
        if self.thread.is_alive():
            logger.warning('Request trace drain timed out; buffered records may be lost')


_emit_failures = 0
_writer = None
_writer_pid = None
_writer_lock = threading.Lock()


def get_writer():
    global _writer, _writer_pid
    if not enabled():
        return None
    otel_trace.initialize()
    if not LOG_ENABLED:
        return None
    with _writer_lock:
        if _writer is None or _writer_pid != os.getpid():
            root = os.getenv('LMDEPLOY_TRACE_LOG_DIR', '')
            if not root:
                raise ValueError('LMDEPLOY_TRACE_LOG_DIR is required when observability is enabled')
            _writer = JsonlWriter(root, int(os.getenv('LMDEPLOY_TRACE_LOG_MAX_MB', '256')) * 1024 * 1024)
            _writer_pid = os.getpid()
            atexit.register(_writer.close)
        return _writer


def _after_fork():
    global _writer, _writer_pid, _writer_lock, _emit_failures
    _emit_failures = 0
    _writer = None
    _writer_pid = None
    _writer_lock = threading.Lock()


if hasattr(os, 'register_at_fork'):
    os.register_at_fork(after_in_child=_after_fork)


def emit(event, request_id, **fields):
    # Startup calls get_writer() directly and validates configuration eagerly.
    # Runtime logging must never replace a request result or its original error.
    global _emit_failures
    if not LOG_ENABLED:
        return
    try:
        writer = get_writer()
        if writer is not None:
            writer.submit(dict(event=event, request_id=request_id, component='lmdeploy',
                               hostname=socket.gethostname(), pid=os.getpid(),
                               timestamp=datetime.now(timezone.utc).isoformat(), **fields))
    except Exception:
        _emit_failures += 1


def interval(start, end):
    if start is None or end is None or not math.isfinite(start) or not math.isfinite(end) or end < start:
        return None
    return end - start


def _event_key(event):
    timestamp = event.timestamp
    return (event.type.name, timestamp if math.isfinite(timestamp) else None,
            getattr(event, 'value', None))


class RequestTrace:
    """Fixed-size request state; output chunks are observed but never retained."""

    def __init__(self):
        self.outcome = request_outcome_context.get()
        if self.outcome is not None and self.outcome.get('closed'):
            self.outcome = None
        self.request_id = self.outcome.get('request_id') if self.outcome is not None else None
        self.start = time.monotonic()
        self.start_ns = time.time_ns()
        self.end_ns = None
        self.model = None
        self.otel_span = None
        self.preprocessed = self.generate_start = self.handle_ready = None
        self.queued = self.scheduled = self.first_token = self.last_token = None
        self.delivery_delay = self.previous_delivery = None
        self.max_delivery_gap = None
        self.lookup_start = self.lookup_seconds = self.store_matched_tokens = None
        self.kv_start = self.kv_seconds = self.kv_loaded_tokens = None
        self.kv_pending_tokens = None
        self.kv_status = None
        self.kv_failed = False
        self.kv_active = False
        self.prompt_tokens = self.cached_tokens = None
        self.generated_tokens = 0
        self.max_output_tokens = None
        self.finish_reason = None
        self.finished = False
        self.backend = None
        self.terminal = False
        self.event_cursor = 0
        self.last_event_key = None
        self.engine_events_trusted = True
        self.prompt_index = None
        self.output_observation = None
        if self.outcome is not None:
            traces = self.outcome['traces']
            self.prompt_index = len(traces)
            if self.prompt_index:
                self.outcome['single_prompt'] = False
            traces.append(self)
        self.otel_span = otel_trace.begin_prompt(
            self.outcome.get('otel_span') if self.outcome is not None else None,
            self.start_ns, self.prompt_index, self.request_id)
        self.log_context = otel_trace.correlation(self.otel_span) or {'span_id': uuid.uuid4().hex[:16]}

    def observe(self, output):
        metrics = output.req_metrics
        status = getattr(output, 'status', None)
        status = getattr(status, 'name', status)
        token_count = len(output.token_ids)
        self.terminal |= status == 'FINISH'
        if metrics is not None:
            self.cached_tokens = metrics.cached_tokens
            self._observe_events(metrics.engine_events)
        if token_count:
            # A missing timestamp on the newest batch invalidates the last-token
            # boundary; an older valid timestamp must not understate Decode.
            self.last_token = None
            now = time.monotonic()
            if self.previous_delivery is not None:
                self.max_delivery_gap = max(self.max_delivery_gap or 0, now - self.previous_delivery)
            self.previous_delivery = now
            if (metrics is not None and math.isfinite(metrics.token_timestamp)
                    and metrics.token_timestamp > 0):
                # A final-only multi-token batch supplies no first-token boundary.
                # Preserve backend mode and leave the split unknown in that case.
                if self.generated_tokens == 0 and (status == 'SUCCESS' or token_count == 1):
                    self.first_token = metrics.token_timestamp
                    self.delivery_delay = interval(metrics.token_timestamp, time.time())
                self.last_token = metrics.token_timestamp
        self.generated_tokens += token_count

    def _invalidate_events(self):
        self.engine_events_trusted = False
        self.queued = self.scheduled = None
        self.lookup_start = self.lookup_seconds = self.store_matched_tokens = None
        self.kv_start = self.kv_seconds = self.kv_loaded_tokens = self.kv_pending_tokens = None
        self.kv_status = None
        self.kv_active = False

    def _observe_events(self, events):
        count = len(events)
        if not self.engine_events_trusted or not count:
            return
        if self.event_cursor:
            if count < self.event_cursor or _event_key(events[self.event_cursor - 1]) != self.last_event_key:
                self._invalidate_events()
                return
        start = self.event_cursor
        for index in range(start, count):
            event = events[index]
            name = event.type.name
            value = getattr(event, 'value', None)
            stamp = event.timestamp if math.isfinite(event.timestamp) and event.timestamp > 0 else None
            if name == 'QUEUED' and self.queued is None:
                self.queued = stamp
            elif name == 'SCHEDULED' and self.scheduled is None:
                self.scheduled = stamp
            elif name == 'KV_LOOKUP_STARTED':
                self.lookup_start = stamp
            elif name in ('KV_LOOKUP_FINISHED', 'KV_LOOKUP_CANCELLED'):
                duration = interval(self.lookup_start, stamp)
                if duration is not None:
                    self.lookup_seconds = (self.lookup_seconds or 0) + duration
                self.lookup_start = None
                if value is not None and name == 'KV_LOOKUP_FINISHED':
                    self.store_matched_tokens = max(self.store_matched_tokens or 0, value)
            elif name == 'KV_LOAD_STARTED':
                if self.kv_active:
                    self._invalidate_events()
                    return
                self.kv_active = True
                self.kv_start = stamp
                self.kv_pending_tokens = value
                if not self.kv_failed:
                    self.kv_status = 'pending'
            elif name in ('KV_LOAD_FINISHED', 'KV_LOAD_FAILED', 'KV_LOAD_CANCELLED'):
                duration = interval(self.kv_start, stamp)
                if duration is not None:
                    self.kv_seconds = (self.kv_seconds or 0) + duration
                self.kv_start = None
                if name == 'KV_LOAD_FAILED':
                    self.kv_status = 'failed'
                    self.kv_failed = True
                    self.kv_loaded_tokens = self.kv_loaded_tokens or 0
                elif name == 'KV_LOAD_CANCELLED':
                    if not self.kv_failed:
                        self.kv_status = 'cancelled'
                    self.kv_loaded_tokens = self.kv_loaded_tokens or 0
                else:
                    if not self.kv_failed:
                        self.kv_status = 'success'
                    if self.kv_pending_tokens is not None:
                        self.kv_loaded_tokens = (self.kv_loaded_tokens or 0) + self.kv_pending_tokens
                self.kv_pending_tokens = None
                self.kv_active = False
        if count > start:
            self.event_cursor = count
            self.last_event_key = _event_key(events[count - 1])

    def finish(self, status):
        if self.finished:
            return
        self.finished = True
        if self.outcome is not None and status in ('error', 'cancelled'):
            self.outcome[status] = True
        decode = interval(self.first_token, self.last_token)
        self.end_ns = time.time_ns() if self.otel_span is not None else None
        self.engine_status = status
        otel_trace.finish_engine(self, status)
        emit('engine_request_finished', self.request_id, **self.log_context, prompt_index=self.prompt_index,
             status=status, backend=self.backend,
             engine_events_trusted=self.engine_events_trusted,
             finish_reason=self.finish_reason,
             preprocess_seconds=interval(self.start, self.preprocessed),
             handle_wait_seconds=interval(self.generate_start, self.handle_ready),
             queue_seconds=interval(self.queued, self.scheduled),
             prefill_seconds=interval(self.scheduled, self.first_token),
             decode_seconds=decode,
             engine_ttft_seconds=interval(self.queued, self.first_token),
             tpot_seconds=decode / (self.generated_tokens - 1)
             if decode is not None and self.generated_tokens > 1 else None,
             token_delivery_delay_seconds=self.delivery_delay,
             max_engine_output_gap_seconds=self.max_delivery_gap,
             store_lookup_seconds=self.lookup_seconds, store_matched_tokens=self.store_matched_tokens,
             kv_load_seconds=self.kv_seconds, kv_loaded_tokens=self.kv_loaded_tokens,
             kv_load_status=self.kv_status,
             total_seconds=interval(self.start, time.monotonic()),
             engine_timestamps=dict(queued=self.queued, scheduled=self.scheduled,
                                    first_token=self.first_token, last_token=self.last_token),
             input_tokens=self.prompt_tokens, output_tokens=self.generated_tokens,
             cached_tokens=self.cached_tokens, max_output_tokens=self.max_output_tokens,
             token_counts_complete=self.terminal and status == 'success')


def trace_preprocess(func):
    @functools.wraps(func)
    async def wrapped(*args, **kwargs):
        if not enabled() or (args and not getattr(args[0], 'request_trace_enabled', True)):
            return await func(*args, **kwargs)
        trace = RequestTrace()
        engine = args[0] if args else None
        trace.backend = getattr(engine, 'backend', None)
        trace.model = getattr(engine, 'model_name', None)
        try:
            request = await func(*args, **kwargs)
        except BaseException as exc:
            trace.finish('cancelled' if isinstance(exc, (asyncio.CancelledError, GeneratorExit)) else 'error')
            raise
        trace.preprocessed = time.monotonic()
        trace.prompt_tokens = request.input_token_len
        trace.max_output_tokens = getattr(getattr(request, 'gen_config', None), 'max_new_tokens', None)
        request.trace = trace
        return request
    return wrapped


def trace_generate(func):
    async def traced(self, request, trace, *args, **kwargs):
        if trace is not None:
            trace.generate_start = time.monotonic()
        status = 'cancelled'
        generator = func(self, request, *args, **kwargs)
        try:
            async for output in generator:
                if output.finish_reason is not None:
                    if trace is not None:
                        trace.finish_reason = output.finish_reason
                    status = ('cancelled' if output.finish_reason == 'abort' else
                              'error' if output.finish_reason == 'error' else 'success')
                # Response construction and ASGI send run in the consuming task.
                # This also identifies sequential batch prompts when a protocol
                # emits the same choice index for every prompt.
                if trace.outcome is not None:
                    trace.outcome['active_trace'] = trace
                yield output
        except (asyncio.CancelledError, GeneratorExit):
            raise
        except BaseException:
            status = 'error'
            raise
        finally:
            try:
                await generator.aclose()
            except (asyncio.CancelledError, GeneratorExit):
                if status != 'success':
                    status = 'cancelled'
                raise
            except BaseException:
                status = 'error'
                raise
            finally:
                if trace is not None:
                    trace.finish(status)
    @functools.wraps(func)
    def wrapped(self, request, *args, **kwargs):
        trace = getattr(request, 'trace', None)
        if trace is None or getattr(request, 'consumed', False):
            return func(self, request, *args, **kwargs)
        return traced(self, request, trace, *args, **kwargs)
    return wrapped


class RequestTraceMiddleware:
    """Pure ASGI wrapper. Passes bodies unchanged; observes server send times."""

    def __init__(self, app):
        self.app = app
        get_writer()

    async def __call__(self, scope, receive, send):
        if (not enabled() or scope['type'] != 'http' or scope.get('method') != 'POST'
                or scope.get('path') not in ('/v1/chat/completions', '/v1/completions',
                                            '/v1/responses', '/v1/messages', '/generate')):
            return await self.app(scope, receive, send)
        # HTTP correlation is read-only; prompt state and spans are independent.
        outcome = {'error': False, 'cancelled': False, 'traces': [], 'active_trace': None,
                   'closed': False, 'single_prompt': False}
        start = time.monotonic()
        received_ns = time.time_ns()
        received_unix = received_ns / 1e9
        wanted = {b'traceparent', b'tracestate', b'x-request-id', b'x-session-id'}
        headers = {k.decode('latin1').lower(): v.decode('latin1')
                   for k, v in scope.get('headers', []) if k.lower() in wanted}
        outcome['operation'] = ('chat' if scope['path'] in ('/v1/chat/completions', '/v1/messages')
                                else 'text_completion')
        outcome['request_id'] = otel_trace.request_id(headers)
        outcome['otel_span'] = otel_trace.begin_http(headers, scope['path'], received_ns)
        outcome_token = request_outcome_context.set(outcome)
        first_body = None
        status_code = None
        complete = disconnected = False
        observation = OutputObservation(start)
        status = 'cancelled'
        stream_terminal = stream_error = stream_cancelled = False

        def response_request_id():
            return outcome['request_id']

        async def traced_receive():
            nonlocal disconnected
            message = await receive()
            if message['type'] == 'http.disconnect':
                disconnected = True
            return message

        async def traced_send(message):
            nonlocal first_body, status_code, complete, stream_terminal, stream_error, stream_cancelled
            if message['type'] == 'http.response.start':
                status_code = message['status']
                message = dict(message)
                message['headers'] = [(k, v) for k, v in message.get('headers', []) if k.lower() != HEADER.encode()]
                if response_request_id() is not None:
                    message['headers'].append((HEADER.encode(), response_request_id().encode()))
                observation.sse = any(k.lower() == b'content-type' and b'text/event-stream' in v
                                      for k, v in message['headers'])
                if len(outcome['traces']) == 1:
                    trace = outcome['traces'][0]
                    trace.output_observation = observation
                    observation.start = trace.start
                    outcome['single_prompt'] = True
            await send(message)
            if message['type'] == 'http.response.body':
                if message.get('body') and first_body is None:
                    first_body = time.monotonic()
                if observation.sse and outcome['single_prompt']:
                    observation.feed(message.get('body', b''))
                elif observation.sse:
                    trace = outcome['active_trace']
                    if trace is None and len(outcome['traces']) == 1:
                        trace = outcome['traces'][0]
                    observed = observation
                    if trace is not None:
                        if trace.output_observation is None:
                            if trace.prompt_index == 0:
                                trace.output_observation = observation
                                observation.start = trace.start
                                outcome['single_prompt'] = len(outcome['traces']) == 1
                            else:
                                trace.output_observation = OutputObservation(trace.start)
                        observed = trace.output_observation
                    observed.feed(message.get('body', b''))
                    stream_terminal |= observed.terminal
                    stream_error |= observed.error
                    stream_cancelled |= observed.cancelled
                if not message.get('more_body', False):
                    complete = True

        def result():
            if (observation.error or stream_error or outcome['error']
                    or (status_code is not None and status_code >= 400)):
                return 'error'
            if observation.cancelled or stream_cancelled or outcome['cancelled']:
                return 'cancelled'
            if (complete and not observation.sse) or observation.terminal or stream_terminal:
                return 'success'
            return 'cancelled'

        try:
            await self.app(scope, traced_receive, traced_send)
            status = result()
        except (asyncio.CancelledError, GeneratorExit, OSError):
            status = result()
            raise
        except BaseException:
            status = 'error'
            raise
        finally:
            try:
                traces = outcome['traces']
                # A rejected HTTP request can fail before any prompt is prepared.
                # It still gets one record and the same ID returned in its header.
                if not traces:
                    emit('request_finished', response_request_id(),
                         **(otel_trace.correlation(outcome['otel_span']) or {}), path=scope['path'],
                         prompt_index=None, status=status, http_status=status_code,
                         disconnected=disconnected, http_received_unix_seconds=received_unix,
                         http_first_body_seconds=interval(start, first_body),
                         http_total_seconds=time.monotonic() - start, **observation.summary())
                else:
                    http_total = time.monotonic() - start
                    for trace in traces:
                        if not trace.finished:
                            trace.finish('error' if status == 'error' else 'cancelled')
                        observed = trace.output_observation
                        otel_trace.finish(trace.otel_span,
                                          trace.engine_status, end_ns=trace.end_ns,
                                          http_status=status_code,
                                          output=observed.summary() if observed is not None else None)
                        emit('request_finished', trace.request_id, **trace.log_context, path=scope['path'],
                             prompt_index=trace.prompt_index, status=status, http_status=status_code,
                             disconnected=disconnected, http_received_unix_seconds=received_unix,
                             http_first_body_seconds=interval(start, first_body), http_total_seconds=http_total,
                             **(observed.summary() if observed is not None else _EMPTY_OUTPUT_SUMMARY))
            finally:
                try:
                    completed = outcome['traces']
                    if completed and outcome['otel_span'] is not None:
                        attrs = {'lmdeploy.token_counts_complete': all(
                            t.terminal and t.engine_status == 'success' for t in completed)}
                        for key, field in (('input_tokens', 'prompt_tokens'), ('output_tokens', 'generated_tokens'),
                                           ('cached_tokens', 'cached_tokens')):
                            values = [getattr(t, field) for t in completed]
                            if all(v is not None for v in values):
                                attrs['gen_ai.usage.' + key] = sum(values)
                        models = {t.model for t in completed if t.model}
                        if len(models) == 1:
                            attrs['gen_ai.request.model'] = attrs['gen_ai.response.model'] = models.pop()
                        first_tokens = [t.first_token for t in completed
                                        if t.first_token is not None and t.first_token >= received_unix]
                        if first_tokens:
                            attrs['gen_ai.latency.time_to_first_token'] = min(first_tokens) - received_unix
                        attrs['gen_ai.latency.e2e'] = time.monotonic() - start
                        otel_trace.attributes(outcome['otel_span'], attrs)
                    if observation.sse and (observation.terminal or stream_terminal):
                        otel_trace.stream_end(outcome['otel_span'])
                    otel_trace.finish(outcome['otel_span'], status, http_status=status_code,
                                      output={'http_total_seconds': time.monotonic() - start})
                except Exception:
                    otel_trace.finish(outcome['otel_span'], status, http_status=status_code)
                outcome['closed'] = True
                outcome['active_trace'] = None
                outcome['traces'].clear()
                request_outcome_context.reset(outcome_token)


class OutputObservation:
    """Bounded SSE observation, including fragments split across ASGI messages."""

    def __init__(self, start):
        self.start = start
        self.sse = self.terminal = self.error = self.cancelled = False
        self.buffer = bytearray()
        self.skipping = False
        self.first_output = self.reasoning_first = self.reasoning_last = self.content_first = None
        self.previous_output = self.max_output_gap = None

    def feed(self, body):
        # One accepted ASGI body has one observation time, even if it carries
        # many SSE records. Avoid splitlines() allocations and repeated copying
        # of a partial line split over many small body messages.
        observed_at = time.monotonic()
        # The server normally sends one complete SSE record per body. Keep
        # split, coalesced, CRLF and oversized records on the bounded slow path.
        if (not self.buffer and not self.skipping and len(body) <= 1024 * 1024
                and body.startswith(b'data:') and body.endswith(b'\n\n')
                and body.find(b'\n') == len(body) - 2):
            self._line(body[:-2], observed_at)
            return
        offset = 0
        while offset < len(body):
            newline = body.find(b'\n', offset)
            end = len(body) if newline < 0 else newline + 1
            size = end - offset
            if len(self.buffer) + size > 1024 * 1024:
                self.buffer.clear()
                self.skipping = True
            if not self.skipping:
                if not self.buffer and newline >= 0:
                    self._line(body[offset:end].strip(), observed_at)
                else:
                    self.buffer.extend(memoryview(body)[offset:end])
                    if newline >= 0:
                        self._line(self.buffer.strip(), observed_at)
            if newline >= 0:
                self.buffer.clear()
                self.skipping = False
            offset = end

    def _line(self, line, observed_at):
        if not line.startswith(b'data:'):
            return
        data = line[5:].strip()
        if data == b'[DONE]':
            self.terminal = True
            return
        try:
            # SSE is UTF-8; avoid json.loads(bytes)' repeated encoding detection.
            obj = _decode_json(data.decode('utf-8'))
        except (ValueError, UnicodeError, RecursionError):
            return
        if not isinstance(obj, dict):
            return
        kind = obj.get('type', '')
        error = obj.get('error')
        response = obj.get('response')
        response_cancelled = isinstance(response, dict) and response.get('status') == 'cancelled'
        if response_cancelled or (isinstance(error, dict) and error.get('code') == 'request_cancelled'):
            self.cancelled = True
        elif error or kind in ('error', 'response.failed'):
            self.error = True
        self.terminal |= kind in ('message_stop', 'response.completed', 'response.incomplete', 'response.failed')
        reasoning = content = tool = False
        choices = obj.get('choices')
        if isinstance(choices, list):
            for choice in choices:
                if not isinstance(choice, dict):
                    continue
                delta = choice.get('delta') or {}
                if isinstance(delta, dict):
                    reasoning |= bool(delta.get('reasoning_content') or delta.get('reasoning'))
                    content |= bool(delta.get('content'))
                    tool |= bool(delta.get('tool_calls') or delta.get('function_call'))
                content |= bool(choice.get('text'))
                self.cancelled |= choice.get('finish_reason') == 'abort'
                self.error |= choice.get('finish_reason') in ('error', 'parse_error')
        delta = obj.get('delta')
        if kind in ('response.reasoning_text.delta', 'response.reasoning_summary_text.delta'):
            reasoning |= bool(delta)
        elif kind == 'response.output_text.delta':
            content |= bool(delta)
        elif kind == 'response.function_call_arguments.delta':
            tool |= bool(delta)
        elif kind == 'response.output_item.added':
            item = obj.get('item')
            tool |= isinstance(item, dict) and item.get('type') == 'function_call'
        elif isinstance(delta, dict):
            reasoning |= bool(delta.get('thinking'))
            content |= bool(delta.get('text'))
            tool |= bool(delta.get('partial_json'))
        block = obj.get('content_block')
        if isinstance(block, dict):
            reasoning |= bool(block.get('thinking'))
            content |= bool(block.get('text'))
            tool |= block.get('type') == 'tool_use'
        meta = obj.get('meta_info')
        if isinstance(meta, dict):
            content |= bool(obj.get('text'))
            finish = meta.get('finish_reason')
            if isinstance(finish, dict):
                self.cancelled |= finish.get('type') == 'abort'
                self.error |= finish.get('type') == 'error'
        now = observed_at
        if reasoning:
            self.reasoning_first = now if self.reasoning_first is None else self.reasoning_first
            self.reasoning_last = now
        if content and self.content_first is None:
            self.content_first = now
        if reasoning or content or tool:
            if self.first_output is None:
                self.first_output = now
            if self.previous_output is not None:
                self.max_output_gap = max(self.max_output_gap or 0, now - self.previous_output)
            self.previous_output = now

    def summary(self):
        return dict(first_output_seconds=interval(self.start, self.first_output),
                    max_output_gap_seconds=self.max_output_gap,
                    reasoning_first_seconds=interval(self.start, self.reasoning_first),
                    reasoning_last_seconds=interval(self.start, self.reasoning_last),
                    content_first_seconds=interval(self.start, self.content_first),
                    reasoning_to_content_seconds=interval(self.reasoning_first, self.content_first))


_EMPTY_OUTPUT_SUMMARY = OutputObservation(0).summary()
