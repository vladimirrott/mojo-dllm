from std.os import remove
from std.os.path import exists
from std.testing import assert_equal, assert_true, assert_raises, TestSuite

from cli.args import Args
from mojo_dllm.diffusion.sampler import GenResult
from mojo_dllm.formats.gguf import GGUFFile
from mojo_dllm.models.diffusion_gemma import DiffusionGemma
from mojo_dllm.sys.mem import F32Ptr, Floats
from mojo_dllm.sys.mmap import Mapping
from mojo_dllm.tokenizer.bpe import Tokenizer
from main import (
    Decision,
    boolean_flags,
    chat_prompt,
    check_args,
    check_arch_flags,
    command_spec,
    decide,
    encode_prompt,
    execute,
    inspect_text,
    json_str,
    _csv,
    _logits_gemma,
    is_top_level_help,
    model_error,
    version_line,
    stop_json,
    usage,
    usage_for,
)


def test_documented_booleans_are_parsed_without_values() raises:
    var flags = boolean_flags()
    var count = 0
    var doc: String
    with open("docs/cli.md", "r") as f:
        doc = f.read()
    for line in doc.split("\n"):
        if not line.startswith("| `--"):
            continue
        var cells = line.split("|")
        if String(cells[2].strip()) != "off":
            continue
        var spelling = String(cells[1].strip())
        var flag = String(spelling[byte = 3 : spelling.byte_length() - 1])
        var found = False
        for candidate in flags:
            if candidate == flag:
                found = True
        assert_true(found, "documented boolean missing: " + flag)
        var spec = command_spec("run")
        var a = Args(["x", "run", "--" + flag], spec.values, spec.booleans)
        assert_true(a.has(flag))
        assert_equal(len(a.unknown), 0)
        count += 1
    assert_equal(count, 9)
    assert_equal(len(flags), count)


def test_chat_templates_strip_user_text() raises:
    var llada = "<|startoftext|><|start_header_id|>user<|end_header_id|>\n\nhi<|eot_id|><|start_header_id|>assistant<|end_header_id|>\n\n"
    var dream = (
        "<|im_start|>system\nYou are a helpful"
        " assistant.<|im_end|>\n<|im_start|>user\nhi<|im_end|>\n<|im_start|>assistant\n"
    )
    assert_equal(chat_prompt("llada", " \thi\n"), llada)
    assert_equal(chat_prompt("dream", " \thi\n"), dream)
    assert_equal(chat_prompt("unknown", "hi"), llada)


def test_chat_template_for_diffusion_gemma() raises:
    # tokenizer.chat_template: <bos>, a user turn, then an open model turn.
    assert_equal(
        chat_prompt("diffusion-gemma", " \thi\n"),
        "<bos><|turn>user\nhi<turn|>\n<|turn>model\n",
    )


def test_run_prompt_for_diffusion_gemma_has_one_bos() raises:
    var tok = Tokenizer(GGUFFile("tests/fixtures/gemma4-tokenizer.gguf"))
    var spec = command_spec("run")
    var chat = Args(["x", "run", "--prompt", "Hi"], spec.values, spec.booleans)
    var ids = encode_prompt(tok, "diffusion-gemma", chat)
    # <bos> from the template is the only BOS; <|turn> opens the user turn
    # and the model turn, and <turn|> closes the user turn.
    assert_equal(ids[0], 2)
    assert_equal(ids[1], 105)
    var bos = 0
    var opens = 0
    var closes = 0
    for t in ids:
        bos += 1 if t == 2 else 0
        opens += 1 if t == 105 else 0
        closes += 1 if t == 106 else 0
    assert_equal(bos, 1)
    assert_equal(opens, 2)
    assert_equal(closes, 1)
    var raw = Args(
        ["x", "run", "--prompt", "Hi", "--no-chat"], spec.values, spec.booleans
    )
    var plain = encode_prompt(tok, "diffusion-gemma", raw)
    assert_equal(len(plain), 2)
    assert_equal(plain[0], 2)
    assert_equal(tok.decode([plain[1]], skip_special=False), "Hi")


