"""VM base image builder.

Builds a QEMU microvm root filesystem image for a given target
by building a container image (Dockerfile) and exporting it to
raw ext4.
"""

from __future__ import annotations

import hashlib
import logging
import os
import re
import shlex
import shutil
import subprocess
import tempfile
import time
from datetime import datetime, timezone
from pathlib import Path
from typing import TYPE_CHECKING, Any

from .paths import load_meta_safe
from .target_config import TARGETS_DIR

if TYPE_CHECKING:
    from .target_config import TargetConfig

log = logging.getLogger(__name__)

# Image sizing: computed dynamically from the extracted rootfs tree.
# We measure actual bytes used (du -sb) and add a 20% fudge plus a
# 128 MiB floor so ext4 metadata (inode tables, journal, group descs)
# always fits.  resize2fs -M then shrinks to minimum; the qcow2 overlay
# is resized to 8G at VM creation and rc.local expands ext4 to fill.
_IMAGE_SIZE_FUDGE = 1.2
_IMAGE_SIZE_FLOOR_MB = 512
_IMAGE_SIZE_HEADROOM_MB = 128


def _run(cmd: list[str], **kwargs: Any) -> subprocess.CompletedProcess[str]:
    """Run a command, logging it and raising on failure."""
    log.info("Running: %s", " ".join(str(c) for c in cmd))
    return subprocess.run(
        cmd,
        check=True,
        capture_output=kwargs.pop("capture_output", True),
        text=kwargs.pop("text", True),
        **kwargs,
    )


def _check_mke2fs() -> None:
    """Verify mke2fs and fakeroot are installed up-front."""
    import shutil as _sh

    missing = [t for t in ("mke2fs", "fakeroot") if _sh.which(t) is None]
    if missing:
        raise RuntimeError(
            f"missing host tool(s): {', '.join(missing)} -- "
            f"install e2fsprogs and fakeroot, or run `sudo ltvm install`"
        )
    # -d support was added in e2fsprogs 1.43 (2016)
    result = subprocess.run(["mke2fs", "-V"], capture_output=True, text=True)
    version_str = result.stderr + result.stdout
    if "mke2fs" not in version_str:
        raise RuntimeError("mke2fs not functional; reinstall e2fsprogs")


def _container_image_tag(target_config: TargetConfig) -> str:
    if target_config.arch != "x86_64":
        return f"ltvm-image-{target_config.name}-{target_config.arch}"
    return f"ltvm-image-{target_config.name}"


def _is_cross_build(target_config: TargetConfig) -> bool:
    """True if the target arch differs from the host.

    Normalises both sides through ``cross_compile.normalize_arch`` so
    Apple Silicon (``platform.machine() == 'arm64'``) is correctly
    treated as native when the target arch is ``aarch64``.
    """
    import platform

    from .cross_compile import normalize_arch

    return normalize_arch(target_config.arch) != normalize_arch(
        platform.machine()
    )


def _podman_platform(target_config: TargetConfig) -> list[str]:
    """Return --platform flag for podman if cross-arch build needed.

    Unlike kernel_build (which flips to host arch so its cross
    toolchain runs natively), the image build needs a target-arch
    rootfs: the package manager inside pulls packages for whatever
    platform the container image was resolved as.  Running the image
    container as host arch would install host-arch binaries into the
    ext4, which then fails to boot on the target.

    Switching to a host-native builder + dnf/apt --forcearch install
    into a target-arch sysroot is the clean fix but is non-trivial
    across distros; tracked as a follow-up to bead s3f.  Until then
    image cross-builds pay the emulation tax (mitigated in part by
    `_prebuild_tools_native`, which cross-builds IOR/iozone/e2fsprogs
    natively and COPYs them into the emulated image build).
    """
    if not _is_cross_build(target_config):
        return []
    from .cross_compile import podman_platform_for
    return ["--platform", podman_platform_for(target_config.arch)]


