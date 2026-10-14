# Write the verifier for a task

You are not solving this task. You are writing the **verifier**: the tests that decide whether someone
else's attempt at it succeeded. Your verifier will be run on many real attempts, some correct and some
subtly wrong. Accepting a wrong attempt and rejecting a correct one count equally against you.

## The task the solver was given

<task-instruction>
{instruction}
</task-instruction>

## Where you are

This machine is the solver's starting environment: the same files, tools and services the solver begins
with. Explore it and run anything you like to understand what a correct result looks like. Do not
attempt the whole task. A small hand-made output, in a scratch directory outside `/verifier_out`, is
enough to check that your tests run.

## What to write

Write a folder `/verifier_out/tests/` containing:

- `test.sh`: the grader runs it as `bash /tests/test.sh`. It must write exactly `1` (the attempt fully
  meets the task) or `0` (anything else) to `/logs/verifier/reward.txt`.
- any other files your tests use. The whole folder is placed at `/tests/`.

## What your tests will see

Your tests do not run on this machine. They run in a separate grading container built from this
Dockerfile, which you cannot change:

```dockerfile
{grading_dockerfile}
```

It also has `python3` and `bubblewrap` installed. Nothing else is available: you cannot install anything,
and there is no network. Anything else your tests need must be a file in `/verifier_out/tests/`.

The only things carried over from a solver's machine are these paths, copied to the same locations:

{artifacts}

Nothing else from the solver's machine is available. Your tests must finish within {timeout} seconds per
attempt.

When `/verifier_out/tests/` is complete, stop.