def test_json_escapes_and_preserves_unicode() raises:
    assert_equal(json_str('"\\\n\r\t'), '"\\"\\\\\\n\\r\\t"')
    assert_equal(json_str("\x00\x08\x0b\x1f"), '"\\u0000\\u0008\\u000b\\u001f"')
    assert_equal(json_str("héllo 世界"), '"héllo 世界"')
    assert_equal(json_str(""), '""')


def test_csv_format() raises:
    assert_equal(_csv([]), "")
    assert_equal(_csv([7]), "7")
    assert_equal(_csv([1, -2, 3]), "1,-2,3")


def test_usage_lists_all_commands() raises:
    var text = usage()
    for command in List[String](["run", "tokenize", "inspect", "logits"]):
        assert_true(text.__contains__("mojo-dllm " + command + " "))


def test_no_suppress_mask_is_a_run_boolean() raises:
    var spec = command_spec("run")
    var args = Args(
        ["mojo-dllm", "run", "--no-suppress-mask"], spec.values, spec.booleans
    )
    assert_true(args.has("no-suppress-mask"))
    assert_equal(len(args.unknown), 0)
    assert_true(usage_for("run").__contains__("--no-suppress-mask"))


def _parse(command: String, rest: List[String]) raises -> Args:
    var spec = command_spec(command)
    var argv = List[String](["mojo-dllm", command])
    for r in rest:
        argv.append(r)
    return Args(argv, spec.values, spec.booleans)


def _check(command: String, rest: List[String]) raises -> String:
    return check_args(_parse(command, rest), command_spec(command))


def test_every_command_declares_its_flags() raises:
    var run = command_spec("run")
    assert_equal(len(run.values), 18)
    assert_equal(len(run.booleans), 9)
    var tokenize = command_spec("tokenize")
    assert_equal(len(tokenize.values), 2)
    assert_equal(len(tokenize.booleans), 1)
    var inspect = command_spec("inspect")
    assert_equal(len(inspect.values), 0)
    assert_equal(len(inspect.booleans), 0)
    assert_true(inspect.takes_path)
    var logits = command_spec("logits")
    assert_equal(len(logits.values), 6)
    assert_equal(len(logits.booleans), 0)
    with assert_raises(contains="unknown command: frobnicate"):
        _ = command_spec("frobnicate")


def test_declared_booleans_come_from_the_single_list() raises:
    var all_booleans = boolean_flags()
    for command in List[String](["run", "tokenize", "inspect", "logits"]):
        for flag in command_spec(command).booleans:
            var found = False
            for candidate in all_booleans:
                if candidate == flag:
                    found = True
            assert_true(found, command + " declares a boolean not in the list")


def test_a_flag_of_another_command_is_unknown() raises:
    var message = _check(
        "tokenize", ["--model", "m", "--prompt", "p", "--json"]
    )
    assert_equal(
        message,
        "unknown flag --json for 'tokenize'\nsee: mojo-dllm tokenize --help",
    )


def test_misspelled_flag_suggests_the_declared_one() raises:
    var message = _check("run", ["--stpes", "3"])
    assert_equal(
        message,
        (
            "unknown flag --stpes for 'run' (did you mean --steps?)\nsee:"
            " mojo-dllm run --help"
        ),
    )


def test_unknown_flag_is_reported_before_a_missing_one() raises:
    var message = _check("run", ["--stpes", "3"])
    assert_true(not message.__contains__("missing required"))


def test_missing_required_flag_prints_usage() raises:
    var message = _check("run", ["--prompt", "x"])
    assert_equal(
        message,
        "missing required flag --model for 'run'\n" + usage_for("run"),
    )
    assert_true(message.__contains__("usage:\n  mojo-dllm run --model M"))
    var second = _check("run", ["--model", "m"])
    assert_true(second.startswith("missing required flag --prompt for 'run'\n"))
    var logits = _check(
        "logits", ["--model", "m", "--tokens", "1", "--rows", "0"]
    )
    assert_true(logits.startswith("missing required flag --out for 'logits'\n"))