def _prebuild_tools_native(
    target_config: TargetConfig,
    output_dir: Path,
) -> None:
    """Cross-compile IOR, iozone, pjdfstest, e2fsprogs using the
    host-native build container + cross-compiler.

    This avoids compiling under QEMU user-mode emulation by running
    the cross-compiler natively. The output goes to *output_dir* and
    is injected into the emulated image build via COPY.
    """
    # We deliberately want the NATIVE (host-arch) build container, not
    # the cross-compile one.  Build the tag from the *host* arch, not
    # an "unsuffixed == native" assumption: an aarch64 host has its
    # native container tagged ltvm-build-<name>-aarch64 (created by
    # _ensure_container_image with default_arch=x86_64), and the
    # unsuffixed tag does not exist there.
    import platform as _platform

    from .cross_compile import normalize_arch

    arch = target_config.arch
    host_arch = normalize_arch(_platform.machine())
    if host_arch == "x86_64":
        build_tag = f"ltvm-build-{target_config.name}"
    else:
        build_tag = f"ltvm-build-{target_config.name}-{host_arch}"

    output_dir.mkdir(parents=True, exist_ok=True)

    # Ensure the native build container exists (build it if missing).
    r = subprocess.run(
        ["podman", "image", "exists", build_tag], capture_output=True
    )
    if r.returncode != 0:
        log.info("Building native container %s for cross-compile...", build_tag)
        build_dockerfile = target_config.target_dir / "container.Dockerfile"
        subprocess.run(
            [
                "podman",
                "build",
                "-t",
                build_tag,
                "--build-arg",
                f"BASE_IMAGE={target_config.container_image}",
                "-f",
                str(build_dockerfile),
                str(TARGETS_DIR),
            ],
            check=True,
        )

    log.info(
        "Pre-building tools natively for %s (cross-compile in %s)...",
        arch,
        build_tag,
    )

    script = (
        f"export TARGET_ARCH={arch} DESTDIR=/output\n"
        "bash /input/build-tools.sh\n"
        "bash /input/build-e2fsprogs.sh\n"
    )

    common_dir = TARGETS_DIR / "common"
    cmd = [
        "podman",
        "run",
        "--rm",
        "-v",
        f"{common_dir}:/input:ro,Z",
        "-v",
        f"{output_dir}:/output:Z",
        build_tag,
        "-c",
        script,
    ]
    subprocess.run(cmd, check=True)
    log.info("Pre-built tools at %s", output_dir)


def _lustre_staging_hash_input(staging: Path) -> bytes:
    """Return bytes to fold into the image input hash when --with-lustre
    is active. Uses Module.symvers sha256 recorded in the staging meta.

    Staging meta MUST exist for any modern build; the old rglob+sha256
    fallback over the entire staging tree was multi-GB-expensive and
    has been removed.
    """
    from .lustre_build import read_staging_meta

    meta = read_staging_meta(staging)
    if not meta or not isinstance(meta.get("module_symvers_sha256"), str):
        raise FileNotFoundError(
            f"missing or invalid .ltvm-staging-meta.json under {staging}; "
            "run `ltvm build-lustre` to regenerate staging meta"
        )
    return b"|".join(
        [b"with-lustre:", b"symvers:", meta["module_symvers_sha256"].encode()]
    )


def _lustre_inject_lines(
    staging: Path,
    inject_dir: Path,
    kver: str,
    os_family: str,
) -> list[str]:
    """Stage Lustre module + userland subtrees from *staging* into
    *inject_dir* and return the Dockerfile lines that COPY them into
    the image.

    Uses tar-in / tar-out to transplant whole subdirectories into the
    inject context so the Dockerfile stays free of shell
    interpolation -- each COPY source is a fixed pathname and the
    file layout on the host decides what ends up in the image.

    Layout produced in *inject_dir*:
      lustre-extra/            -> /lib/modules/<kver>/extra/
      lustre-userland-usr/     -> /usr/
      lustre-userland-etc/     -> /etc/
    Only the subtrees that actually exist in staging are copied.
    """
    lines: list[str] = []

    modules_src = (
        staging / "lib" / "modules" / kver / "extra"
    )
    if modules_src.is_dir():
        dest = inject_dir / "lustre-extra"
        # copy_function=shutil.copy intentionally drops metadata
        # (xattrs, ACLs).  podman build COPY scans listxattr on each
        # file as it ingests the build context; on the macOS->podman
        # machine virtiofs path, listxattr can return ENOMEM ("cannot
        # allocate memory") on otherwise-fine .ko files and aborts the
        # build.  We don't need any of the source-tree metadata for
        # the in-image install -- contents and perms are enough.
        shutil.copytree(
            modules_src,
            dest,
            symlinks=False,
            copy_function=shutil.copy,
        )
        lines.append(f"COPY lustre-extra/ /lib/modules/{kver}/extra/")

    # Userland subtrees.  /usr/ is the usual catch-all (sbin, bin,
    # lib64, share all live under it) so we stage it as one subtree
    # instead of four fragile COPYs.  etc/ is separate because it
    # sits outside /usr.  Debian's Lustre DESTDIR has the same layout
    # -- DESTDIR install is OS-agnostic; the only OS-specific bit is
    # whether /usr/lib or /usr/lib64 gets populated, which the COPY
    # transplants faithfully either way.
    # sbin/ holds mount.lustre (the mount(8) helper that registers the
    # Lustre filesystem type).  Without it, `mount -t lustre` fails
    # with "unknown filesystem type 'lustre'" even though the modules
    # loaded fine.  DESTDIR installs it to the top-level sbin/, not
    # usr/sbin/.
    for rel in ("usr", "etc", "sbin"):
        src = staging / rel
        if src.is_dir():
            dest = inject_dir / f"lustre-userland-{rel}"
            # See lustre-extra branch above: drop xattrs to avoid
            # podman machine virtiofs listxattr ENOMEM.
            shutil.copytree(
                src,
                dest,
                symlinks=False,
                copy_function=shutil.copy,
            )
            lines.append(
                f"COPY lustre-userland-{rel}/ /{rel}/"
            )

    # A second depmod after Lustre modules land.  Without this,
    # `modprobe lustre` inside the VM fails -- the earlier depmod
    # (run after kernel modules) didn't see /lib/modules/<k>/extra/.
    lines.append(f"RUN depmod -a {kver}")
    # Some distros' mount(8) wants mount.lustre_tgt; symlink if
    # missing.  os_family is accepted for future per-family tweaks
    # but currently all our targets share this invocation.
    _ = os_family
    lines.append(
        "RUN ln -sf mount.lustre "
        "/usr/sbin/mount.lustre_tgt 2>/dev/null || true"
    )
    return lines


