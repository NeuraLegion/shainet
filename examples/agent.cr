require "../src/shainet"
require "json"
require "colorize"
require "./agent_workspace"
require "./agent_v4a"

# Agentic chat demo: a multi-turn conversation with a growing context and a
# tool-calling loop, built entirely on Network#run. Think of it as a very light
# Claude/Copilot/Kiro-style CLI agent.
#
# The model (Qwen3-Coder-style: ChatML + XML tool calls) can call local tools;
# this harness parses the calls, runs the tools, feeds the results back, and
# lets the model continue until it produces a plain answer.
#
# Usage:
#   SHAINET_Q4=1 SHAINET_MOE_OFFLOAD=1 \
#     crystal run examples/agent.cr --release -Denable_cuda -- ~/models/Qwen3-Coder-30B-A3B-Instruct
#
# Built-in tools are intentionally read-only (list_directory, read_file). Add
# your own in build_tools — that is the extension point for an MCP bridge etc.

module AgentDemo
  MAX_READ_BYTES = 64_000

  # Tool-calling iterations allowed per user turn, before the agent hands control back.
  #
  # A runaway guard, not a work budget: without it a model that keeps emitting tool calls
  # never returns to the prompt. The number was 8, chosen when a turn's prefill cost minutes
  # and a runaway was expensive. Prefill is now ~29 s at 4096 with KV prefix reuse making
  # turn 2+ about a second, so 8 stopped being a runaway guard and started truncating
  # ordinary work -- reading four files and grepping twice already exceeds it.
  #
  # 40 is high enough that hitting it means something is actually looping.
  # AGENT_MAX_TOOL_STEPS overrides it, clamped to at least 1: a 0 would break out before
  # generating anything and every turn would answer with silence.
  MAX_TOOL_STEPS = begin
    n = (ENV["AGENT_MAX_TOOL_STEPS"]? || "40").to_i
    n < 1 ? 1 : n
  end

  # How many times an IDENTICAL tool call is allowed before the loop intervenes, and how many recent
  # call signatures to remember. Small on purpose: two identical calls are a retry, three is a loop.
  REPEAT_CALL_LIMIT = 2

  # How many times one turn may be told to finish a dropped tool call before its reply is
  # accepted as-is. Two is enough for a formatting slip without letting a model that simply
  # wants to answer briefly be nudged in a loop.
  EMPTY_REPLY_NUDGE_LIMIT =  2
  RECENT_CALL_MEMORY      = 12

  # Turn a failed list_directory into an answer rather than a dead end.
  #
  # Three cases, in the order a caller actually hits them:
  #   - the argument is a shell command, not a path (a model reaching for `ls a b 2>/dev/null`
  #     because no tool offered "check several paths at once") -- name the right tool;
  #   - the path is a FILE -- say so and list its parent, which is what was wanted;
  #   - the path does not exist -- list the nearest existing ancestor and point out entries whose
  #     names are close, so a typo like "example/" for "examples/" is corrected in one round trip.
  def self.directory_miss_help(raw : String, resolved : String) : String
    if raw.matches?(/[;|&><$`]|\*\s|\s2>/)
      return "Error: '#{raw}' looks like a shell command, not a directory path. list_directory " \
             "takes ONE directory path. Use run_command to run shell, or call list_directory once " \
             "per path."
    end

    if File.exists?(resolved) && !Dir.exists?(resolved)
      parent = File.dirname(raw)
      parent = "." if parent.empty?
      listing = safe_children(File.dirname(resolved))
      return "Error: #{raw} is a FILE, not a directory (use read_file to read it).\n" \
             "Contents of #{parent}:\n#{listing}"
    end

    # Walk up to the nearest ancestor that exists, and list it.
    rel = raw
    anc = resolved
    3.times do
      break if Dir.exists?(anc)
      anc = File.dirname(anc)
      rel = File.dirname(rel)
    end
    rel = "." if rel.empty? || rel == "/"

    unless Dir.exists?(anc)
      return "Error: no such directory: #{raw}"
    end

    wanted = File.basename(raw)
    entries = begin
      Dir.children(anc)
    rescue
      [] of String
    end
    # "Close" deliberately means a shared prefix rather than an edit distance: the typos that
    # actually occur here are a missing or extra trailing character (example/ for examples/).
    near = entries.select do |e|
      next false if wanted.empty?
      e.starts_with?(wanted[0, [wanted.size, 3].min]) || wanted.starts_with?(e[0, [e.size, 3].min])
    end.sort!.first(8)

    out = ["Error: no such directory: #{raw}"]
    out << "Did you mean: #{near.join(", ")}" unless near.empty?
    out << "Contents of #{rel}:\n#{safe_children(anc)}"
    out.join("\n")
  end

  # Directory listing with directories marked, or a readable reason it could not be listed.
  def self.safe_children(dir : String) : String
    Dir.children(dir).sort.map { |e| Dir.exists?(File.join(dir, e)) ? "#{e}/" : e }.join("\n")
  rescue ex
    "(could not list: #{ex.message})"
  end

  record ToolParam, name : String, type : String, description : String, required : Bool = true
  # `ids` holds the EXACT tokens the model produced for an assistant turn, when they are
  # known. Re-encoding the decoded text does not reliably reproduce them -- a decode,
  # UTF-8 scrub and re-encode round trip can shift token boundaries -- and a single
  # mismatched token destroys KV prefix reuse for the whole conversation.
  record Message, role : String, content : String, ids : Array(Int32)? = nil
  record ToolCall, name : String, args : Hash(String, String)

  class Tool
    getter name : String
    getter description : String
    getter params : Array(ToolParam)
    getter handler : Hash(String, String) -> String

    def initialize(@name, @description, @params, &@handler : Hash(String, String) -> String)
    end

    def call(args : Hash(String, String)) : String
      handler.call(args)
    end
  end

  # Root that every file tool is confined to: the directory the agent was launched in, unless
  # AGENT_WORKSPACE says otherwise.
  #
  # Resolved once at startup rather than per call, so nothing can widen its own sandbox by
  # chdir-ing partway through a turn.
  @@workspace = File.realpath(ENV["AGENT_WORKSPACE"]? || Dir.current)

  def self.workspace : String
    @@workspace
  end

  # Resolve a model-supplied path. Returns {path, ""} on success and {nil, error_text} on
  # refusal, so a tool body stays a single line and the model gets told WHY.
  #
  # Inside the workspace needs no approval. OUTSIDE it, the path is negotiable rather than
  # forbidden: the user is asked once per location and the answer is remembered, so working on
  # a file elsewhere costs one prompt instead of one per tool call. An approval is per PATH on
  # purpose -- approving a model config should not also hand over ~/.ssh/id_rsa. Answering "a"
  # still opens everything, matching the prompt's existing meaning.
  def self.safe_path(raw : String?) : {String?, String}
    {WorkspacePath.resolve(@@workspace, raw || ""), ""}
  rescue WorkspaceEscapeError
    outside_path(raw || "")
  rescue ex : WorkspacePathError
    {nil, "Error: #{ex.message}."}
  end

  private def self.outside_path(raw : String) : {String?, String}
    resolved = WorkspacePath.resolve_anywhere(@@workspace, raw)
    return {resolved, ""} if allow_all? || WorkspacePath.approved_outside?(resolved)
    unless confirm?("access #{resolved} — OUTSIDE the workspace (#{@@workspace})")
      return {nil, "Error: #{raw} is outside the workspace and the user declined access. " \
                   "Work within #{@@workspace} instead."}
    end
    # Remembered, so the next tool call on this file does not ask again.
    WorkspacePath.approve_outside(resolved)
    {resolved, ""}
  rescue ex : WorkspacePathError
    {nil, "Error: #{ex.message}."}
  end

  # A unified-ish diff of a proposed whole-file write, for the confirmation prompt.
  #
  # Approving "write 4182 bytes to x.cr" says nothing about what actually changes, which is
  # the real problem with a blanket approval: allow-all is only reasonable if each prompt
  # showed enough to judge. Capped on purpose -- a 3000-line rewrite scrolling past defeats
  # the point as thoroughly as showing nothing.
  def self.preview_diff(path : String, new_content : String, max_lines : Int32 = 40) : String
    old_lines = File.exists?(path) ? File.read(path).lines : [] of String
    new_lines = new_content.lines
    # Trim the common head and tail, so the window shown is the change and not the file.
    head = 0
    while head < old_lines.size && head < new_lines.size && old_lines[head] == new_lines[head]
      head += 1
    end
    tail = 0
    while tail < (old_lines.size - head) && tail < (new_lines.size - head) &&
          old_lines[old_lines.size - 1 - tail] == new_lines[new_lines.size - 1 - tail]
      tail += 1
    end
    removed = old_lines[head, old_lines.size - head - tail]
    added = new_lines[head, new_lines.size - head - tail]
    return "  (no textual change)" if removed.empty? && added.empty?

    half = max_lines // 2
    out = [] of String
    out << "  @@ line #{head + 1} @@"
    removed.first(half).each { |l| out << "  -#{l}" }
    out << "  ... #{removed.size - half} more removed" if removed.size > half
    added.first(half).each { |l| out << "  +#{l}" }
    out << "  ... #{added.size - half} more added" if added.size > half
    out.join("\n")
  end

  # Set by answering "a" at a confirmation prompt: allow every later mutating tool call for
  # the rest of the process, without re-asking.
  #
  # Deliberately in-memory and process-scoped, not persisted: a blanket approval that
  # outlived the session would be a much bigger promise than the one the user made at the
  # prompt. SHAINET_AGENT_YOLO=1 is the same thing chosen up front.
  @@allow_all = false

  def self.allow_all? : Bool
    @@allow_all
  end

  def self.allow_all=(value : Bool)
    @@allow_all = value
  end

  # Confirmation gate for mutating/executing tools.
  #
  #   y  allow this call
  #   n  deny this call (the default, so a bare Enter is safe)
  #   a  allow this and every later call this session
  #
  # Skipped entirely with SHAINET_AGENT_YOLO=1.
  def self.confirm?(desc : String) : Bool
    return true if ENV.fetch("SHAINET_AGENT_YOLO", "0") == "1"
    return true if @@allow_all
    STDERR.print "  #{"⚠ allow".colorize(:yellow)} #{desc}? [y/N/a=all] "
    STDERR.flush
    ans = gets
    # EOF (piped input, closed stdin) must not read as approval.
    return false unless ans
    case ans.strip.downcase
    when "a", "all"
      @@allow_all = true
      STDERR.puts "  #{"⚠ approving all further tool calls this session".colorize(:yellow)}"
      true
    when .starts_with?("y")
      true
    else
      false
    end
  end

  # Basic code-agent tools. Read-only ones run freely; write/edit/run ask for
  # confirmation first (unless SHAINET_AGENT_YOLO=1).
  def self.build_tools : Array(Tool)
    [
      Tool.new(
        "list_directory",
        "List the files and subdirectories in a directory. Paths are relative to the workspace root; an absolute path outside it needs the user to approve that location once.",
        [ToolParam.new("path", "string", "Directory path to list (default: current directory).")]
      ) do |args|
        raw = (args["path"]? || "").strip
        raw = "." if raw.empty?
        path, err = AgentDemo.safe_path(raw)
        if path.nil?
          next err
        end
        if Dir.exists?(path)
          Dir.children(path).sort.map { |e| Dir.exists?(File.join(path, e)) ? "#{e}/" : e }.join("\n")
        else
          # A miss used to dead-end with just "not a directory", which is what sent a model into a
          # loop: its real question was "which of these paths exist?", and the error answered
          # nothing, so it reissued variants -- eventually smuggling a shell command into this
          # argument. Answer the underlying question instead.
          AgentDemo.directory_miss_help(raw, path)
        end
      end,
      Tool.new(
        "read_file",
        "Read a text file. Returns the whole file when it is small, or the lines from start_line to " \
        "end_line (1-based, inclusive) when given. A large file returns only its first lines plus its " \
        "total line count -- ask again with a range to see the rest. Prefer `search` to FIND the lines " \
        "you want and then read that range: reading a whole large file usually costs more context than " \
        "the answer is worth. Output is line-numbered. Binary files are refused. Paths are relative to " \
        "the workspace root; an absolute path outside it needs the user to approve that location once.",
        [ToolParam.new("path", "string", "File path to read."),
         ToolParam.new("start_line", "integer", "Optional first line to return (1-based).", false),
         ToolParam.new("end_line", "integer", "Optional last line to return (1-based, inclusive).", false)]
      ) do |args|
        path, err = AgentDemo.safe_path(args["path"]?)
        if path.nil?
          next err
        end
        if Dir.exists?(path) || !File.exists?(path)
          "Error: not a file: #{args["path"]?}"
        else
          c = File.read(path)
          # Refuse binaries outright. A model asked to inspect a directory will happily try
          # to read a compiled executable, and the bytes are useless to it while being
          # ruinously expensive: 64 KB of binary tokenized to 60534 tokens in one observed
          # run, against an 8192-token window. A NUL byte is the cheap, reliable signal.
          if c.byte_slice(0, Math.min(c.bytesize, 8192)).includes?('\u0000')
            "Error: #{path} looks like a binary file (contains NUL bytes); refusing to read it"
          elsif !c.valid_encoding?
            "Error: #{path} is not valid UTF-8; refusing to read it"
          else
            AgentDemo.render_file(args["path"]? || path, c,
              args["start_line"]?.try(&.to_i?), args["end_line"]?.try(&.to_i?))
          end
        end
      end,
      Tool.new(
        "search",
        "Search file CONTENTS and get back path:line: text for every hit. This is how you find the few " \
        "ranges worth reading instead of reading whole files — search first, then read_file with " \
        "start_line/end_line around a hit. Case-insensitive; literal text unless regex is true.",
        [ToolParam.new("pattern", "string", "Text to find, or a regular expression when regex is true."),
         ToolParam.new("path", "string", "Directory to search (default: workspace root).", false),
         ToolParam.new("glob", "string", "Only search files whose name matches this, e.g. '*.cr'.", false),
         ToolParam.new("context", "string", "Lines of context around each hit, 0-5 (default 0).", false),
         ToolParam.new("regex", "string", "'true' to treat pattern as a regular expression.", false)]
      ) do |args|
        pat = args["pattern"]? || ""
        next "Error: empty pattern" if pat.empty?
        root, err = AgentDemo.safe_path(args["path"]? || ".")
        if root.nil?
          next err
        end
        ctx = Math.min(5, Math.max(0, (args["context"]? || "0").to_i? || 0))
        rx = (args["regex"]? || "").downcase == "true"
        AgentDemo.search_contents(root, pat, args["glob"]?, ctx, rx)
      end,
      Tool.new(
        "glob",
        "List FILES BY NAME matching a glob, e.g. '**/*.cr' or 'src/**/gguf*.cr'. Use it to see what " \
        "exists before reading anything; it returns paths only, never file contents.",
        [ToolParam.new("pattern", "string", "Glob pattern, e.g. '**/*.cr'."),
         ToolParam.new("path", "string", "Directory to search from (default: workspace root).", false)]
      ) do |args|
        pat = args["pattern"]? || ""
        next "Error: empty pattern" if pat.empty?
        root, err = AgentDemo.safe_path(args["path"]? || ".")
        if root.nil?
          next err
        end
        AgentDemo.glob_files(root, pat)
      end,
      Tool.new(
        "write_file",
        "Create a NEW text file. An existing file is refused: use apply_patch or edit_file to change one. Paths are relative to the workspace root; an absolute path outside it needs the user to approve that location once.",
        [ToolParam.new("path", "string", "File path to write."),
         ToolParam.new("content", "string", "Full file content.")]
      ) do |args|
        path, err = AgentDemo.safe_path(args["path"]?)
        if path.nil?
          next err
        end
        # Refuse to clobber. A model that means to change three lines will cheerfully pass a
        # whole-file rewrite, and any part it did not remember is silently gone. Making it
        # patch or edit instead keeps the rest of the file out of the blast radius.
        if File.exists?(path)
          next "Error: #{args["path"]?} already exists. Use apply_patch or edit_file to modify it, " \
               "or delete it first with run_command if replacing it wholesale is really intended."
        end
        content = args["content"]? || ""
        rel = args["path"]?
        STDERR.puts AgentDemo.preview_diff(path, content) unless AgentDemo.allow_all?
        next "Declined by user." unless AgentDemo.confirm?("create #{rel} (#{content.bytesize} bytes)")
        # mkdir -p the parents: otherwise a new file in a new directory needs a shell call.
        Dir.mkdir_p(File.dirname(path))
        File.write(path, content)
        "Wrote #{content.bytesize} bytes to #{rel}"
      end,
      Tool.new(
        "replace_lines",
        "Replace a RANGE OF LINES in a file, addressed by number (1-based, inclusive) — you never have " \
        "to reproduce the existing text. Prefer this over edit_file and apply_patch when search or " \
        "read_file has already told you the line numbers. Pass the same number twice to replace one " \
        "line, and an empty content to delete the range.",
        [ToolParam.new("path", "string", "File path to edit."),
         ToolParam.new("start_line", "string", "First line to replace (1-based, inclusive)."),
         ToolParam.new("end_line", "string", "Last line to replace (1-based, inclusive)."),
         ToolParam.new("content", "string", "Replacement text for those lines (may be several lines; empty deletes them).")]
      ) do |args|
        path, err = AgentDemo.safe_path(args["path"]?)
        if path.nil?
          next err
        end
        next "Error: #{args["path"]?} does not exist" unless File.exists?(path)
        s = (args["start_line"]? || "").to_i?
        e = (args["end_line"]? || "").to_i?
        next "Error: start_line and end_line must be integers" if s.nil? || e.nil?
        body = File.read(path)
        lines = body.split('\n')
        # A trailing newline makes split produce a final empty element; it is not a line the user can
        # address, and counting it would put every range off by one at the end of the file.
        total = lines.size
        total -= 1 if total > 0 && lines[-1].empty? && body.ends_with?('\n')
        next "Error: start_line #{s} is outside #{args["path"]?} (#{total} lines)" if s < 1 || s > total
        next "Error: end_line #{e} is before start_line #{s}" if e < s
        e = total if e > total

        replacement = args["content"]? || ""
        before = lines[0, s - 1]
        after = lines[e..]
        middle = replacement.empty? ? [] of String : replacement.split('\n')
        preview = "#{s}-#{e} of #{args["path"]?} → #{middle.size} line(s)"
        next "Declined by user." unless AgentDemo.confirm?("replace lines #{preview}")
        File.write(path, (before + middle + after).join('\n'))
        "Replaced lines #{s}-#{e} with #{middle.size} line(s) in #{args["path"]?}."
      end,
      Tool.new(
        "edit_file",
        "Replace an exact string in a file. 'find' must match EXACTLY ONE occurrence, including whitespace; include surrounding context to make it unique. Paths are relative to the workspace root; an absolute path outside it needs the user to approve that location once.",
        [ToolParam.new("path", "string", "File path to edit."),
         ToolParam.new("find", "string", "Exact text to find (must be unique in the file)."),
         ToolParam.new("replace", "string", "Replacement text.")]
      ) do |args|
        path, err = AgentDemo.safe_path(args["path"]?)
        if path.nil?
          next err
        end
        next "Error: not a file: #{args["path"]?}" if Dir.exists?(path) || !File.exists?(path)
        find = args["find"]? || ""
        next "Error: empty 'find'" if find.empty?
        replace = args["replace"]? || ""
        content = File.read(path)
        count = content.scan(find).size
        next "No occurrences of the given text in #{args["path"]?}" if count == 0
        # Refuse a non-unique match instead of replacing every one of them.
        #
        # This used to gsub. A model asked to change one `end` rewrote every `end` in the
        # file, and the only hint was a count buried in the confirmation line, which an
        # approved-all session never shows. Ambiguity is the model's to resolve, not ours to
        # guess at, so hand it back and say how to fix it.
        if count > 1
          next "Error: 'find' matches #{count} times in #{args["path"]?}. Include more " \
               "surrounding context so it matches exactly once, or use apply_patch for a " \
               "multi-hunk change."
        end
        updated = content.sub(find, replace)
        STDERR.puts AgentDemo.preview_diff(path, updated) unless AgentDemo.allow_all?
        next "Declined by user." unless AgentDemo.confirm?("edit #{args["path"]?}")
        File.write(path, updated)
        "Edited #{args["path"]?} (replaced #{find.size} chars with #{replace.size} chars)"
      end,
      Tool.new(
        "apply_patch",
        <<-DESC,
          Apply a V4A context-diff patch to one or more files. PREFERRED for all file edits: it supports multi-file, multi-hunk changes in a single call, and edits are located by surrounding context rather than line numbers, so they survive minor drift. Read the file first so your context lines match.

          Format:
          *** Begin Patch
          *** Update File: path/to/file
          @@ optional anchor (e.g. a function name)
           unchanged context line
          -removed line
          +added line
          *** Add File: path/to/new-file
          +line 1
          *** Delete File: path/to/old-file
          *** End Patch

          Rules: ' ' prefix = context, '-' = remove, '+' = add. Include ~3 context lines around each change. Use @@ anchors when the context is not unique. All patch paths must be INSIDE the workspace: unlike read_file and edit_file, a patch cannot reach an approved outside location, so use edit_file for those.
          DESC
        [ToolParam.new("patch", "string", "Full patch in V4A format, including the *** Begin Patch / *** End Patch markers.")]
      ) do |args|
        patch = args["patch"]? || ""
        next "Error: empty patch" if patch.empty?
        # Show which files the patch touches BEFORE asking: the patch body is the diff, so a
        # separate preview would just repeat it, but the file list is what the approval is
        # actually about.
        targets = patch.lines.compact_map do |l|
          m = l.match(/^\*\*\* (Update|Add|Delete) File: (.+)$/)
          "#{m[1].downcase} #{m[2].strip}" if m
        end
        next "Error: no *** Update/Add/Delete File: directives found in the patch" if targets.empty?
        next "Declined by user." unless AgentDemo.confirm?("apply patch to #{targets.size} file(s): #{targets.join(", ")}")
        begin
          result = AgentDemo::V4A.apply(AgentDemo.workspace, patch)
        rescue ex : AgentDemo::V4A::PatchParseError
          next "Error: patch does not parse: #{ex.message}"
        rescue ex : AgentDemo::WorkspacePathError
          next "Error: #{ex.message}. Paths must be relative to the workspace."
        rescue ex
          next "Error applying patch: #{ex.message}"
        end
        lines = [] of String
        lines << "Applied: #{result[:applied].join(", ")}" unless result[:applied].empty?
        # Report partial success honestly: some hunks landing and others not is the normal
        # failure mode of context matching, and the model must know which is which to retry.
        lines << "Failed: #{result[:errors].join("; ")}" unless result[:errors].empty?
        lines << "Patch matched nothing." if lines.empty?
        lines.join("\n")
      end,
      Tool.new(
        "run_command",
        "Run a shell command and return its combined stdout/stderr and exit code.",
        [ToolParam.new("command", "string", "The shell command to execute.")]
      ) do |args|
        cmd = args["command"]? || ""
        next "Error: empty command" if cmd.empty?
        next "Declined by user." unless AgentDemo.confirm?("run: #{cmd}")
        buf = IO::Memory.new
        status = Process.run("/bin/sh", ["-c", cmd], output: buf, error: buf)
        result = buf.to_s
        result = "#{result.byte_slice(0, MAX_READ_BYTES)}\n... [truncated]" if result.bytesize > MAX_READ_BYTES
        "exit=#{status.exit_code}\n#{result}"
      end,
    ]
  end

  # Streams assistant output token-by-token, coloring reasoning (<think>…
  # </think>) dim and the answer normal, while hiding tool-call XML. Buffers a
  # small tail so tags split across tokens are never shown half-rendered.
  class StreamRenderer
    TAGS = {"<think>" => :think_open, "</think>" => :think_close,
            "<tool_call>" => :tool_open, "</tool_call>" => :tool_close}
    SPINNER = %w[⠋ ⠙ ⠹ ⠸ ⠼ ⠴ ⠦ ⠧ ⠇ ⠏]

    def initialize(@io : IO)
      @mode = :normal
      @pending = ""
      @started = false
      @tool_chars = 0
      @spin = 0
      @status_shown = false
      @status_width = 0
    end

    def feed(text : String)
      @pending += text
      loop do
        idx = nil
        found = nil
        TAGS.each_key do |tag|
          i = @pending.index(tag)
          if i && (idx.nil? || i < idx.not_nil!)
            idx, found = i, tag
          end
        end
        if (i = idx) && (tag = found)
          emit(@pending[0...i])
          apply(TAGS[tag])
          @pending = @pending[(i + tag.size)..]
        else
          hold = partial_tag_suffix(@pending)
          emit(@pending[0, @pending.size - hold])
          @pending = @pending[(@pending.size - hold)..]
          break
        end
      end
    end

    def finish
      clear_status
      emit(@pending)
      @pending = ""
    end

    private def emit(t : String)
      return if t.empty?
      # Hidden tool-call tokens (the model writing a whole file inline) would
      # otherwise be dead silence — show a live spinner + byte count instead.
      if @mode == :tool
        @tool_chars += t.size
        @spin = (@spin + 1) % SPINNER.size
        status = "  #{SPINNER[@spin]} writing tool call… (#{@tool_chars} chars)"
        @io.print "\r#{status.colorize(:dark_gray)}"
        @io.flush
        # Remember how wide this actually was. The erase used to be a hardcoded 36, which is exactly
        # the width at a five-digit count and one short from six digits on -- so a tool call over
        # 99,999 characters, which an apply_patch of a large file reaches, left residue on the line.
        # Tracking the real width also means the string above can be reworded without silently
        # breaking the erase.
        @status_width = status.size if status.size > @status_width
        @status_shown = true
        return
      end
      # Trim leading whitespace before the very first visible chars.
      unless @started
        t = t.lstrip
        return if t.empty?
        @started = true
      end
      case @mode
      when :think  then @io.print t.colorize(:dark_gray)
      when :normal then @io.print t
      end
      @io.flush
    end

    # Erase the in-progress status line (so following output starts clean).
    private def clear_status
      return unless @status_shown
      @io.print "\r" + (" " * @status_width) + "\r"
      @io.flush
      @status_shown = false
    end

    private def apply(action)
      case action
      when :think_open  then @mode = :think
      when :think_close then @mode = :normal
      when :tool_open   then @tool_chars = 0; @mode = :tool
      when :tool_close  then clear_status; @mode = :normal
      end
    end

    # Longest suffix of s that is a (shorter) prefix of some tag — held back in
    # case the tag completes on the next token.
    private def partial_tag_suffix(s : String) : Int32
      max = 0
      TAGS.each_key do |tag|
        (1...tag.size).each do |k|
          max = k if k <= s.size && k > max && s[(s.size - k)..] == tag[0, k]
        end
      end
      max
    end
  end

  # Bytes above which a whole-file read returns a head plus a line count instead of the file.
  #
  # The old tool truncated at MAX_READ_BYTES mid-line and said only "... [truncated]" -- no total, no
  # hint that a range was possible -- so the model could not do better even in principle. Observed on
  # a 2000-line source file: one read_file spent 16124 tokens, a quarter of a 64K window, to answer a
  # question an outline would have served.
  #
  # The design is ported from bar-bot's coding agent, which had already solved this in Crystal, and it
  # matches what a survey of established harnesses found: they enforce context economy through BOUNDED
  # READ DEFAULTS in the tool itself rather than through a "grep before reading" rule in the system
  # prompt. A rule the model may ignore is weaker than a tool that cannot overspend.
  LARGE_FILE_BYTES = 20_000
  HEAD_LINES       =    200

  # Directories never worth walking for source. A plain "**/*" walk of this repo descends into .git
  # (thousands of loose objects), into lib/ (every installed shard's full source) and into any build
  # output, which is slow and buries the real hits.
  NOISE_DIRS = {".git", "node_modules", "dist", "build", "vendor", "target", ".cache", "lib", "bin", ".shards"}

  # Most matching lines returned before the rest are summarized as a count.
  MAX_MATCHES = 120

  private def self.noise_path?(rel : String) : Bool
    rel.split('/').any? { |seg| NOISE_DIRS.includes?(seg) }
  end

  private def self.relativize(path : String) : String
    ws = workspace
    path.starts_with?("#{ws}/") ? path[(ws.size + 1)..] : path
  end

  # Set by the SIGINT handler, read by the generation loop.
  #
  # Ctrl-C used to kill the process outright, which on this model means losing a loaded 9 GB of
  # weights, the KV cache and the whole conversation because a turn went somewhere unhelpful -- and a
  # 27B prefill takes long enough that wanting out mid-turn is routine, not exceptional. A flag the
  # decoder checks each token turns that into abandoning one turn.
  @@cancelled = false

  # Whether a turn is in flight. The SIGINT handler needs this to decide between cancelling the turn
  # and treating the press as "I want out": the same key means different things at a prompt and
  # mid-generation, and guessing wrong either strands the user or discards their work.
  @@generating = false

  def self.generating? : Bool
    @@generating
  end

  def self.generating=(v : Bool)
    @@generating = v
  end

  def self.cancelled? : Bool
    @@cancelled
  end

  def self.cancel!
    @@cancelled = true
  end

  def self.clear_cancel!
    @@cancelled = false
  end

  # Bracketed paste. A terminal told to enable it wraps pasted text in these markers, which is the
  # only reliable way to tell "the user pasted four lines" from "the user sent four messages" --
  # timing heuristics misfire on a slow terminal and on a fast typist alike.
  PASTE_START = "\e[200~"
  PASTE_END   = "\e[201~"

  def self.enable_bracketed_paste
    return unless STDIN.tty?
    STDERR.print "\e[?2004h"
    STDERR.flush
  end

  def self.disable_bracketed_paste
    return unless STDIN.tty?
    STDERR.print "\e[?2004l"
    STDERR.flush
  end

  # Read one submission, joining a bracketed paste into a single multi-line string.
  #
  # Plain `gets` ends the turn at the first newline, so pasting a stack trace or a code block sent the
  # first line as the prompt and left the rest queued as separate turns -- the model answered a
  # fragment while the remainder arrived as nonsense follow-ups. Returns nil on EOF (Ctrl-D).
  def self.read_submission : String?
    line = gets
    return if line.nil?

    unless line.includes?(PASTE_START)
      return line.chomp
    end

    # Everything from the marker onward is pasted content; keep reading until the closing marker.
    buf = [] of String
    first = line.split(PASTE_START, 2)[1]
    if first.includes?(PASTE_END)
      return first.split(PASTE_END, 2)[0].chomp
    end
    buf << first.chomp
    while nxt = gets
      if nxt.includes?(PASTE_END)
        buf << nxt.split(PASTE_END, 2)[0]
        break
      end
      buf << nxt.chomp
    end
    text = buf.join("\n")
    lines = text.count('\n') + 1
    STDERR.puts "  #{"pasted #{lines} line(s), #{text.bytesize} B".colorize(:dark_gray)}" if lines > 1
    text
  end

  # One dimmed line describing what a tool returned.
  #
  # Results previously went only into the model's context, so the human watching saw the CALL and then
  # nothing: a read that came back empty, a search that matched nothing, and a search that matched a
  # hundred lines were indistinguishable on screen. That is the difference between watching an agent
  # work and watching a spinner. An error shows its first line, because the reason a retry is happening
  # is exactly what a person needs in order to intervene.
  def self.summarize_result(result : String) : String
    first = result.lines.first?.to_s.strip
    return "↳ (empty)" if result.strip.empty?
    if first.starts_with?("Error")
      return "↳ #{first[0, 100]}"
    end
    lines = result.count('\n') + 1
    kb = result.bytesize >= 1024 ? " · #{(result.bytesize / 1024.0).round(1)} KB" : " · #{result.bytesize} B"
    # A file read already states its own range in the header, and a no-match search says so; echoing
    # a line count over those adds nothing, so show their own first line instead.
    if first.starts_with?("// ") || first.starts_with?("No matches") || first.starts_with?("No files")
      "↳ #{first[0, 100]}"
    else
      "↳ #{lines} line(s)#{kb}"
    end
  end

  # Structural regex metacharacters. A bare '.' is deliberately NOT here: it appears in almost every
  # literal search ("agent.cr", "File.read") and as a regex it still matches the literal, so treating
  # it as an intent signal would fire constantly for no gain.
  REGEX_METACHARS = /[|()\[\]+*?{}^$]/

  # Search file contents, returning "path:line: text" lines.
  #
  # git grep first: it is far faster than walking the tree in-process and it honours .gitignore, so
  # generated and vendored files do not drown the real hits. It is not always available -- the
  # workspace may not be a repo, or git may not be installed -- so the in-process walk stays as the
  # fallback rather than as dead code, and both paths are held to the same output budget.
  #
  # A zero-hit LITERAL search whose pattern looks like a regex is retried as one. Matching literally by
  # default is right -- it cannot produce surprising hits -- but observed behaviour is that the model
  # writes an alternation without setting regex and then misreads the empty result: in one session it
  # searched "puts|print|colorize|…", got nothing, concluded the path parameter rejects files (it does
  # not -- that same query matches 46 lines), changed the path AND dropped the alternation together,
  # and credited the wrong change. Two calls wasted and a false belief to reason from. The retry only
  # ever fires when the strict answer was already empty, so it cannot mask a real result, and it says
  # what it did so the next call is better formed.
  def self.search_contents(root : String, pattern : String, glob : String?,
                           context : Int32, regex : Bool) : String
    hit = git_grep(root, pattern, glob, context, regex)
    hit ||= walk_grep(root, pattern, glob, context, regex)
    return hit unless hit == "No matches." && !regex && pattern.matches?(REGEX_METACHARS)

    retried = git_grep(root, pattern, glob, context, true) ||
              walk_grep(root, pattern, glob, context, true)
    return hit if retried == "No matches."
    "(no literal match; retried as a regular expression — pass regex=true to do this directly)\n#{retried}"
  end

  # Returns nil when git grep could not run, so the caller falls back.
  private def self.git_grep(root : String, pattern : String, glob : String?,
                            context : Int32, regex : Bool) : String?
    rel = relativize(root)
    args = ["grep", "-nI", "--no-color", "--untracked", "-i"]
    args += ["-C", context.to_s] if context > 0
    args << (regex ? "-E" : "-F")
    args += ["-e", pattern, "--"]
    if glob && !glob.empty?
      spec = glob.includes?("/") ? glob : "**/#{glob}"
      prefix = (rel == "." || rel.empty?) ? "" : "#{rel.rstrip('/')}/"
      args << ":(glob)#{prefix}#{spec}"
    elsif rel != "." && !rel.empty?
      args << rel
    end

    stdout = IO::Memory.new
    stderr = IO::Memory.new
    status = Process.run("git", args, output: stdout, error: stderr, chdir: workspace)
    # Exit 1 is "no matches", which is a real answer. Anything else (128 = not a repo, or git
    # missing) means the search did not happen, so say so by returning nil.
    return unless status.exit_code == 0 || status.exit_code == 1
    bound_matches(stdout.to_s.lines.map(&.chomp).reject(&.empty?))
  rescue
    nil
  end

  private def self.walk_grep(root : String, pattern : String, glob : String?,
                             context : Int32, regex : Bool) : String
    re = begin
      regex ? Regex.new(pattern, Regex::Options::IGNORE_CASE) : Regex.new(Regex.escape(pattern), Regex::Options::IGNORE_CASE)
    rescue ex
      return "Error: invalid regex: #{ex.message}"
    end

    files = Dir.exists?(root) ? Dir.glob(File.join(root, "**", "*")) : [root]
    hits = [] of String
    files.each do |f|
      break if hits.size >= MAX_MATCHES
      rel = relativize(f)
      next if noise_path?(rel)
      next if Dir.exists?(f) || !File.exists?(f) || File.size(f) > 2_000_000
      next if glob && !glob.empty? && !File.match?(glob.includes?("/") ? glob : "**/#{glob}", rel)
      begin
        lines = File.read_lines(f)
        lines.each_with_index do |line, i|
          next unless re.matches?(line)
          lo = Math.max(0, i - context)
          hi = Math.min(lines.size - 1, i + context)
          (lo..hi).each { |j| hits << "#{rel}:#{j + 1}: #{lines[j].strip}" }
          break if hits.size >= MAX_MATCHES
        end
      rescue
        # unreadable or binary
      end
    end
    bound_matches(hits)
  end

  # Hold match output to the same budget as a file read: long lines cut, total bounded, and the
  # overflow reported as a count with the remedy rather than silently dropped.
  private def self.bound_matches(lines : Array(String)) : String
    return "No matches." if lines.empty?
    kept = lines.first(MAX_MATCHES)
    body = kept.map do |l|
      l.size > MAX_LINE_CHARS ? "#{l[0, MAX_LINE_CHARS]} …[+#{l.size - MAX_LINE_CHARS} chars]" : l
    end
    text = body.join("\n")
    if text.bytesize > LARGE_FILE_BYTES
      acc = [] of String
      used = 0
      body.each do |l|
        break if used + l.bytesize + 1 > LARGE_FILE_BYTES
        used += l.bytesize + 1
        acc << l
      end
      text = acc.join("\n")
      return "#{text}\n… output truncated at #{acc.size} of #{lines.size} matching lines; narrow the pattern, the glob or the path."
    end
    if lines.size > kept.size
      "#{text}\n… and #{lines.size - kept.size} more matches; narrow the pattern, the glob or the path."
    else
      text
    end
  end

  # Find files by NAME. Returns paths only, so the model can pick what to read.
  def self.glob_files(root : String, pattern : String) : String
    spec = File.join(root, pattern)
    found = Dir.glob(spec).reject do |p|
      rel = relativize(p)
      noise_path?(rel) || Dir.exists?(p)
    end
    return "No files match #{pattern}." if found.empty?
    rels = found.map { |p| relativize(p) }.sort!
    shown = rels.first(MAX_MATCHES)
    head = "#{rels.size} file(s) match #{pattern}"
    body = shown.join("\n")
    if rels.size > shown.size
      "#{head} (showing #{shown.size}):\n#{body}\n… narrow the pattern to see the rest."
    else
      "#{head}:\n#{body}"
    end
  end

  # Longest tool argument value shown on the call line.
  #
  # The call line used to print every argument through `inspect` in full, so a write_file or
  # apply_patch carrying a whole file scrolled the entire payload past the user -- the one moment they
  # most need to SEE what is about to happen is the moment the screen fills with it. The name and the
  # size are what a person checks; the body is already shown by the confirmation diff.
  ARG_PREVIEW_CHARS = 72

  # Format tool-call arguments for the one-line display: short values verbatim, long ones cut with
  # their real size, so a large patch reads as "patch=\"*** Begin Patch…\" (+4182 chars)".
  def self.format_args(args : Hash(String, String)) : String
    args.map do |k, v|
      if v.size > ARG_PREVIEW_CHARS
        "#{k}=#{v[0, ARG_PREVIEW_CHARS].inspect} (+#{v.size - ARG_PREVIEW_CHARS} chars)"
      else
        "#{k}=#{v.inspect}"
      end
    end.join(", ")
  end

  # Longest single line returned before it is cut.
  #
  # A line-count cap alone does NOT bound the response: 200 lines of minified JavaScript, generated
  # code or an embedded data blob is still enormous, so the head limit above would be satisfied while
  # the budget was blown anyway. Claude Code truncates each line to 2000 characters for this reason.
  # 500 is tighter because our window is 64K rather than 200K, and a source line past 500 characters
  # is nearly always machine-written.
  MAX_LINE_CHARS = 500

  # Render a file for the model: line-numbered, with a header saying which lines these are of how many.
  #
  # The header is what makes paging possible. A model that sees "lines 1-200 of 2093" knows both that
  # there is more and exactly how to ask for it; one handed a silent truncation knows neither.
  def self.render_file(display_path : String, content : String,
                       start_line : Int32?, end_line : Int32?) : String
    lines = content.split('\n')
    total = lines.size

    if start_line || end_line
      s = Math.max(1, start_line || 1)
      e = Math.min(total, end_line || total)
      return "Error: line #{s} is past the end of #{display_path} (#{total} lines)" if s > total
      return "Error: end_line #{e} is before start_line #{s}" if e < s
      kept = fit_lines(lines, s - 1, e - s + 1)
      last = s + kept - 1
      note = last < e ? "; clipped at line #{last} to stay inside the context budget, ask for the rest" : ""
      return "// #{display_path} — lines #{s}-#{last} of #{total}#{note}\n" \
             "#{number_lines(lines[(s - 1), kept], s, last)}"
    end

    if content.bytesize > LARGE_FILE_BYTES
      kept = fit_lines(lines, 0, HEAD_LINES)
      "// #{display_path} — lines 1-#{kept} of #{total}; file is large, so this is only the head. " \
      "Call read_file again with start_line/end_line for a specific range, or use search to locate " \
      "what you need first.\n#{number_lines(lines[0, kept], 1, kept)}"
    else
      "// #{display_path} — #{total} lines\n#{number_lines(lines, 1, total)}"
    end
  end

  # How many lines starting at `from` fit inside the byte budget, up to `want` of them.
  #
  # A line COUNT cap does not bound the response on its own, and neither does a per-line cap: 200
  # lines of 500 characters is still 100 KB, about 26K tokens, which would defeat the whole point on a
  # 64K window. Only counting the bytes actually does it. Measured on 400 lines of 2000 characters --
  # the shape of minified or generated code -- this is what takes an 800 KB file to a bounded reply
  # instead of a 104 KB one.
  #
  # At least one line is always returned, so a single enormous line still yields something rather than
  # an empty response.
  private def self.fit_lines(lines : Array(String), from : Int32, want : Int32) : Int32
    budget = LARGE_FILE_BYTES
    used = 0
    kept = 0
    while kept < want && (from + kept) < lines.size
      line = lines[from + kept]
      cost = Math.min(line.bytesize, MAX_LINE_CHARS) + 10 # +10 for the "NNNN | " gutter
      break if kept > 0 && used + cost > budget
      used += cost
      kept += 1
    end
    kept
  end

  private def self.number_lines(slice : Array(String), from : Int32, upto : Int32) : String
    width = upto.to_s.size
    slice.map_with_index do |line, i|
      shown = if line.size > MAX_LINE_CHARS
                "#{line[0, MAX_LINE_CHARS]} …[+#{line.size - MAX_LINE_CHARS} chars]"
              else
                line
              end
      "#{(from + i).to_s.rjust(width)} | #{shown}"
    end.join("\n")
  end

  # Did this reply START a tool call without finishing it?
  #
  # This is the precise signal, and it beats guessing from prose. The observed failure was the model
  # emitting its preamble inside a <think> block and then getting 81 characters into the call before
  # generation stopped -- right after </parameter>, with </function></tool_call> missing. The parser
  # needs the closing tag, so it returned nothing and the loop treated a half-written call as the
  # final answer.
  #
  # Counting the tags is unambiguous where prose heuristics are not: an earlier version of this looked
  # for "let's" / "i'll" openers and missed the real case entirely, because once the <think> block was
  # stripped the remaining text began with "<tool_call>".
  def self.truncated_tool_call?(text : String) : Bool
    opens = text.split("<tool_call>").size - 1
    closes = text.split("</tool_call>").size - 1
    opens > closes
  end

  # Did the model reply with nothing usable at all -- no call, no answer?
  #
  # Distinct from a truncated call: here it never started one and said nothing either, so there is
  # nothing to salvage and nothing to show the user.
  def self.empty_reply?(visible : String) : Bool
    visible.strip.empty?
  end

  def self.parse_tool_calls(text : String) : Array(ToolCall)
    text = text.scrub # never run regex on invalid UTF-8 (broken-model output)
    calls = [] of ToolCall
    text.scan(/<tool_call>(.*?)<\/tool_call>/m) do |m|
      body = m[1]
      fmatch = body.match(/<function=([^>\s]+)>(.*)/m)
      next unless fmatch
      name = fmatch[1].strip
      next if name.empty? || name == "none" # ignore placeholder/hallucinated calls
      args = {} of String => String
      fmatch[2].scan(/<parameter=([^>\s]+)>\n?(.*?)\n?<\/parameter>/m) do |pm|
        args[pm[1].strip] = pm[2]
      end
      calls << ToolCall.new(name, args)
    end
    calls
  end

  class Agent
    @im_start : Int32
    @im_end : Int32
    @nl : Array(Int32)
    @stop_ids : Array(Int32)
    @system_block : String
    @messages : Array(Message)
    @recent_calls : Array(String)
    @sampler : SHAInet::Sampler
    getter max_context : Int32

    def initialize(@net : SHAInet::Network, @tokenizer : SHAInet::BPETokenizer, @tools : Array(Tool), @max_context : Int32 = 65536)
      im_start = @tokenizer.vocab["<|im_start|>"]?
      im_end = @tokenizer.vocab["<|im_end|>"]?
      raise "model is not ChatML (<|im_start|>/<|im_end|> missing); this agent targets Qwen3-style models" unless im_start && im_end
      @im_start = im_start.not_nil!
      @im_end = im_end.not_nil!
      @nl = @tokenizer.encode("\n")
      @stop_ids = [@im_end]
      ["<|endoftext|>", "<|end_of_text|>"].each { |n| (id = @tokenizer.vocab[n]?) && @stop_ids << id }
      @system_block = AgentDemo.render_tools_block(@tools)
      @recent_calls = [] of String
      @sampler = SHAInet::Sampler.new(temperature: 0.3, top_k: 20, repetition_penalty: 1.1)
      @messages = [] of Message
    end

    # <|im_start|>{role}\n{content}<|im_end|>\n
    private def render_message(role : String, content : String) : Array(Int32)
      ids = [@im_start]
      ids.concat(@tokenizer.encode("#{role}\n#{content}"))
      ids << @im_end
      ids.concat(@nl)
      ids
    end

    # Same framing, but with the assistant's body taken VERBATIM from the tokens the model
    # emitted. This is what makes the KV prefix match: during generation the cache holds
    # `<|im_start|>assistant\n` followed by exactly these ids, so the cache is a true prefix
    # of the next prompt and only the tail has to be prefilled.
    private def render_assistant(body : Array(Int32)) : Array(Int32)
      ids = [@im_start]
      ids.concat(@tokenizer.encode("assistant\n"))
      ids.concat(body)
      ids << @im_end
      ids.concat(@nl)
      ids
    end

    private def build_prompt : Array(Int32)
      ids = render_message("system", @system_block)
      @messages.each do |m|
        if m.role == "tool"
          ids.concat(render_message("user", "<tool_response>\n#{m.content}\n</tool_response>"))
        elsif body = m.ids
          ids.concat(render_assistant(body))
        else
          ids.concat(render_message(m.role, m.content))
        end
      end
      ids << @im_start
      ids.concat(@tokenizer.encode("assistant\n"))
      ids
    end

    # Current prompt size in tokens (full transcript + assistant primer).
    def context_tokens : Int32
      build_prompt.size
    end

    def reset
      @messages.clear
      # Also drop the KV cache. Prefix reuse would stay correct without this -- a shorter
      # prompt cannot be an extension of the old cache, so it would fall back to a full
      # prefill -- but there is no reason to keep the old conversation's cache resident.
      reset_cache!
    end

    # Bound a tool result in TOKENS, not bytes.
    #
    # The tools already cap their output at MAX_READ_BYTES, but bytes are the wrong unit: the
    # binding constraint is the context window, and the bytes-per-token ratio varies wildly.
    # 64 KB of English is roughly 16k tokens; 64 KB of a compiled binary tokenized to 60534
    # in one observed run, which then tried to prefill against an 8192-token window.
    # Compaction cannot rescue that either, because it drops the OLDEST messages while the
    # offending one is the newest.
    #
    # A quarter of the window leaves room for the transcript, the primer and a reply.
    private def clamp_tool_result(result : String) : String
      budget = @max_context // 4
      ids = @tokenizer.encode(result)
      return result if ids.size <= budget
      kept = @tokenizer.decode(ids[0, budget]).scrub
      "#{kept}\n... [truncated: #{ids.size} tokens exceeded the #{budget}-token tool budget]"
    end

    # Tokens one message contributes to the prompt.
    private def message_tokens(m : Message) : Int32
      if m.role == "tool"
        render_message("user", "<tool_response>\n#{m.content}\n</tool_response>").size
      else
        render_message(m.role, m.content).size
      end
    end

    # Summarize a slice of old messages into a single concise note using the
    # model itself (Claude/Kiro-style compaction) so history is condensed rather
    # than lost. Falls back to a plain marker if the model returns nothing.
    private def summarize(msgs : Array(Message)) : String
      transcript = String.build do |s|
        msgs.each { |m| s << m.role << ": " << m.content << "\n\n" }
      end
      instruction = "Summarize the following conversation between a user and an AI coding " \
                    "assistant. Preserve key facts, decisions, file paths, tool results, and " \
                    "any unfinished tasks. Be concise.\n\n#{transcript}"
      prompt = render_message("system", "You write concise, faithful conversation summaries.")
      prompt.concat(render_message("user", instruction))
      prompt << @im_start
      prompt.concat(@tokenizer.encode("assistant\n"))
      summary = generate_from(prompt, 384)[0].strip
      summary.empty? ? TRUNCATION_MARKER : summary
    end

    # Compact the transcript to fit `target` tokens: keep a recent tail, and
    # replace the older head with a model-written summary. Hard-trims as a last
    # resort if it still doesn't fit. Returns tokens removed.
    def compact!(target : Int32) : Int32
      before = context_tokens
      return 0 if before <= target || @messages.size <= 1

      # Keep the most recent messages within ~half the target; summarize the rest.
      keep_budget = target // 2
      tail = [] of Message
      tail_tokens = 0
      @messages.reverse_each do |m|
        t = message_tokens(m)
        break if !tail.empty? && tail_tokens + t > keep_budget
        tail.unshift(m)
        tail_tokens += t
      end
      head = @messages[0, @messages.size - tail.size]

      if head.empty?
        # Nothing old enough to summarize — fall back to plain truncation.
        return truncate!(target)
      end

      summary = summarize(head)
      @messages = [Message.new("user", "[Summary of earlier conversation]\n#{summary}")] + tail
      # If the summary + tail still overflow, drop oldest until it fits.
      truncate!(target)
      before - context_tokens
    end

    # Plain sliding-window drop of oldest messages with a marker. Returns tokens removed.
    private def truncate!(target : Int32) : Int32
      before = context_tokens
      trimmed = false
      while context_tokens > target && @messages.size > 1
        @messages.shift
        trimmed = true
      end
      if trimmed && (@messages.empty? || @messages.first.content != TRUNCATION_MARKER)
        @messages.unshift(Message.new("user", TRUNCATION_MARKER))
      end
      before - context_tokens
    end

    TRUNCATION_MARKER = "[Earlier conversation was truncated to fit the context window.]"

    # One-line status: context usage, VRAM, expert-cache hit rate.
    def status : String
      parts = ["ctx #{context_tokens}/#{@max_context} tok"]
      if info = SHAInet::CUDA.memory_info
        used = info[:total] - info[:free]
        mb = 1024.0 * 1024.0
        parts << "VRAM #{(used / mb).round}/#{(info[:total] / mb).round} MB (#{(100.0 * used / info[:total]).round}%)"
      end
      if ENV.fetch("SHAINET_MOE_OFFLOAD", "0") == "1" && SHAInet::CUDA.fully_available?
        cs = SHAInet::Q4HostMatrix.cache_stats
        if cs[:hits] + cs[:misses] > 0
          parts << "cache #{(cs[:hit_rate] * 100).round}% hit"
        end
      end
      "[#{parts.join(" · ")}]"
    end

    # Tokens currently held in the KV cache, in order. This is what makes turn 2 onwards
    # cheap: the cache already contains the whole conversation so far, so only the new tail
    # has to be prefilled.
    @cache_ids = [] of Int32

    # Clearing the KV cache and forgetting what it held MUST happen together. If they drift,
    # a later turn believes the cache still holds a prefix that is gone and reuses it, which
    # is silently wrong output rather than an error.
    private def reset_cache!
      @net.clear_cache!
      @cache_ids.clear
    end

    # Prefill `prompt`, reusing whatever the KV cache already holds.
    #
    # This used to clear the cache and re-prefill the entire transcript on EVERY call, and
    # the tool loop calls it once per step -- so one request with three tool calls paid four
    # full prefills of a growing context. At 16k that is around 405 s each, which is the
    # multi-minute silence between an answer and the next action. It was never hidden
    # reasoning; it was prefill with nothing to show.
    #
    # build_prompt appends, so consecutive prompts share a long prefix. Reuse is only taken
    # when the cache is EXACTLY a prefix of the new prompt: a KV cache cannot drop a suffix,
    # so a partial match cannot be salvaged. If the assistant's text re-tokenizes differently
    # from the tokens that were generated, the common prefix simply ends early and this falls
    # back to a full prefill -- slower, never wrong.
    private def prefill(prompt : Array(Int32)) : SHAInet::SimpleMatrix
      shared = 0
      limit = Math.min(@cache_ids.size, prompt.size)
      while shared < limit && @cache_ids[shared] == prompt[shared]
        shared += 1
      end

      if shared == @cache_ids.size && shared > 0 && shared < prompt.size
        reused = shared
        tail = prompt[shared..]
        STDERR.puts "  reusing #{reused} cached tok · prefilling #{tail.size}".colorize(:dark_gray)
        logits = run_prefill(tail, reused, prompt.size)
        record_prefilled(prompt)
        logits
      else
        STDERR.puts "  prefilling #{prompt.size} tok from scratch".colorize(:dark_gray) if prompt.size > 512
        reset_cache!
        logits = run_prefill(prompt, 0, prompt.size)
        record_prefilled(prompt)
        logits
      end
    end

    # Record what the KV cache now holds -- unless the prefill was interrupted, in which case throw the
    # cache away.
    #
    # An interrupted prefill leaves the cache holding FEWER tokens than the prompt, so claiming the
    # whole prompt would make the next turn "reuse" a prefix that is not physically there. That is
    # silent corruption of the kind this codebase has already produced once (a clear_cache! that missed
    # the recurrent blocks), and it is the exact hole an audit flagged as the next one of its family:
    # nothing asserts that a prefix reuser's cache length matches the prefix it claims. An aborted turn
    # does not need to be fast, it needs to leave the next one correct.
    private def record_prefilled(prompt : Array(Int32))
      if AgentDemo.cancelled?
        reset_cache!
        STDERR.puts "  #{"cache cleared after the interrupted prefill".colorize(:dark_gray)}"
      else
        @cache_ids = prompt.dup
      end
    end

    # Feed tokens to the model in slices so there is something to show. The KV cache
    # accumulates across calls, so slicing is equivalent to one call.
    private def run_prefill(ids : Array(Int32), already : Int32, total : Int32) : SHAInet::SimpleMatrix
      slice = (ENV["SHAINET_PREFILL_SLICE"]? || "0").to_i
      slice = ids.size if slice <= 0
      logits = nil
      i = 0
      t0 = Time.monotonic
      # Per-layer progress callback
      @net.prefill_progress = ->(layer_idx : Int32, total_layers : Int32) do
        elapsed = (Time.monotonic - t0).total_seconds
        pct = layer_idx * 100 // total_layers
        STDERR.print "\r  prefill layer #{layer_idx}/#{total_layers} (#{pct}%) · #{elapsed.round(0).to_i}s".colorize(:dark_gray)
        STDERR.flush
        nil
      end
      while i < ids.size
        n = Math.min(slice, ids.size - i)
        logits = @net.run(ids[i, n], stealth: true, return_matrix: true).as(SHAInet::SimpleMatrix)
        i += n
        done = already + i
        elapsed = (Time.monotonic - t0).total_seconds
        STDERR.print "\r  prefill #{done}/#{total} tok (#{done * 100 // total}%) · #{elapsed.round(0).to_i}s".colorize(:dark_gray)
        STDERR.flush
        # Prefill is the OTHER long blocking phase, and the one most worth escaping: a cold 60K prefill
        # runs for minutes, and realizing the prompt was wrong 20 seconds in should not mean waiting it
        # out. Same reason as the decode loop -- without a yield the signal fiber never runs -- and the
        # cost is one yield per chunk, not per token.
        Fiber.yield
        if AgentDemo.cancelled?
          STDERR.print "\r\033[K"
          STDERR.puts "  #{"interrupted during prefill".colorize(:yellow)}"
          break
        end
      end
      @net.prefill_progress = nil
      STDERR.print "\r\033[K"
      logits.not_nil!
    end

    # Generate from an explicit prompt. When echo is set, the user-facing prose is streamed
    # live (with <think> and tool-call markup filtered out).
    private def generate_from(prompt : Array(Int32), max_tokens : Int32, echo : Bool = false) : Tuple(String, Array(Int32))
      logits = prefill(prompt)
      generated = [] of Int32
      renderer = echo ? AgentDemo::StreamRenderer.new(STDERR) : nil
      prev = ""
      max_tokens.times do
        # Let the scheduler run the signal-handling fiber.
        #
        # Without this the Ctrl-C handler NEVER RUNS. Crystal catches the signal in a C handler that
        # only writes to a pipe; the block registered with Process.on_terminate is invoked by a
        # dedicated fiber reading that pipe. This loop is single-threaded and CPU/GPU bound with no
        # other yield point, so the scheduler never gets control and that fiber never runs -- measured
        # directly: 40 iterations of heavy compute with a signal already pending, handler never fired;
        # the same loop with this line fired on the first iteration. The earlier version of this
        # feature was therefore inert, and pressing Ctrl-C repeatedly did nothing until SIGQUIT dumped
        # core.
        #
        # Costs 786 ns, against roughly 85 ms per token.
        Fiber.yield
        # Abandon the turn on Ctrl-C. Checked per token rather than per tool step so a long answer
        # stops promptly; the partial text stays on screen and in history, which is what makes the
        # next instruction ("no, not that file") land in context that explains itself.
        if AgentDemo.cancelled?
          STDERR.puts "\n  #{"interrupted".colorize(:yellow)}"
          break
        end
        row = logits.rows - 1
        # The repetition penalty must NOT run inside a tool call.
        #
        # Tool-call syntax is repetitive BY DESIGN -- <function=read_file> and </function> share the
        # token "function", every argument repeats <parameter= and </parameter>. With window 20 the
        # tokens needed to CLOSE the call are still inside the window from opening it, so they get
        # penalised exactly when they are the only correct choice, and the sampler takes <|im_end|>
        # instead. Observed: generation stopped 81 characters in, immediately after </parameter>,
        # leaving </function></tool_call> unwritten and the call unparseable.
        #
        # Prose still gets the penalty, which is where it earns its keep.
        unless AgentDemo.truncated_tool_call?(prev)
          @sampler.apply_repetition_penalty!(logits, generated, window: 20, row: row)
        end
        id = @sampler.sample(logits, row)
        break if id < 0 || @stop_ids.includes?(id)
        break unless logits[row, id].finite?
        generated << id
        # Decoded unconditionally, not just when echoing: the tool-call state above is derived from
        # it, so a non-echoing call (/ask) needs it too.
        full = @tokenizer.decode(generated).scrub
        if r = renderer
          r.feed(full[prev.size..]) if full.size > prev.size
        end
        prev = full
        logits = @net.run([id], stealth: true, return_matrix: true).as(SHAInet::SimpleMatrix)
        # The sampled token is now in the cache too, so the next turn can reuse it.
        @cache_ids << id
      end
      renderer.try(&.finish)
      # scrub: a broken model can emit tokens that decode to invalid UTF-8, which
      # would crash downstream regex/parsing. The raw ids go back too: the decoded text is
      # for humans and parsing, the ids are what the KV cache actually holds.
      {@tokenizer.decode(generated).scrub, generated}
    end

    # Generate one assistant turn from the current transcript, streaming the
    # filtered prose live. Re-prefills the whole (growing) context each call.
    private def generate(max_tokens : Int32) : Tuple(String, Array(Int32))
      generate_from(build_prompt, max_tokens, echo: true)
    end

    # Handle one user input: run the tool loop until the model answers plainly.
    def chat(input : String, max_tokens : Int32)
      @messages << Message.new("user", input)
      @recent_calls.clear
      # One OOM recovery per turn: a second failure after compacting is not a transient.
      compacted_for_oom = false
      empty_nudges = 0
      step = 0
      loop do
        step += 1
        # A cancel during a tool step must also end the LOOP, not just the token stream it was in --
        # otherwise the decoder returns early and the loop calmly starts the next step.
        break if AgentDemo.cancelled?
        # The LAST allowed step still generates, it just may not call tools. Breaking before
        # generation (which is what this did) threw the turn away: the user got the cap
        # message and no answer, after the agent had already done the work. So tell the model
        # its budget is gone and let it write a closing reply from what it has.
        last_step = step >= MAX_TOOL_STEPS
        if step > MAX_TOOL_STEPS
          break
        end
        if last_step
          STDERR.puts "  [agent] tool budget reached (#{MAX_TOOL_STEPS} steps); asking for a final answer".colorize(:dark_gray)
          STDERR.puts "  (raise it with AGENT_MAX_TOOL_STEPS)".colorize(:dark_gray)
          @messages << Message.new("user",
            "You have used all #{MAX_TOOL_STEPS} tool steps for this turn. Do not call any " \
            "more tools. Answer now with what you already have, and say plainly what you " \
            "could not finish.")
        end

        # Keep the prompt within the context budget (compact to 75% to leave room
        # for the response + any tool round-trips before the next compaction).
        if context_tokens > @max_context
          removed = compact!((@max_context * 0.75).to_i)
          STDERR.puts "  [agent] context compacted (−#{removed} tokens)" if removed > 0
        end

        STDERR.print "\n#{"Agent".colorize(:light_cyan).bold} ❯ "
        STDERR.flush
        begin
          text, text_ids = generate(max_tokens) # streams the filtered prose inline
        rescue ex
          # An allocation failure is recoverable, and losing the turn to it is the wrong answer.
          #
          # Auto-compaction only triggers above @max_context, but VRAM can run out BELOW it -- a
          # reported session died at 15401 of 16384 tokens, failing a 64 MB allocation with 79 MB
          # free, throwing away several minutes of tool work. The cache and context are exactly what
          # the memory is holding, so drop both hard and try once more before giving up.
          oom = ex.message.to_s.downcase.includes?("memory allocation") ||
                ex.message.to_s.downcase.includes?("out of memory")
          if oom && !compacted_for_oom
            compacted_for_oom = true
            reset_cache!
            removed = compact!((@max_context * 0.5).to_i)
            STDERR.puts "\n  [agent] out of GPU memory at #{context_tokens + removed} tokens; " \
                        "compacted to #{context_tokens} (−#{removed}) and retrying".colorize(:yellow)
            next
          end
          STDERR.puts "\n  [agent] generation failed: #{ex.message}".colorize(:red)
          STDERR.puts "  (out of GPU memory? try /clear, a shorter request, or a smaller SHAINET_EXPERT_CACHE_MB)".colorize(:dark_gray)
          reset_cache!
          break
        end
        STDERR.puts ""
        calls = AgentDemo.parse_tool_calls(text)

        # If the model generated only think tags or whitespace, the user sees nothing.
        visible = text.gsub(/<think>.*?<\/think>/m, "").gsub(/<tool_call>.*?<\/tool_call>/m, "").strip
        if visible.empty? && calls.empty?
          STDERR.puts "  [agent] model returned no visible text".colorize(:dark_gray)
        end

        # Keep the assistant's output (incl. any tool_call markup) verbatim.
        @messages << Message.new("assistant", text.strip, text_ids)

        # A short reply with no tool call is almost always a DROPPED call, not an answer.
        #
        # This model's own chat template says reasoning may come "in natural language BEFORE the
        # function call, but NOT after", so a turn that ends on a one-line preamble has stopped in
        # the middle of the format it was told to use. Observed verbatim: asked to analyse a file,
        # the model replied "Let's take a look at the file." and ended the turn -- the loop treated
        # that as the final answer, printed it, and handed the prompt back having done nothing.
        #
        # Nudging costs one extra generation; accepting it costs the whole request. Bounded so a
        # model that genuinely wants to answer briefly is not badgered, and skipped on the last step
        # where there would be no chance to act on a call anyway.
        truncated = AgentDemo.truncated_tool_call?(text)
        if calls.empty? && !last_step && empty_nudges < EMPTY_REPLY_NUDGE_LIMIT &&
           (truncated || AgentDemo.empty_reply?(visible))
          empty_nudges += 1
          if truncated
            STDERR.puts "  [agent] tool call was cut off mid-write; asking for it again".colorize(:yellow)
            @messages << Message.new("tool",
              "Your last reply began a <tool_call> but stopped before closing it, so nothing ran. " \
              "Send the SAME call again, complete, as the entire reply -- every <parameter> closed, " \
              "then </function>, then </tool_call>. Write nothing after the closing </tool_call>.")
          else
            STDERR.puts "  [agent] reply was empty; asking the model to act or answer".colorize(:yellow)
            @messages << Message.new("tool",
              "Your last reply was empty, so nothing ran and the user saw nothing. Either emit a " \
              "tool call as the entire reply, or give the complete answer.")
          end
          next
        end

        break if calls.empty?
        # On the final step the reply IS the answer. Running its tool calls would spend the
        # results and then break on the next iteration, throwing them away unanswered.
        break if last_step

        calls.each do |c|
          STDERR.puts "  #{"⚒ #{c.name}".colorize(:yellow)}(#{AgentDemo.format_args(c.args)})".colorize(:dark_gray)

          # Break identical repeated calls.
          #
          # Nothing else in the loop can. The repetition penalty runs with window 20 over the
          # CURRENT message's tokens, but a tool call is ~45 tokens and each retry is a separate
          # generate() call, so the penalty never sees that the same call was already made last
          # turn. Observed in practice: a model asked for a path that did not exist, then reissued
          # one malformed list_directory ten times in a row, each round costing a full prefill and
          # ~94 tokens of context, until the step budget ran out.
          sig = "#{c.name}(#{c.args.to_a.sort_by(&.[0]).map { |k, v| "#{k}=#{v}" }.join(",")})"
          repeats = @recent_calls.count(sig)
          if repeats >= REPEAT_CALL_LIMIT
            STDERR.puts "  [agent] same call #{repeats + 1}x; telling the model to change approach".colorize(:yellow)
            @recent_calls.clear
            @messages << Message.new("tool",
              "This exact call was already made #{repeats + 1} times and returned the same result " \
              "each time. Repeating it will not help. Change approach: check the argument against " \
              "the tool's description (list_directory takes a DIRECTORY path, not a shell command " \
              "-- use run_command for shell), try a different tool, or answer with what you have " \
              "and say what you could not determine.")
            next
          end
          @recent_calls << sig
          @recent_calls.shift if @recent_calls.size > RECENT_CALL_MEMORY

          tool = @tools.find { |t| t.name == c.name }
          result =
            if tool
              begin
                tool.call(c.args)
              rescue ex
                "Error running #{c.name}: #{ex.message}"
              end
            else
              "Error: unknown tool #{c.name}"
            end
          @messages << Message.new("tool", clamp_tool_result(result))
          STDERR.puts "    #{AgentDemo.summarize_result(result).colorize(:dark_gray)}"
        end
      end
    end
  end

  # ASCII splash banner.
  def self.print_banner(io : IO, subtitle : String)
    # ameba:disable Style/HeredocEscape
    art = <<-'ASCII'
       ____  _   _    _    ___            _
      / ___|| | | |  / \  |_ _|_ __   ___| |_
      \___ \| |_| | / _ \  | || '_ \ / _ \ __|
       ___) |  _  |/ ___ \ | || | | |  __/ |_
      |____/|_| |_/_/   \_\___|_| |_|\___|\__|
      ASCII
    io.puts
    io.puts art.colorize(:light_cyan).bold
    io.puts "  ▸ Agent ".colorize(:cyan).bold.to_s + "· #{subtitle}".colorize(:dark_gray).to_s
    io.puts
  end

  # System prompt describing the tools in the Qwen3-Coder XML format.
  def self.render_tools_block(tools : Array(Tool)) : String
    String.build do |s|
      s << "You are a helpful AI coding assistant that can interact with the user's"
      s << " computer to solve tasks.\n\n# Tools\n\nYou have access to the following functions:\n\n<tools>"
      tools.each do |t|
        s << "\n<function>\n<name>" << t.name << "</name>"
        s << "\n<description>" << t.description << "</description>\n<parameters>"
        t.params.each do |p|
          s << "\n<parameter>\n<name>" << p.name << "</name>\n<type>" << p.type
          s << "</type>\n<description>" << p.description << "</description>\n</parameter>"
        end
        s << "\n</parameters>\n</function>"
      end
      s << "\n</tools>"
      s << "\n\nIf you choose to call a function ONLY reply in the following format with NO suffix:\n\n"
      s << "<tool_call>\n<function=example_function_name>\n<parameter=example_parameter_1>\nvalue_1\n"
      s << "</parameter>\n</function>\n</tool_call>\n\n"
      s << "<IMPORTANT>\n- Function calls MUST be wrapped in <tool_call></tool_call> with an inner"
      s << " <function=...></function> block.\n- Provide any reasoning BEFORE the call, never after.\n"
      s << "- If no function is needed, just answer normally.\n</IMPORTANT>\n\n"
      # Locating before reading is the difference between three targeted reads and paging a whole
      # file. Asked what to improve in a 1389-line file, the model read the head and then every
      # remaining range in sequence -- five calls, about 24K tokens -- when glob plus search would
      # have pointed at the handful of ranges that mattered. The bounded read stops any single call
      # from being huge; only knowing WHERE to look stops the total from being huge.
      s << "<SEARCH_FIRST>\nTo work on code you have not read, LOCATE before you read:\n"
      s << "1. glob to see which files exist (e.g. pattern='src/**/*.cr').\n"
      s << "2. search for the symbol, message or pattern you care about — it returns path:line, and\n"
      s << "   context=3 shows the surrounding lines.\n"
      s << "3. read_file with start_line/end_line around the lines search pointed at.\n"
      s << "Reading a whole large file, or paging one range after another until you have all of it,"
      s << " spends the context you need for the actual work. Search is cheap; a full read is not.\n"
      s << "</SEARCH_FIRST>"
    end
  end
end

# ----------------------------------------------------------------------------
# Entry point
# ----------------------------------------------------------------------------
model_dir = ARGV[0]?
max_tokens = (ARGV[1]? || ENV["SHAINET_AGENT_MAX_TOKENS"]? || "4096").to_i

# Resolve the model path: Ollama name ("qwen3.8:27b"), GGUF file, or directory.
gguf_mode = false
if model_dir && SHAInet::OllamaResolve.ollama_name?(model_dir)
  resolved = SHAInet::OllamaResolve.resolve(model_dir)
  if resolved
    STDERR.puts "Resolved Ollama '#{model_dir}' -> #{resolved}"
    model_dir = resolved
    gguf_mode = true
  else
    STDERR.puts "Ollama model '#{model_dir}' not found. Is it pulled?"
    exit 1
  end
elsif model_dir && File.file?(model_dir)
  gguf_mode = true
end

unless model_dir && (Dir.exists?(model_dir) || File.file?(model_dir.not_nil!))
  STDERR.puts "Usage: agent <model | gguf-file | ollama-name> [max_tokens]"
  STDERR.puts "  agent ~/models/Qwen3.8-27B/.q4"
  STDERR.puts "  agent qwen3.8:27b"
  exit 1
end

# Colour when a human is watching, and only then. A tty is not sufficient on its own: NO_COLOR is the
# cross-tool convention for "I am a human on a tty and I still do not want escapes" (screen readers,
# logging a session to a file through `script`, a terminal with a palette that renders dark_gray
# unreadable), and TERM=dumb terminals do not interpret the sequences at all.
Colorize.enabled = STDERR.tty? && ENV["NO_COLOR"]?.nil? && ENV["TERM"]? != "dumb"
STDERR.sync = true # stream tokens as they arrive (no buffering)
AgentDemo.print_banner(STDERR, "#{File.basename(model_dir)} · local coding agent on Network#run")

STDERR.puts "Loading model from #{model_dir}...".colorize(:dark_gray)

# Decide the context BEFORE loading, and tell the loader about it.
#
# These were two independent defaults that happened to agree, and when they stopped agreeing the
# failure was an OOM mid-conversation rather than anything legible. The loader sizes its VRAM reserve
# from SHAINET_MAX_CONTEXT so the KV cache has somewhere to grow; the agent separately decided how
# many tokens it would allow. Loading first and reading the agent's context afterwards meant the
# reserve was always built for the LOADER's default no matter what the agent went on to permit -- so
# raising the agent's window silently produced a model with no room for it.
#
# 64K is the default because this architecture is built for it (the GGUF declares 262144) and because
# a 16K window is the difference between an agent that can hold a session and one that compacts every
# few turns. The loader places what fits and leaves the rest on the host, so a smaller card degrades
# in speed rather than failing.
agent_context = (ENV["SHAINET_AGENT_CONTEXT"]? || "65536").to_i
ENV["SHAINET_MAX_CONTEXT"] ||= agent_context.to_s
# A 30B takes about nine minutes here. Without a progress line that is indistinguishable
# from a hang, and the layer loop is where nearly all of it goes.
load_started = Time.monotonic
SHAInet::HFLoader.progress = ->(done : Int32, total : Int32) do
  elapsed = (Time.monotonic - load_started).total_seconds
  eta = done > 0 ? (elapsed / done) * (total - done) : 0.0
  STDERR.print "\r  layer #{done}/#{total} (#{done * 100 // total}%) " \
               "· #{elapsed.round.to_i}s elapsed · ~#{eta.round.to_i}s left".colorize(:dark_gray)
  STDERR.print "\n" if done == total
end
t0 = Time.monotonic
# Q4 + MoE offload are the only configuration a large MoE model actually runs in on a
# single consumer GPU: without them a 30B-A3B does not fit at all. So they are the
# DEFAULT here rather than opt-in. SHAINET_Q8=1 and SHAINET_MOE_OFFLOAD=0 opt out.
ENV["SHAINET_MOE_OFFLOAD"] = "1" unless ENV.has_key?("SHAINET_MOE_OFFLOAD")
quantize = SHAInet::CUDA.fully_available? && !ENV["SHAINET_FP32"]?
bits = ENV.fetch("SHAINET_Q8", "0") == "1" ? 8 : 4
offload = ENV.fetch("SHAINET_MOE_OFFLOAD", "0") == "1"
net = SHAInet::HFLoader.load(model_dir, quantize: quantize, bits: bits)
net.use_kv_cache = true
if gguf_mode
  STDERR.print "Extracting tokenizer from GGUF... ".colorize(:dark_gray)
  STDERR.flush
  tokenizer = SHAInet::GGUF.extract_tokenizer(model_dir)
  STDERR.puts "#{tokenizer.vocab.size} tokens".colorize(:dark_gray)
else
  tokenizer_path = ENV["SHAINET_TOKENIZER_PATH"]? || File.join(model_dir, "tokenizer.json")
  unless File.exists?(tokenizer_path)
    STDERR.puts "Error: tokenizer.json not found."
    exit 1
  end
  tokenizer = SHAInet::BPETokenizer.from_hf(tokenizer_path)
end
has_moe = net.hidden_layers.any? { |l| l.is_a?(SHAInet::LlamaBlock) && l.as(SHAInet::LlamaBlock).ffn.is_a?(SHAInet::MoEFF) }
mode = ENV["SHAINET_FP32"]? ? "fp32" : "Q#{bits}"
mode += " (MoE offload)" if offload && has_moe
STDERR.puts "Loaded in #{(Time.monotonic - t0).total_seconds.round(1)}s · #{mode} (vocab #{tokenizer.vocab.size})"

# Size the expert cache to leave headroom for the model + prefill activations.
# Only relevant for MoE models, where a fraction of experts are active per token and the rest
# are cached in VRAM for reuse. Dense models (Qwen3.5, Qwen3-0.6B) have no experts to cache,
# so reserving VRAM for this wastes 2+ GB that could serve KV context instead.
# Override with SHAINET_EXPERT_CACHE_MB (0 disables).
# Set before the load, so the loader's VRAM reserve and this window cannot disagree.
max_context = agent_context

has_moe = net.hidden_layers.any? { |l| l.is_a?(SHAInet::LlamaBlock) && l.as(SHAInet::LlamaBlock).ffn.is_a?(SHAInet::MoEFF) }

# The reserve has to cover what GROWS with context -- the KV cache above all -- not just a
# flat allowance. Measured on Qwen3-Coder-30B-A3B: with a fixed 6 GB reserve the cache took
# 7881 MB and a 16384-token prefill peaked at 15140 MB of 16376, leaving 1.2 GB. That is
# where a multi-turn agent runs out. Capping the cache instead put the same prefill at
# 11455 MB, and 24576 tokens fit in 11069 MB.
#
# 128 KiB per token is deliberately generous: fp16 KV on this 48-layer 30B is about 96
# KiB/token, and the slack covers the prefill workspaces. A smaller model over-reserves,
# which costs it cache it did not need anyway since it is not near the VRAM limit.
# SHAINET_EXPERT_CACHE_MB overrides the whole calculation (0 disables the cache).
if has_moe && offload && !ENV["SHAINET_EXPERT_CACHE_MB"]? && (info = SHAInet::CUDA.memory_info)
  kv_reserve = max_context.to_u64 * 128_u64 * 1024_u64
  reserve = 6_u64 * 1024 * 1024 * 1024 + kv_reserve
  free = info[:free]
  budget_mb = free > reserve ? ((free - reserve) // (1024_u64 * 1024_u64)) : 0_u64
  ENV["SHAINET_EXPERT_CACHE_MB"] = budget_mb.to_s
  STDERR.puts "  Expert cache budget: #{budget_mb} MB " \
              "(free #{free // (1024*1024)} MB − 6GB − #{kv_reserve // (1024*1024)} MB for #{max_context} tok context)".colorize(:dark_gray)
end

agent = AgentDemo::Agent.new(net, tokenizer, AgentDemo.build_tools, max_context)
STDERR.puts "Ready · tools: #{AgentDemo.build_tools.map(&.name).join(", ")} · max context #{max_context} tok".colorize(:green)
STDERR.puts "Commands: /context  /compact  /clear  /ask  /help   (Ctrl-C interrupts a turn, Ctrl-D exits)".colorize(:dark_gray)

# Ctrl-C interrupts the TURN; twice in a row at an idle prompt exits.
#
# The default handler kills the process, which here throws away 9 GB of loaded weights, the KV cache
# and the conversation -- a brutal price for "not that file". Trapping it means a wrong turn costs the
# turn. A second press while already idle is an explicit request to leave, so honour it rather than
# leaving the user hunting for the exit.
idle_interrupt = false
Process.on_terminate do |reason|
  if reason.interrupted?
    if AgentDemo.generating?
      AgentDemo.cancel!
    elsif idle_interrupt
      STDERR.puts "\nbye 👋".colorize(:cyan)
      AgentDemo.disable_bracketed_paste
      exit 0
    else
      idle_interrupt = true
      STDERR.print "\n  #{"press Ctrl-C again to exit, or Ctrl-D".colorize(:dark_gray)}\n#{"You".colorize(:light_green).bold} ❯ "
    end
  else
    # A real termination request (TERM, or the terminal going away) is not a change of mind about one
    # turn -- do not swallow it into a cancel the user is not there to see.
    AgentDemo.disable_bracketed_paste
    exit 0
  end
end

AgentDemo.enable_bracketed_paste
at_exit { AgentDemo.disable_bracketed_paste }

loop do
  STDERR.print "\n#{"You".colorize(:light_green).bold} ❯ "
  input = AgentDemo.read_submission
  break if input.nil?
  idle_interrupt = false
  AgentDemo.clear_cancel!
  input = input.strip
  next if input.empty?

  case input
  when "/help"
    STDERR.puts "  /context  show context size, VRAM and cache usage".colorize(:dark_gray)
    STDERR.puts "  /compact  summarize + trim the conversation history now".colorize(:dark_gray)
    STDERR.puts "  /clear    reset the conversation".colorize(:dark_gray)
    STDERR.puts "  /ask      revoke 'allow all' and confirm each tool call again".colorize(:dark_gray)
    STDERR.puts "  /help     this message".colorize(:dark_gray)
    next
  when "/ask"
    # The way back from answering "a". Without this, one keystroke silently approves every
    # write and shell command for the rest of the session with no way to reconsider. It also
    # forgets approved out-of-workspace locations, since those were granted by the same
    # keystroke and leaving them behind would make the revocation only partly true.
    outside = AgentDemo::WorkspacePath.approved_outside_count
    if AgentDemo.allow_all? || outside > 0
      AgentDemo.allow_all = false
      AgentDemo::WorkspacePath.reset_outside_approvals!
      note = outside > 0 ? " (also forgot #{outside} approved path(s) outside the workspace)" : ""
      STDERR.puts "  will confirm each tool call again#{note}".colorize(:dark_gray)
    else
      STDERR.puts "  already confirming each tool call".colorize(:dark_gray)
    end
    next
  when "/context"
    STDERR.puts "  #{agent.status}".colorize(:dark_gray)
    next
  when "/compact"
    removed = agent.compact!((agent.max_context * 0.75).to_i)
    STDERR.puts "  compacted −#{removed} tokens · #{agent.status}".colorize(:dark_gray)
    next
  when "/clear"
    agent.reset
    STDERR.puts "  conversation cleared".colorize(:dark_gray)
    next
  else
    # A mistyped command used to go to the MODEL as an ordinary prompt: "/cotext" spent a whole
    # generation explaining that it does not know what /cotext means. Anything starting with a slash
    # was meant for the program, so say it is unknown rather than charging a turn for the typo.
    if input.starts_with?('/')
      STDERR.puts "  unknown command #{input.split(' ').first} · try /help".colorize(:dark_gray)
      next
    end
  end

  AgentDemo.generating = true
  begin
    agent.chat(input, max_tokens)
  ensure
    AgentDemo.generating = false
  end
  STDERR.puts "  #{agent.status}".colorize(:dark_gray)
end
STDERR.puts "\nbye 👋".colorize(:cyan)
SHAInet::Profile.report(STDERR)