def test_inspect_needs_a_path_and_nothing_else() raises:
    var missing = _check("inspect", [])
    assert_equal(
        missing, "missing model path for 'inspect'\n" + usage_for("inspect")
    )
    assert_equal(_check("inspect", ["m.gguf"]), "")
    var extra = _check("run", ["--model", "m", "--prompt", "p", "stray"])
    assert_equal(
        extra,
        "unexpected argument 'stray' for 'run'\nsee: mojo-dllm run --help",
    )


def test_complete_commands_pass_the_check() raises:
    assert_equal(
        _check(
            "run", ["--model", "m", "--prompt", "p", "--json", "--steps", "4"]
        ),
        "",
    )
    assert_equal(_check("tokenize", ["--model", "m", "--prompt", "p"]), "")
    assert_equal(
        _check(
            "logits",
            ["--model", "m", "--tokens", "1", "--rows", "0", "--out", "o"],
        ),
        "",
    )


def test_usage_for_one_command() raises:
    var run = usage_for("run")
    assert_true(
        run.startswith("usage:\n  mojo-dllm run --model M --prompt TEXT")
    )
    assert_true(not run.__contains__("mojo-dllm tokenize"))
    assert_true(not run.endswith("\n"))
    var tokenize = usage_for("tokenize")
    assert_equal(
        tokenize,
        "usage:\n  mojo-dllm tokenize --model M --prompt TEXT [--no-chat]",
    )
    with assert_raises(contains="unknown command: nope"):
        _ = usage_for("nope")


def test_usage_for_names_exactly_the_declared_flags() raises:
    for command in List[String](["run", "tokenize", "inspect", "logits"]):
        var spec = command_spec(command)
        var text = usage_for(command)
        var declared = spec.declared()
        for flag in declared:
            assert_true(
                text.__contains__("--" + flag),
                command + " usage omits --" + flag,
            )
        var cleaned = (
            text.replace("\n", " ").replace("]", " ").replace("|", " ")
        )
        for token in cleaned.split(" "):
            var word = String(token)
            if not word.startswith("--"):
                continue
            var name = String(word[byte=2:])
            var found = False
            for flag in declared:
                if flag == name:
                    found = True
            assert_true(found, command + " usage names undeclared --" + name)


def test_docs_table_lists_only_declared_run_flags() raises:
    var doc: String
    with open("docs/cli.md", "r") as f:
        doc = f.read()
    var declared = command_spec("run").declared()
    var seen = 0
    for line in doc.split("\n"):
        if not line.startswith("| `--"):
            continue
        var cell = String(line.split("|")[1].strip()).replace("`", "")
        var name = String(String(cell.split(" ")[0])[byte=2:])
        var found = False
        for flag in declared:
            if flag == name:
                found = True
        assert_true(found, "docs/cli.md lists undeclared flag: " + name)
        seen += 1
    assert_equal(seen, len(declared))


def test_help_routing() raises:
    for command in List[String](["", "help", "--help", "-h"]):
        assert_true(is_top_level_help(command))
    for command in List[String](["run", "tokenize", "frobnicate"]):
        assert_true(not is_top_level_help(command))
    for command in List[String](["run", "tokenize", "inspect", "logits"]):
        assert_true(_parse(command, ["--help"]).has("help"))
        assert_true(_parse(command, ["-h"]).has("help"))
    # help wins over every other problem, because check_args runs after it.
    var a = _parse("run", ["--stpes", "--help"])
    assert_true(a.has("help"))


def _decide(command: String, rest: List[String]) raises -> Decision:
    var argv = List[String](["mojo-dllm", command])
    for r in rest:
        argv.append(r)
    return decide(argv)


def test_unknown_command_is_a_usage_error() raises:
    var d = _decide("bogus", [])
    assert_equal(d.code, 2)
    assert_true(d.is_error)
    assert_equal(d.text, "unknown command: bogus\nsee: mojo-dllm --help")
    assert_equal(execute(["mojo-dllm", "bogus"]), 2)