def _kdump_inject_lines(
    kdir: Path,
    inject_dir: Path,
    kver: str | None,
    os_family: str,
) -> list[str]:
    """Return the Dockerfile lines that bake kdump boot artifacts into
    the image, copying the needed source files into *inject_dir*.

    Baking vmlinuz + initramfs at image-build time means VM boot can
    skip the per-boot scp + dracut that used to run in
    _seed_kdump_boot (~10-20s savings).  If only vmlinux is available
    (no bzImage), copy it as /boot/vmlinuz-<kver> and let the runtime
    fallback build the initramfs.
    """
    if not kver:
        return []

    vmlinuz_src = kdir / "vmlinuz"
    if vmlinuz_src.exists():
        shutil.copy2(vmlinuz_src, inject_dir / "vmlinuz")
        lines = [f"COPY vmlinuz /boot/vmlinuz-{kver}"]
        if os_family == "debian":
            kconfig_src = kdir / "build-tree" / ".config"
            if kconfig_src.exists():
                shutil.copy2(kconfig_src, inject_dir / "kconfig")
                lines.append(f"COPY kconfig /boot/config-{kver}")
            lines.append(
                "RUN rm -f /usr/share/initramfs-tools/hooks/dhcpcd && "
                f"update-initramfs -c -k {kver} && "
                "mkdir -p /var/lib/kdump && "
                f"cp /boot/initrd.img-{kver} "
                f"/var/lib/kdump/initrd.img-{kver} && "
                f"ln -sf /boot/vmlinuz-{kver} /var/lib/kdump/vmlinuz"
            )
        else:
            lines.append(
                f"RUN dracut --kver {kver} --force "
                f"--no-hostonly --no-hostonly-cmdline "
                f"/boot/initramfs-{kver}.img {kver}"
            )
        return lines

    vmlinux_src = kdir / "vmlinux"
    if vmlinux_src.exists():
        shutil.copy2(vmlinux_src, inject_dir / "vmlinuz")
        log.warning(
            "No vmlinuz for %s; skipping baked kdump initramfs -- "
            "runtime fallback will handle it",
            kver,
        )
        return [f"COPY vmlinuz /boot/vmlinuz-{kver}"]

    return []


