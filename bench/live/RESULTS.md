# Live Gate 1 run (2026-10-07): inconclusive

Command: `python3 bench/live/run.py --repeats 2 --model haiku` (Haiku, 1 scenario, 4 later-session runs per config, ~$0.02 total).

| config | runs | repeated-mistake rate | explore calls | cost USD |
|---|---|---|---|---|
| none | 4 | 0.00 | 1.0 | 0.011 |
| memcode | 4 | 0.00 | 0.8 | 0.010 |

## Reading
- **Not evidence either way.** The trap never fired even without memory: the agent reads `conftest.py` and runs `python3 -m pytest` on its own, so there was no mistake for memory to prevent (floor effect).
- **Plugin does load headlessly:** a separate check created `.memcode/memory.db` in the temp repo, so the SessionStart hook ran. Whether the correction turn produced a stored memory was not verified in this run.
- Tiny N, one model, one scenario.

## Next
Scenarios need traps a competent agent cannot infer from the repo (an arbitrary convention that exists only in the user's correction, e.g. "tests live in `checks/`, never `tests/`", or a required custom command). Verify per run that a memory was written before attributing any difference to memory.