def test_help_exits_zero_and_wins_over_other_problems() raises:
    for command in List[String](["", "help", "--help", "-h"]):
        var d = _decide(command, [])
        assert_equal(d.code, 0)
        assert_true(not d.is_error)
        assert_equal(d.text, usage())
    for command in List[String](["run", "tokenize", "inspect", "logits"]):
        var d = _decide(command, ["--stpes", "--steps", "abc", "--help"])
        assert_equal(d.code, 0)
        assert_equal(d.text, usage_for(command))
        assert_true(not d.proceed)
    # --help before a value flag that has no value: help, not "needs a value".
    var late = _decide("run", ["--help", "--prompt"])
    assert_equal(late.code, 0)
    assert_equal(late.text, usage_for("run"))
    assert_equal(execute(["mojo-dllm", "run", "--help", "--prompt"]), 0)
    assert_equal(execute(["mojo-dllm", "--help"]), 0)


def test_version_flag_prints_one_line_and_exits_zero() raises:
    var d = _decide("--version", [])
    assert_equal(d.code, 0)
    assert_true(not d.is_error)
    assert_true(not d.proceed)
    assert_equal(d.text, version_line())
    assert_true(not d.text.__contains__("\n"))
    assert_true(usage().startswith(version_line() + ": "))
    assert_equal(execute(["mojo-dllm", "--version"]), 0)


def test_usage_mentions_the_version_flag() raises:
    assert_true(usage().__contains__("mojo-dllm --version"))


def test_usage_errors_exit_two() raises:
    var unknown = _decide("run", ["--stpes", "3"])
    assert_equal(unknown.code, 2)
    assert_true(unknown.is_error)
    var missing = _decide("run", ["--model", "m", "--prompt"])
    assert_equal(missing.code, 2)
    assert_equal(
        missing.text,
        "flag --prompt needs a value\nsee: mojo-dllm run --help",
    )
    var number = _decide(
        "run", ["--model", "m", "--prompt", "p", "--steps", "abc"]
    )
    assert_equal(number.code, 2)
    assert_equal(
        number.text,
        "flag --steps needs an integer, got 'abc'\nsee: mojo-dllm run --help",
    )
    assert_equal(execute(["mojo-dllm", "run", "--stpes", "3"]), 2)
    assert_equal(execute(["mojo-dllm", "run", "--prompt"]), 2)
    assert_equal(
        execute(
            [
                "mojo-dllm",
                "run",
                "--model",
                "m",
                "--prompt",
                "p",
                "--steps",
                "x",
            ]
        ),
        2,
    )


def test_valid_arguments_proceed() raises:
    var d = _decide("run", ["--model", "m", "--prompt", "p"])
    assert_equal(d.code, 0)
    assert_true(d.proceed)
    assert_true(not d.is_error)


def test_runtime_failure_exits_one() raises:
    assert_equal(
        execute(
            [
                "mojo-dllm",
                "run",
                "--model",
                "/nonexistent/model.gguf",
                "--prompt",
                "hi",
            ]
        ),
        1,
    )
    assert_equal(execute(["mojo-dllm", "inspect", "tests/fixtures"]), 1)


def test_integer_flags_name_the_flag_and_the_value() raises:
    var base = List[String](["--model", "m", "--prompt", "p"])
    for flag in List[String](
        ["max-tokens", "steps", "block-length", "seed", "threads"]
    ):
        for bad in List[String](["abc", "", "12.5", "99999999999999999999"]):
            var rest = base.copy()
            rest.append("--" + flag)
            rest.append(bad)
            assert_equal(
                _check("run", rest),
                "flag --"
                + flag
                + " needs an integer, got '"
                + bad
                + "'\nsee: mojo-dllm run --help",
            )
    var logits = _check(
        "logits",
        [
            "--model",
            "m",
            "--tokens",
            "1",
            "--rows",
            "0",
            "--out",
            "o",
            "--threads",
            "many",
        ],
    )
    assert_equal(
        logits,
        (
            "flag --threads needs an integer, got 'many'\nsee: mojo-dllm logits"
            " --help"
        ),
    )