def build_image(
    target_config: TargetConfig,
    force: bool = False,
    kernel: str | None = None,
    with_lustre: str | Path | None = None,
) -> Path:
    """Build a VM base image for the given target.

    Steps:
      1. Build container image via podman build
      2. Export container filesystem to raw ext4
      3. Write meta.json

    Args:
        target_config: TargetConfig instance
        force: rebuild even if inputs unchanged
        kernel: kernel name (short or full) whose modules to bake in;
                defaults to the target's default kernel
        with_lustre: optional path to a Lustre source tree whose
                per-kernel staging should be baked into the image
                alongside the kernel modules.  Requires a prior
                `ltvm build lustre <target> --kernel <k>`.
    """
    _check_mke2fs()

    kernel_name = target_config.resolve_kernel(kernel)

    # MOFED variant: ensure per-kernel kmod RPMs exist (auto-build if
    # not).  Their hash folds into the image hash so changing kernel or
    # mofed_version invalidates the image.
    from .target_config import DEFAULT_VARIANT
    mofed_kmods_dir: Path | None = None
    mofed_kmods_hash_input: bytes = b""
    if target_config.variant_name != DEFAULT_VARIANT and \
            target_config.variant(target_config.variant_name).params.get(
                "mofed_version"
            ):
        from .mofed_kmod_build import (
            build_mofed_kmods,
            is_stale as _mofed_is_stale,
            mofed_kmod_dir as _mofed_kmod_dir,
        )
        mofed_kmods_dir = _mofed_kmod_dir(target_config, kernel)
        if force or _mofed_is_stale(target_config, kernel) or \
                not any(mofed_kmods_dir.glob("*.rpm")):
            log.info("MOFED kmods missing or stale -- building first...")
            mofed_kmods_dir = build_mofed_kmods(
                target_config, kernel=kernel, force=force,
            )
        # Hash the produced RPM names + sizes so image rebuilds when
        # the kmod set changes (e.g. mofed_version bump).
        h = hashlib.sha256()
        for rpm in sorted(mofed_kmods_dir.glob("*.rpm")):
            h.update(rpm.name.encode())
            h.update(b"\0")
            h.update(str(rpm.stat().st_size).encode())
            h.update(b"\0")
        mofed_kmods_hash_input = h.digest()

    lustre_staging: Path | None = None
    lustre_hash_input: bytes = b""
    if with_lustre is not None:
        from .lustre_build import staging_path as _staging_path

        lustre_tree = Path(with_lustre).resolve()
        lustre_staging = _staging_path(
            lustre_tree,
            target_config.name,
            arch=target_config.arch,
            kernel=kernel_name,
            variant=target_config.variant_name,
        )
        if not lustre_staging.is_dir() or not any(
            lustre_staging.rglob("*.ko")
        ):
            raise FileNotFoundError(
                f"No Lustre staging at {lustre_staging} -- "
                f"run: ltvm build lustre {target_config.name} "
                f"--kernel {kernel_name} --lustre-tree {lustre_tree}"
            )
        lustre_hash_input = _lustre_staging_hash_input(lustre_staging)

    combined_extra_hash = lustre_hash_input + mofed_kmods_hash_input
    if not force and not target_config.is_stale(
        "image", kernel=kernel, extra_hash=combined_extra_hash
    ):
        log.info(
            "Image for %s (kernel=%s) is up to date, skipping (use force=True to rebuild)",
            target_config.name,
            kernel_name,
        )
        return target_config.image_output_dir(kernel) / "base.ext4"

    out_dir = target_config.image_output_dir(kernel)
    out_dir.mkdir(parents=True, exist_ok=True)
    image_path = out_dir / "base.ext4"

    tag = _container_image_tag(target_config)
    dockerfile = target_config.target_dir / "image.Dockerfile"
    if not dockerfile.exists():
        raise FileNotFoundError(
            f"No image.Dockerfile for target {target_config.name}"
        )

    t0 = time.monotonic()

    # ── Step 1: Build container image ──
    cross = _is_cross_build(target_config)
    platform_args = _podman_platform(target_config)
    effective_dockerfile = dockerfile
    prebuilt_dir: Path | None = None

    if cross:
        # Cross-build: compile tools natively, then inject into the
        # emulated image build (avoids slow compilation under QEMU).
        prebuilt_dir = out_dir / "_prebuilt"
        _prebuild_tools_native(target_config, prebuilt_dir)

        # Patch the Dockerfile: replace the RUN build-tools.sh and
        # build-e2fsprogs.sh steps with COPY from pre-built output.
        original = dockerfile.read_text()
        patched = original
        replacements = {
            "RUN bash /tmp/build-tools.sh": "COPY _prebuilt/usr/local/ /usr/local/",
            "RUN bash /tmp/build-e2fsprogs.sh": "COPY _prebuilt/usr/ /usr/",
        }
        for old, new in replacements.items():
            # Match any line starting with the key (ignoring trailing args
            # like version strings) so version bumps don't silently skip.
            pattern = re.compile(re.escape(old) + r".*", re.MULTILINE)
            patched, n = pattern.subn(new, patched)
            if n == 0:
                raise RuntimeError(
                    f"Cross-build Dockerfile patching failed: "
                    f"could not find '{old}' in {dockerfile}. "
                    f"Has the Dockerfile changed?"
                )

        # Write patched Dockerfile next to the original
        effective_dockerfile = out_dir / "image.Dockerfile.cross"
        effective_dockerfile.write_text(patched)
        log.info(
            "Using patched Dockerfile for cross-build: %s", effective_dockerfile
        )

        # Build context needs the prebuilt dir AND the targets/ content.
        # Podman doesn't follow symlinks outside the context, so we
        # hard-copy the target dirs into the build context.
        build_context = out_dir
        for name in ("common", target_config.name):
            dest = build_context / name
            src = TARGETS_DIR / name
            if dest.exists():
                shutil.rmtree(dest)
            shutil.copytree(src, dest)
    else:
        build_context = TARGETS_DIR

    log.info("Building container image %s ...", tag)
    _run(
        [
            "podman",
            "build",
            *platform_args,
            "--build-arg",
            f"BASE_IMAGE={target_config.container_image}",
            "-t",
            tag,
            "-f",
            str(effective_dockerfile),
            str(build_context),
        ],
        capture_output=False,
    )

    # ── Step 1a: Apply variant image overlay (e.g. MOFED) ──
    # Sits between the base image build and the kernel-module inject
    # step so MOFED lands in the rootfs before `depmod -a` runs (which
    # might pick up MOFED kmods too, depending on what the overlay
    # installs).  Kernel build-tree is exposed at /kernel-build-tree
    # in the context for overlays that need --kernel-sources.
    from .target_config import DEFAULT_VARIANT

    variant_name = target_config.variant_name
    if variant_name != DEFAULT_VARIANT:
        v = target_config.variant(variant_name)
        if v.image_overlay is None or not v.image_overlay.exists():
            raise RuntimeError(
                f"variant {variant_name!r}: image_overlay is required "
                f"but missing (checked {v.image_overlay})"
            )
        overlay_tag = f"{tag}-{variant_name}"
        log.info(
            "Applying variant image overlay %s -> %s",
            v.image_overlay,
            overlay_tag,
        )
        v_cmd = [
            "podman",
            "build",
            *platform_args,
            "--build-arg",
            f"BASE_IMAGE_TAG={tag}",
            "-t",
            overlay_tag,
        ]
        for key, val in sorted(v.params.items()):
            v_cmd += ["--build-arg", f"VARIANT_{key.upper()}={val}"]
        v_cmd += ["-f", str(v.image_overlay), str(TARGETS_DIR)]
        _run(v_cmd, capture_output=False)
        tag = overlay_tag  # downstream stages layer on top of the overlay

    # ── Step 1b: Add kernel modules + Lustre via a second Dockerfile stage ──
    # resolve_kernel never raises -- it returns the short name if no
    # built directory exists yet.  The actual "no kernel built yet"
    # case is detected below by checking has_modules / has_lustre.
    final_tag = tag

    if kernel_name is not None:
        kdir = target_config.output_dir / "kernels" / kernel_name
        modules_dir = kdir / "modules"
        # Read the exact kernel release string the modules were built for
        # so the injected `depmod -a <kver>` is deterministic instead of
        # globbing /lib/modules.
        kver_file = (
            kdir / "build-tree" / "include" / "config" / "kernel.release"
        )
        kver = kver_file.read_text().strip() if kver_file.exists() else None
        # Lustre staging now lives per-tree under <lustre_tree>/.ltvm-staging,
        # so build_image can no longer auto-inject Lustre from a global
        # location it owns.  Maintainers who want to bake Lustre into the
        # image should run `ltvm build lustre` then deploy via
        # `ltvm deploy-lustre --build`, or rely on `ltvm fetch` which carries
        # prebuilt Lustre in the package via lustre-artifacts/.  We keep
        # injecting kernel modules because those live deterministically
        # next to the kernel build output, not in a per-user tree.
        has_modules = (modules_dir / "lib" / "modules").is_dir()

        if has_modules:
            # Build a context dir with the files to inject
            inject_dir = out_dir / "_inject"
            if inject_dir.exists():
                shutil.rmtree(inject_dir)
            inject_dir.mkdir()

            # Write a tiny Dockerfile
            lines = [f"FROM {tag}"]
            if has_modules:
                log.info("Including kernel modules")
                # Copy modules into inject context, clean symlinks
                mod_dest = inject_dir / "modules"
                shutil.copytree(
                    str(modules_dir / "lib" / "modules"),
                    str(mod_dest),
                    symlinks=False,
                    ignore=shutil.ignore_patterns("build", "source"),
                )

            kdump_lines = _kdump_inject_lines(
                kdir, inject_dir, kver, target_config.os_family
            )
            lustre_lines: list[str] = []
            if lustre_staging is not None:
                if not kver:
                    raise RuntimeError(
                        "--with-lustre requires a resolved kernel "
                        "release (kernel.release missing from build-tree)"
                    )
                lustre_lines = _lustre_inject_lines(
                    lustre_staging,
                    inject_dir,
                    kver,
                    target_config.os_family,
                )
            # Lustre auto-inject was here.  It looked at a global
            # staging dir and silently baked whatever was there into the
            # image.  That doesn't work in the multi-user model where
            # staging is per-tree, and was foot-gunny in single-user mode
            # too (a stale build_lustre run would silently leak into
            # every subsequent build_image).  Maintainers who need
            # baked-in Lustre should snapshot it via `ltvm package`,
            # which puts it in lustre-artifacts/ for the fetcher to use.
            if (inject_dir / "modules").is_dir() and any(
                (inject_dir / "modules").iterdir()
            ):
                lines.append("COPY modules/ /lib/modules/")
            # MOFED kmod RPMs (when present) install BEFORE depmod so
            # the resulting modules.dep includes mlnx-ofa_kernel kmods.
            # These provide MOFED's mlx5_core / ib_core / rdma_cm symbol
            # versions, which Lustre's ko2iblnd was linked against in
            # the build container.
            if mofed_kmods_dir is not None and any(
                mofed_kmods_dir.glob("*.rpm")
            ):
                kmod_dest = inject_dir / "mofed-kmods"
                kmod_dest.mkdir(exist_ok=True)
                for rpm in mofed_kmods_dir.glob("*.rpm"):
                    shutil.copy2(rpm, kmod_dest / rpm.name)
                log.info(
                    "Including %d MOFED kmod RPMs", len(list(kmod_dest.iterdir()))
                )
                lines.append("COPY mofed-kmods/ /tmp/mofed-kmods/")
                # --nodeps because the kmod RPMs Require kernel-core =
                # <stock-rhel-version>, which our Lustre-patched kernel
                # doesn't provide via rpmdb.  The actual ABI match is
                # enforced by the kver we built them against.
                lines.append(
                    "RUN rpm -ivh --nodeps --force /tmp/mofed-kmods/*.rpm "
                    "&& rm -rf /tmp/mofed-kmods"
                )
            if kver:
                lines.append(f"RUN ldconfig && depmod -a {kver}")
            else:
                # No kernel.release file available; fall back to whatever
                # /lib/modules contains.  Sorted -V picks the highest.
                lines.append(
                    "RUN ldconfig && depmod -a "
                    "$(ls /lib/modules/ | sort -V | tail -1)"
                )
            lines.append(
                "RUN ln -sf mount.lustre /usr/sbin/mount.lustre_tgt 2>/dev/null || true"
            )
            lines.extend(kdump_lines)
            lines.extend(lustre_lines)

            inject_dockerfile = inject_dir / "Dockerfile"
            inject_dockerfile.write_text("\n".join(lines) + "\n")

            final_tag = f"{tag}-final"
            log.info("Building final image with kernel modules...")
            _run(
                [
                    "podman",
                    "build",
                    "-t",
                    final_tag,
                    "-f",
                    str(inject_dockerfile),
                    str(inject_dir),
                ],
                capture_output=False,
            )
            # Clean up inject dir
            shutil.rmtree(inject_dir, ignore_errors=True)

    # ── Step 2: Export to ext4 ──
    # If the export fails, the injected image (when we built one)
    # would otherwise leak as a podman layer on every retry.  Wrap
    # so we can rmi it on failure.  We don't rmi on success because
    # the next build pass benefits from layer caching.
    log.info("Exporting container to ext4 ...")
    try:
        image_path = _export_to_ext4(final_tag, image_path)
    except BaseException:
        if final_tag != tag:
            subprocess.run(
                ["podman", "rmi", "-f", final_tag],
                capture_output=True,
            )
        raise

    elapsed = time.monotonic() - t0

    # ── Step 3: Collect metadata ──
    size_mb = image_path.stat().st_size / (1024 * 1024)
    pkg_manifest = _get_package_manifest(tag, target_config.os_family)

    lustre_version: str | None = None
    if lustre_staging is not None:
        # Prefer lustre.ko: some LNet modules (ko2iblnd.ko, etc.) carry
        # a legacy baked-in MODULE_VERSION like "2.8.0 (in-kernel)" from
        # the in-tree-Lustre days, which has nothing to do with the
        # version we just built.  A blind rglob pick would hit one of
        # those first and write garbage to meta.  Walk a priority
        # list of canonical module names and use the first that yields
        # a sensible version string.
        from .paths import read_modinfo_field

        candidates = ("lustre.ko", "libcfs.ko", "obdclass.ko", "ptlrpc.ko")
        for cand in candidates:
            ko = next(lustre_staging.rglob(cand), None)
            if ko is None:
                continue
            v = (read_modinfo_field(ko, "version") or "").strip()
            # Guard against the legacy "in-kernel" stub even if a future
            # refactor lets it leak back in under a preferred name.
            if v and "in-kernel" not in v:
                lustre_version = v
                break

    # Schema: see ltvm_pkg.meta_schema.ImageMeta.
    # target/input_hash are written by TargetConfig.write_meta.
    target_config.write_meta(
        "image",
        kernel=kernel,
        extra_hash=combined_extra_hash,
        build_date=datetime.now(timezone.utc).isoformat(),
        with_lustre=str(Path(with_lustre).resolve())
        if with_lustre is not None
        else None,
        lustre_version=lustre_version,
        mofed_kmods=(
            sorted(p.name for p in mofed_kmods_dir.glob("*.rpm"))
            if mofed_kmods_dir is not None
            else None
        ),
        build_seconds=round(elapsed, 1),
        image_size_mb=round(size_mb, 1),
        packages=pkg_manifest,
        kernel_name=kernel_name,
    )

    log.info("Image built: %s (%.0f MiB, %.0fs)", image_path, size_mb, elapsed)
    return image_path