def test_values_that_can_never_be_valid_are_refused() raises:
    var base = List[String](["--model", "m", "--prompt", "p"])
    for flag in List[String](
        ["max-tokens", "steps", "block-length", "threads"]
    ):
        for bad in List[String](["0", "-3"]):
            var rest = base.copy()
            rest.append("--" + flag)
            rest.append(bad)
            assert_equal(
                _check("run", rest),
                "flag --"
                + flag
                + " must be at least 1, got "
                + bad
                + "\nsee: mojo-dllm run --help",
            )
    var rest = base.copy()
    rest.append("--temperature")
    rest.append("-0.5")
    assert_equal(
        _check("run", rest),
        (
            "flag --temperature must be at least 0, got -0.5\nsee: mojo-dllm"
            " run --help"
        ),
    )
    for bad in List[String](["warm", "nan", "inf", ""]):
        var r = base.copy()
        r.append("--temperature")
        r.append(bad)
        assert_equal(
            _check("run", r),
            "flag --temperature needs a finite number, got '"
            + bad
            + "'\nsee: mojo-dllm run --help",
        )
    # Negative seeds and zero temperature stay valid.
    var ok = base.copy()
    ok.append("--seed")
    ok.append("-5")
    ok.append("--temperature")
    ok.append("0")
    assert_equal(_check("run", ok), "")


def test_entropy_bound_flags_are_checked_before_the_model_loads() raises:
    var base = List[String](["--model", "m", "--prompt", "p"])
    for flag in List[String](["eb-steps", "eb-stability"]):
        var r = base.copy()
        r.append("--" + flag)
        r.append("x")
        assert_equal(
            _check("run", r),
            "flag --"
            + flag
            + " needs an integer, got 'x'\nsee: mojo-dllm run --help",
        )
    var low = base.copy()
    low.append("--eb-steps")
    low.append("0")
    assert_equal(
        _check("run", low),
        "flag --eb-steps must be at least 1, got 0\nsee: mojo-dllm run --help",
    )
    var stab = base.copy()
    stab.append("--eb-stability")
    stab.append("-1")
    assert_equal(
        _check("run", stab),
        (
            "flag --eb-stability must be at least 0, got -1\nsee: mojo-dllm"
            " run --help"
        ),
    )
    for flag in List[String](
        ["eb-t-min", "eb-t-max", "eb-bound", "eb-confidence"]
    ):
        for bad in List[String](["warm", "nan", "inf", ""]):
            var r = base.copy()
            r.append("--" + flag)
            r.append(bad)
            assert_equal(
                _check("run", r),
                "flag --"
                + flag
                + " needs a finite number, got '"
                + bad
                + "'\nsee: mojo-dllm run --help",
            )
    var zero_max = base.copy()
    zero_max.append("--eb-t-max")
    zero_max.append("0")
    assert_equal(
        _check("run", zero_max),
        "flag --eb-t-max must be above 0, got 0\nsee: mojo-dllm run --help",
    )
    for flag in List[String](["eb-t-min", "eb-bound", "eb-confidence"]):
        var r = base.copy()
        r.append("--" + flag)
        r.append("-0.5")
        assert_equal(
            _check("run", r),
            "flag --"
            + flag
            + " must be at least 0, got -0.5\nsee: mojo-dllm run --help",
        )
    # The branch's own defaults, and the boundary values, are valid.
    var ok = base.copy()
    for pair in List[String](
        [
            "--eb-steps",
            "48",
            "--eb-t-min",
            "0",
            "--eb-t-max",
            "0.8",
            "--eb-bound",
            "0",
            "--eb-stability",
            "0",
            "--eb-confidence",
            "0",
        ]
    ):
        ok.append(pair)
    assert_equal(_check("run", ok), "")


def test_entropy_bound_flags_belong_to_diffusion_gemma() raises:
    var spec = command_spec("run")
    var with_eb = Args(
        ["x", "run", "--eb-bound", "0.2"], spec.values, spec.booleans
    )
    with assert_raises(contains="--eb-bound applies to diffusion-gemma only"):
        check_arch_flags(with_eb, "llada")
    with assert_raises(contains="not dream"):
        check_arch_flags(with_eb, "dream")
    check_arch_flags(with_eb, "diffusion-gemma")
    var plain = Args(["x", "run"], spec.values, spec.booleans)
    check_arch_flags(plain, "llada")
    var steps = Args(["x", "run", "--steps", "9"], spec.values, spec.booleans)
    with assert_raises(contains="use --eb-steps"):
        check_arch_flags(steps, "diffusion-gemma")
    check_arch_flags(steps, "llada")


def test_json_reports_steps_taken_and_the_stop_reason() raises:
    var res = GenResult()
    assert_equal(
        stop_json(res), ', "steps_taken": 0, "stop_reason": "complete"'
    )
    res.steps_taken = 17
    res.stop_reason = "converged"
    assert_equal(
        stop_json(res), ', "steps_taken": 17, "stop_reason": "converged"'
    )


def test_csv_flags_of_logits_are_checked() raises:
    var message = _check(
        "logits",
        ["--model", "m", "--tokens", "1,x", "--rows", "0", "--out", "o"],
    )
    assert_equal(
        message,
        (
            "flag --tokens needs comma-separated integers, got '1,x'\nsee:"
            " mojo-dllm logits --help"
        ),
    )


def test_equals_form_says_how_values_are_given() raises:
    assert_equal(
        _check("run", ["--model=x"]),
        (
            "unknown flag --model=x for 'run'\nflags take their value as the"
            " next argument: --model x\nsee: mojo-dllm run --help"
        ),
    )
    # A boolean has no value to give, and an undeclared name gets no advice.
    assert_equal(
        _check("run", ["--json=1"]),
        (
            "unknown flag --json=1 for 'run' (did you mean --json?)\nsee:"
            " mojo-dllm run --help"
        ),
    )


def _joined(lines: List[String]) -> String:
    var text = String("")
    for line in lines:
        text += line + "\n"
    return text


def test_inspect_pins_the_diffusion_gemma_fixture_output() raises:
    var path = "tests/fixtures/tiny-diffusion-gemma.gguf"
    var text = inspect_text(path)
    var head = _joined(
        [
            "file: " + path,
            "gguf version: 3",
            "architecture: diffusion-gemma",
            "name: tiny-diffusion-gemma",
            "tensors: 52",
            "metadata keys: 28",
            "",
            "config:",
            "  blocks: 2 (sliding 1, global 1)",
            "  global layers: 1",
            "  hidden size: 256",
            "  heads: 8",
            "  kv heads: 4 sliding, 1 global",
            "  head size: 64 sliding, 128 global",
            "  rope base: 10000.0 sliding, 1000000.0 global",
            "  sliding window: 128",
            "  dense ffn: 512",
            "  experts: 4 (2 used), ffn 64",
            "  vocabulary: 512, mask token 4",
            "  final logit softcap: 30.0",
            "  canvas length: 16",
            "  context length: 8192",
            "",
            "metadata:",
            '  general.architecture = "diffusion-gemma"',
            '  general.name = "tiny-diffusion-gemma"',
            "  diffusion-gemma.block_count = 2",
            "  diffusion-gemma.context_length = 8192",
            "  diffusion-gemma.embedding_length = 256",
            "  diffusion-gemma.feed_forward_length = 512",
            "  diffusion-gemma.attention.head_count = 8",
            "  diffusion-gemma.attention.head_count_kv = <array of 2>",
            "  diffusion-gemma.rope.freq_base = 1000000.0",
            "  diffusion-gemma.rope.freq_base_swa = 10000.0",
            "  diffusion-gemma.attention.layer_norm_rms_epsilon = 1e-06",
            "  diffusion-gemma.expert_count = 4",
            "  diffusion-gemma.expert_used_count = 2",
            "  diffusion-gemma.attention.key_length = 128",
            "  diffusion-gemma.attention.value_length = 128",
            "  diffusion-gemma.final_logit_softcapping = 30.0",
            "  diffusion-gemma.attention.sliding_window = 128",
            "  diffusion-gemma.attention.shared_kv_layers = 0",
            "  diffusion-gemma.embedding_length_per_layer_input = 0",
            "  diffusion-gemma.attention.sliding_window_pattern = <array of 2>",
            "  diffusion-gemma.attention.key_length_swa = 64",
            "  diffusion-gemma.attention.value_length_swa = 64",
            "  diffusion-gemma.expert_feed_forward_length = 64",
            "  diffusion-gemma.rope.dimension_count = 128",
            "  diffusion-gemma.rope.dimension_count_swa = 64",
            "  diffusion-gemma.attention.causal = false",
            "  diffusion.canvas_length = 16",
            "  tokenizer.ggml.mask_token_id = 4",
            "",
            "tensor types:",
            "  Q6_K: 2",
            "  F32: 31",
            "  Q4_K: 14",
            "  Q5_0: 3",
            "  Q8_0: 2",
            "",
            "tensors:",
        ]
    )
    assert_true(text.startswith(head), "the inspect output starts differently")
    assert_true(
        "  blk.1.ffn_gate_up_exps.weight  Q4_K  [256, 128, 4]\n" in text,
        "a 3-D expert tensor is listed with its shape",
    )
    assert_true(
        "  blk.0.ffn_down_exps.weight  Q5_0  [64, 256, 4]\n" in text,
        "a Q5_0 expert tensor is listed with its type",
    )
    assert_true("blk.1.attn_v.weight" not in text, "a global layer has no V")