def _compute_image_size_mb_from_tar(tarball: Path) -> int:
    """Return the ext4 image size (MiB) needed to hold *tarball*.

    The uncompressed tar payload is a tight upper bound on rootfs
    bytes.  We add a 20% fudge for ext4 metadata (inode tables,
    journal, group descriptors), tack on a 128 MiB headroom for small
    trees, and clamp up to a 512 MiB floor.  resize2fs -M then shrinks
    whatever we over-allocate back to minimum.
    """
    tar_bytes = tarball.stat().st_size
    mb = (
        int(tar_bytes * _IMAGE_SIZE_FUDGE / (1024 * 1024))
        + _IMAGE_SIZE_HEADROOM_MB
    )
    return max(mb, _IMAGE_SIZE_FLOOR_MB)


def _export_to_ext4(
    container_tag: str,
    image_path: Path,
) -> Path:
    """Export a container image to a raw ext4 file, rootless.

    1. podman create + podman export to a tarball
    2. fakeroot tar -x into a tmpdir (preserves uid=0 on-disk)
    3. fakeroot mke2fs -d <tmpdir> -E root_owner=0:0 into a sized image
    4. e2fsck + resize2fs -M to shrink

    Runs entirely as the invoking user -- no mount/losetup needed.
    fakeroot wraps tar+mke2fs so the extracted tree records uid=0 (via
    LD_PRELOAD) and mke2fs -d reads those faked stats when populating
    the image; -E root_owner=0:0 additionally pins the root inode.
    """
    container_id: str | None = None
    tmpdir: str | None = None
    tmpfile: str | None = None

    try:
        result = _run(["podman", "create", container_tag])
        container_id = result.stdout.strip()
        log.info("Container: %s", container_id[:12])

        tmpdir = tempfile.mkdtemp(prefix="ltvm-rootfs-")
        rootfs = Path(tmpdir) / "rootfs"
        rootfs.mkdir()
        tarball = Path(tmpdir) / "rootfs.tar"

        image_path.parent.mkdir(parents=True, exist_ok=True)
        tmp_f = tempfile.NamedTemporaryFile(
            suffix=".ext4",
            prefix="ltvm-image-",
            dir=str(image_path.parent),
            delete=False,
        )
        tmpfile = tmp_f.name
        tmp_f.close()

        log.info("Exporting container filesystem to tarball...")
        with tarball.open("wb") as fp:
            subprocess.run(
                ["podman", "export", container_id],
                stdout=fp,
                check=True,
            )

        log.info("Extracting rootfs tarball...")
        # tar --exclude=dev/* skips device nodes we can't mknod as user;
        # we recreate the pseudo-fs mountpoints dev/{pts,shm,mqueue}.
        # `chmod -R u+rX` heals unreadable files left by container
        # post-install scripts (gshadow lands as 0000) so mke2fs -d can
        # ingest them.  Earlier we used `find ! -readable -exec chmod
        # u+r` but BSD find on macOS doesn't have -readable, so the
        # find call errored out and the chmod never ran -- mke2fs then
        # tripped on gshadow.  `chmod -R u+rX` is portable: u+r adds
        # user-read on every entry; the capital X adds user-execute
        # only on directories (and on files that already have any
        # exec bit), so we don't accidentally mark plain data files
        # executable.
        extract_script = (
            f"set -e; "
            f"tar -C {shlex.quote(str(rootfs))} -xpf "
            f"{shlex.quote(str(tarball))} --exclude=dev/*; "
            f"mkdir -p {shlex.quote(str(rootfs))}/dev/pts "
            f"{shlex.quote(str(rootfs))}/dev/shm "
            f"{shlex.quote(str(rootfs))}/dev/mqueue; "
            f"chmod -R u+rX {shlex.quote(str(rootfs))}; "
            # -O ^metadata_csum,^dir_index works around two distinct
            # e2fsprogs 1.46.5 bugs in `mke2fs -d`:
            #   * "Directory block checksum does not match" on htree
            #   * "EXT2 directory corrupted" when populating large
            #     directories (e.g. /lib/modules/.../kernel/ with
            #     thousands of .ko files)
            # Both are fixed in 1.47.  We re-enable the features with
            # tune2fs + e2fsck -D afterwards so the final image has
            # htree and checksums like a normal ext4 fs.
            f"mke2fs -t ext4 -b 4096 -L rootfs -E root_owner=0:0 "
            f"-O ^metadata_csum,^dir_index "
            f"-d {shlex.quote(str(rootfs))} "
            f"{shlex.quote(tmpfile)} {_compute_image_size_mb_from_tar(tarball)}M"
        )
        _run(["fakeroot", "bash", "-c", extract_script], capture_output=False)

        subprocess.run(
            ["podman", "rm", "-f", container_id], capture_output=True
        )
        container_id = None

        r_fsck = subprocess.run(["e2fsck", "-fy", tmpfile], capture_output=True)
        # e2fsck exit codes: 0 = clean, 1 = errors corrected (both OK),
        # 2+ = errors remain or operational failure.
        if r_fsck.returncode > 1:
            raise RuntimeError(
                f"e2fsck failed (rc={r_fsck.returncode}): "
                f"{r_fsck.stderr.decode(errors='replace').strip()}"
            )
        _run(["resize2fs", "-M", tmpfile])
        # Re-enable metadata_csum and dir_index that were skipped during
        # populate to work around e2fsprogs 1.46.5 bugs.  e2fsck -D
        # rebuilds htree indexes over the linear dirs we just wrote.
        _run(["tune2fs", "-O", "metadata_csum,dir_index", tmpfile])
        subprocess.run(["e2fsck", "-fyD", tmpfile], capture_output=True)

        os.rename(tmpfile, str(image_path))
        tmpfile = None

        return image_path

    finally:
        if container_id:
            subprocess.run(
                ["podman", "rm", "-f", container_id], capture_output=True
            )
        if tmpdir and os.path.exists(tmpdir):
            shutil.rmtree(tmpdir, ignore_errors=True)
        if tmpfile and os.path.exists(tmpfile):
            os.unlink(tmpfile)