def test_inspect_says_why_a_diffusion_gemma_config_is_refused() raises:
    var text = inspect_text(
        "tests/fixtures/diffusion-gemma/shared-kv-layers.gguf"
    )
    assert_true("architecture: diffusion-gemma\n" in text)
    assert_true(
        "config: refused: diffusion-gemma.attention.shared_kv_layers must be 0,"
        " got 2"
        in text,
        "inspect names the refused key",
    )
    assert_true(
        "  diffusion-gemma.attention.shared_kv_layers = 2\n" in text,
        "inspect still lists the metadata",
    )


def test_inspect_lists_every_global_layer() raises:
    var two = inspect_text("tests/fixtures/diffusion-gemma/all-global.gguf")
    assert_true("  blocks: 2 (sliding 0, global 2)\n" in two)
    assert_true("  global layers: 0, 1\n" in two)
    var none = inspect_text("tests/fixtures/diffusion-gemma/all-sliding.gguf")
    assert_true("  blocks: 2 (sliding 2, global 0)\n" in none)
    assert_true("  global layers: none\n" in none)


def test_inspect_prints_no_config_for_the_other_architectures() raises:
    var text = inspect_text("tests/fixtures/tiny-llada.gguf")
    assert_true("architecture: llada\n" in text)
    assert_true("config:" not in text)


def test_inspect_rejects_a_second_path() raises:
    assert_equal(
        _check("inspect", ["a", "b"]),
        "unexpected argument 'b' for 'inspect'\nsee: mojo-dllm inspect --help",
    )


def _mapping_error(path: String) -> String:
    try:
        _ = Mapping(path)
    except e:
        return model_error(String(e))
    return String("opened")


def test_missing_model_file_hint() raises:
    var path = "/nonexistent/model.gguf"
    assert_equal(
        _mapping_error(path),
        "cannot open model file "
        + path
        + ": No such file or directory\nto download a model, run: ./mojo-dllm"
        " pull",
    )


def test_missing_model_file_hint_with_quote_colon_in_path() raises:
    var path = "/nonexistent/x': y"
    assert_equal(
        _mapping_error(path),
        "cannot open model file "
        + path
        + ": No such file or directory\nto download a model, run: ./mojo-dllm"
        " pull",
    )


def test_other_open_failures_get_no_pull_hint() raises:
    # ENOTDIR: a path below a regular file. EACCES takes the same branch.
    var path = "tests/fixtures/bad-magic.gguf/x"
    assert_equal(
        _mapping_error(path),
        "cannot open model file " + path + ": Not a directory",
    )
    assert_equal(
        model_error("cannot open file: m.gguf: Permission denied"),
        "cannot open model file m.gguf: Permission denied",
    )


def test_non_gguf_file_hint() raises:
    var path = "build/tests/not-a-gguf.gguf"
    with open(path, "w") as f:
        f.write("<html>404 Not Found</html>")
    var message = String("")
    try:
        _ = GGUFFile(path)
    except e:
        message = model_error(String(e))
    remove(path)
    assert_equal(
        message,
        path
        + " is not a GGUF file (bad magic).\na failed download leaves an HTML"
        " error page with a .gguf name; delete the file and run ./mojo-dllm"
        " pull again",
    )