def _get_package_manifest(
    container_tag: str, os_family: str = "rhel"
) -> list[str]:
    """Get installed package list from the container image."""
    if os_family == "debian":
        result = _run(
            [
                "podman",
                "run",
                "--rm",
                container_tag,
                "dpkg-query",
                "-W",
                "-f",
                "${Package} ${Version} ${Architecture}\n",
            ]
        )
    else:
        result = _run(
            [
                "podman",
                "run",
                "--rm",
                container_tag,
                "rpm",
                "-qa",
                "--queryformat",
                "%{NAME}-%{VERSION}-%{RELEASE}.%{ARCH}\\n",
            ]
        )
    packages = sorted(result.stdout.strip().splitlines())
    return packages


def image_status(
    target_config: TargetConfig,
    kernel: str | None = None,
    variant: str | None = None,
) -> dict[str, bool | str | float | None]:
    """Return status dict for the target's image artifact for a kernel.

    ``variant`` defaults to the variant this TargetConfig is bound to;
    pass an explicit name to inspect a sibling variant's image without
    constructing a second TargetConfig.

    Keys:
        built: bool -- whether an image exists
        build_date: str or None -- ISO timestamp
        stale: bool -- whether inputs have changed
        size_mb: float or None -- image file size
        path: str or None -- path to base.ext4
        kernel: str -- resolved kernel name this image is paired with
        variant: str -- variant name this image belongs to
    """
    from .target_config import DEFAULT_VARIANT

    variant_name = (
        target_config.variant_name if variant is None else variant
    )
    kernel_name = target_config.resolve_kernel(kernel)
    out_dir = target_config.image_output_dir(kernel, variant=variant_name)
    image_path = out_dir / "base.ext4"
    meta_path = out_dir / "meta.json"

    if not image_path.exists():
        return {
            "built": False,
            "build_date": None,
            "stale": True,
            "size_mb": None,
            "path": None,
            "kernel": kernel_name,
            "variant": variant_name,
        }

    meta = load_meta_safe(meta_path) or {}

    size_mb = image_path.stat().st_size / (1024 * 1024)
    stale = target_config.is_stale("image", kernel=kernel, variant=variant_name)

    return {
        "built": True,
        "build_date": meta.get("build_date"),
        "stale": stale,
        "size_mb": round(size_mb, 1),
        "path": str(image_path),
        "kernel": kernel_name,
        "variant": variant_name,
    }