def test_other_errors_pass_through_unchanged() raises:
    assert_equal(
        model_error("unsupported model architecture: qwen2"),
        "unsupported model architecture: qwen2",
    )
    assert_equal(
        model_error("file is empty or unreadable: m.gguf"),
        "file is empty or unreadable: m.gguf",
    )


comptime DG_TINY = "tests/fixtures/tiny-diffusion-gemma.gguf"


def _gemma_tokens(n: Int) -> List[Int]:
    var tokens = List[Int]()
    for i in range(n):
        tokens.append((i * 37) % 500 + 5)
    return tokens^


def test_logits_runs_diffusion_gemma_over_prompt_and_canvas() raises:
    # 25 tokens: a prompt of 9 and the canvas of 16 the tiny model declares.
    var tokens = _gemma_tokens(25)
    var rows = List[Int]()
    for r in range(9, 25):
        rows.append(r)
    var path = String("build/tests/dg-logits-cli.f32")
    _logits_gemma(DG_TINY, 2, tokens, rows, path)
    var m = DiffusionGemma(DG_TINY, threads=2, max_tokens=25)
    var want = Floats(16 * 512)
    m.forward(tokens, want.ptr())
    var mm = Mapping(path)
    var got = F32Ptr(unsafe_from_address=mm.addr)
    var differ = 0
    for i in range(16 * 512):
        if got.unsafe_load(i) != want[i]:
            differ += 1
    remove(path)
    assert_equal(differ, 0)


def test_logits_refuses_rows_that_are_not_the_canvas() raises:
    var tokens = _gemma_tokens(25)
    var path = String("build/tests/dg-logits-refused.f32")
    var rows = List[Int]()
    for r in range(8, 24):
        rows.append(r)
    with assert_raises(
        contains=(
            "scores the 16 canvas positions, the last of the tokens: --rows"
            " must be 9,10,11,12,13,14,15,16,17,18,19,20,21,22,23,24, got 8,"
        )
    ):
        _logits_gemma(DG_TINY, 1, tokens, rows, path)
    var all_rows = List[Int]()
    for r in range(25):
        all_rows.append(r)
    with assert_raises(contains="--rows must be 9,10"):
        _logits_gemma(DG_TINY, 1, tokens, all_rows, path)
    with assert_raises(contains="below the canvas length 16"):
        _logits_gemma(DG_TINY, 1, _gemma_tokens(15), List[Int](), path)


def _logits_args(rows: String, path: String, device: String) -> List[String]:
    return [
        "mojo-dllm",
        "logits",
        "--model",
        DG_TINY,
        "--tokens",
        _csv(_gemma_tokens(25)),
        "--rows",
        rows,
        "--out",
        path,
        "--threads",
        "1",
        "--device",
        device,
    ]


def test_the_logits_command_runs_diffusion_gemma_on_the_cpu() raises:
    var rows = List[Int]()
    for r in range(9, 25):
        rows.append(r)
    var path = String("build/tests/dg-logits-command.f32")
    assert_equal(execute(_logits_args(_csv(rows), path, "cpu")), 0)
    var m = DiffusionGemma(DG_TINY, threads=1, max_tokens=25)
    var want = Floats(16 * 512)
    m.forward(_gemma_tokens(25), want.ptr())
    var mm = Mapping(path)
    var got = F32Ptr(unsafe_from_address=mm.addr)
    var differ = 0
    for i in range(16 * 512):
        if got.unsafe_load(i) != want[i]:
            differ += 1
    remove(path)
    assert_equal(differ, 0)


def test_the_logits_command_refuses_the_gpu_for_diffusion_gemma() raises:
    var rows = List[Int]()
    for r in range(9, 25):
        rows.append(r)
    var path = String("build/tests/dg-logits-command-gpu.f32")
    if exists(path):
        remove(path)
    assert_equal(execute(_logits_args(_csv(rows), path, "gpu")), 1)
    assert_true(not exists(path))


def main() raises:
    TestSuite.discover_tests[__functions_in_module()]().run()
